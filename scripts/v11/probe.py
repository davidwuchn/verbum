#!/usr/bin/env python3
"""v11 probe — checkpoint diagnostics for KIBC combinator VSM.

Probes v11 checkpoints with:
  - Eval loss + relational loss
  - Combinator dispatch distribution (K, I, B, C weights and evolution)
  - Per-position dispatch analysis (which combinator dominates where)
  - CycleContinue dynamics (effective cycles, continuation gates)
  - Combinator emphasis from S4 intelligence channel
  - φ-compression analysis (stratified by content type)
  - S3 gates, S5 reweight, S2 coordination
  - Ternary topology statistics
  - Multi-checkpoint evolution tables
  - JSONL trajectory analysis (metrics_log.jsonl)

Usage:
    # Single checkpoint
    uv run python scripts/v11/probe.py checkpoints/v11/step_001000

    # Multiple checkpoints — evolution table
    uv run python scripts/v11/probe.py checkpoints/v11/step_*

    # Trajectory analysis from JSONL logs (no checkpoint loading)
    uv run python scripts/v11/probe.py --trajectory checkpoints/v11

    # Per-position dispatch distribution analysis
    uv run python scripts/v11/probe.py checkpoints/v11/step_005000 --dispatch-detail

    # Quick: skip eval, just metrics
    uv run python scripts/v11/probe.py checkpoints/v11/step_001000 --no-eval

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

from config import V11Config
from model import V11Model, create_model, count_parameters
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

RESULTS_DIR = Path("results/v11")


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


def load_checkpoint(ckpt_path: Path) -> tuple[V11Model, int, dict, V11Config]:
    """Load a v11 checkpoint. Returns (model, step, state_dict, config)."""
    state_path = ckpt_path / "state.json"
    model_path = ckpt_path / "model.npz"

    if not state_path.exists() or not model_path.exists():
        raise FileNotFoundError(f"Missing state.json or model.npz in {ckpt_path}")

    state = json.loads(state_path.read_text())
    step = state["step"]
    config_data = state.get("config", {})

    cfg = V11Config()
    if "d_model" in config_data:
        cfg.d_model = config_data["d_model"]
        cfg.d_ff = cfg.d_model * 3
        cfg.d_ff_consolidate = cfg.d_model * 4
    if "vocab_size" in config_data:
        cfg.vocab_size = config_data["vocab_size"]
    if "seq_len" in config_data:
        cfg.seq_len = config_data["seq_len"]
        cfg.max_seq_len = config_data["seq_len"]

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


def evaluate_on_data(model: V11Model, cfg: V11Config,
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
    model: V11Model, cfg: V11Config, n_batches: int = 10
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
    print(f"  v11 Trajectory Analysis — {checkpoint_dir}")
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
        print(f" {'eff_cyc':>8} {'emph':>20}")
        print(f"  {'─'*8} {'─'*8} {'─'*8} {'─'*10}", end="")
        for _ in COMBINATOR_NAMES:
            print(f" {'─'*6}", end="")
        print(f" {'─'*8} {'─'*20}")

        for m in metrics:
            step = m["step"]
            loss = m.get("loss", 0)
            r = m.get("r", (loss - E_IRREDUCIBLE) / (LOG_V - E_IRREDUCIBLE))
            cg = m.get("compute_gate_mean", 0)

            # Dispatch weights — handle both v10 (22) and v11 (4) formats
            dw = m.get("combinator_dispatch_weights",
                       m.get("kernel_dispatch_weights", []))

            # Effective cycles
            eff = m.get("effective_cycles", [])
            eff_str = ",".join(f"{e:.2f}" for e in eff) if eff else "—"

            # Emphasis
            emph = m.get("combinator_emphasis",
                         m.get("op_emphasis", []))

            print(f"  {step:>8} {loss:>8.4f} {r:>8.4f} {cg:>10.4f}", end="")
            for ci in range(min(len(dw), N_COMBINATORS)):
                print(f" {dw[ci]:>6.3f}", end="")
            if len(dw) < N_COMBINATORS:
                for _ in range(N_COMBINATORS - len(dw)):
                    print(f" {'—':>6}", end="")
            print(f" {eff_str:>8}", end="")

            # Emphasis: show as K=1.00 I=1.00 B=1.00 C=1.00
            if emph and len(emph) <= N_COMBINATORS:
                emph_strs = [f"{COMBINATOR_NAMES[i]}={emph[i]:.2f}"
                             for i in range(len(emph))]
                print(f" {' '.join(emph_strs):>20}", end="")

            # Alarm factors (if present)
            af = m.get("alarm_factors", [])
            if af:
                any_active = any(abs(f - 1.0) > 0.01 for f in af)
                if any_active:
                    af_str = " ".join(f"{f:.2f}" for f in af)
                    print(f"  🚨[{af_str}]", end="")
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

        # ── CycleContinue trajectory ──────────────────────
        has_cycles = any(m.get("cycle_continue_gates") for m in metrics)
        if has_cycles:
            print(f"\n  CycleContinue trajectory:")
            print(f"  {'step':>8} {'eff_L1↓':>8} {'eff_L0↓':>8} "
                  f"{'cont_L1↓':>16} {'cont_L0↓':>16}")
            print(f"  {'─'*8} {'─'*8} {'─'*8} {'─'*16} {'─'*16}")
            for m in metrics:
                step = m["step"]
                eff = m.get("effective_cycles", [])
                cont = m.get("cycle_continue_gates", [])
                eff_strs = [f"{e:.3f}" for e in eff] if eff else ["—", "—"]
                cont_strs = []
                for cg_list in cont:
                    if cg_list:
                        cont_strs.append(",".join(f"{g:.3f}" for g in cg_list))
                    else:
                        cont_strs.append("—")
                while len(eff_strs) < 2:
                    eff_strs.append("—")
                while len(cont_strs) < 2:
                    cont_strs.append("—")
                print(f"  {step:>8} {eff_strs[0]:>8} {eff_strs[1]:>8} "
                      f"{cont_strs[0]:>16} {cont_strs[1]:>16}")

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
    model: V11Model, tokenizer, samples: list[str]
) -> dict:
    """Run forward_instrumented on text samples."""
    all_metrics = {
        "s3_gates": [], "s5_reweight": [], "register_norms": [],
        "pass_compression": [], "pass_phi_dev": [],
        "pass_entropy_in": [], "pass_entropy_out": [],
        "losses": [], "per_sample": [],
        "combinator_dispatch_weights": [], "combinator_type_weights": [],
        "combinator_emphasis": [],
        "cycle_continue_gates": [], "effective_cycles": [],
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
        if metrics.get("combinator_emphasis"):
            all_metrics["combinator_emphasis"].append(
                metrics["combinator_emphasis"])
        if metrics.get("cycle_continue_gates"):
            all_metrics["cycle_continue_gates"].append(
                metrics["cycle_continue_gates"])
        if metrics.get("effective_cycles"):
            all_metrics["effective_cycles"].append(
                metrics["effective_cycles"])
        if "compute_gate_mean" in metrics:
            all_metrics["compute_gate_mean"].append(
                metrics["compute_gate_mean"])

        all_metrics["per_sample"].append({
            "text": text[:60],
            "loss": float(loss.item()),
            "pass_compression": metrics["pass_compression"],
        })

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


def print_banner(step: int, state: dict, model: V11Model):
    print(f"\n{'='*72}")
    print(f"  v11 Probe — KIBC Combinator VSM — step {step:,}")
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

    # Emphasis
    emph = raw.get("combinator_emphasis", [])
    if emph:
        avg_emph = [0.0] * N_COMBINATORS
        for e in emph:
            for i in range(N_COMBINATORS):
                avg_emph[i] += e[i]
        avg_emph = [v / len(emph) for v in avg_emph]
        print(f"  ├─ Combinator emphasis (S4→dispatch) ────────────┤")
        for ci in range(N_COMBINATORS):
            dev = avg_emph[ci] - 1.0
            marker = " ↑" if dev > 0.05 else (" ↓" if dev < -0.05 else "")
            print(f"  │ {COMBINATOR_NAMES[ci]}: {avg_emph[ci]:.4f}{marker}")

    # Compute gate
    cg = raw.get("compute_gate_mean", [])
    if cg:
        avg_cg = sum(cg) / len(cg)
        print(f"  ├─ Compute gate ──────────────────────────────────┤")
        print(f"  │ mean={avg_cg:.4f}")

    # CycleContinue
    ccg = raw.get("cycle_continue_gates", [])
    eff = raw.get("effective_cycles", [])
    if ccg or eff:
        print(f"  ├─ CycleContinue ─────────────────────────────────┤")
        if eff:
            avg_eff = [0.0] * len(eff[0])
            for e in eff:
                for i in range(len(e)):
                    avg_eff[i] += e[i]
            avg_eff = [v / len(eff) for v in avg_eff]
            print(f"  │ effective cycles: "
                  f"{' '.join(f'{e:.3f}' for e in avg_eff)}")

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

    print(f"  └─────────────────────────────────────────────────┘")


# ══════════════════════════════════════════════════════════════════════
# Multi-checkpoint evolution
# ══════════════════════════════════════════════════════════════════════


def print_evolution(all_results: list[dict]):
    if len(all_results) < 2:
        return

    print(f"\n{'='*72}")
    print(f"  KIBC Combinator Evolution")
    print(f"{'='*72}")

    # Loss
    print(f"\n  {'step':>8} {'loss':>8} {'r':>8}", end="")
    for cn in COMBINATOR_NAMES:
        print(f" {cn:>7}", end="")
    print(f" {'comp_gate':>10} {'eff_cyc':>8}")
    print(f"  {'─'*8} {'─'*8} {'─'*8}", end="")
    for _ in COMBINATOR_NAMES:
        print(f" {'─'*7}", end="")
    print(f" {'─'*10} {'─'*8}")

    for r in all_results:
        loss = r.get("eval_loss", r.get("loss", 0))
        rel_r = (loss - E_IRREDUCIBLE) / (LOG_V - E_IRREDUCIBLE) if loss else 0
        dw = r.get("dispatch", [0.25] * N_COMBINATORS)
        cg = r.get("compute_gate", 0)
        eff = r.get("effective_cycles", "—")
        print(f"  {r['step']:>8} {loss:>8.4f} {rel_r:>8.4f}", end="")
        for ci in range(N_COMBINATORS):
            print(f" {dw[ci]:>7.4f}", end="")
        print(f" {cg:>10.4f} {eff:>8}")

    print(f"{'='*72}\n")


# ══════════════════════════════════════════════════════════════════════
# Ternary statistics
# ══════════════════════════════════════════════════════════════════════


def ternary_stats(model: V11Model) -> dict:
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
        "architecture": "v11-kibc-combinator-vsm",
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

    out_path.write_text(json.dumps(output, indent=2, default=str))
    return out_path


# ══════════════════════════════════════════════════════════════════════
# CLI
# ══════════════════════════════════════════════════════════════════════


def main():
    parser = argparse.ArgumentParser(
        description="v11 probe — KIBC combinator VSM checkpoint diagnostics")
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

        eff_list = raw.get("effective_cycles", [])
        eff_str = "—"
        if eff_list:
            avg_eff = [sum(e[i] for e in eff_list) / len(eff_list)
                       for i in range(len(eff_list[0]))]
            eff_str = ",".join(f"{e:.2f}" for e in avg_eff)

        all_results.append({
            "step": step,
            "loss": float(sum(raw["losses"]) / len(raw["losses"])),
            "eval_loss": eval_result["loss"] if eval_result else 0,
            "dispatch": avg_dw,
            "compute_gate": avg_cg,
            "effective_cycles": eff_str,
        })

    print_evolution(all_results)


if __name__ == "__main__":
    main()
