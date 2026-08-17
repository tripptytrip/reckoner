"""Phase 1: supervised warm start.

Targets, per the chunk-8 brief:

* **policy** — the action the BFS-optimal derivation took, one-hot over the legal
  set, masked by ``legal_actions``.
* **steps** — remaining steps to the solve, regressed, masked to solved rows
  (every Phase-1 row is on a solved derivation, so the mask is all-true here and
  is kept anyway: the machinery must be exercised before Phase 2 relies on it).
* **W/D/L** — **loss weight 0, deliberately.** Spec §5 trains Phase-1 value on
  steps-to-solve. Imitation data has degenerate z: every row is on an optimal
  derivation, so every episode would be a draw, and training the head on that
  manufactures a confidently-wrong prior rather than an ignorant one.
  Untrained-but-uninformative beats miswired. Phase 2 wakes it.

The single-BFS-path caveat is recorded in the dataset's own meta: where several
optimal derivations exist, the network is taught the one BFS reached first.
Phase 2's improved-policy targets are visit distributions over the whole legal
set and wash it out.
"""

from __future__ import annotations

import json
import math
import random
from collections.abc import Callable
from dataclasses import dataclass, field
from pathlib import Path

import numpy as np
import torch
from torch import nn

from reckoner.config import Config
from reckoner.dataset import anchored_path, sample_indices
from reckoner.episode import Problem, decode_state
from reckoner.model import N_RULES, Reckoner, StateTooLarge, encode, policy_loss, steps_loss
from reckoner.valuegate import ValueHeadState, value_contribution
from reckoner.vocab import PAD


@dataclass
class Batch:
    tokens: torch.Tensor
    site_positions: torch.Tensor
    legal_mask: torch.Tensor
    policy_target: torch.Tensor
    steps_target: torch.Tensor
    solved_mask: torch.Tensor
    depth: torch.Tensor
    skipped: int = 0
    width: int = 0  # columns after the crop; `tokens.shape[1]`, recorded not inferred
    #: Phase-2 only: the episode's real z as a W/D/L class, and the search's
    #: root_q. Absent for Phase-1 batches, where z is degenerate by construction.
    z_class: torch.Tensor | None = None
    root_q: torch.Tensor | None = None


@dataclass
class TrainStats:
    steps: int = 0
    examples: int = 0
    nan_skips: int = 0
    encode_skips: int = 0
    losses: list[float] = field(default_factory=list)

    def as_dict(self) -> dict:
        return {
            "steps": self.steps,
            "examples": self.examples,
            "nan_skips": self.nan_skips,
            "encode_skips": self.encode_skips,
            "final_loss": self.losses[-1] if self.losses else None,
        }


class SupervisionSet:
    """Mapped Phase-1 examples. Host RAM is the scarce pool; nothing is loaded."""

    def __init__(self, path: Path, repo: Path | None = None) -> None:
        # THE SECOND LOADER, gated. `read_dataset` governs the train_100k /
        # eval_held_out family and was structurally blind to this one, which
        # reads phase1_train and phase1_eval — the two datasets that carried no
        # registry entry at all until 2026-08-16. Both holes were the same shape
        # and they lined up, because SupervisionSet and those datasets are
        # pre-discipline contemporaries: born before registration-at-birth
        # existed, they travelled together under the old rules while every
        # mechanism built since covered the newer families.
        #
        # Hence the coverage-form corollary: a gate on births governs nothing
        # already alive, so a retrofit's completion criterion is a census of the
        # past, not merely a gate on the future.
        repo = repo or Path(__file__).resolve().parents[2]
        try:
            Path(path).resolve().relative_to(repo.resolve())
        except ValueError:
            pass  # a fixture outside the repo, per assert_tracked's precedent
        else:
            anchored_path(path, repo)
        self.path = path
        self.meta = json.loads((path / "meta.json").read_text())
        n, width = self.meta["n"], self.meta["max_len"]
        load = lambda name, shape: np.memmap(  # noqa: E731
            path / f"{name}.i32", dtype=np.int32, mode="r", shape=shape
        )
        self.tokens = load("tokens", (n, width))
        self.lengths = load("lengths", (n,))
        self.action = load("action", (n,))
        self.steps_remaining = load("steps_remaining", (n,))
        self.depth = load("depth", (n,))
        self.goal = load("goal", (n,))

    def sample(self, k: int, seed: int) -> list[int]:
        """Indices sampled across the whole set. Never a prefix — the supervision
        set is laid out stratum by stratum, so a prefix is a depth-1 pilot."""
        return sample_indices(len(self), k, seed)

    def __len__(self) -> int:
        return int(self.meta["n"])


