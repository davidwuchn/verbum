#!/usr/bin/env python3
"""v12 probe — checkpoint diagnostics for KIBC combinator VSM.

Probes v12 checkpoints with:
  - Eval loss + relational loss
  - Combinator dispatch distribution (K, I, B, C weights and evolution)
  - Per-position dispatch analysis (which combinator dominates where)
  - Combinator emphasis from S4 intelligence channel
  - φ-compression analysis (stratified by content type)
  - S3 gates, S5 reweight, S2 coordination
  - Ternary topology statistics
  - Multi-checkpoint evolution tables
  - JSONL trajectory analysis (metrics_log.jsonl)
  - Retrieval (M kernel) metrics: gate means, memory norms, register norms, write gates

Usage:
    # Single checkpoint
    uv run python scripts/v12/probe.py checkpoints/v12/step_001000

    # Multiple checkpoints — evolution table
    uv run python scripts/v12/probe.py checkpoints/v12/step_*

    # Trajectory analysis from JSONL logs (no checkpoint loading)
    uv run python scripts/v12/probe.py --trajectory checkpoints/v12

    # Per-position dispatch distribution analysis
    uv run python scripts/v12/probe.py checkpoints/v12/step_005000 --dispatch-detail

    # Quick: skip eval, just metrics
    uv run python scripts/v12/probe.py checkpoints/v12/step_001000 --no-eval

License: MIT
"""

from __future__ import annotations

import argparse
import json
import math
import sys
import time
from datetime import UTC, datetime
from pathlib import Path

import mlx.core as mx
import mlx.nn as nn
import numpy as np
from mlx.utils import tree_flatten

sys.path.insert(0, str(Path(__file__).resolve().parent))

from config import V12Config
from model import V12Model, create_model, count_parameters
from kernel import N_COMBINATORS, COMBINATOR_NAMES, COMBINATOR_ROLE
from ternary import (
    freeze_ternary_weights,
    restore_ternary,
    count_ternary_weights,
    unpack_ternary_mlx,
    unpack_ternary,
    _walk_ternary_modules,
    TernaryLinear,
    TernaryEmbedding,
)


# ══════════════════════════════════════════════════════════════════════
# Constants
# ══════════════════════════════════════════════════════════════════════

E_IRREDUCIBLE = 1.82
LOG_V = math.log(151936)  # ≈ 11.93
PHI = (1 + math.sqrt(5)) / 2
INV_PHI = 1 / PHI

PASS_NAMES = ("L0_asc", "L1_asc", "L2_apex", "L1_desc", "L0_desc")
PASS_NAMES_SHORT = ("L0↑", "L1↑", "L2", "L1↓", "L0↓")

RESULTS_DIR = Path("results/v12")


# ══════════════════════════════════════════════════════════════════════
# φ-compression strata (shared with v10)
# ══════════════════════════════════════════════════════════════════════

PHI_STRATA = {
    "prose": [
        "The cat sat on the mat and looked out the window at the birds flying south for the winter.",
        "Every student who passed the final exam received a certificate of achievement from the dean.",
        "The quick brown fox jumps over the lazy dog near the river bank on a warm summer afternoon.",
        "In a quiet village nestled between rolling hills, the old baker opened his shop at dawn.",
    ],
    "compositional": [
        "The man who the dog that the cat chased bit ran away quickly.",
        "If every student reads a book then some teacher who knows the author is happy.",
        "No politician who endorsed the candidate that lost the election won their own race.",
        "Every lawyer who represents a client that a judge dismissed the case against appealed.",
    ],
    "technical": [
        "The gradient of the loss with respect to the weights is computed via backpropagation.",
        "Attention scores are computed as the softmax of the scaled dot product of queries and keys.",
        "The learning rate schedule uses cosine annealing with linear warmup over 500 steps.",
        "Each layer applies layer normalization before the self-attention and feed-forward blocks.",
    ],
    "lambda": [
        "λx. λy. apply(x, y) → result",
        "K x y = x selects the first and discards the second",
        "B f g x = f (g x) composes two functions together",
        "C f x y = f y x flips the argument order for closures",
    ],
}


# ══════════════════════════════════════════════════════════════════════
# Checkpoint loading
# ══════════════════════════════════════════════════════════════════════


def load_checkpoint(ckpt_path: Path) -> tuple[V12Model, int, dict, V12Config]:
    """Load a v12 checkpoint. Returns (model, step, state_dict, config)."""
    state_path = ckpt_path / "state.json"
    model_path = ckpt_path / "model.npz"

    if not state_path.exists() or not model_path.exists():
        raise FileNotFoundError(f"Missing state.json or model.npz in {ckpt_path}")

    state = json.loads(state_path.read_text())
    step = state["step"]
    config_data = state.get("config", {})

    cfg = V12Config()
    if "d_model" in config_data:
        cfg.d_model = config_data["d_model"]
        cfg.d_ff = cfg.d_model * 3
    if "vocab_size" in config_data:
        cfg.vocab_size = config_data["vocab_size"]
    if "seq_len" in config_data:
        cfg.seq_len = config_data["seq_len"]
        cfg.max_seq_len = config_data["seq_len"]
    if config_data.get("desc_stride_reverse", False):
        cfg.desc_stride_reverse = True
    if config_data.get("fractal_stride_bands", False):
        cfg.fractal_stride_bands = True

    model = create_model(cfg)
    weights = dict(mx.load(str(model_path)))
    model.load_weights(list(weights.items()), strict=False)
    mx.eval(model.parameters())
    freeze_ternary_weights(model)
    restore_ternary(model)

    return model, step, state, cfg


# ══════════════════════════════════════════════════════════════════════
# Evaluation
# ══════════════════════════════════════════════════════════════════════


