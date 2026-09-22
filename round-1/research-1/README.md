# What rival safety-scoring methods already achieve

`demo/` — Self-contained demo (Colab-ready notebook or markdown). Run without setup.  
`src/` — Full source code, data, and outputs from the experiment execution.

**Type:** research  
**ID:** `art_DeogIL_xh3pE`

## Layman Summary

Reads the published methods that already score a model's safety from the inside, works out exactly what each measures and how well, and checks which of our five planned ideas are still unclaimed.

## Full Summary

IMPLEMENTATION-GRADE SPECS FOR FOUR INCUMBENTS, FIVE DATED CANDIDATE VERDICTS, AND FIVE VERIFIED NUMBERS. Machine-readable output: spec_table.json (full) and the fenced json block in research_out.json (compact); prose twin research_report.md (~76KB).

FOUR INCUMBENTS (the plan named three; the fourth was found by the saturation search).
- AMS 2608.05578 = IEEE Access 14:91723-91737, verdict REPRODUCIBLE, with Apache-2.0 code (pip install "ams-scanner[cli]"; ams scan <model>). Statistic: sigma = (mu+ - mu-)/sigma_pooled on FINAL-TOKEN residual streams along an in-sample difference-of-centroids direction; 16 contrastive pairs x 3 concepts = 96 forward passes, 10-40s/model; layer swept over range(int(0.4L), int(0.8L)) and picked to MAXIMISE separation on the same pairs; PASS>3.5, CRITICAL<2.0. Tier 1 parent-free, Tier 2 needs a stored baseline. DECISIVE: the 71% (10/14) leave-one-out held out ONLY THE THRESHOLD - direction, layer sweep and prompt set were never held out, and the authors concede the coupling. So 71% is a LOOSE, NON-MATCHED bar; a leave-one-LINEAGE-out number from us is strictly stricter. Also: r=-0.546 (p=.043, n=14 models) but Spearman rho=-0.423 (p=.13, N.S.); median bootstrap 95% CI width 3.36 sigma against a 2.0-3.5 band (62% of cells unresolvable). Class (iv) behavioural fine-tuning is ALREADY PUBLISHED as undetectable - cite, do not claim.
- Skin-Deep/GFS 2606.22676: TWO PLAN ASSUMPTIONS OVERTURNED. It is NOT parent-free (Eq 1 cPCA needs the base model's covariance; code requires --base_model) and needs 1000 prompts; and its retention-prediction claim has NO PRINTED COEFFICIENT - a qualitative co-occurrence at n=7. There is no GFS number to beat.
- N-GLARE 2511.14195 / ACL 2026 Long 1334: CLASSIFY-BY-FUNCTIONAL-FORM-ONLY. Eq 7 and Eq 9 confirmed verbatim; parent-free AND generation-free, but needs FOUR probing conditions {B,J,R,P} over 7000+ cases, so it is separated from our lane on the PROMPT-BUDGET AXIS ALONE. No numeric Kendall tau for the headline claim in either version; Table 2's numeric taus belong to a DIFFERENT robustness check - quoting them would be a misattribution.
- RAS/SafeVec 2606.25750 (NEW, not in the plan): the closest published thing to the deliverable - white-box, generation-free, per-checkpoint, calibrated 0-100, separates aligned/uncensored/abliterated, tracks ASR, 210-217x faster than judge-based. BUT it needs a per-family reference model, a calibration set, AND those models' MEASURED ASR, and states "family-specific calibration remains necessary". Our cross-family negative would be a REPLICATION.
All four bar rows are comparable:false, each for a DIFFERENT nameable reason - that is the finding, and the reasons are now written down.

CANDIDATES (searched 2026-09-20, plus an adversarial kill-attempt pass): C1 PARTIAL (must beat HRCI_repr; pre-register as DISCRIMINATOR ONLY), C2 PARTIAL (IRT owns the behavioural half; 2608.13329 owns the internal variance decomposition and reports a generalizability coefficient of 0.00002 for cross-family comparison on one prompt wrapper), C3 OPEN as an aggregation only (recipe confound from 2609.03887), C4 OPEN on WEIGHTS-ONLY and PARENT-FREE and GRADED and PREDICTS-COMPLIANCE (the highest-value verdict), C5 OPEN on the ABLATION only. ADVERSARIAL PASS (27 refutation queries): all three OPEN verdicts SURVIVED but two were narrowed - C3's two required curves already coexist in 2507.11878 on the same models, so C3's novelty is ONLY the collapse-subtract-correlate aggregation; and C5's ablation is ESTABLISHED PRIOR ART as a method (2606.02907 residualizes source identity and drives a 100%-accurate hidden-state probe to chance; Hewitt & Liang control tasks), so C5 must be claimed as 'we ran the established control on the per-MODEL axis' not 'we invented the control'. C4 held, with three further near-misses named and excluded; cite the abliteration.org wiki to concede that the cell is a known practitioner open problem. C5's attack was only 6 queries and is the least well-tested verdict.

NUMBERS: N1/N2/N3/N5 CONFIRMED, N4 AMBIGUOUS-MULTIPLE-OCCURRENCES with BOTH readings of BOTH numbers genuinely true - NO misattribution exists, the premise stands. N1 forces the motivating sentence to be rescoped to per-PROMPT vs per-CHECKPOINT.

12 DECISIONS (D1-D12) each name the artifact and the action. Handoff blocks are written for the screen, ladder and payoff executors separately, with exact commands and six standing prohibitions.

GOTCHAS FOR REUSE: scholarly-mode search (OpenAlex/Crossref) is UNUSABLE for this field - an empty result is evidence about the backend, not the field. PDF-to-text inserts hard line breaks mid-sentence, so exact-phrase greps manufacture FALSE NEGATIVES; use whitespace-flexible patterns before recording NOT-FOUND. Near-ID collision 2606.22676 (Skin-Deep) vs 2606.22686 (Geometry of Refusal, TrustNLP). Title collision: Google lists AMS under a different title.

## Output Files

- `research_out.json`

## Demo Files

- **research_report.md** — Research report markdown (auto-generated from artifact)

---
*Generated by AI Inventor Pipeline*