def _crop_to_content(tokens: torch.Tensor, site_positions: torch.Tensor) -> torch.Tensor:
    """Drop trailing all-PAD columns. **Exact, not approximate** — and measured.

    ``encode`` pads every state to ``model.seq_len`` (512), sized in chunk 6 from
    the *reachable*-state distribution, because Phase 2 self-play can grow states
    past 295 tokens (F-05). Phase 1 supervision states are all on BFS-optimal
    derivations, and optimal derivations never apply ``add_both_sides``
    (ROUND-01), so the whole 313,628-example set has ``max_len 64``. Eight times
    the width, and attention is O(L²).

    Cropping changes nothing the network computes: the trunk already ignores PAD
    via ``src_key_padding_mask``, ``_masked_mean`` pools over ``ne(PAD)``, and
    positions are indexed from 0 by ``arange``, so rows 0..width-1 of the
    position table are the same rows either way. That equality is pinned as an
    exact tensor identity by ``test_cropping_padding_is_exact``, both polarities:
    the crop must fire *and* the outputs must be bit-identical.

    **Do not "fix" this by lowering ``model.seq_len``.** The envelope is sized
    for Phase 2, where the states really are that long; the width is a property
    of a batch, not of the model.
    """
    filled = tokens.ne(PAD).nonzero()
    # An all-PAD batch cannot occur (a state has at least a goal token), but a
    # width of 0 would be silently catastrophic, so the floor is stated.
    width = int(filled[:, 1].max()) + 1 if filled.numel() else 1
    width = max(width, int(site_positions.max()) + 1)
    return tokens[:, :width]


def make_batch(data: SupervisionSet, indices: list[int], cfg: Config) -> Batch:
    """Encode a batch. Site positions and legality are derived, never stored.

    Storing them would cost ~660 MB for a 313K set at `max_sites=192`; deriving
    them costs a decode plus one `legal_actions` call per row, and keeps the
    single legality oracle intact — a stored mask is a second copy that can
    disagree with the engine.
    """
    tokens, positions, masks, targets, steps, depths = [], [], [], [], [], []
    skipped = 0
    for i in indices:
        seq = tuple(int(t) for t in data.tokens[i, : data.lengths[i]])
        goal, target, expr = decode_state(seq)
        problem = Problem(
            goal=goal, expr=expr, par=int(data.depth[i]), target=target, par_source="bfs"
        )
        try:
            state = encode(problem, expr, cfg)
        except StateTooLarge:
            skipped += 1  # counted, never cropped
            continue
        one_hot = torch.zeros(N_RULES * cfg.model.max_sites)
        one_hot[int(data.action[i])] = 1.0
        tokens.append(state.tokens)
        positions.append(state.site_positions)
        masks.append(state.legal_mask)
        targets.append(one_hot)
        steps.append(float(data.steps_remaining[i]))
        depths.append(int(data.depth[i]))

    if not tokens:
        raise ValueError("every row in the batch failed to encode")
    steps_tensor = torch.tensor(steps)
    stacked = _crop_to_content(torch.stack(tokens), torch.stack(positions))
    return Batch(
        tokens=stacked,
        site_positions=torch.stack(positions),
        width=int(stacked.shape[1]),
        legal_mask=torch.stack(masks),
        policy_target=torch.stack(targets),
        steps_target=steps_tensor,
        solved_mask=torch.ones_like(steps_tensor, dtype=torch.bool),
        depth=torch.tensor(depths),
        skipped=skipped,
    )