def evaluate_on_data(model: V12Model, cfg: V12Config,
                     target_tokens: int = 50_000) -> dict:
    """Evaluate on held-out Dolma shards."""
    from data import ShardedDataLoader

    eval_loader = ShardedDataLoader(
        data_dir=cfg.data_dir, batch_size=cfg.batch_size,
        seq_len=cfg.seq_len, shard_start=cfg.n_train_shards,
        shard_end=cfg.n_train_shards + cfg.n_eval_shards, seed=9999,
    )

    total_loss = 0.0
    n_batches = 0
    tokens_seen = 0

    while tokens_seen < target_tokens:
        input_ids_np, targets_np = eval_loader.next_batch()
        input_ids = mx.array(input_ids_np)
        targets = mx.array(targets_np)
        _, loss = model(input_ids, targets)
        mx.eval(loss)
        total_loss += float(loss.item())
        n_batches += 1
        tokens_seen += input_ids_np.size

    avg_loss = total_loss / max(n_batches, 1)
    ppl = math.exp(min(avg_loss, 20.0))
    r = (avg_loss - E_IRREDUCIBLE) / (LOG_V - E_IRREDUCIBLE)

    return {"loss": avg_loss, "ppl": ppl, "r": r,
            "tokens_evaluated": tokens_seen, "n_batches": n_batches}


# ══════════════════════════════════════════════════════════════════════
# Per-position dispatch distribution analysis
# ══════════════════════════════════════════════════════════════════════


def analyze_dispatch_distribution(
    model: V12Model, cfg: V12Config, n_batches: int = 10
) -> dict:
    """Analyze per-position combinator dispatch distribution.

    Runs multiple batches through the model, collects dispatch weights
    at every position, and computes:
      - Mean combinator distribution
      - Per-position dominant combinator histogram
      - Entropy of the dispatch distribution (specialization measure)
      - Combinator co-occurrence (which pairs appear in top-2)
      - Per-combinator positional statistics
    """
    from data import ShardedDataLoader

    eval_loader = ShardedDataLoader(
        data_dir=cfg.data_dir, batch_size=cfg.batch_size,
        seq_len=cfg.seq_len, shard_start=cfg.n_train_shards,
        shard_end=cfg.n_train_shards + cfg.n_eval_shards, seed=42,
    )

    all_dispatch_weights = []  # list of (B, L, 4) arrays
    all_type_weights = []
    all_compute_gates = []

    for _ in range(n_batches):
        input_ids_np, _ = eval_loader.next_batch()
        input_ids = mx.array(input_ids_np)
        _, metrics = model.forward_instrumented(input_ids)

        # Collect raw dispatch weights from the model's cached state
        if hasattr(model.combinator_dispatch, '_dispatch_weights'):
            dw = model.combinator_dispatch._dispatch_weights  # (B, L, 4)
            mx.eval(dw)
            all_dispatch_weights.append(np.array(dw))

        if hasattr(model.combinator_integrate, '_type_weights'):
            tw = model.combinator_integrate._type_weights  # (B, L, 4)
            mx.eval(tw)
            all_type_weights.append(np.array(tw))

        if hasattr(model.combinator_integrate, '_compute_gate'):
            cg = model.combinator_integrate._compute_gate  # (B, L, 1)
            mx.eval(cg)
            all_compute_gates.append(np.array(cg))

    if not all_dispatch_weights:
        return {"error": "no dispatch weights captured"}

    # Concatenate across batches: (total_positions, 4)
    dw_all = np.concatenate(all_dispatch_weights, axis=0)  # (N_batches*B, L, 4)
    dw_flat = dw_all.reshape(-1, N_COMBINATORS)             # (total_pos, 4)
    n_positions = dw_flat.shape[0]

    # ── Mean distribution ─────────────────────────────────
    mean_dist = dw_flat.mean(axis=0)  # (4,)

    # ── Dominant combinator histogram ─────────────────────
    dominant = np.argmax(dw_flat, axis=-1)  # (total_pos,)
    dom_counts = np.bincount(dominant, minlength=N_COMBINATORS)
    dom_fracs = dom_counts / n_positions

    # ── Dispatch entropy per position ─────────────────────
    # H = -Σ p log p (uniform = log(4) ≈ 1.386, fully specialized = 0)
    log_dw = np.log(dw_flat + 1e-8)
    entropy = -(dw_flat * log_dw).sum(axis=-1)  # (total_pos,)
    max_entropy = np.log(N_COMBINATORS)

    # ── Top-2 co-occurrence ───────────────────────────────
    # For each position, which 2 combinators have highest weight?
    top2 = np.argsort(dw_flat, axis=-1)[:, -2:]  # (total_pos, 2)
    cooccur = np.zeros((N_COMBINATORS, N_COMBINATORS), dtype=np.int64)
    for row in top2:
        a, b = sorted(row)
        cooccur[a, b] += 1

    # ── Per-combinator weight statistics ──────────────────
    per_comb = {}
    for ci in range(N_COMBINATORS):
        weights = dw_flat[:, ci]
        per_comb[COMBINATOR_NAMES[ci]] = {
            "mean": float(weights.mean()),
            "std": float(weights.std()),
            "median": float(np.median(weights)),
            "p95": float(np.percentile(weights, 95)),
            "p05": float(np.percentile(weights, 5)),
            "dominant_frac": float(dom_fracs[ci]),
        }

    # ── Type weights and compute gate ─────────────────────
    type_dist = None
    if all_type_weights:
        tw_all = np.concatenate(all_type_weights, axis=0)
        type_dist = tw_all.reshape(-1, N_COMBINATORS).mean(axis=0)

    compute_gate_stats = None
    if all_compute_gates:
        cg_all = np.concatenate(all_compute_gates, axis=0).flatten()
        compute_gate_stats = {
            "mean": float(cg_all.mean()),
            "max": float(cg_all.max()),
            "p95": float(np.percentile(cg_all, 95)),
            "active_frac": float((cg_all > 0.5).mean()),
        }

    return {
        "n_positions": n_positions,
        "mean_distribution": {COMBINATOR_NAMES[i]: float(mean_dist[i])
                               for i in range(N_COMBINATORS)},
        "dominant_fractions": {COMBINATOR_NAMES[i]: float(dom_fracs[i])
                                for i in range(N_COMBINATORS)},
        "entropy": {
            "mean": float(entropy.mean()),
            "std": float(entropy.std()),
            "max_possible": float(max_entropy),
            "normalized_mean": float(entropy.mean() / max_entropy),
        },
        "top2_cooccurrence": {
            f"{COMBINATOR_NAMES[i]}+{COMBINATOR_NAMES[j]}": int(cooccur[i, j])
            for i in range(N_COMBINATORS)
            for j in range(i, N_COMBINATORS)
            if cooccur[i, j] > 0
        },
        "per_combinator": per_comb,
        "type_distribution": (
            {COMBINATOR_NAMES[i]: float(type_dist[i])
             for i in range(N_COMBINATORS)}
            if type_dist is not None else None
        ),
        "compute_gate": compute_gate_stats,
    }


