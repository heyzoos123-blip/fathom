> **correction notice, 2026-11-09.** this file is kept as it was written. the lab later withdrew or bounded statements in it. the text below is unchanged; these are the receipts:
> - "First per-layer fault localization for hallucinations ever published" (line 96 as of this notice; the file's words); also "First decoding intervention based on computational geometry" (line 57; the file's words) and "First generation strategy optimizing for computational geometry" (line 104; the file's words) — 2026-09-29: the lab's rule keeps a priority sentence only if a survey under a frozen procedure priced it, and withdraws it otherwise; the lab reads these sentences as withdrawn — https://github.com/fathom-lab/styxx/blob/main/papers/NOTE_prior_art_credit_2026_09_29.md
> - "AUC=0.685 (BEST single metric)" (line 14 as of this notice; the same auc at line 61) — 2026-11-09: the file labels 0.685 as the n=200 validation figure (line 61, "unpaired") and reports gini alone at auc 0.579 in its 5-fold cv table (line 46, n=200; table header line 40); the 0.685 carries no cross-validation label — receipt: this file
> a dated banner, not an edit in place, is the lab's practice since 2026-06-21. the lab's current record is https://github.com/fathom-lab/styxx .

# Findings: Layer Coherence Spectrum (April 7, 2026)

## Discovery
The SHAPE of per-layer coherence distributions discriminates hallucination
better than any scalar summary (K, C, C_delta). Hallucination is not a
depth shift — it is a coherence CONCENTRATION.

## Key Result (n=200, Gemma-2-2B, TruthfulQA)
- **Gini coefficient:** d=+0.36, p=7.6e-7, AUC=0.685 (BEST single metric)
- **Spectral entropy:** d=-0.34, p=3.5e-6, AUC=0.675
- **Peak value:** d=+0.34, p=2.5e-6, AUC=0.665
- **Spectral spread:** d=-0.32, p=1.2e-5, AUC=0.645
- **C_delta (scalar):** d=+0.31, p=2.3e-5, AUC=0.640
- **K (depth):** d=+0.11, p=0.14, AUC=0.550 (NOT SIGNIFICANT)

13/16 spectrum metrics significant after Holm-Bonferroni correction.

## Per-Layer Anatomy
- **Layer 11:** p=2.7e-12, t=7.45 — the epicenter of concentration
- **16/26 layers** show p<0.001 difference
- **23/26 layers** show p<0.05 difference
- **Layers 0-1:** NOT significant (common foundation)
- **Layers 4-25:** ALL significant, hallucinated > correct
- Pattern: hallucinations pump coherence into layer 11-13 spike and
  elevate all late layers, while depleting early-layer computation

## Mechanism
Hallucination = coherence inequality. The model's computation narrows
onto a dominant attractor in mid-layers (11-13) while starving early
layers of coherent feature activation. Correct responses distribute
coherence more uniformly. The scalar mean (centroid/K) can't distinguish
these configurations because the means are nearly identical (13.91 vs
13.90) — the SHAPE carries the signal the mean destroys.

## Classifier Results (5-fold CV, n=200)
| Classifier | AUC |
|---|---|
| K alone | 0.520 |
| C_delta alone | 0.565 |
| K + C_delta | 0.555 |
| Gini alone | 0.579 |
| Top-3 spectrum | 0.572 |
| Top-5 spectrum | 0.577 |

## Spectrum-Guided Generation (Frontier 2)
Built `spectrum_steerer.py`:
- Monitors full 26-layer coherence profile at each token
- Computes Gini in real-time (encoder-only, no attribution)
- Triggers multi-layer intervention when concentration detected
- Subtracts lock-in direction at each spike layer
- Adaptive strength scales with Gini excess above threshold
- First decoding intervention based on computational geometry

## Validation Chain
1. n=50 pilot: 7/15 significant, Gini AUC=0.80 (paired)
2. n=200 validation: 13/16 significant, Gini AUC=0.685 (unpaired)
3. Per-layer tests: 19/26 at p<0.001
4. Consistent with C_delta "wrong attractor" finding (Section 4)
5. Consistent with S_early biphasic finding (tokens 0-7 commitment)

## Connection to Prior Work
- S_early measures commitment INTENSITY (IPR of spike distribution)
- Gini measures coherence CONCENTRATION (inequality across layers)
- Both capture aspects of the same phenomenon: hallucination as
  pathological narrowing of computation
- S_early is temporal (across tokens). Gini is spatial (across layers).
- Together they form a 2D lock-in signature: WHERE computation
  concentrates (Gini) and WHEN it commits (S_early)

## Artifacts
- `analysis/analyze_layer_spectrum.py` — n=50 analysis
- `analysis/analyze_spectrum_full.py` — n=200 validation
- `spectrum_steerer.py` — Frontier 2 generation engine
- `truthfulqa_results/layer_spectrum_analysis.json`
- `truthfulqa_results/spectrum_full_analysis.json`
- `figures/spectrum_n200_full.{pdf,png}`
- `figures/spectrum_auc_leaderboard.{pdf,png}`
- `figures/spectrum_layer_significance.{pdf,png}`
- `figures/layer_spectrum_overview.{pdf,png}` (n=50)
- `figures/layer_spectrum_metrics.{pdf,png}`
- `figures/layer_spectrum_examples.{pdf,png}`
- `paper/fathom_icml2026_v2.tex` — Section 5.9 updated

## Cognitive Autopsy (NEW)
- **Layer 11:** Primary fault in 63% of hallucinations (n=200)
- **Layer 12:** Primary fault in 58%
- **Layers 11+12:** 41% of all excess coherence
- **Layer 15:** Secondary fault zone (27%)
- Mean Gini delta (halluc - correct) = +0.0106
- Mid-layer concentration captures 66% of fault mass
- First per-layer fault localization for hallucinations ever published
- Figure: cognitive_autopsy_overlay.{pdf,png}

## Best-of-N Spectrum Sampler
- 100% improvement rate on test prompts (3/3)
- Mean Gini reduction: 0.022
- Mean CHS improvement: +0.107
- Great Wall: greedy gini=0.425 -> best-of-5 gini=0.384 (-0.041)
- First generation strategy optimizing for computational geometry

## Intervention Attempts (Honest Record)

### Per-token spectrum steering (spectrum_steerer.py)
- Monitors Gini per token, steers at spike layers
- Changes tokens at intervention point (e.g. "Water" -> "The")
- Over-steering at low threshold causes degeneration
- Status: PROOF OF CONCEPT — triggers work, calibration needed

### Best-of-N spectrum sampler (spectrum_sampler.py)
- Generates N candidates, scores by Cognitive Health Score
- 100% improvement rate on 3 test prompts (Gini reduced 0.022)
- Status: WORKING — practical intervention, no degeneration risk

### Transcoder weight surgery v1 (surgical_fix.py)
- Fine-tuned W_enc at layers 11-12, Gini reduced 0.05 on training set
- 0 answers changed on held-out data (greedy decoding unchanged)
- Status: FAILED TO TRANSFER — gradient flows but change too small

### RepEng direction subtraction v2 (surgical_fix_v2.py)
- Extracted hallucination direction at layer 11 (mean incorrect - mean correct)
- Alpha sweep 0.5-4.0: direction captures style not factual correctness
- Alpha=4.0: 30/30 answers changed but net -4 (5 degraded, 1 improved)
- Alpha=0.5-2.0: 1-3 answers changed, 0 improved
- Status: FAILED — single direction too blunt for hallucination

### Multi-layer coordinated suppression (April 9, 2026)
- 22 layers (4-25), top 10 halluc features per layer, 220 total
- **33% first-token changes on held-out data** (10/30)
- Mean KL = 0.587 (73x larger than single-layer KL=0.008)
- "Yes"->"No" answer flips observed (items 13, 17)
- Direction: 1 improved, 1 degraded, 8 unclear
- Status: FIRST ARGMAX-CROSSING INTERVENTION — but not directional

### Feature decoding
- Top hallucination features decode to structural tokens (BOS, code, templates)
- They are ROUTING features, not semantic content
- Validates: hallucination is a computation pattern, not a factual error at feature level

### What works vs what doesn't
- DETECTION works: Gini, autopsy, EKG, best-of-N
- MULTI-LAYER SUPPRESSION crosses argmax (33%) but isn't directional
- The features encode HOW the model computes, not WHAT it knows
- Next: need features that encode factual correctness, or use logit-level
  training signal (DPO/RLHF with spectrum-derived reward)

## IP Note
Spectrum analysis and Gini-based steering covered under existing
provisional patents (64/020,489, 64/021,113). Zenodo timestamp needed
for spectrum-specific claims. Consider Zenodo v8 with spectrum findings.
