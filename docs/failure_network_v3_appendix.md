# Cross-disease meta-validation — the framework applied to the framework

This document describes a second, parallel analysis strand that applies the
same falsification posture as Theory Copilot's discovery loop — but at a
different level. Instead of asking *"does this molecular law survive contact
with biology?"* it asks: *"does the audit framework itself survive validation
against clinical trial outcomes?"*

The two systems are distinct. Theory Copilot is a discovery loop for compact
biological laws (Proposer → PySR → 5-test gate → Skeptic → Interpreter).
The v3 scope-of-evidence audit framework is a separate tool that classifies
drug-target coupling evidence across diseases and asks whether that
classification predicts clinical success or failure. They share an epistemic
posture — pre-registered criteria, honest reporting of nulls — but they are
not the same pipeline.

**Why include it here.** The answers to the v3 meta-validation are the same
kind of honest output that Theory Copilot's gate produces: the framework IS
non-trivially discriminative (null sampling, below); it does NOT predict trial
failure (GEE model, below); and the initial claim that it did (v3.2.1's 4.6×
enrichment) was a selection-bias artifact that the framework then self-corrected
via proper stratification. Rejection-as-product applied to the tool's own
claims.

---

## Three-disease scope: ccRCC + DIPG + IPF

The v3 audit framework was applied to three disease-specific clinical trial
target panels:

| Disease | Panel | Pairs classified |
|---|---|---|
| ccRCC (clear-cell renal cell carcinoma) | 51 drug-target pairs, literature-curated | 102 directional rows |
| DIPG (diffuse intrinsic pontine glioma) | 27 pairs | 54 rows |
| IPF (idiopathic pulmonary fibrosis) | 26 pairs | 52 rows |

Each pair is assigned one of 8 observable verdict classes (spanning 10 priority
branches in the v0.5 verdict function) based on the availability and strength
of functional evidence in LINCS L1000 CGS perturbation data, DepMap, and
cross-species ortholog mapping:

| Class | Meaning |
|---|---|
| `admitted_null_coupling` | Target perturbed; evidence is null or weakly negative |
| `protected_positive_prior` | Target perturbed; evidence is strongly positive |
| `raw_evidence_below_admission` | Evidence exists but doesn't clear the admission threshold |
| `untestable_no_kd` | No perturbation data for this target in this disease context |
| `untestable_secreted_drug_target` | Target is secreted; not amenable to expression-KD approach |
| `absent_from_v3` | Target not present in the data |
| `readout_only_by_design` | Target is a readout marker, not a perturbation target |
| `untestable_context_uninformative` | Perturbation data present but context too noisy to interpret |

**D1 verification (100% PASS).** Before any downstream analysis, the verdict
function was verified against hand-curated gold standards:
ccRCC 102/102 matches, DIPG 54/54, IPF 52/52 — all 100%.

---

## Finding 1 — The framework discriminates (null sampling, 16/42 BY-FDR)

**Setup.** 1,000 permutations × 3 diseases × 2 null tiers (Tier 1: pan-genome
random panels; Tier 2: class-matched random panels preserving target-class
composition) = 6,000 null panels total. Each null panel is processed through
the full v0.5 verdict function. Across 7 verdict classes × 6 arms = 42 tests,
corrected with BY-FDR (Benjamini-Yekutieli, dependency-aware — the correct
correction when verdict-space tests are not independent). `readout_only_by_design`
is excluded from the 42-test family: it is assigned by panel construction (a target
is a readout marker by design), so it has no informative null distribution under
gene permutation.

**Result: 16/42 tests significant at q < 0.10** (all 16 shown below).

| Verdict class | Arm | Designed | Null mean [range] | q (BY-FDR) |
|---|---|---|---|---|
| `admitted_null_coupling` | ccRCC Tier 1 | 37 | 3.1 [0, 8] | ≈ 0 |
| `admitted_null_coupling` | ccRCC Tier 2 | 37 | 5.0 [0, 11] | ≈ 0 |
| `admitted_null_coupling` | DIPG Tier 1 | 41 | 1.7 [0, 5] | ≈ 0 |
| `admitted_null_coupling` | DIPG Tier 2 | 41 | 2.5 [0, 6] | ≈ 0 |
| `admitted_null_coupling` | IPF Tier 1 | 21 | 1.6 [0, 5] | ≈ 0 |
| `admitted_null_coupling` | IPF Tier 2 | 21 | 1.9 [0, 6] | ≈ 0 |
| `protected_positive_prior` | ccRCC Tier 1 | 21 | 0.0 [0, 0] | ≈ 0 |
| `protected_positive_prior` | ccRCC Tier 2 | 21 | 0.0 [0, 0] | ≈ 0 |
| `protected_positive_prior` | DIPG Tier 1 | 6 | 0.0 [0, 0] | ≈ 0 |
| `protected_positive_prior` | DIPG Tier 2 | 6 | 0.0 [0, 0] | ≈ 0 |
| `protected_positive_prior` | IPF Tier 1 | 5 | 0.0 [0, 0] | ≈ 0 |
| `protected_positive_prior` | IPF Tier 2 | 5 | 0.0 [0, 0] | ≈ 0 |
| `raw_evidence_below_admission` | ccRCC Tier 1 | 16 | 3.0 [0, 8] | ≈ 0 |
| `raw_evidence_below_admission` | IPF Tier 1 | 8 | 1.6 [0, 5] | 0.068 |
| `untestable_context_uninformative` | DIPG Tier 1 | 1 | 0.0 [0, 0] | ≈ 0 |
| `untestable_context_uninformative` | DIPG Tier 2 | 1 | 0.0 [0, 0] | ≈ 0 |