def print_dispatch_analysis(da: dict) -> None:
    """Display combinator dispatch distribution analysis."""
    if "error" in da:
        print(f"  ⚠ {da['error']}")
        return

    n = da["n_positions"]
    print(f"\n  ┌─ Combinator Dispatch Distribution ({n:,} positions) ─┐")

    # Mean distribution with bars
    md = da["mean_distribution"]
    for name in COMBINATOR_NAMES:
        w = md[name]
        bar = "█" * int(w * 80)
        role = COMBINATOR_ROLE.get({"K": 0, "I": 1, "B": 2, "C": 3}[name], "")
        print(f"  │ {name} ({role:8s}): {w:.4f} {bar}")

    # Dominant combinator
    print(f"  ├─ Dominant combinator per position ──────────────┤")
    df = da["dominant_fractions"]
    for name in COMBINATOR_NAMES:
        f = df[name]
        bar = "█" * int(f * 60)
        print(f"  │ {name}: {f:.1%} {bar}")

    # Entropy (specialization)
    ent = da["entropy"]
    print(f"  ├─ Dispatch entropy ──────────────────────────────┤")
    print(f"  │ mean={ent['mean']:.4f} / {ent['max_possible']:.4f} "
          f"(normalized={ent['normalized_mean']:.3f})")
    if ent["normalized_mean"] > 0.95:
        print(f"  │ ≈ uniform — not specialized yet")
    elif ent["normalized_mean"] > 0.8:
        print(f"  │ → beginning to specialize")
    elif ent["normalized_mean"] > 0.5:
        print(f"  │ ✓ meaningful specialization")
    else:
        print(f"  │ ✓ strong specialization")

    # Top-2 co-occurrence
    cooc = da["top2_cooccurrence"]
    if cooc:
        print(f"  ├─ Top-2 co-occurrence ───────────────────────────┤")
        sorted_cooc = sorted(cooc.items(), key=lambda x: -x[1])
        for pair, count in sorted_cooc[:6]:
            pct = count / n * 100
            print(f"  │ {pair:5s}: {count:>8,} ({pct:>5.1f}%)")

    # Per-combinator statistics
    pc = da["per_combinator"]
    print(f"  ├─ Per-combinator weight statistics ──────────────┤")
    print(f"  │ {'':1s} {'mean':>7s} {'std':>7s} {'median':>7s} "
          f"{'p05':>7s} {'p95':>7s}")
    for name in COMBINATOR_NAMES:
        s = pc[name]
        print(f"  │ {name} {s['mean']:>7.4f} {s['std']:>7.4f} "
              f"{s['median']:>7.4f} {s['p05']:>7.4f} {s['p95']:>7.4f}")

    # Type distribution
    td = da.get("type_distribution")
    if td:
        print(f"  ├─ Combinator type distribution ──────────────────┤")
        for name in COMBINATOR_NAMES:
            w = td[name]
            bar = "█" * int(w * 50)
            print(f"  │ {name}: {w:.4f} {bar}")

    # Compute gate
    cg = da.get("compute_gate")
    if cg:
        print(f"  ├─ Compute gate ──────────────────────────────────┤")
        print(f"  │ mean={cg['mean']:.4f}  max={cg['max']:.4f}  "
              f"p95={cg['p95']:.4f}  active(>0.5)={cg['active_frac']:.1%}")

    print(f"  └─────────────────────────────────────────────────┘")


# ══════════════════════════════════════════════════════════════════════
# JSONL trajectory analysis
# ══════════════════════════════════════════════════════════════════════