#: z -> W/D/L class index. Column order is the head's and is part of the format:
#: 0 = under par (+1), 1 = equal (0), 2 = over par or capped (-1).
Z_TO_CLASS = {1: 0, 0: 1, -1: 2}


def ring_batch(ring, indices: list[int], cfg: Config) -> Batch | None:
    """Turn stored steps into a trainable batch. Legality is re-derived, never stored.

    The visit vector was stored **sparsely** (top-m actions and counts); it is
    re-expanded here into the dense action layout the policy head emits, so the
    ring stays small and the loss still sees a distribution.
    """
    from reckoner.absence import Absent

    tokens, positions, masks, targets, steps, depths, zs, qs = [], [], [], [], [], [], [], []
    skipped = 0
    for i in indices:
        record = ring.get(i)
        if any(isinstance(record[k], Absent) for k in ("tokens", "visit_counts", "root_q", "z")):
            skipped += 1  # an era-absent field is not a zero; the row sits out
            continue
        goal, target, expr = decode_state(tuple(int(t) for t in record["tokens"]))
        problem = Problem(
            goal=goal, expr=expr, par=int(record["par"]), target=target, par_source="bfs"
        )
        try:
            state = encode(problem, expr, cfg)
        except StateTooLarge:
            skipped += 1  # counted, never cropped
            continue

        visits = np.asarray(record["visit_counts"], dtype=np.float64)
        total = visits.sum()
        if total <= 0:
            skipped += 1
            continue
        dense = torch.zeros(N_RULES * cfg.model.max_sites)
        for action, count in zip(record["visit_actions"], visits, strict=True):
            if count > 0:
                dense[int(action)] = float(count / total)

        tokens.append(state.tokens)
        positions.append(state.site_positions)
        masks.append(state.legal_mask)
        targets.append(dense)
        steps.append(float(record["steps_remaining"]))
        depths.append(int(record["depth"]))
        zs.append(Z_TO_CLASS[int(record["z"])])
        qs.append(float(record["root_q"]))

    if not tokens:
        return None
    steps_tensor = torch.tensor(steps)
    stacked = _crop_to_content(torch.stack(tokens), torch.stack(positions))
    batch = Batch(
        tokens=stacked,
        site_positions=torch.stack(positions),
        width=int(stacked.shape[1]),
        legal_mask=torch.stack(masks),
        policy_target=torch.stack(targets),
        steps_target=steps_tensor,
        solved_mask=torch.ones_like(steps_tensor, dtype=torch.bool),
        depth=torch.tensor(depths),
        skipped=skipped,
    )
    batch.z_class = torch.tensor(zs, dtype=torch.long)
    batch.root_q = torch.tensor(qs, dtype=torch.float32)
    return batch