**Interpretation.**

- `protected_positive_prior` enrichment is structural: curators include
  known-biology pairs, so designed panels test targets with strong positive
  evidence that random panels can't match by chance. This validates that the
  verdict function is operating correctly.
- `admitted_null_coupling` enrichment is the key signal: designed panels test
  targets whose biology v3 can evaluate as *null-coupled* at 10–24× higher
  rates than chance (DIPG reaches 41 designed vs 1.7–2.5 null mean ≈ 24×).
  This is the framework operating as intended — catching the systematic absence
  of coupling evidence in panels assembled by clinical judgment.

- `untestable_context_uninformative` in DIPG (Tier 1 and Tier 2, q ≈ 0 both): represents
  a single designed pair. The null distribution is identically zero across all 1,000
  random DIPG panels, so any designed occurrence achieves formal significance — but
  the finding is a single-case signal, not a pattern, and should be read accordingly.

See [`results/failure_network_appendix/figures/fig2_per_disease_verdict_stacked.svg`](../results/failure_network_appendix/figures/fig2_per_disease_verdict_stacked.svg)
for per-disease verdict distributions (designed vs null).

---

## Finding 2 — Sign-flip reveals case-mix heterogeneity (v3.4)

**Setup.** Clinical trial targets from failed trials (AACT Phase 3, 2010–2024)
were mapped to the v3 audit framework and compared against a matched approved
arm. The "failed" pool was split by failure mode:

| Arm | Definition | n genes | OR (vs approved) | Perm p (two-sided) |
|---|---|---|---|---|
| Track 1 | Terminated early for futility | 56 | **6.41** [5.54, 7.42] | 0.234 |
| Track 2 | Completed but missed primary endpoint | 153 | **0.13** [0.09, 0.19] | 0.154 |
| Combined (pooled) | All failed trials | 185 | 2.19 [1.90, 2.53] | 0.469 |

**Woolf OR homogeneity test (T1 vs T2):** Z = 19.97, p ≪ 1×10⁻⁸⁷.

Neither arm achieves individual significance in the gene-level permutation
null (T1 p = 0.234, T2 p = 0.154), which is the appropriate test controlling
for edge non-independence in knowledge graphs (per MAGMA 2015, Guney 2016
Nat Comm). That is not the key finding. The key finding is that Track 1 and
Track 2 show *opposite* directions — the Woolf homogeneity test decisively
rejects the assumption that both arms come from the same population. Pooling
them (the default in trial-graveyard analyses) produces a spurious moderate
enrichment (Combined OR = 2.19, p_perm = 0.469) when no coherent signal
exists across the pooled population.

**Why the initial 4.6× finding (v3.2.1) was wrong.** The original enrichment
was computed on Track 1 only (early-terminated trials). Further investigation
showed that 98% of the signal was driven by three transcription factors —
TP53, NFKB1, RELA — which are well-known "un-drugable" TFs concentrated in
the early-termination group. Track 2 shows depletion (OR = 0.13) for the same
targets, reflecting that trials that completed to an endpoint tested a
systematically different, less-studied target distribution.

**Methodological lesson.** Trial failure mode is the population stratifier.
Any trial-graveyard analysis that pools futility-terminated and
completed-missed-primary trials is mixing incomparable populations.

See [`results/failure_network_appendix/figures/fig1_track_signflip_forest.svg`](../results/failure_network_appendix/figures/fig1_track_signflip_forest.svg)
for the sign-flip forest plot.

---

## Finding 3 — Trial-level GEE NULL = honest scope (v3.5)

