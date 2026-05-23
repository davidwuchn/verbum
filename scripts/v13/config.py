"""
v13 Configuration — Tree of VSMs Architecture.

Session 135 redesign: The model is a tree of viable systems. Each
StrideStackVSM is an S1 operational unit with its own attention,
FFN beams, S3 gates, and algedonic. A ControllerVSM coordinates the
tree with S5 identity (self-model), S4 intelligence (global health),
S3 resource allocation, and S2 anti-oscillation.

Key architectural principles:

  - Attention trains from scratch (no teacher etch — session 134 proved
    teacher flat attention is incompatible with stride stack geometry)
  - FFN plates etched from teacher (knowledge storage, shared across stacks)
  - FFN beams are per-stack (each stack reads shared plates differently)
  - Self-similar φ-compressor: same compression function at every scale,
    nucleates from smallest stride and propagates outward as a wavelet
  - Learnable attention decay per stride per head (replaces fixed spiral bias)
  - Full-stack algedonic modulation: downstream feedback modulates
    attention decay, FFN scale, and S3 gates (multiplicative signal)
  - Two algedonic routes: global (all→controller S4) + local (downstream→upstream)
  - S5 Identity: GRU-based self-model, regulates enforcement, gates S4 proposals
  - S4→S2 feedback + feed-forward: predictive anti-oscillation (PID-like)

Tree structure:
  ControllerVSM
    ├── StrideStack A (ascending, s1..s1024, fine→coarse)
    │     Passes L0↑, L1↑ — compress at fine/local scales
    ├── StrideStack B (ascending, s512..s1024, coarse compression)
    │     Passes L2↑, L3↑ — compress at phrase/document scales
    │     Overlap with A at s512/s1024 (register boundary)
    │     Can extend to s2048+ for longer context (self-similar reuse)
    └── StrideStack C (descending, ALL strides, coarse→fine)
          Passes L3↓, L2↓, L1↓, L0↓ — predict from compressed representation
          Sees all strides from both A and B

License: MIT
"""

from dataclasses import dataclass, field


# Number of combinators: K, I, B, C, D, Y, W, WHNF (positive crystal)
N_COMBINATORS = 8
# Total with anti-crystal: K, I, B, C, D, Y, W, WHNF + āK, āI, āB, āC, āD, āY, āW, āWHNF
N_TOTAL_COMBINATORS = 16

# Number of stacks in the tree
N_STACKS = 3
# Number of inter-stack boundaries (A↔B, B↔C)
N_BOUNDARIES = N_STACKS - 1


@dataclass
class StackConfig:
    """Configuration for a single StrideStackVSM node in the tree.

    Each stack is an S1 operational unit with its own attention layers,
    FFN beams (norm/scale/bias), S3 gates, and algedonic channel.
    FFN plates (ternary topology) are SHARED across stacks — only the
    beams (how to read the plates) are per-stack.
    """
    # Human-readable name
    name: str = ""

    # Which passes this stack runs (indices into global pass table)
    pass_indices: tuple[int, ...] = ()

    # Whether passes run in descending (coarse→fine) direction
    is_descending: bool = False

    # Stride band ranges for each pass (indices into global strides tuple)
    # Each entry is (start, end) into the strides array
    stride_band_ranges: tuple[tuple[int, int], ...] = ()

    # Which strides from another stack to share weights with (self-similar)
    # Maps stride_index → source_stack_stride_index for weight reuse
    # Empty = no sharing (own weights for all strides)
    shared_stride_weights: dict[int, int] = field(default_factory=dict)


