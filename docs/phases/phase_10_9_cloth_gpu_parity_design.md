# Phase 10.9 Slice 17 — GPU Cloth Parity: Convergence Accelerator + CPU-Feature Reconciliation (Cl9 + Cl10)

## Status

**APPROVED 2026-06-06** (user sign-off after the cold-eyes loop closed clean).
Cleared for implementation per project rule 1 (research → design → review →
code). Implementation order: Cl9 first (offline ρ fit → accelerator → flip
`Cl1_StiffDrapeParity_PendingConvergenceFix` from SKIP to the strict assertion),
then Cl10 #2 (rest-pose port) and #3 (sleep port), each with its own parity pin.

Two coupled ROADMAP items, both surfaced by the **Cl1** CPU↔GPU cloth parity
harness (shipped 2026-06-03, `tests/test_cloth_cpu_gpu_parity.cpp`):

- **Cl9** (Kind: perf) — GPU cloth constraint **convergence accelerator**
  (Chebyshev / SOR) to close the stiff-drape CPU↔GPU gap.
- **Cl10** (Kind: implement) — the GPU backend lacks three CPU-only features
  (adaptive damping, rest-pose blending, sleep detection). For each: **port to
  GPU or document as intentional CPU-only** behaviour (Rule 7 parity gate).

### Cold-eyes loop log (per `~/.claude/CLAUDE.md` rule 14)

Two cold reviewers (Cl9-half + Cl10/parity-half), briefed cold each loop, looped
to a clean pass — independent confirmation reviewer returned zero verified
findings. Findings fixed across loops:

- **L1** — citation drift: `getDihedralBendCompliance` line (135→134), CPU sweep
  range (327-345→327-342), adaptive-damp application line; the enter-sleep vs
  wake **threshold conflation** (doc said one 0.05 gate; code enters at
  `gust<0.05` and wakes at `gust>0.1`) + the wind-clock-advances-while-asleep
  fact; `setAdaptiveDamping` is not on `IClothSolverBackend`.
- **L2** — Chebyshev *combine* form + buffer count flagged **pin-at-implementation**
  (rule 13) rather than transcribed from an image-only PDF I couldn't verify;
  the parity test **disables sleep** (`sleepThreshold=0.0f`) noted as a second
  non-confound; TOC added.
- **L3** — `S < solverIterations` reconciled with the clamp floor (`mode≠None`
  precedence); shader-path prefixes; rest-pose port must carry the `0.015f`
  per-substep blend constant.
- **L4** — enter-sleep **timing** (skip takes effect the *next* frame);
  `setSolverIterations(≤S)` precedence pinned (clamp up to `S+1`); `S` delay
  softened to "confirm at impl".
- **L5** — verify-step-7a pinned to a deterministic dispatch counter (not a fuzzy
  GPU timer).

Two **code-side** comment errors were surfaced (not edited under a docs review):
`cloth_simulator.cpp:383` says "16 substeps" but the default is 10;
`gpu_cloth_simulator.h:98` mis-cites `captureRestPositions`'s line range.

### Guiding constraint (user steer, 2026-06-06)

> *"Run games on low-end hardware but with as much simulation as possible…
> optimisations are critical and also smart approaches to calculations."*

This reframes both items as **convergence-per-FLOP** problems, not "make it
correct at any cost":

- **Cl9** must pick the accelerator with the best convergence **per GPU cycle**
  — brute-forcing more sweeps is exactly what we must *avoid*. Chebyshev buys an
  order-of-magnitude convergence gain for the cost of one–two extra buffers + one
  cheap combine pass (see § Cl9).
- **Cl10**'s sleep detection is the single highest-value item for this goal: a
  **settled cloth should cost ~zero GPU time**. That alone reframes it from
  "nice parity feature" to "core low-end optimisation" (see § Cl10).

## Contents

