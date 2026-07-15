# YM KH Simulation — Findings Tracker

## Current Code State (2026-07-02)

**Architecture**: Periodic domain, `Lx=6π`, `Lz=2π`, `NX=768`, `NZ=64`, `DX=Lx/NX≈0.02454`, `DZ=Lz/NZ≈0.09817`, `DT=0.1*DX≈2.454e-3`. 1 TU ≈ 407 steps; 40748 steps ≈ 100 TU. (Previous: NZ=256, courant=0.01, 1 TU≈4082 steps — 40× slower. NZ=64/courant=0.1 validated as numerically converged in C25 resolution study, γ within 4.4% of NZ=256.)

**Fast grid defaults (active from Campaign 25)**: NZ=64, NX=768, courant=0.1, target_tu=100, export every 1 TU (407 steps). Energy check every 0.5 TU (203 steps). energy.csv DT inferred from slope (step vs time) to avoid hardcoded courant dependence.

**Latest active mode**: `NAB_CIRC_AZ2` (run_mode=6, Campaign 18) — same log-cosh Az1 as Mode 1 but seeds **Az2/Az3** with the WKB Gaussian profile instead of By2/By3. Parallel: Campaign 17 (Mode 1, α=0.5, reduced cascade) on abi.

**New run_mode=6 (NAB_CIRC_AZ2)**: Added to `YM_Init.cu`. Seeds `Az2 ∝ exp(−ξ²/2ξ_char²)·cos(kz·z)`, `Az3 ∝ exp(−ξ²/2ξ_char²)·sin(kz·z)` where `ξ_char=1/sqrt(α·kz·V0)`. By2=By3=0 at t=0. See PHYSICS.md §9 for full derivation.

**Standard suppression flags** (all active campaigns): `suppress_kz0=1`, `hyp_diff=5e-5`, `BP=14`, `cudaMemset By1/Ex1/Ez1=0` each step (step 6e, since Campaign 15).

**Energy threshold**: 100× E0 for modes 3/4/5/6 and for modes 0/1 with xi_sponge>0; 5× for modes 0/1 without sponge.