def train_on_ring(
    model: Reckoner,
    ring,
    cfg: Config,
    *,
    steps: int,
    seed: int = 0,
    device: str = "cpu",
    value_head: ValueHeadState | None = None,
) -> TrainStats:
    """**Phase 2's training phase.** Ring -> batches -> blended loss -> step.

    The z/q blend, at last implemented: cross-entropy toward the episode's real
    ``z`` plus ``train.value_q_mse_weight`` times MSE between the head's expected
    z and the search's ``root_q``. The self-referential hazard that makes blending
    dangerous elsewhere is structurally absent here because the **checker**, not
    the model's own Q, decides solved — so a wrong Q cannot bootstrap a false
    solve. Stated here as well as in config so a later reader does not "fix" it by
    turning the blend off.

    **The value head trains at full weight even while the search distrusts it.**
    Gating both consumers by the declaration deadlocks the ratchet — no gradient,
    no accuracy, no switch, forever (`FINDINGS.md` F-15). The declaration governs
    what the search *trusts*; this governs what the head is *taught*.
    """
    rng = random.Random(seed)
    torch.manual_seed(seed)
    was_training = model.training
    model.to(device).train()
    optimiser = torch.optim.AdamW(
        model.parameters(), lr=cfg.train.lr, weight_decay=cfg.train.weight_decay
    )
    stats = TrainStats()

    # The switch criterion's slice is held out from training: a head graded on
    # rows it fit would clear its own bar by memorising them.
    reserved = ring.holdout(cfg.train.ring_holdout_frac, seed=0)
    trainable = [i for i in range(len(ring)) if i not in reserved]

    for step in range(steps):
        if not trainable:
            break
        indices = [
            trainable[rng.randrange(len(trainable))]
            for _ in range(min(cfg.train.batch_size, len(trainable)))
        ]
        batch = ring_batch(ring, indices, cfg)
        if batch is None:
            stats.encode_skips += len(indices)
            continue
        stats.encode_skips += batch.skipped

        lr = lr_at(step, steps, cfg)
        for group in optimiser.param_groups:
            group["lr"] = lr

        policy, value_logits, steps_out = model(
            batch.tokens.to(device), batch.site_positions.to(device)
        )
        loss = cfg.train.policy_loss_weight * policy_loss(
            policy, batch.policy_target.to(device), batch.legal_mask.to(device)
        )
        assert steps_out is not None
        loss = loss + cfg.train.steps_loss_weight * steps_loss(
            steps_out, batch.steps_target.to(device), batch.solved_mask.to(device)
        )
        value_ce = nn.functional.cross_entropy(value_logits, batch.z_class.to(device))
        probs = torch.softmax(value_logits, dim=1)
        expected_z = probs[:, 0] - probs[:, 2]
        q_mse = nn.functional.mse_loss(expected_z, batch.root_q.to(device))
        loss = loss + cfg.train.value_loss_weight * (
            value_ce + cfg.train.value_q_mse_weight * q_mse
        )

        optimiser.zero_grad(set_to_none=True)
        loss.backward()
        finite = all(p.grad is None or torch.isfinite(p.grad).all() for p in model.parameters())
        if not finite:
            stats.nan_skips += 1
            optimiser.zero_grad(set_to_none=True)
        else:
            nn.utils.clip_grad_norm_(model.parameters(), cfg.train.grad_clip)
            optimiser.step()

        stats.steps += 1
        stats.examples += int(batch.tokens.shape[0])
        stats.losses.append(float(loss.detach()))

        if stats.steps >= cfg.train.nan_abort_min_steps:
            rate = stats.nan_skips / stats.steps
            if rate > cfg.train.nan_abort_frac:
                raise RuntimeError(
                    f"non-finite gradients on {rate:.1%} of steps — a rate, not a transient"
                )
    # F-22: TRAIN MODE IS CONFINED HERE. Leaving it set is what put dropout
    # inside every subsequent search — the caller asked for a training step, not
    # for a permanently mutated model.
    model.train(was_training)
    return stats


def rehearsal_split(batch_size: int, cfg: Config) -> tuple[int, int]:
    """How many Phase-1 rows to mix into a Phase-2 batch. **Dormant at 0.0.**

    Ported now and left inert, per the plan's "the lever exists before it's
    needed": a rehearsal mechanism added *after* catastrophic forgetting appears
    is a mechanism written under pressure, against a run that is already
    degrading. At ``rehearsal_frac = 0.0`` this returns ``(0, batch_size)`` and
    nothing in the training path changes — which is the accepting case that has
    to be tested too, or "dormant" means "untested".

    Returns ``(from_supervision, from_replay)``.
    """
    frac = cfg.train.rehearsal_frac
    if not 0.0 <= frac < 1.0:
        raise ValueError(
            f"train.rehearsal_frac must be in [0, 1); got {frac}. At 1.0 a Phase-2 "
            "iteration trains on no Phase-2 data, which is not rehearsal."
        )
    supervision = int(round(batch_size * frac))
    return supervision, batch_size - supervision