- [Background: why the gap exists](#background-why-the-gap-exists-verified-against-source)
- [Cl9 — GPU constraint convergence accelerator](#cl9--gpu-constraint-convergence-accelerator)
- [Cl10 — three CPU-only features: port-vs-document](#cl10--three-cpu-only-features-port-vs-document-decisions)
- [CPU / GPU placement](#cpu--gpu-placement-project-rule-7)
- [Performance (60 FPS floor)](#performance-60-fps-hard-floor--claudemd)
- [Accessibility](#accessibility)
- [Verify-step plan](#verify-step-plan-global-rule-12)
- [Backwards compatibility](#backwards-compatibility)
- [Cited sources](#cited-sources)

## Background: why the gap exists (verified against source)

Both backends run **small-steps XPBD**: `ClothConfig::substeps` (default **10**,
`cloth_simulator.h:29`) integrations per frame, and **one** constraint sweep per
substep. The compliance term is identical: `α̃ = compliance / dtSub²`, and the
positional correction is `Δp = λ·n` with `λ = −C / (wSum + α̃)`
(`assets/shaders/cloth_constraints.comp.glsl:82-90`, mirrored in
`ClothSimulator::solveDistanceConstraint`).

The difference is **solver ordering**, confirmed by reading both paths:

| Backend | Sweep order | Information propagation per sweep |
|---|---|---|
| CPU (`cloth_simulator.cpp:327-342`) | **Sequential** Gauss-Seidel — each constraint reads positions already updated by every earlier constraint in the same sweep | A pin's clamp propagates **cloth-wide in one sweep** (constraints walk the chain) |
| GPU (`gpu_cloth_simulator.cpp:707-716`) | **Coloured-parallel** Gauss-Seidel — constraints within a colour are independent; a colour only sees earlier colours' writes | A pin's clamp propagates only a **bounded hop-distance per sweep** |

Measured by the Cl1 harness on a stiff 4-corner-pinned 12×12 cloth
(`test_cloth_cpu_gpu_parity.cpp`). The sag figures below are the numbers
recorded in the Cl1 harness session (`ROADMAP.md` Cl9 entry, the Cl1 commit
`1b61308`), not re-measured for this doc:

- CPU sequential GS settles to **~0.18 m** sag.
- GPU coloured GS settles **~0.67 m** (post-Cl1 damping fix; ~1.44 m pre-fix).
- Extra brute-force sweeps converge only **logarithmically** — still ~22 % of
  the diagonal at 16 sweeps/substep. **Unaffordable** at 60 FPS, doubly so on
  low-end GPUs.

The strict positional assertion in `Cl1_StiffDrapeParity_PendingConvergenceFix`
(the test at `test_cloth_cpu_gpu_parity.cpp:199`) is `GTEST_SKIP`-gated at `:242`;
the skip message (`:242-248`) records the measured divergence and names the flip:
replace the
`GTEST_SKIP` with `EXPECT_LT(haus, 0.05f * diagonal)` — a 5 % symmetric Hausdorff
bound, the same assertion form the passing free-fall test already uses at `:178`.

### Verified non-confound: rest-pose blending is OFF in the parity test

A natural worry: the CPU's tight sag could be **rest-pose blending** (Cl10
feature 2) pulling particles toward the flat initial grid, not solver quality.
**Checked and ruled out.** Rest-pose blending is gated on
`!m_lraConstraints.empty()` (`cloth_simulator.cpp:379`), and LRA constraints are
built **only** by an explicit `rebuildLRA()` call (`cloth_simulator.cpp:719`) —
which the parity test never makes. `pinParticle()` (`cloth_simulator.cpp`) does
not build LRA, nor does `initialize()`. So `m_lraConstraints` is **empty** in
the drape test → rest-pose blending is inactive → **Cl9's accelerator alone
closes the drape gap.** This is the load-bearing fact for the parity-flip plan.

---

## Cl9 — GPU constraint convergence accelerator

### Options considered

#### Option A — SOR over-relaxation (scale Δp by ω∈(1,2))
One uniform (`u_omega`), one multiply in the shader: `positions += w·ω·Δp`.
Trivial, zero extra memory. **Rejected as the primary fix:** a *fixed* ω is
fragile — too high diverges on stiff/irregular topology, too low barely helps;
gains are sub-linear and the safe ω for the worst constraint under-relaxes the
rest. Good as a **fallback / floor** (see recommendation), not the headline.

#### Option B — brute-force N outer iterations per substep
Wrap the per-colour dispatch set in an `N`-iteration loop. Simple, but cost is
**O(N)** for **logarithmic** convergence — the exact "throw cycles at it" path
the low-end-hardware goal rules out.

#### Option C — Chebyshev semi-iterative acceleration *(recommended)*
Wrap the per-colour dispatch set in an outer iteration loop **and** apply the
Chebyshev semi-iterative combination across those iterations (Wang 2015). This
accelerates the *same* Gauss-Seidel iterations by **~1 order of magnitude**
(Wang's headline result) for a fixed memory cost of **one (possibly two) extra
position buffer(s)** (pinned at implementation — see warning below) plus **one
cheap combine pass per outer iteration**.

**The ω coefficient recurrence (the part this design pins; matches the secondary
sources cited below):**

```
ω₁ = 1
ω₂ = 2 / (2 − ρ²)
ωₙ = 4 / (4 − ρ²·ωₙ₋₁)          for n ≥ 3
```

where `ρ` is the estimated spectral radius of the iteration.

**The combine step (form pinned at implementation — see warning below).** After
each ordinary coloured-GS outer iteration produces a fresh iterate `x̄ⁿ`, the
accelerator blends it against a *retained earlier iterate*, weighted by `ωₙ`.
The PBD form given by Wang 2015 is, in its simplest presentation,
`xⁿ = ωₙ·(x̄ⁿ − xⁿ⁻²) + xⁿ⁻²` (the cited secondary source's transcription); the
paper's robust PBD variant additionally applies an **under-relaxation factor
`γ ≈ 0.9–0.95`** to damp the nonlinearity.

> ⚠️ **Implementation-pin (rule 13 — do not transcribe from this doc).** The
> exact combine — which prior iterate the recurrence subtracts (`xⁿ⁻¹` vs
> `xⁿ⁻²`), whether `γ` is included, and therefore **whether one or two extra
> position-sized buffers are required** — MUST be read directly from Wang 2015
> Algorithm 1 at implementation (verify-step 2), not paraphrased from here. This
> doc verified the ω-recurrence and the order-of-magnitude convergence *claim*,
> not a specific buffer-exact transcription of the combine. Budget memory for
> **up to two** extra position buffers until the exact form is confirmed.

**Stability rules from the paper, carried into the design:**
- **Delay** the Chebyshev combine until outer iteration `n ≥ S`. The first few
  iterations of nonlinear PBD don't yet behave like the linear system the
  recurrence assumes; combining too early oscillates. Wang's `S` (a small
  single-digit delay; confirm the exact value at verify-step 2 alongside the
  combine form) is tuned to his *many-iteration* projective-dynamics regime; our few-iteration
  regime (see § Performance, 4–8 iterations) needs a **small `S` (≈2)** with the
  hard invariant **`S < solverIterations`** — otherwise the accelerator never
  fires. The invariant is enforced **only when `mode ≠ None`**: with the
  accelerator off, the floor stays `1` (today's default, bit-for-bit
  behaviour); switching to `Chebyshev`/`SOR` requires `solverIterations > S`, so
  `setConvergenceMode(Chebyshev)` bumps `solverIterations` up to `S+1` if it is
  still at the default `1`. Precedence rule for the clamp collision (so the
  behaviour is gateable): while a mode is active, `setSolverIterations(n)`
  **clamps `n` up to `S+1`** rather than rejecting — the accelerator is never
  silently left disabled by a too-low value, and the effective range becomes
  `[S+1, MAX_SOLVER_ITERS]`. The `[1, MAX_SOLVER_ITERS]` floor of `1` applies
  only when `mode == None`.
- **Under-estimate / ramp ρ** for safety — an over-estimate of ρ diverges.
- Wang reports Chebyshev composes with direct, Jacobi, **and Gauss-Seidel**
  global steps; Jacobi is his GPU favourite, but our coloured-GS is a *stronger*
  smoother per iteration, so we keep it and let Chebyshev accelerate the outer
  loop.

#### Where ρ comes from — Formula Workbench (project rule 6)
ρ depends on grid dimension and stiffness (compliance). Rather than hand-code a
magic constant, **fit `ρ(gridDim, stretchCompliance)` offline in
`tools/formula_workbench/`** from a convergence sweep (measure the asymptotic
error-reduction ratio per outer iteration across a grid of configs), export the
coefficients, and load them at `initialize()`. This is the legitimate Workbench
use case from rule 6 (fit/validate/export instead of a hand-tuned `0.99f`), and
keeps a `TODO: revisit via Formula Workbench` out of the code.

### Recommendation

**Option C (Chebyshev) as the accelerator, with Option A (a conservative fixed
ω) available as a cheap floor for the lowest-iteration / lowest-end path.**
Default config keeps today's behaviour (accelerator off → 1 iteration/substep,
bit-for-bit unchanged) so nothing regresses; the editor / preset layer opts a
cloth into the accelerator.

### Dispatch integration (insertion point verified)

In `GpuClothSimulator::simulate`, the per-substep colour loop at
`gpu_cloth_simulator.cpp:707-716` becomes:

```
for each substep:
    integrate + predict (unchanged)
    seed the retained-iterate buffer(s) from the predicted positions
    for n in 1..solverIterations:           # S < solverIterations enforced
        for each colour range:                 # existing 707-716 body
            dispatch cloth_constraints.comp ; barrier
        dihedral colour passes (existing 721-736)
        if n >= S and accelerator == Chebyshev:
            ωₙ = recurrence(ρ, ωₙ₋₁)
            dispatch cloth_chebyshev_combine.comp over positions SSBO   # new, cheap
            advance retained iterate(s) for the next combine
    LRA + pins + collisions (unchanged tail)
```

The new combine shader is a per-particle pass (the `ωₙ`-weighted blend above)
over the positions SSBO, reusing the existing DSA dispatch/barrier idiom
(`gpu_cloth_simulator.cpp:721-736`). It needs the retained-iterate SSBO(s)
starting at binding `BIND_CHEBYSHEV_PREV = 12` (0–11 are taken — `BIND_TRIANGLE_TURB = 11`
in `gpu_cloth_simulator.h` is the highest current slot; Sh4b ended there). If
the confirmed combine form needs two history iterates, a second slot
`BIND_CHEBYSHEV_PREV2 = 13` is added — both free.

### API (mirrors existing tuning-setter pattern in `IClothSolverBackend`)

Add next to `getDihedralBendCompliance()` (`cloth_solver_backend.h:134`):

```cpp
// Constraint-solver convergence (Cl9). Default: 1 iteration, accelerator off —
// bit-for-bit identical to pre-Cl9 behaviour.
enum class ClothConvergenceMode { None, SOR, Chebyshev };
virtual void  setSolverIterations(int iterations) = 0;     // mode==None: clamp [1, MAX]; mode!=None: clamp [S+1, MAX]
virtual int   getSolverIterations() const = 0;
virtual void  setConvergenceMode(ClothConvergenceMode mode) = 0;
virtual ClothConvergenceMode getConvergenceMode() const = 0;
```

`MAX_SOLVER_ITERS` lives beside `MAX_SUBSTEPS` in `cloth_solver_backend.h`
(Cl7 precedent). `ρ`, `ω`, and `S` are internal (loaded from the Workbench fit /
sensible defaults), not part of the public surface — keeps the API minimal
(rule 2). The CPU implements the same setters; since sequential GS already
converges, the CPU accelerator is effectively a no-op (iteration knob honoured,
Chebyshev path a tuned-down identity) — the contract is mirrored for parity,
not because the CPU needs it.

---

## Cl10 — three CPU-only features: port-vs-document decisions

| # | Feature | CPU ref | Default state | Decision | Rationale |
|---|---|---|---|---|---|
| 1 | Adaptive damping | `cloth_simulator.cpp:256-273`, combined `:394`, applied `:404` | **OFF** (`m_adaptiveDampingFactor = 0.0f`, `cloth_simulator.h:409`) | **Document as CPU-only** (defer port) | Opt-in stabiliser, off by default → not parity-blocking (verified: free-fall + drape tests use default config). Porting needs a GPU velocity reduction for a feature nobody enables yet. Simplest-correct call (rule 2); revisit if a GPU instability case ever justifies the reduction. |
| 2 | Rest-pose blending | `cloth_simulator.cpp:373-391` | Active only when **LRA present** (`!m_lraConstraints.empty()`, `:379`) **and** `gust < 0.99` | **PORT to GPU** | Cheap (one per-particle combine pass), and it's the *one* of the three that visibly affects hanging/LRA cloth — curtains/veils, a primary Tabernacle use case. GPU already owns every input: `m_initialPositions` (Cl5), the LRA SSBO (`BIND_LRAS=8`), and `ClothWindModel::gustCurrent()` (shared model, Sh4b). ~15-line shader — **must carry the CPU's per-substep blend rate `0.015f` (`cloth_simulator.cpp:384`)** and the `lerp(pos, rest, 0.015·(1−gust))` form verbatim, or the port won't match CPU. Carry the *per-substep* `0.015f`, not a per-frame figure: the code comment's "≈21 %/frame" (`:383`) assumes 16 substeps, but the default is 10 (`1−(1−0.015)¹⁰ ≈ 14 %`), so only `0.015f`/substep is the substep-count-independent invariant. |
| 3 | Sleep detection | `cloth_simulator.cpp:408-447` | Active by default (`sleepThreshold = 0.001`, `cloth_simulator.h:34`); **disabled in the parity test** (`sleepThreshold = 0.0f`, `test_cloth_cpu_gpu_parity.cpp:77`) | **PORT to GPU** | **Highest-value item for the low-end goal.** A settled cloth → **skip the substep dispatch loop** → ~zero GPU cost. A standalone parallel-reduction kernel sums kinetic energy over velocities on GPU, `avgKE` read back as **one float**, **freeze decision on CPU** (a branch — matches the CPU/GPU heuristic: reduction→GPU, decision→CPU). The 3-frame enter-debounce + the two-gate gust hysteresis stay CPU-side. The shared wind clock keeps advancing while asleep (see design detail) so a gust can still wake it. |

### Sleep detection — design detail (the load-bearing optimisation)

- **Wind clock first:** the CPU advances the shared wind model
  (`m_windModel.advance(deltaTime)`, `cloth_simulator.cpp:227`) **before** the
  sleep early-out (`:230`). The GPU port must do the same — keep ticking the
  shared `ClothWindModel` even when the substep dispatches are skipped, or a
  slept cloth can never see the gust that should wake it.
- **GPU:** a parallel reduction kernel sums `0.5·m·|v|²` over free particles into
  a single-element SSBO (standard shared-memory tree reduction, one workgroup
  tail). Runs **only while awake**.
- **CPU:** reads back the one float (`glGetNamedBufferSubData`, tiny sync) and
  applies the existing two-threshold sleep state machine, which uses **distinct
  enter and wake gates** (verified in source — do not collapse to one):
  - **Enter sleep:** `avgKE < sleepThreshold && gustCurrent() < 0.05f`
    (`cloth_simulator.cpp:431`) for `SLEEP_FRAME_COUNT = 3` consecutive frames
    (constant at `cloth_simulator.h:431`, used at `cloth_simulator.cpp:434`).
    Note the timing: the sleep test runs at the **end** of `simulate()` (after
    that frame's substeps already ran), so on the 3rd qualifying frame it zeroes
    the velocities SSBO once and sets `m_sleeping` — and the **next** frame's
    early-out (`:230`) is what actually skips the substep dispatch loop. The GPU
    port must match this one-frame-later skip, or a verify-step-7a "dispatches
    stopped" assertion checked on the entering frame will mis-fire.
  - **Wake:** `gustCurrent() > 0.1f` (`cloth_simulator.cpp:232`) — a *higher*
    threshold than the enter gate, giving hysteresis so a cloth on the 0.05
    boundary doesn't sleep/wake every frame.
- **Cost trade:** one float read-back per **awake** frame buys skipping *all*
  substep dispatches per **asleep** frame. For a scene of mostly-static drapery
  (a temple interior) this is the difference between paying for dozens of idle
  cloths and paying for none.

### Parity-flip dependency (precise, so the flip isn't misdiagnosed)

- The **stiff-drape** strict flip depends on **Cl9 only**. Both Cl10 features
  that could otherwise confound it are inactive in that test: rest-pose blending
  (no LRA built — verified above) and sleep (`sleepThreshold = 0.0f` in
  `parityConfig()`, `test_cloth_cpu_gpu_parity.cpp:77` — verified). So once the
  GPU converges, nothing else moves the comparison.
- That deliberate disabling is also a gap to close *later*: a **future** parity
  test that enables sleep on both backends would expose the risk that the CPU
  freezes mid-settle while the GPU keeps micro-jittering. Porting sleep
  (Cl10 #3) is what makes that future test deterministic. Recommended order:
  **land Cl9, flip the current drape assertion, then land Cl10 #2/#3** each with
  its own parity pin (rest-pose on an LRA cloth; sleep with `sleepThreshold > 0`
  on both backends).

---

## CPU / GPU placement (project rule 7)

| Work | Placement | Reason |
|---|---|---|
| Constraint solve + Chebyshev/SOR combine | **GPU** | per-particle / per-constraint |
| Spectral-radius `ρ` fit | **CPU / offline (Formula Workbench)** | one-time fit, not per-frame; decision/data |
| `ω` recurrence, `S`/ρ-ramp schedule | **CPU → uniform** | scalar bookkeeping per outer iteration |
| KE / velocity reductions (sleep, adaptive-damp-if-ported) | **GPU** | per-particle sum |
| Sleep freeze decision + hysteresis | **CPU** | branch on a scalar, 1 bool of state |
| Rest-pose blend | **GPU** | per-particle lerp |

No "CPU for now, move later" deferrals — every piece is placed once (rule 7).

## Performance (60 FPS hard floor — `CLAUDE.md`)

- **Budget framing:** the win is convergence **per FLOP**. Chebyshev's promise is
  matching CPU drape in **few** outer iterations vs **many** brute-force sweeps.
- **Profiling gate (blocking before flipping the parity assertion):** on the
  RX 6600 dev GPU **and** a deliberately throttled low-end proxy, measure
  per-frame cloth time for the 12×12 parity cloth and a stress grid (128²) at:
  baseline (1 iter), brute-force N, and Chebyshev to the **same** Hausdorff. Pin
  the Chebyshev iteration count needed for `haus < 0.05·diag` and confirm the
  whole-frame budget stays ≥ 60 FPS with a representative cloth count.
- **Starting target for the implementer** (so step 2 has a value to code
  against, not an open variable): begin at `MAX_SOLVER_ITERS = 16` and a default
  of **4–8 Chebyshev outer iterations/substep**, then profile *down* to the
  smallest count that still clears the 5 % Hausdorff gate. These are starting
  guesses to be replaced by the measured number, not final budgets.
- **Sleep** is a pure subtraction from the frame budget for static scenes — the
  largest single low-end win in this slice.
- Record the numbers in the CHANGELOG entry per project rule 5 if any clamp /
  iteration cap ships.

## Accessibility

Cloth is non-interactive visual motion, so the surface is small but real:
- **Sleep / settling** removes idle micro-jitter that can distract motion-
  sensitive users, and gives a deterministic rest state a future "reduce motion"
  setting can rely on.
- No photosensitivity concern — no flashing/strobing introduced.
- The accelerator changes *convergence*, not visual style, so it's invisible to
  colour-vision / contrast needs.

## Verify-step plan (global rule 12)

**Cl9**
1. Offline ρ fit in Formula Workbench → export coeffs. *Verify:* fit reproduces
   measured convergence ratios within tolerance on the validation set.
2. Add `cloth_chebyshev_combine.comp.glsl` + `BIND_CHEBYSHEV_PREV=12` + the
   outer-iteration loop + API setters (CPU + GPU). *Verify:* default config
   (1 iter, mode None) is **bit-for-bit unchanged** — existing cloth tests +
   `Cl1_FreeFall…` still green.
3. Tune iterations/ρ for the drape. *Verify:* `Cl1_StiffDrapeParity` Hausdorff
   `< 0.05·diagonal`; flip the `GTEST_SKIP` to `EXPECT_LT`.
4. Profiling gate (above). *Verify:* ≥ 60 FPS at representative cloth load on
   both GPUs; numbers recorded.

**Cl10**
5. Document adaptive damping as a concrete-`ClothSimulator`-only feature (it is
   **not** on the `IClothSolverBackend` interface — `setAdaptiveDamping` /
   `getAdaptiveDamping` live at `cloth_simulator.h:291,294`). The note lives as a
   header comment on `setAdaptiveDamping`, plus a one-line "CPU-only, not
   promoted to the backend interface" entry in the interface header's class
   doc-comment so a reader of `IClothSolverBackend` learns the gap. *Verify:*
   `grep` confirms both comment strings present (gateable, not eyeball); no
   behaviour change (no test delta).
6. Port rest-pose blending (`cloth_rest_blend.comp.glsl`). *Verify:* new
   CPU↔GPU parity test on an **LRA** cloth in calm wind passes < 5 % Hausdorff.
7. Port sleep detection (reduction kernel + CPU freeze + dispatch early-out).
   *Verify:* (a) a settled GPU cloth reports `isSleeping()` and a **deterministic
   substep-dispatch counter** (not a fuzzy GPU-timer reading) shows zero
   dispatches on the frame after it sleeps; (b) gust wakes it (counter resumes);
   (c) drape parity still holds with sleep enabled on both.

## Backwards compatibility

Default `ClothConfig` + default `IClothSolverBackend` state reproduce **exactly**
today's behaviour: 1 solver iteration, accelerator `None`, sleep already exists
on CPU and is being *added* to GPU (GPU gains the early-out; awake behaviour
unchanged). No save-format or scene-schema change. The three new API methods are
additive virtuals with defaulting call-sites.

## Cited sources

- **Wang, H. 2015. "A Chebyshev Semi-Iterative Approach for Accelerating
  Projective and Position-Based Dynamics."** *ACM Trans. Graph. 34, 6
  (SIGGRAPH Asia).* — the accelerator, recurrence, spectral-radius estimation,
  delay-S and ρ-ramp stability rules, GPU-friendliness.
  https://wanghmin.github.io/publication/wang-2015-csi/ ·
  recurrence cross-checked at
  https://www.physicsbasedanimation.com/2015/09/29/a-chebyshev-semi-iterative-approach-for-accelerating-projective-and-position-based-dynamics/
- **Macklin, Müller, Chentanez. 2016. "XPBD: Position-Based Simulation of
  Compliant Constrained Dynamics."** *MIG 2016.* — the `α̃ = compliance/dt²`
  compliance formulation already in `assets/shaders/cloth_constraints.comp.glsl`.
- **Macklin et al. 2019. "Small Steps in Physics Simulation."** *SCA 2019.* —
  the substeps-over-iterations strategy this engine uses (`substeps=10`).
- **Fratarcangeli, Tibaldo, Pellacini. 2016/2018. "Parallel iterative solvers
  for real-time elastic deformations."** — graph-coloured Gauss-Seidel
  convergence behaviour vs sequential, the root of the Cl9 gap.
  https://www.researchgate.net/publication/329287832
- **Successive over-relaxation** (Option A floor), ω∈(0,2) convergence range.
  https://en.wikipedia.org/wiki/Successive_over-relaxation