def analyze_trajectory(checkpoint_dir: Path) -> None:
    """Analyze training trajectory from JSONL logs (no model loading)."""
    metrics_path = checkpoint_dir / "metrics_log.jsonl"
    train_path = checkpoint_dir / "train_log.jsonl"
    evo_path = checkpoint_dir / "evolution_log.jsonl"

    print(f"\n{'='*72}")
    print(f"  v12 Trajectory Analysis — {checkpoint_dir}")
    print(f"{'='*72}")

    # ── Metrics trajectory ────────────────────────────────
    if metrics_path.exists():
        with open(metrics_path) as f:
            metrics = [json.loads(l) for l in f]

        print(f"\n  📊 Metrics trajectory ({len(metrics)} evaluations)")

        # Loss trajectory
        print(f"\n  {'step':>8} {'loss':>8} {'r':>8} {'comp_gate':>10} ", end="")
        for cn in COMBINATOR_NAMES:
            print(f" {cn:>6}", end="")
        print()
        print(f"  {'─'*8} {'─'*8} {'─'*8} {'─'*10}", end="")
        for _ in COMBINATOR_NAMES:
            print(f" {'─'*6}", end="")
        print()

        for m in metrics:
            step = m["step"]
            loss = m.get("loss", 0)
            r = m.get("r", (loss - E_IRREDUCIBLE) / (LOG_V - E_IRREDUCIBLE))
            cg = m.get("compute_gate_mean", 0)

            # Dispatch weights — handle both v10 (22) and v11 (4) formats
            dw = m.get("combinator_dispatch_weights",
                       m.get("kernel_dispatch_weights", []))

            print(f"  {step:>8} {loss:>8.4f} {r:>8.4f} {cg:>10.4f}", end="")
            for ci in range(min(len(dw), N_COMBINATORS)):
                print(f" {dw[ci]:>6.3f}", end="")
            if len(dw) < N_COMBINATORS:
                for _ in range(N_COMBINATORS - len(dw)):
                    print(f" {'—':>6}", end="")

            # Alarm factors (if present)
            af = m.get("alarm_factors", [])
            if af:
                any_active = any(abs(f - 1.0) > 0.01 for f in af)
                if any_active:
                    af_str = " ".join(f"{f:.2f}" for f in af)
                    print(f"  🚨[{af_str}]", end="")

            # Abstraction slot summary (if present)
            abs_slots = m.get("abstraction_slots")
            if abs_slots:
                n_active = abs_slots.get("n_active_slots", 0)
                n_total = len(abs_slots.get("slot_gates", []))
                if n_active > 0:
                    print(f"  🔮[{n_active}/{n_total}]", end="")

            print()

        # ── Dispatch evolution summary ────────────────────
        if len(metrics) >= 2:
            first = metrics[0]
            last = metrics[-1]
            dw_first = first.get("combinator_dispatch_weights",
                                  first.get("kernel_dispatch_weights", []))
            dw_last = last.get("combinator_dispatch_weights",
                                last.get("kernel_dispatch_weights", []))
            if dw_first and dw_last and len(dw_first) <= N_COMBINATORS:
                print(f"\n  Dispatch Δ (step {first['step']} → {last['step']}):")
                for ci in range(len(dw_first)):
                    name = COMBINATOR_NAMES[ci] if ci < N_COMBINATORS else f"op{ci}"
                    d = dw_last[ci] - dw_first[ci]
                    arrow = "↑" if d > 0.01 else ("↓" if d < -0.01 else "→")
                    print(f"    {name}: {dw_first[ci]:.4f} {arrow} {dw_last[ci]:.4f} "
                          f"(Δ={d:+.4f})")

        # ── S3 gate trajectory ────────────────────────────
        print(f"\n  S3 gate trajectory (L0↑ pass — earliest signal):")
        print(f"  {'step':>8} {'prep':>8} {'conv':>8} {'cons':>8}")
        print(f"  {'─'*8} {'─'*8} {'─'*8} {'─'*8}")
        for m in metrics:
            s3 = m.get("s3_gates", [])
            if s3 and len(s3) > 0:
                g = s3[0]  # L0↑ pass
                if len(g) >= 3:
                    print(f"  {m['step']:>8} {g[0]:>8.3f} {g[1]:>8.3f} {g[2]:>8.3f}")

    # ── Train loss trajectory ─────────────────────────────
    if train_path.exists():
        with open(train_path) as f:
            train = [json.loads(l) for l in f]
        if train:
            steps = [t["step"] for t in train]
            losses = [t.get("r", t.get("ce", 0)) for t in train]
            print(f"\n  Train trajectory: {len(train)} entries, "
                  f"step {steps[0]}-{steps[-1]}")
            # Show loss at 10 evenly-spaced points
            indices = [int(i * len(train) / 10) for i in range(10)] + [len(train) - 1]
            for idx in sorted(set(indices)):
                t = train[idx]
                ce = t.get("ce", 0)
                r = t.get("r", 0)
                tok = t.get("tok_per_sec", 0)
                print(f"    step={t['step']:>8}  CE={ce:.4f}  r={r:.4f}  "
                      f"tok/s={tok:.0f}")

    # ── Evolution trajectory ──────────────────────────────
    if evo_path.exists():
        with open(evo_path) as f:
            evo = [json.loads(l) for l in f]
        if evo:
            accepted = sum(1 for e in evo if e.get("accepted"))
            total = len(evo)
            print(f"\n  Evolution: {accepted}/{total} accepted "
                  f"({accepted/total*100:.1f}%)")
            # Show last 5
            for e in evo[-5:]:
                acc = "✓" if e.get("accepted") else "✗"
                flips = e.get("actual_flips", 0)
                delta = e.get("delta", 0)
                print(f"    step={e['step']:>8} {acc} flips={flips:>5} "
                      f"Δ={delta:+.6f}")

    print(f"\n{'='*72}")


# ══════════════════════════════════════════════════════════════════════
# Instrumented analysis on text samples
# ══════════════════════════════════════════════════════════════════════


def run_instrumented_samples(
    model: V12Model, tokenizer, samples: list[str]
) -> dict:
    """Run forward_instrumented on text samples."""
    all_metrics = {
        "s3_gates": [], "s5_reweight": [], "register_norms": [],
        "pass_compression": [], "pass_phi_dev": [],
        "pass_entropy_in": [], "pass_entropy_out": [],
        "losses": [], "per_sample": [],
        "combinator_dispatch_weights": [], "combinator_type_weights": [],
        "compute_gate_mean": [],
    }

    for text in samples:
        ids = mx.array(tokenizer.encode(text)).reshape(1, -1)
        if ids.shape[1] > model.cfg.max_seq_len:
            ids = ids[:, -model.cfg.max_seq_len:]
        targets = mx.concatenate(
            [ids[:, 1:], mx.zeros((1, 1), dtype=mx.int32)], axis=1)

        hidden, metrics = model.forward_instrumented(ids)
        mx.eval(hidden)

        logits = model.output_norm(hidden)
        logits = model.embed.output_proj(logits)
        loss = nn.losses.cross_entropy(
            logits.reshape(-1, model.cfg.vocab_size),
            targets.reshape(-1)).mean()
        mx.eval(loss)

        all_metrics["s3_gates"].append(metrics["s3_gates"])
        all_metrics["s5_reweight"].append(metrics["s5_reweight"])
        all_metrics["register_norms"].append(metrics["register_norms"])
        all_metrics["pass_compression"].append(metrics["pass_compression"])
        all_metrics["pass_phi_dev"].append(metrics["pass_phi_dev"])
        all_metrics["pass_entropy_in"].append(metrics["pass_entropy_in"])
        all_metrics["pass_entropy_out"].append(metrics["pass_entropy_out"])
        all_metrics["losses"].append(float(loss.item()))

        if metrics.get("combinator_dispatch_weights"):
            all_metrics["combinator_dispatch_weights"].append(
                metrics["combinator_dispatch_weights"])
        if metrics.get("combinator_type_weights"):
            all_metrics["combinator_type_weights"].append(
                metrics["combinator_type_weights"])
        if "compute_gate_mean" in metrics:
            all_metrics["compute_gate_mean"].append(
                metrics["compute_gate_mean"])

        all_metrics["per_sample"].append({
            "text": text[:60],
            "loss": float(loss.item()),
            "pass_compression": metrics["pass_compression"],
        })

    # Average abstraction slot metrics from last sample (they're model-wide)
    if "abstraction_slots" in metrics:
        all_metrics["abstraction_slots"] = metrics["abstraction_slots"]

    # Holographic intermediate losses (from last sample — they're stable)
    if "holo_losses" in metrics:
        all_metrics["holo_losses"] = metrics["holo_losses"]

    return all_metrics


