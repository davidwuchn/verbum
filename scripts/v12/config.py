"""
v12 Configuration — KIBC + M (retrieval) dual-layer architecture.

V12 adds the M (match/retrieval) kernel as a *layer type*, not a 5th
combinator in the KIBC dispatch softmax. The insight from session 095:
Qwen3.6-35B-A3B accidentally separates composition (full attention at
every 4th layer) from retrieval (GatedDeltaNet between). The induction
circuit (J=0.176 with everything else) lives exclusively in the linear
attention layers — it's mechanistically independent.

V12 makes this separation intentional:
  - Composition layers: StrideStack (windowed attention) — KIBC lives here
  - Retrieval layers: GatedLinearAttention — M lives here
  - HybridStrideStack: interleaves both, configurable per stride

Design principle — SEPARATION ENABLES HOLOGRAPHY (session 096):
  Cross-architecture analysis (Pythia, Qwen3, SmolLM3, 7 models) proved:
    - MLP/FFN: universally holographic (score 0.97, CV 0.025)
    - Attention output: universally holographic (score 0.94, CV 0.020)
    - Separate Q/K/V: holographic (score 0.92, Qwen3/SmolLM3)
    - Fused QKV: magnitude-dependent (score 0.60, Pythia)
  Multiplexing functions into shared weights forces magnitudes to act
  as "lenses" steering beams between subspaces. Separation lets each
  weight encode one function as pure sign topology.
  → V12: every projection is separate. Every weight has one job.

Architecture:
  Ascending arm: HybridStrideStack (interleaved composition + retrieval)
  Descending arm: KIBC combinator dispatch + retrieval register access
  7 passes: L0↑ → L1↑ → L2↑ → L3_apex → L2↓ → L1↓ → L0↓
  Output: tied embedding projection → next-token prediction

Carries forward from v11:
  - KIBC combinator basis (4-way softmax, not 5)
  - VSM hierarchy (S1-S5, algedonic, CycleContinue)
  - Holographic loss (progressive intermediate decoding)
  - Abstraction slots (S4→S5 proposals)
  - Fractal stride bands (MERA topology)

License: MIT
"""

from dataclasses import dataclass, field

from kernel import N_COMBINATORS


