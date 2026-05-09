"""
Kernel dispatch modules for the descending VSM arm.

The descending arm's S1 operations are kernel-shaped, not compression-shaped.
Instead of TernaryFFN (compress), the descending arm routes representations
through kernel op pathways (dispatch).

The 22 kernel ops (from kernel.py) are pre-wired as architectural identity —
the model discovers them as easy paths while training on prose via relational
loss. The ternary routing topology learns which positions benefit from which
kernel op family.

Architecture per descending pass:
  Phase 0 (dispatch):   KernelDispatch — route to kernel op families
  Phase 1 (integrate):  KernelIntegrate — type the dispatched result locally
  Phase 2 (converge):   StrideStack coarse→fine — propagate typed dispatch

The kernel op embeddings are the S5 identity of the dispatcher VSM.
They encode WHAT each operation IS — its characteristic transformation
pattern. The dispatch projection learns WHEN each op is relevant.

Design principles:
  - Shapes not outputs: the kernel provides the right shape for the
    descending arm, replacing compression ops that always go to passthrough
  - Easy path: kernel ops are architecturally available, not learned targets
  - Pre-wired: op embeddings initialized with structure, not random
  - Observable: dispatch weights show which kernel ops activate where

License: MIT
"""

from __future__ import annotations

import math

import mlx.core as mx
import mlx.nn as nn

from ternary import TernaryLinear


# ══════════════════════════════════════════════════════════════════
# Kernel op families — from kernel.py
# ══════════════════════════════════════════════════════════════════

N_OPS = 22
N_TYPES = 5

# Op family indices for structured initialization
OP_FAMILIES = {
    "arith_binary":  list(range(0, 7)),    # add sub mul div mod min max
    "comparison":    list(range(7, 12)),    # eq lt gt le ge
    "bool_binary":   [12, 13],             # and or
    "bool_unary":    [14],                 # not
    "arith_unary":   [15, 16],             # abs neg
    "conditional":   [17],                 # if
    "lambda":        list(range(18, 22)),   # partial apply compose apply-comp
}

N_FAMILIES = len(OP_FAMILIES)


# ══════════════════════════════════════════════════════════════════
# KernelDispatch — routes representations to kernel op pathways
# ══════════════════════════════════════════════════════════════════