def _avg_nested(values: list, n: int = 5) -> list[float]:
    if not values:
        return [0.0] * n
    result = [0.0] * n
    for vals in values:
        for i in range(min(len(vals), n)):
            result[i] += vals[i]
    return [v / len(values) for v in result]


def _avg_register_norms(norm_lists: list) -> dict[str, list[float]]:
    if not norm_lists:
        return {}
    n = len(norm_lists)
    result: dict[str, list[float]] = {}
    for norms in norm_lists:
        for bank_name, vals in norms.items():
            if bank_name not in result:
                result[bank_name] = [0.0] * len(vals)
            for i, v in enumerate(vals):
                result[bank_name][i] += v
    return {k: [v / n for v in vals] for k, vals in result.items()}


# ══════════════════════════════════════════════════════════════════════
# Display
# ══════════════════════════════════════════════════════════════════════


def print_banner(step: int, state: dict, model: V12Model):
    print(f"\n{'='*72}")
    print(f"  v12 Probe — KIBC Combinator VSM — step {step:,}")
    print(f"{'='*72}")

    cfg_data = state.get("config", {})
    print(f"  d_model={cfg_data.get('d_model', '?')}  "
          f"vocab={cfg_data.get('vocab_size', '?')}  "
          f"seq_len={cfg_data.get('seq_len', '?')}")

    params = count_parameters(model)
    n_ternary = count_ternary_weights(model)
    print(f"  params: total={params['total']:,}  "
          f"trainable={params['trainable']:,}  ternary={n_ternary:,}")

    evo_gen = state.get("total_generations", 0)
    evo_acc = state.get("total_accepted", 0)
    if evo_gen > 0:
        print(f"  evolution: {evo_acc}/{evo_gen} accepted "
              f"({evo_acc/evo_gen*100:.0f}%)")