@dataclass
class V12Config:
    """v12 model + training configuration."""

    # ── Tokenizer (Qwen3 BBPE) ──
    vocab_size: int = 151936     # Qwen3 BBPE vocab
    eod_id: int = 151643        # end-of-document token

    # ── Core dimensions ──
    d_model: int = 512            # representation dimension
    d_ff: int = 1536              # FFN width (3× d_model)
    d_register: int = 128         # register dimension (real dim = 2×)
    n_heads: int = 8              # attention heads (d_head = 64)
    window: int = 8               # attention window width
    alpha: float = 1.18           # spiral bias coefficient

    # 9 strides: the full scale hierarchy proven in v6
    strides: tuple[int, ...] = (1, 8, 16, 32, 64, 128, 256, 512, 1024)

    # Register semantics:
    #   reg 0 = combinator (K/I/B/C identity)
    #   reg 1 = binding_depth (how many lambdas deep)
    #   reg 2 = phase (recognize / identify / resolve / produce)
    n_registers: int = 3

    # ── Retrieval (M kernel) — GatedLinearAttention ──
    # d_state: dimension of the running memory matrix per head.
    # The GLA memory is (n_heads, d_head, d_state) — keys project
    # to d_state, values to d_head. Total memory = n_heads × d_head × d_state.
    # At d_state=64 with 8 heads and d_head=64: 8×64×64 = 32K params of state.
    d_state: int = 64

    # Which strides use retrieval (GLA) vs composition (attention).
    # Tuple of booleans, one per stride. True = retrieval layer.
    # Default: small strides (local patterns) use composition,
    # medium strides use retrieval (pattern matching across phrases),
    # large strides use composition (structural composition).
    #
    # Inspired by Qwen3.6 layout: GatedDeltaNet at 3/4 of layers,
    # full attention at every 4th. We're more conservative — 3 of 9
    # strides are retrieval, focusing on the phrase/sentence scales
    # where induction patterns live empirically.
    #
    # stride:    1     8    16    32    64   128   256   512  1024
    # type:     comp  comp  ret   ret   ret  comp  comp  comp comp
    stride_is_retrieval: tuple[bool, ...] = (
        False, False, True, True, True, False, False, False, False,
    )

    # Retrieval registers: M writes pattern match results here.
    # The descending arm reads them alongside existing registers.
    # n_retrieval_registers: how many retrieval slots M can write to.
    n_retrieval_registers: int = 2

    # ── Beam mirrors (ternary angular deflectors before Q projections) ──
    use_q_mirrors: bool = True    # enable ternary mirrors before Q projections
    n_q_mirrors: int = 1          # mirrors per attention layer (cascade for finer angles)

    # ── Combinator dispatch ──
    n_combinators: int = N_COMBINATORS  # 4: K, I, B, C (M is NOT here)

    # Total number of passes — mirrors per-pass beam angle differentiation
    n_passes: int = 7

    # NOTE: max_cycles removed permanently. Architecture is max_cycles=1:
    # 7 passes × 1 dispatch→stride→integrate = 7 kernel ops total.
    # Each pass has its own mirror = unique beam angle = unique variety.
    # Adding cycles (same mirror twice) adds depth without variety — redundant
    # when passes already provide sequential refinement at different angles.
    # If more depth is needed: add passes (more mirrors), not cycles.

    # Descending arm stride direction: coarse→fine (TST-aligned)
    desc_stride_reverse: bool = True

    # Fractal stride bands (MERA topology)
    # v12: 7 passes (3 asc + apex + 3 desc) — symmetric hourglass.
    # Each level handles a narrow stride band. Adjacent levels share
    # 1-2 strides for inter-level communication.
    #
    # stride indices: 0=s1, 1=s8, 2=s16, 3=s32, 4=s64, 5=s128, 6=s256, 7=s512, 8=s1024
    #
    # L0↑ (fine):     [0,1,2]     → s1,s8,s16           fine→coarse
    # L1↑ (medium):   [1,2,3,4]   → s8,s16,s32,s64      fine→coarse
    # L2↑ (coarse):   [3,4,5,6]   → s32,s64,s128,s256   fine→coarse
    # L3  (apex):     [5,6,7,8]   → s128,s256,s512,s1024 fine→coarse
    # L2↓ (coarse):   [3,4,5,6]   → s256,s128,s64,s32   coarse→fine
    # L1↓ (medium):   [1,2,3,4]   → s64,s32,s16,s8      coarse→fine
    # L0↓ (fine):     [0,1,2]     → s16,s8,s1           coarse→fine
    fractal_stride_bands: bool = True
    stride_band_ranges: tuple[tuple[int, int], ...] = (
        (0, 3),   # L0↑: indices 0-2 → s1,s8,s16
        (1, 5),   # L1↑: indices 1-4 → s8,s16,s32,s64
        (3, 7),   # L2↑: indices 3-6 → s32,s64,s128,s256
        (5, 9),   # L3:  indices 5-8 → s128,s256,s512,s1024
        (3, 7),   # L2↓: indices 3-6 → s32..s256 (reversed by desc_stride_reverse)
        (1, 5),   # L1↓: indices 1-4 → s8..s64 (reversed by desc_stride_reverse)
        (0, 3),   # L0↓: indices 0-2 → s1..s16 (reversed by desc_stride_reverse)
    )

    # ── Abstraction slots (S4→S5 composed abstractions) ──
    n_abstraction_slots: int = 16
    abstraction_diversity_lambda: float = 0.01
    abstraction_copy_lambda: float = 0.01
    abstraction_copy_threshold: float = 0.7
    abstraction_diversity_threshold: float = 0.5
    abstraction_dead_recycle_steps: int = 2000
    abstraction_proposal_threshold_init: float = 1.0

    # ── Holographic loss (progressive intermediate decoding) ──
    holo_lambda: float = 0.0
    holo_warmup_steps: int = 0
    holo_ramp_steps: int = 0

    # ── Dispatch ratio prior (empirical universal ratio) ──
    # Base KIBC: K:I:B:C ≈ 1:0.5:1:1 measured across 9 models, 2 architectures.
    # Extended DYWH: D:Y:W:WHNF ≈ 0.5:0.3:0.3:0.2 (rarer operations, lower prior).
    # Applied as log(ratio/Σratio) additive bias in logit space.
    # When logits are zero (no opinion), dispatch defaults to this ratio.
    # The model can still deviate, but must overcome the prior to do so.
    dispatch_ratio: tuple[float, ...] = (
        1.0, 0.5, 1.0, 1.0,   # K, I, B, C (base)
        0.5, 0.3, 0.3, 0.2,   # D, Y, W, WHNF (extended, rarer)
    )

    # ── Dispatch entropy regularization (v12 variety fix) ──
    # Penalizes dispatch collapse: squared hinge on entropy below target.
    # Target = entropy of the ratio prior (not uniform).
    # With 8-way ratio (1, 0.5, 1, 1, 0.5, 0.3, 0.3, 0.2):
    # Σ = 4.8, probs ≈ (0.208, 0.104, 0.208, 0.208, 0.104, 0.063, 0.063, 0.042)
    # H = -Σ p·ln(p) ≈ 1.93. At 85%: 1.93 * 0.85 ≈ 1.64.
    # Session 117: raised from 0.01 (negligible: 0.003 vs CE~7.5) to 0.5.
    # At λ=0.5: moderate collapse (H=0.8) → deficit=0.84 → penalty=0.35 (5% of CE).
    # This is secondary to KL (primary anti-collapse) — catches edge cases
    # where dispatch concentrates on prior-consistent subset.
    dispatch_entropy_lambda: float = 0.5
    dispatch_entropy_target: float = 1.64   # H(ratio_prior) * 0.85

    # ── Per-pass dispatch bias (depth-selective KIBC prior) ──
    # From lambda kernel probes (session 106): operations peak at different depths.
    # B_compose peaks at L0 (33×), K_select at L20 (51×), M_match at L30 (145×).
    # Each pass gets a fixed additive logit bias derived from the cross-model
    # agreed depth profile. Combines with ratio prior in logit space:
    #   dispatch_logits = raw + ratio_prior + pass_bias[pass_idx]
    # Values are fixed constants (not learned) — cross-model agreement validates them.
    # Extended to 8 ops: D peaks where B peaks (deep-compose is composition),
    # Y at mid-depth (recursion detection), W near I (duplication ≈ identity),
    # WHNF at deep passes (terminal detection requires semantic understanding).
    #                            K     I     B     C     D     Y     W    WHNF
    pass_dispatch_bias: tuple[tuple[float, ...], ...] = (
        (-1.0, -1.0, +2.0, +0.5, +1.5, -1.0, -0.5, -1.5),  # Pass 0 (L0↑): B/D dominate
        (+0.0, +0.0, +0.5, +0.5, +0.5, +0.0, +0.0, -1.0),  # Pass 1 (L1↑): balanced
        (+1.0, +0.5, +0.0, +0.5, +0.0, +1.0, +0.0, +0.0),  # Pass 2 (L2↑): K/I/Y emerging
        (+2.0, +1.5, -0.5, +0.0, -0.5, +1.5, +0.5, +1.0),  # Pass 3 (apex): K/I/Y/WHNF
        (+1.5, +1.0, -0.5, +0.0, -0.5, +1.0, +0.5, +1.0),  # Pass 4 (L2↓): K/I reading
        (+0.5, +0.5, +0.0, +1.0, +0.0, +0.0, +0.5, +0.0),  # Pass 5 (L1↓): C/W reorder
        (-0.5, +0.0, +1.5, +0.5, +1.0, -0.5, +0.0, -1.0),  # Pass 6 (L0↓): B/D compose
    )

    # ── KL divergence toward empirical ratio (hard constraint) ──
    # We know an optimal solution uses this ratio. Find it.
    # K:I:B:C = 1:0.5:1:1 — measured across 9 models, 2 architectures.
    # λ=100: only tiny deviations are free. The model discards the
    # massive space of solutions that don't respect the ratio and
    # KL computed on LIVE dispatch (differentiable) against the static prior.
    # Session 117 fix: previously computed on stop_gradient(EMA) → zero gradient.
    # Recalibrated from λ=100 (dead) to λ=2 (live):
    #   B→30%   (±10pt drift): 0.3%CE — free exploration
    #   B→40%   (big drift):   1.2%CE — gentle pushback
    #   WHNF=30% (early collapse): 10%CE — visible wall
    #   WHNF=50% (deep collapse):  31%CE — strong wall
    dispatch_kl_lambda: float = 2.0

    # ── EMA-smoothed dispatch (monitoring only) ──
    # EMA tracks dispatch distribution for logging/diagnostics (~30 step memory).
    # KL loss now uses live dispatch directly; EMA is not in the gradient path.
    dispatch_kl_ema_decay: float = 0.967  # ~30 steps of effective memory

    # ── Crystal lattice geometry loss ──
    # Session 117: replaced probe-based backbone whisper with constant lattice.
    # 8×8 combinator embedding cosines → MSE against universal crystal targets.
    # Precomputed from cross-model RDM (session 106, 380 probes, 20 axes).
    # No probe forwarding — pure embedding geometry, every step.
    use_relational_loss: bool = True
    rel_lambda: float = 0.01
    rel_target_path: str = "results/holographic-extraction/lambda_kernel_verified_dimensions.json"

    # ── Hierarchical dispatch (category → operation) ──
    # Level 1: which CATEGORY of kernel? (3-way: lambda, math, passthrough)
    # Level 2a: which COMBINATOR? (8-way, existing dispatch)
    # Level 2b: which MATH kernel? (17-way)
    # Passthrough = no kernel, normal next-token prediction via residual.
    n_categories: int = 3              # lambda, math, passthrough
    n_math_kernels: int = 17           # from math_kernels.py registry
    math_extractor_d: int = 64         # extraction head hidden dim
    category_gate_init: float = -3.0   # sigmoid(-3)≈0.05 — math starts nearly off
    use_math_kernels: bool = True      # enable math kernel pathway

    # Dropout
    dropout: float = 0.1

    # ── Training ──
    batch_size: int = 2
    grad_accum: int = 4
    total_steps: int = 20000
    lr: float = 6e-4
    lr_floor_ratio: float = 0.01
    warmup_steps: int = 500
    weight_decay: float = 0.01
    grad_clip: float = 1.0

    # ── Evolution (legacy — disabled when etching is active) ──
    gen_interval: int = 50
    base_pct: float = 0.0002
    sign_flip_rate: float = 0.2
    guided_fraction: float = 0.7
    mutation_adam_decay: float = 0.1
    s4_boost: float = 3.0
    evolution_min_delta: float = 0.02
    evolution_alarm_min_delta: float = 0.02
    use_evolution: bool = False  # disabled by default, etching replaces it

    # ── Etching (gradient-directed ternary topology shaping) ──
    # The laser etcher: gradient heat accumulates in signal planes,
    # consensus across planes triggers sign flips in the weight topology.
    #
    # Signal planes (3 per TernaryLinear, same packed uint32 format):
    #   Plane 1 (weak):   votes from positions with heat > p_weak
    #   Plane 2 (medium): votes from positions with heat > p_medium
    #   Plane 3 (strong): votes from positions with heat > p_strong
    #
    # Etch condition: all etch_consensus planes agree on direction
    #   AND that direction disagrees with current weight sign → flip.
    use_etching: bool = True
    etch_signal_interval: int = 1     # steps between signal plane updates
    etch_interval: int = 2            # steps between etch checks
    etch_warmup: int = 200            # steps before etching begins (signal planes need history)
    etch_heat_alpha: float = 0.99     # EMA decay for heat accumulation
    etch_heat_thresholds: tuple[float, ...] = (50.0, 75.0, 90.0)  # percentiles for planes
    etch_consensus: int = 3           # planes that must agree (2 or 3)
    etch_adam_decay: float = 0.1      # Adam state decay for etched gamma rows
    etch_max_flips_per_event: int = 200    # laser precision: only highest-consensus flips
    etch_reset_after_flip: bool = True     # reset accumulators after etch

    # ── Depth-selective etch thresholds ──
    # Shallow passes etch more freely (structural templates evolve fast).
    # Deep passes need more consensus (semantic content is high-value).
    # Multiplier scales the heat percentile thresholds per pass.
    # At 0.5×: half the consensus needed. At 1.0×: full consensus.
    pass_etch_multiplier: tuple[float, ...] = (
        0.5,   # Pass 0 (L0↑): etch freely — structural templates
        0.7,   # Pass 1 (L1↑): moderate
        1.0,   # Pass 2 (L2↑): standard
        1.0,   # Pass 3 (apex): standard
        1.0,   # Pass 4 (L2↓): standard
        0.8,   # Pass 5 (L1↓): moderate
        0.6,   # Pass 6 (L0↓): etch freely — final composition
    )
    # NOTE: etch_max_pct and etch_max_pct_ramp are REMOVED.
    # Consensus mechanism (+ etch_max_flips_per_event ceiling) governs flip rate.
    # Self-terminating: early=aggressive (many wrong signs), late=quiet (signs aligned).

    # ── Checkpointing ──
    checkpoint_interval: int = 500
    eval_interval: int = 500
    log_interval: int = 25
    checkpoint_dir: str = "checkpoints/v12"

    # ── Data ──
    data_dir: str = "/Users/mwhitford/data/fractal-bitnet/shards-qwen3"
    structured_shard: str = "data/structured_shard.npy"
    mix_ratio: float = 0.0
    seq_len: int = 4096
    max_seq_len: int = 4096
    n_train_shards: int = 54
    n_eval_shards: int = 6

    @property
    def d_head(self) -> int:
        return self.d_model // self.n_heads

    @property
    def n_strides(self) -> int:
        return len(self.strides)

    @property
    def n_composition_strides(self) -> int:
        return sum(1 for r in self.stride_is_retrieval if not r)

    @property
    def n_retrieval_strides(self) -> int:
        return sum(1 for r in self.stride_is_retrieval if r)

    @property
    def tokens_per_step(self) -> int:
        return self.batch_size * self.grad_accum * self.seq_len

    def __post_init__(self):
        assert self.d_model % self.n_heads == 0
        assert self.d_model % 16 == 0, "d_model must be divisible by 16 (ternary packing)"
        assert self.d_model % 4 == 0, "d_model must be divisible by 4 (embedding packing)"
        assert len(self.stride_is_retrieval) == len(self.strides), \
            f"stride_is_retrieval length ({len(self.stride_is_retrieval)}) must match strides ({len(self.strides)})"
        assert self.d_state % 16 == 0, "d_state must be divisible by 16 (ternary packing)"