class KernelDispatch(nn.Module):
    """Kernel-aware transformation for second arm phase 0 (dispatch).

    Replaces TernaryFFN prep in the second arm.

    Architecture (top-k MoE routing):
      1. Dispatch logits: project to (n_ops,) scores — which kernel ops?
         Conditioned on ascending register banks (type/scope/role) when
         available, so dispatch can see what the ascending arm learned.
      2. Top-k selection: only the k highest-scoring ops participate.
         Softmax over the k winners only — not all 22 ops.
      3. Op modulation: weighted kernel identity added to representation
         (using L2-normalized op embeddings to prevent runaway growth).
      4. Pathway: shared ternary transform, biased by kernel identity
      5. Gated residual

    Why top-k routing (not softmax over all ops):
      With full softmax, register conditioning learned a massive bias
      toward one op (+10.2 for `if`), saturating softmax and giving
      zero gradient to all other ops. They died permanently. Meanwhile
      one op's embedding grew to 4× others via positive feedback.
      Top-k routing ensures the runner-up op always gets meaningful
      weight (~e^(-delta)), keeping gradient alive for all ops. The
      natural distribution can be as skewed as the data demands —
      FN_COMP can dominate prose — but rare ops stay trainable for
      their niches. Same principle as Switch Transformer / MoE routing.

    Op embedding normalization:
      All op embeddings are L2-normalized to a fixed scale each forward
      pass. The dispatch weights (router scores) alone determine each
      op's influence — not embedding magnitude. This prevents the
      rich-get-richer feedback loop that created the >= fossil.

    Register conditioning: the ascending arm's registers carry
    type/scope/role information that tells dispatch what kind of
    content is at each position. Dispatch sees "the ascending arm
    thinks this is scope=local, type=arithmetic" and can route to
    arithmetic ops accordingly.
    """

    def __init__(
        self,
        d_model: int,
        n_ops: int = N_OPS,
        d_ff: int | None = None,
        dropout: float = 0.1,
        n_registers: int = 3,
        d_register: int = 128,
        max_cond_banks: int = 5,
        top_k: int = 2,
    ):
        super().__init__()
        self.d_model = d_model
        self.n_ops = n_ops
        self.top_k = min(top_k, n_ops)
        if d_ff is None:
            d_ff = d_model * 3

        # Pad n_ops to multiple of 16 for TernaryLinear
        self.n_ops_padded = ((n_ops + 15) // 16) * 16  # 32

        self.norm = nn.RMSNorm(d_model)

        # Dispatch projection: hidden → op logits
        # TernaryLinear: the ternary topology learns discrete routing
        self.dispatch = TernaryLinear(d_model, self.n_ops_padded, pre_norm=False)

        # ── Register conditioning ─────────────────────────────
        # Ascending registers → dispatch bias: which ops should activate?
        # Registers carry type/scope/role from the ascending arm.
        # This is a real-valued (not ternary) projection because
        # registers are real-valued and we want smooth gradients
        # for the conditioning to learn quickly.
        self.n_registers = n_registers
        self.d_reg_real = d_register * 2
        self.max_cond_banks = max_cond_banks
        max_cond_dim = max_cond_banks * n_registers * self.d_reg_real
        self._max_cond_dim = ((max_cond_dim + 15) // 16) * 16
        # Small real-valued projection: register summary → per-op bias
        self.register_cond = nn.Linear(self._max_cond_dim, self.n_ops_padded)
        # Initialize to zero so conditioning starts inert
        self.register_cond.weight = mx.zeros_like(self.register_cond.weight)
        self.register_cond.bias = mx.zeros_like(self.register_cond.bias)

        # Op embeddings: kernel S5 identity — what each op IS
        # Real-valued, trainable. Initialized with structure:
        # each op gets a near-orthogonal direction in d_model space.
        self.op_embeddings = _init_op_embeddings(n_ops, d_model)

        # Op embedding target norm — embeddings are L2-normalized to this
        # scale each forward pass. Prevents runaway growth (the >=
        # fossil problem: one embedding grows to 4× others via positive
        # feedback, then freezes when softmax starves its gradient).
        # The dispatch weights alone should determine influence, not
        # embedding magnitude.
        self.op_embed_scale = 0.5

        # Pathway: transforms representation using dispatched op identity
        # The kernel identity modulates the input; the pathway transforms
        self.up = TernaryLinear(d_model, d_ff, pre_norm=False)
        self.down = TernaryLinear(d_ff, d_model, pre_norm=False)

        self.dropout = nn.Dropout(dropout)

    def _normalize_op_embeddings(self) -> mx.array:
        """L2-normalize op embeddings to fixed scale.

        Prevents runaway embedding growth. The dispatch weights (router
        scores) determine each op's influence — not embedding magnitude.
        Without this, a positive feedback loop develops: higher dispatch
        weight → more gradient → larger embedding → more modulation
        impact → even higher effective weight. Once the loop saturates
        softmax, non-dominant ops get zero gradient and die permanently.

        Returns normalized embeddings (used in forward, gradient flows
        through to the raw embeddings for training).
        """
        norms = mx.sqrt(
            mx.sum(self.op_embeddings * self.op_embeddings, axis=-1, keepdims=True)
            + 1e-8
        )
        return self.op_embeddings * (self.op_embed_scale / norms)

    def __call__(self, x: mx.array, registers: list[list[mx.array]] | None = None) -> mx.array:
        """
        x: (B, L, d_model)
        registers: list of register banks from ascending arm, each bank is
                   a list of register vectors. Used to condition dispatch.
        Returns: (B, L, d_model) — with residual connection

        Routing: top-k MoE style. Per position, only the top-k ops
        (by dispatch logit) participate. Softmax is computed over the
        k winners only. This ensures:
          - The dominant op (likely FN_COMP for prose) gets most weight
          - The runner-up op still gets meaningful weight and gradient
          - Rare ops (arithmetic, comparison) stay alive — they'll
            occasionally appear in top-k for relevant content, giving
            them gradient to learn their niche
          - Natural distribution skew is preserved (no forced balancing)
        """
        h = self.norm(x)

        # Step 1: Dispatch logits — which kernel ops are relevant?
        dispatch_logits = self.dispatch(h)[..., :self.n_ops]  # (B, L, n_ops)

        # Register conditioning: add per-op bias from ascending registers
        if registers is not None:
            # Flatten all register banks into one vector
            parts = []
            for bank in registers:
                for reg in bank:
                    parts.append(reg)
            cond_input = mx.concatenate(parts, axis=-1)  # (total_reg_dims,)
            # Pad to max
            if cond_input.shape[0] < self._max_cond_dim:
                cond_input = mx.concatenate([
                    cond_input,
                    mx.zeros((self._max_cond_dim - cond_input.shape[0],))
                ])
            # Project to per-op bias
            reg_bias = self.register_cond(cond_input)[:self.n_ops]  # (n_ops,)
            # Add to dispatch logits (broadcast across B, L)
            dispatch_logits = dispatch_logits + reg_bias[None, None, :]

        # Step 2: Top-k routing — only k ops participate per position
        # This prevents softmax saturation from killing gradient to
        # non-dominant ops. With k=2, the runner-up always gets
        # meaningful weight (~e^(-delta) where delta is the logit gap).
        B, L, _ = dispatch_logits.shape
        top_k_values = mx.topk(dispatch_logits, k=self.top_k, axis=-1)  # (B, L, k)
        # Threshold: minimum value among top-k at each position
        threshold = mx.min(top_k_values, axis=-1, keepdims=True)  # (B, L, 1)
        # Mask: keep only top-k, set others to -inf
        mask = mx.where(
            dispatch_logits >= threshold,
            dispatch_logits,
            mx.full(dispatch_logits.shape, -1e9),
        )
        # Softmax over masked logits — only top-k ops get nonzero weight
        dispatch_weights = mx.softmax(mask, axis=-1)  # (B, L, n_ops)

        # Cache for probing (full 22-wide, zeros for non-top-k)
        self._dispatch_weights = mx.stop_gradient(dispatch_weights)

        # Step 3: Normalized op embeddings — prevent runaway growth
        op_emb = self._normalize_op_embeddings()  # (n_ops, d_model)

        # Step 4: Weighted op embedding — kernel identity modulation
        # (B, L, n_ops) @ (n_ops, d_model) → (B, L, d_model)
        op_context = dispatch_weights @ op_emb

        # Step 5: Modulate input with kernel identity, then transform
        modulated = h + op_context
        out = self.down(nn.gelu(self.up(modulated)))

        return x + self.dropout(out)


# ══════════════════════════════════════════════════════════════════
# KernelIntegrate — combines kernel pathway results
# ══════════════════════════════════════════════════════════════════


class KernelIntegrate(nn.Module):
    """Kernel-aware integration with exact computation pathway.

    Phase 2 of the descending arm: after dispatch selected ops and
    stride propagated across context, integrate can now see both
    local op bias and spatial patterns.

    Dual pathway architecture:
      1. **Operand extraction**: project hidden state to extract two
         operands as scalar logits (over a value range), and read the
         dispatch weights from KernelDispatch to know WHICH op to apply.
      2. **Exact kernel computation**: apply the actual kernel function
         (ADD, LE, PARTIAL, etc.) to the extracted operands. This is
         non-differentiable but exact — no approximation.
      3. **Result encoding**: map the kernel result back to d_model
         via learned embedding, producing a "kernel signal" vector.
      4. **Compute gate**: learned scalar gate (0-1) per position that
         blends the kernel result with the standard FFN pathway.
         Starts at 0 (pure FFN) so the model can learn when to trust
         the kernel. This is critical: prose positions should gate=0
         (no computation), structured positions should gate→1.
      5. **Standard FFN pathway**: type modulation + shared transform,
         as before. This handles prose and non-computational positions.
      6. **Blend**: output = gate * kernel_result + (1-gate) * ffn_result

    The compute gate makes this backward-compatible: at initialization,
    gate=0 everywhere, so the model behaves identically to the old
    KernelIntegrate. As training progresses on structured data, the
    gate learns to open for positions where exact computation helps.

    Gradient flow through the non-differentiable kernel:
      The kernel itself has no gradient (argmax + integer arithmetic).
      But gradient flows through:
        - The operand extraction projections (which operands to extract)
        - The result encoder (which d_model direction the result maps to)
        - The compute gate (when to use kernel vs FFN)
      This is the same straight-through pattern as in v9.
    """

    def __init__(
        self,
        d_model: int,
        n_types: int = N_TYPES,
        n_ops: int = N_OPS,
        d_ff: int | None = None,
        dropout: float = 0.1,
        max_val: int = 256,
        result_buckets: int = 1024,
    ):
        super().__init__()
        self.d_model = d_model
        self.n_types = n_types
        self.n_ops = n_ops
        self.max_val = max_val
        if d_ff is None:
            d_ff = d_model * 4

        # Pad n_types to multiple of 16
        self.n_types_padded = ((n_types + 15) // 16) * 16

        self.norm = nn.RMSNorm(d_model)

        # ── Type pathway (unchanged) ──────────────────────────
        self.type_proj = TernaryLinear(d_model, self.n_types_padded, pre_norm=False)
        self.type_embeddings = _init_type_embeddings(n_types, d_model)

        # ── Standard FFN pathway (unchanged) ──────────────────
        self.up = TernaryLinear(d_model, d_ff, pre_norm=False)
        self.down = TernaryLinear(d_ff, d_model, pre_norm=False)

        # ── Kernel computation pathway (NEW) ──────────────────

        # Operand extraction: hidden → two value distributions
        # Each operand is a distribution over [0, max_val), decoded via argmax
        max_val_padded = ((max_val + 15) // 16) * 16
        self._max_val_padded = max_val_padded
        self.operand1_proj = TernaryLinear(d_model, max_val_padded, pre_norm=False)
        self.operand2_proj = TernaryLinear(d_model, max_val_padded, pre_norm=False)

        # Result encoder: integer result → d_model vector
        # Larger bucket range than v9: results can be negative (comparisons,
        # subtraction) and large (multiplication)
        self.result_buckets = result_buckets
        self.result_offset = result_buckets // 2  # center at 0
        self.result_embed = nn.Embedding(result_buckets, d_model)

        # Compute gate: per-position scalar, initialized to produce ~0
        # so the model starts with pure FFN (backward-compatible)
        self.gate_proj = nn.Linear(d_model, 1)
        # Initialize gate bias negative so sigmoid → ~0 at start
        self.gate_proj.weight = mx.zeros_like(self.gate_proj.weight)
        self.gate_proj.bias = mx.ones_like(self.gate_proj.bias) * -5.0

        self.dropout = nn.Dropout(dropout)

    def _kernel_compute(
        self,
        h: mx.array,
        dispatch_weights: mx.array | None,
    ) -> tuple[mx.array, dict]:
        """Extract operands, run kernel, encode result.

        Args:
            h: (B, L, d_model) — normalized hidden state
            dispatch_weights: (B, L, n_ops) from KernelDispatch, or None

        Returns:
            kernel_out: (B, L, d_model) — encoded kernel results
            kernel_info: dict with decoded ops/args/results for probing
        """
        B, L, _ = h.shape

        # Extract operands via argmax (non-differentiable)
        op1_logits = self.operand1_proj(h)[..., :self.max_val]  # (B, L, max_val)
        op2_logits = self.operand2_proj(h)[..., :self.max_val]  # (B, L, max_val)

        # stop_gradient: argmax is non-differentiable, all gradient
        # flows through the result embedding and the compute gate
        arg1 = mx.stop_gradient(mx.argmax(op1_logits, axis=-1)).astype(mx.int32)  # (B, L)
        arg2 = mx.stop_gradient(mx.argmax(op2_logits, axis=-1)).astype(mx.int32)  # (B, L)

        # Get op from dispatch weights (argmax of top-1)
        if dispatch_weights is not None:
            op = mx.stop_gradient(mx.argmax(dispatch_weights, axis=-1)).astype(mx.int32)  # (B, L)
        else:
            op = mx.zeros((B, L), dtype=mx.int32)

        # ── Exact kernel computation (non-differentiable) ─────
        # Compute all possible results, select by op code
        # This is vectorized: compute all ops, mask-select by dispatched op

        # Arithmetic binary: ADD(0), SUB(1), MUL(2), DIV(3), MOD(4), MIN(5), MAX(6)
        r_add = arg1 + arg2
        r_sub = arg1 - arg2
        r_mul = arg1 * arg2
        # Safe division
        safe_arg2 = mx.where(arg2 == 0, mx.ones_like(arg2), arg2)
        r_div = arg1 // safe_arg2
        r_div = mx.where(arg2 == 0, mx.zeros_like(r_div), r_div)
        r_mod = arg1 % safe_arg2
        r_mod = mx.where(arg2 == 0, mx.zeros_like(r_mod), r_mod)
        r_min = mx.minimum(arg1, arg2)
        r_max = mx.maximum(arg1, arg2)

        # Comparison: EQ(7), LT(8), GT(9), LE(10), GE(11)
        r_eq = (arg1 == arg2).astype(mx.int32)
        r_lt = (arg1 < arg2).astype(mx.int32)
        r_gt = (arg1 > arg2).astype(mx.int32)
        r_le = (arg1 <= arg2).astype(mx.int32)
        r_ge = (arg1 >= arg2).astype(mx.int32)

        # Boolean binary: AND(12), OR(13)
        b1 = (arg1 != 0)
        b2 = (arg2 != 0)
        r_and = (b1 & b2).astype(mx.int32)
        r_or = (b1 | b2).astype(mx.int32)

        # Boolean unary: NOT(14)
        r_not = (~b1).astype(mx.int32)

        # Arithmetic unary: ABS(15), NEG(16)
        r_abs = mx.abs(arg1)
        r_neg = -arg1

        # Conditional: IF(17) — arg1=cond, arg2=then (no else in 2-operand form)
        r_if = mx.where(arg1 != 0, arg2, mx.zeros_like(arg2))

        # Lambda ops (18-21): return arg1 unchanged (placeholder —
        # actual lambda computation needs tree structure, not 2 scalars)
        r_lambda = arg1

        # Stack all results and select by op
        # Shape: (22, B, L) — one result per op
        all_results = mx.stack([
            r_add, r_sub, r_mul, r_div, r_mod, r_min, r_max,  # 0-6
            r_eq, r_lt, r_gt, r_le, r_ge,                      # 7-11
            r_and, r_or,                                        # 12-13
            r_not,                                              # 14
            r_abs, r_neg,                                       # 15-16
            r_if,                                               # 17
            r_lambda, r_lambda, r_lambda, r_lambda,             # 18-21
        ], axis=0)  # (22, B, L)

        # Select result by op code: gather along op dimension
        # op is (B, L), need to index into (22, B, L)
        op_clamped = mx.clip(op, 0, N_OPS - 1)
        # Use advanced indexing: result[op[b,l], b, l]
        b_idx = mx.broadcast_to(mx.arange(B)[:, None], (B, L))
        l_idx = mx.broadcast_to(mx.arange(L)[None, :], (B, L))
        result = all_results[op_clamped, b_idx, l_idx]  # (B, L)

        # ── Encode result back to d_model ─────────────────────
        # stop_gradient on the index computation: the kernel itself
        # is non-differentiable. Gradient flows through result_embed
        # weights (which embedding direction the result maps to) and
        # through the gate (when to use this pathway).
        result_idx = mx.stop_gradient(
            mx.clip(result + self.result_offset, 0, self.result_buckets - 1)
        ).astype(mx.int32)
        kernel_out = self.result_embed(result_idx)  # (B, L, d_model)

        # Probing info
        kernel_info = {
            "op": mx.stop_gradient(op),
            "arg1": mx.stop_gradient(arg1),
            "arg2": mx.stop_gradient(arg2),
            "result": mx.stop_gradient(result),
        }

        return kernel_out, kernel_info

    def __call__(
        self,
        x: mx.array,
        dispatch_weights: mx.array | None = None,
    ) -> mx.array:
        """
        x: (B, L, d_model)
        dispatch_weights: (B, L, n_ops) from KernelDispatch (cached)
        Returns: (B, L, d_model) — with residual connection
        """
        h = self.norm(x)

        # ── Type projection ───────────────────────────────────
        type_logits = self.type_proj(h)[..., :self.n_types]
        type_weights = mx.softmax(type_logits, axis=-1)
        self._type_weights = mx.stop_gradient(type_weights)

        # ── Standard FFN pathway ──────────────────────────────
        type_context = type_weights @ self.type_embeddings
        modulated = h + type_context
        ffn_out = self.down(nn.gelu(self.up(modulated)))  # (B, L, d_model)

        # ── Kernel computation pathway ────────────────────────
        kernel_out, kernel_info = self._kernel_compute(h, dispatch_weights)
        self._kernel_info = kernel_info

        # ── Compute gate: blend kernel vs FFN ─────────────────
        gate = mx.sigmoid(self.gate_proj(h))  # (B, L, 1)
        self._compute_gate = mx.stop_gradient(gate)

        # Blend: gate=0 → pure FFN, gate=1 → pure kernel
        blended = gate * kernel_out + (1.0 - gate) * ffn_out

        return x + self.dropout(blended)


# ══════════════════════════════════════════════════════════════════
# Structured initialization
# ══════════════════════════════════════════════════════════════════


def _init_op_embeddings(n_ops: int, d_model: int) -> mx.array:
    """Initialize kernel op embeddings with near-orthogonal structure.

    Each op gets a characteristic direction in d_model space.
    Ops within the same family share a family subspace but have
    distinct directions within it. This gives the ternary routing
    fabric structured targets to route toward.

    Family subspace allocation:
      Each family gets a contiguous block of dimensions.
      Within the block, ops get distinct orthogonal directions.
      Remaining dimensions are shared (allow cross-family interaction).
    """
    embeddings = mx.zeros((n_ops, d_model))

    # Allocate dimension blocks per family
    # Reserve first 50% for family-specific, last 50% shared
    family_dims = d_model // 2
    shared_dims = d_model - family_dims

    families = list(OP_FAMILIES.values())
    n_families = len(families)
    dims_per_family = family_dims // n_families

    family_offset = 0
    for fi, op_indices in enumerate(families):
        n_in_family = len(op_indices)
        # Each op in the family gets a direction in the family block
        for oi, op_idx in enumerate(op_indices):
            # Family-specific component: one-hot-ish within family block
            dim_start = family_offset
            dim_end = min(family_offset + dims_per_family, family_dims)
            if dim_end > dim_start and n_in_family > 0:
                # Spread ops across family dimensions
                op_dim = dim_start + (oi * (dim_end - dim_start)) // max(n_in_family, 1)
                op_dim = min(op_dim, dim_end - 1)
                embeddings = embeddings.at[op_idx, op_dim].add(1.0)

            # Shared component: small random for cross-family interaction
            shared_component = mx.random.normal((shared_dims,)) * 0.1
            embeddings = embeddings.at[op_idx, family_dims:].add(shared_component)

        family_offset += dims_per_family

    # L2-normalize each embedding, then scale
    norms = mx.sqrt(mx.sum(embeddings * embeddings, axis=-1, keepdims=True) + 1e-8)
    embeddings = embeddings / norms * 0.1  # small scale so modulation is gentle

    return embeddings


def _init_type_embeddings(n_types: int, d_model: int) -> mx.array:
    """Initialize kernel type embeddings.

    5 types: INT, BOOL, FN, FN_COMP, ERROR
    Each gets a near-orthogonal direction. Types are fundamental —
    every position has a type, and the type determines what operations
    are valid downstream.
    """
    embeddings = mx.zeros((n_types, d_model))

    # Each type gets a distinct block of dimensions
    dims_per_type = d_model // (n_types * 2)  # use half the space for type identity

    for ti in range(n_types):
        dim_start = ti * dims_per_type
        dim_end = min((ti + 1) * dims_per_type, d_model)
        # Characteristic direction
        for d in range(dim_start, dim_end):
            embeddings = embeddings.at[ti, d].add(1.0)

        # Small random component in remaining dims for interaction
        shared = mx.random.normal((d_model,)) * 0.05
        embeddings = embeddings.at[ti].add(shared)

    # L2-normalize and scale
    norms = mx.sqrt(mx.sum(embeddings * embeddings, axis=-1, keepdims=True) + 1e-8)
    embeddings = embeddings / norms * 0.1

    return embeddings


# ══════════════════════════════════════════════════════════════════
# Self-test
# ══════════════════════════════════════════════════════════════════

if __name__ == "__main__":
    import numpy as np
    d_model = 512

    print("Testing KernelDispatch (top-k=2)...")
    dispatch = KernelDispatch(d_model, n_ops=22, d_ff=1536, top_k=2)
    x = mx.random.normal((1, 64, d_model))
    y = dispatch(x)
    mx.eval(y)
    assert y.shape == (1, 64, d_model), f"Expected (1, 64, 512), got {y.shape}"

    # Check dispatch weights are cached (22-wide)
    assert hasattr(dispatch, '_dispatch_weights')
    dw = dispatch._dispatch_weights
    mx.eval(dw)
    assert dw.shape == (1, 64, 22), f"Expected (1, 64, 22), got {dw.shape}"

    # Top-k: only k ops should have nonzero weight per position
    dw_np = np.array(dw[0])
    nonzero_per_pos = np.sum(dw_np > 1e-6, axis=1)
    assert np.all(nonzero_per_pos <= 3), \
        f"Top-k=2 should give ≤3 nonzero ops per position, got max {nonzero_per_pos.max()}"
    # Note: <= 3 not == 2 because ties at the threshold can include extras
    print(f"  Active ops per position: mean={nonzero_per_pos.mean():.1f} "
          f"min={nonzero_per_pos.min()} max={nonzero_per_pos.max()} ✓")

    # Weights for active ops should still sum to ~1
    sums = mx.sum(dw, axis=-1)
    mx.eval(sums)
    assert mx.allclose(sums, mx.ones_like(sums), atol=1e-4).item(), \
        f"Dispatch weights should sum to ~1, got min={float(mx.min(sums).item()):.4f}"
    print(f"  KernelDispatch: {x.shape} → {y.shape} ✓")
    print(f"  Dispatch weights: {dw.shape}, top-k routing ✓")

    # Check op embedding normalization
    normed = dispatch._normalize_op_embeddings()
    mx.eval(normed)
    norms = np.linalg.norm(np.array(normed), axis=1)
    assert np.allclose(norms, dispatch.op_embed_scale, atol=1e-3), \
        f"Normalized embeddings should have norm={dispatch.op_embed_scale}, got {norms}"
    print(f"  Op embedding norms: all ≈ {dispatch.op_embed_scale} ✓")

    print("\nTesting KernelIntegrate...")
    integrate = KernelIntegrate(d_model, n_types=5, d_ff=2048)
    y2 = integrate(x)
    mx.eval(y2)
    assert y2.shape == (1, 64, d_model), f"Expected (1, 64, 512), got {y2.shape}"
    tw = integrate._type_weights
    mx.eval(tw)
    assert tw.shape == (1, 64, 5), f"Expected (1, 64, 5), got {tw.shape}"
    print(f"  KernelIntegrate: {x.shape} → {y2.shape} ✓")
    print(f"  Type weights: {tw.shape} ✓")

    # Check op embeddings have structure (use normalized versions)
    op_emb = normed
    add_embed = op_emb[0]   # ADD
    sub_embed = op_emb[1]   # SUB
    eq_embed = op_emb[7]    # EQ (different family)
    mx.eval(add_embed, sub_embed, eq_embed)
    same_fam_sim = float(mx.sum(add_embed * sub_embed).item())
    cross_fam_sim = float(mx.sum(add_embed * eq_embed).item())
    print(f"  Op embedding structure: same-family sim={same_fam_sim:.4f}, "
          f"cross-family sim={cross_fam_sim:.4f}")

    # Test gradient flow — critical: verify all top-k ops get gradient
    import mlx.nn as nn_mod

    class TestModel(nn_mod.Module):
        def __init__(self):
            super().__init__()
            self.dispatch = KernelDispatch(d_model, n_ops=22, d_ff=1536, top_k=2)
            self.integrate = KernelIntegrate(d_model, n_types=5, d_ff=2048)

        def __call__(self, x):
            h = self.dispatch(x)
            h = self.integrate(h)
            return mx.mean(h)

    tm = TestModel()
    mx.eval(tm.parameters())

    def test_loss(tm, x):
        return tm(x)

    gfn = nn_mod.value_and_grad(tm, test_loss)
    x = mx.random.normal((1, 16, d_model))
    lv, g = gfn(tm, x)
    mx.eval(lv, g)

    # Check that op_embeddings gradient has nonzero entries for multiple ops
    op_grad = g["dispatch"]["op_embeddings"]
    mx.eval(op_grad)
    og_np = np.array(op_grad)
    grad_norms = np.linalg.norm(og_np, axis=1)
    n_with_grad = np.sum(grad_norms > 1e-6)
    print(f"  Gradient flow OK: loss={lv.item():.4f}")
    print(f"  Ops with gradient: {n_with_grad}/22 "
          f"(top-k=2 should give ≥2) ✓")

    print("\nkernel_dispatch.py self-test: all ok ✓")