def print_compressor_metrics(raw: dict):
    """Print compressor metrics from instrumented samples."""
    n = len(raw["losses"])
    if n == 0:
        return

    print(f"\n  ┌─ S3 gates ──────────────────────────────────────┐")
    s3_avg = [[0.0]*3 for _ in range(5)]
    for gates in raw["s3_gates"]:
        for pi in range(min(len(gates), 5)):
            for ph in range(min(len(gates[pi]), 3)):
                s3_avg[pi][ph] += gates[pi][ph]
    for pi, pname in enumerate(PASS_NAMES_SHORT):
        g = [v / n for v in s3_avg[pi]]
        if pi >= 3:
            # Descending — may have cycle phases
            has_cycles = raw["s3_gates"] and len(raw["s3_gates"][0][pi]) > 3
            if has_cycles:
                all_g = [0.0] * len(raw["s3_gates"][0][pi])
                for gates in raw["s3_gates"]:
                    for j in range(len(gates[pi])):
                        all_g[j] += gates[pi][j]
                all_g = [v / n for v in all_g]
                cycles = len(all_g) // 3
                for cy in range(cycles):
                    base = cy * 3
                    print(f"  │ {pname}c{cy}: disp={all_g[base]:.3f}  "
                          f"conv={all_g[base+1]:.3f}  intg={all_g[base+2]:.3f}")
                continue
        print(f"  │ {pname:4s}: prep={g[0]:.3f}  conv={g[1]:.3f}  "
              f"cons={g[2]:.3f}")

    # S5 reweight
    print(f"  ├─ S5 reweight ───────────────────────────────────┤")
    s5 = _avg_nested(raw["s5_reweight"])
    print(f"  │ {' '.join(f'{pn}={g:.3f}' for pn, g in zip(PASS_NAMES_SHORT, s5))}")

    # Combinator dispatch
    cdw = raw.get("combinator_dispatch_weights", [])
    if cdw:
        avg_cdw = [0.0] * N_COMBINATORS
        for dw in cdw:
            for i in range(N_COMBINATORS):
                avg_cdw[i] += dw[i]
        avg_cdw = [v / len(cdw) for v in avg_cdw]
        print(f"  ├─ Combinator dispatch ───────────────────────────┤")
        for ci in range(N_COMBINATORS):
            bar = "█" * int(avg_cdw[ci] * 80)
            print(f"  │ {COMBINATOR_NAMES[ci]} ({COMBINATOR_ROLE[ci]:8s}): "
                  f"{avg_cdw[ci]:.4f} {bar}")

    # Compute gate
    cg = raw.get("compute_gate_mean", [])
    if cg:
        avg_cg = sum(cg) / len(cg)
        print(f"  ├─ Compute gate ──────────────────────────────────┤")
        print(f"  │ mean={avg_cg:.4f}")

    # Register norms
    reg_norms = _avg_register_norms(raw["register_norms"])
    if reg_norms:
        print(f"  ├─ Register norms ────────────────────────────────┤")
        for bname in sorted(reg_norms.keys()):
            norms = reg_norms[bname]
            print(f"  │ {bname:12s}: {' '.join(f'{n:>7.2f}' for n in norms)}")

    # Compression
    cr = _avg_nested(raw["pass_compression"])
    pd = _avg_nested(raw["pass_phi_dev"])
    print(f"  ├─ φ-Compression (target 1/φ = {INV_PHI:.4f}) ──────┤")
    for pi, pname in enumerate(PASS_NAMES_SHORT):
        phi_mark = " ←φ" if pd[pi] < 0.05 else "   "
        print(f"  │ {pname:4s}: ratio={cr[pi]:>7.3f}  φ-dev={pd[pi]:.3f}{phi_mark}")

    # Algedonic alert (Beer's fire alarm)
    alarm_factors = raw.get("alarm_factors")
    eff_s5 = raw.get("effective_s5_gates")
    alarm_metrics_named = raw.get("alarm_metrics_named")
    if alarm_factors:
        any_alarm = any(abs(f - 1.0) > 0.01 for f in alarm_factors)
        symbol = "🚨" if any_alarm else "🔕"
        print(f"  ├─ Algedonic ({symbol} {'ACTIVE' if any_alarm else 'silent'}) "
              f"──────────────────────┤")
        parts = [f"{pn}={f:.3f}" for pn, f in zip(PASS_NAMES_SHORT, alarm_factors)]
        print(f"  │ factors: {' '.join(parts)}")
        if eff_s5:
            parts2 = [f"{pn}={g:.3f}" for pn, g in zip(PASS_NAMES_SHORT, eff_s5)]
            print(f"  │ eff.gates: {' '.join(parts2)}")
        if alarm_metrics_named:
            for section in ["s3_gate_means", "s3_gate_mins",
                            "dispatch_entropy", "suppression_ratios"]:
                vals = alarm_metrics_named.get(section)
                if vals:
                    val_str = " ".join(f"{v:.3f}" for v in vals)
                    print(f"  │ {section}: {val_str}")

    # Abstraction slots
    abs_slots = raw.get("abstraction_slots")
    if abs_slots:
        n_active = abs_slots.get("n_active_slots", 0)
        n_total = len(abs_slots.get("slot_gates", []))
        symbol = "🟢" if n_active > 0 else "⚪"
        print(f"  ├─ Abstraction slots "
              f"({symbol} {n_active}/{n_total} active) ──────┤")

        gates = abs_slots.get("slot_gates", [])
        if gates:
            alive = [f"{g:.3f}" for g in gates if g > 0.05]
            dormant = sum(1 for g in gates if g <= 0.05)
            if alive:
                top = " ".join(alive[:8])
                sfx = "..." if len(alive) > 8 else ""
                print(f"  │ active gates: {top}{sfx}")
            print(f"  │ dormant: {dormant}/{n_total}")

        usage = abs_slots.get("slot_usage")
        if usage:
            total_mass = sum(usage)
            top = sorted(enumerate(usage), key=lambda x: -x[1])[:5]
            print(f"  │ slot dispatch mass: {total_mass:.4f}")
            if top and top[0][1] > 0.001:
                s = " ".join(
                    f"s{i}={u:.4f}" for i, u in top if u > 0.001)
                print(f"  │ top slots: {s}")

        conf = abs_slots.get("proposal_confidence")
        if conf is not None:
            print(f"  │ proposal confidence: {conf:.4f}")

        max_cos = abs_slots.get("max_slot_kibc_cosine")
        if max_cos:
            avg_c = sum(max_cos) / len(max_cos)
            worst_c = max(max_cos)
            warn = " ⚠ copying!" if worst_c > 0.7 else ""
            print(f"  │ slot→KIBC cos: avg={avg_c:.3f}"
                  f" max={worst_c:.3f}{warn}")

    # Holographic intermediate losses
    holo = raw.get("holo_losses")
    if holo:
        print(f"  ├─ Holographic intermediate losses ───────────────┤")
        for pi, (pname, hl) in enumerate(zip(PASS_NAMES_SHORT, holo)):
            bar_len = max(0, int((12.0 - hl) * 4))  # scale: lower loss = longer bar
            bar = "█" * min(bar_len, 40)
            grad_sources = len(holo) - pi
            print(f"  │ {pname:4s}: CE={hl:>7.3f}  "
                  f"(∂ sources={grad_sources}) {bar}")
        # Early exit quality: pass 0 alone vs final
        if len(holo) >= 2:
            ratio = holo[0] / max(holo[-1], 1e-8)
            print(f"  │ pass_0/final ratio: {ratio:.2f}  "
                  f"({'decodeable' if ratio < 1.5 else 'opaque'})")

    # ── Retrieval (M kernel) ──
    ret_gate_means = raw.get("retrieval_gate_means")
    ret_mem_norms = raw.get("retrieval_memory_norms")
    ret_reg_norms = raw.get("retrieval_register_norms")
    ret_write_gates = raw.get("retrieval_write_gates")
    has_retrieval = any(x is not None for x in
                        (ret_gate_means, ret_mem_norms,
                         ret_reg_norms, ret_write_gates))
    if has_retrieval:
        print(f"  ├─ Retrieval (M kernel) ──────────────────────────┤")
        if ret_gate_means is not None:
            # per-stride gate means across passes — list[list[float]] or list[float]
            if ret_gate_means and isinstance(ret_gate_means[0], (list, tuple)):
                for si, stride_vals in enumerate(ret_gate_means):
                    vals_str = " ".join(f"{v:.4f}" for v in stride_vals)
                    print(f"  │ gate_means stride[{si}]: {vals_str}")
            else:
                vals_str = " ".join(f"{v:.4f}" for v in ret_gate_means)
                print(f"  │ gate_means: {vals_str}")
        if ret_mem_norms is not None:
            if ret_mem_norms and isinstance(ret_mem_norms[0], (list, tuple)):
                for si, stride_vals in enumerate(ret_mem_norms):
                    vals_str = " ".join(f"{v:>8.3f}" for v in stride_vals)
                    print(f"  │ mem_norms  stride[{si}]: {vals_str}")
            else:
                vals_str = " ".join(f"{v:>8.3f}" for v in ret_mem_norms)
                print(f"  │ mem_norms: {vals_str}")
        if ret_reg_norms is not None:
            vals_str = " ".join(f"{v:>8.3f}" for v in ret_reg_norms)
            print(f"  │ reg_norms (per-register L2): {vals_str}")
        if ret_write_gates is not None:
            vals_str = " ".join(f"{v:.4f}" for v in ret_write_gates)
            print(f"  │ write_gates (per-register): {vals_str}")

    print("  └──────────────────────────────────────────"
          "───────┘")


# ══════════════════════════════════════════════════════════════════════
# Multi-checkpoint evolution
# ══════════════════════════════════════════════════════════════════════