def lr_at(step: int, total: int, cfg: Config) -> float:
    """Learning rate for ``step`` (0-based), per ``train.lr_schedule``.

    Warmup is linear and applies to both schedules: the first steps of a warm
    start see a policy head at chance over ~1,344 actions, and the gradient that
    produces is not the one the run should be steered by.
    """
    warmup = cfg.train.lr_warmup_steps
    if warmup and step < warmup:
        return cfg.train.lr * (step + 1) / warmup
    if cfg.train.lr_schedule == "constant":
        return cfg.train.lr
    span = max(1, total - warmup)
    progress = min(1.0, (step - warmup) / span)
    return cfg.train.lr * 0.5 * (1.0 + math.cos(math.pi * progress))


def train(
    model: Reckoner,
    data: SupervisionSet,
    cfg: Config,
    *,
    steps: int,
    device: str = "cpu",
    seed: int = 0,
    log_every: int = 50,
    on_log: Callable[[int, float, float], None] | None = None,
    value_head: ValueHeadState | None = None,
) -> TrainStats:
    """Run the warm start. NaN-skip guard with a 1% abort, per the inherited kit.

    ``on_log(step, mean_loss_over_window, lr)`` is called every ``log_every`` steps.
    Library code does not print (AGENTS.md §6) — the caller in ``scripts/`` owns
    the terminal, and a training loop that printed would also be unusable from a
    dashboard or a test.
    """
    rng = random.Random(seed)
    torch.manual_seed(seed)
    model.to(device).train()
    optimiser = torch.optim.AdamW(
        model.parameters(), lr=cfg.train.lr, weight_decay=cfg.train.weight_decay
    )
    stats = TrainStats()

    for step in range(steps):
        lr = lr_at(step, steps, cfg)
        for group in optimiser.param_groups:
            group["lr"] = lr
        indices = [rng.randrange(len(data)) for _ in range(cfg.train.batch_size)]
        batch = make_batch(data, indices, cfg)
        stats.encode_skips += batch.skipped

        policy, _value, steps_out = model(batch.tokens.to(device), batch.site_positions.to(device))
        loss = cfg.train.policy_loss_weight * policy_loss(
            policy, batch.policy_target.to(device), batch.legal_mask.to(device)
        )
        assert steps_out is not None
        loss = loss + cfg.train.steps_loss_weight * steps_loss(
            steps_out, batch.steps_target.to(device), batch.solved_mask.to(device)
        )
        # W/D/L head: loss weight is `value_loss_weight * value_contribution(state)`,
        # and in Phase 1 the state is untrusted so the product is 0 — the head's
        # parameters do not appear in this graph. THE SAME FUNCTION scales the
        # search's value contribution (F-14): one declaration, two consumers, so
        # a head nobody is training cannot be a head the search is trusting.
        _value_weight = cfg.train.value_loss_weight * value_contribution(
            value_head or ValueHeadState()
        )

        optimiser.zero_grad(set_to_none=True)
        loss.backward()
        finite = all(p.grad is None or torch.isfinite(p.grad).all() for p in model.parameters())
        if not finite:
            stats.nan_skips += 1
            optimiser.zero_grad(set_to_none=True)
        else:
            nn.utils.clip_grad_norm_(model.parameters(), cfg.train.grad_clip)
            optimiser.step()

        stats.steps += 1
        stats.examples += int(batch.tokens.shape[0])
        stats.losses.append(float(loss.detach()))

        if stats.steps >= cfg.train.nan_abort_min_steps:
            rate = stats.nan_skips / stats.steps
            if rate > cfg.train.nan_abort_frac:
                raise RuntimeError(
                    f"non-finite gradients on {rate:.1%} of steps "
                    f"({stats.nan_skips}/{stats.steps}) — a rate, not a transient"
                )
        if on_log is not None and log_every and (step + 1) % log_every == 0:
            window = stats.losses[-log_every:]
            on_log(step + 1, sum(window) / len(window), lr)

    return stats