**Setup.** A generalized estimating equations (GEE) Binomial Exchangeable
model, clustered on indication_mesh (631 clusters, 9,943 trials), tested
whether v3 coupling score predicts trial success (FDA approval) vs failure,
after controlling for sponsor class and trial year quartile.

Approved arm: 8,253 Phase 3 COMPLETED ≥2010 trials linked to FDA-approved
drugs via OpenTargets `drug_indication.references[source==ClinicalTrials]`
(81% of 9,678 OpenTargets drugs have ClinicalTrials.gov NCT IDs; this is the
cleanest chembl\_id→AACT linkage without a DrugCentral intermediate).

Five coupling encodings were tested with Bonferroni × 5 correction:

| Encoding | OR / 0.1-unit | 95% CI | p\_raw | p\_Bonf | Significant |
|---|---|---|---|---|---|
| mean\_protected\_positive\_prior\_rate | 1.26 | [0.06, 25.7] | 0.879 | 1.00 | no |
| max\_protected\_positive\_prior\_rate | 1.69 | [0.26, 10.9] | 0.579 | 1.00 | no |
| mean\_admitted\_null\_rate | 1.00 | [1.00, 1.00] | NaN | 1.00 | no |
| max\_admitted\_null\_rate | 1.00 | [1.00, 1.00] | NaN | 1.00 | no |
| mean\_null\_fraction\_avg | 2.75 | [0.85, 8.92] | 0.092 | 0.461 | no |

**No encoding survives Bonferroni × 5.**

The best signal (`mean_null_fraction_avg`, OR = 2.75, p = 0.092) is
directionally consistent with Track 1's enrichment, but does not survive
multiple-testing correction across the 5-encoding family. The GEE result
is convergent with v3.4's combined-arm permutation null (OR = 2.19, p_perm
= 0.469) — both independently confirm that no robust association exists
between v3 coupling and trial outcome at the trial level.

See [`results/failure_network_appendix/figures/fig3_permutation_null_overlay.svg`](../results/failure_network_appendix/figures/fig3_permutation_null_overlay.svg)
for the permutation null overlay.

---

## What this means for the framework

| Question | Answer |
|---|---|
| Does v3 discriminate curated panels from random? | **YES** — 16/42 tests BY-FDR significant at q < 0.10 |
| Does v3 coupling predict trial failure? | **NO** — trial-level GEE NULL after Bonferroni × 5 |
| Is there case-mix heterogeneity between failure modes? | **YES** — Woolf Z = 19.97, p ≪ 10⁻⁸⁷ |
| Was the initial 4.6× claim (v3.2.1) a real predictor? | **NO** — Track-1 selection-bias artifact |
| What is v3 useful for? | **Scope-of-evidence audit**: catches `untestable_no_kd`, `untestable_secreted_drug_target`, `absent_from_v3` systematically across diseases |

**The scope-of-evidence auditor framing** is the honest answer. v3 reliably
classifies what is testable vs. untestable, and what evidence exists or
doesn't, in a way that random panels cannot replicate. What it cannot do is
use that classification to predict whether a given trial will succeed or fail.
The prediction claim requires stratification by failure mode (and even then
the signal is concentrated in a small TF-class subset). This is the system
accurately reporting its own limits.

---

## Honest scope statement

This analysis is research-level and pre-publication. It does not constitute a
clinical or regulatory decision tool. The verdict classifications depend on the
LINCS L1000 CGS experimental coverage, which is incomplete for secreted
targets, GPCRs, and post-translational regulators — three drug classes that
are systematically `untestable` under the current v3 framework and should not
be interpreted as "lacking evidence" in a clinical sense.

The GEE result is an honest null, not a failure. The same pre-registered
falsification posture that makes Theory Copilot's discovery loop credible
makes this meta-validation credible: the null is informative precisely because
it was sought under conditions designed to find a signal if one existed.

---

## Navigation

- Figures: [`results/failure_network_appendix/figures/`](../results/failure_network_appendix/figures/)
- Primary submission narrative: [`docs/methodology.md`](methodology.md),
  [`results/external_validation_dipg/RESULTS.md`](../results/external_validation_dipg/RESULTS.md),
  [`results/external_validation_ipf/RESULTS.md`](../results/external_validation_ipf/RESULTS.md)
- Cross-disease scope gaps: `untestable_no_kd`, `untestable_secreted_drug_target`,
  and `absent_from_v3` are the systematic scope-gap classes the v3 framework
  identifies across ccRCC, DIPG, and IPF. `admitted_null_coupling` is a positive
  evidence verdict (target was perturbed and coupling evidence is null or weakly
  negative) — not a scope gap. The distinction matters: scope-gap targets are
  untestable by design; admitted-null targets were tested and found non-coupled.