def print_evolution(all_results: list[dict]):
    if len(all_results) < 2:
        return

    print(f"\n{'='*72}")
    print(f"  KIBC Combinator Evolution")
    print(f"{'='*72}")

    # Determine if any result has retrieval metrics
    has_ret_gate = any(r.get("ret_gate_mean") is not None for r in all_results)
    has_ret_reg = any(r.get("ret_reg_norm_mean") is not None for r in all_results)

    # Loss
    print(f"\n  {'step':>8} {'loss':>8} {'r':>8}", end="")
    for cn in COMBINATOR_NAMES:
        print(f" {cn:>7}", end="")
    print(f" {'comp_gate':>10}", end="")
    if has_ret_gate:
        print(f" {'ret_gate':>9}", end="")
    if has_ret_reg:
        print(f" {'ret_regnorm':>11}", end="")
    print()
    print(f"  {'─'*8} {'─'*8} {'─'*8}", end="")
    for _ in COMBINATOR_NAMES:
        print(f" {'─'*7}", end="")
    print(f" {'─'*10}", end="")
    if has_ret_gate:
        print(f" {'─'*9}", end="")
    if has_ret_reg:
        print(f" {'─'*11}", end="")
    print()

    for r in all_results:
        loss = r.get("eval_loss", r.get("loss", 0))
        rel_r = (loss - E_IRREDUCIBLE) / (LOG_V - E_IRREDUCIBLE) if loss else 0
        dw = r.get("dispatch", [0.25] * N_COMBINATORS)
        cg = r.get("compute_gate", 0)
        print(f"  {r['step']:>8} {loss:>8.4f} {rel_r:>8.4f}", end="")
        for ci in range(N_COMBINATORS):
            print(f" {dw[ci]:>7.4f}", end="")
        print(f" {cg:>10.4f}", end="")
        if has_ret_gate:
            rg = r.get("ret_gate_mean")
            print(f" {rg:>9.4f}" if rg is not None else f" {'—':>9}", end="")
        if has_ret_reg:
            rn = r.get("ret_reg_norm_mean")
            print(f" {rn:>11.4f}" if rn is not None else f" {'—':>11}", end="")
        print()

    print(f"{'='*72}\n")


# ══════════════════════════════════════════════════════════════════════
# Ternary statistics
# ══════════════════════════════════════════════════════════════════════


def ternary_stats(model: V12Model) -> dict:
    stats = {}
    for path, mod in _walk_ternary_modules(model):
        if isinstance(mod, TernaryLinear):
            w_int = unpack_ternary_mlx(mod.weight)
            mx.eval(w_int)
            w_np = np.array(w_int.astype(mx.int8))
            total = w_np.size
            n_zero = int(np.sum(w_np == 0))
            sparsity = n_zero / total
            gamma_np = np.array(mod.gamma)
            stats[path] = {
                "type": "linear", "shape": (mod.out_features, mod.in_features),
                "sparsity": sparsity,
                "gamma_mean": float(np.mean(np.abs(gamma_np))),
                "gamma_std": float(np.std(gamma_np)),
            }
        elif isinstance(mod, TernaryEmbedding):
            w_int = unpack_ternary(mod.ternary_weight, mod.in_features)
            mx.eval(w_int)
            w_np = np.array(w_int.astype(mx.int8))
            total = w_np.size
            sparsity = int(np.sum(w_np == 0)) / total
            gamma_np = np.array(mod.gamma)
            stats[path] = {
                "type": "embedding",
                "shape": (mod.out_features, mod.in_features),
                "sparsity": sparsity,
                "gamma_mean": float(np.mean(np.abs(gamma_np))),
                "gamma_std": float(np.std(gamma_np)),
            }
    return stats


def print_ternary_stats(stats: dict):
    groups: dict[str, list] = {}
    for path, s in stats.items():
        group = path.split(".")[0]
        groups.setdefault(group, []).append(s)

    print(f"\n  Ternary topology ({len(stats)} modules):")
    print(f"  {'Group':18s} {'#':>3} {'sparsity':>9} {'γ_mean':>8}")
    print(f"  {'─'*18} {'─'*3} {'─'*9} {'─'*8}")

    total_params = 0
    total_zeros = 0
    for grp in sorted(groups.keys()):
        mods = groups[grp]
        n = len(mods)
        sp = sum(m["sparsity"] for m in mods) / n
        gm = sum(m["gamma_mean"] for m in mods) / n
        for m in mods:
            total_params += m["shape"][0] * m["shape"][1]
            total_zeros += int(m["sparsity"] * m["shape"][0] * m["shape"][1])
        print(f"  {grp:18s} {n:>3} {sp:>9.3f} {gm:>8.4f}")

    overall_sp = total_zeros / total_params if total_params else 0
    print(f"  {'─'*18} {'─'*3} {'─'*9}")
    print(f"  {'TOTAL':18s} {len(stats):>3} {overall_sp:>9.3f}  "
          f"({total_params:,} ternary params)")


# ══════════════════════════════════════════════════════════════════════
# JSON output
# ══════════════════════════════════════════════════════════════════════


def save_results(step: int, state: dict, phi_raw: dict,
                 dispatch_analysis: dict | None,
                 eval_result: dict | None,
                 out_dir: Path) -> Path:
    out_dir.mkdir(parents=True, exist_ok=True)
    out_path = out_dir / f"probe_step_{step:06d}.json"

    output = {
        "timestamp": datetime.now(UTC).isoformat(),
        "architecture": "v12-kibc-combinator-vsm",
        "step": step,
        "config": state.get("config", {}),
        "evolution": {
            "total_generations": state.get("total_generations", 0),
            "total_accepted": state.get("total_accepted", 0),
        },
    }
    if eval_result:
        output["eval"] = eval_result
    if dispatch_analysis:
        output["dispatch_analysis"] = dispatch_analysis
    # Holographic intermediate losses (per-pass CEs)
    holo_losses = phi_raw.get("holo_losses")
    if holo_losses:
        output["holographic"] = {
            "pass_ces": {name: float(ce) for name, ce in
                         zip(("L0_up", "L1_up", "L2", "L1_down", "L0_down"),
                             holo_losses)},
            "ratio": float(holo_losses[0] / max(holo_losses[-1], 1e-8)),
        }
    # Abstraction slot metrics (from instrumented analysis)
    abs_slots = phi_raw.get("abstraction_slots")
    if abs_slots:
        output["abstraction_slots"] = abs_slots
    # Retrieval (M kernel) metrics
    retrieval: dict = {}
    if "retrieval_gate_means" in phi_raw:
        retrieval["retrieval_gate_means"] = phi_raw["retrieval_gate_means"]
    if "retrieval_memory_norms" in phi_raw:
        retrieval["retrieval_memory_norms"] = phi_raw["retrieval_memory_norms"]
    if "retrieval_register_norms" in phi_raw:
        retrieval["retrieval_register_norms"] = phi_raw["retrieval_register_norms"]
    if "retrieval_write_gates" in phi_raw:
        retrieval["retrieval_write_gates"] = phi_raw["retrieval_write_gates"]
    if retrieval:
        output["retrieval"] = retrieval

    out_path.write_text(json.dumps(output, indent=2, default=str))
    return out_path