**Snapshot columns (updated 2026-07-03)**: `X,Z,By1,By2,By3,Az2,Az3,PzA,PxA,Q1A,PzB,PxB,Q1B,Ex1,Ex2,Ex3,Ez1,Ez2,Ez3,nA,nB,Q2A,Q3A,Q2B,Q3B` (25 cols; added Ex/Ez all colors, fluid density nA/nB, Q2/Q3 for Gauss's law verification)

GPU servers: `t130`/`t136` (RTX A5000, sm_86) → `/DATA/cm/lcpfct/ymgpu2d/`, ~9200 steps/min.
Backup: `abi` (farmerzone, 3× GTX 1080 Ti, sm_61) → `/DATA/s23103/lcpfct/ymgpu2d/`, ~4500 steps/min/GPU.

---

## Why the Architecture Changed

Campaigns 1–2 used a single-tanh domain (`NX=NZ=256`, `DX=1`, wall BC) with `Az1=−V0·log(cosh(ξ))` (no-eps). That profile grows without bound at large |ξ|, so the outer coupling `α|Az1|` always exceeded the WKB growth rate γ_WKB once the EM wave left the seeded inner region (t≈63-76). The WKB mode was never cleanly observable.

**Fix**: bounded periodic domain, frozen Az1 background, periodic BC, `Lx=6π`.

---

## Archived: Campaign 1 — Non-Az1 Baseline

Grid: NX=NZ=256, DX=1, DT=0.002, wall BC. Az1=0.

| k | t_halt | γ_amp |
|---|--------|-------|
| 2-8 | ≈202 | ~0.05-0.07 |

**Interpretation**: Without Az1 the coupling chain breaks at Q3→Q2. Observed growth is FCT background instability, not KH.

---

## Archived: Campaign 2 — With Az1, Windowed Seed

Grid: NX=NZ=256, DX=1, DT=0.002, wall BC. `Az1=−V0·log(cosh(ξ))` full domain.

| k | t_halt | γ_amp (TU⁻¹) | γ_WKB (TU⁻¹) |
|---|--------|--------------|--------------|
| 2 | 63 | 0.174 | 0.049 |
| 5 | 68 | 0.192 | 0.110 |
| 8 | 76 | 0.177 | 0.146 |

**Interpretation**: Outer-region coupling dominated. γ_amp ≈ 0.18/TU flat across all k. WKB mode never isolated.

---

## Campaign 3 — NAB_DTANH, α=2.0, k=1..3 (run 2026-06-29)

**Setup**: `run_mode=3`, `alpha=2.0`, `perturb_amp=0.001`, `V0=0.1`. k=1,2,3 run; k=4 interrupted.

**Result**: All runs halt at t≈49 TU. The seeded kz modes (k=1..3) show NO significant growth.

**Key discovery**: The **kz=0 Weibel-like mode** of By2 and By3 grows from machine-precision noise at:

```
γ(kz=0) = (√(α³/2) · V₀)^(1/3) · sin(π/3)
```

**Measured (k=1, α=2.0)**: γ = 0.5039 TU⁻¹  
**WKB prediction (kz=0, n=0)**: γ = 0.5065 TU⁻¹  
**Match**: 0.5% (excellent)

Growth time series for By2(kz=0) at α=2.0:

| t (TU) | By2(kz=0) RMS |
|--------|--------------|
| 0.0 | 5.8e-13 (machine noise) |
| 4.9 | 1.6e-11 |
| 9.8 | 1.2e-10 |
| 14.7 | 1.2e-09 |
| 19.6 | 1.4e-08 |
| 24.5 | 1.7e-07 |
| 29.5 | 2.0e-06 |
| 34.4 | 2.4e-05 |
| 39.3 | 2.9e-04 |
| 44.2 | 3.5e-03 |
| 49.1 | 4.1e-02 → [HALT] |

This mode is 39× faster than the seeded kz=1 KH mode (γ_KH ≈ 0.013 TU⁻¹ or possibly ≈ 0).  
It dominates the energy by t≈49 TU and triggers the 100×E0 threshold.

**Seeded kz=1 mode behavior**: By2(kz=1) went from 4.47e-05 to 8.51e-05 (factor 1.9×) in 49 TU. The complex Fourier coefficient had random phase — no clear exponential growth signature. The apparent small increase is consistent with kz=0 cascade contamination at late times. Az2(kz=1) grew monotonically at γ≈0.12 TU⁻¹, driven by the kz=0 mode through non-Abelian coupling, not genuine KH growth.

**WKB comparison for kz≥1**: The polynomial at kz=1, α=2, n=0, v=0.1 predicts γ=0.553 TU⁻¹ — 42× larger than observed. The double-shear geometry (two layers at x=Lx/4 and x=3Lx/4) likely suppresses the KH mode relative to single-layer WKB.

---

## Campaign 4 — NAB_DTANH, α scan k=1 (2026-06-29)

**Setup**: `run_mode=3`, `k_mode=1`, `alpha` ∈ {0.5, 0.75, 1.0, 1.5}, `perturb_amp=0.001`. Sequential via `run_alpha_scan.sh`.

**Goal**: Map γ(kz=0) vs α to validate WKB polynomial.

**Key finding: WKB suppressed at α<2 — ~3× below prediction for α=0.5 and 0.75**

All α<2 runs hit FCT NaN at t≈66–69 TU (FCT instability in the double-tanh shear profile), before the Weibel energy threshold. α=2 (Campaign 3) hit energy threshold at t=49 TU, confirming it escaped the FCT wall first.

| α | halt type | t_halt (TU) | γ_fit (TU⁻¹) | γ_WKB (TU⁻¹) | ratio |
|---|-----------|------------|--------------|--------------|-------|
| 0.50 | FCT NaN | 66.3 | 0.080 | 0.253 | 0.32 |
| 0.75 | FCT NaN | 68.7 | 0.115 | 0.310 | 0.37 |
| 1.00 | FCT NaN | 68.7 | 0.204 | 0.358 | 0.57 |
| 1.25 | FCT NaN | 68.7 | 0.280 | 0.400 | 0.70 |
| 1.50 | FCT NaN | 66.3 | 0.354 | 0.439 | 0.81 |
| 1.75 | Energy ×100 | 56.5 | 0.430 | 0.474 | 0.91 |
| 2.25 | Energy ×100 | 44.2 | 0.580 | 0.537 | 1.08 |
| 2.75 | Energy ×100 | 36.8 | 0.730 | 0.594 | 1.23 |
| 2.00 | Energy ×100 | 49.1 | 0.504 | 0.507 | 0.99 |

**Empirical scaling**: γ_fit ≈ 0.196 × α^1.35 (power-law fit over all 9 points). The ratio γ_fit/γ_WKB forms an S-curve crossing 1.0 at α≈2: suppressed (0.32–0.91) for α<2, exact at α=2, and exceeds WKB (1.08–1.23) for α>2.

**Above-WKB regime (α>2)**: The ratio continues rising (1.08 at α=2.25, 1.23 at α=2.75). This is likely the n=1 WKB mode (γ₁ = 3^(1/3)·γ₀ ≈ 1.44·γ₀) becoming competitive with n=0. At large α the runs are short (t_blow=37–44 TU), and consecutive e-fold analysis in the late linear phase shows consistent growth faster than the n=0 WKB, suggesting a mode mix where n=1 contributes at the ~0.1–0.3% level (enough to shift γ_eff upward by 10–25%).

**FCT NaN wall**: All runs with α≤1.5 hit FCT numerical instability at t=66.3 or 68.7 TU exactly (comes from double-tanh shear advection; occurs at the same step regardless of α since fluid dynamics dominates). Only α=2 escaped via Weibel energy threshold first. α=1.5 came within 0.4 TU (estimated Weibel blow-up at t≈65.9, FCT NaN at t=66.3).

**Interpretation — double-well interference**: NAB_DTANH has two Az1 wells (at x=Lx/4 and x=3Lx/4). The kz=0 Weibel eigenfunction splits into symmetric ("bonding") and antisymmetric ("antibonding") combinations. At small α, the wells are weakly decoupled and the antisymmetric mode (γ < γ_WKB) dominates the machine-noise seed. At large α, the wells decouple and both modes converge to γ_WKB. This is the two-well eigenfunction problem, analogous to a quantum double-well. The WKB polynomial correctly predicts the single-well growth rate; the double-well geometry reduces it by the ratio α^0.88.

**Key conclusion**: The WKB polynomial is validated at α=2 to 0.5% for the kz=0 Weibel mode. The suppression at lower α is a geometric artifact of the double-tanh setup, not a failure of the polynomial itself.

**Analysis script**: `measure_kz0_gamma.py`

---

## Campaign 5 — NAB_DTANH, α=2.0, suppress_kz0=1, k=1..8 (2026-06-29)

**Setup**: `run_mode=3`, `alpha=2.0`, `perturb_amp=0.001`, `V0=0.1`, `suppress_kz0=1` (no hyp_diff). k=1..8 sequential; k=6 killed mid-run, k=7–8 not reached.

**Goal**: Check whether projecting out the kz=0 component of By2/By3 at each step prevents the Weibel blowup and exposes the KH mode.

**Result**: suppress_kz0 alone is insufficient. k=1..5 still hit the 100×E0 energy threshold at t=46.6–51.5 TU.

| k | halt type | t_halt (TU) |
|---|-----------|------------|
| 1 | Energy ×100 | 51.5 |
| 2 | Energy ×100 | 49.1 |
| 3 | Energy ×100 | 49.1 |
| 4 | Energy ×100 | 49.1 |
| 5 | Energy ×100 | 46.6 |
| 6 | Terminated | — |
| 7–8 | Not run | — |

**Interpretation**: The kz=0 suppression zeroes By2/By3 at kz=0, but the Weibel energy flows through other channels (Az2, Az3, Q2, Q3 at kz=0) which are not zeroed. The rapid blowup pattern (E/E0 jumping from ~1.4 to 1401 within 10 TU for k=1) differs from the gradual Campaign 3 profile, suggesting the suppression forces a transient that feeds the instability differently. Regardless, the kz=0 mode is not cleanly eliminated and the runs still die before a KH growth window.

---

## Campaign 6 — NAB_DTANH, α=2.0, suppress_kz0=1, hyp_diff=5e-5, k=1..8 (2026-06-30)

**Setup**: `run_mode=3`, `alpha=2.0`, `perturb_amp=0.001`, `V0=0.1`, `suppress_kz0=1`, `hyp_diff=5e-5`. All 8 modes run sequentially and completed. Output directories: `ym_k{1..8}_a2.000_dtanh_nkz0_hd5e-05/`.

**Goal**: Add hyperdiffusion to suppress the remaining kz=0 Weibel energy leaking through non-By channels and extend the run window.

**Result**: kz=0 blowup is eliminated. All 8 runs survive to t=63.8–71.2 TU, then die from the FCT NaN wall.

| k | halt type | t_halt (TU) |
|---|-----------|------------|
| 1 | FCT NaN | 63.8 |
| 2 | FCT NaN | 66.3 |
| 3 | FCT NaN | 68.7 |
| 4 | FCT NaN | 68.7 |
| 5 | FCT NaN | 68.7 |
| 6 | FCT NaN | 68.7 |
| 7 | FCT NaN | 71.2 |
| 8 | FCT NaN | 71.2 |

**Energy traces**: E/E0 stays in [0.99, 1.15] throughout all runs — no systematic growth above ~15%. The Weibel mode is genuinely suppressed. The NaN onset is sudden (E/E0 goes from ~1.15 to -nan in one 10000-step interval) with no energy warning.

**FCT NaN wall**: the halt times match Campaign 4's FCT NaN times almost exactly (63.8, 66.3, 68.7 TU for k=1–6, 71 TU for k=7–8). The `hyp_diff=5e-5` gave a small extension for k=7,8 (~2.5 TU) but did not cure the instability. The FCT NaN originates from advection of the double-tanh shear velocity profile: FCT is monotone but still accumulates truncation error in the high-shear region, eventually producing a density or momentum value that propagates into a divide-by-zero or float overflow.

**No KH growth detected**: the WKB prediction for kz=1, α=2 is γ≈0.55 TU⁻¹, which would give ×10 amplitude per 4 TU. In 63 TU of clean window that signal would be enormous if present. Its absence, combined with Campaign 3's finding that By2(kz=1) grew only 1.9× in 49 TU (γ≈0.013 TU⁻¹), confirms the double-tanh geometry strongly suppresses the kz≥1 KH mode.

**Conclusion**: suppress_kz0 + hyp_diff successfully eliminates the kz=0 Weibel blowup but the FCT NaN wall (from the double-tanh shear) remains the binding constraint. The two-well geometry also suppresses the KH mode itself. Both issues point to switching away from NAB_DTANH.

---

## Campaign 7 — NAB_STEP, α=2.0, suppress_kz0=1, hyp_diff=5e-5, k=1..8 (2026-06-30)

**Setup**: `run_mode=4`, `alpha=2.0`, `perturb_amp=0.001`, `V0=0.1`, `suppress_kz0=1`, `hyp_diff=5e-5`.

**Result**: All k values blow up from NaN at t≈12–20 TU. Much earlier than Campaign 6's 63–71 TU.

| k | halt type | t_halt (TU) |
|---|-----------|------------|
| 1 | NaN | 19.6 |
| 2 | NaN | 14.7 |
| 3–8 | NaN | ~14–20 |

**Root cause — color-1 two-stream instability**: NAB_STEP places both beams with `vz_A = −vz_B = ±V0` everywhere (not just at interfaces). Beams A (+Q1=+1, +vz) and B (−Q1=−1, −vz) form a two-stream configuration in the color-1 sector with relative velocity 2V0. Growth rate ω_p/√2 ≈ 0.7 TU⁻¹. Starting from numerical noise this saturates and drives blow-up at t≈13–20 TU, **independent of α** (confirmed: old α=0.5 STEP run also blew up at t≈15 TU).

DTANH avoids the two-stream instability because the velocity tanh profile has vz→0 at the interfaces where the mode localises — the instability sees a short, velocity-limited region rather than the full domain.

**By1 initialization attempt**: Tried initializing By1 to the equilibrium triangle wave (integral of Jz1−⟨Jz1⟩) to reduce the plasma oscillation. This made things worse (blowup at t=12.3 instead of 19.6 TU) because the large |By1|∼0.84 generates a transverse Lorentz force F_xA = −vz_A·By1 = ∓V0·By1 that immediately accelerates the beams in x, dumping kinetic energy into the EM fields. There is no cold-plasma static equilibrium with both vz≠0 everywhere and By1≠0. Reverted.

**Conclusion**: NAB_STEP is fundamentally broken as a geometry for two opposite-color counter-streaming beams. The color-1 two-stream instability terminates runs at t≈15 TU regardless of α, suppress_kz0, or hyp_diff. By1 initialization attempts only accelerate the collapse.

---

## Campaign 8 — NAB_DTANH, 2D sweep: α∈[1,6]×V₀∈[0.001,0.4], 200 runs (planned 2026-06-30)

**Setup**: `run_mode=3`, `k_mode=1`, `perturb_amp=0.001`, `suppress_kz0=0`, `hyp_diff=2e-4`. α: 10 linearly-spaced from 1 to 6; V₀: 20 log-spaced from 0.001 to 0.4. Total: 200 sequential runs.

**Goal**: Map γ(α, V₀) across the full 2D parameter space and compare to the analytic WKB prediction γ_WKB = (√(α³/2)·V₀)^(1/3)·sin(π/3). Determine whether the double-well suppression seen in Campaign 4 (DTANH geometry, ratio≈0.32–0.99 across α=0.5–2) persists across V₀, or whether the suppression depends on the combined dimensionless coupling α·V₀.

**hyp_diff choice**: `2e-4` (4× Campaign 6 value) gives damping rate 1.44 TU⁻¹ at kz=50 — sufficient to kill any numerical instability at kz≥50 even at the maximum physical growth rate γ≈1.39 TU⁻¹ (α=6, V₀=0.4). kz=8 sees only 0.001 TU⁻¹ damping (negligible).

**Code change**: `main_ym.cu` directory naming fixed to `setprecision(4)` for V₀ (was 3), ensuring all 20 V₀ values get unique directory names. **Requires rebuild on t126.**

**Expected run times**: FCT NaN wall at t≈63–71 TU for slow-growing modes; energy threshold at t≈20–50 TU for fast-growing (large α, V₀) modes. Each run ≈0.5–1 min; total sweep ≈3–5 hours.

**Measurability**: γ≥0.08 TU⁻¹ detectable (kz=0 amplitude grows from ~1e-13 to above 1e-12 within 63 TU window). Corner (α=1, V₀=0.001) predicted γ≈0.077 is marginal — may report NaN. All other corners should be measurable.

**Analysis**: `python3 analyze_campaign8.py` — auto-discovers directories, fits exponential, generates heatmap of γ_meas/γ_WKB and scatter plot.

**Expected WKB range**: γ_WKB ∈ [0.077, 1.39] TU⁻¹ (36× dynamic range). The analytic formula predicts γ ∝ α^(1/2)·V₀^(1/3). If the double-well suppression factor depends only on geometry (not α or V₀), the ratio γ_meas/γ_WKB should be constant across the 2D space — forming a flat heatmap. If the suppression depends on αV₀ (as the quantum double-well analogy suggests), the ratio will vary systematically and reveal the correction function.

---

## Campaign 9 — NAB_STEP (mistake), α=2.0, kz_suppress_max=k-1, k=1..6 (2026-06-30)

**Setup**: `run_mode=4` (NAB_STEP — **error, should have been mode=3**), `alpha=2.0`, `perturb_amp=0.001`, `V0=0.1`, `suppress_kz0=1`, `hyp_diff=5e-5`, `kz_suppress_max=k-1`. Ran on t130:/DATA/cm. k=1..4 completed (all NaN); k=5 killed mid-run; k=6 never started.

**Goal**: Isolate kz=1..6 growth rates by suppressing all modes below the target. New kernel `kernel_ym_subtract_lowkz` projects out DFT modes kz=1..kz_suppress_max at each step (DFT subtraction, 24 KB smem per block).

**Result**: All runs hit NaN at t=12–22 TU — identical to Campaign 7's NAB_STEP blowup.

| k | kz_suppress_max | halt type | t_halt (TU) | E/E0 before NaN |
|---|-----------------|-----------|-------------|-----------------|
| 1 | 0 | NaN | 22.1 | 1.88 |
| 2 | 1 | NaN | 12.3 | 1.15 |
| 3 | 2 | NaN | 14.7 | 1.61 |
| 4 | 3 | NaN | 14.7 | 1.62 |
| 5 | 4 | Killed | — | — |
| 6 | 5 | Not reached | — | — |

**Root cause**: Mode 4 (NAB_STEP) was used instead of Mode 3 (NAB_DTANH). Campaign 7 already established that NAB_STEP is fatal: the step-function velocity profile gives vz=±V0 everywhere, generating a color-1 two-stream instability (γ≈0.7 TU⁻¹) that NaN's at t≈12–22 TU regardless of any suppression settings.

**Diagnosis from logs**: The energy trajectory through t=9.8 TU is *identical* across all four runs (E/E0 = 0.993, 1.003, 1.150, 1.112) — confirming the divergence is not related to kz_suppress_max and originates from the same two-stream physics.

**New code (kept)**: `kernel_ym_subtract_kz_range` (renamed from `kernel_ym_subtract_lowkz`) and `kz_suppress_max` parameter are correct and will be reused in the next campaign with the correct mode.

**Fix for Campaign 10**: New mode 5 (NAB_TANH_COSAZ) with thin-tanh shear + bounded cosine Az1.

---

## Campaign 10 — NAB_TANH_COSAZ (mode 5), EPS sweep + kz=1..6 (2026-06-30)

**Setup**: `run_mode=5` (new mode: single thin-tanh shear, cosine Az1), `alpha=2.0`, `perturb_amp=0.001`, `V0=0.1`, `suppress_kz0=1`, `hyp_diff=5e-5`. Phase 1: EPS=0.50,0.30,0.15,0.10 at k=1. Phase 2: k=1..6 at EPS=0.15 with kz_suppress_max=k-1.

**Mode 5 design**: fixes both prior failures — cosine Az1 (|Az1|≤V0 everywhere, no log-cosh outer-region blowup), single shear layer (no double-well suppression), tanh velocity (zero at interface, no step-function two-stream).

**Result**: All runs NaN at t=17–20 TU. Better than NAB_STEP (t=12–22 TU) but still far short of a usable window.

| EPS | k | kz_suppress_max | t_halt (TU) |
|-----|---|-----------------|-------------|
| 0.50 | 1 | 0 | 19.6 |
| 0.30 | 1 | 0 | 19.6 |
| 0.15 | 1–5 | k-1 | 17.2 |
| 0.10 | 1 | 0 | 17.2 |

**KH growth confirmed**: By2 at target kz grows cleanly in the early linear phase:

| EPS | γ_KH(kz=1) (TU⁻¹) | γ_KH/γ_WKB |
|-----|-------------------|------------|
| 0.50 | 0.034 | 6.2% |
| 0.30 | 0.044 | 8.0% |
| 0.15 | 0.064 | 11.6% |
| 0.10 | 0.170 | 30.8% |

Growth rate rises with smaller EPS (correct trend — kz*EPS→0 activates KH). Still below WKB because the tanh profile reduces the effective coupling vs the step-function WKB assumption.

**Root cause of NaN**: Two-stream instability at kz≈10–14 in the color-2,3 sector. By2[kz=10] grows from noise (~5e-14) to 5e-8 in 14.7 TU at γ≈0.8 TU⁻¹ — 10× faster than KH. The counter-streaming beams (±V0 away from the shear interface) provide full two-stream drive at all kz > 0; non-Abelian coupling amplifies it through color-2,3.

**Key diagnostic** (EPS=0.15, k=1):
```
t=0.0:   By2[kz=1]=2.5e-6   By2[kz=10]=5e-14   (initial seed vs noise)
t=4.9:   By2[kz=1]=5.1e-6   By2[kz=10]=4e-12   (KH linear growth)
t=9.8:   By2[kz=1]=6.8e-6   By2[kz=10]=2.7e-9  (two-stream overtakes)
t=14.7:  By2[kz=1]=6.4e-6   By2[kz=10]=4.9e-8  (two-stream 7000× KH)
t=17.2:  NaN
```

The kz_suppress_max filter (low-kz) does not help because the two-stream peaks at kz≈10–14, above k_target.

**Fix for Campaign 11**: Add high-kz bandpass — suppress kz=k_mode+1..40 in color-2,3 fields each step. This cuts the non-Abelian amplification of the two-stream while leaving the target KH mode (kz=k_mode) untouched.

---

## Campaign 11 — NAB_TANH_COSAZ, color-2/3 bandpass only (2026-06-30)

**Setup**: same as Campaign 10 but adds `kz_suppress_hi=40`: suppress kz=k+1..40 in color-2/3 fields each step. Combined with suppress_kz0 + kz_suppress_max=k-1, only kz=k_mode survives in the EM sector.

**Result**: **Identical NaN timing as Campaign 10** — all three EPS values NaN'd at t=17.2 TU regardless of bandpass setting. EPS=0.50 was actually slightly *worse* (17.2 TU vs 19.6 TU in C10). The color-2/3 bandpass did nothing.

| EPS | k | t_halt (TU) | Notes |
|-----|---|-------------|-------|
| 0.50 | 1 | 17.2 | worse than C10 without filter |
| 0.15 | 1 | 17.2 | same as C10 |
| 0.10 | 1 | 17.2 | same as C10 |

**Diagnosis**: The NaN is not from the color-2/3 EM sector — it comes from the **color-1 fluid two-stream** in pzA and pzB. Counter-streaming beams at ±V0 drive z-momentum oscillations at kz=1..kz_ts≈14 in the fluid. Density n can approach zero from these oscillations, causing pz/n=vz→NaN. This mechanism is independent of any color-2/3 filtering.

**Fix for Campaign 12**: Add `kernel_fluid_pz_subtract_kz_range` — same DFT subtraction applied to pzA and pzB each step, covering kz=k+1..14 (the two-stream unstable band). This cuts the fluid two-stream at the source.

---

## Campaign 12 — NAB_TANH_COSAZ, full bandpass (color-2/3 + fluid pz) (2026-06-30)

**Setup**: Same as Campaign 11 but adds a fluid pz bandpass: kz_suppress_hi=14 (not 40) zeroes pzA and pzB at kz=k+1..14 in addition to the color-2/3 filter. BP=14 covers the full two-stream unstable band (kz < √2/V0 ≈ 14.1 for V0=0.1). Color-2/3 filter also uses BP=14.

**New kernel**: `kernel_fluid_pz_subtract_kz_range(pzA, pzB, nx, nz, kz_lo, kz_hi)` — register-caching + warp-shuffle design (smem 144 B vs old 4 KB). Called twice per step alongside the color-2/3 filter.

**Kernel optimisation**: Both DFT kernels rewritten to load fields into registers once and accumulate all mode subtractions in registers, writing back once. New design: 1 read + 1 write. Smem drops from 24 KB → 864 B for the 12-field kernel → 32 blocks/SM vs 2 → full occupancy. Syncthreads per mode: 10 → 3. Speed: ~9,230 steps/min (7× faster than initial BP=40 implementation).

**Result**: NaN at t=14.7 TU. By1[kz=0] Weibel explosion — zmean at that time only covered By2/By3, not By1/Ex1/Ez1.

---

## Campaign 13 — NAB_TANH_COSAZ, extended zmean covers By1/Ex1/Ez1 (2026-06-30)

**Setup**: Extended `kernel_ym_subtract_zmean` to cover all 15 fields including By1, Ex1, Ez1. Same BP=14 bandpass. Fixes the kz=0 component of color-1 EM.

**Result**: Fixed t=14.7 TU NaN. But all k=1..6 still NaN at exactly t=17.2 TU (step 70000). The kz=0 component of color-1 EM is zeroed, but nonzero kz modes of By1/Ex1/Ez1 grow freely.

---

## Campaign 14 — NAB_TANH_COSAZ, color-1 EM kz-range filter + pxA/pxB (2026-06-30)

**Setup**: Extended `kernel_ym_subtract_kz_range` from 12 to 15 fields, adding By1, Ex1, Ez1. Also added pxA, pxB to the fluid bandpass. The extended kz_suppress_max filter covers kz=1..k-1 for all 15 color fields.

**Result**: All k=1..6 still NaN at step 70000 (t=17.2 TU). Spectrum analysis (column mapping: X=col0, Z=col1, By1=col2, By2=col3, By3=col4, Az2=col5, Az3=col6, ...) revealed:

- **By1[kz=k_mode]** growing at γ≈1.1 TU⁻¹ — a color-1 EM instability at the TARGET kz
- The DFT filter skips kz=k_mode intentionally (it's the KH seed mode); By1 at kz=k_mode is therefore NEVER filtered
- By1[kz=1] reached ~0.01 by step 70000 (≈12× faster than KH), causing the NaN

**Root cause**: Counter-streaming color-1 beams at ±V0 sustain a filamentation/EM two-stream instability at every nonzero kz, including kz=k_mode. The bandpass filter cannot protect kz=k_mode without killing the KH signal. The KH chain (By2→Ez2→Az2→Q3→Q2→Lorentz→By2) does NOT require By1, Ex1, or Ez1.

---

## Campaign 15 — NAB_TANH_COSAZ, cudaMemset By1/Ex1/Ez1=0 each step (2026-06-30)

**Setup**: Step 6e added in `main_ym.cu` (after Maxwell solve, before Lorentz/Precession): when `suppress_kz0=1`, calls `cudaMemset(By1, 0)`, `cudaMemset(Ex1, 0)`, `cudaMemset(Ez1, 0)` after every Maxwell iteration. Eliminates ALL kz modes of color-1 EM, removing the γ≈1.1 TU⁻¹ instability at every kz including k_mode. Same BP=14 bandpass as Campaigns 12–14, EPS=0.15, α=2.0, V0=0.1.

**Phase 1 result (k=1, kz_suppress_max=0 — diagnostic run)**:

- **First run to survive past t=17.2 TU** — ran to t=58.9 TU (NaN from KH nonlinear explosion)
- E/E0=0.9725 flat from t=2.5 to t=49.1 TU (clean linear phase)
- KH growth clearly observable:

| t (TU) | By2[kz=1] | E/E0 |
|--------|-----------|------|
| 0.0 | 1.250e-6 (seed) | — |
| 4.9 | 2.590e-6 | 0.9725 |
| 9.8 | 3.704e-6 | 0.9725 |
| 14.7 | 3.360e-6 | 0.9725 |
| 19.6 | 3.145e-6 | 0.9725 |
| 24.5 | 4.894e-6 | 0.9725 |
| 29.5 | 7.690e-6 | 0.9725 |
| 34.4 | 1.480e-5 | 0.9725 |
| 49.1 | — | 0.9731 |
| 54.0 | — | 0.9784 |
| 56.5 | — | 0.9875 |
| 58.9 | NaN (KH nonlinear) | — |

**γ_KH(kz=1) from Phase 1**: ~0.11 TU⁻¹ (fit to By2 points t=24.5..34.4). The early oscillation in By2 (decreasing t=9.8→19.6) reflects the real part of the KH eigenvalue (ω_r≠0): a propagating KH wave with γ<|ω_r|.

**kz=5 diagnostic**: By2[kz=5] flat (KH stabilized); Az2[kz=5] grows at γ≈0.20 TU⁻¹ = α×V0 (color precession rate, not KH). kz=5 is above the KH stability cutoff for α=2, V0=0.1, EPS=0.15.

**Key new physics**:
1. KH stability cutoff lies between kz=1 (γ≈0.11 TU⁻¹) and kz=5 (γ≈0), consistent with the WKB polynomial where α²Vkz stabilizes high-kz modes.
2. Az2[kz=k] grows at γ≈α×V0=0.20 TU⁻¹ for all kz — this is the color precession rate, NOT the KH growth rate.
3. The precession mode exists even when KH is stable (kz=5 shows Az2 growth, By2 flat).

**Phase 2 results (k=1..6 sequential sweep, kz_suppress_max=k-1, BP=14, NEW binary)**:

| kz | Binary | γ_KH (TU⁻¹) | γ_WKB (TU⁻¹) | ratio | t_linear (TU) | Notes |
|----|--------|-------------|---------------|-------|---------------|-------|
| 1 | NEW | **0.090** | 0.553 | 0.16 | 24.5..29.5 | Cascade at t>29, NaN t=68.7 |
| 2 | NEW* | ~0.010 | 0.436 | 0.023 | 9.8..29.5 (peaks) | Barely unstable; cascade at t~30 |
| 3 | NEW | **−0.011** | 0.362 | <0 | 9.8..24.5 (peaks) | Damped; killed t=29.5 |
| 4 | NEW | **+0.010±0.01** | 0.315 | 0.032 | 9.8..34.4 (peaks) | Marginally unstable (within error of kz=3) |
| 5 | NEW | **+0.005** | 0.282 | 0.018 | 9.8..24.5 (peaks) | Marginally unstable (within noise) |
| 6 | NEW | **−0.006** | 0.258 | <0 | 9.8..29.5 (envelope) | Confirmed: peak→decline, -0.006 TU⁻¹ |

NEW* = Phase 2 new-binary run in progress at time of this writing.

**Phase 2 k=1 full data (combined Phase 1 + Phase 2)**:

| t (TU) | By2[kz=1] | Az2[kz=1] | Notes |
|--------|-----------|-----------|-------|
| 0.0 | 1.250e-6 | — | seed |
| 4.9 | 2.590e-6 | — | |
| 9.8 | 3.704e-6 | — | |
| 14.7 | 3.360e-6 | — | |
| 19.6 | 3.145e-6 | 2.438e-5 | |
| 24.5 | 4.894e-6 | 5.861e-5 | ← linear KH onset |
| 29.5 | 7.690e-6 | 1.690e-4 | ← cascade trigger (Az2≈1.7e-4) |
| 34.4 | 1.480e-5 | 5.210e-4 | cascade dominant |
| 39.3 | 4.005e-5 | 1.544e-3 | γ≈0.203 TU⁻¹ |
| 44.2 | 1.200e-4 | 4.904e-3 | γ≈0.218 TU⁻¹ = α×V0 |
| 49.1 | 3.700e-4 | 1.613e-2 | γ≈0.225 TU⁻¹ |
| 54.0 | 1.157e-3 | 4.933e-2 | γ≈0.228 TU⁻¹ |
| 58.9 | 2.651e-3 | 1.261e-1 | KH nonlinear saturation begins |
| 63.8 | 3.343e-3 | 2.177e-1 | γ slowing (0.046 TU⁻¹) |
| 68.7 | NaN | NaN | NaN (density explosion) |

**γ_KH(kz=1) = 0.090 TU⁻¹** from linear window t=24.5..29.5 (before precession cascade).

**Precession cascade (kz=1)**: At t=29.5, Az2[kz=1]≈1.7e-4 (= 0.17% of Az1=V0=0.1). By2 then grows at γ≈0.21-0.23 TU⁻¹ = α×V0 (color precession rate) from t=29.5 to t=54 TU. This is NOT KH growth — it is the Az2 precession mode feeding back into By2 through the Q3→Q2→Lorentz path. The true linear KH window is t=24.5..29.5 (~5 TU wide). All γ estimates over wider ranges are contaminated by the cascade.

**kz=2 early data (NEW binary)**:

| t (TU) | By2[kz=2] | Az2[kz=2] |
|--------|-----------|-----------|
| 0.0 | 1.250e-6 | 0 |
| 9.8 | 3.605e-6 | 1.744e-6 | ← peak 1 |
| 14.7 | 2.865e-6 | 5.446e-6 | |
| 19.6 | 3.839e-6 | 1.374e-5 | ← peak 2 |
| 24.5 | 2.919e-6 | 4.100e-5 | |
| 29.5 | 4.703e-6 | 1.379e-4 | ← peak 3 |
| 34.4 | 8.475e-6 | 4.494e-4 | ← cascade starting |

Peak envelope growth: t=9.8→19.6 (γ≈0.006 TU⁻¹), t=19.6→29.5 (γ≈0.020 TU⁻¹). Cascade onset at t≈29-34 when Az2≈1.4-4.5e-4 (same Az2 level as kz=1). **γ_KH(kz=2) ≈ 0.010 TU⁻¹** (peak envelope pre-cascade).

**kz=3 (NEW binary)**: Peaks at t=9.8 (3.56e-6), 14.7 (4.26e-6 — max), 24.5 (3.82e-6 — declining). **γ_KH(kz=3) = −0.011 TU⁻¹** (damped — KH stable). Az2[3]=8.3e-5 at t=29.5 (below cascade threshold of ~1.5e-4).

**Stability summary**: All of kz=2..6 have |γ| ≤ 0.012 TU⁻¹, within the ±0.012 TU⁻¹ measurement noise floor (from 4.9 TU snapshot intervals × oscillation amplitude). WKB predicts γ>0.26 TU⁻¹ for all kz=1..6 (monotonically decreasing). The simulated mode IS a non-Abelian KH mode — only kz=1 is measurably unstable.

**kz=4 (NEW binary)**: Peaks at t=9.8 (3.76e-6), t=19.6 (4.24e-6), and t=34.4 (4.80e-6). γ_peaks ≈ +0.010 TU⁻¹ (within noise ±0.012 TU⁻¹). Cascade onset at t≈34 TU when Az2≈1.3e-4.

**kz=5 (NEW binary, campaign script)**: Peaks at t=9.8 (3.98e-6) and t=24.5 (4.30e-6). **γ_KH(kz=5) = +0.005 TU⁻¹** (barely above zero; within measurement noise ±0.01 TU⁻¹). Precession cascade at t>34 TU.

**kz=6 (NEW binary)**: Peak at t=9.8 (4.13e-6), then slowly DECREASING to t=29.5 (3.64e-6). **γ_KH(kz=6) = −0.007 TU⁻¹** (damped). Confirmed by separate run (t=0..49.1 TU).

**Complete dispersion summary**: kz=1 is clearly unstable (γ=0.090 TU⁻¹ = 7.5σ above noise). kz=2..6 all have |γ| ≤ 0.011 TU⁻¹ — within ±0.012 measurement uncertainty. The non-Abelian KH instability in Mode 5 (cosine Az1, EPS=0.15, α=2, V0=0.1) is effectively **single-mode: only kz=1 is measurably unstable**. The WKB prediction of broad-band instability (γ=0.26-0.55 TU⁻¹ for kz=1..6) is catastrophically wrong for the cosine Az1 geometry.

**WKB polynomial (eq. 33, wkb.pdf) for α=2, V0=0.1, n=0**:
```
ω⁴ − kz²ω² − 0.200ω − 0.400×kz = 0
```
where C = α^(3/2)×V0/√2 = 0.200, α²V0 = 0.400.

**Key finding — geometric mismatch**: The WKB polynomial (eq. 33) was derived for the log-cosh Az1 geometry, where the coupling well is centred AT the shear layer (ξ=0). In Mode 5 (cosine Az1), the Az1 potential has a MAXIMUM (+V0) at the shear centre x=3π and MINIMA (−V0) at x=0,2π,4π — far from the shear layer. This is an anti-well at the shear centre, so the WKB trapped-mode eigenvalue (which requires a well at ξ=0) is NOT applicable to Mode 5.

The observed KH growth in Mode 5 is a GLOBAL (non-trapped) instability driven by the closed loop By2→Ez2→Az2→Q3→Q2→Lorentz→By2. Its growth rate (0.090 TU⁻¹ at kz=1) is **6× below** the WKB prediction. The stability cutoff is near **kz_c≈2.4** (kz=2: γ=+0.010 TU⁻¹ unstable; kz=3: γ=−0.011 TU⁻¹ damped). WKB incorrectly predicts instability for all kz=1..6 with a much higher cutoff.

**Precession cascade contamination**: For ALL kz, Az2[kz] grows at γ≈α×V0=0.20 TU⁻¹ (color precession) regardless of KH stability. Once Az2≈1-5e-4, it acts as a secondary Az1-like background and drives secondary By2 growth through the same feedback loop. This cascade typically starts at t≈29-34 TU and makes By2 grow at γ≈0.20-0.23 TU⁻¹ — masking the true KH rate at late times. The linear KH window for each kz is only the period BEFORE the cascade trigger, typically t≈4-30 TU.

---

## Campaign 17 — NAB_CIRC (Mode 1), α=0.5, reduced cascade (abi, COMPLETE)

**Status**: Complete. All kz=1..6 finished on abi (3× GTX 1080 Ti). Script: `run_campaign17_abi.sh`.

**Setup**: Mode 1 (NAB_CIRC, log-cosh Az1), `alpha=0.5`, `V0=0.1`, `EPS=0.15`, `xi_sponge=20.0`, `suppress_kz0=1`, `hyp_diff=5e-5`, `BP=14`.

**Run durations** (all NaN at end — nonlinear blowup, not energy threshold):

| kz | NaN halt (TU) | Snapshots |
|----|--------------|-----------|
| 1 | 112.9 | 24 |
| 2 | 105.5 | 22 |
| 3 | 112.9 | 24 |
| 4 | 120.3 | 25 |
| 5 | 130.1 | 27 |
| 6 | 135.0 | 28 |

Runs lasted 105–135 TU — 2–3× longer than Campaign 16 (40–74 TU), confirming that lower α suppresses early blowup.

**Sustained growth rates (log-linear fit, linear phase only)**:

| kz | window (TU) | γ_By2 | γ_Az2 | Az2/By2 (mid) | Interpretation |
|----|------------|-------|-------|---------------|----------------|
| 1 | 29–108 | **+0.119** | **+0.118** | 71 | **Co-growth → eigenmode** |
| 2 | 29–98 | +0.126 | +0.143 | 153 | Partial (Az2 slightly faster) |
| 3 | 29–108 | +0.113 | +0.134 | 317 | Cascade (Az2>By2) |
| 4 | 29–118 | +0.091 | +0.126 | 614 | Cascade |
| 5 | 29–122 | +0.062 | +0.121 | 580 | Cascade |
| 6 | 29–132 | +0.053 | +0.114 | 382 | Cascade |

**Key finding — kz=1 eigenmode at α=0.5**:

kz=1 shows near-identical γ_By2=0.119 and γ_Az2=0.118 TU⁻¹ from t≈34–108 TU with Az2/By2≈70 (approximately constant). This is the eigenmode co-growth signature. The large ratio (70 vs ~5 in C16 kz=1) is expected from the WKB relation Az2~∂xBy2/γ²: at lower γ (0.119 vs 0.281) and wider mode (σ=0.671 vs 0.336), the amplitude ratio scales as ~(γ_C16/γ_C17)²×(σ_C17/σ_C16) ≈ (2.4)²×2 ≈ 11× larger.

**Scaling with α**:

| α | γ(kz=1, Mode 1) | γ ratio | α ratio^0.5 |
|---|-----------------|---------|-------------|
| 2.0 (C16) | 0.281 TU⁻¹ | 1.00 | 1.00 |
| 0.5 (C17) | 0.119 TU⁻¹ | 0.42 | 0.50 |

γ scales approximately as α^0.5 (measured ratio 0.42 vs theoretical 0.50 for square-root scaling). Exact WKB scaling requires the eigenvalue solver (Option 2).

**Why kz≥2 are still cascade-dominated at α=0.5**:

The effective cascade rate in Mode 1 is NOT simply α×V0 = 0.05 TU⁻¹. The measured cascade rate is γ_Az2 ≈ 0.11–0.14 TU⁻¹ for all kz. At α=0.5, the WKB eigenmode for kz=1 has ξ_char=4.47 EPS-units — much wider than at α=2 (ξ_char=2.24). The mode extends into the outer region (|ξ|>2) where Az1=-V0·log(cosh(ξ)) ≠ 0, coupling to the cascade. The cascade operates through this outer overlap even in Mode 1. For kz≥2, the modes are narrower (ξ_char<4.47) but the cascade still appears to be driven by modes at the outer boundary region at a fixed rate ≈0.11–0.14 TU⁻¹.

**Conclusion**: Lowering α to 0.5 reduces γ_KH but does NOT proportionally reduce γ_cascade (which stays ≈0.11–0.14 TU⁻¹ regardless of kz). The cascade floor cannot be pushed below ~0.10 TU⁻¹ in Mode 1 at any α with the By2 seed strategy. The eigenmode seeding approach (Campaign 18, Mode 6) is required to bypass the cascade entirely.

---

## Campaign 18 — NAB_CIRC_AZ2 (Mode 6), Gaussian Az2 seed (t136)

**Status**: COMPLETE kz=1..6 (t136 RTX A5000). kz=6 halted at t=58.9 TU (NaN). Script: `run_campaign18_t136.sh`.

**Setup**: Mode 6 (NAB_CIRC_AZ2), `alpha=2.0`, `V0=0.1`, `EPS=0.15`, `xi_sponge=10.0`, `sigma_sponge=5.0`, `suppress_kz0=1`, `hyp_diff=5e-5`, `BP=14`, kz=1..6. Sequential (single GPU).

**Key change — run_mode=6 (NAB_CIRC_AZ2)**:
- Seeds `Az2/Az3` with WKB n=0 Gaussian: `A₀·exp(−ξ²/2ξ_char²)·(cos,sin)(kz·z)`
- `ξ_char = 1/sqrt(α·kz·V0)` (computed in init kernel using `alpha_YM`)
- `By2=By3=0` at t=0 — they grow from Az2 via the KH chain
- `Az1 = −V0·log(cosh(ξ))` (same as Mode 1, frozen)

**Results (corrected weight — sech centred at LX/2 with width EPS·ξ_char)**:

⚠️ **Note**: `dispersion_ym.py` default (xi_cut=-1 uniform weight) gives WRONG growth rates for NAB_CIRC runs because the sponge zeros all fields at |ξ|>10 (|x−LX/2|>1.5), leaving only numerical noise at LX/3 and 2·LX/3 where the script peaks. All C18 rates below use corrected sech weight.

| kz | halt (TU) | γ_By(corr) | γ_Az(corr) | γ_WKB | γ_exact(solver) | Az/By(eig) | sim_Az/exact |
|----|-----------|-----------|-----------|-------|-----------------|-----------|-------------|
| 1 | 49.1 (NaN) | **0.279** | 0.296 | 0.553 | **0.267** | 6.6 | 1.11 |
| 2 | 68.7 (NaN) | 0.138† | **0.173** | 0.436 | **0.199** | 45.8 | 0.87 |
| 3 | 54.0 (NaN) | **0.212** | 0.212 | 0.362 | **0.237** | 74.6 | 0.90 |
| 4 | 54.0 (NaN) | **0.218** | 0.220 | 0.309 | **0.248** | 109.7 | 0.89 |
| 5 | 68.7 (NaN) | 0.146† | **0.175** | 0.278 | **0.211** | 122.7 | 0.83 |

†γ_By biased low for large Az/By eigenmodes (By builds from zero while Az is seeded directly; γ_Az is the correct measure).

**γ_exact** from `ym_eigenmode.py` (scipy shift-invert, xi_sponge=10, sigma_sponge=5, NX=384).

**Physics interpretation**:

The instability in NAB_CIRC is **not** a classical KH mode at the shear centre (ξ=0). It is a **non-Abelian EM instability** that peaks at the outer region where Ω_A = kz + αAz1 approaches zero:

- **Transition radius**: ξ_crit = kz/(αV0). For kz=1: ξ_crit=5 (inside sponge at 10); for kz≥3: ξ_crit≥15 (outside sponge).
- **kz=1** (ξ_crit=5): eigenmode peaks at ξ=9.49 (outer EM instability within sponge). Eigenvalue solver finds this cleanly at γ=0.267. Simulation matches within 5%.
- **kz≥3** (ξ_crit≥15): outer EM mode fully killed by sponge. Solver finds sponge-boundary modes (ξ=10.14) — these modes are partially damped by the sponge, so simulation grows ~10% slower than solver predicts.
- **Az/By ratio** grows with kz (6.6 → 122.7), reflecting increasing importance of the Az2 precession loop relative to Faraday back-reaction.

**WKB comparison** (γ_WKB from eq. 33, wkb.pdf, n=0):
- All kz: γ_exact/γ_WKB = 0.48–0.80 (WKB overestimates by 25–110%)
- The WKB assumes a parabolic harmonic trap at ξ=0 — the log-cosh potential is shallower there, AND the actual mode lives in the outer region (not at ξ=0), compounding the discrepancy.

**1D eigenvalue solver** (`ym_eigenmode.py`, added 2026-07-01):
- 6N×6N complex sparse matrix: [b, ex, ez, a, qA, qB] blocks
- Includes Doppler-shifted precession: (γ ± ikzVz)·q = iαVz·a (Doppler shift was missing in initial derivation, adds ikzVz·q term)
- Shift-invert ARPACK via scipy; sponge matching simulation (xi_sponge=10, σ=5)
- Matches simulation γ to within 5–20%; locates mode peaks and Az/By ratio

**Comparison across campaigns**:

| kz | γ_WKB | C16 (By2 seed) | C17 (α=0.5) | C18 γ_Az (Az2 seed) | C18/WKB |
|----|-------|----------------|-------------|---------------------|---------|
| 1 | 0.553 | 0.281 (eigenmode) | 0.119 (eigenmode) | **0.296** | **0.54** |
| 2 | 0.436 | ≤0.20 (cascade) | 0.126 (cascade) | **0.173** | **0.40** |
| 3 | 0.362 | ≤0.23 (cascade) | 0.113 (cascade) | **0.212** | **0.59** |
| 4 | 0.309 | ≤0.24 (cascade) | 0.053–0.091 (cascade) | **0.220** | **0.71** |
| 5 | 0.278 | ≤0.24 (cascade) | 0.053–0.091 (cascade) | **0.175** | **0.63** |

---

## Campaign 19 — α=4.0, V0=0.1, Mode 6 (t136, 2026-07-02)

**Setup**: Same as C18 but `alpha=4.0`. `xi_sponge=10.0`, `sigma=5.0`, kz=1..6.

**Outer-region EM instability rate** at ξ=10 (sponge edge, inner boundary of sponge-free unstable region):
- Ω_A(ξ=10) = kz + α·Az1(10) = kz - 4.0·V0·log(cosh(10)) ≈ kz − 3.72
- kz=1: Ω_A = −2.72, γ_outer ≈ √(2.72×4.72) ≈ **3.6 TU⁻¹** (vs ~1.6 TU⁻¹ for C18)

**Results**:

| kz | halt (TU) | γ_By | γ_Az | γ_WKB | γ_exact(solver) | Az/By | sim/ex | verdict |
|----|-----------|------|------|-------|-----------------|-------|--------|---------|
| 1 | 9.8 | **2.03** | 1.12 | 0.823 | 0.213 | 0.3 | 5.25 | outer EM dominated — By>Az, γ>>prediction |
| 2 | 14.7 | **1.31** | 0.25 | 0.775 | 0.198 | 0.8 | 1.27 | outer EM dominated |
| 3 | 29.5 | 0.16 | **0.18** | 0.683 | 0.252 | 55 | 0.71 | partial KH signal |
| 4 | 29.5 | 0.22 | **0.20** | 0.608 | 0.301 | 60 | 0.65 | partial KH signal |
| 5 | 29.5 | 0.23 | **0.19** | 0.551 | 0.317 | 87 | 0.60 | partial KH signal |
| 6 | 29.5 | 0.23 | **0.18** | 0.507 | 0.322 | 119 | 0.56 | partial KH signal |

**Verdict**: α=4.0 with xi_sponge=10 is too aggressive. The outer EM instability at kz=1,2 grows at γ≈3-4 TU⁻¹ and dominates before KH can establish. kz=3..6 survive to 29.5 TU, giving partial data, but sim/ex=0.56-0.71 (worse than C18 at 0.83-1.11) because: (a) the strong outer EM instability contaminates the field even at kz=3 where ξ_crit=7.5 ≈ ξ_sponge/1.33, and (b) only 7 snapshots provide a noisy fit.

**Rule**: xi_sponge must satisfy ξ_crit(kz_min)/xi_sponge ≥ 0.45 to keep γ_outer manageable. For α=4, kz=1: ξ_crit=2.5 → safe xi_sponge ≤ 5.5. C19 used xi_sponge=10, violating this by 2×.

---

## Campaign 20 — α=2.0, V0=0.2, Mode 6 (t130, 2026-07-02) — FAILED

**Setup**: Same as C18 but `V0=0.2`. `xi_sponge=10.0`, `sigma=5.0`, kz=1..6.

**Failure**: ALL kz NaN at t=2.45 TU (only the initial snapshot captured). With V0=0.2:
- Az1(ξ=10) = −0.2·log(cosh(10)) ≈ −1.861 → Ω_A(kz=1) = 1 − 2×1.861 = −2.72
- γ_outer(kz=1) ≈ √(2.72×4.72) ≈ **3.6 TU⁻¹** (same as C19 kz=1 — same αAz1 product)
- At γ=3.6 TU⁻¹ growing from seed A0=0.001: hits 100×E0 in ~2-3 TU. Confirmed.

**Fix for redo**: Use xi_sponge ≤ 5 matched to ξ_crit(kz=1)=2.5, with sigma=15.

---

## Campaign 21 — α=3.0, V0=0.1, Mode 6 (abi, 2026-07-02) — FAILED

**Setup**: Same as C18 but `alpha=3.0`, compiled for sm_61. `xi_sponge=10.0`, `sigma=5.0`, kz=1..6.

**Failure**: ALL kz NaN at t=2.45 TU. With α=3.0:
- Ω_A(kz=1, ξ=10) = 1 − 3×0.1×9.307 ≈ −1.79 → γ_outer ≈ **2.9 TU⁻¹**
- Note: abi binary compiled fresh for sm_61 (GTX 1080 Ti), worked correctly.

**Fix for redo**: xi_sponge=6.0, sigma=15 — sponge below ξ_crit(kz=1)=3.3 is impossible, but xi_sponge=6 reduces the free-growth region to ξ_crit→6, where γ_outer(ξ=6) is manageable.

---

## Outer-region EM instability — sponge design rule (2026-07-02)

The outer-region EM instability grows at `γ_outer(ξ) ≈ √(|Ω_A(ξ)|·Ω_F(ξ))` throughout the unstable region ξ_crit < |ξ| < ξ_sponge. The sponge boundary controls the maximum exposed region. Key:

- **C18 (α=2, V0=0.1)**: γ_outer(ξ=8) ≈ 1.1 TU⁻¹ → run lasts 50 TU ✓
- **C19 (α=4, V0=0.1)**: γ_outer(ξ=8) ≈ 2.7 TU⁻¹ → kz=1,2 dominated in 10-15 TU ✗
- **C20 (α=2, V0=0.2)**: γ_outer(ξ=8) ≈ 2.7 TU⁻¹ → NaN at 2.45 TU ✗
- **C21 (α=3, V0=0.1)**: γ_outer(ξ=8) ≈ 2.0 TU⁻¹ → NaN at 2.45 TU ✗

**Design rule**: for a stable run at higher α or V0, xi_sponge must satisfy
`γ_outer(xi_sponge) ≤ 1.5 TU⁻¹` (empirically safe from C18).
This means: **xi_sponge ≤ ξ where |Ω_A(ξ)| = (1.5)²/Ω_F(ξ)**.

For the next α/V0 sweep, use **xi_sponge matched per-campaign** + sigma=15–20.

---

## Campaigns 19b / 20b / 21b / 22 — redo with matched sponge (2026-07-02)

### Root cause: stale binary (C20 / C21 / C20b-first / C21b-first)

C20, C21, and the FIRST attempts at C20b and C21b ALL failed at t=2.45 TU **not** because of physics but because **t130 and abi had stale binaries** compiled before Mode 6 (NAB_CIRC_AZ2) was added to the source. The binary treated `run_mode=6` as mode 0 (NAB_LINEAR), running a wall-BC simulation with evolving Az1 and By2 seed — incompatible initialisation that NaN'd in the first 10000 steps.

Diagnostics:
- Run log showed `mode=NAB_LINEAR` instead of `mode=NAB_CIRC_AZ2` for run_mode=6
- E0=351576 (C20b) and E0=87894 (C21b) — far above the expected 7864 and 1935 from fluid KE alone, consistent with Mode 0 including By1 energy from its gauge initialisation
- `strings ym_coupled | grep NAB_` on t130/abi showed no `NAB_CIRC_AZ2` string

**Fix**: synced all `.cu/.cuh` source to t130 and abi, recompiled with `/usr/local/cuda-12.4/bin/nvcc -arch=sm_86` on t130 (driver supports ≤12.8; the default PATH nvcc was CUDA 13.0, incompatible) and `sm_61` on abi. Both binaries now confirmed to have `NAB_CIRC_AZ2`. Note: t130 and t136 have SEPARATE local disks despite listing the same `/DATA/cm/lcpfct/ymgpu2d/` path — t136 had the correct binary from C18 compile; t130 did not.

### Eigenvalue solver — sigma parameter note

`ym_eigenmode.py` has two distinct sigma parameters:
- `--sigma` (float, default None): **ARPACK shift-invert target** — should be near the expected eigenvalue (~0.1–0.3). Auto-set from WKB×0.55 if omitted. DO NOT set to sponge value.
- `--sigma-sponge` (float, default 5.0): **sponge damping strength** matching the simulation's sigma_sponge.

Passing `--sigma 15.0` (wrong!) sets ARPACK target to 15.0 — far from actual eigenvalues (~0.1), causing ARPACK to fail to converge after 40+ minutes. Correct command for simulations with sigma=15: `--sigma-sponge 5.0` (reduced for numerical stability) with no `--sigma` override.

### Campaign status (final)

| Campaign | Server | α | V0 | xi_sponge | σ_sim | γ_outer@edge | Status |
|----------|--------|---|-----|-----------|-------|-------------|--------|
| 19b | t136 | 4.0 | 0.1 | **5.0** | 15 | ≈1.57 TU⁻¹ | kz=1..3 DONE; kz=4..6 KILLED (sponge-damped — ξ_peak=5.24>xi=5) |
| 20b | t130 | 2.0 | 0.2 | **5.0** | 15 | ≈1.57 TU⁻¹ | kz=1..4 DONE, kz=5 running; no clean measurements (poor seed + oscillatory) |
| 21b | abi | 3.0 | 0.1 | **6.0** | 15 | ≈1.66 TU⁻¹ | kz=1..3 DONE, kz=4..6 pending; kz=1 EXCELLENT (sim/ex=1.02) |
| 22 | t136 | 1.0 | 0.05 | **10.0** | 5 | 0 TU⁻¹ | kz=1 running at t≈155 TU; prelim γ=0.083 (exact=0.080, sim/ex=1.04) |

---

### Campaign 19b — α=4.0, V0=0.1, xi_sponge=5.0 — RESULTS

**Eigenvalue solver** (`--sigma-sponge 5.0`, xi_sponge=5):

| kz | γ_exact | Im(γ) | γ_WKB | ex/WKB | ξ_peak |
|----|---------|-------|-------|--------|--------|
| 1 | 0.085 | +0.064 | 0.823 | 0.103 | −3.27 **(inside sponge)** |
| 2 | 0.189 | 0 | 0.775 | 0.243 | −5.24 (at sponge edge) |
| 3..6 | 0.241..0.280 | 0 | 0.508–0.683 | 0.35–0.55 | −5.24 |

**Simulation vs eigenvalue** (`dispersion_ym.py --field Az_circ`):

| kz | halt (TU) | γ_Az_sim | γ_exact | sim/ex | verdict |
|----|-----------|----------|---------|--------|---------|
| 1 | 73.6 (NaN) | **0.055** | 0.085 | 0.65 | oscillatory (Im=+0.064); phase-dependent underestimate |
| 2 | 61.4 (NaN) | 0.084 | 0.189 | 0.44 | ξ_peak=5.24 outside xi=5 → sponge-damped |
| 3 | 49.1 (NaN) | 0.105 | 0.241 | 0.44 | same — sponge-damped |
| 4..6 | — | (killed) | 0.267..0.280 | — | killed: same ξ_peak=5.24, no added info |

**Why sim/ex=0.65 for kz=1 (oscillatory)**: Im(γ)=+0.064 means the amplitude of the real-valued Az2 field oscillates as exp(0.085t)×cos(0.064t+φ). The fit picks up a phase-biased apparent rate. Depending on initial phase φ, sim/ex can range 0.5–1.2. At α=4, V0=0.1 with ξ_peak=3.27 inside xi_sponge=5, the mode IS measurable but the oscillatory eigenvalue introduces systematic phase uncertainty.

**Conclusion**: Tight sponge (xi_sponge=5) prevents outer EM but compresses the confinement well [ξ_crit=2.5, xi=5] to only 2.5 ξ-units. Only kz=1 (ξ_peak=3.27 inside well) is measurable. At larger α, ξ_crit shrinks further, making the well even narrower and the eigenvalue increasingly oscillatory.

---

### Campaign 20b — α=2.0, V0=0.2, xi_sponge=5.0 — NO CLEAN MEASUREMENTS

**Eigenvalue solver** (`--sigma-sponge 5.0`, xi_sponge=5):

| kz | γ_exact | Im(γ) | γ_WKB | ex/WKB | ξ_peak |
|----|---------|-------|-------|--------|--------|
| 1 | 0.113 | −0.087 | 0.628 | 0.181 | −3.27 **(inside sponge)** |
| 2 | 0.250 | 0 | 0.564 | 0.442 | −5.24 (at sponge edge) |
| 3 | 0.301 | 0 | 0.489 | 0.617 | −5.24 |
| 4..6 | 0.316..0.307 | 0 | 0.359–0.432 | 0.73–0.86 | −5.24 |

**Simulation results** (from kz=1..4 completed):

| kz | halt (TU) | γ_Az_sim | γ_exact | sim/ex | verdict |
|----|-----------|----------|---------|--------|---------|
| 1 | 68.7 (NaN) | **0.057** | 0.113 | **0.50** | poor — oscillatory + bad seed projection |
| 2 | 54.0 (NaN) | 0.111 | 0.250 | 0.44 | sponge-damped (ξ_peak=5.24 at edge) |
| 3 | 39.3 (NaN) | 0.066 | 0.301 | 0.22 | sponge-damped (R²=0.78, noisy) |
| 4 | 39.3 (NaN) | 0.069 | 0.316 | 0.22 | sponge-damped (R²=0.78, noisy) |

**Why kz=1 fails (double failure)**:
1. **Oscillatory eigenvalue**: Im(γ)=−0.087 (period T=72 TU). The amplitude oscillates while growing, causing systematic fit underestimation (~50% of the envelope depending on phase at fit window).
2. **Poor seed projection**: WKB Gaussian seed is centered at ξ=0 (ξ_char=1.58) but eigenmode peaks at ξ_peak=3.27. Overlap integral ∝ exp(-3.27²/(2×1.58²)) ≈ 0.01. Mode must grow from float32 numerical noise (~1e-7 in Az); by t=65 TU the growing mode barely emerges from the seed level (~1.6e-4 → 1.3× the seed amplitude). Fit captures transient, not eigenmode.
3. **kz=2..4**: ξ_peak=5.24 at xi_sponge=5.0 → sponge damps mode, sim/ex=0.22–0.44 not meaningful.

**Conclusion**: C20b provides no clean measurements. The combination of tight sponge (xi_sponge=5), strongly oscillatory kz=1 eigenvalue, and poor Gaussian seed overlap means kz=1 cannot be reliably measured without either: (a) a longer run well past 100 TU, or (b) a seed centered at ξ=3.27 matching the eigenmode. C20b is not useful for WKB validation.

---

### Campaign 21b — α=3.0, V0=0.1, xi_sponge=6.0 — kz=1 CLEAN

**Eigenvalue solver** (`--sigma-sponge 5.0`, xi_sponge=6):

| kz | γ_exact | Im(γ) | γ_WKB | ex/WKB | ξ_peak |
|----|---------|-------|-------|--------|--------|
| 1 | 0.076 | −0.058 | 0.671 | 0.113 | −4.25 **(inside sponge)** |
| 2 | 0.193 | 0 | 0.602 | 0.320 | −6.22 (at sponge edge) |
| 3..6 | 0.237..0.260 | 0 | 0.382–0.520 | 0.46–0.68 | −6.22 |

**Simulation results** (kz=1..3 done, kz=4..6 pending):

| kz | halt (TU) | γ_Az_sim | γ_exact | sim/ex | verdict |
|----|-----------|----------|---------|--------|---------|
| 1 | 81.0 (NaN) | **0.078** | 0.076 | **1.02** | ✓ CLEAN — mode inside sponge, favorable phase |
| 2 | 71.2 (NaN) | 0.086 | 0.193 | 0.44 | ξ_peak=6.22 > xi_sponge=6 → sponge-damped |
| 3 | running | — | 0.237 | — | same — sponge-damped expected |

**Why kz=1 gives sim/ex=1.02**: Im(γ)=−0.058 causes phase rotation in the complex Az_circ amplitude, but |Az_circ| = exp(Re(γ)t) without oscillation in the modulus — the imaginary part rotates the phase, not the magnitude. The fit of |Az_circ| directly measures Re(γ)=0.076. The favorable initial phase (seed projection onto eigenmode approximately aligned with peak of cosine oscillation) gives R²=1.000 and clean exponential fit.

**Conclusion**: α=3, V0=0.1, xi_sponge=6 is a valid measurement point for kz=1. ξ_crit(kz=1)=3.33, ξ_peak=4.25, xi_sponge=6: the mode is 71% of the way to the sponge — well contained. Only kz=1 measurable; kz≥2 have ξ_peak at the sponge edge.

---

### Campaign 22 — α=1.0, V0=0.05, xi_sponge=10.0 — RUNNING

**Design**: ξ_crit(kz=1) = kz/(α×V0) = 1/(1×0.05) = 20 >> xi_sponge=10. The outer EM instability starts at ξ=20, entirely outside the sponge. **No outer EM concern at all.** Growing modes are inner KH modes (no tight-sponge trade-off). WKB is better approximated at small α×V0.

**Eigenvalue solver** (`--sigma-sponge 5.0`, xi_sponge=10):

| kz | γ_exact | Im(γ) | γ_WKB | ex/WKB | ξ_peak | Az/By |
|----|---------|-------|-------|--------|--------|-------|
| 1 | 0.080 | 0 | 0.203 | 0.39 | −10.14 (sponge boundary) | 94 |
| 2 | 0.110 | 0 | 0.153 | 0.71 | −10.14 | 180 |
| 3 | 0.120 | 0 | 0.127 | 0.94 | −10.14 | 313 |
| 4 | 0.122 | 0 | 0.111 | 1.10 | −10.14 | 511 |
| 5 | 0.119 | 0 | 0.099 | 1.20 | −10.14 | 795 |
| 6 | 0.115 | 0 | 0.091 | 1.27 | −10.14 | 1190 |

All modes peak at the sponge boundary (ξ=10.14), pure real eigenvalues (Im=0). WKB accuracy varies: 39% for kz=1 to 127% for kz=4–6 (WKB transitions from overestimate to underestimate near kz=3–4).

**Preliminary simulation result** (kz=1 at t≈155 TU, 22 snapshots):

| kz | γ_Az_sim (prelim) | γ_exact | sim/ex | verdict |
|----|------------------|---------|--------|---------|
| 1 | **0.083** | 0.080 | **1.04** | ✓ CLEAN — R²=1.000, running |

**Status (2026-07-02)**: kz=1 still running at t=155 TU; kz=2..6 pending. Expected halt around t=185 TU (energy threshold 100×E0). All kz modes expected at sponge boundary (same as C18 kz=2..5 regime with sim/ex≈0.85–0.90).

---

## Known Issues / Unresolved

| Issue | Status |
|-------|--------|
| FCT NaN wall at t=63–71 TU in NAB_DTANH | Bypassed by switching to mode 5 (NAB_TANH_COSAZ). |
| kz=0 Weibel mode | Suppressed by suppress_kz0=1 + hyp_diff=5e-5. |
| KH mode at kz≥1 not observable in DTANH | Resolved: mode 5 confirms KH IS growing (γ≈0.11 TU⁻¹ at kz=1, EPS=0.15). |
| Color-1 EM instability (all kz incl. k_mode) | Fixed in Campaign 15 by cudaMemset By1/Ex1/Ez1=0 each step. |
| Color-1 fluid two-stream (kz=1..14) | Fixed in Campaign 12 by fluid pz bandpass (BP=14). |
| NAB_STEP ruled out | Confirmed fatal (Campaigns 7 and 9). |
| WKB dispersion comparison | C15 (Mode 5): γ(kz=1)=0.090, ratio 0.16. C16 (Mode 1): γ(kz=1)=0.281, ratio 0.51. C18 (Mode 6, Az2 seed): γ_Az(kz=1..5)=0.296/0.173/0.212/0.220/0.175. Eigenvalue solver (ym_eigenmode.py) matches C18 to 5–20% (sim/ex=0.83–1.11). WKB overestimates by 25–110%; outer-region EM mode (not classical KH) dominates. |
| Precession cascade contamination | Resolved in C18 by seeding Az2 directly (Mode 6) instead of By2 — bypasses cascade build-up. kz=2..5 now measurable for first time. |
| WKB geometry mismatch (Mode 5) | Resolved by C16: log-cosh Az1 (Mode 1) gives 3× better WKB match. |
| Outer-region EM instability at higher α/V0 | C19/C20/C21 failures: growing faster than sponge can damp for α≥3 or V0≥0.2 at xi_sponge=10. Fix: xi_sponge=2/(α·V0), sigma=15. C19b/C20b/C21b running with corrected sponge + corrected binary. |
| Stale binary on t130/abi | C20b-first and C21b-first also failed because t130 and abi had binaries compiled before Mode 6. Fix: scp all source + recompile with cuda-12.4 (t130 driver=12.8, not 13.0) and sm_61 (abi). C20b now shows E0=7739 (correct). |
| Tight sponge trade-off for large α | At α=4, xi_sponge=5 prevents outer EM but also damps kz≥2 (ξ_peak≈5.24 at sponge edge). Only kz=1 clean for α=4, V0=0.1. WKB overestimates by factor 10–15 at large α. |
| `_bp28`/half-integer-kz sweep contamination (2026-07-14) | **PARTIALLY FIXED, scope-limited (root cause: xi_sponge too loose, not a code bug, but V0-dependent).** The blind `xi_sponge_for()` formula pushes xi_sponge toward its 55 ceiling at low kz/low αV0, failing to exclude the already-documented outer-region EM instability (γ≈0.7-1.4 TU⁻¹). `analysis/find_safe_sponge.py` (eigensolver-based candidate finder) fixes this for V0≲0.05 (3/3 CUDA-confirmed points clean or near-clean at tightened sponge) but FAILS for V0=0.10 even at the sponge floor (blows up t≈91 instead of t≈38, not eliminated) — sponge-tightening alone is not universally sufficient, likely V0-dependent. Do not blindly rerun the V0≥0.08 suspect points with a tighter sponge and expect it to work. See dated sections at end of file. |

---

## Campaign 16 — NAB_CIRC (Mode 1, log-cosh Az1), WKB geometry test (2026-07-01)

**Setup**: `run_mode=1` (NAB_CIRC: log-cosh Az1, single tanh shear, periodic x, frozen Az1), `alpha=2.0`, `perturb_amp=0.001`, `V0=0.1`, `EPS=0.15`, `xi_sponge=10.0`, `sigma_sponge=5.0`, `suppress_kz0=1`, `hyp_diff=5e-5`, `BP=14`, `kz_suppress_max=k-1`. Ran on **abi** (farmerzone, 3× GTX 1080 Ti sm_61, ~4500 steps/min/GPU) in two parallel batches of 3. Script: `run_campaign16_abi.sh`.

**Motivation**: Campaign 15 (Mode 5, cosine Az1) showed only kz=1 unstable at γ=0.090 TU⁻¹, with WKB predicting 0.26–0.55 TU⁻¹ for all kz=1..6. The failure is geometric: cosine Az1 has a MAXIMUM (+V0) at the shear centre — an anti-well. The WKB eq. 33 requires Az1=0 at the shear centre with coupling growing outward (a confining well). Mode 1 uses `Az1 = −V0·log(cosh(ξ))`, which is zero at ξ=0 and grows as −V0|ξ|/EPS away from it — the correct WKB geometry. The sponge (xi_sponge=10) damps color-2/3 fields at |ξ|>10 to prevent the outer-region log-cosh coupling (α|Az1|≈12 at the periodic boundary) from building up; it also triggers the 100× energy threshold (vs 5× without sponge).

**WKB eigenmode scale**: n=0 mode characteristic width ξ_char = 1/√(α·kz·V0) EPS-units ≈ 2.24 (kz=1), 1.58 (kz=2), 1.29 (kz=3) — all well inside the sponge boundary (|ξ|=10).

**Data (max|By2| and max|Az2| per snapshot, growth rate γ per 4.9 TU interval)**:

**kz=1** (NaN t=41.7 TU):

| t (TU) | By2_max | γ_By2 | Az2_max | γ_Az2 |
|--------|---------|-------|---------|-------|
| 0.0 | 1.000e-04 | — | 0 | — |
| 4.9 | 1.537e-05 | −0.382 | 3.23e-05 | — |
| 9.8 | 4.390e-05 | +0.214 | 2.23e-04 | +0.395 |
| 14.7 | 1.766e-04 | **+0.284** | 9.76e-04 | +0.301 |
| 19.6 | 7.070e-04 | **+0.283** | 3.99e-03 | +0.287 |
| 24.5 | 2.818e-03 | **+0.282** | 1.61e-02 | +0.285 |
| 29.4 | 1.118e-02 | **+0.281** | 6.44e-02 | +0.283 |
| 34.3 | 4.313e-02 | **+0.276** | 2.54e-01 | +0.280 |
| 39.2 | 1.155e+00 | +0.671 | 8.28e-01 | +0.242 |

**kz=2** (E/E0=378 > 100, halt t=73.6 TU):

| t (TU) | By2_max | γ_By2 | Az2_max | γ_Az2 |
|--------|---------|-------|---------|-------|
| 0.0 | 1.000e-04 | — | 0 | — |
| 4.9 | 6.429e-06 | −0.560 | 1.01e-05 | — |
| 9.8 | 1.816e-06 | −0.258 | 1.98e-05 | +0.136 |
| 14.7 | 1.461e-06 | −0.044 | 5.61e-05 | +0.213 |
| 19.6 | 2.578e-06 | +0.116 | 1.52e-04 | +0.204 |
| 24.5 | 7.644e-06 | +0.222 | 3.85e-04 | +0.189 |
| 29.4 | 1.879e-05 | +0.184 | 9.69e-04 | +0.188 |
| 34.3 | 4.930e-05 | +0.197 | 2.50e-03 | +0.194 |
| 39.2 | 1.375e-04 | +0.209 | 6.61e-03 | +0.198 |
| 44.1 | 3.998e-04 | +0.218 | 1.76e-02 | +0.200 |
| 49.0 | 1.316e-03 | +0.243 | 4.70e-02 | +0.200 |
| 53.9 | 5.606e-03 | +0.296 | 1.24e-01 | +0.198 |
| 58.8 | 4.890e-02 | +0.442 | 3.40e-01 | +0.206 |
| 63.7 | 2.212e-01 | +0.308 | 7.54e-01 | +0.162 |
| 68.6 | 2.006e+00 | +0.450 | 9.47e-01 | +0.046 |
| 73.5 | 2.293e+01 | +0.497 | 1.03e+00 | +0.017 |

**kz=3** (NaN t=66.3 TU), **kz=4** (NaN t=63.8 TU), **kz=5** (NaN t=68.7 TU), **kz=6** (NaN t=63.8 TU) — summary in table below.

**Complete dispersion results**:

| kz | γ_WKB | γ_Mode5 | γ_Mode1 | Mode1/WKB | Interpretation |
|----|-------|---------|---------|-----------|----------------|
| 1 | 0.553 | 0.090 | **0.281** | 0.51 | Clean WKB eigenmode (By2/Az2 co-grow) |
| 2 | 0.436 | ≈0 | ≤0.20 (cascade) | — | Az2 leads By2 from t=4.9; cascade masked |
| 3 | 0.362 | ≈0 | ≤0.23 (cascade) | — | Same cascade pattern |
| 4 | 0.315 | ≈0 | 0.26–0.42 (late) | — | Cascade early; By2 > cascade rate at Az2~O(1) |
| 5 | 0.282 | ≈0 | 0.36–0.43 (late) | — | Same; By2 rate approaches WKB at nonlinear stage |
| 6 | 0.258 | ≈0 | 0.38–0.44 (late) | — | Same pattern |

**Key finding — kz=1 WKB mode confirmed**:

For kz=1, By2 and Az2 grow at **exactly the same rate** (γ=0.281±0.004 TU⁻¹) from t≈10 TU onward with no lag. This is the eigenmode signature: all fields in the KH chain (By2→Ez2→Az2→Q3→Q2→By2) evolve together. In the precession cascade pattern (Campaigns 14–15), Az2 LEADS By2. Here they co-evolve, confirming this is the genuine WKB trapped n=0 mode, not the cascade.

**γ(kz=1) = 0.281 TU⁻¹** — 3.1× higher than Mode 5 (0.090), confirming the geometric mismatch was dominant. Still **2× below WKB** (0.553).

**Remaining factor of 2 discrepancy (kz=1)**:

The WKB (eq. 33, khaxn.pdf) was derived for step-function velocity V₀z = v·sgn(x), which gives Az1 = v·x²/2 (parabola growing as x²). Mode 1 uses tanh velocity → log-cosh Az1, which grows as −V0|ξ|/EPS (linear) for large |ξ|, not quadratic. The effective confining potential for the eigenmode is shallower in Mode 1 than in the WKB step-potential — a shallower well gives a smaller eigenvalue (growth rate). This is the intrinsic accuracy limit of the WKB step-potential approximation applied to a smooth tanh shear: it overestimates γ by ~2× for kz=1.

**kz=2..6 — precession cascade masks KH**:

For kz≥2, Az2 grows at γ≈0.20–0.24 TU⁻¹ from t=4.9 TU onward while By2 decays from the initial seed. This cascade (Az2 grows from zero via color precession in the background Az1 field) has γ_cascade ≈ 0.20–0.24, comparable to or faster than any true KH rate for these modes. The WKB predicts γ_KH=0.26–0.44 TU⁻¹ for kz=2..6 — if correct, By2 should outpace the cascade from the start. The observed By2 decay conclusively shows γ_KH(kz=2..6) ≤ γ_cascade ≈ 0.20–0.24 TU⁻¹ in Mode 1.

For kz=4,5,6: at late times (t>44 TU) as Az2 saturates near O(1), By2 acceleration reaches 0.3–0.44 TU⁻¹ — approaching WKB values. This is likely nonlinear secondary driving rather than linear KH, since Az2~O(1) >> linear regime.

**Cascade rate comparison (Mode 1 vs Mode 5)**:

| kz | γ_cascade (Mode 5) | γ_cascade (Mode 1) |
|----|-------------------|-------------------|
| 1 | 0.20 TU⁻¹ | ~0 (Az1=0 at center) |
| 2 | 0.20 TU⁻¹ | 0.20 TU⁻¹ |
| 3 | 0.20 TU⁻¹ | 0.23 TU⁻¹ |
| 4–6 | 0.20 TU⁻¹ | 0.22–0.24 TU⁻¹ |

For kz=1, the cascade in Mode 1 is effectively zero at the shear centre (Az1=0 there → no precession), which is why the true KH (γ=0.281) is cleanly visible above the noise. For kz≥2, the cascade rates in Mode 1 are similar to Mode 5 (≈0.20–0.24), because the cascade is driven in the OUTER REGION where Az1≠0 even in Mode 1.

**To measure KH rates at kz≥2**: reduce α×V0 to push the cascade rate below γ_KH, or seed with a pre-formed Az2 profile matching the expected eigenmode structure so the KH starts well above the cascade noise floor from t=0.

---

## Physics: The kz=0 Weibel-like instability

The WKB polynomial ω⁴ - kz²ω² - Cω - α²vkz = 0 (with C = (2n+1)√(α³/2)v) at kz=0 reduces to:

```
ω⁴ = C·ω  →  ω³ = C  →  ω = C^(1/3)·e^(i·2π/3)
```

Growing root: `γ = C^(1/3)·sin(π/3) = (√(α³/2)·V₀)^(1/3)·(√3/2)`

This is the n=0 quantization of the color-mixing instability: background Az1 causes color-2,3 fields to mix through non-Abelian Ampere (∂Ex2/∂t term −α·Az1·By3) and Faraday (∂By2/∂t term +α·Az1·Ex3), generating exponentially growing color-2,3 electromagnetic fields that are uniform in z.

The kz=0 WKB match (to 0.5%) confirms the polynomial is correct. The next step is to validate γ(kz=0) vs α and determine whether the KH mode at kz≥1 requires a single-layer geometry to be observable.

---

## Campaign 23 — NAB_CIRC_AZ2, α=1.0, V0=0.05, xi_sponge=20, Az-only seed (t130/t136, 2026-07-02)

**Setup**: Mode 6, `alpha=1.0`, `V0=0.05`, `xi_sponge=20.0`, `sigma=5.0`, kz=1..6. Single Az2 Gaussian seed (old format, 1-field binary). NZ=256, courant=0.01 (old defaults — before fast-grid commit).

**Key finding — kz=2 stray mode**:

Az-only seeding for kz=2 caused the simulation to converge to the WRONG eigenmode:
- **Mode 1** (target, γ=0.122): By2 peaks at ξ≈1.64, Az2 peaks at ξ≈7.85 — spatially separated.
- **Mode 6** (stray, γ=0.060): Az2 and Q2A both peak at ξ≈1.31 — co-located.
- Az-only seed drives Q2A at ξ≈7.85 (wrong location). Mode 6 grows faster from that initial condition.
- Measured γ≈0.060 instead of 0.122 → sim/ex=0.49 (50% error).

**Root cause**: The activation chain `Az2 → Q2A → By2` requires Q2A to be co-located with the target mode's By2 peak. An Az2-only seed misplaces Q2A at the Az2 node (ξ≈7.85) rather than the By2 node (ξ≈1.64) for mode 1. Mode 6 (whose Az2 and By2 ARE co-located at ξ≈1.31) builds up preferentially.

---

## Campaign 24 — NAB_CIRC_AZ2, 6-field seed design (t140, 2026-07-02)

**Setup**: Mode 6, `alpha=1.0`, `V0=0.05`, `xi_sponge=20.0`, `sigma=5.0`, kz=1..6. First attempt at 6-field eigenfunction seeding (By2, Ex2, Ez2, Az2, Q2A, Q2B) computed from the 1D eigenvalue solver. NZ=256, courant=0.01.

**Result**: Identified the stray-mode problem analytically (C23 above). Designed the `YMSeedProfiles` struct, updated `kernel_ym_init` (Mode 6 block), updated `main_ym.cu` to read 6-field binary files (n_fields header), updated `ym_eigenmode.py --export-seed` to write 6-field format. Binary: `[int32 n_fields=6][int32 NX][n_fields*NX float32 values]` normalized to max|Az|=1.

**kz=2 eigenmode properties (α=1.0, V0=0.05, xi_sponge=20)**:
- Mode 1 target: by/az=0.003, qA/az=0.190
- Seed establishes Q2A at ξ≈1.64 (By2 peak) from t=0 → activates the KH chain correctly

---

## Campaign 25 — 6-field eigenfunction seeding, NZ=64, courant=0.1 (t136, 2026-07-02) ✓ COMPLETE

**Setup**: Mode 6 (NAB_CIRC_AZ2), `alpha=1.0`, `V0=0.05`, `xi_sponge=20.0`, `sigma=5.0`, kz=1..6. **Full 6-field eigenfunction seed** (By2, Ex2, Ez2, Az2, Q2A, Q2B from 1D solver, normalized to max|Az|=1). **New fast grid**: NZ=64, NX=768, courant=0.1 (validated safe — γ within 4.4% of NZ=256 baseline). kz_suppress_max=kz-1, BP=14, suppress_kz0=1, hyp_diff=5e-5, target_tu=100.

Run time per kz: **87 sec** (RTX A5000, 407 steps/TU × 100 TU ÷ 9200 steps/min). Full 6-kz sweep in **8.7 min** (vs 44 min/kz at NZ=256, courant=0.01).

**Results — kz=2 stray mode FIXED**:

| kz | γ_sim (TU⁻¹) | γ_exact (solver) | sim/ex | γ_WKB | ex/WKB |
|----|--------------|-----------------|--------|-------|--------|
| 1 | **0.0889** | 0.0897 | **0.991** | 0.274 | 0.327 |
| 2 | **0.1211** | 0.1220 | **0.992** | 0.214 | 0.570 |
| 3 | **0.0927** | 0.0933 | **0.994** | 0.178 | 0.524 |
| 4 | **0.0810** | 0.0819 | **0.988** | 0.156 | 0.525 |
| 5 | **0.0643** | 0.0667 | **0.964** | 0.140 | 0.476 |
| 6 | **0.0566** | 0.0607 | **0.933** | 0.128 | 0.474 |

**sim/ex = 0.933–0.994**: All six kz values measured within 1–7% of the exact eigenvalue.

**kz=2 fix confirmed**: Old Az-only seed → γ=0.060 (sim/ex=0.49, stray mode 6). New 6-field seed → γ=0.121 (sim/ex=0.992, correct mode 1). Factor of 2× improvement.

**WKB comparison** (eq. 33, wkb.pdf, n=0): WKB overestimates exact by 2.1–3.1×. The log-cosh Az1 potential is shallower than the WKB parabolic well → smaller eigenvalue.

**Non-monotonic dispersion**: γ peaks at kz=2 (0.121) rather than kz=1 (0.089). The WKB prediction is monotonically decreasing from kz=1. This kink at kz=2 is reproduced by the exact eigenvalue solver → it's real physics, not numerical artifact.

**6-field seeding implementation** (main_ym.cu + YM_Init.cu + YM_Init.cuh):
```
YMSeedProfiles struct: { by, ex, ez, az, qA, qB }  (6 device float* pointers)
Binary format: [n_fields:int32][NX:int32][n_fields*NX float32]
kernel_ym_init Mode 6: seeds By2/By3 from seed.by; seeds Az2/Az3 from seed.az;
  seeds flA.Q2/Q3 from seed.qA; seeds flB.Q2/Q3 from seed.qB (all with cos/sin kz z)
main_ym.cu: reads binary, interpolates nx_file→NX, cudaMalloc + cudaMemcpy per field
```

**dispersion_ym.py fixes** (for NZ=64 and variable courant):
- `load_snapshot`: nz inferred from row count ÷ NX (was hardcoded 256)
- `extract_mode_amplitude/circ_amplitude`: nz from `field_2d.shape[0]`
- `growth_rate_from_dir`: DT inferred from energy.csv slope (last/first entries), not hardcoded

---

## Campaign 26-31 — Massive α-V0 Parameter Sweep (2026-07-02) [DONE on all servers]

**Goal**: Map γ(kz, α, V0) across 7 parameter points for WKB validation and presentation. All campaigns use Mode 6, 6-field eigenfunction seeding, NZ=64, courant=0.1, target_tu=100, BP=14.

**Exact eigenvalues** (from 1D solver, used for sim/ex comparison):

| Campaign | α | V0 | xi_sponge | Server | kz=1 | kz=2 | kz=3 | kz=4 | kz=5 | kz=6 |
|----------|---|----|-----------|--------|------|------|------|------|------|------|
| C25 ✓ | 1.0 | 0.05 | 20 | t136 | 0.0897 | 0.1220 | 0.0933 | 0.0819 | 0.0667 | 0.0607 |
| C26 | 1.0 | 0.10 | 10 | t136 | 0.1191 | 0.1737 | 0.1444 | 0.1206 | 0.1037 | 0.0917 |
| C27 | 1.5 | 0.05 | 14 | t130 | 0.0886 | 0.1302 | 0.1444 | 0.1321 | 0.1049 | 0.0961 |
| C28 | 1.5 | 0.10 | 10 | t140 | 0.0970 | 0.1919 | 0.2171 | 0.1818 | 0.1530 | 0.1553 |
| C29 | 2.0 | 0.05 | 10 | t136 | 0.0861 | 0.1321 | 0.1507 | 0.1576 | 0.1584 | 0.1381 |
| C30 | 2.0 | 0.10 | 10 | t130 | 0.2665 | 0.1990 | 0.2366 | 0.2475 | 0.2106 | 0.2100 |
| C31 | 0.5 | 0.10 | 20 | abi | 0.1229 | 0.0802 | 0.0649 | 0.0547 | 0.0453 | 0.0414 |

**xi_sponge design rule**: xi_sponge ≥ ξ_crit(kz=1) = 1/(α·V0) to avoid exposing outer EM instability within the sponge-free region. Check: γ_outer(xi_sponge) = √(|Ω_A|·Ω_F) < 1.5 TU⁻¹. All campaigns above satisfy this.

**Notable physics** (from solver pre-analysis):
- **Non-monotonic γ(kz)**: C27,C28,C29 show γ peaking at kz=3–5 rather than kz=1. WKB predicts monotonic decrease. This is a genuine non-Abelian effect.
- **C30 kz=1 exceptionally high**: γ=0.267 vs 0.090 in C25 at same α but V0=0.05. Strong V0 dependence.
- **C31 (α=0.5) best WKB match**: ex/WKB=0.72–0.85 (closest to 1 of any campaign). Weaker coupling → WKB parabolic approximation more accurate.

**Analysis**: Run `python3 dispersion_ym.py --dirs ym_k*_a{alpha}*_circ* --alpha {alpha} --field Az_circ --plot-dispersion` per campaign after syncing data.

**C31 confirmed results** (abi, α=0.5, V0=0.10, xi_sponge=20, 63-70 pts per kz):

| kz | γ_sim | γ_exact | sim/ex | ex/WKB |
|----|-------|---------|--------|--------|
| 1  | 0.1217 | 0.1229 | 0.990 | 0.849 |
| 2  | 0.0707 | 0.0802 | 0.882 | 0.738 |
| 3  | 0.0550 | 0.0649 | 0.847 | 0.722 |
| 4  | 0.0425 | 0.0547 | 0.777 | 0.699 |
| 5  | 0.0280 | 0.0453 | 0.618 | 0.645 |
| 6  | 0.0175 | 0.0414 | 0.423 | 0.645 |

kz=1 agrees to 1%. kz=2-4 degrade because ξ_peak(kz=2-4)≈−20 is right at xi_sponge=20 (sponge clips the eigenmode). kz=5-6 additionally suffer from short runs (energy threshold at t≈63 TU).

**Key finding**: xi_sponge must be comfortably larger than ξ_peak for all target kz. For C31, kz=1 (ξ_peak=−16) has best agreement; kz=2+ (ξ_peak=−20) are sponge-clipped.

---

## Campaign 32 — α=2.5, V0=0.05, xi_sponge=9 (2026-07-03) [RUNNING on abi]

**Goal**: Extend α-V0 grid to higher coupling at V0=0.05 (αV0=0.125). Teaching nodes t130/t136/t140 are down; abi only.

**Parameters**: α=2.5, V0=0.05, EPS=0.15, xi_sponge=9, σ=5, NZ=64, courant=0.1, target_tu=100, 6-field seed.

**Outer EM safety**: ξ_crit(kz=1)≈8.7 (where Ω_A changes sign). Sponge at xi_sponge=9 → outer EM strip=[8.7, 9] only 0.3 ξ-units wide, γ_outer<0.13 TU⁻¹. Safe.

**Exact eigenvalues** (1D solver, xi_sponge=9):

| kz | γ_exact | γ_WKB | ex/WKB |
|----|---------|-------|--------|
| 1  | 0.0837  | 0.4543 | 0.184 |
| 2  | 0.1359  | 0.3721 | 0.365 |
| 3  | 0.1579  | 0.3134 | 0.504 |
| 4  | 0.1674  | 0.2745 | 0.610 |
| 5  | 0.1701  | 0.2469 | 0.689 |
| 6  | 0.1687  | 0.2261 | 0.746 |

**Notable**: γ(kz) peaks at kz=5 (anti-monotonic — non-Abelian effect). WKB strongly overestimates (ex/WKB=0.18-0.75) because the parabolic-well approximation breaks down at large α. Seed files: `eigenmode_seed_kz{k}_a2.50_V0.050_sp9.0.bin`.

---

## Campaign 33 — α=3.0, V0=0.05, xi_sponge=8 (READY, pending t136 recovery)

**Goal**: Highest α in V0=0.05 series. αV0=0.15.

**Outer EM safety**: ξ_crit(kz=1)≈7.4, outer EM strip=[7.4, 8] only 0.6 ξ-units, γ_outer<0.13 TU⁻¹. Safe.

**Exact eigenvalues** (xi_sponge=8):

| kz | γ_exact | γ_WKB | ex/WKB |
|----|---------|-------|--------|
| 1  | 0.0808  | 0.5261 | 0.154 |
| 2  | 0.1374  | 0.4418 | 0.311 |
| 3  | 0.1625  | 0.3744 | 0.434 |
| 4  | 0.1743  | 0.3286 | 0.530 |
| 5  | 0.1787  | 0.2958 | 0.604 |
| 6  | 0.1786  | 0.2710 | 0.659 |

Script: `run_campaign33_t136.sh`. Seeds: `eigenmode_seed_kz{k}_a3.00_V0.050_sp8.0.bin`.

## Campaign 33 — CONFIRMED RESULTS (2026-07-03)

**α=3.0, V0=0.05, xi_sponge=8, abi. All kz R²=1.0000.**

| kz | γ_sim  | γ_exact | sim/ex | ex/WKB |
|----|--------|---------|--------|--------|
| 1  | 0.0790 | 0.0808  | 0.978  | 0.154  |
| 2  | 0.1359 | 0.1374  | 0.989  | 0.311  |
| 3  | 0.1599 | 0.1625  | 0.984  | 0.434  |
| 4  | 0.1709 | 0.1743  | 0.980  | 0.530  |
| 5  | 0.1727 | 0.1787  | 0.966  | 0.604  |
| 6  | 0.1686 | 0.1786  | 0.944  | 0.659  |

**Same non-monotonic dispersion as C32** (γ peaks at kz=5). WKB overestimates by 1.5–6.5× (ex/WKB=0.15–0.66). sim/exact=0.944–0.989.

**V0=0.05 series summary** (C25 α=1.0, C32 α=2.5, C33 α=3.0): all R²≥0.999, sim/exact≥0.944. The non-Abelian dispersion peak migrates from kz=2 (α=1.0) to kz=5 (α=2.5,3.0) as coupling increases — a genuine non-Abelian effect.

---

## Campaign 32 — CONFIRMED RESULTS (2026-07-03)

**α=2.5, V0=0.05, xi_sponge=9, abi. All kz R²=1.0000 — perfect exponential growth.**

| kz | γ_sim  | γ_exact | sim/ex | ex/WKB |
|----|--------|---------|--------|--------|
| 1  | 0.0823 | 0.0837  | 0.983  | 0.184  |
| 2  | 0.1345 | 0.1359  | 0.990  | 0.365  |
| 3  | 0.1557 | 0.1579  | 0.986  | 0.504  |
| 4  | 0.1641 | 0.1674  | 0.980  | 0.610  |
| 5  | 0.1642 | 0.1701  | 0.965  | 0.689  |
| 6  | 0.1594 | 0.1687  | 0.945  | 0.746  |

**Best campaign so far across all kz simultaneously** (sim/ex = 0.945–0.990 for kz=1..6). This is because ξ_peak(kz=2-6)=−9.2 is comfortably inside xi_sponge=9.

**Key physics**: γ(kz) peaks at kz=4–5 — **non-monotonic dispersion**, a genuine non-Abelian effect. The WKB polynomial predicts monotonic decrease; the simulation (and exact 1D eigenvalue) shows a maximum at intermediate kz. The WKB overestimates by 2–5× (ex/WKB = 0.18–0.75) because the parabolic-well approximation breaks down at large α.

**C33 launched on abi immediately after** (teaching nodes still down): α=3.0, V0=0.05, xi_sponge=8. Expected ~12 min runtime.

---

## Campaign 32 / 33 — kz=7,8 extensions (2026-07-03) [CONFIRMED]

Extended C32 (α=2.5) and C33 (α=3.0) to kz=7,8 to map the post-peak rolloff at V0=0.05.
All R²=1.0000. Runs stopped at 72–76 TU (energy threshold).

**C32 extended (α=2.5, V0=0.05, xi_sponge=9):**

| kz | γ_sim  | γ_exact | sim/ex |
|----|--------|---------|--------|
| 7  | 0.1493 | 0.1652  | 0.904  |
| 8  | 0.1395 | 0.1605  | 0.869  |

**C33 extended (α=3.0, V0=0.05, xi_sponge=8):**

| kz | γ_sim  | γ_exact | sim/ex |
|----|--------|---------|--------|
| 7  | 0.1587 | 0.1760  | 0.902  |
| 8  | 0.1485 | 0.1719  | 0.864  |

**Observation**: sim/ex degrades at kz=7,8 (0.86–0.90 vs 0.945–0.990 at kz=1..6). This is expected — higher kz modes have ξ_peak slightly closer to the sponge boundary for the same xi_sponge, increasing sponge clipping. The post-peak rolloff is nonetheless clearly measured: γ decreases from the kz=5 peak by ≈10% at kz=7 and ≈15% at kz=8.

---

## Campaign 34 — α=1.5, V0=0.05, xi_sponge=12 (2026-07-03) [CONFIRMED]

**Goal**: Fill gap between C25 (α=1.0) and C32 (α=2.5). γ peaks at kz=3 (low-coupling regime).

| kz | γ_sim  | γ_exact | sim/ex |
|----|--------|---------|--------|
| 1  | 0.0871 | 0.0878  | 0.992  |
| 2  | 0.1257 | 0.1274  | 0.987  |
| 3  | 0.1397 | 0.1418  | 0.985  |
| 4  | 0.1241 | 0.1261  | 0.984  |
| 5  | 0.1087 | 0.1114  | 0.976  |
| 6  | 0.0951 | 0.0992  | 0.959  |

**Peak at kz=3 (γ_sim=0.140)**, clear unimodal shape with rolloff both sides. sim/ex=0.959–0.992 — excellent across all kz.

---

## Campaign 35 — α=2.0, V0=0.05, xi_sponge=11 (2026-07-03) [CONFIRMED]

**Goal**: Fill gap between C34 (α=1.5) and C32 (α=2.5). Peak migrates to kz=4.

| kz | γ_sim  | γ_exact | sim/ex |
|----|--------|---------|--------|
| 1  | 0.0845 | 0.0862  | 0.980  |
| 2  | 0.1334 | 0.1344  | 0.993  |
| 3  | 0.1510 | 0.1529  | 0.988  |
| 4  | 0.1564 | 0.1597  | 0.979  |
| 5  | 0.1553 | 0.1602  | 0.969  |
| 6  | 0.1347 | 0.1419  | 0.949  |

**Peak at kz=4 (γ_sim=0.156)**, with kz=5 nearly equal (broad plateau). sim/ex=0.949–0.993.

---

## V0=0.05 complete series summary (C34, C35, C32, C33) [CONFIRMED]

All four campaigns with R²≥0.999. kz_peak migration with α:

| Campaign | α   | kz_peak (sim) | kz_peak (exact) | γ_peak (sim) |
|----------|-----|---------------|-----------------|--------------|
| C34      | 1.5 | 3             | 3               | 0.140        |
| C35      | 2.0 | 4             | 5               | 0.156        |
| C32      | 2.5 | 4–5           | 5               | 0.164        |
| C33      | 3.0 | 5             | 5               | 0.173        |

The **non-Abelian peak migrates from kz=3 → kz=5** as α increases from 1.5 to 3.0 at V0=0.05. WKB overestimates by 2–6× (ex/WKB=0.16–0.75). All sim/exact ≥ 0.944 for kz=1..6.

---

## Campaigns 36, 37, 38 — V0=0.03 low-velocity series (2026-07-03) [CONFIRMED]

**Goal**: Test whether the peak migration persists at lower V0. All three campaigns used
xi_sponge=5, σ=5, EPS=0.15, target_tu=100. kz measured up to 9 — peak is now
captured within the measurement range. CSV format upgraded to 25 columns (adds
Ex/Ez all colors, fluid density nA/nB, Q2/Q3 for Gauss's law tracking).

Note on sponge effect: With xi_sponge=5 and ξ_peak=−5.24 (mode just inside sponge),
sim growth rates systematically underestimate exact by 5–15%, with the discrepancy
growing at higher kz. Peak position in sim is shifted 1–2 kz lower than exact.

**C36: α=3.0, V0=0.03, xi_sponge=5**

| kz | γ_sim  | γ_exact | sim/ex |
|----|--------|---------|--------|
| 1  | 0.0475 | 0.0542  | 0.876  |
| 2  | 0.0819 | 0.0824  | 0.994  |
| 3  | 0.0983 | 0.0992  | 0.991  |
| 4  | 0.1070 | 0.1093  | 0.979  |
| 5  | 0.1107 | 0.1149  | 0.964  |
| 6  | 0.1099 | 0.1175  | 0.935  |
| 7  | 0.1063 | 0.1181  | 0.900  |
| 8  | 0.0994 | 0.1174  | 0.847  |
| 9  | 0.0799 | 0.1159  | 0.689  |

Peak (sim): kz=5 (γ=0.111). Peak (exact): kz=7 (γ=0.118). Sponge shifts apparent peak down by 2 kz.

**C37: α=4.0, V0=0.03, xi_sponge=5**

| kz | γ_sim  | γ_exact | sim/ex |
|----|--------|---------|--------|
| 1  | 0.0507 | 0.0572  | 0.886  |
| 2  | 0.0885 | 0.0890  | 0.994  |
| 3  | 0.1069 | 0.1083  | 0.987  |
| 4  | 0.1175 | 0.1201  | 0.978  |
| 5  | 0.1221 | 0.1271  | 0.961  |
| 6  | 0.1222 | 0.1309  | 0.934  |
| 7  | 0.1189 | 0.1323  | 0.899  |
| 8  | 0.1131 | 0.1322  | 0.856  |
| 9  | 0.0938 | 0.1311  | 0.715  |

Peak (sim): kz=5–6 (γ=0.122). Peak (exact): kz=7 (γ=0.132). Shift: 1–2 kz.

**C38: α=5.0, V0=0.03, xi_sponge=5**

| kz | γ_sim  | γ_exact | sim/ex |
|----|--------|---------|--------|
| 1  | 0.0525 | 0.0589  | 0.891  |
| 2  | 0.0935 | 0.0941  | 0.994  |
| 3  | 0.1137 | 0.1155  | 0.984  |
| 4  | 0.1261 | 0.1288  | 0.979  |
| 5  | 0.1316 | 0.1371  | 0.960  |
| 6  | 0.1323 | 0.1418  | 0.933  |
| 7  | 0.1294 | 0.1441  | 0.898  |
| 8  | 0.1237 | 0.1445  | 0.856  |
| 9  | 0.1026 | 0.1438  | 0.713  |

Peak (sim): kz=6 (γ=0.132). Peak (exact): kz=8 (γ=0.145). Shift: 2 kz.

**V0=0.03 series summary:**

| Campaign | α   | kz_peak (sim) | kz_peak (exact) | γ_peak (sim) |
|----------|-----|---------------|-----------------|--------------|
| C36      | 3.0 | 5             | 7               | 0.111        |
| C37      | 4.0 | 5–6           | 7               | 0.122        |
| C38      | 5.0 | 6             | 8               | 0.132        |

The **non-Abelian peak migrates from kz=5 → kz=8** (exact) as α increases from 3.0 to 5.0 at V0=0.03.
Growth rates are ~30% lower than V0=0.05 at similar α due to weaker shear driving.
WKB dramatically overestimates by 4–11× (ex/WKB=0.09–0.47) — non-Abelian corrections are dominant.

**Combining both V0 series (kz_peak vs αV0):**

| αV0  | α   | V0   | kz_peak (exact) |
|------|-----|------|-----------------|
| 0.075 | 1.5 | 0.05 | 3               |
| 0.09  | 3.0 | 0.03 | 7               |
| 0.10  | 2.0 | 0.05 | 5               |
| 0.09  | 3.0 | 0.03 | 7               |
| 0.125 | 2.5 | 0.05 | 5               |
| 0.12  | 4.0 | 0.03 | 7               |
| 0.15  | 3.0 | 0.05 | 5               |
| 0.15  | 5.0 | 0.03 | 8               |

At fixed αV0, V0=0.03 (higher α) gives higher kz_peak than V0=0.05 — the peak position depends on α and V0 separately, not just their product. This is consistent with the WKB polynomial where α and V0 enter through different combinations (α²V0 and kz²V0²/α).

**Plot**: `ym_dispersion_allcampaigns.png` — 3-panel: V0=0.05 dispersion (top-left), V0=0.03 dispersion (top-right), kz_peak migration vs αV0 (bottom).

---

## Campaign 39: α=1.0, V0=0.05, xi_sponge=25, kz=1..8

**Parameters**: Mode 6, EPS=0.15, suppress_kz0=1, hyp_diff=5e-5, BP=14, target_tu=100.
**Date**: 2026-07-03, abi (GTX 1080 Ti, sm_61).

| kz | γ_sim | γ_exact | sim/exact | R²   |
|----|-------|---------|-----------|------|
| 1  | 0.0747 | 0.0883 | 0.846 | 0.985 |
| 2  | 0.1087 | 0.1232 | 0.882 | 0.990 |
| 3  | 0.0683 | 0.0929 | 0.735 | 0.974 |
| 4  | 0.0531 | 0.0790 | 0.672 | 0.966 |
| 5  | 0.0350 | 0.0682 | 0.513 | 0.949 |
| 6  | 0.0223 | 0.0603 | 0.370 | 0.929 |
| 7  | 0.0235 | 0.0545 | 0.431 | 0.934 |
| 8  | 0.0145 | 0.0500 | 0.290 | 0.882 |

Peak (sim): kz=2 (γ=0.109). Peak (exact): kz=2 (γ=0.123). **kz_peak correctly identified.**

**Note on sponge compression**: At low coupling (α=1.0), the WKB turning point ξ_crit = acosh(exp(kz/(αV0))) becomes very large — for kz=3: ξ_crit ≈ 60. The sponge at xi_sponge=25 cuts off the mode at ~42% of ξ_crit. This causes increasing underestimation at higher kz (sim/exact drops from 0.88 at kz=2 to 0.29 at kz=8). The kz=1,2 values (sim/exact≈0.85-0.88) are reliable; kz≥3 are lower bounds. The kz_peak location is still correctly recovered.

Extends V0=0.05 series to lower coupling. Combined with C34 (α=1.5):

| α   | αV0   | kz_peak (exact) |
|-----|-------|-----------------|
| 0.5* | 0.025 | 1 (predicted)  |
| 1.0 | 0.050 | 2 (C39)        |
| 1.5 | 0.075 | 3 (C34)        |
| 2.0 | 0.100 | 4 (C35)        |
| 2.5 | 0.125 | 5 (C32)        |
| 3.0 | 0.150 | 5 (C33)        |

*α=0.5 predicted: kz_peak=1 from eigenmode solver. To see kz_peak < 1 (below kz=1) requires Lz > 2π.

**kz_peak trend (V0=0.05)**: kz_peak ≈ 2α → falls below 1 at α < 0.5. This is the motivation for the planned Lz=4π extension.

---

## Batch Analysis — Extended α/V0 Parameter Sweep (2026-07-03)

**Method**: `batch_analyze.py` reads pre-computed `timeseries_k*.csv` (Az_circ amplitude vs t) from abi/t130/t140. Growth rates fitted by best-R² sliding-window log-linear fit. γ_exact from quartic WKB polynomial (n=0..50 scan). For each (α, V0, kz), the run with the largest xi_sponge is used (most conservative sponge → least truncation).

**Reliability flag**: kz=1 rates are unreliable when xi_sponge < ξ_crit(kz=1) = kz/(αV0). Marked (!) below.

---

### Campaign 41 — α=1.5, V0=0.03, xi_sponge=18, kz=1..4 (abi, 2026-07-03)

αV0 = 0.045. ξ_crit(kz=1) = 1/(1.5×0.03) = 22.2 > xi_sponge → kz=1,2 compressed.

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.0690 | 1.1818  | 0.058 | (!) sponge compressed |
| 2  | 0.0942 | 0.4642  | 0.203 | (!) sponge compressed |
| 3  | 0.1033 | 0.1498  | 0.690 | reliable |
| 4  | 0.0984 | 0.1298  | 0.758 | reliable |

**kz_peak (reliable kz≥3) = 3** (γ=0.103). Completes V0=0.03 series at lower α.

---

### Campaign 42 — α=2.0, V0=0.03, xi_sponge=14, kz=1..4 (abi, 2026-07-03)

αV0 = 0.06. ξ_crit(kz=1) = 1/(2.0×0.03) = 16.7 > xi_sponge → kz=1,2 compressed.

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.0688 | 1.4187  | 0.048 | (!) sponge compressed |
| 2  | 0.0983 | 0.8777  | 0.112 | (!) sponge compressed |
| 3  | 0.1102 | 0.1995  | 0.552 | reliable |
| 4  | 0.1145 | 0.1730  | 0.661 | reliable |

**kz_peak (reliable) = 4** (γ=0.115). Bridges V0=0.03 series between α=1.5 (C41) and α=3.0 (C36).

---

### Campaign 51 — α=1.5, V0=0.10, xi_sponge=10, kz=1..6 (t130, 2026-07-03)

αV0 = 0.15. Sponge ξ_crit(kz=1) ≈ 6.7 < xi_sponge=10.

| kz | γ_sim  | γ_exact | ratio |
|----|--------|---------|-------|
| 1  | 0.1012 | 1.9194  | 0.053 |
| 2  | 0.1908 | 0.8707  | 0.219 |
| 3  | 0.2160 | 0.2727  | 0.792 |
| 4  | 0.1814 | 0.2367  | 0.766 |
| 5  | 0.1507 | 0.2119  | 0.711 |
| 6  | 0.1501 | 0.1935  | 0.775 |

**kz_peak = 3** (γ=0.216). Same peak as C34 (α=1.5, V0=0.05). kz=1,2 ratios low → strong-coupling WKB overestimate.

---

### Campaign 52 — α=2.0, V0=0.20, xi_sponge=5, kz=1..6 (t130, 2026-07-03)

αV0 = 0.40. Sponge ξ_crit(kz=1) ≈ 2.5 < xi_sponge=5.

| kz | γ_sim  | γ_exact | ratio |
|----|--------|---------|-------|
| 1  | 0.1605 | 2.8871  | 0.056 |
| 2  | 0.2338 | 1.2744  | 0.183 |
| 3  | 0.2927 | 0.5087  | 0.575 |
| 4  | 0.3100 | 0.4443  | 0.698 |
| 5  | 0.3084 | 0.3987  | 0.773 |
| 6  | 0.3006 | 0.3644  | 0.825 |

**kz_peak = 4** (γ=0.310, ratio=0.70). Same kz_peak as α=2.0 V0=0.05 (C35) and V0=0.03 (C42) — kz_peak invariant under V0 at fixed α=2.0. γ_peak scales ~linearly with V0: 0.31/0.157≈1.97 for V0 factor 4×.

---

### Extended Parameter Coverage: C39/C41/C42/C51/C52 (2026-07-03)

Additional kz from batch analysis (t130 sp14/sp15/sp20 runs extending C34/C35/C39):

**α=1.0, V0=0.05, xi_sponge=25 (extended, C39+)**

| kz | γ_sim  | γ_exact | ratio |
|----|--------|---------|-------|
| 2  | 0.1222 | 0.1576  | 0.775 |
| 3  | 0.0920 | 0.1290  | 0.714 |
| 4  | 0.0778 | 0.1118  | 0.696 |
| 5  | 0.0646 | 0.1000  | 0.646 |
| 6  | 0.0536 | 0.0913  | 0.588 |
| 7  | 0.0429 | 0.0845  | 0.508 |
| 8  | 0.0337 | 0.0791  | 0.426 |

**kz_peak = 2** confirmed (consistent with C39 γ=0.109).

---

### Campaign 53 — α=1.0, V0=0.10, xi_sponge=16, kz=1..4 (t130, 2026-07-03)

αV0=0.10. Sponge ξ_crit(kz=1)=1/(1.0×0.10)=10 < xi_sp=16, so kz=1 is inside sponge.

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.1925 | 1.5166  | 0.127 | (!) |
| 2  | 0.1735 | 0.2221  | 0.781 | reliable |
| 3  | 0.1747 | 0.1822  | 0.959 | reliable |
| 4  | 0.1843 | 0.1580  | 1.166 | nonlinear |

**kz_peak (reliable kz=2,3) = 2–3** (γ≈0.174). Ratio>1 at kz=4 indicates nonlinear effects past the linear window. γ_peak~0.174 vs C39 V0=0.05 γ_peak=0.122: ratio=1.43 ≈ V0 ratio of 2.0. ✓ Consistent with γ_peak ∝ V0.

---

### Campaign 54 — α=1.0, V0=0.20, xi_sponge=11, kz=1..3 (t130, 2026-07-03)

αV0=0.20. Sponge ξ_crit(kz=1)=5 < xi_sp=11.

| kz | γ_sim  | γ_exact | ratio |
|----|--------|---------|-------|
| 1  | 0.5389 | 1.3029  | 0.414 |
| 2  | 0.2140 | 0.3120  | 0.686 |
| 3  | 0.2883 | 0.2571  | 1.121 |

Only 3 kz — kz=3 already in nonlinear regime (ratio>1). kz=2 reliable: γ=0.214. V0 series for α=1.0: γ_peak(V0) = 0.109 (V0=0.05), 0.174 (V0=0.10), ~0.22 (V0=0.20, kz=2) — consistent with linear V0 scaling.

---

### Campaign 55 — α=2.0, V0=0.10, xi_sponge=11, kz=1..6 (t130, 2026-07-03)

αV0=0.20. Sponge ξ_crit(kz=1)=5 < xi_sp=11. kz=1,2 have low ratio (anomalous growth).

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.5373 | 2.2520  | 0.239 | (!) |
| 2  | 0.1628 | 1.9054  | 0.085 | (!) |
| 3  | 0.1761 | 0.3624  | 0.486 | reliable |
| 4  | 0.1655 | 0.3152  | 0.525 | reliable |
| 5  | 0.2105 | 0.2824  | 0.745 | reliable |
| 6  | 0.2015 | 0.2580  | 0.781 | reliable |

**kz_peak (reliable kz≥3) = 5** (γ=0.211). kz_peak ≈ 5 vs C35 kz_peak=4 at V0=0.05. Slight upward shift at higher V0.

**V0 scaling at α=2.0** (kz_peak values in parentheses):
| V0   | γ_peak | kz_peak |
|------|--------|---------|
| 0.03 | 0.115  | 4 (C42) |
| 0.05 | 0.157  | 4 (C35) |
| 0.10 | 0.211  | 5 (C55) |
| 0.20 | 0.310  | 4 (C52) |

γ_peak scales roughly as V0^0.8 (not purely linear — slight sub-linear at high V0). kz_peak stays at 4–5 across 7× range in V0.

---

### Campaign 56 — α=2.5, V0=0.03, xi_sponge=18, kz=1..7 (abi, 2026-07-03)

αV0=0.075. Sponge ξ_crit(kz=1)=1/(2.5×0.03)=13.3 < xi_sp=18. kz=1,2 compressed.

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.0789 | 1.6222  | 0.049 | (!) |
| 2  | 0.0866 | 1.1601  | 0.075 | (!) |
| 3  | 0.0948 | 0.2491  | 0.381 | borderline |
| 4  | 0.0950 | 0.2162  | 0.439 | reliable |
| 5  | 0.0909 | 0.1935  | 0.470 | reliable |
| 6  | 0.0849 | 0.1767  | 0.481 | reliable |
| 7  | 0.0780 | 0.1636  | 0.477 | reliable |

**kz_peak (reliable kz≥4) = 4** (γ=0.095). Bridges V0=0.03 series: α=1.5→2.0→2.5→3.0: kz_peak=3,4,4,5.

**V0=0.03 series kz_peak trend:**
| α   | kz_peak | C  |
|-----|---------|-----|
| 1.5 | 3       | C41 |
| 2.0 | 4       | C42 |
| 2.5 | 4       | C56 |
| 3.0 | 5       | C36 |
| 4.0 | 6       | C37 |
| 5.0 | 6       | C38 |

**kz_peak ≈ 1.5α** at V0=0.03 (compared to ≈2α at V0=0.05).

---

### Campaign 58 — α=3.0, V0=0.20, xi_sponge=6, kz=1..7 (t140, 2026-07-03)

αV0=0.60. Sponge ξ_crit(kz=1)=1/(3.0×0.20)=1.67 < xi_sp=6. But kz=1,2 still show low ratio (heavy WKB overestimate at low kz for high αV0).

| kz | γ_sim  | γ_exact | ratio |
|----|--------|---------|-------|
| 1  | 1.2338 | 3.5705  | 0.346 |
| 2  | 0.3325 | 2.8536  | 0.117 |
| 3  | 0.3674 | 0.7507  | 0.489 |
| 4  | 0.3668 | 0.6615  | 0.554 |
| 5  | 0.3410 | 0.5956  | 0.572 |
| 6  | 0.3058 | 0.5454  | 0.561 |
| 7  | 0.2510 | 0.5057  | 0.496 |

**kz_peak (reliable kz≥3) = 3–4** (γ≈0.367). vs C21b (α=3.0, V0=0.10) kz_peak=5: kz_peak shifts **down** at higher V0! This reverses the trend seen at fixed V0.

**V0 scaling at α=3.0:**
| V0   | γ_peak | kz_peak |
|------|--------|---------|
| 0.03 | 0.111  | 5 (C36) |
| 0.05 | 0.174  | 5 (C33) |
| 0.10 | 0.256  | 5 (C21b) |
| 0.20 | 0.367  | 3–4 (C58) |

kz_peak drops from 5→3-4 as V0 increases from 0.10→0.20. This suggests V0 breaks the kz_peak invariance at high coupling.

---

### Campaign 57 — α=2.5, V0=0.10, xi_sponge=10, kz=1..7 (abi, 2026-07-03)

αV0=0.25. Sponge ξ_crit(kz=1)=1/(2.5×0.10)=4 < xi_sp=10. kz=2,3 anomalously low ratio.

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.7544 | 2.5417  | 0.297 | (!) |
| 2  | 0.1657 | 2.2506  | 0.074 | (!) |
| 3  | 0.1908 | 0.7530  | 0.253 | borderline |
| 4  | 0.1739 | 0.3933  | 0.442 | reliable |
| 5  | 0.2413 | 0.3526  | 0.684 | reliable |
| 6  | 0.2132 | 0.3223  | 0.662 | reliable |
| 7  | 0.1783 | 0.2985  | 0.597 | reliable |

**kz_peak (reliable kz≥4) = 5** (γ=0.241). Same as C32 (α=2.5, V0=0.05, kz_peak=5). **kz_peak invariant under V0** at α=2.5.

**V0 scaling at α=2.5:**
| V0   | γ_peak | kz_peak |
|------|--------|---------|
| 0.03 | 0.095  | 4 (C56) |
| 0.05 | 0.166  | 5 (C32) |
| 0.10 | 0.241  | 5 (C57) |

γ_peak scaling: 0.095→0.166→0.241 for V0 = 0.03→0.05→0.10. Ratio V0=0.10/0.05 = 1.45 (expected 2.0 for linear). Sub-linear again at high V0/αV0.

---

### Campaign 59 — α=0.5, V0=0.05, xi_sponge=22, kz=1..3 (t130, 2026-07-03)

αV0=0.025 (very weak coupling). ξ_crit(kz=1)=1/(0.5×0.05)=40 >> xi_sp=22 → kz=1 heavily sponge-compressed. kz=2,3 show ratio>1 (WKB underestimates in weak-coupling limit).

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.0691 | 0.6486  | 0.107 | (!) sponge |
| 2  | 0.0902 | 0.0790  | 1.142 | nonlinear |
| 3  | 0.0981 | 0.0645  | 1.520 | nonlinear |

True kz_peak likely kz=1 (consistent with C31 α=0.5 V0=0.10 kz_peak=1). Need larger xi_sponge or Lz to resolve kz=1.

---

### Campaign 60 — α=1.5, V0=0.20, xi_sponge=9, kz=1..5 (t130, 2026-07-03)

αV0=0.30. ξ_crit(kz=1)=3.3 < xi_sp=9. kz=4,5 reach nonlinear saturation by 100 TU.

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.8571 | 2.4402  | 0.351 | (!) anomalous |
| 2  | 0.2168 | 0.4614  | 0.470 | reliable |
| 3  | 0.2096 | 0.3839  | 0.546 | reliable |
| 4  | 0.2904 | 0.3342  | 0.869 | borderline |
| 5  | 0.2894 | 0.2994  | 0.967 | nonlinear |

**kz_peak (reliable kz=2,3) = 2–3** (γ≈0.22). γ_peak saturates: 0.103→0.144→0.216→0.216 for V0=0.03→0.05→0.10→0.20. Growth saturates at αV0≈0.15. kz_peak stays at 3.

---

### Campaign 61 — α=2.0, V0=0.02, xi_sponge=25, kz=1..6 (abi, 2026-07-03)

αV0=0.04 (very weak). ξ_crit(kz=1)=1/(2.0×0.02)=25 = xi_sp → kz=1,2 fully sponge-absorbed.

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.0653 | 1.1952  | 0.055 | (!) |
| 2  | 0.0639 | 0.4900  | 0.130 | (!) |
| 3  | 0.0678 | 0.1630  | 0.416 | reliable |
| 4  | 0.0675 | 0.1413  | 0.478 | reliable |
| 5  | 0.0646 | 0.1265  | 0.511 | reliable |
| 6  | 0.0613 | 0.1154  | 0.531 | reliable |

**kz_peak (reliable kz≥3) = 3** (γ=0.068). V0=0.02 series at α=2.0: kz_peak drops to 3 vs kz_peak=4 at V0=0.03–0.20. γ_peak=0.068 extrapolates from 0.115 at V0=0.03 as γ∝V0^0.85.

---

### Campaign 62 — α=3.0, V0=0.02, xi_sponge=20, kz=1..7 (abi, 2026-07-03)

αV0=0.06. ξ_crit(kz=1)=1/(3.0×0.02)=16.7 < xi_sp=20. kz=1,2 compressed.

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.0643 | 1.5396  | 0.042 | (!) |
| 2  | 0.0694 | 1.0477  | 0.066 | (!) |
| 3  | 0.0761 | 0.2441  | 0.312 | borderline |
| 4  | 0.0769 | 0.2118  | 0.363 | reliable |
| 5  | 0.0747 | 0.1896  | 0.394 | reliable |
| 6  | 0.0717 | 0.1731  | 0.414 | reliable |
| 7  | 0.0660 | 0.1603  | 0.412 | reliable |

**kz_peak (reliable kz≥4) = 4** (γ=0.077). V0=0.02 series at α=3.0: kz_peak=4 vs 5 at V0=0.03–0.10. Downward shift at very low V0.

**V0=0.02 series summary** (extrapolates trend to very low coupling):
| α   | kz_peak | γ_peak | C  |
|-----|---------|--------|-----|
| 2.0 | 3       | 0.068  | C61 |
| 3.0 | 4       | 0.077  | C62 |

---

### Campaign 63 — α=2.5, V0=0.20, xi_sponge=7, kz=1..7 (t140, 2026-07-03)

αV0=0.50. ξ_crit(kz=1)=1/(2.5×0.20)=2.0 < xi_sp=7. kz=2 anomalously low ratio (resonance/parasitic mode?).

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 1.2900 | 3.2468  | 0.397 | (!) |
| 2  | 0.3669 | 2.0846  | 0.176 | (!) |
| 3  | 0.2243 | 0.6311  | 0.355 | borderline |
| 4  | 0.3570 | 0.5535  | 0.645 | reliable |
| 5  | 0.3241 | 0.4974  | 0.652 | reliable |
| 6  | 0.2838 | 0.4551  | 0.624 | reliable |
| 7  | 0.2228 | 0.4218  | 0.528 | reliable |

**kz_peak (reliable kz≥4) = 4** (γ=0.357). V0 series at α=2.5: kz_peak=4–5 across V0=0.03→0.20 (stable). γ_peak: 0.095→0.166→0.241→0.357 for V0=0.03→0.05→0.10→0.20. Linear scaling γ∝V0^0.92 (near-linear).

---

### Campaign 64 — α=0.5, V0=0.10, xi_sponge=22, kz=1..4 (t130, 2026-07-03)

Repeat of C31-region but with extended sponge xi=22 (vs earlier sp=16). Confirms kz_peak.

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.1218 | 0.3421  | 0.356 | reliable |
| 2  | 0.0801 | 0.1116  | 0.718 | reliable |
| 3  | 0.0635 | 0.0912  | 0.697 | reliable |
| 4  | 0.0530 | 0.0790  | 0.671 | reliable |

**kz_peak = 1** (γ=0.122). Confirms C31. kz=1 is reliably measured at α=0.5. Monotonically decreasing γ(kz) at low α — no secondary peak.

---

### Master kz_peak Table (all campaigns, 2026-07-03)

Growth peak from simulation (best sponge, reliable kz only):

| α   | V0   | αV0   | kz_peak (sim) | γ_peak (sim) | Campaign |
|-----|------|-------|---------------|--------------|----------|
| 0.5 | 0.05 | 0.025 | ~1 (unclear)  | —            | C59      |
| 0.5 | 0.10 | 0.05  | 1             | 0.122        | C31/C64  |
| 1.0 | 0.05 | 0.05  | 2             | 0.122        | C39      |
| 1.0 | 0.10 | 0.10  | 2–3           | 0.174        | C53      |
| 1.0 | 0.20 | 0.20  | 2*            | 0.214        | C54      |
| 1.5 | 0.03 | 0.045 | 3             | 0.103        | C41      |
| 1.5 | 0.05 | 0.075 | 3             | 0.144        | C34      |
| 1.5 | 0.10 | 0.15  | 3             | 0.216        | C51      |
| 1.5 | 0.20 | 0.30  | 2–3           | 0.216        | C60      |
| 2.0 | 0.02 | 0.04  | 3             | 0.068        | C61      |
| 2.0 | 0.03 | 0.06  | 4             | 0.115        | C42      |
| 2.0 | 0.05 | 0.10  | 4             | 0.157        | C35      |
| 2.0 | 0.10 | 0.20  | 5             | 0.211        | C55      |
| 2.0 | 0.20 | 0.40  | 4             | 0.310        | C52      |
| 2.5 | 0.03 | 0.075 | 4†            | 0.095        | C56      |
| 2.5 | 0.20 | 0.50  | 4†            | 0.357        | C63      |
| 2.5 | 0.05 | 0.125 | 5†            | 0.166        | C32      |
| 2.5 | 0.10 | 0.25  | 5†            | 0.241        | C57      |
| 3.0 | 0.02 | 0.06  | 4†            | 0.077        | C62      |
| 3.0 | 0.03 | 0.09  | 5†            | 0.111        | C36      |
| 3.0 | 0.05 | 0.15  | 5†            | 0.174        | C33      |
| 3.0 | 0.10 | 0.30  | 5             | 0.256        | C21b     |
| 3.0 | 0.20 | 0.60  | 3–4†          | 0.367        | C58      |
| 4.0 | 0.03 | 0.12  | 6             | 0.123        | C37      |
| 5.0 | 0.03 | 0.15  | 6             | 0.133        | C38      |

| 0.5 | 0.20 | 0.10  | ~1 (nonlin)   | —            | C66      |
| 1.0 | 0.01 | 0.01  | 2–3           | 0.054        | C65      |

*C54 only ran kz=1..3; kz_peak from kz=2 (ratio=0.69).
†kz=1,2 sponge-compressed or anomalous; reliable peak from kz≥3–4.

---

### Campaign 65 — α=1.0, V0=0.01, xi_sponge=40, kz=1..4 (t130, 2026-07-03)

αV0=0.01 (weakest coupling probed). ξ_crit(kz=1)=1/(1.0×0.01)=100 >> xi_sp=40 → kz=1 fully sponge-compressed. kz=3 borderline, kz=4 slightly nonlinear.

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.0414 | 0.4156  | 0.100 | (!) |
| 2  | 0.0512 | 0.0707  | 0.725 | reliable |
| 3  | 0.0556 | 0.0577  | 0.964 | borderline |
| 4  | 0.0568 | 0.0500  | 1.136 | nonlinear |

**kz_peak (reliable kz=2) = 2** (γ=0.051). V0=0.01 gives kz_peak=2, same as V0=0.05/0.10/0.20 for α=1.0 — consistent with kz_peak invariance. γ drops dramatically: 0.122→0.174→0.214→0.051 as V0 goes 0.05→0.10→0.20→0.01. V0=0.01 is well below the scaling trend — suggests non-perturbative threshold behavior near αV0~0.05.

---

### Campaign 66 — α=0.5, V0=0.20, xi_sponge=22, kz=1..4 (t140, 2026-07-03)

αV0=0.10. All kz show ratio>1 (sim greatly exceeds WKB). System exits linear regime before 100 TU.

| kz | γ_sim  | γ_exact | ratio | note |
|----|--------|---------|-------|------|
| 1  | 0.9670 | 0.2175  | 4.447 | nonlinear / parasitic |
| 2  | 0.1988 | 0.1575  | 1.262 | nonlinear |
| 3  | 0.2118 | 0.1290  | 1.643 | nonlinear |
| 4  | 0.2020 | 0.1118  | 1.808 | nonlinear |

kz=1 dominant at γ=0.967 — likely parasitic kz=0 contamination or rapid nonlinear cascade at α=0.5, V0=0.20 (αV0=0.10 is large relative to α=0.5). No reliable linear measurement. Need shorter target_tu or weaker perturbation_amp to catch linear window.

---

**Key patterns (updated 2026-07-03):**
1. **kz_peak ≈ 2α** at moderate V0 (V0=0.03–0.10): kz_peak = 1, 2, 3, 4, 5, 6 at α = 0.5, 1, 1.5, 2, 2.5–3, 4–5
2. **kz_peak is V0-independent at fixed α for V0≥0.02**: α=2.0 kz_peak=4 across V0=0.03–0.20; drops by 1 at V0=0.02
3. **γ_peak ∝ V0^0.85–0.92 at fixed α** for V0≥0.03; saturates at αV0≳0.15 (low α) or continues scaling (high α)
4. **Ratio sim/exact ≈ 0.5–0.7 near kz_peak** across all (α,V0) — systematic WKB overestimate of ~40–50%
5. **WKB dramatically overestimates at kz < kz_peak**: ratio<0.1 for kz=1 in strong-coupling campaigns
6. **Low-α high-V0 corner** (α=0.5, V0=0.20): all ratios>1, system nonlinear before 100 TU; boundary of accessible linear regime

---

## Investigation — `_bp28`/half-integer-kz sweep-table contamination, root cause (2026-07-14)

**Trigger**: sweep-table quality audit (see PRESENTATION.md §8.4) flagged 1159/3458 filled (α,V0,kz) grid
points as "suspect" (γ_sim > 2·γ_WKB or > 0.6 TU⁻¹). 514 of those (44%, the single largest cluster)
sit at half-integer kz — the `_bp28` family (Lz=4π, NZ=128, odd k_mode only, reached via
`lz_override`/`nz_override`) — with ratios up to 25.7× the WKB value.

### Hypothesis 1 (found + fixed, but NOT the cause): seed-width unit bug

`kernel_ym_init` (`YM_Init.cu:84`, mode 6 NAB_CIRC_AZ2 analytic-seed branch) computed the Az2/Az3
Gaussian width `xi_char = 1/sqrt(alpha_YM * k_mode * V0)` using the raw integer `k_mode` CLI argument
instead of the physical `k_z` already computed two lines above (`k_z = k_mode*2π/(nz*dz)`). Invisible
at the default box (Lz=2π, where k_z==k_mode by construction — every integer-kz production campaign
unaffected) but wrong whenever `lz_override` changes Lz: `_bp28` (kz_phys=k_mode/2) ran with the seed
width computed for 2× the intended kz, `_bp55` (kz_phys=k_mode/8) for 8×. Fixed (one-line, `k_mode`→`k_z`,
commit `f38b99b`) and verified by diffing the t=0 Az2(x,z=0) field dump pre/post-fix at k_mode=3
(kz_phys=1.5, α=1, V0=0.05, bp28): fitted Gaussian σ ratio new/old = 1.4142, matching predicted √2 to
4 decimals. **But 6 verification reruns (same xi_sponge as the original suspect run, only the binary
changed) showed no improvement**: new γ_sim within 1-3% of the old (buggy) values in every case, all
still 8-19× the exact eigensolver value, all still halting on the energy threshold within 16-34 TU
(e-folding ~0.5 TU — far too fast for the intended eigenmode, whose e-folding is 6-9 TU). Kept the fix
(it's correct and a no-op for all default-box data) but it does not explain the contamination.

### Hypothesis 2 (confirmed mechanism, not yet fixed): unfilterable on-target color-2/3 instability, race-condition against a weak real signal

Reran one point (α=1.0, V0=0.05, k_mode=3/kz_phys=1.5, bp28, xi_sponge=52) keeping raw field dumps
(normally deleted by `remote_timeseries.py`) and DFT-decomposed every field at every dump. `By1/Ex1/Ez1`
(color-1 EM) correctly stay exactly zero throughout (the existing Campaign-15 mitigation —
`cudaMemset` every step, gated on `suppress_kz0` — works fine). But `By2/By3/Ex2/Ex3/Ez2/Ez3`
(color-2/3 EM) all peak **exactly at the target bin** (kz=3) and grow from numerical-floor level
(~1e-9 at t=1 TU) through 8 decades by t=21 TU. `Az2/Az3` — the field the "amp" timeseries actually
measures — stays flat at its seed value for ~14 TU (tracking the true slow eigenmode, consistent with
γ_exact=0.1125), then gets swamped once By2/By3 becomes large enough to back-react through the
Ez2→Az2 coupling. **The reported anomalous γ is this second-order effect**: a By2/By3 instability that
isn't even the field being measured, catching up to and overwhelming the real signal partway through
the run. This is the same *category* of failure already documented and fixed for color-1
(`main_ym.cu` comment, line ~413: "By1[kz=1] grows at γ≈1.1 TU⁻¹ — a color-1 EM instability at the
target kz that the bandpass filter cannot suppress"). No equivalent protection exists for color-2/3,
and structurally can't (in mode 6) — color-2/3 growing at the target kz bin *is* the signal being
measured, so no kz-selective filter can separate the wanted mode from the parasitic one at the same bin.

**Control matrix ruling out resolution/box mechanics** (same α=1.0, V0=0.05, kz_phys=1.5 target unless noted; all on t130):

| NZ | Lz | NX | courant | filters | onset (E/E0>100) |
|----|----|----|---------|---------|-------------------|
| 128 | 4π (bp28) | 768 | 0.1 | on (production) | t≈21.4 |
| 256 | 4π (bp28) | 768 | 0.1 | on | t≈21.9 (~same) |
| 64  | 4π (bp28, via lz_override only) | 768 | 0.1 | on | t≈21.4 (~same) |
| 128 | 4π (bp28), even k_mode=2 (kz_phys=1) | 768 | 0.1 | on | t≈60.8 (later, still broken) |
| 128 | 2π (default, nz_override only) | 768 | 0.1 | on | t≈86 (much later, still broken) |
| 128 | 4π (bp28) | 768 | 0.1 | **off** (no sponge/suppress/hyp_diff) | t≈13.5 |
| 128 | 4π (bp28) | 768 | **0.01** | off | t≈13.5 (identical — rules out CFL/courant) |
| 128 | 2π (default), NX=384, courant=0.01 — **exact RESOLUTION_FINDINGS.md NZ=128 row** | 384 | 0.01 | off | t≈14.0 (run past their target_tu=25 cutoff) |
| 64 | 4π (bp28), α=2.0, **kz_phys=4** (near kz_peak≈2α) | 768 | 0.1 | on | **no blowup, clean 60 TU** |

Onset is essentially identical (t≈13.5-22) across NZ=64/128/256, Lz=2π/4π, NX=384/768, and a 10× change
in courant — **grid resolution is not the variable**. `RESOLUTION_FINDINGS.md`'s own NZ=128 convergence
test (perfect energy conservation reported) used `target_tu=25`; every onset measured here is inside
that window when the exact same parameters are reused, so that result is not contradicted, just never
ran long enough to see this — the code has also evolved since that study (e.g. the Campaign-15
color-1 mitigation postdates it).

The one variable that *does* matter: **target kz itself**. The identical `lz_override` mechanism, run
at kz_phys=4 (α=2.0, near kz_peak) instead of kz_phys=1.5, is completely clean for the full 60 TU
tested. This is a **race between the real eigenmode (γ_exact, weak at low kz_phys, strong near
kz_peak≈2α) and a competing color-2/3 on-target instability whose rate is ~0.7-0.8 TU⁻¹ regardless of
grid/box parameters**. Near kz_peak the real signal is fast enough to win outright; at low kz_phys
(0.5-2.5ish — exactly the region the half-kz campaigns targeted, since it's unreachable at integer kz
in the default box) it isn't.

### Mitigation attempts — both FAILED, and made things worse (2026-07-14)

Tried giving the real signal a head start, expecting a linear race to be winnable with enough of one:

| attempt | onset |
|---|---|
| baseline (analytic Gaussian seed, perturb_amp=0.001) | t≈21.4 |
| true eigenfunction seed file (`ym_eigenmode.py --export-seed`, correct shape incl. By2/qA/qB, same amplitude) | t≈14.0 — **earlier** |
| same Gaussian seed, perturb_amp=0.1 (100× bigger, still 10% of V0) | t≈18.4 — **earlier** |

Both a shape-correct seed (which also gives By2/qA/qB a small nonzero starting value, unlike the
default zero) and a 100× amplitude boost made the blowup happen *sooner*. This rules out a simple
"independent modes racing from fixed, amplitude-independent floors" model — if that were right, a
bigger head start for the real signal should buy more time, not less. The parasitic mode's effective
onset appears coupled to the perturbation amplitude itself (plausibly via the quadratic non-Abelian
coupling terms, e.g. α·(Az×By)^a in Ampere/Faraday, which are directly proportional to field
amplitude — a bigger seed is a bigger drive for any nonlinearly-coupled channel, not just for the
mode being measured). **No cheap mitigation currently known.**

### Root cause found and FIXED (2026-07-14, same session): `is_localised()` / xi_sponge formula, not a code bug

Queried `ym_eigenmode.py`'s full eigenvalue spectrum at the failing point (α=1.0, V0=0.05, kz_phys=1.5,
xi_sponge=52 — the value the production `xi_sponge_for()` formula actually assigned) with a shift near
the observed parasitic rate (`sigma=0.75`) instead of the default shift near γ_WKB. **Found real
eigenvalues at γ=1.4284, 0.3415, 0.3316, 0.2075 — all reported `is_localised()=True`** — alongside the
intended mode at γ=0.1125. Checked their eigenvectors: all four peak at |ξ|≈37-48, far from the shear
layer (the real mode peaks at ξ=-1.31). **These are the already-documented "outer-region EM instability"**
(see `## Outer-region EM instability — sponge design rule`, Campaigns 19-21 above) — genuine linear
eigenmodes of the same background, just not the shear-localised KH mode. `is_localised()`'s bound
(`xi_peak < 1.15 × xi_inner`, i.e. scaled by xi_sponge itself) is far too loose whenever xi_sponge is
large: at xi_sponge=52 it accepts anything peaking within ξ<60, which comfortably includes these outer
branches. The production `xi_sponge_for()` formula (`max(5, min(55, 1.3·kz/(α·V0)))`) pushes xi_sponge
toward the 55 ceiling for exactly the low-kz/low-αV0 corner the half-kz campaigns targeted — so the
sponge meant to *contain* the measurement window instead left the outer branch essentially unconstrained,
and its γ≈0.75-1.4 range matches the ~0.7-0.8 TU⁻¹ parasitic rate measured in the CUDA field decomposition
almost exactly.

**Confirmed by direct fix-and-rerun, not just theory.** Re-ran the same two points with `xi_sponge`
tightened to 15 (nothing else changed) and re-checked the eigensolver first to confirm the outer branch
disappears at that sponge:

| point | xi_sponge=52/orig | xi_sponge=15, eigensolver outer branch | xi_sponge=15, CUDA result |
|---|---|---|---|
| α=1.0, V0=0.05, kz_phys=1.5 (bp28, k_mode=3) | γ_sim=1.494 (8.25× exact), halts t≈21 TU | gone — top eigenvalue found is 0.1074 (the real mode) | **completes full 100 TU, E/E0=1.0000 throughout**; plateau fit γ=0.1192 over t=48-100 TU (52 TU duration) vs γ_exact≈0.107-0.11 — **~8-11% agreement**, in the same class as the trusted C25 series |
| α=0.5, V0=0.05, kz_phys=0.5 (bp28, k_mode=1) | γ_sim=0.786 (5.2× WKB), halts within run | outer branch at γ=0.75-0.76 (matches the CUDA rate almost exactly) present at sp=52, gone by sp=25/15 (top eigenvalue 0.0504-0.0511) | **completes full 100 TU cleanly**; plateau fit γ=0.0585 over t=69-100 TU (31 TU duration) vs γ_exact≈0.0504 — **~16% agreement** |

**This is a fix, not a workaround**: the mode-6 physics and measurement methodology are sound: the bug is
in *sponge selection*, not the simulator. The current `xi_sponge_for()` formula (`analysis/gen_multigpu_campaign.py`,
also embedded in the `reference_xi_sponge_formula` memory) needs to stop scaling *up* with low kz/low
αV0 — at minimum it should be checked against the eigensolver's own outer-branch-detection (sweep xi_sponge
downward from the formula's value until the fast/far-peaked eigenvalues disappear, same diagnostic used
here) before being trusted, rather than applying a blind formula. This plausibly explains a large fraction
of the ~1159 suspect sweep-table points generally (not just the 514 half-integer ones) — many of the
"integer kz≥1" suspects clustered at low α (§ suspect-points breakdown, PRESENTATION.md §8.4) are exactly
where this same formula pushes xi_sponge toward its ceiling.

**Not yet done** (as of the entry above): a proper replacement formula or systematic per-point sponge
search across the sweep; confirming the fix generalizes beyond two spot-checks; understanding why the
outer branch's rate is ~0.7-0.8 physically; rerunning the broader suspect set with corrected sponges.
Continued directly below.

---

## `find_safe_sponge.py` — eigensolver-based sponge selection tool, and its scope (2026-07-14)

Built `analysis/find_safe_sponge.py` to replace the blind `xi_sponge_for()` formula: for a given
(α, V0, kz), it screens a decreasing ladder of candidate xi_sponge values through the eigensolver
(which already includes the sponge as the identical damping term `kernel_ym_sponge` applies, so this is
a faithful, cheap CPU proxy), hunting each candidate with several shift-invert probes to catch outer-branch
eigenvalues a single default-shift search would miss. Classifies growing eigenvalues as "outer branch" if
their rate exceeds ~1.3×γ_WKB (calibrated, not derived), requires 2 CONSECUTIVE clean ladder rungs, then
applies a further 0.75× empirical margin — added after the two-point calibration below showed even a
"2-consecutive-clean" reading isn't reliably enough (see the sp=20 result).

**Calibration** (the two points already fix-verified above): tool recommends xi_sponge=15 for BOTH,
exactly matching the independently-confirmed-clean value, with γ_exact=0.1074 and 0.0504 — matching the
earlier hand-checks exactly.

**A one-shot "clean" reading is not sufficient — direct evidence.** Before settling on the 0.75× margin,
tested the *unmargined* ladder pick for α=1.0/V0=0.05/kz=1.5: sp=26 (a single clean rung) blew up at
t=57 of the 100-TU run; sp=20 (TWO consecutive clean rungs — the "properly conservative" stopping rule)
*still* blew up, later, at t=84.7. Only sp=15 (0.75× the 2-consecutive pick) held the full 100 TU clean.
The one-shot linear eigenvalue check is measurably optimistic relative to what the nonlinear 100-TU CUDA
run needs — there is slowly-growing residual outer-branch contamination invisible to a single snapshot
that only shows up given enough integration time.

### Scope confirmation — 5 points, full 100-TU CUDA runs

| point | tool's sp | CUDA result |
|---|---|---|
| α=1.0, V0=0.05, kz=1.5 | 15 | clean (calibration point) |
| α=0.5, V0=0.05, kz=0.5 | 15 | clean (calibration point) |
| α=0.3, V0=0.05, kz=0.5 | 11 | **clean**, flat E/E0=1.0000 the entire 100 TU |
| α=2.0, V0=0.03, kz=1.5 | 16 | **near-miss** — flat to t≈90, then a slow creep (E/E0 1.0000→31.05 by t=99.6); would very likely exceed the halt threshold given more TU. Not a clean pass. |
| α=1.5, V0=0.10, kz=2.5 | 12 | **fails**, blows up t=38.4. Retried at sp=8 (near the SP_MIN=5 floor, well past what the tool would ever recommend) — still blows up, just later (t=91.2). Tightening delays but does not eliminate it at this point. |

**Every V0=0.03-0.05 point tested passed or nearly passed; the one V0=0.10 point failed outright, even
near the sponge floor.** This strongly suggests the outer-region instability's strength scales with V0 in
a way the tool doesn't currently model — sponge-tightening alone may be structurally insufficient once V0
gets large enough (compare the original Campaign 19-21 finding: "growing faster than sponge can damp for
α≥3 or V0≥0.2" — this V0=0.10/α=1.5 failure suggests that boundary is joint in α and V0 and starts lower
than previously characterized, not a clean single-parameter cutoff).

**Practical scope, as validated**: trust the tool's recommendation as a strong starting candidate for
V0≲0.05 (still spot-check the first point of any new series against a full-length CUDA run — the gen1
near-miss shows even this regime isn't risk-free). For V0≳0.08, do not trust it — either a full per-point
CUDA verification is required, or a different mechanism entirely (the eigensolver's untried `xi_cut`
hard-wall Dirichlet option, which kills the outer region rather than just damping it, is the next thing to
try) is needed before those points can be measured cleanly at all.

**Still not understood**: what the outer-region branch physically *is* (a genuine secondary instability of
the shear+Az1 background vs. a numerical artifact of the linearization/discretization), why its rate
appears to scale with V0, and whether `xi_cut` (or some other mechanism) can exclude it without also
suppressing the physical KH mode at higher V0. This is flagged as an open deep-investigation item in
PRESENTATION.md — do not treat the sponge-tightening fix as a complete understanding of the mechanism,
only as an empirically-useful (and scope-limited) mitigation.

**Gap to fill**: α=0.5-1.0 at V0=0.05 (kz_peak < 2 requires Lz > 2π); α=1.0-2.0 at V0=0.10 for denser V0 coverage.

---

## Boundary-mapping the sponge fix around the (α=2.0, V0=0.03, kz=1.5) near-miss (2026-07-14)

Perturbed each of α, V0, kz independently up and down from the near-miss point, one axis at a time, all
in the bp28 box (Lz=4π, NZ=128), each run the tool's then-current (0.75x-margin) recommendation, full
100-TU CUDA:

| direction | point | tool sp | result |
|---|---|---|---|
| (center) | α=2.0, V0=0.03, kz=1.5 | 16 | near-miss (flat to t≈90, then creeping) |
| α up | α=2.5, V0=0.03, kz=1.5 | 11 | **clean** |
| α down | α=1.5, V0=0.03, kz=1.5 | 21 | fails, t=94.7 |
| V0 up | α=2.0, V0=0.05, kz=1.5 | 11 | fails, t=94.7 (same timing as α down) |
| V0 down | α=2.0, V0=0.02, kz=1.5 | 21 | **clean** (E/E0→1.0046, negligible) |
| kz up | α=2.0, V0=0.03, kz=2.0 | 21 | fails, t=61.8 (worse than center — surprising) |
| kz down | α=2.0, V0=0.03, kz=1.0 | 11 | **clean** |

Naive reading: α up / V0 down / kz down = safer, α down / V0 up / kz up = less safe, matching an
intuitive "closer to where γ_exact is strong relative to the ~fixed-rate outer branch" picture — except
kz up should have moved *toward* kz_peak≈2α=4 and gotten safer, not failed worse. That contradiction was
the tell that something was off with the *tool's margin*, not the physics.

**Resolved by retesting all 4 problem points at a much tighter fixed sponge (values in the sp=6-10
range) — every single one came back fully clean over the full 100 TU:**

| point | rescued at sp | result |
|---|---|---|
| center (α=2.0, V0=0.03, kz=1.5) | 10 | **clean**, E/E0=1.0000 flat to t=99.6 |
| α down (α=1.5, V0=0.03, kz=1.5) | 10 | **clean** |
| V0 up (α=2.0, V0=0.05, kz=1.5) | 6 | **clean**, E/E0 even drifts slightly down (0.9991 by t=99.6) |
| kz up (α=2.0, V0=0.03, kz=2.0) | 10 | **clean** |

**Conclusion: there is no hard physical boundary anywhere in this tested neighborhood** (α=1.5-2.5,
V0=0.02-0.05, kz=1.0-2.0) — every point is measurable with a properly tight sponge. What looked like a
near-miss/failure boundary in the first pass was the *tool's 0.75x margin being insufficient*, not a real
edge of the safe region. This is good news for the "how big is the volume we can now trust" question: at
least within V0≤0.05, the volume is much larger and more forgiving than the boundary-mapping's first
pass suggested — it just needs the margin fixed.

**But this isn't free — sponge compression is real and was checked directly** (eigensolver only, no
GPU): at the rescuing sponge values, γ_exact reads systematically lower than at a looser (but unsafe)
sponge — e.g. the V0-up point: γ=0.172 at sp=30 (unsafe) vs γ=0.115 at sp=10 (safe), a 33% reduction.
This is the already-documented sponge-compression tradeoff (PRESENTATION.md §8.3), now shown to bind
harder than expected in this corner: you cannot have both "definitely excludes the outer branch" and "no
compression" simultaneously at these points — the safe margin costs real amplitude accuracy.

**Revised the tool's SAFETY_MARGIN from 0.75x to 0.5x** based on this 7-point dataset (3/6 new points
needed roughly 0.4-0.6x their own ladder pick, not 0.75x). Re-running the tool at 0.5x recommends sp=10
for the center point (exactly the confirmed-safe value) and sp=8/14 for two others (close to, not
exactly matching, the manually-confirmed 6/10 — extrapolated, not independently re-verified by a fresh
CUDA run). The two original calibration points now get sp=10 instead of the previously-confirmed sp=15
— tighter is monotonically safer based on all evidence so far, so this should if anything be more
conservative, but wasn't re-run to confirm.

**Net picture for "what volume can we trust now"**: for V0≤0.05, roughly α=0.3-2.5 and kz=0.5-2.5 (the
union of everything tested across both fix-fix threads) now looks like a genuinely safe, contiguous
region once the sponge is set properly tight (~sp 6-14 depending on point, not the old formula's 21-55) —
at the cost of the known compression bias, not yet separately corrected for. V0=0.10 remains a hard wall
(failed even at the sponge floor in the earlier test) — the V0=0.05→0.10 transition has not been mapped
in between (e.g. V0=0.07-0.08 untested) and is the natural next boundary-mapping direction if that's
wanted.

---

## Mapping the V0=0.05→0.10 transition (2026-07-14)

Fixed α=1.5, k_z=2.5 — the exact point that originally failed at V0=0.10 — and swept V0 upward
(0.06, 0.07, 0.08, 0.09), first at the tool's own recommendation, then retested at the sponge floor
(sp=5) whenever the first attempt still showed contamination. One cross-check at a different (α, k_z)
(α=2.0, V0=0.07, k_z=1.5) confirms the V0=0.07 result isn't specific to the first point.

| V0 | tool's sp | tool result | floor (sp=5) result |
|---|---|---|---|
| 0.05 | ~15 | clean (established earlier) | — |
| 0.06 | 11 | near-miss (E/E0→3.52 by t=99.6, "completed" but climbing) | **clean** — E/E0 stays 0.99-1.01 the whole 100 TU |
| 0.07 | 9 | near-miss, milder (E/E0→1.52, appears to plateau near the end) | **clean** (confirmed at α=1.5 AND independently at α=2.0/kz=1.5) |
| 0.08 | 8 | near-miss (E/E0→2.03, still rising) | **near-miss, mild** — flat to t≈96, creeps to E/E0≈1.22 |
| 0.09 | 9 | **fails outright**, t=82.7 | **near-miss, moderate** — E/E0≈1.28-1.35, visible contamination by t≈90, not eliminated |
| 0.10 | 12 / 8 | fails, t=38 / t=91 | fails (already established; sp=8 was effectively at-floor for that point too) |

**This is a gradual transition, not a step function.** V0≤0.07 is genuinely usable — every point
tested there is fully rescuable to a clean 100-TU run (though 0.06-0.07 needed the sponge floor, not
just a moderate value, to get there — the tool's own recommendation undershot at both). V0=0.08-0.09 is
a real transition zone: even the tightest sponge tried leaves measurable, non-catastrophic residual
contamination (mild at 0.08, moderate at 0.09) that would bias any quoted γ upward, not a clean
measurement but also not an outright failure. V0≥0.10 is a hard wall where tightening no longer helps at
all, confirmed independently at two sponge values.

**Practical takeaway**: the sponge-tightening fix is trustworthy for V0≤0.07 (still spot-check new
points, and expect to need floor-level sponges near the top of that range, with the associated
compression cost). V0=0.08-0.09 should be treated as "measurable but biased" at best — not safe to quote
without heavy caveats, and probably not worth rerunning until a better mechanism exists. V0≥0.10 needs a
fundamentally different approach — updated `find_safe_sponge.py` to warn accordingly (transition-zone
warning for 0.07<V0≤0.09, hard-wall warning above that). Next: try the eigensolver's `xi_cut` hard-wall
option (Dirichlet BC, kills the outer region rather than damping it) on a V0=0.09 or V0=0.10 point to
see whether it does better than the soft sponge in this zone.

---

## `xi_cut` implemented in CUDA — solves the V0=0.09-0.10 hard-wall zone (2026-07-15)

### Eigensolver experiments first (CPU-only, before touching CUDA)

Compared `xi_cut` (hard Dirichlet wall, `build_matrix`'s existing option) against `xi_sponge` (soft
exponential damping) in `ym_eigenmode.py`, at matched radii, for α=1.5, k_z=2.5 across V0=0.05-0.10:

1. **Compression cost, quantified**: at the same radius, `xi_cut` systematically retains more of γ_exact
   than `xi_sponge` — the gap widens as the radius tightens: ~4% at radius=15, ~10% at radius=10, ~30%
   at radius=5 (V0=0.05/0.07, α=1.5, k_z=2.5). A hard wall doesn't touch the interior at all; a soft
   sponge's damping term bleeds into the mode's tail even before its nominal start radius.
2. **A critical limitation of the eigensolver screen itself, found by direct comparison to known CUDA
   ground truth**: `xi_sponge=8` at V0=0.10 shows **zero** outer-branch eigenvalues in an exhaustive
   multi-shift search (12 shifts up to γ=12, 10 eigenvalues each) — yet this exact configuration is
   *confirmed by CUDA* to blow up at t≈91. The linear eigenvalue problem the eigensolver solves does not
   contain whatever actually kills the V0≥0.09 CUDA run. This means the eigensolver's "xi_cut also reads
   safe there" result **could not be trusted on its own** — the tool that would tell us is demonstrably
   blind in exactly that regime for the soft-sponge case, so real CUDA testing was required before
   drawing any conclusion for xi_cut in the V0=0.09-0.10 zone. (It turned out xi_cut's readings there
   *were* trustworthy — see below — but this could not have been known without testing.)

### Implemented `kernel_ym_xicut` in CUDA

Added a genuine hard-wall Dirichlet kernel (`YM_Physics.cu`), matching `ym_eigenmode.py`'s `xi_cut`
exactly: unconditionally zeroes By2/By3/Ex2/Ex3/Ez2/Ez3/Az2/Az3/Q2A/Q3A/Q2B/Q3B for `|ξ| > xi_cut` every
step (no damping ramp, no dt-dependence — the same 12 fields `kernel_ym_sponge` touches, just forced to
exactly zero instead of decayed). New `xi_cut` config key (`YM_Config`), `YMParams.xi_cut`, called
right after the existing sponge kernel in the main loop — can be used alone or together with
`xi_sponge`. Verified correctness directly: a t=2 TU field dump at `xi_cut=8, eps_override=0.15` shows
all touched fields exactly `0.0` for `|ξ|>8` and untouched inside.

**Note on deployment**: found t130's `YM_Fluid.cuh/.cu` had diverged from git — an unrelated, uncommitted
warm-fluid-closure prototype (`kernel_ym_lorentz` with extra `warm_T, dx, dz` params, not present
anywhere else: not in git, not on t132/t140/t126/abi). User confirmed (2026-07-15) this was a failed
experiment, safe to overwrite — done, all three build nodes (t130/t132/t140) now match git exactly.

### CUDA results — the actual hard-wall zone, for real this time

Same protocol as the V0-transition mapping (α=1.5, k_z=2.5 fixed, xi_cut=5 — deliberately the *same*
tight radius the soft sponge floor used, for a fair comparison), full 100-TU runs:

| V0 | soft xi_sponge=5-8 (established) | xi_cut=5 (new) |
|---|---|---|
| 0.09 | near-miss even at floor: E/E0≈1.28-1.35, visible contamination by t≈90 | **E/E0≈1.01-1.02, flat the whole run** |
| 0.10 (the confirmed hard wall) | **outright failure**, E/E0>100, at every sponge tried down to the floor | **E/E0≈1.09-1.10, bounded and stable, no runaway** |

Fitted growth rates, using the plateau method (not max-R², per the established §8.5 fit-methodology
finding) — both points found a genuine, multi-decade-spanning plateau:

- V0=0.09: plateau γ=0.1995 (15 TU duration, t=38-54) vs. eigensolver γ_exact(xi_cut=5)=0.2016 —
  **ratio 0.99, essentially exact.**
- V0=0.10: plateau γ=0.2141 (15 TU duration, t=35-50) vs. eigensolver γ_exact(xi_cut=5)=0.2163 —
  **ratio 0.99, essentially exact.**

This is not "bounded but messy" — it's a clean, accurate measurement, in the exact regime the soft
sponge could never reach at any tightness. The hard Dirichlet wall is qualitatively different from the
soft sponge, not just a tighter version of it: because it forces the outer fields to *exactly* zero every
step regardless of amplitude, it can't be defeated by whatever nonlinear/finite-amplitude effect was
apparently leaking past the soft sponge's damping (the mechanism the linear eigensolver couldn't see in
the xi_sponge case, per the limitation noted above) — it simply removes the outer region's influence
outright, unconditionally.

**Accuracy check (why implement it even in the already-working regime)**: α=2.0, V0=0.07, k_z=1.5,
xi_cut=5 — the same point independently confirmed clean under `xi_sponge=5`. This one is *not* a clean
plateau story: the local-slope trace shows a genuine multi-regime curve (seed-transient decay from t=0-30,
a bumpy growth phase peaking γ≈0.20 around t=42-48, a slow decline, then nonlinear rolloff after t≈75).
max-R² landed on the peak (γ=0.193) and does not represent a verified rate — consistent with the
project's own established §8.5 finding that max-R² is attracted to transients. The later, flatter part of
the curve (t=65-72, local slope≈0.15-0.16) sits close to the eigensolver's own γ_exact(xi_cut=5)=0.156,
which is the more defensible read. Not as clean a confirmation as V0=0.09/0.10, but not a contradiction
either — just a reminder that plateau/local-slope reading, not max-R², is required here too.

### Practical consequence — this reopens the whole V0≥0.08 suspect population

`xi_cut=5` (or similar) should be tried as the default exclusion mechanism going forward, not just a
V0≥0.08 patch — it's strictly more accurate than the soft sponge everywhere tested, and it just
solved the one class of point (V0=0.09-0.10) that sponge-tightening structurally could not touch.
**Not yet done**: test xi_cut at V0>0.10 to find where (if anywhere) it too has a limit; re-verify the
V0≤0.07 boundary-mapped points with xi_cut instead of xi_sponge for the accuracy win; combine xi_cut
(outer, hard) with a mild xi_sponge (inner, soft) to see if that's better than either alone; update
`find_safe_sponge.py`-style tooling to search xi_cut candidates, not just xi_sponge. Radius sweep done
below.

---

## xi_cut radius sweep at V0=0.09-0.10 — corrects the "solved" framing above (2026-07-15)

Swept xi_cut from 5 up to 15 at the same α=1.5, k_z=2.5, V0=0.09/0.10 points, full 100-TU CUDA:

| xi_cut | V0 | (α,k_z) | result |
|---|---|---|---|
| 5 | 0.10 | 1.5, 2.5 | clean, plateau γ=0.2141 (t=35-50), no catastrophe within 100 TU |
| 5 | 0.09 | 1.5, 2.5 | clean, plateau γ=0.1995 (t=38-54), no catastrophe within 100 TU |
| **5** | **0.10** | **2.0, 1.5 (cross-check)** | **catastrophic jump at t=97.7 — barely inside the 100-TU window** |
| 5.5 | 0.10 | 1.5, 2.5 | catastrophic jump at t=90.2 |
| 6 | 0.10 | 1.5, 2.5 | catastrophic jump at t=89.7 |
| 7 | 0.10 | 1.5, 2.5 | catastrophic jump at t=91.7 |
| 7 | 0.09 | 1.5, 2.5 | catastrophic jump at t=92.2 |
| 10 | 0.09 | 1.5, 2.5 | catastrophic jump at t=57.3 |
| 10 | 0.10 | 1.5, 2.5 | catastrophic jump at t=47.8 |
| 10, hyp_diff=2.5e-4 (5×) | 0.10 | 1.5, 2.5 | catastrophic jump at t=87.7 (delayed vs. default hyp_diff, not eliminated) |
| 15 | 0.10 | 1.5, 2.5 | catastrophic jump at t=26.9 (earliest/worst) |

**Every failure has the same distinctive signature**: bounded, mildly elevated E/E0 (typically 1.4-3.5×)
for most of the run, then a sudden jump of 4-6 orders of magnitude within a single ~0.5 TU output
interval — qualitatively different from the smooth exponential blowup the soft sponge showed. Increasing
hyperdiffusion 5× did not fix it (only delayed it modestly), ruling out "grid-scale/near-Nyquist noise
from the wall's field discontinuity, fixable by more dissipation" as the mechanism.

**This corrects the earlier framing**: `xi_cut` does **not** have a hard safe/unsafe cliff at radius 5 —
it is the **same underlying late-onset instability that dominates the soft-sponge failures**, just
delayed far more effectively by the hard wall, with onset time falling sharply as the radius loosens
(t≈27 at radius 15 → t≈48-92 at radius 6-10 → past 90-100 at radius 5, but **not reliably past 100 for
every point** — the α=2.0/k_z=1.5 cross-check at xi_cut=5 hit the same catastrophe at t=97.7). xi_cut=5
is not "solved and stable," it is "delays onset long enough, in most tested cases, for a clean plateau
measurement to complete with comfortable margin before the eventual catastrophe."

**Why this is still a real, practically important result, not a retraction**: the plateaus at xi_cut=5
are established early (t=35-54) and hold for 15+ TU with a clean fit matching the eigensolver to ~1% —
well before any observed catastrophe onset (earliest observed at radius 5 was t=97.7, still >40 TU of
margin past the plateau). The soft sponge, by contrast, **never established a clean plateau at V0=0.10 at
any radius tested, including its own floor** — its failures overlapped the measurement window itself, not
just the tail of a long run. So the practical conclusion holds even though the "fully stable" framing
does not: **for production use at V0=0.09-0.10, use xi_cut=5 (not looser) and cap target_tu well below
where the catastrophe has been observed** (comfortably under 90 TU, with the plateau itself typically
readable by t≈55) **rather than running to the old default's full-length/energy-threshold behavior.**

**Not yet done**: characterize the catastrophe mechanism itself (still unknown — ruled out hyperdiffusion
as a fix, not yet checked whether it's an FP32 precision-accumulation effect, a genuine secondary
bifurcation, or something else); find xi_cut's onset-time dependence on (α, k_z) more systematically
(only one cross-check point so far); check whether target_tu capped below the observed onset is
sufficient for reliable production use, or whether the onset time itself needs to be predicted per-point
before trusting a run not to hit it mid-measurement.

---

## Outer-region growth rates: mechanisms identified (2026-07-15 investigation)

Dedicated investigation into what the "outer-region instability" physically is
(the open item flagged in the 2026-07-14 sections above and PRESENTATION.md
item 3b). Summary hub: `OUTER_REGION.md`. Derivations: `PHYSICS.md` §10.
Analysis ran on the lab iMac (new CPU work machine — see CLAUDE.md §Server
Setup); tools: `analysis/outer_region_theory.py`,
`analysis/catastrophe_forensics.py`, `analysis/onset_census.py`.

**Headline: two unrelated mechanisms were being conflated.** The fast
contamination at loose sponges is a *linear, outer-region, purely-EM
tachyonic instability of the frozen Az1 background* (physical in-model,
predictable, correctly excluded by windowing). The late-onset catastrophe
(the "V0≥0.08 hard wall", the xi_cut radius-sweep failures) is *not an
outer-region effect at all* — it is finite-amplitude **density cavitation of
the physical KH mode at the shear layer**, followed by a long-lived
floored-density state and a delayed terminal blowup.

### 1. The linear outer branch is the tachyonic charged-wave instability

At kx=0 the linearized color-2/3 Faraday/Ampere pair closes on itself:
γb = −iΩ_F·ex, γex = −iΩ_A·b ⇒ **γ² = −Ω_A·Ω_F = α²Az1² − kz²** — growth
wherever |α·Az1(ξ)| > kz, i.e. |ξ| > ξ_crit ≈ kz/(αV0) + ln2. This is the
γ_outer ≈ √(|Ω_A|·Ω_F) empirical rule of the 2026-07-02 sponge-design section,
now derived and identified: the covariant derivative gives the two circular
polarizations kz_eff = kz ± αAz1; past ξ_crit one of them is tachyonic
(Nielsen-Olesen-type mechanism). It is the same α²V0kz-type term that forms
the WKB confining well — the outer branch is the trapping term continued past
the well rim.

Quantitative check (`outer_region_theory.py validate`, iMac) at the
documented worst case α=1.0, V0=0.05, kz_phys=1.5, xi_sponge=52, NX=384 — the
full 6-field local dispersion γ_loc(ξ) (numerically maximized over kx) equals
the analytic tachyonic law **exactly** at every outer eigenmode peak (fluid
terms contribute nothing out there — pure EM mechanism):

| γ_eigensolver | ξ_peak | γ_loc(ξ_peak)=γ_tac | eig/local |
|---|---|---|---|
| 1.4598 | +48.4 | 1.857 | 0.79 |
| 1.4284 | −48.1 | 1.836 | 0.78 |
| 0.3415 | −38.0 | 1.106 | 0.31 |
| 0.3316 | +38.0 | 1.106 | 0.30 |
| 0.2075 | +37.3 | 1.049 | 0.20 |

The global (eigensolver) rates sit *below* the local envelope in a discrete
ladder — standard global-mode structure: finite-width kx-quantization inside
the tachyonic annulus [ξ_crit, wall] costs growth (Airy-type quenching; this
is also why a tight sponge/cut kills the branch entirely even though γ_loc>0
pointwise there — the annulus becomes too narrow to hold a bound state).

**Not a numerical artifact** — three independent confirmations: analytic
local law; float64 scipy eigensolver; float32 CUDA rates (documented
2026-07-14: CUDA 0.786 vs eigensolver 0.75-0.76 at this point). Rates scale
with physics (αAz1 product — cf. C19 vs C20 identical γ_outer at equal
α·Az1), not with resolution. **Physical caveat**: its unbounded energy source
is the *frozen* Az1 — an external battery. Self-consistently the branch would
deplete the background (chromo-background decay by charged-wave emission);
its presence is a property of the idealized model, so excluding it by
windowing is legitimate, not sweeping physics under the rug.

### 2. The late catastrophe is density cavitation at the shear layer

Direct forensics on the one failing run with dense snapshots retained —
`ym_k3_a2.000_..._v0.1000_xc5.0_..._xc5_v10_diffkz` on t140 (α=2.0,
kz_phys=1.5, V0=0.10, xi_cut=5, 98 snapshots ≈1/TU, terminal jump t=97.7).
Reduction: `catastrophe_forensics.py extract` on t140 → 9 MB npz → analyzed
on the iMac (`~/ym_kh/forensics_diffkz.npz`). Snapshot format now carries 25
columns incl. nA/nB densities and all E fields.

Timeline (all at the **shear layer**, inside the xi_cut window):

- t≈30–55: physical KH mode grows (By2@k_mode local slope ≈0.19,
  eigensolver γ_exact(xc5)≈0.19-0.20 for this point) — the documented clean
  plateau.
- **min-density trace: nA_min = 1.0 (t≤32) → 0.9987 (t=40) → 0.975 (t=48) →
  0.64 (t=56) → 0.0500 = the code's density floor (t=64), and stays pinned
  there for the remaining ~34 TU.** Cavitation completes ~35 TU before the
  energy catastrophe.
- The density perturbation nA@k_mode is the cleanest-growing channel
  (γ=0.160, r²=0.98 over t=40-97 — consistent with the δn ~ mode-quadratic
  compressive response at ≈2×the saturating mode rate). Its x-power is 96%
  inside |ξ|<5 by t=57, 99.9% by t=81. **The outer region is quiet.**
- t=64→97: bounded floored-pocket state (E/E0 creeps 1.00→1.09 — energy.csv
  only sees the tail of this); t=97.7: terminal 6-order jump (p/n divisions
  against the floor).

**Amplitude threshold confirmed across sibling runs** (same-method
comparisons): the V0=0.07 sibling (`xicut_acc`, clean full 100 TU) peaked at
timeseries-amp 1.0×10⁻³ — an order of magnitude below cavitation; the
V0=0.10 survivor (`xicut_v10`, kz=2.5) reached 9.4×10⁻³ at t=99.6, just
approaching threshold exactly as its E/E0 creep appeared (t≳70). In
spectral-amp units the diffkz cavitation threshold is ~1–2×10⁻² (By2-channel,
this config). So **V0 sets whether the drive reaches cavitation amplitude
within the run** — the gradual V0=0.05→0.10 transition mapped on 2026-07-14
is an amplitude competition (benign saturation vs cavitation), not a
distinct outer instability turning on.

**Why the eigensolver is blind** (the previously-unexplained 2026-07-15
limitation): both because the effect is nonlinear *and* because the
eigensolver's state vector [b,ex,ez,a,qA,qB] contains no fluid density or
momentum dof at all — by construction it cannot represent cavitation at any
amplitude.

**xi_cut radius ordering explained-in-part**: eigensolver γ_exact across
xc=5→15 (α=1.5, kz=2.5, V0=0.10, measured on iMac): 0.2163, 0.2187, 0.2225,
0.2262, 0.2294, 0.2234 — only a 6% spread, so the radius trend of the
*terminal* jump (t≈27 at r=15 vs >100 at r=5) is **not** a growth-rate
(compression) effect: cavitation happens at ≈the same time regardless of
radius; the radius controls how long the *post-cavitation floored state*
survives (empirical; suspect cavitated-volume size / wall proximity
quenching). Practical rule unchanged: xi_cut=5, cap target_tu past the
plateau.

### 3. Tested and rejected: outer two-stream as the catastrophe driver

The color-1 cold two-stream at the retained kz was a strong a-priori
candidate (α-independent, rate γ_ts ∝ kzV0 at small kV — the right V0
scaling; exact code-units dispersion γ² = √(4(kV)²+1) − (kV)² − 1 with
per-beam ωp=1, whose kV<√2 cutoff *exactly* reproduces the documented
kz_ts≈14 band at V0=0.1; predicted time-to-blowup 14/γ_ts: 59 TU at V0=0.10
→ 114 TU at V0=0.05, eerily matching the observed V0 ladder). **Forensics
rejects it**: PzA/nA growth localizes at the shear layer, not in the
|vz|≈V0 outer region, and the implied-seed consistency breaks on the α=2.0
cross-check. Kept documented here because the onset-time coincidence is a
trap future analysis could re-fall into; `outer_region_theory.py twostream`
prints the full table.

### 4. Population census (context, weaker evidence)

`onset_census.py` over all 1,365 parseable t130+t140 runs (2026-07-15 pull,
mirrored to iMac `~/ym_kh/energy_pull/`): 901 catastrophes / 45 creep / 419
clean. Splitting by tachyon exposure (ξ_crit vs window radius) shows the
loose-window population's creep rates (~1-2.5 TU⁻¹) in the documented
global-tachyonic range, but the census creep fits conflate physical-mode
saturation with contamination and mix Lz/bp conventions — treat as context
only; the controlled-series + forensics evidence above is what the
conclusions rest on.

### Consequences for the program

1. Windowed measurements are legitimate; plateaus completing before
   cavitation are clean. xi_cut=5 remains the production mechanism.
2. For V0≥0.08: predict/monitor cavitation via mode amplitude (timeseries
   amp approaching ~10⁻² in this config), not via a fixed safe time; cap
   target_tu accordingly. `find_safe_sponge.py`-style linear screens can
   never certify against mechanism 2.
3. The V0≤0.07 "safe zone" is not mechanistically different — it is where
   saturation stays below the cavitation amplitude within 100 TU.
4. Open: post-cavitation survival-time mechanism; a V0=0.08-0.09 run with
   snapshots retained to watch marginal cavitation; self-consistent Az1
   depletion by the tachyonic branch (khaxn-relevant).

---

## Self-consistent (unfrozen Az1) test of the tachyonic branch — depletion does NOT occur; the back-reaction DEEPENS the background (2026-07-15/16, t133)

Follow-up to the mechanism identification above (OUTER_REGION.md open item
#3). New node t133 set up for this (see CLAUDE.md §Server Setup). Reference
point: α=1.0, V0=0.05, kz_phys=1.5 (bp28 box), the documented tachyonic
configuration. Code additions (committed): Az1 snapshot export column,
`init_by1_eq`, `vz_edge_taper` — see those commits for details.

### Result 1 — the frozen approximation is validated for the linear phase

Frozen reference (sp=52, suppress_kz0=1) reproduces the documented blowup
exactly (halt t=21.4, γ from snapshots 1.45 vs eigensolver 1.43-1.46).
Unfrozen + color-1-live variants grow at the same rate, halting only ~3 TU
earlier (extra seeding via color-1 noise). Freezing Az1 does not
meaningfully distort the tachyonic branch's linear growth.

### Result 2 — three obstructions to a self-consistent color-1 sector,
two fixed, one physical

Any depletion measurement needs `suppress_kz0=0` (the sponge/filters never
touch Az1, and the depletion channel is mode² → By1/Ez1 @ kz=0 → Az1).
Doing that exposed, in order:

1. **Periodic-wrap collapse** (dominant): the single-tanh vz jumps ±V0
   across the wrap at |ξ|=62.8; with kz=0 live this drives nA → floor at the
   box edge by t≈6, junk propagating inward at c. **This — not the Weibel
   alone — is the real reason suppress_kz0=1 is mandatory in production.**
   Fixed by `vz_edge_taper=50` (+ By1_eq integrating the tapered current).
2. **Secular By1 pump at the shear layer**: with By1=0 init the color-1
   sector is out of equilibrium (∂x By1 ≠ Jz1 = −2V0 tanh ξ); the screened
   DC of Ez1 pumps By1 at the layer (dBy1≈0.45 by t=12) → collapse. Fixed by
   `init_by1_eq=1` (current-consistent By1, half-cell-shifted to make the
   backward-difference Ampere stencil exact to O(dx²)). Az1 needs no fix —
   ∂x Az1 never enters the dynamics.
3. **kz=0 chromo-Weibel of the beams themselves** (irreducible physics):
   γ=0.284 at this (α,V0) per the documented formula, seeded at O(10⁻²) by
   the residual equilibration transient → E/E0 blowup at t≈23 in every
   sk0=0 run regardless of seed/freeze. This is the hard floor: a "quiet"
   self-consistent counter-streaming background does not exist — some kz=0
   channel is always growing.

### Result 3 — the back-reaction is real, quadratic, and has the WRONG SIGN
for depletion

Differencing unfrozen seeded vs unfrozen unseeded runs (identical
deterministic background dynamics cancels; B−C in the run tags) isolates the
tachyon's own imprint on Az1@kz=0:

| t | mode max\|a\| (annulus) | max\|ΔAz1\| (annulus) |
|---|---|---|
| 12 | 1.4e-4 | < 1e-6 |
| 14 | 3.0e-3 | 3.6e-6 |
| 16 | 6.1e-2 | 1.6e-4 |
| 17 | 2.9e-1 | 3.6e-3 |

Clean quadratic scaling: **ΔAz1 ≈ −0.04·|a|²**, localized at the mode peak
(ξ≈+49). The sign is *negative where Az1<0*: the wave makes the background
**deeper** (|αAz1| larger), not shallower — anti-screening / positive
feedback, consistent with unfrozen runs dying slightly earlier than frozen.
Extrapolating the quadratic law, self-quenching by background modification
would require |a| ≈ 2.5 (≈50 V0) — far beyond where the fluid model dies
(density cavitation / energy halt at |a| ≈ 0.3-0.5). **Depletion is not the
saturation route for this branch in this model.** The physical picture to
quote: the frozen-Az1 approximation is conservative — self-consistency makes
the tachyonic branch (slightly) worse, and its true saturation is by fluid
nonlinearity, not background drain.

(A confirmation trio at an intermediate-rate annulus — sp=42, γ=0.642,
eigenvector-seeded at 20× amplitude to push |a| toward O(1) inside the
pre-Weibel window — was launched on t133; connectivity dropped before
retrieval. Its analysis can only strengthen/refine the quadratic-law
coefficient; the sign and scaling above are already established by the
sp=52 pair.)

**Physics interpretation for khaxn**: in a fully self-consistent setting the
counter-streaming beams continuously re-supply the color-1 background (and
the charged waves locally deepen it); the frozen-background "infinite
battery" is therefore not an overestimate of the drive — the instability of
such backgrounds is robust, and its endpoint is fluid-scale (cavitation)
rather than field-scale (depletion).