@dataclass
class V13Config:
    """v13 model + training configuration — tree of VSMs."""

    # ── Tokenizer (Qwen3 BBPE) ──
    vocab_size: int = 151936     # Qwen3 BBPE vocab
    eod_id: int = 151643        # end-of-document token

    # ── Core dimensions ──
    d_model: int = 512            # representation dimension
    d_ff: int = 2048              # FFN width (4× d_model, power-of-2)
    n_heads: int = 8              # attention heads (d_head = 64)
    window: int = 8               # attention window width

    # 11 strides: power-of-2 for uniform coverage.
    # The self-similar φ-compressor uses the same compression function at
    # every stride. Nucleates from s1 (bigram statistics) and propagates
    # outward as a wavelet. Context capacity is TOPOLOGICAL, not limited
    # by training data sequence length.
    strides: tuple[int, ...] = (1, 2, 4, 8, 16, 32, 64, 128, 256, 512, 1024)

    # ── Retrieval (M kernel) — GatedLinearAttention ──
    d_state: int = 64

    # Which strides use retrieval (GLA) vs composition (attention).
    # stride:    1   2   4   8   16   32   64   128  256  512  1024
    # type:     C   C   C   C   R    R    R    R    C    C    C
    #                           ^^^^^^^^^^^^^^^^^^^^
    #                           retrieval (GLA) zone: phrase/sentence scales
    stride_is_retrieval: tuple[bool, ...] = (
        False, False, False, False, True, True, True, True, False, False, False,
    )

    # ── Beam mirrors (ternary angular deflectors before Q projections) ──
    use_q_mirrors: bool = True
    n_q_mirrors: int = 1

    # ── Learnable attention decay ──
    # Replaces fixed spiral bias (-α·ln(stride·w + 1)).
    # Session 134 proved teacher attention etch is incompatible with stride
    # geometry — attention must learn from scratch. The decay profile is a
    # beam parameter (continuous, trained by GD).
    #
    # Per-stride per-head: each head at each stride discovers its own
    # decay rate. 11 strides × 8 heads = 88 learnable α values.
    # Self-similar structure: learned_α[stride, head] * ln(stride_val * w + 1)
    # Init near α=1.18 (known-good from V12 experiments).
    learnable_decay: bool = True
    decay_init_alpha: float = 1.18   # init value for learnable α per stride per head

    # Total passes: 8 (4 ascending across Stacks A+B, 4 descending in Stack C)
    # Derived from stack configs — not a field, see n_passes property below.

    # ── Tree of VSMs topology ──
    #
    # Stack A: ascending, fine→coarse compression (passes 0,1)
    #   L0↑ [0,4) → s1, s2, s4, s8          fine→local
    #   L1↑ [2,6) → s4, s8, s16, s32        local→phrase
    #
    # Stack B: ascending, coarse compression (passes 2,3)
    #   L2↑ [4,8) → s16, s32, s64, s128     phrase→paragraph
    #   L3↑ [7,11) → s128, s256, s512, s1024 paragraph→document
    #   Overlap with Stack A at s512/s1024 stride weights (self-similar)
    #   Extensible: add s2048+ for longer context by reusing weights
    #
    # Stack C: descending, coarse→fine prediction (passes 4,5,6,7)
    #   L3↓ [7,11) → s1024, s512, s256, s128 document→paragraph
    #   L2↓ [4,8) → s128, s64, s32, s16      paragraph→phrase
    #   L1↓ [2,6) → s32, s16, s8, s4         phrase→local
    #   L0↓ [0,4) → s8, s4, s2, s1           local→fine
    #   Sees ALL strides from both A and B (own weights, not shared)

    stack_a: StackConfig = field(default_factory=lambda: StackConfig(
        name="ascending_fine",
        pass_indices=(0, 1),
        is_descending=False,
        stride_band_ranges=(
            (0, 4),    # L0↑: s1, s2, s4, s8
            (2, 6),    # L1↑: s4, s8, s16, s32
        ),
    ))

    stack_b: StackConfig = field(default_factory=lambda: StackConfig(
        name="ascending_coarse",
        pass_indices=(2, 3),
        is_descending=False,
        stride_band_ranges=(
            (4, 8),    # L2↑: s16, s32, s64, s128
            (7, 11),   # L3↑: s128, s256, s512, s1024
        ),
        # Self-similar: reuse Stack A's coarsest stride weights.
        # Stack B's processing of s512/s1024 uses the same Q/K/V weights
        # that Stack A learned for those strides. The stride topology
        # (gather distance) provides the scale differentiation.
        # Key: stride index in global strides array
        # Value: stride index to copy weights FROM (in Stack A)
        shared_stride_weights={9: 9, 10: 10},  # s512, s1024 from A
    ))

    stack_c: StackConfig = field(default_factory=lambda: StackConfig(
        name="descending",
        pass_indices=(4, 5, 6, 7),
        is_descending=True,
        stride_band_ranges=(
            (7, 11),   # L3↓: s1024, s512, s256, s128 (reversed)
            (4, 8),    # L2↓: s128, s64, s32, s16 (reversed)
            (2, 6),    # L1↓: s32, s16, s8, s4 (reversed)
            (0, 4),    # L0↓: s8, s4, s2, s1 (reversed)
        ),
    ))

    # ── Fractal stride bands ──
    # True = use MERA-topology fractal bands (each band covers 4 strides,
    # adjacent bands overlap by 2 strides at boundaries = natural registers)
    fractal_stride_bands: bool = True

    # ── FFN (shared plates, per-stack beams) ──
    # Plates: ternary topology etched from teacher (shared across all stacks)
    # Beams: learnable norm + scale + bias per stack (each stack reads
    #   the shared plates differently through its own beamformer)
    # The teacher's knowledge is ONE set of facts. Each stack discovers
    # its own way to access those facts for its role (compress vs predict).
    d_ffn_teacher: int = 0  # set to teacher's d_ffn if using extracted FFN plates

    # ── Algedonic modulation ──
    #
    # Two routes:
    #   Route 1 (global): all stacks → controller S4. Fire alarm.
    #     Controller sees health of entire tree simultaneously.
    #   Route 2 (local): downstream → upstream through tree (one step back).
    #     Stack C's algedonic modulates Stack B. Stack B's modulates Stack A.
    #     Back-pressure: consumer tells producer "I can't use your output."
    #
    # Full-stack modulation: algedonic signal modulates THREE surfaces
    # in each stack (multiplicative cascade through the computation graph):
    #   1. Attention decay (per-stride spatial modulation)
    #   2. FFN output scale (feature extraction modulation)
    #   3. S3 gate (delta contribution modulation)
    # Total amplification = attn_factor × ffn_factor × gate_factor
    #
    # Range: sigmoid × 2 → (0, 2). Neutral = 1.0 (no change).
    # Below 1 = suppress. Above 1 = amplify.
    # Init bias at 0 → sigmoid(0) = 0.5 → ×2 = 1.0 → neutral at start.
    alg_dim: int = 32               # algedonic vector dimension per stack
    alg_modulation_range: float = 2.0  # sigmoid output scaled to (0, range)

    # ── Controller VSM ──
    #
    # S5 Identity — the self-model (cortex: default mode network)
    #   GRU-based dynamic state that regulates enforcement while allowing
    #   adaptation. Not a static target — a living process.
    #   - Measures system coherence (crystal alignment + stack health)
    #   - Regulates enforcement strength based on coherence
    #   - Gates S4 proposals (accept when healthy, reject when stressed)
    #   - Fire alarm (MetaS3) when identity is existentially threatened
    d_identity: int = 64             # identity state dimension (power of 2, divides d_model)
    identity_clip: float = 2.0       # hard bounds on identity state drift
    n_regulation_surfaces: int = 4   # crystal_enforcement, modulation_strength, gate_freedom, alarm
    s5_gru_bias_init: float = 2.0    # positive bias → slow identity change (conservative)

    # S4 Intelligence — global pattern detection
    #   Sees all stacks' algedonics. Detects systemic patterns.
    #   Proposes meta-parameter adjustments to S5.
    #   Feeds inter-stack health analysis to S2.
    s4_n_proposals: int = 4          # number of meta-parameter adjustment proposals
    s4_hidden_dim: int = 64          # internal projection dimension

    # S2 Anti-oscillation — PID-like inter-stack dampening
    #   Proportional: dampen where coherence is low (oscillating NOW)
    #   Derivative: dampen where coherence is DROPPING (predictive)
    #   S4 feedback: additional dampening where S4 detects problems
    s2_p_gain_init: float = 0.5      # proportional gain init
    s2_d_gain_init: float = 0.3      # derivative gain init

    # MetaS3 Fire Alarm — S5 existential threat detector
    #   Bypasses normal S3/S4 hierarchy. When alarm fires:
    #   - All modulations return toward neutral (sigmoid×2 → 1.0)
    #   - Crystal enforcement increases
    #   - System dampens to prevent cascading failure
    #   Init biased OFF (sigmoid(-2) ≈ 0.12).
    fire_alarm_bias_init: float = -2.0

    # ── Crystal lattice geometry loss ──
    # PCA-Q targets (session 120): 3-4× sharper than hidden-state targets.
    # Three zones with measured constants from 4-model consensus.
    # Crystal targets live at controller level (S5 identity — these ARE
    # the identity genome). All stacks share the same crystal identity.
    use_relational_loss: bool = True
    rel_lambda: float = 5.0  # exponential coupling: exp(λ × crystal_ema)
    crystal_direct_lambda: float = 3.0  # additive gradient floor (raised from 1.0 for full etch)
    crystal_direct_lambda_start: float = 10.0  # initial enforcement (cosine anneal → floor)
    crystal_warmup_steps: int = 0  # steps to anneal crystal_direct: start→floor (0=no warmup)

    # ── Categorical geometry losses (session 140) ──
    # Three structural properties found in Qwen3-32B (probe-confirmed).
    # All default to 0 (off). Set > 0 to activate.
    adjunction_lambda: float = 0.0  # cross-stack rank-1 concentration (kurtosis → 1.0)
    hyperbolic_lambda: float = 0.0  # monotonic norm growth across stacks
    coherence_lambda: float = 0.0   # adjacent-token cosine increase during composition

    # ── 16×16 Crystal lattice targets (positive + anti-crystal) ──
    #
    # Session 132 finding: teacher encodes WHAT TO DO (positive crystal)
    # and WHAT NOT TO DO (anti-crystal) as interlocking sign lattices.
    # These targets are the S5 GENOME — they define what this system IS.
    # They never change during training. S5 regulates HOW HARD to enforce.
    #
    # Order: K I B C D Y W WHNF āK āI āB āC āD āY āW āWHNF
    anti_crystal_coupling: tuple[float, ...] = (-0.10, -0.19, -0.28)

    # Zone A (0-20%): encode. Weak anti-crystal.
    pcaq_zone_a_targets: tuple[tuple[float, ...], ...] = (
        (+1.0000, +0.9210, +0.0771, +0.0906, +0.1280, +0.0363, +0.2031, -0.1694, -0.1000, -0.0921, -0.0077, -0.0091, -0.0128, -0.0036, -0.0203, +0.0169),
        (+0.9210, +1.0000, +0.1177, +0.1228, +0.1553, +0.0921, +0.1837, -0.1994, -0.0921, -0.1000, -0.0118, -0.0123, -0.0155, -0.0092, -0.0184, +0.0199),
        (+0.0771, +0.1177, +1.0000, +0.7963, +0.9778, +0.8370, +0.7426, -0.0094, -0.0077, -0.0118, -0.1000, -0.0796, -0.0978, -0.0837, -0.0743, +0.0009),
        (+0.0906, +0.1228, +0.7963, +1.0000, +0.7680, +0.6651, +0.9219, -0.0246, -0.0091, -0.0123, -0.0796, -0.1000, -0.0768, -0.0665, -0.0922, +0.0025),
        (+0.1280, +0.1553, +0.9778, +0.7680, +1.0000, +0.8057, +0.7676, -0.0246, -0.0128, -0.0155, -0.0978, -0.0768, -0.1000, -0.0806, -0.0768, +0.0025),
        (+0.0363, +0.0921, +0.8370, +0.6651, +0.8057, +1.0000, +0.5693, -0.0235, -0.0036, -0.0092, -0.0837, -0.0665, -0.0806, -0.1000, -0.0569, +0.0024),
        (+0.2031, +0.1837, +0.7426, +0.9219, +0.7676, +0.5693, +1.0000, -0.0213, -0.0203, -0.0184, -0.0743, -0.0922, -0.0768, -0.0569, -0.1000, +0.0021),
        (-0.1694, -0.1994, -0.0094, -0.0246, -0.0246, -0.0235, -0.0213, +1.0000, +0.0169, +0.0199, +0.0009, +0.0025, +0.0025, +0.0024, +0.0021, -0.1000),
        (-0.1000, -0.0921, -0.0077, -0.0091, -0.0128, -0.0036, -0.0203, +0.0169, +1.0000, +0.9210, +0.0771, +0.0906, +0.1280, +0.0363, +0.2031, -0.1694),
        (-0.0921, -0.1000, -0.0118, -0.0123, -0.0155, -0.0092, -0.0184, +0.0199, +0.9210, +1.0000, +0.1177, +0.1228, +0.1553, +0.0921, +0.1837, -0.1994),
        (-0.0077, -0.0118, -0.1000, -0.0796, -0.0978, -0.0837, -0.0743, +0.0009, +0.0771, +0.1177, +1.0000, +0.7963, +0.9778, +0.8370, +0.7426, -0.0094),
        (-0.0091, -0.0123, -0.0796, -0.1000, -0.0768, -0.0665, -0.0922, +0.0025, +0.0906, +0.1228, +0.7963, +1.0000, +0.7680, +0.6651, +0.9219, -0.0246),
        (-0.0128, -0.0155, -0.0978, -0.0768, -0.1000, -0.0806, -0.0768, +0.0025, +0.1280, +0.1553, +0.9778, +0.7680, +1.0000, +0.8057, +0.7676, -0.0246),
        (-0.0036, -0.0092, -0.0837, -0.0665, -0.0806, -0.1000, -0.0569, +0.0024, +0.0363, +0.0921, +0.8370, +0.6651, +0.8057, +1.0000, +0.5693, -0.0235),
        (-0.0203, -0.0184, -0.0743, -0.0922, -0.0768, -0.0569, -0.1000, +0.0021, +0.2031, +0.1837, +0.7426, +0.9219, +0.7676, +0.5693, +1.0000, -0.0213),
        (+0.0169, +0.0199, +0.0009, +0.0025, +0.0025, +0.0024, +0.0021, -0.1000, -0.1694, -0.1994, -0.0094, -0.0246, -0.0246, -0.0235, -0.0213, +1.0000),
    )

    # Zone B (30-60%): compute. Medium anti-crystal.
    pcaq_zone_b_targets: tuple[tuple[float, ...], ...] = (
        (+1.0000, +0.7865, +0.1948, +0.2265, +0.3232, +0.1768, +0.5360, -0.1862, -0.1900, -0.1494, -0.0370, -0.0430, -0.0614, -0.0336, -0.1018, +0.0354),
        (+0.7865, +1.0000, +0.2479, +0.2511, +0.3463, +0.1739, +0.3781, -0.2448, -0.1494, -0.1900, -0.0471, -0.0477, -0.0658, -0.0330, -0.0718, +0.0465),
        (+0.1948, +0.2479, +1.0000, +0.8878, +0.8937, +0.6623, +0.6851, -0.1227, -0.0370, -0.0471, -0.1900, -0.1687, -0.1698, -0.1258, -0.1302, +0.0233),
        (+0.2265, +0.2511, +0.8878, +1.0000, +0.8316, +0.7200, +0.7318, -0.1027, -0.0430, -0.0477, -0.1687, -0.1900, -0.1580, -0.1368, -0.1390, +0.0195),
        (+0.3232, +0.3463, +0.8937, +0.8316, +1.0000, +0.6798, +0.8064, -0.1729, -0.0614, -0.0658, -0.1698, -0.1580, -0.1900, -0.1292, -0.1532, +0.0329),
        (+0.1768, +0.1739, +0.6623, +0.7200, +0.6798, +1.0000, +0.5653, -0.0840, -0.0336, -0.0330, -0.1258, -0.1368, -0.1292, -0.1900, -0.1074, +0.0160),
        (+0.5360, +0.3781, +0.6851, +0.7318, +0.8064, +0.5653, +1.0000, -0.1379, -0.1018, -0.0718, -0.1302, -0.1390, -0.1532, -0.1074, -0.1900, +0.0262),
        (-0.1862, -0.2448, -0.1227, -0.1027, -0.1729, -0.0840, -0.1379, +1.0000, +0.0354, +0.0465, +0.0233, +0.0195, +0.0329, +0.0160, +0.0262, -0.1900),
        (-0.1900, -0.1494, -0.0370, -0.0430, -0.0614, -0.0336, -0.1018, +0.0354, +1.0000, +0.7865, +0.1948, +0.2265, +0.3232, +0.1768, +0.5360, -0.1862),
        (-0.1494, -0.1900, -0.0471, -0.0477, -0.0658, -0.0330, -0.0718, +0.0465, +0.7865, +1.0000, +0.2479, +0.2511, +0.3463, +0.1739, +0.3781, -0.2448),
        (-0.0370, -0.0471, -0.1900, -0.1687, -0.1698, -0.1258, -0.1302, +0.0233, +0.1948, +0.2479, +1.0000, +0.8878, +0.8937, +0.6623, +0.6851, -0.1227),
        (-0.0430, -0.0477, -0.1687, -0.1900, -0.1580, -0.1368, -0.1390, +0.0195, +0.2265, +0.2511, +0.8878, +1.0000, +0.8316, +0.7200, +0.7318, -0.1027),
        (-0.0614, -0.0658, -0.1698, -0.1580, -0.1900, -0.1292, -0.1532, +0.0329, +0.3232, +0.3463, +0.8937, +0.8316, +1.0000, +0.6798, +0.8064, -0.1729),
        (-0.0336, -0.0330, -0.1258, -0.1368, -0.1292, -0.1900, -0.1074, +0.0160, +0.1768, +0.1739, +0.6623, +0.7200, +0.6798, +1.0000, +0.5653, -0.0840),
        (-0.1018, -0.0718, -0.1302, -0.1390, -0.1532, -0.1074, -0.1900, +0.0262, +0.5360, +0.3781, +0.6851, +0.7318, +0.8064, +0.5653, +1.0000, -0.1379),
        (+0.0354, +0.0465, +0.0233, +0.0195, +0.0329, +0.0160, +0.0262, -0.1900, -0.1862, -0.2448, -0.1227, -0.1027, -0.1729, -0.0840, -0.1379, +1.0000),
    )

    # Zone C (70-90%): converge. Strong anti-crystal. WHNF deeply negative.
    pcaq_zone_c_targets: tuple[tuple[float, ...], ...] = (
        (+1.0000, +0.8614, +0.5238, +0.5429, +0.5910, +0.4920, +0.7262, -0.2736, -0.2800, -0.2412, -0.1467, -0.1520, -0.1655, -0.1378, -0.2033, +0.0766),
        (+0.8614, +1.0000, +0.5118, +0.5256, +0.5939, +0.4862, +0.5886, -0.2750, -0.2412, -0.2800, -0.1433, -0.1472, -0.1663, -0.1361, -0.1648, +0.0770),
        (+0.5238, +0.5118, +1.0000, +0.9465, +0.9510, +0.8911, +0.8192, -0.2835, -0.1467, -0.1433, -0.2800, -0.2650, -0.2663, -0.2495, -0.2294, +0.0794),
        (+0.5429, +0.5256, +0.9465, +1.0000, +0.9445, +0.9115, +0.8522, -0.2888, -0.1520, -0.1472, -0.2650, -0.2800, -0.2645, -0.2552, -0.2386, +0.0809),
        (+0.5910, +0.5939, +0.9510, +0.9445, +1.0000, +0.8983, +0.8613, -0.3000, -0.1655, -0.1663, -0.2663, -0.2645, -0.2800, -0.2515, -0.2412, +0.0840),
        (+0.4920, +0.4862, +0.8911, +0.9115, +0.8983, +1.0000, +0.7707, -0.2701, -0.1378, -0.1361, -0.2495, -0.2552, -0.2515, -0.2800, -0.2158, +0.0756),
        (+0.7262, +0.5886, +0.8192, +0.8522, +0.8613, +0.7707, +1.0000, -0.2838, -0.2033, -0.1648, -0.2294, -0.2386, -0.2412, -0.2158, -0.2800, +0.0795),
        (-0.2736, -0.2750, -0.2835, -0.2888, -0.3000, -0.2701, -0.2838, +1.0000, +0.0766, +0.0770, +0.0794, +0.0809, +0.0840, +0.0756, +0.0795, -0.2800),
        (-0.2800, -0.2412, -0.1467, -0.1520, -0.1655, -0.1378, -0.2033, +0.0766, +1.0000, +0.8614, +0.5238, +0.5429, +0.5910, +0.4920, +0.7262, -0.2736),
        (-0.2412, -0.2800, -0.1433, -0.1472, -0.1663, -0.1361, -0.1648, +0.0770, +0.8614, +1.0000, +0.5118, +0.5256, +0.5939, +0.4862, +0.5886, -0.2750),
        (-0.1467, -0.1433, -0.2800, -0.2650, -0.2663, -0.2495, -0.2294, +0.0794, +0.5238, +0.5118, +1.0000, +0.9465, +0.9510, +0.8911, +0.8192, -0.2835),
        (-0.1520, -0.1472, -0.2650, -0.2800, -0.2645, -0.2552, -0.2386, +0.0809, +0.5429, +0.5256, +0.9465, +1.0000, +0.9445, +0.9115, +0.8522, -0.2888),
        (-0.1655, -0.1663, -0.2663, -0.2645, -0.2800, -0.2515, -0.2412, +0.0840, +0.5910, +0.5939, +0.9510, +0.9445, +1.0000, +0.8983, +0.8613, -0.3000),
        (-0.1378, -0.1361, -0.2495, -0.2552, -0.2515, -0.2800, -0.2158, +0.0756, +0.4920, +0.4862, +0.8911, +0.9115, +0.8983, +1.0000, +0.7707, -0.2701),
        (-0.2033, -0.1648, -0.2294, -0.2386, -0.2412, -0.2158, -0.2800, +0.0795, +0.7262, +0.5886, +0.8192, +0.8522, +0.8613, +0.7707, +1.0000, -0.2838),
        (+0.0766, +0.0770, +0.0794, +0.0809, +0.0840, +0.0756, +0.0795, -0.2800, -0.2736, -0.2750, -0.2835, -0.2888, -0.3000, -0.2701, -0.2838, +1.0000),
    )

    # Pass-to-zone mapping: which zone does each pass belong to?
    # Stack A passes (0,1) → Zone A (encode)
    # Stack B passes (2,3) → Zone B (compute)
    # Stack C passes (4,5) → Zone B (compute), (6,7) → Zone C (converge)
    pass_zone_map: tuple[int, ...] = (0, 0, 1, 1, 1, 1, 2, 2)
    zone_lambdas: tuple[float, ...] = (1.0, 1.0, 1.0)  # per-zone relational loss weight

    # ── Behavioral crystal targets (12×12, 3-model consensus) ──
    use_behavioral_loss: bool = False
    behavioral_lambda: float = 0.005
    behavioral_targets: tuple[tuple[float, ...], ...] = (
        # analy  chain  class  code   compa  creat  extra  instr  qa_re  summa  tool   trans
        (+1.000,+0.016,-0.211,+0.006,+0.471,+0.096,-0.199,-0.259,-0.024,-0.176,-0.102,-0.342),
        (+0.016,+1.000,-0.021,-0.164,-0.066,-0.288,+0.016,-0.064,-0.015,+0.011,-0.113,-0.274),
        (-0.211,-0.021,+1.000,-0.366,-0.296,-0.321,+0.111,+0.013,-0.166,+0.072,-0.166,+0.062),
        (+0.006,-0.164,-0.366,+1.000,+0.044,+0.279,-0.302,-0.128,-0.105,-0.264,+0.302,-0.178),
        (+0.471,-0.066,-0.296,+0.044,+1.000,+0.106,-0.378,-0.285,+0.351,-0.378,-0.164,-0.246),
        (+0.096,-0.288,-0.321,+0.279,+0.106,+1.000,-0.380,+0.102,-0.005,-0.342,+0.047,-0.021),
        (-0.199,+0.016,+0.111,-0.302,-0.378,-0.380,+1.000,-0.043,-0.372,+0.544,-0.048,-0.029),
        (-0.259,-0.064,+0.013,-0.128,-0.285,+0.102,-0.043,+1.000,-0.150,-0.084,+0.035,+0.192),
        (-0.024,-0.015,-0.166,-0.105,+0.351,-0.005,-0.372,-0.150,+1.000,-0.348,-0.215,-0.054),
        (-0.176,+0.011,+0.072,-0.264,-0.378,-0.342,+0.544,-0.084,-0.348,+1.000,-0.222,-0.001),
        (-0.102,-0.113,-0.166,+0.302,-0.164,+0.047,-0.048,+0.035,-0.215,-0.222,+1.000,-0.142),
        (-0.342,-0.274,+0.062,-0.178,-0.246,-0.021,-0.029,+0.192,-0.054,-0.001,-0.142,+1.000),
    )

    # ── Spectral φ-ratio loss (session 137) ──
    #
    # The SVD spectrum of hidden state representations follows a geometric
    # sequence where consecutive singular values have ratio ≈ 1/φ.
    #
    # 5-model consensus (Pythia-160m, Pythia-410m, Qwen3-0.6B, SmolLM3-3B,
    # Mistral-7B): target ratio = 0.6299 ± 0.019.  φ-deviation = 0.012.
    #
    # This is the universal language compressor. Every model converges to it.
    # Adding it as a loss target tells the stride-stack WHERE the compression
    # fixed point is, eliminating the search. Another dimension of the crystal
    # lattice encoded in S5.
    #
    # Implementation: subsample tokens, compute top-k singular values,
    # measure consecutive ratios, penalize deviation from target.
    # Efficient: O(subsample × d × k) per measurement, not O(L × d²).
    use_spectral_loss: bool = True
    spectral_lambda: float = 1.0
    spectral_target_ratio: float = 0.6299   # 5-model consensus mean
    spectral_target_std: float = 0.019      # consensus std (soft margin)
    spectral_top_k: int = 5                 # number of singular values to compute
    spectral_subsample: int = 64            # max tokens to subsample for SVD
    spectral_measure_every: int = 1         # compute every N steps (1 = every step)

    # ── Holographic progressive loss ──
    use_holographic_loss: bool = True
    holo_lambda: float = 5.0
    holo_subsample: int = 8
    holo_warmup_steps: int = 0

    # ── Dropout ──
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

    # ── Checkpointing ──
    checkpoint_interval: int = 500
    eval_interval: int = 500
    log_interval: int = 25
    checkpoint_dir: str = "checkpoints/v13"

    # ── Data ──
    data_dir: str = "/Users/mwhitford/data/fractal-bitnet/shards-qwen3"
    structured_shard: str = "data/structured_shard.npy"
    mix_ratio: float = 0.1
    seq_len: int = 4096
    max_seq_len: int = 4096
    n_train_shards: int = 54
    n_eval_shards: int = 6

    # ── Derived properties ──

    @property
    def n_combinators(self) -> int:
        return N_COMBINATORS

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

    @property
    def n_passes(self) -> int:
        """Total passes across all stacks in the tree."""
        return (len(self.stack_a.pass_indices)
                + len(self.stack_b.pass_indices)
                + len(self.stack_c.pass_indices))

    @property
    def stack_configs(self) -> tuple["StackConfig", ...]:
        """All stack configs in tree order (A, B, C)."""
        return (self.stack_a, self.stack_b, self.stack_c)

    def __post_init__(self):
        assert self.d_model % self.n_heads == 0
        assert self.d_model % 16 == 0, "d_model must be divisible by 16 (ternary packing)"
        assert self.d_model % 4 == 0, "d_model must be divisible by 4 (embedding packing)"
        assert self.d_model % self.d_identity == 0, \
            f"d_identity ({self.d_identity}) must divide d_model ({self.d_model})"
        assert len(self.stride_is_retrieval) == len(self.strides), \
            f"stride_is_retrieval length ({len(self.stride_is_retrieval)}) must match strides ({len(self.strides)})"
        assert self.d_state % 16 == 0, "d_state must be divisible by 16 (ternary packing)"
        assert len(self.pass_zone_map) == self.n_passes

        # Validate stack pass assignments cover all passes
        all_passes = sorted(
            list(self.stack_a.pass_indices)
            + list(self.stack_b.pass_indices)
            + list(self.stack_c.pass_indices)
        )
        assert all_passes == list(range(self.n_passes)), \
            f"Stack pass assignments {all_passes} must cover all {self.n_passes} passes"

        # Validate each stack's stride bands match its pass count
        for sc in self.stack_configs:
            assert len(sc.stride_band_ranges) == len(sc.pass_indices), \
                f"Stack '{sc.name}': stride_band_ranges ({len(sc.stride_band_ranges)}) " \
                f"must match pass_indices ({len(sc.pass_indices)})"

        # Validate stride band ranges are valid indices
        for sc in self.stack_configs:
            for start, end in sc.stride_band_ranges:
                assert 0 <= start < end <= len(self.strides), \
                    f"Stack '{sc.name}': band range ({start},{end}) " \
                    f"out of bounds for {len(self.strides)} strides"