# ══════════════════════════════════════════════════════════════════════
# CLI
# ══════════════════════════════════════════════════════════════════════


def main():
    parser = argparse.ArgumentParser(
        description="v12 probe — KIBC combinator VSM checkpoint diagnostics")
    parser.add_argument("checkpoints", type=Path, nargs="*",
                        help="Checkpoint directory/directories")
    parser.add_argument("--trajectory", type=Path, default=None,
                        help="Checkpoint dir for JSONL trajectory analysis "
                             "(no model loading)")
    parser.add_argument("--dispatch-detail", action="store_true",
                        help="Per-position dispatch distribution analysis")
    parser.add_argument("--no-eval", action="store_true",
                        help="Skip data evaluation (faster)")
    parser.add_argument("--no-ternary", action="store_true",
                        help="Skip ternary statistics")
    parser.add_argument("--dispatch-batches", type=int, default=10,
                        help="Number of batches for dispatch analysis")
    parser.add_argument("--results-dir", type=Path, default=RESULTS_DIR)
    args = parser.parse_args()

    # ── Trajectory mode (no model loading) ────────────────
    if args.trajectory:
        analyze_trajectory(args.trajectory)
        return

    if not args.checkpoints:
        parser.print_help()
        return

    # ── Tokenizer ─────────────────────────────────────────
    print("  Loading Qwen3 tokenizer...", file=sys.stderr)
    from transformers import AutoTokenizer
    tokenizer = AutoTokenizer.from_pretrained(
        "Qwen/Qwen3-0.6B", trust_remote_code=True)

    ckpts = sorted(
        [p for p in args.checkpoints if p.is_dir()],
        key=lambda p: int(p.name.split("_")[-1])
        if p.name.startswith("step_") else 0,
    )
    if not ckpts:
        print("  No checkpoint directories found.", file=sys.stderr)
        return

    all_results = []

    for ckpt_path in ckpts:
        t0 = time.time()
        print(f"\n  Loading {ckpt_path}...", file=sys.stderr)
        model, step, state, cfg = load_checkpoint(ckpt_path)
        print_banner(step, state, model)

        # ── Instrumented analysis on sample strata ────────
        print(f"\n  Running instrumented analysis...", file=sys.stderr)
        all_samples = []
        for samples in PHI_STRATA.values():
            all_samples.extend(samples)
        raw = run_instrumented_samples(model, tokenizer, all_samples)
        print_compressor_metrics(raw)

        # ── Dispatch distribution analysis ────────────────
        dispatch_analysis = None
        if args.dispatch_detail:
            print(f"\n  Running dispatch distribution analysis "
                  f"({args.dispatch_batches} batches)...", file=sys.stderr)
            dispatch_analysis = analyze_dispatch_distribution(
                model, cfg, n_batches=args.dispatch_batches)
            print_dispatch_analysis(dispatch_analysis)

        # ── Eval ──────────────────────────────────────────
        eval_result = None
        if not args.no_eval:
            print(f"\n  Evaluating on held-out data...", file=sys.stderr)
            eval_result = evaluate_on_data(model, cfg)
            print(f"\n  📊 Eval: loss={eval_result['loss']:.3f}  "
                  f"ppl={eval_result['ppl']:.0f}  r={eval_result['r']:.3f}  "
                  f"({eval_result['tokens_evaluated']:,} tokens)")

        # ── Ternary stats ─────────────────────────────────
        if not args.no_ternary:
            ts = ternary_stats(model)
            print_ternary_stats(ts)

        # ── Save ──────────────────────────────────────────
        out_path = save_results(step, state, raw, dispatch_analysis,
                                eval_result, args.results_dir)
        print(f"\n  💾 Saved: {out_path}")

        elapsed = time.time() - t0
        print(f"  ⏱  {elapsed:.1f}s", file=sys.stderr)

        # ── Collect for evolution ─────────────────────────
        cdw = raw.get("combinator_dispatch_weights", [])
        avg_dw = [0.25] * N_COMBINATORS
        if cdw:
            avg_dw = [sum(d[i] for d in cdw) / len(cdw)
                      for i in range(N_COMBINATORS)]

        cg_list = raw.get("compute_gate_mean", [])
        avg_cg = sum(cg_list) / len(cg_list) if cg_list else 0

        result_entry: dict = {
            "step": step,
            "loss": float(sum(raw["losses"]) / len(raw["losses"])),
            "eval_loss": eval_result["loss"] if eval_result else 0,
            "dispatch": avg_dw,
            "compute_gate": avg_cg,
        }
        # Retrieval summary scalars for evolution table
        ret_gm = raw.get("retrieval_gate_means")
        if ret_gm is not None:
            flat = [v for row in ret_gm for v in (row if isinstance(row, (list, tuple)) else [row])]
            result_entry["ret_gate_mean"] = float(sum(flat) / len(flat)) if flat else None
        ret_rn = raw.get("retrieval_register_norms")
        if ret_rn is not None:
            result_entry["ret_reg_norm_mean"] = float(sum(ret_rn) / len(ret_rn)) if ret_rn else None
        all_results.append(result_entry)

    print_evolution(all_results)


if __name__ == "__main__":
    main()
