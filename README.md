# Manifold model-collapse — reproducibility packet

Self-consuming (recursive) training of diffusion models on **manifold-supported
(singular) data** — the σ→0 / infinite-Fisher regime that 2606.13796 (Cambridge) left
as an explicitly **open Case 2**. This directory contains the code, data, and figures
behind the result: annealed truncation (Cambridge's remedy) cannot reach the data
distribution in this regime, and a data-anchoring matcher does.

**Read [`PROOFS.md`](PROOFS.md) for the theorems and the honest ledger (§5).** Claims are
tiered there as **proved** (theorems / lower bounds), **experimentally validated**
(the runs below), and **partially modeled** (empirical mechanisms). This README is the
run-order map; it does not restate the math.

**New to the paper? Start with [`paper/WALKTHROUGH.md`](paper/WALKTHROUGH.md)** — a
plain-English companion that explains every theorem, assumption, and proof step in words
and answers "why?" for each, ending with a self-quiz of the questions a reviewer will ask.

This repository is a curated subset of a larger private research directory: it contains
everything needed to reproduce the paper's claims (scripts, logs, the paper itself), but
two sections below (*Supporting / earlier-phase evidence*, *Not load-bearing*) describe
earlier or superseded scripts that live only in that private directory, kept here for
context — they are not part of this repository.

---

## Environment

- **CPU-only** for the core pipeline (steps 1–13; all runs were done on 12 threads, no
  GPU needed). The CIFAR-10 scale check (steps 14–16) is GPU-only in practice (small conv
  UNet, AMP; a laptop RTX 3050 took ~4.75 h/seed) — it is a preliminary supplement, not a
  load-bearing claim of the paper.
- Python 3.11+, with `numpy`, `torch`, `matplotlib`. `torchvision` is only
  needed once to build the MNIST cache (a prebuilt `mnist8x8.npz` is already included).
  `falsify_floor.py` additionally needs `scipy` (and uses `sympy` if installed). The CIFAR
  scripts need `pyarrow` and `pillow` to decode the HuggingFace parquet.
- Each script sets `os.environ["KMP_DUPLICATE_LIB_OK"]="TRUE"` before importing torch and
  calls `torch.set_num_threads(12)` — no shell setup required.
- Every long run is **append-only resumable**: results stream to a `*.jsonl`; re-running a
  script skips keys already present. Kill and restart freely.

Run anything with `python <script>.py`.

---

## Core pipeline (this is the paper)

Ordered as the argument is built. "Establishes" ties each run to a claim; "→ figure" ties
it to a panel in [`paper/figs/`](paper/figs) (the committed, final figures). Running
`make_figures.py` yourself regenerates them into a local `figures/` first, exactly as in
step 12 below.

| # | Script | Output | Establishes | → figure | ~time |
|---|--------|--------|-------------|----------|-------|
| 1 | `rprime_probe.py`, `rprime_probe2.py` | `rprime_probe25.jsonl`, `rprime_probe2_25.jsonl`, `rprime_probe_net25.pt` | **Measured** network normal-slope ceiling κ̄ ≈ 3.9, residual field r²≈0.03, ν≈0.75 (R=2.5 ring). The single input the floor prediction needs. | — | ~3 min |
| 2 | `deficit_floor_law.py` | `deficit_floor_law.jsonl` | Finite-σ floor table Φ_det(κ̄): Φ_det/σ²={14.1,6.28,3.82,2.44,1.43,1.00} at κ̄={2,3,3.9,5,7,10} (σ=0.05). κ̄=3.9→3.8σ² is the **envelope floor, a proven lower bound** — it explains ~60% of the directly measured single-pass floor (6.3–7.5σ²); rows 23–25 measure the remainder's anatomy and test the law interventionally. (Thm I(a), items 1 & 6) | **fig4** | seconds |
| 2b | `floor_theory_upgrade.py` + `closed_form_check.py` | stdout (tables) | **CLOSED FORMS (proved).** Limit ODE in ρ=2σκ̄ alone (universality = theorem, Lemma 3.2); no-overshoot g(ρ) explicit, C₀=(1+3e⁻⁴)/2, Φ→0.1319/κ̄²; **unconditional** (κ̂≤κ̄ only) g=1/(2ρ²) exact, Φ→1/(8κ̄²), floor>σ² ⟺ ρ<1/√2. Closed forms vs numerics ≤2.4e-5. "0.141" = finite-σ effective value of exact 0.1319. (Lemmas 3.2/3.3, challenge #13) | — | ~4 min |
| 3 | `head_to_head.py` | `head_to_head.jsonl` (15) | **Headline.** Cambridge annealed truncation (t₀:0.05→1e-4, no anchor) vs ours (std+anchor, jump+anchor). 5 seeds, G=20, λ=½. Arm A → 9.84σ²; Arms B,C → 1.01σ², flat. (items 2 & 3) | **fig1** | ~59 min |
| 4 | `analyze_head_to_head.py` | `head_to_head_figure.json` (stdout) | Mean±std trajectories + the deterministic recursion fixed point v*_det for overlay. | (fig1) | seconds |
| 5 | `inject_ablation.py` | `inject_ablation.jsonl` (6) | **Break-test / two-horned trap.** Fixed t₀=1e-4, no anchor, reverse-SDE noise ON vs ZEROED. ON → 10.8–13.2σ² (fat); OFF → 0. (challenge #12) | **fig2** | ~22 min |
| 6 | `verify_nonoise.py` | stdout | Confirms the noise-OFF collapse is a **single point** (2D std→4e-4, NaN-free), not an artifact. | (fig2) | ~1 min |
| 7 | `det_fp_diagnose.py` | stdout | The honest gap: Φ_det recursion fixed point = 4.54σ² at the method's real t₀; measured stochastic recursion ≈11σ² is 2.4× above → Φ_det is an exact single-pass floor and a **lower bound** on the recursion. (Half of the 2.4× is now accounted for — see row 17.) | — | ~2 min |
| 8 | `pixel_mnist_recursion.py` | `pixel_mnist_recursion.jsonl` (8) | **Real-data step.** 8×8 pixel MNIST, G=8, 3 seeds. Unfixed → off-manifold 3.06; anchored → 1.66 (true baseline 1.34). Needs `mnist8x8.npz`. (item 4) | **fig3** | ~30 min |
| 9 | `poolwidth_probe.py` | `poolwidth_probe.jsonl` (6) | **Small-c resolved.** Net c≈{0,.05,.13,.10,.05} = deficit response −0.68 + injection response +0.73 (near-cancellation). (item 5) | — | ~5 min |
| 10 | `jump_dscaling.py` | `jump_dscaling.jsonl` (12) | Supporting: raw floor blows up ~linearly in ambient d; matched floor **saturates** (~d^0.1); no compounding to d=128. | — | ~20 min |
| 11 | `test_axmatch.py` | stdout | Unit test of the pixel-space local matcher (no crash when pool>ref; off-manifold 3.02→1.55). | — | ~1 min |
| 12 | `make_figures.py` (+ `figstyle.py`, `make_paper_diagrams.py`, `make_cifar_fig.py`) | `paper/figs/fig0–6.{pdf,png}` | Regenerates all seven paper figures (vector PDF + PNG twins) from the jsonl above, one shared publication style. fig4 now includes the interventional test (row 25): five protocol points, floor tracks the law, never below the bound. | all | seconds |
| 13 | `falsify_floor.py` | stdout (14 checks) | **Adversarial verification of Theorem 2.** Independent RK45 integration vs both closed forms; sympy symbolic re-derivation of the band crossing; limits ρ→0, ρ→1⁻, κ̄→∞, λ→1; boundary-layer contraction at the predicted quadratic rate; 200-profile Monte Carlo attack on the comparison bound (incl. overshoot). 14/14 pass. | — | ~1 min |
| 14 | `cifar_recursion.py` | `cifar_state/*.npz` (not committed, large), `cifar_run_offman.log` | **Scale check (preliminary).** Same recursion at D=3,072 (CIFAR-10 pixels), small conv UNet (~7M params, GPU/AMP), G=8, λ=½, 3 seeds. Unanchored settles at 22.8±1.2σ (true baseline 20.1); anchored holds 16.3±0.7, gap +6.5±1.1 in every seed. Needs a CUDA GPU in practice (~4.75 h/seed on an RTX 3050); downloads CIFAR-10 from HF parquet on first run (script prints the fetch command). | **fig6_cifar** | ~4.75 h/seed |
| 15 | `cifar_diversity_check.py <seed>` | stdout | **Adversarial check on 14: is the anchored arm's lower off-manifold distance real quality or mode collapse the distance metric can't see?** Three NN metrics vs a real-vs-real baseline: precision (0.80×), **coverage (1.00×, rules out mode collapse)**, diversity (0.75×, bounded/non-compounding — identical at g4 and g7). Unanchored: precision 1.11×, coverage 1.16× (real modes go uncovered), diversity 1.20×. Read-only, CPU, <1 min per seed. | (fig6_cifar) | ~1 min |
| 16 | `analyze_seeds.py` | stdout | Cross-seed trend analysis: unanchored slope +0.238±0.259/gen (noisy, not monotone — seed 2 is flat, so this is a stable degraded fixed point at λ=½, not runaway collapse); anchored slope −0.073±0.141/gen (flat). Full numbers in `CIFAR_3SEED_RESULTS.txt`. | — | seconds |
| 17 | `gap_closure.py` | stdout | **The 2.4× gap, a-quarter-to-half closed.** The width probe's own per-width slope fits give an *empirical* capacity-degradation fit κ̄(w) ≈ 4.4 − 11.6·√w (seed-501 nets; seeds 500/777 give 4.06 − 9.7·√w and 4.68 − 13.0·√w — rows 19–20 measure the scatter and replication). Feeding it back self-consistently, v ← Φ_det(w(v), κ̄(w(v))), moves the deterministic fixed point 4.54σ² → 5.57–7.13σ² across the three seeds' fits at t₀=1e-4, and the resulting √w\* = 0.091–0.101 sits **inside** the measured support [0.03, 0.13] (interpolation, not extrapolation). Shrinks the unexplained factor 2.4 → 1.5–2.0 (a quarter to a half of the log gap); for the rest see row 20 (what it is *not*). Pure numerics on logged data. | — | ~2 min |
| 18 | `gap_b_decompose.py` | stdout | **Three-channel anatomy of c.** Splits dΦ_det(w, κ̄(w))/dw into deficit (∂/∂w at fixed κ̄ ≈ −0.94 mid-range) + capacity degradation ((∂Φ/∂κ̄)·κ̄′(w) ≈ +0.7) + residual injection (≈ +0.3 to +0.4). Injection is *defined* as measured-minus-derived, so the three channels sum to the measurement by construction; the non-trivial content is that the residual comes out stable, positive, and of the size the residual-channel model expects — and that most of what row 9 attributes to "injection" is really κ̄ degrading on fatter pools. Trust mid-range only: κ̄′(w) diverges at the thinnest width (a fit artifact of the √w parametrization). | — | ~3 min |
| 19 | `gap_review_checks.py`, `gap_review_torch.py` | stdout | **Adversarial review battery on rows 17–18** (same spirit as row 13). R1 functional form: refitting κ̄(w) linear/log/quadratic or replacing it with a fit-free monotone interpolation moves v\* by ≤10% (PCHIP lands on the identical 6.11σ²) — the √w is cosmetic, the closure only interpolates. R2 honest closure arithmetic (the source of row 17's closure fractions). R3 the capacity-degradation channel recomputed from raw centered differences, no functional form: +0.78/+0.68/+0.67 vs fit +0.84/+0.70/+0.65 at the interior widths. R4 κ̄ seed scatter: level shifts ~0.3 between seeds (→ v\* 6.11–7.13σ²), slope consistent. R5 **mixture test**: the recursion pool is a mixture, not a single tube — training on the fixed point's own composition (half σ=0.05, half σ=0.124) gives κ̄ = 3.37 ± 0.15 vs single-tube prediction 3.34; the width-only reduction survives its sharpest objection. | — | ~10 min |
| 20 | `gap_protocol_robustness.py`, `gap_residual_attack.py` | stdout | **Replication + residual forensics.** Replication: the κ̄ degradation replicates under a half-width network (law 4.25 − 9.4·√w), a different ring radius R=3.5 (4.29 − 11.2·√w), and a third seed (4.68 − 13.0·√w) — the *phenomenon* is protocol-robust (slope −9.4 to −13.0, κ̄ falls ≈3.9–4.3 → ≈2.9–3.0 everywhere); the *constants* are protocol-specific. Residual forensics — what the remaining 1.5–2.0× is **not**: (a) Jensen/fluctuation bias of iterating a noisy map, computed from the logged fixed-t₀ plateau variance: 0.006σ², negligible; (b) the measured t≥0.1 slope-tracking ratio 0.95–0.97 applied to the whole profile: moves v\* by only +0.3–0.4σ². Leading remaining suspect: the profile shape inside the deficit band, where tracking is unmeasured. | — | ~3 min |
| 21 | `replay_baseline.py` | `replay_baseline.jsonl` (5) | **Replay-vs-anchor control (the missing baseline).** The anchor's own m=2000 stale reference inserted INTO the pool every generation (λ_eff = 2/3, synthetic a 1/3 *minority*) — identical information budget to the anchor, head-to-head protocol otherwise. Plateau g19 = 8.5±1.1σ² vs 9.84±1.7 without replay and 1.01±0.02 anchored: replay *dilutes* the floor (the small λ-dilution the law predicts); anchoring *removes* it. | — | ~28 min |
| 22 | `subcritical_lambda.py` | `subcritical_lambda.jsonl` (6) | **The critical fraction, located and exhibited.** λ\* = c∞/(1+c∞) ≈ 0.03–0.05 from the probe's saturated slope. λ=0.02 (at/below λ\*, fixed t₀=1e-4, G=25): v climbs monotonically to 69±16σ² at g24 (~10× its early value), no plateau in horizon. λ=0.25 control: plateau 16.5±2.2σ² by g≈5. Implied per-pass excess e²(w\*) = λ(v∞−σ²) = 3.9–5.0σ² across λ ∈ {0.25, 0.5, 2/3} — the law's e²/λ scaling across a 2.7× range of effective fraction. | — | ~38 min |
| 23 | `residual_anatomy.py` | `residual_anatomy.jsonl` (13) | **The 1.5–2.0× residual, measured to death.** Per width (6 widths spanning the fixed point × 2 net seeds): v_env (envelope, the closure's model) → +C1 profile sag (κ̂(t) sags 0.3–0.7 below its own ceiling inside the band; +0.7σ² at data width, flips to mild overshoot at √w≥0.10) → +C2 **ensemble displacement** (slope regressed on the sampler's own fatter-than-p_t ensemble at every step; +2.6→+3.6σ², the DOMINANT channel) → v_full measured, with the nonlinear remainder C3 = −0.4 to −1.0σ² (small: affine-along-path is complete once the ensemble slope is used). **Iterating the measured map: fixed point 9.9σ² vs measured 10.8–13.2σ² — the 2.4× gap is now 1.1–1.3×**, protocol-level. Also corrects the old "zero-fit match": the direct single-pass floor is 6.3–7.5σ², of which the envelope explains ~60% (see row 2). | — | ~6 min |
| 24 | `capacity_domains.py` | `capacity_domains.jsonl` | **κ̄(w) degradation is not a ring artifact.** Same protocol, three new geometries: flat segment (the flat-tube idealization made exact) 6.12−23.1√w (42% drop — needs NO curvature); sphere in R³ 4.65−12.8√w (30%); circle in R¹⁰, codim 9, 6.81−29.7√w (49%). Constants geometry-specific, phenomenon universal. Kills the "single data-domain" limitation. | — | ~4 min |
| 25 | `ceiling_origin.py` | `ceiling_origin.jsonl` (5) | **What sets κ̄ — and the interventional test of the floor law.** Five training arms: baseline κ̄=3.7; t-importance-sampling into the band κ̄=6.7; 4× steps κ̄=6.4; higher-freq time embedding κ̄=3.5 (**does nothing** — not expressivity); both κ̄=7.5. The band holds <1% of the uniform t-measure (t<1e-3 never sampled) → the ceiling is **gradient starvation**, an optimization constant. Measured floors fall from ~7.6σ² (two low-κ̄ protocols) into the 2.5–4.9σ² range (three high-κ̄ ones) — a group-level fall with protocol scatter, not a clean 1/κ̄² trace — every one **staying strictly above its proven bound** — the law survives intervention. Band-weighted t-sampling is a practical 2–3× mitigation; it cannot reach σ² and the recursion still compounds, so anchoring stays necessary. | — | ~2 min |

### Regenerate the figures
```
python make_figures.py         # figs 1–4: reads head_to_head.jsonl, inject_ablation.jsonl,
                               # pixel_mnist_recursion.jsonl, ceiling_origin.jsonl
python make_paper_diagrams.py  # fig 0 (mechanism + closed-form floor), fig 5 (pipeline)
python make_cifar_fig.py       # fig 6 (CIFAR-10 recursion + coverage/diversity)
```
Each writes vector PDF + PNG twins to `paper/figs/` (shared style in `figstyle.py`).
All inputs are already present, so this runs in seconds without redoing any training.

---

## Headline numbers (check a correct reproduction against these)

σ² = 0.0025 throughout (σ = 0.05).

- **Head-to-head (fig1):** Arm A g19 = 0.0246 ≈ 9.84σ²; Arms B,C = 0.00252 ≈ 1.01σ², flat 20 gens.
- **Two-horned trap (fig2):** stochastic ≈ 0.027–0.033 (≈11σ²); deterministic → 0 (point collapse).
- **Pixel MNIST (fig3):** unfixed g7 = 3.06; anchored g7 = 1.66; true-data baseline = 1.34.
- **Capacity floor (fig4):** finite-σ Φ_det·κ̄² = 0.141 ± 0.003 (σ=0.05); exact σ→0 constants: (1+3e⁻⁴)/8 = 0.1319 (no-overshoot), 1/8 (unconditional); measured κ̄=3.9 → envelope floor 3.8σ², a proven lower bound = ~60% of the directly measured 6.3–7.5σ² floor; remainder measured as profile sag + ensemble displacement (row 23); law confirmed interventionally across κ̄ 3.5→7.5 (row 25).
- **Honest gap, now closed to protocol level:** recursion Φ_det fixed point 4.54σ² vs measured ≈11σ² → factor 2.4. Self-consistent iteration with the empirical capacity fit κ̄(w) ≈ 4.4 − 11.6·√w gives v\* = 5.57–7.13σ² (a quarter to a half in log); the remainder is now MEASURED (row 23): profile sag + ensemble displacement lift the per-pass map to its directly measured values, and iterating the measured map gives 9.9σ² vs measured 10.8–13.2σ² → residual 1.1–1.3×, protocol-level. Degradation replicates at h=128, R=3.5, and across flat/sphere/high-codim geometries (row 24). Underived: the constants (κ̄ = gradient starvation per row 25, its degradation law, the saturation profile).
- **Three-channel c:** deficit ≈ −0.94 + capacity degradation ≈ +0.7 (form-free check: +0.78/+0.68/+0.67) leaves residual injection ≈ +0.3–0.4, stable and positive (residual is defined as measured-minus-derived — a plausibility check, not an independent validation).
- **CIFAR-10 pixels, D=3,072 (fig6_cifar, preliminary, 3 seeds):** the two arms stabilize on *opposite sides* of the true baseline 20.1 — unanchored 22.8±1.2 (+2.7, fattening), anchored 16.3±0.7 (−3.8, mild contraction), split sign consistent in every seed. The deviations are of comparable size, so the distance metric alone ranks neither arm; the ranking evidence is coverage: anchored 1.00× (no real modes dropped — no mode collapse) vs unanchored 1.16× (real modes go uncovered), with the anchor's diversity 0.75× a bounded, non-compounding cost. Samples are blurry at this model budget — this is a dynamics/coverage check, not a perceptual-quality claim (see `CIFAR_3SEED_RESULTS.txt`).

---

## Supporting / earlier-phase evidence (not included in this repo)

Theorem II′ (the collapse law) and the fix were first established in an earlier,
2026-07-02 solution phase, ahead of the polished pipeline above. Those scripts
(`solution_law_test.py`, `solution_validation.py`, `scale_experiment.py`,
`scale_variants.py`, `jump_solution_test.py`, `grand_harness.py`,
`manifold_fix_test.py`/`_test2.py`) underpin the results narratively but are superseded by
the core pipeline's cleaner re-derivation and are **not part of this repository** — they
live only in the author's private research directory. `SOLUTION_NOTE.md` and
`THEORY_NOTE.md` (included here) narrate that phase and carry in-place correction banners
where later results superseded earlier claims; the corrected, citable statements are in
`PROOFS.md`.

**Doc hygiene (challenge #11) — DONE 2026-07-04:** the superseded "jump breaks the floor" /
"jump sits 6× below Φ(0+)" lines in `SOLUTION_NOTE.md §4c` and `THEORY_NOTE.md` now carry
in-place **[CORRECTION 2026-07-04]** banners (the *matcher* is the floor-breaker; the jump
is a raw-error reducer). Safe to quote those files — the banners travel with the prose.
Corrected statements live in `PROOFS.md` Theorems I(b)/III(b).

---

## Not load-bearing for this paper

Left in the directory but **not part of the manifold-collapse result** — exploratory
probes, other topics, or superseded lines. Ignore for reproduction:

- `probe_ragas_*.py`, `probe_gsm8k_extract.py` — LLM-faithfulness probes (different topic).
- `minority_extinction_law.py`, `real_model_minority.py`, `gmm_crossover.py`, `crossover.py`,
  `collapse_gaussian_repro.py`, `collapse_vae_*.py`, `collapse_phase_*.py`,
  `collapse_break_accumulate.py`, `complexity_bias.py`, `entropy_headtohead.py` — earlier
  angles / non-manifold collapse explorations.
- `heavytail_a4_probe.py`, `tail_vs_poison_*.py`, `annealed_fix_heavytail.py` — the
  heavy-tail critique line (superseded: the A4-vs-Fisher distinction resolved it; see the
  `cambridge-spectral-collapse` note).
- `diffusion_collapse_fulltest.py` (+ `analyze_fulltest.py`), `problem_verify_*.py`,
  `loop_verifier_center.py` — scaffolding / one-off verifications.

---

## Data artifacts

- `mnist8x8.npz` — 8×8 pixel MNIST cache (train/test, [-1,1]) for `pixel_mnist_recursion.py`.
- `mnist_latents32.npz` — 32-d PCA latents (used by earlier scale experiments).
- `rprime_probe_net25.pt`, `rprime_probe_net.pt` — trained score nets from the κ̄ probe.
- `cifar32.npz` (737 MB, **not committed**) and `cifar_state/*.npz` (73 MB × 5, **not
  committed**) — `cifar_recursion.py` fetches/builds and caches these on first run;
  `cifar_run_offman.log` (committed) has the full per-generation trajectory, and
  `CIFAR_3SEED_RESULTS.txt` has the final numbers if you just want to check without
  re-running.
