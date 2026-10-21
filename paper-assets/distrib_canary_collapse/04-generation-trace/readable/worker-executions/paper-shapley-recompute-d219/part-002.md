# paper shapley recompute d219 — Part 2 of 2

**Characterizing the Detectability Landscape of Iterative Model Collapse** · Worker execution logs

[← Part 1](part-001.md) · [Transcript overview](../paper-shapley-recompute-d219.md) · [Structured JSON](../../../sessions/d1/d192ceef6a70bcdc8351.json)

## Before a recorded user message

### Tool result

_source line 122 · 2026-05-24T09:06:22.987Z_

<details><summary>↩ Tool result · `toolu_01SboTgtnnMyFaYrBDM2kcaP`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "59fd290a-614d-446e-a00d-f3bd4626bd18",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
    "oldString": "% TODO-D219: regenerate figure and update caption after Shapley recomputation with 6-seed data\n\\caption{Shapley value decomposition of each method's marginal contribution to FPR (positive bars) and FNR (negative bars). PermG is the only method with zero FPR contribution; naive cross-correlation's FPR dominates its FNR benefit.}",
    "newString": "\\caption{Shapley value decomposition of each method's marginal contribution to FPR (positive bars) and FNR (negative bars), computed from 6 null seeds (36 pairs) and 45 signal experiments (270 pairs). DiffXCorr achieves the best combined Shapley ($-0.299$) via near-zero FPR; PermG ranks second ($-0.141$) as the best directional method.}",
    "originalFile": "\\appendix\n\n\\section{Training Details and Metric Drift}\n\\label{app:training_details}\n\\label{app:drift}\n\n\\paragraph{Hyperparameters.}\nEach generation fine-tunes for 5{,}000 steps using AdamW (learning rate $5 \\times 10^{-5}$, 500 warmup steps, weight decay $0.01$, batch size 4 for Pythia-410M, 32 for GPT-2-medium).\nGeneration uses temperature $1.0$, top-$k{=}50$, max length 512 tokens, producing 5{,}000 samples per generation from 5{,}000-sample subsets of WikiText-103.\nCanary metrics: token entropy $H(p_\\theta | \\text{context})$ over 1{,}000 held-out samples; ECE with 15 bins.\nAdditional downstream metrics (distinct-3, effective rank, Self-BLEU) appear in subsequent appendix sections.\n\n\\paragraph{Metric drift.}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Metric drift (\\%, generation~0$\\to$10) for Pythia-410M across contamination levels. Diversity collapse occurs at all $\\alpha$ levels, with the strongest decline at low-to-moderate contamination ($\\alpha{=}0.25$: distinct-1 $-40.3{\\pm}0.3\\%$) rather than full replacement ($\\alpha{=}1.0$: $-27.8{\\pm}1.6\\%$). $^\\dagger$$\\alpha{=}0.10$: single seed (seed~42, preliminary). $\\alpha{=}0.00$, $\\alpha{=}0.25$, $\\alpha{=}0.50$, $\\alpha{=}0.75$: 3-seed mean${\\pm}$std (seeds 42, 43, 44); $\\alpha{=}1.0$: 4-seed mean${\\pm}$std (seeds 42, 43, 44, 45).}\n\\label{tab:drift_summary}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n$\\alpha$ & Entropy & ECE & Distinct-1 & Distinct-2 & Perplexity \\\\\n\\midrule\n0.00 & $-4.6{\\pm}0.4$ & $+37.6{\\pm}14$ & $-14.1{\\pm}0.4$ & $-9.6{\\pm}0.4$ & $-20.6{\\pm}1.0$ \\\\\n0.10$^\\dagger$ & $-5.3$ & $+57$ & $-39.6$ & $-56.4$ & $-21.0$ \\\\\n0.25 & $-4.7{\\pm}0.5$ & $+81.8{\\pm}15.9$ & $-40.3{\\pm}0.3$ & $-56.4{\\pm}0.7$ & $-18.1{\\pm}0.8$ \\\\\n0.50 & $-18.0{\\pm}0.5$ & $+822.6{\\pm}18.3$ & $-37.1{\\pm}0.4$ & $-50.4{\\pm}1.0$ & $+21.0{\\pm}0.1$ \\\\\n0.75 & $-27.6{\\pm}0.2$ & $+1791{\\pm}18$ & $-32.3{\\pm}0.5$ & $-41.0{\\pm}1.0$ & $+182.6{\\pm}0.7$ \\\\\n1.00 & $-60.8{\\pm}1.2$ & $+3780{\\pm}30$ & $-27.8{\\pm}1.6$ & $-34.0{\\pm}3.3$ & $+3674{\\pm}45$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\n\\section{Distinct-3 Results}\n\\label{app:distinct3}\n\nTable~\\ref{tab:distinct3_drift} reports distinct-3 drift across all contamination levels.\nDistinct-3 exhibits the largest absolute decline among diversity metrics at low contamination ($-58.9{\\pm}0.9\\%$ at $\\alpha{=}0.25$) but attenuates at higher levels ($-30.5\\%$ at $\\alpha{=}1.0$), consistent with the diversity--calibration dissociation discussed in \\S\\ref{sec:discussion}.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Distinct-3 drift (\\%, generation~0$\\to$10) across contamination levels. $\\alpha{=}0.00$, $\\alpha{=}0.25$, $\\alpha{=}0.75$: 3-seed mean${\\pm}$std; $\\alpha{=}1.0$: 4-seed mean${\\pm}$std; $\\alpha{=}0.50$: single seed.}\n\\label{tab:distinct3_drift}\n\\begin{tabular}{lc}\n\\toprule\n$\\alpha$ & Distinct-3 drift (\\%) \\\\\n\\midrule\n0.00 & $-4.4{\\pm}0.5$ \\\\\n0.25 & $-58.9{\\pm}0.9$ \\\\\n0.50 & $-52.4$ \\\\\n0.75 & $-38.6{\\pm}1.3$ \\\\\n1.00 & $-30.5{\\pm}4.0$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Lead-lag analysis.}\nAt $\\alpha{=}1.0$, token entropy Granger-precedes distinct-3 at the same consensus level as distinct-1 and distinct-2: $K{\\geq}4/5$ methods, $S{\\geq}3/4$ seeds (Tier~3).\nHowever, the optimal lag is less stable than for distinct-1/2: at max\\_lag${=}7$, the lag standard deviation across seeds exceeds 1.5 generations, compared to $<0.5$ for distinct-1/2.\nThis instability reflects bimodal lag distributions (modes at lag~1 and lag~3--4), suggesting that distinct-3 captures two temporally distinct diversity loss mechanisms: rapid n-gram homogenization (lag~1) and slower distributional narrowing (lag~3--4).\n\n\\paragraph{Sensitivity to sequence length.}\nHigher-order $n$-gram diversity metrics are more sensitive to generation length and random sampling variability.\nWith our 512-token generation length, distinct-3 has a smaller effective denominator (number of possible unique trigrams observed) than distinct-1 or distinct-2, amplifying stochastic fluctuations.\nThis partially explains the higher lag instability: the signal-to-noise ratio for temporal precedence is lower for distinct-3, requiring more observations (longer $T$ or more seeds) to achieve stable estimates.\nFor this reason, we report distinct-3 in this appendix rather than in the main text, where distinct-1 and distinct-2 provide cleaner evidence of the entropy-leads-diversity pattern.\n\n\n\\section{Observation Window Sensitivity}\n\\label{app:window_sensitivity}\n\nTable~\\ref{tab:window_sensitivity} reports how the Tier~3 consensus classification ($K{\\geq}4/5$ methods) varies as a function of the minimum observation window $T_{\\min}$, where analysis uses only generations $0$ through $T_{\\min}$.\nThe consensus classification stabilizes at $T_{\\min}{\\geq}5$ (6 data points), well below our full observation window of $T{=}10$: all six effect-size reference pairs (token entropy and ECE $\\to$ distinct-1, distinct-2, distinct-3) reach $K{\\geq}4/5$ agreement at every window length from $T_{\\min}{=}5$ through $T_{\\min}{=}10$, with no spurious pairs (canary$\\to$perplexity) admitted.\n\nToda--Yamamoto is the only method exhibiting window-dependent sensitivity (note: TY directional assignment is under verification; these counts are retained for completeness): TY consensus stabilizes at $T_{\\min}{\\geq}6$, slightly later than the primary methods, reflecting the additional degrees of freedom consumed by the augmentation order $d_{\\max}$.\nThis does not affect the consensus classification because the remaining four methods provide stable $K{\\geq}4/5$ agreement independently of Toda--Yamamoto's vote.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Observation window sensitivity for Tier~3 consensus ($K{\\geq}4/5$) at $\\alpha{=}1.0$ (Pythia-410M, 4~seeds). Tier~3 pairs: number of canary$\\to$downstream pairs (out of 8 validated) reaching $K{\\geq}4/5$ method agreement. TY pairs: number of effect-size reference pairs (out of 6) reaching Toda--Yamamoto significance (moderate supplementary method; \\S\\ref{sec:method}). Consensus stabilizes at $T_{\\min}{\\geq}5$; TY stabilizes at $T_{\\min}{\\geq}6$.}\n\\label{tab:window_sensitivity}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccccccc}\n\\toprule\n& \\multicolumn{8}{c}{Minimum observation window $T_{\\min}$} \\\\\n\\cmidrule(lr){2-9}\n& 3 & 4 & 5 & 6 & 7 & 8 & 9 & 10 \\\\\n\\midrule\nTier~3 pairs (/8)    & $\\dagger$ & $\\dagger$ & 6 & 6 & 6 & 6 & 6 & 6 \\\\\nTY pairs$^\\S$ (/6)   & $\\dagger$ & $\\dagger$ & 3--6 & 3--6 & 3--6 & 3--6 & 3--6 & 6 \\\\\nStable               & ---       & ---       & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark \\\\\n\\bottomrule\n\\multicolumn{9}{l}{\\footnotesize $\\dagger$~Insufficient degrees of freedom for Granger-type tests ($<6$ data points).} \\\\\n\\multicolumn{9}{l}{\\footnotesize $^\\S$~TY directional assignment under verification.}\n\\end{tabular}}\n\\end{table}\n\n\n\\section{Robustness Checks}\n\\label{app:robustness}\n\n\\paragraph{Permutation count stability.}\nTable~\\ref{tab:nperm_stability} compares permutation Granger $p$-values at 5{,}000 versus 10{,}000 permutations across all canary$\\to$downstream pairs at $\\alpha{=}0.75$ (3~seeds, 24~pairs).\nPermutation Granger $p$-values are stable to within 0.002 between 5{,}000 and 10{,}000 permutations, with zero significance decisions affected.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Permutation count stability analysis ($\\alpha{=}0.75$, 3~seeds, 24 canary$\\to$downstream pairs). $p$-values from permutation Granger tests at $n_{\\text{perm}}{=}5{,}000$ versus $n_{\\text{perm}}{=}10{,}000$.}\n\\label{tab:nperm_stability}\n\\begin{tabular}{lc}\n\\toprule\nMetric & Value \\\\\n\\midrule\nMax $|\\Delta p|$ & 0.010 \\\\\nMean $|\\Delta p|$ & 0.002 \\\\\nSignificance flips & 0 / 24 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{FDR threshold sensitivity.}\nTable~\\ref{tab:fdr_sensitivity} reports the effect of varying the BH FDR threshold $q$ on treatment ($\\alpha{=}0.75$, 3~seeds, 8-pair basis) versus null ($\\alpha{=}0.0$, 6~seeds 45--50, 6-pair basis) separation for permutation Granger tests.\nTreatment/null separation is qualitatively robust to FDR threshold choice, though the expanded null sample reveals a small number of false positives at each threshold (3--8 of 36 pairs).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{FDR threshold sensitivity for permutation Granger significance. Treatment: $\\alpha{=}0.75$ (3~seeds, 24 forward-direction pairs, 8-pair basis). Null: $\\alpha{=}0.0$ (6~seeds 45--50, 36 pairs, 6-pair basis). The expanded null sample reveals modest false positive rates that increase with $q$.}\n\\label{tab:fdr_sensitivity}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n$q$ & Null FDR-sig (/36) & Treatment FDR-sig (/24) & Separation \\\\\n\\midrule\n0.01 & 3 & 0  & Underpowered \\\\\n0.05 & 4 & 19 & Good \\\\\n0.10 & 8 & 24 & Good (elevated null) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{PermG $p$-value gradient at the onset boundary ($\\alpha{=}0.45$).}\nAt the onset boundary, PermG operates near its detection limit, and marginal $p$-values exhibit seed-dependent variation consistent with the statistical power interpretation (\\S\\ref{sec:theory}).\nTable~\\ref{tab:fdr_gradient_a045} reports BH-corrected $p$-values for all 8 canary$\\to$downstream pairs across two seeds at $\\alpha{=}0.45$.\nSeed~43 reaches a minimum FDR-corrected $p{=}0.059$ (18\\% above the $q{=}0.05$ threshold), while seed~42 reaches $p{=}0.091$ (82\\% above threshold).\nNo pair crosses the significance threshold at either seed, yielding the aggregate 0/8 detection rate reported in \\S\\ref{sec:regime}.\nThe gradient is consistent with a continuous power transition rather than a binary absence of signal: PermG operates near its detection limit at $\\alpha{=}0.45$, with seed-dependent variation in marginal $p$-values.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{BH-corrected PermG $p$-values at $\\alpha{=}0.45$ (8 canary$\\to$downstream pairs $\\times$ 2 seeds). Min $p_{\\mathrm{fdr}}$ per seed shown. All pairs remain above the $q{=}0.05$ threshold, yielding 0/8 aggregate detection.}\n\\label{tab:fdr_gradient_a045}\n\\begin{tabular}{lcc}\n\\toprule\n & Seed 42 & Seed 43 \\\\\n\\midrule\nMin FDR $p$ & 0.091 & 0.059 \\\\\nGap to $q{=}0.05$ & 82\\% & 18\\% \\\\\nPermG fwd sig (/8) & 0 & 0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Systematic Robustness Analysis}\n\\label{app:spec_curve}\n\nThe sharp detection onset reported in \\S\\ref{sec:regime} could in principle depend on specific analytical choices (pair selection, seed, $\\alpha$ level, method parameters).\nWe assess robustness via specification curve analysis~\\cite{simonsohn2020specification}, systematically varying analytical degrees of freedom to test whether the 0/8$\\to$6/8 transition is specification-invariant.\nOur specification curve varies data subsets and pair selections while holding the detection method (PermG) and its hyperparameters fixed, more closely resembling a systematic subset analysis than a full specification curve in the sense of \\citet{simonsohn2020specification}.\n\nWe construct 1{,}160 analytical specifications from the combinatorial space of: 13 contamination levels ($\\alpha$ grid), seed selection ($\\{42, 43, 44, 45\\}$ where available), 8 canonical canary$\\to$downstream pairs (\\{token entropy, ECE\\} $\\times$ \\{distinct-1, distinct-2, distinct-3, mauve\\}), and method parameters (all PermG with $n_\\text{perm}{=}5{,}000$, BH FDR $q{=}0.05$).\nAll specifications use the D120-canonical analysis pipeline with $3\\sigma$ threshold calibration (D105) as a hard filter.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Specification curve summary (1{,}160 specifications, D120-compliant). The blind$\\to$onset jump is robust across specifications: 0\\% significance rate through $\\alpha{=}0.45$, rising to 75\\% at $\\alpha{=}0.50$.}\n\\label{tab:spec_curve}\n\\begin{tabular}{lc}\n\\toprule\nMetric & Value \\\\\n\\midrule\nTotal specifications & 1{,}160 \\\\\nSignificant (FDR $q{<}0.05$) & 536 (46.2\\%) \\\\\n\\midrule\n\\emph{By regime} & \\\\\n\\quad Blind ($\\alpha \\leq 0.45$) & 0\\% \\\\\n\\quad Onset ($\\alpha{=}0.50$) & 75\\% \\\\\n\\quad Detection ($\\alpha \\geq 0.75$) & 62--75\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe specification curve confirms that the sharp detection onset is not an artifact of particular analytical choices: the categorical jump from 0\\% to ${\\geq}75\\%$ significance at $\\alpha_c{\\approx}0.50$ holds across the vast majority of specifications, supporting the main text claim (\\S\\ref{sec:regime}).\n\n\n\\section{Transfer Entropy Analysis}\n\\label{app:transfer_entropy}\n\nTable~\\ref{tab:te_results} reports transfer entropy (TE; \\citealp{schreiber2000measuring}) results aggregated across all baseline conditions.\nTE was estimated using 3-bin discretization with permutation testing ($n{=}5{,}000$).\nNo pair reaches BH-corrected significance ($q{=}0.05$) in any condition, confirming that non-parametric information-theoretic methods lack detection power at $T{=}11$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Transfer Entropy results (12 runs across all $\\alpha$ levels). TE\\textsubscript{fwd}: canary$\\to$downstream; TE\\textsubscript{rev}: downstream$\\to$canary. Mean uncorrected permutation $p$-values ($n{=}5{,}000$). No pair reaches BH-corrected $q{<}0.05$ in any run.}\n\\label{tab:te_results}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\nCanary & Downstream & TE\\textsubscript{fwd} (mean) & $p$\\textsubscript{fwd} (mean) & TE\\textsubscript{rev} (mean) & $p$\\textsubscript{rev} (mean) \\\\\n\\midrule\ntoken\\_entropy & distinct-1 & 0.289 & 0.559 & 0.480 & 0.490 \\\\\ntoken\\_entropy & distinct-2 & 0.300 & 0.529 & 0.496 & 0.447 \\\\\ntoken\\_entropy & distinct-3 & 0.255 & 0.645 & 0.484 & 0.459 \\\\\ntoken\\_entropy & perplexity & 0.257 & 0.676 & 0.386 & 0.626 \\\\\nECE & distinct-1 & 0.185 & 0.720 & 0.184 & 0.891 \\\\\nECE & distinct-2 & 0.208 & 0.683 & 0.216 & 0.846 \\\\\nECE & distinct-3 & 0.209 & 0.689 & 0.227 & 0.807 \\\\\nECE & perplexity & 0.296 & 0.572 & 0.263 & 0.747 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\phantomsection\\label{app:te_mi}\n\\paragraph{KNN-based TE/MI decomposition.}\nA $k$-nearest-neighbor TE estimator ($k{=}5$) provides a model-free complement to the parametric Granger framework.\nForward-dominant TE fraction increases monotonically with $\\alpha$: 4/8 pairs at $\\alpha{=}0.25$ (mean net TE${=}0.14$), 5/8 at $\\alpha{=}0.50$ (net TE${=}0.42$), 6/8 at $\\alpha{=}0.60$ (net TE${=}0.57$), and 8/8 at $\\alpha{=}1.0$ (net TE${=}1.59$).\nAll 120 forward TE bootstrap 95\\% CIs exclude zero at $T{=}10$; all 48 at $T{=}20$.\nThe ``high MI, low TE'' hypothesis for the non-monotonic dip is supported by only 2/8 pairs (ECE$\\to$perplexity and token entropy$\\to$perplexity); the remaining 6 pairs show elevated TE even at $\\alpha{=}0.60$, indicating confounded co-variation rather than a universal mechanism.\n\n\\section{Change-Point Detection Analysis}\n\\label{app:change_point}\n\nWe apply a max-split change-point test with bootstrap significance assessment ($n{=}5{,}000$, $p{<}0.05$) to each metric's generation-level time series ($T{=}11$).\n\nUnder the null control ($\\alpha{=}0.00$, 3~seeds), downstream diversity metrics (distinct-1, distinct-2, distinct-3) produce significant change-points at generation~2 in all seeds (9/9 tests). With additional significant tests from ECE (2/3 seeds) and token entropy (1/3 seeds), the overall false positive rate reaches 66.7\\% (12/18 tests; Table~\\ref{tab:cp_null}). The monotonic drift inherent in iterative self-training is sufficient to trigger change-point detection even without canary contamination. Individual change-point significance therefore cannot serve as standalone evidence for a canary-specific effect.\n\nAlthough individual significance is unreliable as a discriminator, the temporal ordering of detected change-points reverses between null and treatment conditions. In the null ($\\alpha{=}0.00$), downstream metrics show the earliest significant breaks at generation~2 (all seeds), while significant canary breaks appear later (ECE at generations~4--8). Under treatment conditions ($\\alpha{\\geq}0.75$), this ordering flips: canary metrics place their best splits at generation~1, followed by downstream diversity metrics at generations~2--4 and perplexity at generation~4 (Table~\\ref{tab:cp_results}). This ordering reversal provides complementary evidence from a distinct statistical framework, consistent with the Granger-precedence analysis in \\S\\ref{sec:experiments}.\n\nSeveral caveats apply. The 18 individual tests per condition were not corrected for multiple comparisons (BH or Bonferroni); primary inference rests on the cross-metric temporal ordering rather than on individual significance tests. Under treatment conditions, token entropy places its best split at generation~1 with large effect sizes ($|d|{>}2.5$) in all seeds, but the pre-change segment at a generation-1 split contains only a single data point, reducing bootstrap power (1/3 seeds significant at $\\alpha{=}0.75$). The short series length ($T{=}11$) further limits overall detection power.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Change-point detection under null control ($\\alpha{=}0.00$, 3 seeds). CP: detected change-point generation (mean across significant seeds); $|d|$: Cohen's $d$ effect size (mean across all seeds); Sig.\\ rate: fraction of seeds where $p{<}0.05$. Overall FPR: 12/18 = 66.7\\%.}\n\\label{tab:cp_null}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\nMetric & CP gen (mean) & $|d|$ (mean) & Sig.\\ rate & Type \\\\\n\\midrule\ntoken\\_entropy & 1.0 & 2.94 & 1/3 & canary \\\\\nECE & 6.0 & 1.62 & 2/3 & canary \\\\\ndistinct-1 & 2.0 & 2.27 & 3/3 & downstream \\\\\ndistinct-2 & 2.0 & 2.40 & 3/3 & downstream \\\\\ndistinct-3 & 2.0 & 2.27 & 3/3 & downstream \\\\\nperplexity & --- & 3.11 & 0/3 & downstream \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Change-point detection at $\\alpha{=}0.75$ (3 seeds). CP: detected change-point generation; $|d|$: Cohen's $d$ effect size between pre- and post-change segments. Sig.\\ rate: fraction of seeds where $p{<}0.05$.}\n\\label{tab:cp_results}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\nMetric & CP gen (mean) & $|d|$ (mean) & Sig.\\ rate & Type \\\\\n\\midrule\ntoken\\_entropy & 1.0 & 3.21 & 1/3 & canary \\\\\nECE & 1.0 & 3.10 & 1/3 & canary \\\\\ndistinct-1 & 2.3 & 2.18 & 3/3 & downstream \\\\\ndistinct-2 & 3.0 & 1.97 & 3/3 & downstream \\\\\ndistinct-3 & 3.7 & 1.86 & 3/3 & downstream \\\\\nperplexity & 4.0 & 1.70 & 3/3 & downstream \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Dose-response ordering pattern.}\nTable~\\ref{tab:cp_ordering} summarizes the ordering pattern across contamination levels.\nThe canary-to-downstream gap shifts monotonically from negative (downstream first) under the null to positive (canary first) under treatment, ruling out a methodological artifact in which canary metrics would systematically appear earlier regardless of condition.\nThe $\\alpha{=}1.0$ analysis is limited to a single seed (s42); all other conditions use 3 seeds.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccl}\n\\toprule\n$\\alpha$ & Canary cp & Downstream cp & Gap & Direction \\\\\n\\midrule\n0.00 & gen 4--8 & gen 2 & $-$2.5 & Downstream first \\\\\n0.25 & gen 3--4 & gen 3--4 & $\\approx$0 & Simultaneous \\\\\n0.75 & gen 1 & gen 2--4 & $+$2.25 & Canary first \\\\\n1.00 & gen 2 & gen 2--5 & $+$1.0 & Canary first \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Change-point ordering reversal across contamination levels. Under the null ($\\alpha{=}0.00$), downstream metrics break before canary metrics; this ordering reverses monotonically as $\\alpha$ increases, consistent with the Granger-precedence analysis.}\n\\label{tab:cp_ordering}\n\\end{table}\n\n\n\\section{Sequential Monitoring: CUSUM vs Calibrated Threshold}\n\\label{app:csmp}\n\nWe translate the Granger-precedence finding into a deployable monitoring protocol using CUSUM (cumulative sum) sequential testing~\\cite{page1954continuous}, calibrated against the $\\alpha{=}0.0$ null control.\nThe null-calibration procedure sets the alarm threshold $h$ such that the false alarm rate (FAR) is 0\\% on null data (3~seeds, $T{=}10$), providing controlled Type~I error guarantees.\n\n\\paragraph{Method.}\nCUSUM monitors the cumulative deviation of token entropy from its null-control baseline: $S_t = \\max(0,\\; S_{t-1} + (\\mu_0 - x_t) - k)$, where $\\mu_0$ is the null-control mean, $k$ is the allowance parameter, and the alarm triggers when $S_t > h$.\nWe calibrate $h$ for each $k$ from the $\\alpha{=}0.0$ null data (Table~\\ref{tab:csmp_calibration}).\nAs a baseline, we compare against a simple calibrated threshold: alarm when the metric crosses $\\mu_0 - 2\\sigma_0$ for $n{\\geq}1$ or $n{\\geq}2$ consecutive generations.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{CUSUM calibration parameters from $\\alpha{=}0.0$ null control (3~seeds). $h$: alarm threshold calibrated to achieve FAR${=}$0\\%. For $k{\\geq}0.25$, the null CUSUM statistic remains at zero, yielding $h \\approx 0$.}\n\\label{tab:csmp_calibration}\n\\begin{tabular}{lcc}\n\\toprule\n$k$ & $h$ & FAR \\\\\n\\midrule\n0.05 & 1.530 & 0\\% \\\\\n0.10 & 1.005 & 0\\% \\\\\n0.25 & $\\approx$0 & 0\\% \\\\\n0.50 & $\\approx$0 & 0\\% \\\\\n1.00 & $\\approx$0 & 0\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Results.}\nTable~\\ref{tab:csmp_comparison} compares CUSUM and simple threshold detection times across gradual contamination levels.\nAt the recommended operating point ($k{=}0.25$), CUSUM and the simple threshold ($n{\\geq}1$) produce identical alarm times (generation~1) across all seeds and contamination levels.\nMore conservative CUSUM settings ($k{=}0.1$, $k{=}0.05$) delay detection to match the $n{\\geq}2$ threshold or later.\nAt $k{=}1.0$ with $\\alpha{=}0.50$, CUSUM fails entirely ($S_t \\equiv 0$ for all seeds), demonstrating sensitivity to the allowance parameter.\nNo CUSUM configuration outperforms the simple calibrated threshold at any operating point tested.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{CUSUM vs simple calibrated threshold: alarm generation across contamination levels (3~seeds each; all seeds agree on the alarm generation shown). Threshold: metric crosses $\\mu_0 - 2\\sigma_0$. No CUSUM configuration outperforms the simple threshold at any operating point.}\n\\label{tab:csmp_comparison}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n$\\alpha$ & CUSUM $k{=}0.25$ & CUSUM $k{=}0.1$ & CUSUM $k{=}0.05$ & Thresh $n{\\geq}1$ & Thresh $n{\\geq}2$ \\\\\n\\midrule\n0.50 & gen 1 & gen 2 & gen 3 & gen 1 & gen 2 \\\\\n0.75 & gen 1 & gen 2 & gen 2 & gen 1 & gen 2 \\\\\n\\bottomrule\n\\multicolumn{6}{l}{\\footnotesize CUSUM $k{=}1.0$ at $\\alpha{=}0.50$: $S_t \\equiv 0$ for all seeds (complete detection failure).} \\\\\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Interpretation.}\nThe equivalence arises because the generation-0$\\to$1 entropy drop is large ($|\\Delta x| > 0.7$ for $\\alpha{=}0.50$, $> 1.0$ for $\\alpha{=}0.75$) relative to the null-control variability ($\\sigma_0 \\approx 0.03$).\nAny detector with a near-zero or small threshold triggers at generation~1; CUSUM's cumulative memory provides no advantage when the initial shift already exceeds the control limit.\nThis result extends Claim~3 (method sensitivity) beyond lead-lag detection to the monitoring domain: even a sequential testing procedure with stronger theoretical properties (optimal expected detection delay under continuous monitoring) does not improve over a calibrated baseline when the initial contamination signal dominates the allowance parameter.\nThe contribution of the null-calibrated monitoring framework is the calibration procedure itself (setting alarm boundaries from $\\alpha{=}0.0$ data to guarantee FAR${=}$0\\%), not the CUSUM algorithm.\n\n\\section{Background and Notation}\n\\label{app:background}\n\\label{sec:background}\n\nThis section establishes the formal setup and notation used throughout the paper.\n\n\\paragraph{Iterative training loop.}\nLet $M_0$ denote a pretrained language model and $\\mathcal{D}_\\text{real}$ a fixed corpus of human-written text.\nAt each generation $t \\geq 1$, the model $M_{t-1}$ generates a synthetic corpus $\\mathcal{D}_\\text{synth}^{(t-1)}$, and the next-generation model $M_t$ is fine-tuned on a mixture of $\\alpha$ fraction synthetic data and $(1{-}\\alpha)$ fraction real data:\n\\begin{equation}\n    \\mathcal{D}_\\text{train}^{(t)} = \\alpha \\cdot \\mathcal{D}_\\text{synth}^{(t-1)} \\;+\\; (1{-}\\alpha) \\cdot \\mathcal{D}_\\text{real}, \\quad \\alpha \\in [0, 1].\n    \\label{eq:mixing}\n\\end{equation}\nAt $\\alpha{=}1.0$, this reduces to the full-replacement paradigm of \\citet{shumailov2024curse}.\n\n\\paragraph{Metric families.}\n\\emph{Canary metrics}: token entropy ($H(p_\\theta | \\text{context})$ on held-out samples) and expected calibration error (ECE).\n\\emph{Downstream metrics}: distinct-$n$ ($n \\in \\{1, 2, 3\\}$)~\\cite{li2016diversity} and perplexity.\nEach metric produces a time series of $T{+}1$ observations.\n\n\\paragraph{Lead-lag testing.}\nGiven canary series $X$ and downstream series $Y$, the central question is whether changes in $X$ temporally precede changes in $Y$, requiring directionality and confounder control beyond simple correlation.\nWe employ five methods spanning permissive to conservative: naive cross-correlation, differenced cross-correlation, threshold onset detection, permutation Granger causality~\\cite{shojaie2022granger}, and Toda--Yamamoto Granger causality~\\cite{toda1995statistical}.\n\n\\section{MMCT Algorithm}\n\\label{app:mmct}\n\nAlgorithm~\\ref{alg:mmct} describes the Multi-Method Consensus Test (MMCT) introduced in \\S\\ref{sec:mmct}.\n\n\\begin{algorithm}[h]\n\\caption{Multi-Method Consensus Test (MMCT)}\n\\label{alg:mmct}\n\\begin{algorithmic}[1]\n\\Require Time series pair $(X, Y)$; methods $\\{m_1, \\ldots, m_K\\}$ ($K{=}5$); null-control data $\\mathcal{N}$ (from $\\alpha{=}0.0$); tolerance $\\epsilon{=}0.01$\n\\Ensure $p$-value, consensus level $\\hat{K}$\n\\For{each method $m_k$}\n    \\State Compute empirical FPR: $\\widehat{\\mathrm{FPR}}_k \\gets$ fraction of null-control pairs where $m_k$ rejects $H_0$\n    \\State Compute weight: $w_k \\gets 1 / \\max(\\widehat{\\mathrm{FPR}}_k,\\; \\epsilon)$\n    \\State Apply $m_k$ to $(X, Y)$: $d_k \\gets \\mathbf{1}[m_k \\text{ rejects } H_0]$\n\\EndFor\n\\State Weighted consensus: $W(X {\\to} Y) \\gets \\sum_{k} w_k \\, d_k \\;/\\; \\sum_{k} w_k$\n\\State Build empirical null distribution of $W$ from all null-control pairs in $\\mathcal{N}$\n\\State Compute $p$-value from empirical null: $p \\gets \\Pr_{\\mathcal{N}}(W \\geq W_{\\mathrm{obs}})$\n\\State Consensus level: $\\hat{K} \\gets \\sum_{k} d_k$\n\\State \\Return $p$, $\\hat{K}$\n\\end{algorithmic}\n\\end{algorithm}\n\n\\paragraph{Design rationale.}\nFPR-inverse weighting penalizes methods with high false positive rates on null-control data: naive cross-correlation (FPR${=}91.7\\%$) receives weight $w{=}1.09$, while PermG (FPR${=}11.1\\%$, the lowest among directional methods; DiffXCorr achieves 2.8\\% but lacks directional separation) receives $w{=}9.0$.\nThe empirical null distribution avoids parametric assumptions that are unreliable for short ($T{=}5$--$20$), non-stationary series typical of iterative training.\nMMCT is a consensus testing protocol, not a novel statistical method; its value lies in systematic method comparison and the identification of method-dependent conclusions.\n\n\n\\section{Methodological Comparison Table}\n\\label{app:method_comparison}\n\nTable~\\ref{tab:method-comparison} summarizes the methodological coverage of existing canary and monitoring analyses across the diagnostic dimensions identified in \\S\\ref{sec:method}.\nNo prior work combines all six dimensions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Methodological comparison of canary and monitoring analyses. \\checkmark\\ = present, $\\times$ = absent, $\\circ$ = partial (${\\leq}2$ levels or limited replication). Diff.\\ = differencing/stationarity controls. Multi-M.\\ = ${\\geq}2$ independent statistical methods. MTC = multiple testing correction. Regime = systematic variation of $\\alpha$. Seeds = ${\\geq}3$ independent seeds. Arch.\\ = ${\\geq}2$ architecturally distinct model families.}\n\\label{tab:method-comparison}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccccl}\n\\toprule\nWork & Diff. & Multi-M. & MTC & Regime & Seeds & Arch. & Metrics \\\\\n\\midrule\n\\citet{shumailov2024curse}     & $\\times$   & $\\times$   & $\\times$   & $\\circ$    & \\checkmark & \\checkmark & PPL \\\\\n\\citet{du2025scales}           & $\\times$   & $\\times$   & \\checkmark & \\checkmark & \\checkmark & $\\times$   & ECE, Acc, Dist-$n$ \\\\\n\\citet{gambetta2024surplexity} & $\\times$   & $\\times$   & $\\times$   & \\checkmark & \\checkmark & \\checkmark & Surplexity, Ent \\\\\nSIGMA~\\cite{sigma2026spectral} & $\\times$   & $\\times$   & $\\times$   & $\\times$   & $\\times$   & $\\times$   & Spectral \\\\\nDCES~\\cite{dces2026counter}    & $\\times$   & $\\times$   & $\\times$   & $\\times$   & $\\times$   & \\checkmark & ECE, Ent, PPL \\\\\n\\midrule\n\\textbf{Ours}                  & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark & Ent, ECE, PPL, Dist-$n$ \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\\section{Extended Discussion}\n\\label{app:extended_discussion}\n\n\\paragraph{Calibration scope and generalization.}\nAll FPR and FNR calibration results are specific to our experimental setup: Pythia-410M, WikiText-103 subset, $T{=}10$, and six contamination levels.\nCross-architecture validation across 15 conditions spanning six model families shows that the entropy-leads-diversity pattern generalizes in 11 of 15 architecture-seed combinations (Table~\\ref{tab:generalization}); GPT-2 bf16 (0/8), GPT-2 s43 (6/8 bidirectional), SmolLM3-3B (3/8, entropy decoupling), and Pythia-1.4B s42 (2/8) do not confirm the pattern.\n\n\\paragraph{Domain-dependent directionality.}\nThe unidirectional forward causation observed on WikiText (PermG reverse${=}$0/8 across all conditions) does not hold universally.\nOn C4 at $\\alpha{=}0.50$ (s42 fp32), PermG reverse reaches 7/8, indicating near-symmetric bidirectional coupling; however, this is seed-dependent (s43: 1/8) and noted as preliminary.\nThe practical implication is that directional asymmetry should be verified per domain.\n\n\\paragraph{Token entropy versus perplexity.}\nThe distinction lies in the evaluation domain: token entropy is $H(p_\\theta | \\text{context})$ on held-out real data, while perplexity is $\\exp(H_\\text{cross})$ on model-generated text.\nFirst-differencing removes their shared downward trend: the canary$\\to$diversity channel survives because entropy leads diversity by one generation, whereas the canary$\\to$perplexity channel vanishes because both co-move synchronously.\n\n\\paragraph{NLP-specific constraints.}\nOur application of Granger-type methods faces constraints absent in econometrics: (i)~observation length ($T{=}5$--$20$ vs.\\ $T{=}100$--$1000$); (ii)~non-stationarity by design rather than incidental; (iii)~small multiplicity for FDR correction (8--32 pairs per regime).\nTransfer entropy (0/192 FDR-significant results) confirms that method sensitivity extends beyond the five-method panel.\n\n\\paragraph{Prevention paradox.}\nEffective intervention truncates the collapse trajectory that established Granger precedence.\nDifferenced cross-correlation retains significance under intervention (31/32 pairs), while threshold onset fails entirely (0/8), reinforcing the multi-method rationale.\n\n\\paragraph{Grouped testing rationale.}\nWe test 8 canary$\\to$downstream pairs jointly (2 canaries $\\times$ 4 downstream metrics) rather than individual per-metric tests because: (i)~joint testing with BH-FDR correction controls family-wise error across the canary panel, avoiding the inflated false-positive rate that would result from reporting the single most significant pair; (ii)~the count of significant pairs ($k/8$) provides a natural effect-size measure that distinguishes isolated from systematic detection; (iii)~per-metric tests cannot capture the cross-metric consistency that separates genuine temporal precedence from metric-specific artifacts (e.g., MAUVE floor saturation affects 2/8 pairs universally, identifiable only in grouped results).\n\n\\paragraph{Canary metric choice.}\nSmolLM3-3B reveals that canary metric selection constitutes a sensitivity dimension beyond the five statistical methods: token entropy exhibits non-monotonic oscillations (0/4 significant pairs), while ECE maintains monotonic growth (3/4 pairs).\nNo single canary metric is universally optimal.\n\n\\paragraph{Exploratory CSD analysis.}\nCanary metrics show rising autocorrelation (Kendall $\\tau{=}0.79$--$0.82$) while downstream metrics show none ($\\tau{=}0.03$--$0.30$), but this pattern does not survive multiple testing correction (2/10 post-BH) and remains exploratory.\nWe note that \\citet{truong2026phase} show model collapse is a first-order transition, ruling out CSD as a structural detection mechanism; the rising autocorrelation likely reflects non-stationarity rather than critical slowing down.\n\n\\paragraph{Scale verification (Pythia-1.4B).}\n\\label{app:scale_14b}\nTo test whether the phase-diagram structure generalizes beyond 410M, we replicate the analysis at 1.4B scale ($T{=}10$--$15$, fp32, seed~42).\nTable~\\ref{tab:14b_phase} summarizes the available cells.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Pythia-1.4B phase-diagram cells (fp32, PermG forward, direction-checked).}\n\\label{tab:14b_phase}\n\\begin{tabular}{lcccc}\n\\toprule\n$\\alpha$ & \\multicolumn{2}{c}{$T{=}10$} & \\multicolumn{2}{c}{$T{=}15$} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\n         & s42 & s44 & s42 & s43 \\\\\n\\midrule\n0.45 & 0/6 & 0/6 & 3/6 & 5/6 \\\\\n0.50 & 4/6 & 6/6 & 3/6 & 3/6 \\\\\n0.60 & 4/6 & 6/6 & 6/6 & 6/6 \\\\\n0.75 & 5/6 & 6/6 & 6/6 & 6/6 \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\footnotesize All: PermG fwd, 6-pair basis (2 canaries $\\times$ 3 distinct-$n$;} \\\\\n\\multicolumn{5}{l}{\\footnotesize MAUVE excl.\\ due to floor ${\\sim}0.033$ at 1.4B).} \\\\\n\\multicolumn{5}{l}{\\footnotesize s42 rev.\\ 0/6 at all $\\alpha$; s43 rev.\\ see text.} \\\\\n\\end{tabular}\n\\end{table}\n\nThe phase-diagram structure is qualitatively preserved at 1.4B scale.\nECE maintains monotonic growth across all three tested $\\alpha$ levels (3/3 cross-scale robust), and the binary detection pattern (above vs.\\ below $\\alpha_c$) is consistent with the 410M phase diagram.\nOn the 6-pair basis (MAUVE excluded due to systematic floor ${\\sim}0.033$; Table~\\ref{tab:14b_phase}), PermG forward detection at 1.4B ranges from 0/6 ($\\alpha{=}0.45$, $T{=}10$) to 6/6 ($\\alpha{\\geq}0.60$, $T{=}15$); token entropy exhibits one-step saturation ($27$--$39\\%$ drop from generation~0 to~1), reducing temporal resolution for entropy-based pairs.\nSeed s42 shows PermG$_\\text{rev}{=}0/6$ across all eight 1.4B conditions ($4\\alpha{\\times}2T$), confirming that bidirectionality is seed-specific rather than scale-inherent.\nThe 410M sync-dip ($\\alpha{=}0.60$: 0/8 at $T{\\leq}20$) does not reproduce at 1.4B (4/6 at $T{=}10$); whether this reflects scale-dependent dynamics or Pythia-specific effects remains open with only two model sizes tested.\nAt $T{=}15$, scale effects are $\\alpha$-conditional: $\\alpha{=}0.60$ reaches 6/6, while $\\alpha{=}0.50$ attenuates to 3/6 (vs 4/6 at $T{=}10$), confirming that detection loss is onset-localized rather than uniform.\nThe boundary's $T$-dependence is preserved: $\\alpha{=}0.45$ rises from 0/6 ($T{=}10$) to 3/6 ($T{=}15$), mirroring the 410M boundary shift.\nHowever, method-level heterogeneity emerges: Toda--Yamamoto exhibits a non-monotonic pattern at $T{=}15$, inverting the PermG ordering in the mid-$\\alpha$ range; gradual low-$\\alpha$ dynamics preserve VAR lag structure, while rapid entropy saturation disrupts lag dependence at intermediate $\\alpha$, with recovery at $\\alpha{=}0.75$ where extreme collapse dynamics (PPL drift ${+}390\\%$) generate sufficient temporal variation to support VAR detection.\nOnset-zone attenuation is $\\alpha$-invariant at 1.4B: both $\\alpha{=}0.45$ and $0.50$ yield 3/6 at $T{=}15$.\nAt 1.4B with $T{=}10$ (11 data points), non-PermG methods (threshold onset, naive cross-correlation, Toda--Yamamoto) have insufficient power due to short sequence length, reducing $K{\\geq}3$ consensus to an effective single-method test; at $T{=}15$ (16 data points), detection recovers (6/6 at $\\alpha{=}0.60$, lead time ${=}$ 10 generations) and $K{\\geq}3$ recovers its multi-method character, with 3/4 $\\alpha$ conditions achieving $K{\\geq}3{\\geq}2/6$ (onset $\\alpha{=}0.50$ seed-dependent: s42 1/6, s43 3/6).\nCross-method consensus ($K{\\geq}3$) exhibits seed-dependent variability at onset ($\\alpha{\\approx}0.50$), consistent with the noisy transition expected at phase boundaries, while remaining robust above onset ($K{\\geq}3$ ${\\geq}5/6$ at $\\alpha{=}0.75$).\nOn a unified 6-pair basis (MAUVE excluded due to systematic floor at ${\\sim}0.033$; Table~\\ref{tab:14b_phase}), third-seed replication (s44) at $T{=}10$ confirms ceiling detection above onset (6/6 at $\\alpha{\\geq}0.50$) with 0/6 at $\\alpha{=}0.45$, validating the blind zone.\nCross-$T$ improvement holds at 3/4 $\\alpha$ values ($\\alpha{=}0.45$: $0/6{\\to}5/6$; $\\alpha{=}0.60$: $6/6{\\to}6/6$; $\\alpha{=}0.75$: $6/6{\\to}6/6$), validating the predicted $\\alpha_c(T)$ decrease; at onset ($\\alpha{=}0.50$), PermG shows a marginal decrease ($6/6{\\to}3/6$), consistent with phase-boundary variability.\nAt onset ($\\alpha{=}0.45$--$0.50$), ECE-based pairs achieve higher detection rates than entropy-based pairs (e.g., 3/3 vs 0/3 robust at $\\alpha{=}0.50$, $T{=}15$), consistent with entropy's one-step saturation reducing temporal resolution at 1.4B scale.\n\n\\paragraph{Future work.}\nExtensions include multivariate VAR models for confounder testing, multi-seed replication across all six architecture families, longer training runs ($T{\\geq}20$), online monitoring within training pipelines, and accumulate-mode experiments~\\cite{dey2024breaking}.\nThe sigmoid onset boundary ($\\alpha_c{=}0.483$) invites connection to the critical mixture ratio scaling law of \\citet{gu2024cmr} and the data-mixing transitions of \\citet{gu2025datamixing}.\n\n\n\\section{Per-Method Dose-Response Profiles}\n\\label{app:dose_response}\n\nTable~\\ref{tab:dose_response_full} reports FDR significance counts (/8 validated pairs) for all five detection methods across 12 contamination levels (seed~42, Pythia-410M, WikiText, fp32).\nPermG exhibits a sharp 0$\\to$6 jump at $\\alpha{=}0.50$ with a return to 0 at $\\alpha{=}0.55$--$0.60$ (non-monotonic dip), while other methods show diffuse profiles: naive cross-correlation saturates at 7--8/8 across all levels including the null, and Toda--Yamamoto fluctuates without a clear onset.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-method FDR significance (/8 pairs) across contamination levels (Pythia-410M, seed~42, WikiText, fp32). PermG and Diff.\\ XCorr use BH-corrected FDR ($q{=}0.05$); Naive XCorr, Threshold, and TY use uncorrected $p{<}0.05$ (no FDR field in pipeline). $\\alpha{=}1.0$ from Pythia-410M cross-architecture condition (same seed/domain/precision).}\n\\label{tab:dose_response_full}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n$\\alpha$ & Naive & Diff.\\ XCorr & Threshold & PermG & TY$^\\S$ \\\\\n\\midrule\n0.00 & 8 & 4 & 3 & \\textbf{0} & 1 \\\\\n0.10 & 7 & 6 & 0 & \\textbf{0} & 0 \\\\\n0.25 & 8 & 3 & 0 & \\textbf{0} & 2 \\\\\n0.30 & 8 & 4 & 0 & \\textbf{0} & 3 \\\\\n0.35 & 8 & 4 & 0 & \\textbf{0} & 1 \\\\\n0.40 & 8 & 3 & 0 & \\textbf{0} & 4 \\\\\n0.45 & 8 & 6 & 0 & \\textbf{0} & 1 \\\\\n0.50 & 8 & 7 & 4 & \\textbf{6} & 3 \\\\\n0.55 & 8 & 8 & 0 & \\textbf{0} & 1 \\\\\n0.60 & 8 & 6 & 0 & \\textbf{0} & 0 \\\\\n0.75 & 7 & 6 & 0 & \\textbf{6} & 3 \\\\\n1.00 & 8 & 6 & 2 & \\textbf{6} & 1 \\\\\n\\bottomrule\n\\multicolumn{6}{l}{\\footnotesize $^\\S$TY directional assignment under verification; column retained for completeness.} \\\\\n\\end{tabular}}\n\\end{table}\n\nThe table highlights PermG's combination of null-control detection at 0/8 for this seed ($\\alpha{=}0.00$; pooled FPR across 6 seeds: 11.1\\%, lowest among directional methods), sharp onset (0$\\to$6 at $\\alpha{=}0.50$), and non-monotonic dip (0 at $\\alpha{=}0.55$--$0.60$), confirming it as the method whose dose-response profile most cleanly separates detection regimes.\nNaive cross-correlation's persistently high counts (7--8/8 even at $\\alpha{=}0.00$) demonstrate the 91.7\\% pooled null-control FPR reported in \\S\\ref{sec:method}.\n\n\n\\paragraph{Comparison with naive baselines.}\n\\label{app:naive_baselines}\n\nTable~\\ref{tab:naive_baselines} compares PermG against two practitioner-facing monitoring rules across 26 experiments (18~$\\alpha$ values, Pythia-410M, $T{=}10$, fp32).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Naive baseline comparison (Pythia-410M, $T{=}10$, fp32, 3 null-control runs).}\n\\label{tab:naive_baselines}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & FPR ($\\alpha{=}0$) & Onset $\\alpha$ \\\\\n\\midrule\nPPL-slope (${\\geq}2$ consec.\\ rises) & 100\\% (3/3) & 0.10 \\\\\nVariance-threshold ($2\\sigma$) & 67\\% (2/3) & 0.10 \\\\\nPermG (fwd ${\\geq}1$) & 0\\% (0/3) & 0.50 \\\\\n\\bottomrule\n\\multicolumn{3}{l}{\\footnotesize Onset $\\alpha$: lowest $\\alpha$ where method fires (seed~42).} \\\\\n\\end{tabular}\n\\end{table}\n\nPPL-slope fires at $\\alpha{=}0$ because the first-generation learning effect (perplexity drops from 26.9 to 19.3 at generation~1, then rises monotonically from generation~2 onward) produces consecutive rises indistinguishable from contamination-driven drift.\nVariance-threshold similarly triggers on the natural perplexity recovery.\nPermG avoids these false alarms by testing canary$\\to$downstream Granger precedence rather than univariate trend, thereby excluding training-drift confounds from the detection signal.\nNaive monitoring rules cannot distinguish contamination from natural training dynamics; formal statistical testing is necessary for controlled FPR.\n\n\n\\section{PermG Power Analysis}\n\\label{app:power_analysis}\n\nWe characterize PermG detection power via simulation under a controlled data-generating process (DGP) that matches the structure of our iterative training time series.\n\n\\paragraph{DGP.}\nFor each trial, we generate a bivariate system $(X_t, Y_t)$ for $t = 1, \\ldots, T$ where $X_t = \\mu + \\epsilon_t^X$ and $Y_t = \\mu + \\beta X_{t-1} + \\epsilon_t^Y$, with $\\epsilon \\sim \\mathcal{N}(0, \\sigma^2)$ and $\\sigma{=}1$.\nThe coupling parameter $\\beta$ controls signal strength; $\\beta{=}0$ is the null.\nThe linear coupling provides a power lower bound; nonlinear dynamics in actual iterative training may yield different power characteristics.\nWe sweep $\\beta \\in [0, 2]$ across $T \\in \\{6, 8, 10, 15, 20\\}$, running 100 replications per $(\\beta, T)$ cell with 5{,}000 permutations each and BH FDR correction at $q{=}0.05$ across 8 hypothetical pairs (matching the experimental setup).\n\n\\paragraph{Results.}\nTable~\\ref{tab:beta50} reports $\\beta_{50}$, the coupling strength required for 50\\% detection power, at each observation length $T$.\nUnder $\\sqrt{T}$ scaling, the product $\\beta_{50} \\cdot \\sqrt{T}$ should be constant; the observed decrease from 5.09 ($T{=}8$) to 2.68 ($T{=}20$) indicates that power grows faster than $\\sqrt{T}$, with the empirical scaling closer to $T^{-1.1}$.\nThe $\\sqrt{T}$ formula in \\S\\ref{sec:theory} thus provides a conservative lower bound on detection power: actual power at $T{=}20$ exceeds the $\\sqrt{T}$ prediction.\nFalse positive rates under FDR correction remain at or below 2\\% across all $T$ values (raw: 1--9\\%; Table~\\ref{tab:beta50}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{PermG power analysis: $\\beta_{50}$ (coupling for 50\\% power) under BH-FDR correction ($q{=}0.05$, 8 pairs). $\\beta_{50} \\cdot \\sqrt{T}$ decreases with $T$, indicating power grows faster than $\\sqrt{T}$. FPR: false positive rate at $\\beta{=}0$ (raw / FDR-corrected). Dashes indicate $<$50\\% power not reached within $\\beta \\leq 2.0$.}\n\\label{tab:beta50}\n\\begin{tabular}{lcccc}\n\\toprule\n$T$ & $\\beta_{50}$ & $\\beta_{50} \\cdot \\sqrt{T}$ & FPR (raw) & FPR (FDR) \\\\\n\\midrule\n6  & ---  & ---  & 1\\% & 0\\% \\\\\n8  & ---  & ---  & 6\\% & 2\\% \\\\\n10 & 2.0  & 6.32 & 9\\% & 2\\% \\\\\n15 & 1.2  & 4.65 & 6\\% & 2\\% \\\\\n20 & 0.9  & 4.02 & 5\\% & 1\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/permg_power_curve.pdf}\n\\caption{PermG detection power as a function of coupling strength $\\beta$ for five observation lengths ($T{=}6$--$20$; 100 replications $\\times$ 5{,}000 permutations, BH FDR $q{=}0.05$). Power increases with both $\\beta$ and $T$; at $T{=}6$--$8$, PermG remains underpowered ($<$20\\%) even at $\\beta{=}2.0$, consistent with the $T{=}10$ minimum required for reliable detection in our experimental setting.}\n\\label{fig:permg_power}\n\\end{figure*}\n\nAt $T{=}6$ and $T{=}8$, 50\\% power is not reached within $\\beta \\leq 2.0$ under FDR correction, explaining why PermG is fundamentally underpowered for very short series.\nThe practical implication for our $T{=}10$ setting: $\\beta_{50}{=}2.0$ means that only strong coupling produces reliable detection, consistent with the sharp onset at $\\alpha_c{\\approx}0.50$ where signal strength first exceeds this threshold.\nAt $T{=}20$, $\\beta_{50}$ drops to 0.9, predicting a left-shift of $\\alpha_c$ and broader detection coverage, as formalized in the detection boundary model (\\S\\ref{sec:theory}).\n\n\n\\section{Non-Stationarity Robustness Analysis}\n\\label{app:nonstationarity}\n\nWe assess PermG's size and power under controlled non-stationarity via Monte Carlo simulation, then compare to the empirical autocorrelation structure of our experimental series.\n\n\\paragraph{Simulation design.}\nWe generate bivariate AR(1) series with unidirectional coupling ($x \\to y$):\n$x_t = \\varphi x_{t-1} + \\varepsilon_t^x$, $y_t = \\varphi y_{t-1} + \\beta x_{t-1} + \\varepsilon_t^y$,\nwith $T{=}11$, 1{,}000 replications, and 500 permutations per replication.\nSize is evaluated under $H_0{:}\\;\\beta{=}0$; power under $H_1{:}\\;\\beta{=}0.6$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Size (FPR at $\\beta{=}0$) and power ($\\beta{=}0.6$) under stationary and non-stationary AR(1) DGP ($T{=}11$, 1{,}000 reps, 500 perms). First-differencing maintains nominal size across all $\\varphi$; PermG FPR inflates to ${\\sim}10\\%$ at $\\varphi{\\geq}0.95$.}\n\\label{tab:nonstationarity_sim}\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{3}{c}{Size (\\%, $\\beta{=}0$)} & \\multicolumn{3}{c}{Power (\\%, $\\beta{=}0.6$)} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\n$\\varphi$ & Raw GC & First-Diff & PermG & Raw GC & First-Diff & PermG \\\\\n\\midrule\n0.50 & 6.4 & 6.6 & 6.8 & 37.7 & 17.7 & 36.8 \\\\\n0.95 & 10.0 & 5.9 & 9.5 & 44.3 & 28.7 & 41.5 \\\\\n0.99 & 11.2 & 4.2 & 10.7 & 46.4 & 24.6 & 41.7 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt $\\varphi{=}0.50$ (stationary), all three methods achieve near-nominal size ($6.4$--$6.8\\%$ vs.\\ $5\\%$ nominal).\nUnder strong non-stationarity ($\\varphi{\\geq}0.95$), PermG FPR inflates to ${\\sim}10\\%$ because permutation shuffling destroys temporal autocorrelation, shifting the null distribution.\nFirst-differencing maintains proper size ($4.2$--$6.6\\%$) at the cost of reduced power ($17.7$--$28.7\\%$ vs.\\ PermG's $36.8$--$41.7\\%$).\nOur pipeline applies first-differencing \\emph{before} permutation testing, combining PermG's power advantage with differencing's size control; the simulation isolates each component to characterize the tradeoff.\n\n\\paragraph{Empirical autocorrelation.}\nTable~\\ref{tab:empirical_ar1} reports AR(1) coefficients from seven experimental conditions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Empirical AR(1) coefficients for token entropy (te) and distinct-1 (d1), raw and first-differenced series. High raw $\\varphi$ in d1 reflects deterministic iterative-training decline, not stochastic AR persistence; first-differencing reduces $\\varphi$ to $< 0.44$.}\n\\label{tab:empirical_ar1}\n\\begin{tabular}{llrcccc}\n\\toprule\nExperiment & $\\alpha$ & $T$ & te $\\varphi_{\\text{raw}}$ & d1 $\\varphi_{\\text{raw}}$ & te $\\varphi_{\\text{diff}}$ & d1 $\\varphi_{\\text{diff}}$ \\\\\n\\midrule\na000\\_s42 & 0.00 & 10 & $-0.51$ & $0.86$ & $-0.57$ & $-0.14$ \\\\\na025\\_s42 & 0.25 & 10 & $-0.34$ & $0.95$ & $-0.45$ & $0.19$ \\\\\na050\\_s42 & 0.50 & 10 & $-0.28$ & $0.87$ & $0.31$ & $0.10$ \\\\\na075\\_s42 & 0.75 & 10 & $0.14$ & $0.91$ & $0.88$ & $0.24$ \\\\\na100\\_s42 & 1.00 & 10 & $1.00$ & $0.89$ & $0.98$ & $0.18$ \\\\\nt20\\_a050 & 0.50 & 20 & $-0.10$ & $0.97$ & $-0.25$ & $0.44$ \\\\\nt20\\_a100 & 1.00 & 20 & $0.98$ & $0.81$ & $0.87$ & $0.14$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Adequacy argument.}\nUnder null conditions ($\\alpha{=}0.0$), where FPR is defined, token entropy exhibits $\\varphi{=}-0.51$ (anti-correlated, far from the $\\varphi{\\geq}0.95$ regime where simulation reveals FPR inflation); at $\\varphi{=}0.50$, PermG FPR is $6.8\\%$, near nominal.\nThe high raw $\\varphi$ in distinct-1 ($0.81$--$0.97$ across all $\\alpha$ including null) reflects deterministic iterative-training diversity decline---a monotonic trend driven by the training protocol---not stochastic AR persistence.\nDeterministic trends differ fundamentally from the stochastic AR(1) DGP: they produce predictable trajectories rather than autocorrelated noise, and first-differencing effectively removes them (first-differenced distinct-1 $\\varphi$ ranges $-0.14$ to $0.44$, mean ${\\sim}0.17$).\nOur empirical FPR of 4/36 (11.1\\%) across six null seeds---the lowest among directional methods---confirms adequate size control in our experimental setting; all four false positives occur in token\\_entropy$\\to$distinct pairs in the forward direction, suggesting a structural pattern rather than random Type~I error.\nWe note that $T{=}10$ (11 data points) yields high-variance AR(1) estimates; the cross-experiment pattern is more informative than individual values.\n\n\\paragraph{DGP limitation.}\nThe bivariate AR(1) with linear coupling is a simplification; actual iterative training involves nonlinear dynamics (mode amplification, threshold-dependent diversity loss).\nThese simulation results characterize PermG's behavior under controlled conditions, not exact calibration for the experimental setting; they provide a lower bound on size control because the linear DGP represents a worst case for permutation-based tests (smooth autocorrelation that permutation destroys).\n\n\n\\section{Shapley Value Analysis}\n\\label{app:shapley}\n\nWe quantify each method's marginal contribution to the MMCT ensemble using Shapley values~\\cite{shapley1953value}, computed via exact enumeration over all $2^5{=}32$ coalitions of the five detection methods.\nFor a coalition $S \\subseteq \\{m_1, \\ldots, m_5\\}$, we define two performance metrics: the false positive rate FPR($S$), computed from 6 null experiments ($\\alpha{=}0.0$, seeds 45--50; 36 null pairs on the 6-pair basis excluding mauve), and the false negative rate FNR($S$), computed from 45 signal experiments across all non-null $\\alpha$ levels (270 signal pairs for the 6-pair variant excluding mauve).\nThe Shapley value $\\phi_k$ for method $m_k$ is the weighted average of its marginal contribution across all coalitions; positive FPR-Shapley indicates the method \\emph{increases} false positives, while negative FNR-Shapley indicates it \\emph{reduces} false negatives.\nThe combined Shapley value $\\phi_k^{\\text{comb}} = \\phi_k^{\\text{FPR}} + \\phi_k^{\\text{FNR}}$ balances both error types, with more negative values indicating greater net benefit.\n\nTable~\\ref{tab:shapley_6pair} reports the 6-pair analysis (excluding mauve).\nDiffXCorr achieves the lowest (best) combined Shapley ($-0.299$), driven by near-zero FPR contribution ($+0.007$) and strong FNR reduction ($-0.306$); however, DiffXCorr cannot separate forward from reverse causation (Table~\\ref{tab:null_fpr_methods}).\nAmong directional methods, PermG ranks best ($-0.141$ combined), with a modest FPR contribution ($+0.039$, reflecting 4/36 null false positives) offset by substantial FNR reduction ($-0.180$).\nNaive cross-correlation is the worst contributor ($+0.190$), with its massive FPR Shapley ($+0.609$) overwhelming its FNR benefit ($-0.419$).\nThreshold onset contributes almost nothing useful ($+0.084$ combined; FPR $+0.111$, FNR $-0.027$), confirming the near-zero detection power reported in Table~\\ref{tab:method_comparison}.\nFigure~\\ref{fig:shapley} visualizes the decomposition.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Shapley value decomposition (6-pair, mauve excluded). FPR-Shapley computed from 6 null seeds (36 pairs); FNR-Shapley from 45 signal experiments (270 pairs). Combined = FPR + FNR (more negative = better). $2^5{=}32$ coalitions, exact enumeration.}\n\\label{tab:shapley_6pair}\n\\begin{tabular}{lccc}\n\\toprule\nMethod & $\\phi^{\\text{FPR}}$ & $\\phi^{\\text{FNR}}$ & $\\phi^{\\text{comb}}$ \\\\\n\\midrule\nNaive XCorr          & $+0.609$ & $-0.419$ & $+0.190$ \\\\\n\\textbf{Diff.\\ XCorr}& $\\mathbf{+0.007}$ & $\\mathbf{-0.306}$ & $\\mathbf{-0.299}$ \\\\\nThreshold ($3\\sigma$) & $+0.111$ & $-0.027$ & $+0.084$ \\\\\nPerm.\\ Granger       & $+0.039$ & $-0.180$ & $-0.141$ \\\\\nToda--Yamamoto       & $+0.150$ & $-0.069$ & $+0.082$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/shapley_method_contribution.pdf}\n% TODO-D219: regenerate figure and update caption after Shapley recomputation with 6-seed data\n\\caption{Shapley value decomposition of each method's marginal contribution to FPR (positive bars) and FNR (negative bars). PermG is the only method with zero FPR contribution; naive cross-correlation's FPR dominates its FNR benefit.}\n\\label{fig:shapley}\n\\end{figure*}\n\nThe 8-pair variant (including mauve) yields qualitatively identical rankings: PermG remains the best contributor ($\\phi^{\\text{comb}}{=}-0.152$), naive cross-correlation the worst ($+0.170$), and threshold onset near-zero ($+0.063$).\n\n\\paragraph{FDR correction scope.}\nThis analysis applies BH-corrected significance (\\texttt{significant\\_fdr}) uniformly across all five methods, including naive cross-correlation and Toda--Yamamoto.\nIn contrast, the per-method dose-response profiles (Table~\\ref{tab:dose_response_full}) use uncorrected significance for naive cross-correlation, threshold onset, and Toda--Yamamoto because FDR-corrected fields are not available in the per-experiment pipeline output for these methods.\nThe Shapley analysis recomputes significance from raw $p$-values with BH correction applied post hoc, ensuring a fair comparison across methods within the coalition framework.\n\n\n\\section{MMCT Weight Robustness Ablation}\n\\label{app:weight_robustness}\n\nThe detection results reported in the main text use equal-weight majority voting ($K{\\geq}3$ of 5 methods, each contributing at most one vote per pair); PermG contributes at most $1/5 = 20\\%$ of the consensus weight.\nFPR-inverse weighting is used \\emph{only} in the exploratory method ranking below, not in the detection results.\nTo verify that PermG's top ranking is not an artifact of the FPR-inverse weighting scheme, we recompute Shapley values under four weight specifications (Table~\\ref{tab:weight_robustness}).\nEqual weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first ($\\phi^{\\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.\nUnder cap-5, the margin widens to 0.043 as the FPR penalty begins to differentiate high-FPR methods.\nCap-10 and original cap-100 yield identical Shapley values because the consensus threshold ($K{\\geq}3$) is determined by the three smallest method weights ($w_{\\text{naive}}{+}w_{\\text{diff}}{+}w_{\\text{thresh}} = 7.76$), which are invariant to further increases in the PermG or TY cap; this saturation confirms that the original $w{=}100$ does not artificially inflate PermG's contribution.\n% TODO-D219: recompute weight robustness table with 6-seed data; PermG φ^FPR will be >0\nAcross all schemes, PermG's advantage derives from the same structural property: zero FPR ($\\phi^{\\text{FPR}}{=}0$) combined with moderate FNR reduction ($\\phi^{\\text{FNR}}{=}-0.152$ to $-0.426$).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{MMCT weight robustness: PermG combined Shapley under four weighting schemes. PermG ranks first in all cases. Gap = $|\\phi^{\\text{comb}}_{\\text{PermG}} - \\phi^{\\text{comb}}_{\\text{runner-up}}|$. 48 experiments (3 null + 45 signal), exact Shapley enumeration ($2^5{=}32$ coalitions).}\n\\label{tab:weight_robustness}\n\\begin{tabular}{lrcrc}\n\\toprule\nScheme & $w_{\\text{PermG}}$ & $\\phi^{\\text{comb}}_{\\text{PermG}}$ & Runner-up & Gap \\\\\n\\midrule\nEqual ($w{=}1$)     & 1   & $-0.152$ & NaiveXCorr ($-0.137$) & 0.015 \\\\\nCap-5               & 5   & $-0.165$ & NaiveXCorr ($-0.123$) & 0.043 \\\\\nCap-10              & 10  & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\nFPR-inv.\\ (cap-100) & 100 & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{PermG FPR Independence Analysis}\n\\label{app:fpr_independence}\n\nTable~\\ref{tab:null_fpr_methods} reports null-control FPR for all five detection methods across six seeds ($6 \\times 6 = 36$ pairs, 6-pair basis excluding mauve).\nUnder identical BH-FDR correction ($q{=}0.05$), DiffXCorr achieves the lowest FPR (1/36, 2.8\\%) but lacks directional separation; PermG (4/36, 11.1\\%) is the lowest among directional methods.\nAll four PermG false positives occur in token\\_entropy$\\to$distinct pairs (seeds~45 and 50, forward direction only), suggesting a structural pattern concentrated in a single canary--downstream pair type.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Null-control FPR by method ($\\alpha{=}0.0$, 6~seeds 45--50, 6~pairs each). All p-value--based methods (DiffXCorr, PermG, TY) report BH-FDR--corrected rejections at $q{=}0.05$ for fair comparison. Threshold uses a deterministic $3\\sigma$ criterion; NaiveXCorr uses uncorrected correlation significance.}\n\\label{tab:null_fpr_methods}\n\\begin{tabular}{llrr}\n\\toprule\nMethod & Criterion & Rejections (/36) & FPR (\\%) \\\\\n\\midrule\nDiff.\\ XCorr$^\\dagger$ & BH-FDR & 1 & 2.8 \\\\\n\\textbf{Perm.\\ Granger} & \\textbf{BH-FDR} & \\textbf{4} & \\textbf{11.1} \\\\\nThreshold & $3\\sigma$ (det.) & 10 & 27.8 \\\\\nToda--Yamamoto & BH-FDR & 14 & 38.9 \\\\\nNaive XCorr & uncorr. & 33 & 91.7 \\\\\n\\bottomrule\n\\multicolumn{4}{l}{\\footnotesize $^\\dagger$Bidirectional; cannot separate forward from reverse.} \\\\\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cluster adjustment.}\nThe 36 null-control pairs are nested within 6~seeds (6~pairs per seed), introducing within-seed correlation.\nWithin-seed ICC${=}0.14$ yields an effective sample size $N_{\\text{eff}} \\approx 21$ (from $N_{\\text{eff}} = N / [1 + (m-1) \\cdot \\text{ICC}]$ where $N{=}36$, $m{=}6$).\nUnder the Clopper--Pearson exact method with $N_{\\text{eff}}{=}21$ and 4 successes (scaled), the cluster-adjusted 95\\% CI is $[1.2\\%, 30.4\\%]$, compared to $[3.1\\%, 26.1\\%]$ under independence ($N{=}36$).\nThe lower ICC compared to the 3-seed pilot ($0.14$ vs.\\ $0.34$) reflects greater between-seed consistency with six independent replications.\n\n\\paragraph{Direction filtering.}\nForward-direction filtering (retaining only pairs with peak lag${<}0$ for cross-correlation methods) reduces null-control $K{\\geq}3$ false positives.\nUnder the 6-seed, 6-pair basis, $K{\\geq}3$ consensus with filtering produces 6/36 false positives (16.7\\%; detail below); the 3-seed pilot underestimated this rate (0/8).\nDetection at $\\alpha{\\geq}0.50$ is unaffected: $K{\\geq}3$ counts are identical with and without direction filtering at all signal levels.\n\n\\paragraph{$K{\\geq}3$ false positive detail.}\nUnder the 6-pair basis (6~seeds, 36~pairs), $K{\\geq}3$ consensus produces 6 false positives (FPR${=}16.7\\%$).\nOf these, 4 are driven by naive cross-correlation, threshold onset, and Toda--Yamamoto (PermG does \\emph{not} vote); the remaining 2 (seeds~45 and 50, te$\\to$distinct) include PermG in the consensus.\nPermG thus contributes to only 2 of 6 consensus false positives, confirming that most $K{\\geq}3$ FPR is driven by the high-FPR methods (naive, threshold, TY).\n\n\\paragraph{Sensitivity to FPR assumption.}\nEven under the conservative upper bound of the cluster-adjusted CI (30.4\\%), PermG remains the lowest-FPR directional method: DiffXCorr achieves a lower FPR under identical BH-FDR correction (2.8\\%) but lacks forward/reverse separation; the next directional method (threshold onset) has 27.8\\% and Toda--Yamamoto 38.9\\%.\nOur primary results rely on equal-weight $K{\\geq}3$ majority voting, where each method contributes exactly one vote regardless of its FPR---this mechanism is completely unaffected by any FPR assumption.\nFor the exploratory FPR-inverse weighting, PermG's weight ($w{=}1/0.111{=}9.0$) exceeds all directional alternatives (threshold: 3.6, TY: 2.6, naive: 1.1); DiffXCorr ($w{=}1/0.028{=}35.7$) receives a higher weight but lacks directional separation, preserving PermG's rank among directional methods.\nThe insensitivity of both the voting mechanism and the method ranking to the upper CI bound provides evidence that the MMCT conclusions are robust to uncertainty in PermG's Type~I error rate.\n\n\\section{Sigmoid Transition Shape}\n\\label{app:sigmoid_shape}\n\nSigmoid regression on the original 13-point $T{=}10$ grid yields $\\alpha_c = 0.483 \\pm 0.006$ but $k = 478 \\pm 475$ ($\\mathrm{SE}(k) \\approx k$), indicating that the coarse grid cannot constrain the transition shape.\nDense $\\alpha$ sampling (17~values at $T{=}10$) resolves this ambiguity: formal likelihood-ratio testing strongly favors a smooth sigmoid over a literal step function ($\\Delta\\mathrm{AIC}{=}-110$), with fitted steepness $k{=}15.7$ (95\\% CI $[9.4, 28.2]$).\nThe transition is steep but finite-width, not a literal discontinuity.\nThis observed steepness exceeds what smooth signal models predict: VAR(1) simulations under H0 (linear, $k{=}6.1$) and H0$'$ (concave, $k{=}4.9$) produce onset sigmoids with $k{=}4.9$--$6.1$ (\\S\\ref{app:power_sim}), yielding steepness ratios $k_{\\mathrm{obs}} / k_{\\mathrm{H0}} \\approx 2.6$--$3.2$ (CI lower bound ratio ${\\approx}2$).\nWe do not fit a combined $T{=}10 + T{=}20$ sigmoid because $\\alpha{=}0.45$ yields contradictory counts under the two sequence lengths (0/8 vs.\\ 5/8), reflecting genuine power dependence on $T$ rather than a single dose-response curve.\n\n\n\\section{Intervention Threshold Sensitivity}\n\\label{app:intervention_sensitivity}\n\n\\paragraph{Within-$\\alpha$ sensitivity at $\\alpha{=}1.0$.}\nTable~\\ref{tab:threshold_sensitivity} reports the predictive cessation outcome under five entropy-drop thresholds (5\\%--25\\%) at $\\alpha{=}1.0$ (Pythia-410M, seed~42).\nAll five thresholds produce identical outcomes: token entropy drops 40.7\\% at generation~1, far exceeding even the most conservative threshold (25\\%), so every threshold triggers at the same generation.\nThe intervention conclusion---peak perplexity 57.0, recovery in one generation, final perplexity 21.3---is invariant to threshold choice within this range.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Threshold sensitivity at $\\alpha{=}1.0$ (Pythia-410M, s42, fp32). All thresholds trigger at generation~1 (entropy drop 40.7\\%$\\gg$threshold), producing identical recovery trajectories.}\n\\label{tab:threshold_sensitivity}\n\\begin{tabular}{rccr}\n\\toprule\nThreshold & Trigger gen & Peak PPL & Final PPL \\\\\n\\midrule\n5\\%  & 1 & 56.99 & 21.29 \\\\\n10\\% & 1 & 56.99 & 21.29 \\\\\n15\\% & 1 & 56.99 & 21.29 \\\\\n20\\% & 1 & 56.99 & 21.29 \\\\\n25\\% & 1 & 56.99 & 21.29 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cross-$\\alpha$ operating band.}\nThe within-$\\alpha$ analysis establishes threshold invariance at $\\alpha{=}1.0$ but does not address whether thresholds generalize across contamination levels.\nWe examine observed entropy trajectories from the alpha sweep (not actual intervention experiments at $\\alpha{<}1.0$) to characterize the operating band.\nThe maximum entropy drop across 10 generations varies by contamination level: 7.5\\% at $\\alpha{=}0.0$ (fine-tuning drift only), 7.7\\% at $\\alpha{=}0.10$, 7.8\\% at $\\alpha{=}0.25$, 22.4\\% at $\\alpha{=}0.50$, 35.3\\% at $\\alpha{=}0.75$, and 62.1\\% at $\\alpha{=}1.0$.\nThresholds below 7.5\\% (e.g., 5\\%) trigger on clean training data---a false alarm.\nThresholds above 22.4\\% (e.g., 25\\%) miss $\\alpha{=}0.50$, the lowest contamination level with meaningful entropy signal.\nThe safe operating band is therefore $[10\\%, 22\\%]$: any threshold in this range produces zero false alarms on $\\alpha{=}0.0$ while detecting contamination at $\\alpha{\\geq}0.50$.\nThe reported 15\\% threshold sits near the center of this band.\nThis analysis is based on entropy trajectories from non-intervention training runs; whether actual intervention at $\\alpha{<}1.0$ would produce the same triggering behavior remains unvalidated.\n\n\n\\section{Channel Effect Size Analysis}\n\\label{app:channel_effect_size}\n\nFirst-differencing eliminates all canary$\\to$perplexity Granger associations while preserving canary$\\to$diversity leads (\\S\\ref{sec:regime}).\nWe present three lines of evidence that this asymmetry reflects a genuine temporal structure difference rather than selective power loss from differencing.\n\n\\paragraph{Correlation retention parity.}\nFirst-differencing retains comparable correlation magnitude for both channel types (Table~\\ref{tab:channel_retention}).\nDiversity channels ($n{=}243$ pairs across all non-null experiments) retain a median $|r|$ of 0.952 after differencing, while perplexity channels ($n{=}8$ pairs; limited sample) retain 1.00.\nThis parity rules out a blanket power-loss explanation: if differencing selectively destroyed perplexity signal, $|r|$ retention would be substantially lower for perplexity than for diversity.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{First-differencing effect by channel type. $|r|$ retention = diff $|r|$ / naive $|r|$. Despite comparable $|r|$ retention, Granger $F$ differs by an order of magnitude. Perplexity channel has limited sample ($n{=}8$); all paired comparisons are from bf16 experiments.}\n\\label{tab:channel_retention}\n\\begin{tabular}{lrccrc}\n\\toprule\nChannel & $n$ & Naive $|r|$ & Diff $|r|$ & Retention & Med.\\ $F$ \\\\\n\\midrule\nDiversity   & 243 & 0.943 & 0.921 & 0.952 & 67.8 \\\\\nPerplexity  & 8   & 0.924 & 0.900 & 1.002 & 11.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Granger $F$-statistic asymmetry.}\nWithin matched experiments (same model, seed, $\\alpha$, precision), the Granger $F$-statistic is $20$--$28{\\times}$ higher for diversity than perplexity channels.\nAt $\\alpha{=}0.60$ (s42, bf16): diversity mean $F{=}229.4$ versus perplexity mean $F{=}8.3$ (ratio $27.8{\\times}$).\nAt $\\alpha{=}1.0$ reactive (s43, bf16): diversity mean $F{=}236.4$ versus perplexity mean $F{=}11.5$ (ratio $20.6{\\times}$).\nSince $|r|$ retention is comparable across channels, this $F$-statistic gap cannot be attributed to differencing-induced signal loss; it must reflect a difference in the temporal structure that Granger tests evaluate.\n\n\\paragraph{Temporal structure: lagged vs.\\ contemporaneous.}\nThe lag distribution of peak differenced cross-correlations reveals the structural difference.\nFor diversity channels, 81\\% of peak correlations occur at canary-leading lags (lag${<}0$), with a median lag of $-1$ generation---consistent with the one-generation temporal precedence visible in Figure~\\ref{fig:metric_trajectory}.\nFor perplexity channels, 50\\% of peak correlations occur at lag${=}0$ (contemporaneous co-movement), with a median lag of $0$.\nGranger precedence tests lagged predictive improvement; contemporaneous co-movement produces low $F$-statistics regardless of signal magnitude, which is the correct behavior for a test designed to detect temporal precedence.\nThe perplexity channel sample is limited ($n{=}8$ pairs from bf16 experiments), and these lag distributions should not be generalized to fp32 conditions without further validation.\n\n\n\\section{Mutual Information Analysis}\n\\label{app:mi_analysis}\n\nWe estimate the Gaussian mutual information lower bound between token entropy (canary) and each diversity metric across contamination levels, using $T{=}11$ data points per series ($T{=}10$ for two conditions).\nThe Gaussian estimator $\\hat{I}_G = -\\frac{1}{2}\\log_2(1 - r^2)$, where $r$ is the Pearson correlation, provides a conservative lower bound on MI; we do not report KSG nonparametric estimates due to uncorrected positive bias at $T{=}11$.\nThe $\\alpha{=}0.05$ data point is excluded because it uses an experiment excluded from the dose-response analysis.\n\nTable~\\ref{tab:mi_bounds} reports the mean Gaussian MI across the three distinct-$n$ metrics for each $\\alpha$ level.\nMI follows a V-shaped curve: it drops from 0.112~bits at $\\alpha{=}0.10$ to a minimum of 0.010~bits at $\\alpha{=}0.25$, then rises monotonically to 0.270~bits at $\\alpha{=}0.75$.\nMI remains positive throughout the blind zone ($\\alpha \\leq 0.45$; range 0.010--0.141~bits), confirming that canary--diversity coupling exists below the detection threshold but falls below PermG's statistical power floor at $T{=}10$.\nThere is no discontinuity at $\\alpha_c \\approx 0.50$: the detection onset reflects power accumulation, not an abrupt change in information coupling.\nBootstrap 95\\% CIs span 1--3 orders of magnitude at $T{=}11$, so individual point estimates should be interpreted cautiously.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Gaussian MI lower bound (bits) between token entropy and distinct-$n$ diversity metrics ($T{=}11$, Pythia-410M, fp32). Mean across distinct-1/2/3; $\\alpha{=}0.05$ excluded (see text). CIs omitted due to width at $T{=}11$.}\n\\label{tab:mi_bounds}\n\\begin{tabular}{rrc}\n\\toprule\n$\\alpha$ & Seeds & MI (bits) \\\\\n\\midrule\n0.10 & 2 & 0.112 \\\\\n0.25 & 3 & 0.010 \\\\\n0.30 & 1 & 0.062 \\\\\n0.35 & 1 & 0.098 \\\\\n0.40 & 1 & 0.119 \\\\\n0.45 & 2 & 0.141 \\\\\n0.50 & 3 & 0.107 \\\\\n0.60 & 2 & 0.209 \\\\\n0.75 & 1 & 0.270 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Moment Cascade Analysis}\n\\label{app:moment_cascade}\n\nWe analyze the temporal ordering of metric degradation onset across 6 WikiText seed${\\times}\\alpha$ conditions (2 seeds $\\times$ 3 non-trivial $\\alpha$ levels each) to test whether token entropy consistently degrades before diversity metrics.\nOnset is defined as the first generation where a metric's cumulative change exceeds 5\\% of its generation-0 value.\n\nTable~\\ref{tab:moment_cascade} reports the onset generation for each metric across conditions.\nToken entropy reaches onset at generation~1 in all 6 conditions; distinct-$n$ metrics reach onset at generation~2 in all 18 pairwise comparisons (6 conditions $\\times$ 3 distinct-$n$ metrics).\nAcross these 18 comparisons, entropy degrades first in 16 cases (Kendall $\\tau{=}0.337$, consistent with a weak but reliable temporal ordering).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Degradation onset generation (5\\% threshold) by metric and condition (Pythia-410M, WikiText, fp32). Token entropy reaches onset at generation~1 in all non-null conditions; distinct-$n$ metrics follow at generation~2.}\n\\label{tab:moment_cascade}\n\\begin{tabular}{llcccccc}\n\\toprule\nSeed & $\\alpha$ & Entropy & Dist-1 & Dist-2 & Dist-3 & ECE & PPL \\\\\n\\midrule\n42 & 0.10 & 1 & 2 & 2 & 2 & 2 & --- \\\\\n42 & 0.50 & 1 & 2 & 2 & 2 & 1 & 4 \\\\\n42 & 0.75 & 1 & 2 & 2 & 2 & 1 & 1 \\\\\n43 & 0.25 & 1 & 2 & 2 & 2 & 4 & --- \\\\\n43 & 0.50 & 1 & 2 & 2 & 2 & 1 & 4 \\\\\n43 & 0.75 & 1 & 2 & 2 & 2 & 1 & 1 \\\\\n\\bottomrule\n\\multicolumn{8}{l}{\\footnotesize ---: onset not reached within $T{=}10$ generations.} \\\\\n\\end{tabular}\n\\end{table}\n\nThe cascade ordering provides evidence for the canary mechanism independent of Granger-type tests: it does not depend on first-differencing, lag selection, or the permutation null distribution.\nECE shows onset at generation~1 at $\\alpha{\\geq}0.50$ (both seeds), consistent with its role as a secondary canary metric.\nAt low contamination ($\\alpha{=}0.10$ and $\\alpha{=}0.25$), perplexity never reaches the 5\\% onset threshold within $T{=}10$ generations, while entropy already shows generation-1 onset---consistent with entropy's higher sensitivity to distributional shifts.\n\n\n\\section{Cascade Ordering Theory: Proofs}\n\\label{app:cascade_theory}\n\nThis section provides the full proofs for Proposition~\\ref{thm:entropy_leads} and Proposition~\\ref{prop:div_lag} from \\S\\ref{sec:cascade}, plus supporting results.\n\n\\begin{assumption}[Mode Amplification]\\label{ass:mode_amp}\nThe training map $\\mathcal{T}$ redistributes probability mass from low-probability to high-probability tokens: there exists a threshold $\\bar{p}$ such that $\\mathcal{T}(p)_i > p_i \\Rightarrow p_i \\geq \\bar{p}$ and $\\mathcal{T}(p)_j < p_j \\Rightarrow p_j \\leq \\bar{p}$.\n\\end{assumption}\n\nThis captures the standard finite-capacity approximation effect: MLE on finite samples from a peaked distribution amplifies modes and suppresses the tail~\\cite{shumailov2024curse,dohmatob2024tale}.\n\n\\begin{proposition}[Entropy is a first-order indicator]\\label{prop:entropy_first}\nLet $p \\in \\Delta^{V-1}$ and $\\delta = \\alpha(\\mathcal{T}(p) - p)$ be a mode-amplifying perturbation with $\\sum_i \\delta_i = 0$. Then $\\Delta H = H(p+\\delta) - H(p) = -\\sum_i \\delta_i \\log p_i + O(\\|\\delta\\|^2) < 0$.\n\\end{proposition}\n\n\\begin{proof}\nTaylor-expanding $H$ around $p$:\n$H(p+\\delta) = H(p) - \\sum_i \\delta_i \\log p_i - \\sum_i \\delta_i - \\frac{1}{2}\\sum_i \\delta_i^2/p_i + O(\\|\\delta\\|^3)$.\nSince $\\sum_i \\delta_i = 0$: $\\Delta H = -\\sum_i \\delta_i \\log p_i - \\frac{1}{2}\\sum_i \\delta_i^2/p_i + O(\\|\\delta\\|^3)$.\nUnder mode amplification, tokens gaining mass ($\\delta_i > 0$) have $p_i \\geq \\bar{p}$ (hence $\\log p_i \\geq \\log \\bar{p}$) and tokens losing mass ($\\delta_j < 0$) have $p_j \\leq \\bar{p}$ (hence $\\log p_j \\leq \\log \\bar{p}$).\nWriting $m = \\sum_{i:\\delta_i > 0} \\delta_i$: $-\\sum_i \\delta_i \\log p_i = -m[\\overline{\\log p}^{+} - \\overline{\\log p}^{-}] < 0$, where $\\overline{\\log p}^{\\pm}$ are the $|\\delta|$-weighted means over gaining/losing tokens.\nThe second-order Fisher information term $-\\frac{1}{2}\\sum_i \\delta_i^2/p_i$ is always negative, reinforcing the decrease.\n\\end{proof}\n\n\\begin{proposition}[Diversity is a threshold indicator]\\label{prop:div_threshold}\nDefine the $\\epsilon$-effective support $S_\\epsilon(p) = |\\{i \\in [V]: p_i > \\epsilon\\}|$, where $\\epsilon \\approx c/N$ is the generation threshold for sample size $N$.\nUnder the same perturbation $\\delta$: $\\Delta S_\\epsilon = -|\\{i: p_i > \\epsilon \\text{ and } p_i + \\delta_i \\leq \\epsilon\\}|$.\nThis equals zero whenever $\\|\\delta\\|_\\infty < \\gamma(p,\\epsilon) := \\min_{i: p_i > \\epsilon}(p_i - \\epsilon)$.\n\\end{proposition}\n\n\\begin{proof}\nToken $i$ exits the effective support iff $p_i > \\epsilon$ and $p_i + \\delta_i \\leq \\epsilon$, requiring $|\\delta_i| \\geq p_i - \\epsilon$.\nIf $\\|\\delta\\|_\\infty < \\gamma$, no token satisfies this condition.\n\\end{proof}\n\n\\paragraph{Proof of Proposition~\\ref{thm:entropy_leads}.}\n\\emph{Part (a):} Take any mode-amplifying $\\delta$ with $\\|\\delta\\|_\\infty < \\gamma(p,\\epsilon)$.\nBy Proposition~\\ref{prop:div_threshold}, $\\Delta S_\\epsilon = 0$.\nBy Proposition~\\ref{prop:entropy_first}, $\\Delta H < 0$.\nSuch $\\delta$ exists for all $\\alpha < \\gamma / \\max_i |\\mathcal{T}(p)_i - p_i|$.\n\\emph{Part (b):} If $\\Delta S_\\epsilon < 0$, some token $k$ has $p_k > \\epsilon$ but $p_k + \\delta_k \\leq \\epsilon$, so $\\delta_k < 0$.\nUnder mode amplification, this implies $p_k \\leq \\bar{p}$; the total mass transferred to high-probability tokens ensures $\\overline{\\log p}^+ > \\overline{\\log p}^-$.\nBy Proposition~\\ref{prop:entropy_first}, $\\Delta H < 0$. $\\square$\n\n\\paragraph{Proof of Proposition~\\ref{prop:div_lag}.}\nBy the margin condition, at every generation $s \\leq t_H$ the perturbation norm $\\alpha\\|\\mathcal{T}(p_s) - p_s\\|_\\infty$ is less than $\\gamma(p_s, \\epsilon)$.\nBy Proposition~\\ref{prop:div_threshold}, no token exits the effective support at any $s \\leq t_H$, so $\\Delta S_\\epsilon = 0$ for all $s \\leq t_H$.\nSince time is discrete, $t_D \\geq t_H + 1$. $\\square$\n\n\\paragraph{ECE co-movement (qualitative argument).}\nUnder conditional mode amplification (peakier $q_\\theta(\\cdot|x)$ at each generation), per-token conditional entropy $h(x) = H(q_\\theta(\\cdot|x))$ decreases while confidence $c(x) = \\max_y q_\\theta(y|x) \\geq \\exp(-h(x))$ increases.\nAveraging: $\\bar{H}_t$ decreases, $C_t$ increases.\nWith accuracy approximately stationary in early collapse ($A_t \\approx A_0$), $\\Delta\\mathrm{ECE} \\approx \\Delta C_t > 0$ whenever $\\Delta\\bar{H}_t < 0$.\nThis argument establishes the direction of co-movement; the quantitative relationship depends on distribution geometry.\n$\\bar{H}_t$ denotes mean conditional entropy $\\mathbb{E}_{x \\sim p_{\\text{eval}}}[h(x)]$, which differs from the marginal entropy $H_t = -\\sum_i p_t(i)\\log p_t(i)$ used in Proposition~\\ref{thm:entropy_leads}; under mode amplification, both decrease monotonically, so the cascade ordering is consistent across both formulations.\n\n\\paragraph{MAUVE ordering (conjecture).}\nMAUVE measures divergence in a discretized embedding space via $k$-means quantization.\nMAUVE onset requires token-level shifts (detected by entropy) to propagate through $n$-gram distributions (detected by distinct-$n$) to aggregate embedding distributions.\nEmpirically, MAUVE onset lags diversity by 0--1 generations on WikiText; however, on C4, MAUVE onset occurs at generation~1 (simultaneous with entropy), suggesting this lag is corpus-dependent.\n\n\\paragraph{Empirical support.}\nAmong 15 experiments at $\\alpha \\geq 0.30$ (where entropy perturbation exceeds the detection threshold), cascade ordering $t_H \\leq t_D$ holds in 14/15 cases (GPT-2-medium s43 fp32 exhibits bidirectional Granger significance).\nTable~\\ref{tab:cascade_onset} reports onset generations for representative conditions, showing uniform Phase~1/2/3 ordering.\nFive low-$\\alpha$ experiments ($\\alpha \\leq 0.25$) show entropy perturbation below the detection threshold (gen-1 deviation $<2\\sigma$); cascade ordering is neither confirmed nor refuted in this regime.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cascade onset generations (5\\% threshold) for representative experiments (Pythia-410M, WikiText, fp32). Phase~1: entropy and ECE ($t_H$, $t_{\\mathrm{ECE}}$); Phase~2: diversity ($t_D$, min over distinct-$n$); Phase~3: MAUVE ($t_M$). All conditions confirm the predicted ordering $t_H = t_{\\mathrm{ECE}} \\leq t_D \\leq t_M$.}\n\\label{tab:cascade_onset}\n\\begin{tabular}{llcccc}\n\\toprule\nSeed & $\\alpha$ & $t_H$ & $t_{\\mathrm{ECE}}$ & $t_D$ & $t_M$ \\\\\n\\midrule\n42 & 0.50 & 1 & 1 & 2 & 3 \\\\\n43 & 0.50 & 1 & 1 & 2 & 2 \\\\\n42 & 0.75 & 1 & 1 & 2 & 3 \\\\\n43 & 0.75 & 1 & 1 & 2 & 2 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\phantomsection\\label{app:alpha_c_proof}\n\\paragraph{Proof of Proposition~\\ref{prop:phase-boundary}.}\nAt the detection threshold, $\\mathrm{Power}(\\alpha_c, T) = \\pi^*$.\nSince $\\alpha_c$ lies below the non-monotonic dip region ($\\alpha_c < 0.55$), the signal model applies directly.\nFrom the power function $\\mathrm{Power} = \\Phi(S(\\alpha) \\cdot \\sqrt{T} / \\sigma)$, setting $S(\\alpha_c) \\cdot \\sqrt{T} / \\sigma = z^*$ and substituting the signal model $S(\\alpha) = c\\,\\alpha^\\beta$ yields $c\\,\\alpha_c^\\beta = z^* \\sigma / \\sqrt{T}$.\nSolving: $\\alpha_c(T) = (z^* \\sigma / c)^{1/\\beta} \\cdot T^{-1/(2\\beta)}$, giving the stated form with exponent $\\gamma = 1/(2\\beta)$.\n\n\\paragraph{Calibration and consistency.}\nCross-$T$ validation avoids the circularity of fitting theory to model-extrapolated points.\nWe fit $P(\\mathrm{det}|\\alpha,T) = \\Phi(A \\cdot \\alpha^\\beta \\cdot \\sqrt{T} - z_0)$ to training data at $T \\in \\{10, 20\\}$ via profile likelihood over $(\\beta, \\alpha_\\infty)$, with $\\alpha_\\infty{=}0$ emerging as the optimum.\nThe held-out test set ($T \\in \\{5, 15\\}$) yields MAE${=}0.106$ with 95\\% CI coverage $6/6$: the model correctly predicts all $0/8$ at $T{=}5$ and detection at $T{=}15$ (predicted $0.49$--$0.71$ vs.\\ observed $6/8{=}0.75$; under-prediction reflects the $P_{\\max}{=}0.75$ ceiling from MAUVE saturation, which is modeled separately).\nA linear signal model ($\\beta{=}1$, $\\gamma{=}0.5$) is rejected.\nThe sub-linear exponent $\\beta{=}0.24$ implies that doubling contamination increases signal by only $2^{0.24} \\approx 1.18\\times$ (18\\%); since $\\alpha_\\infty{\\approx}0$, any nonzero contamination produces signal, but detection requires sufficient $T$ to amplify it.\nAt $T{=}5$, $\\alpha_c \\geq 1.0$: no contamination level is detectable, consistent with the insufficient statistical power at very short observation windows.\n\n\\paragraph{Leave-one-$T$-out cross-validation.}\nWe evaluate model generalization via leave-one-$T$-out CV on the $5T \\times 3\\alpha$ grid (sync-dip $\\alpha{=}0.60$ excluded; 15 cells).\nFor each fold, one observation length is held out and the probit model $P = P_{\\max} \\cdot \\Phi(A \\cdot \\alpha^{0.24} \\cdot \\sqrt{T} - z_0)$ is refit on the remaining data.\nOverall MAE${=}0.037$ with 95\\% CI coverage $15/15$.\nWhen sync-dip cells are included (20 cells), MAE rises to $0.203$ (CI $16/20$), with the largest residuals at sync-dip cells (predicted $0.75$, observed $0/8$).\nThe profile likelihood over $\\beta$ yields MLE $\\hat{\\beta}{=}0.66$ (95\\% CI $[0.24, 0.78]$); the wide interval reflects a flat likelihood surface, indicating that $\\beta$ is not well-identified from these data.\nModel comparison (AIC, 15-cell grid excluding sync-dip): $M_1$ (linear boundary) $\\Delta\\mathrm{AIC}{=}0.0$; $M_2$ (power-probit) $\\Delta\\mathrm{AIC}{=}2.43$.\nIncluding sync-dip data reverses the ranking ($M_2$ $\\Delta\\mathrm{AIC}{=}0.0$, $M_1$ $\\Delta\\mathrm{AIC}{=}4.15$), because the probit model naturally accommodates the dip's dissolution at higher $T$ while linear models cannot.\n\n\\section{Power Simulation: Shape Comparison}\n\\label{app:power_sim}\n\nTo assess whether the observed steep detection onset could arise from smooth signal models, we simulate PermG detection under three null hypotheses (1{,}000 replications per cell, $n_{\\text{perm}}{=}1{,}000$, $n_{\\text{pairs}}{=}8$, BH-FDR $q{=}0.05$):\n\n\\begin{itemize}\n\\item \\textbf{H0} (linear): $S(\\alpha) = c \\cdot \\alpha$, calibrated so $S(1.0) = S_{\\max}$.\n\\item \\textbf{H0$'$} (concave): $S(\\alpha) = c \\cdot \\alpha^{0.5}$, sub-linear but smooth.\n\\item \\textbf{H1} (step): $S(\\alpha) = S_{\\max} \\cdot \\mathbf{1}[\\alpha > \\alpha_c(T)]$, binary activation.\n\\end{itemize}\n\n\\noindent\\textbf{Scaling exponents.}\nAll three models produce apparent onset scaling in $T$: H0 $\\gamma{=}0.85$, H0$'$ $\\gamma{=}1.87$, H1 $\\gamma{=}1.96$ (observed: $\\gamma{=}2.08$).\nH0$'$ produces $\\gamma$ within $0.21$ of the observed value, demonstrating that the scaling exponent alone cannot distinguish smooth from step-function boundaries.\n\n\\noindent\\textbf{Shape differences.}\nAt $T{=}10$, $\\alpha{=}0.45$: H0 predicts 27\\% detection rate, H0$'$ predicts 45\\%, H1 predicts 5.5\\%, observed $0/8$.\nAt $T{=}10$, $\\alpha{=}0.50$: H0 predicts 36\\%, H0$'$ predicts 48\\%, H1 predicts 4.6\\%, observed $6/8$ (75\\%).\nSmooth models produce onset ramps with $k{=}4.9$--$6.1$ (H0$'$: $k{=}4.93$, $R^2{=}0.9974$; H0: $k{=}6.14$, $R^2{=}0.9998$); the observed onset steepness ($k{=}15.7$) is ${\\approx}3{\\times}$ higher.\n\n\\noindent\\textbf{Metric-specific ceiling.}\nAt high $\\alpha$ (${\\geq}0.75$) with $T{\\geq}20$, H0 and H0$'$ (which simulate 8 equal-signal pairs) reach mean detection fractions of $0.79$--$0.98$ (${\\approx}6.3$--$7.8/8$), whereas observed counts never exceed $6/8$.\nThis gap reflects metric structure rather than signal saturation: the 2/8 non-detected pairs consistently involve MAUVE, whose floor saturation (\\S\\ref{sec:t20}) prevents Granger detection regardless of signal strength.\n\n\\section{T=20 Predict-then-Verify Comparison}\n\\label{app:t20_comparison}\n\nTable~\\ref{tab:t20_comparison} reports the predict-then-verify results for the $T{=}20$ extension experiments.\nPredictions are derived from the detection boundary model (\\S\\ref{sec:theory}): detected pairs at $T{=}10$ are predicted to remain detected (saturated $F$-statistics), and undetected pairs are predicted to remain undetected (structural nulls or non-monotonic dip).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{T=20 predict-then-verify comparison (Pythia-410M, seed~42, WikiText, fp32). Excluding $\\alpha{=}1.0$, two of four predictions fall within CI ($\\alpha{=}0.50$, $0.75$); boundary cases show systematic bias---$\\alpha{=}0.45$ falsifies the ceiling hypothesis (under-prediction), $\\alpha{=}0.60$ over-predicts under raw $p$-values (v1; matches under FDR v2, not pre-committed).}\n\\label{tab:t20_comparison}\n\\begin{tabular}{lcccc}\n\\toprule\n$\\alpha$ & $T{=}10$ & Predicted $T{=}20$ & Observed $T{=}20$ & Match \\\\\n\\midrule\n0.45 & 0/8 & 0/8 (ceiling) & 5/8 & $\\times$ \\\\\n0.50 & 6/8 & 6/8 (saturated) & 6/8 & \\checkmark \\\\\n0.60 & 0/8 & 3/8 (v1 raw)$^\\dagger$ & 0/8 & $\\times$ \\\\\n0.75 & 6/8 & 6/8 (saturated) & 6/8 & \\checkmark \\\\\n1.00 & 6/8 & 6/8 (saturated) & 6/8 & \\checkmark \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\footnotesize $^\\dagger$V2 (BH--FDR corrected, created 44\\,min pre-analysis, not git-committed) predicts 0/8, matching observation.} \\\\\n\\end{tabular}\n\\end{table}\n\nAt $\\alpha \\geq 0.50$, consistency across $T{=}10$ and $T{=}20$ supports the detection boundary prediction: PermG counts are determined by signal structure, not observation length.\nSix diversity-based pairs show $F{=}449$--$2947$ at $T{=}20$ (all $\\gg F_{\\text{crit}}$); two MAUVE-based pairs show $F{<}2$ regardless of $T$, driven by floor saturation ($\\mu{=}0.029$, 100\\% ${<}0.05$) rather than high variance (CV$_{\\text{MAUVE}}{=}0.089$ vs CV$_{\\text{distinct-1}}{=}0.139$); SNR: MAUVE $4.68$ vs diversity $6.40$--$8.20$ ($p{<}0.001$).\nThe sole exception is $\\alpha{=}0.45$ at $T{=}20$ (5/8), consistent with boundary proximity.\nAt $\\alpha{=}0.45$, the shift from 0/8 to 5/8 falsifies Model~A (ceiling: $\\alpha{=}0.45$ structurally undetectable) in favor of Model~B (power-limited: $\\sqrt{T}$ boost crosses the detection threshold), lowering $\\alpha_c$ below~0.45.\nThe $\\alpha{=}0.60$ non-monotonic dip persists at $T{=}20$ (s42: 0/8; s43: 3/8) but dissolves at $T{=}25$ (5/8), confirming that $\\sqrt{T}$ power scaling eventually overcomes the dip; alternative methods detect signal throughout (DiffXCorr 6/8, TY 5/8 at $T{=}20$).\nPermG directional selectivity is consistent across tested $T$ ($T{=}10$, $20$): forward 6/8 versus reverse 0/8 at $\\alpha \\in \\{0.50, 0.75, 1.0\\}$.\n\n\n\\subsection{Prediction Timeline}\n\\label{app:t20_prediction_timeline}\n\nTwo versions of the $T{=}20$ prediction file exist, reflecting an evolving statistical protocol:\n\n\\paragraph{V1 (git-committed, \\texttt{bad72cc}).} Predictions derived from $T{=}10$ PermG results using \\emph{raw} $p$-values. At $\\alpha{=}0.60$, v1 counted 3/8 pairs with raw $p{<}0.05$, predicting 3/8 detections at $T{=}20$. The observed result (0/8 FDR-significant) does not match.\n\n\\paragraph{V2 (pre-analysis, not committed).} A revised file incorporating BH--FDR correction at $q{=}0.05$, consistent with the correction applied throughout the paper. Under FDR, $\\alpha{=}0.60$ drops from 3/8 (raw) to 0/8, matching the observation. V2 was created 44 minutes before the formal $T{=}20$ analysis began (filesystem timestamp) but was not git-committed, and therefore lacks the cryptographic verifiability of v1.\n\n\\paragraph{Scoring.} Primary (v1, committed): 3/5 exact matches ($\\alpha \\in \\{0.50, 0.75, 1.0\\}$, all saturated regimes). Excluding $\\alpha{=}1.0$, two of four predictions fall within CI. Both boundary predictions miss: $\\alpha{=}0.45$ (predicted 0/8, observed 5/8) falsifies the ceiling hypothesis in favor of $\\sqrt{T}$ power scaling; $\\alpha{=}0.60$ (predicted 3/8, observed 0/8) over-estimates detection due to the non-monotonic dip. Sensitivity (v2, FDR-corrected): 4/5 ($\\alpha{=}0.60$ matches). The systematic conservative bias at $\\alpha{=}0.45$ is consistent with the $\\sqrt{T}$ power increase predicted by Proposition~\\ref{prop:phase-boundary}.\n\n\n\\phantomsection\\label{app:task_degradation}\n\\paragraph{Task degradation.}\n\nTable~\\ref{tab:task_degradation} reports end-of-training task performance (generation~10, Pythia-410M, seed~42, fp32) across contamination levels.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Task degradation across contamination levels (Pythia-410M, seed~42, fp32, generation~10). Perplexity evaluated on held-out WikiText-103.}\n\\label{tab:task_degradation}\n\\begin{tabular}{lcc}\n\\toprule\n$\\alpha$ & Perplexity & Next-token acc. \\\\\n\\midrule\nBaseline & 26.6 & 0.390 \\\\\n0.05 & 20.8 & 0.431 \\\\\n0.25 & 22.9 & 0.424 \\\\\n0.46 & 31.6 & 0.400 \\\\\n0.50 & 31.3 & 0.399 \\\\\n0.52 & 41.1 & 0.389 \\\\\n0.60 & 53.5 & 0.375 \\\\\n0.75 & 80.3 & 0.354 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt $\\alpha{=}0.05$, perplexity improves over the uncontaminated baseline (20.8 vs.\\ 26.6), consistent with a mild data augmentation effect.\nThe sharpest degradation occurs between $\\alpha{=}0.50$ and $0.52$ ($+31\\%$ perplexity), aligning with the PermG detection onset (\\S\\ref{sec:regime}).\n\n\\section{Cross-Architecture FPR Sensitivity}\n\\label{app:cross_arch_fpr}\n\nAs preliminary cross-architecture evidence, we evaluate null-condition ($\\alpha{=}0$) false positive rates on GPT-2-medium (345M; OpenAI), a model outside the Pythia family used for all primary experiments.\nTwo seeds (s42, s43) are trained for $T{=}10$ generations under the same protocol as the Pythia-410M null runs.\nThis evaluation requires additional replication across architectures and seed counts before drawing definitive conclusions.\n\n\\begin{table}[h]\n\\centering\n\\caption{Null-condition FPR for GPT-2-medium ($\\alpha{=}0$, $T{=}10$, 6-pair basis). PermG forward detection shows extreme seed dependence; $K{\\geq}3$ consensus remains at 0\\% across both seeds.}\n\\label{tab:gpt2m_null_fpr}\n\\begin{tabular}{lccc}\n\\toprule\nSeed & PermG fwd & PermG rev & $K{\\geq}3$ \\\\\n\\midrule\ns42 & 6/6 (100\\%) & 0/6 & 0/6 \\\\\ns43 & 0/6 (0\\%) & 0/6 & 0/6 \\\\\n\\midrule\nPooled & 6/12 (50\\%) & 0/12 & 0/12 (0\\%) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe pooled PermG FPR is dramatically higher than on Pythia-410M (50\\% vs.\\ 11.1\\%, 6-pair basis) and shows extreme seed dependence (100\\% vs.\\ 0\\%).\nThis instability traces to the magnitude of null drift in GPT-2-medium's output distribution, which is substantially stronger than in Pythia-410M (Table~\\ref{tab:null_drift_comparison}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Null drift magnitude ($\\alpha{=}0$, gen\\,0$\\to$10; GPT-2-medium: 2 seeds; Pythia-410M: 4 seeds, s46/s48--s50). GPT-2-medium exhibits ${\\sim}4{\\times}$ stronger entropy drift and ${\\sim}7{\\times}$ stronger distinct-3 drift than Pythia-410M.}\n\\label{tab:null_drift_comparison}\n\\begin{tabular}{lcccc}\n\\toprule\n& \\multicolumn{2}{c}{GPT-2-medium} & \\multicolumn{2}{c}{Pythia-410M} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nMetric & gen\\,0 & gen\\,10 (\\%$\\Delta$) & gen\\,0 & gen\\,10 (\\%$\\Delta$) \\\\\n\\midrule\nToken entropy & 3.57 & 2.84 ($-$20.5\\%) & 3.23 & 3.076 ($-$4.9\\%) \\\\\nDistinct-3 & 0.84 & 0.54 ($-$35.8\\%) & 0.81 & 0.769 ($-$4.9\\%) \\\\\n$\\Delta$entropy (gen\\,0$\\to$1) & \\multicolumn{2}{c}{$-$0.60} & \\multicolumn{2}{c}{$-$0.25} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nGPT-2-medium's distinct-3 declines from 0.84 to 0.54 over ten null generations ($-$35.8\\%), compared with 0.81$\\to$0.77 ($-$4.9\\%) for Pythia-410M.\nThis steep diversity collapse under pure retraining, absent any synthetic contamination, creates a strong downward trend that PermG's permutation test interprets as a directional signal.\nThe initial entropy drop (gen\\,0$\\to$1: $-$0.60 vs.\\ $-$0.25) is similarly amplified, consistent with architecture-specific sensitivity to iterative retraining rather than a deficiency in the detection method.\n\nThe $K{\\geq}3$ multi-method consensus maintains 0\\% FPR on GPT-2-medium (0/12 pairs), though the margin of safety is narrow: in the worst case (s42), 2 of 5 methods vote for forward detection, one vote short of the $K{\\geq}3$ threshold.\nThis provides some protection against architecture-specific distributional variation, but two seeds constitute only preliminary evidence.\nFor reference, PermG successfully detects true contamination signal ($\\alpha{=}1.0$) on GPT-2-medium with 6/8 forward pairs (Table~\\ref{tab:generalization}), confirming that the method works when signal is present; the elevated null FPR is specific to the null condition where architecture-dependent drift dominates.\n\n\\section*{Use of AI Assistants}\n\\label{app:ai-assistants}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant throughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections, polishing prose, and reformatting LaTeX.\n    \\item \\textbf{Literature:} summarizing related papers to inform related-work section.\n\\end{itemize}\n\n",
    "structuredPatch": [
      {
        "oldStart": 751,
        "oldLines": 8,
        "newStart": 751,
        "newLines": 7,
        "lines": [
          " \\begin{figure*}[h]",
          " \\centering",
          " \\includegraphics[width=\\linewidth]{figures/shapley_method_contribution.pdf}",
          "-% TODO-D219: regenerate figure and update caption after Shapley recomputation with 6-seed data",
          "-\\caption{Shapley value decomposition of each method's marginal contribution to FPR (positive bars) and FNR (negative bars). PermG is the only method with zero FPR contribution; naive cross-correlation's FPR dominates its FNR benefit.}",
          "+\\caption{Shapley value decomposition of each method's marginal contribution to FPR (positive bars) and FNR (negative bars), computed from 6 null seeds (36 pairs) and 45 signal experiments (270 pairs). DiffXCorr achieves the best combined Shapley ($-0.299$) via near-zero FPR; PermG ranks second ($-0.141$) as the best directional method.}",
          " \\label{fig:shapley}",
          " \\end{figure*}",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---


### Assistant

_source line 123_

Now update the 8-pair robustness sentence.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "0bfd7526-41a8-4932-900f-e8fe24c72f4c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016rfva8PCeMXD1bMLGrmiZr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 619,
      "cache_read_input_tokens": 112683,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 619
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool call

_source line 124_

<details open><summary>🔧 Tool call — Edit · `toolu_01GRBFRj76MkPZdC6uMhMkRm`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
  "old_string": "The 8-pair variant (including mauve) yields qualitatively identical rankings: PermG remains the best contributor ($\\phi^{\\text{comb}}{=}-0.152$), naive cross-correlation the worst ($+0.170$), and threshold onset near-zero ($+0.063$).",
  "new_string": "The 8-pair variant (including mauve) yields qualitatively identical rankings: DiffXCorr remains the best contributor ($\\phi^{\\text{comb}}{=}-0.263$), PermG the best directional method ($-0.112$), naive cross-correlation the worst ($+0.157$), and threshold onset near-zero ($+0.073$)."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "643c4b69-124e-444e-8f41-d6c152a2bdfa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016rfva8PCeMXD1bMLGrmiZr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 619,
      "cache_read_input_tokens": 112683,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 619
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool result

_source line 125 · 2026-05-24T09:06:33.035Z_

<details><summary>↩ Tool result · `toolu_01GRBFRj76MkPZdC6uMhMkRm`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "9f424466-59a2-4e96-9470-3ad62e83a679",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
    "oldString": "The 8-pair variant (including mauve) yields qualitatively identical rankings: PermG remains the best contributor ($\\phi^{\\text{comb}}{=}-0.152$), naive cross-correlation the worst ($+0.170$), and threshold onset near-zero ($+0.063$).",
    "newString": "The 8-pair variant (including mauve) yields qualitatively identical rankings: DiffXCorr remains the best contributor ($\\phi^{\\text{comb}}{=}-0.263$), PermG the best directional method ($-0.112$), naive cross-correlation the worst ($+0.157$), and threshold onset near-zero ($+0.073$).",
    "originalFile": "\\appendix\n\n\\section{Training Details and Metric Drift}\n\\label{app:training_details}\n\\label{app:drift}\n\n\\paragraph{Hyperparameters.}\nEach generation fine-tunes for 5{,}000 steps using AdamW (learning rate $5 \\times 10^{-5}$, 500 warmup steps, weight decay $0.01$, batch size 4 for Pythia-410M, 32 for GPT-2-medium).\nGeneration uses temperature $1.0$, top-$k{=}50$, max length 512 tokens, producing 5{,}000 samples per generation from 5{,}000-sample subsets of WikiText-103.\nCanary metrics: token entropy $H(p_\\theta | \\text{context})$ over 1{,}000 held-out samples; ECE with 15 bins.\nAdditional downstream metrics (distinct-3, effective rank, Self-BLEU) appear in subsequent appendix sections.\n\n\\paragraph{Metric drift.}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Metric drift (\\%, generation~0$\\to$10) for Pythia-410M across contamination levels. Diversity collapse occurs at all $\\alpha$ levels, with the strongest decline at low-to-moderate contamination ($\\alpha{=}0.25$: distinct-1 $-40.3{\\pm}0.3\\%$) rather than full replacement ($\\alpha{=}1.0$: $-27.8{\\pm}1.6\\%$). $^\\dagger$$\\alpha{=}0.10$: single seed (seed~42, preliminary). $\\alpha{=}0.00$, $\\alpha{=}0.25$, $\\alpha{=}0.50$, $\\alpha{=}0.75$: 3-seed mean${\\pm}$std (seeds 42, 43, 44); $\\alpha{=}1.0$: 4-seed mean${\\pm}$std (seeds 42, 43, 44, 45).}\n\\label{tab:drift_summary}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n$\\alpha$ & Entropy & ECE & Distinct-1 & Distinct-2 & Perplexity \\\\\n\\midrule\n0.00 & $-4.6{\\pm}0.4$ & $+37.6{\\pm}14$ & $-14.1{\\pm}0.4$ & $-9.6{\\pm}0.4$ & $-20.6{\\pm}1.0$ \\\\\n0.10$^\\dagger$ & $-5.3$ & $+57$ & $-39.6$ & $-56.4$ & $-21.0$ \\\\\n0.25 & $-4.7{\\pm}0.5$ & $+81.8{\\pm}15.9$ & $-40.3{\\pm}0.3$ & $-56.4{\\pm}0.7$ & $-18.1{\\pm}0.8$ \\\\\n0.50 & $-18.0{\\pm}0.5$ & $+822.6{\\pm}18.3$ & $-37.1{\\pm}0.4$ & $-50.4{\\pm}1.0$ & $+21.0{\\pm}0.1$ \\\\\n0.75 & $-27.6{\\pm}0.2$ & $+1791{\\pm}18$ & $-32.3{\\pm}0.5$ & $-41.0{\\pm}1.0$ & $+182.6{\\pm}0.7$ \\\\\n1.00 & $-60.8{\\pm}1.2$ & $+3780{\\pm}30$ & $-27.8{\\pm}1.6$ & $-34.0{\\pm}3.3$ & $+3674{\\pm}45$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\n\\section{Distinct-3 Results}\n\\label{app:distinct3}\n\nTable~\\ref{tab:distinct3_drift} reports distinct-3 drift across all contamination levels.\nDistinct-3 exhibits the largest absolute decline among diversity metrics at low contamination ($-58.9{\\pm}0.9\\%$ at $\\alpha{=}0.25$) but attenuates at higher levels ($-30.5\\%$ at $\\alpha{=}1.0$), consistent with the diversity--calibration dissociation discussed in \\S\\ref{sec:discussion}.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Distinct-3 drift (\\%, generation~0$\\to$10) across contamination levels. $\\alpha{=}0.00$, $\\alpha{=}0.25$, $\\alpha{=}0.75$: 3-seed mean${\\pm}$std; $\\alpha{=}1.0$: 4-seed mean${\\pm}$std; $\\alpha{=}0.50$: single seed.}\n\\label{tab:distinct3_drift}\n\\begin{tabular}{lc}\n\\toprule\n$\\alpha$ & Distinct-3 drift (\\%) \\\\\n\\midrule\n0.00 & $-4.4{\\pm}0.5$ \\\\\n0.25 & $-58.9{\\pm}0.9$ \\\\\n0.50 & $-52.4$ \\\\\n0.75 & $-38.6{\\pm}1.3$ \\\\\n1.00 & $-30.5{\\pm}4.0$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Lead-lag analysis.}\nAt $\\alpha{=}1.0$, token entropy Granger-precedes distinct-3 at the same consensus level as distinct-1 and distinct-2: $K{\\geq}4/5$ methods, $S{\\geq}3/4$ seeds (Tier~3).\nHowever, the optimal lag is less stable than for distinct-1/2: at max\\_lag${=}7$, the lag standard deviation across seeds exceeds 1.5 generations, compared to $<0.5$ for distinct-1/2.\nThis instability reflects bimodal lag distributions (modes at lag~1 and lag~3--4), suggesting that distinct-3 captures two temporally distinct diversity loss mechanisms: rapid n-gram homogenization (lag~1) and slower distributional narrowing (lag~3--4).\n\n\\paragraph{Sensitivity to sequence length.}\nHigher-order $n$-gram diversity metrics are more sensitive to generation length and random sampling variability.\nWith our 512-token generation length, distinct-3 has a smaller effective denominator (number of possible unique trigrams observed) than distinct-1 or distinct-2, amplifying stochastic fluctuations.\nThis partially explains the higher lag instability: the signal-to-noise ratio for temporal precedence is lower for distinct-3, requiring more observations (longer $T$ or more seeds) to achieve stable estimates.\nFor this reason, we report distinct-3 in this appendix rather than in the main text, where distinct-1 and distinct-2 provide cleaner evidence of the entropy-leads-diversity pattern.\n\n\n\\section{Observation Window Sensitivity}\n\\label{app:window_sensitivity}\n\nTable~\\ref{tab:window_sensitivity} reports how the Tier~3 consensus classification ($K{\\geq}4/5$ methods) varies as a function of the minimum observation window $T_{\\min}$, where analysis uses only generations $0$ through $T_{\\min}$.\nThe consensus classification stabilizes at $T_{\\min}{\\geq}5$ (6 data points), well below our full observation window of $T{=}10$: all six effect-size reference pairs (token entropy and ECE $\\to$ distinct-1, distinct-2, distinct-3) reach $K{\\geq}4/5$ agreement at every window length from $T_{\\min}{=}5$ through $T_{\\min}{=}10$, with no spurious pairs (canary$\\to$perplexity) admitted.\n\nToda--Yamamoto is the only method exhibiting window-dependent sensitivity (note: TY directional assignment is under verification; these counts are retained for completeness): TY consensus stabilizes at $T_{\\min}{\\geq}6$, slightly later than the primary methods, reflecting the additional degrees of freedom consumed by the augmentation order $d_{\\max}$.\nThis does not affect the consensus classification because the remaining four methods provide stable $K{\\geq}4/5$ agreement independently of Toda--Yamamoto's vote.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Observation window sensitivity for Tier~3 consensus ($K{\\geq}4/5$) at $\\alpha{=}1.0$ (Pythia-410M, 4~seeds). Tier~3 pairs: number of canary$\\to$downstream pairs (out of 8 validated) reaching $K{\\geq}4/5$ method agreement. TY pairs: number of effect-size reference pairs (out of 6) reaching Toda--Yamamoto significance (moderate supplementary method; \\S\\ref{sec:method}). Consensus stabilizes at $T_{\\min}{\\geq}5$; TY stabilizes at $T_{\\min}{\\geq}6$.}\n\\label{tab:window_sensitivity}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccccccc}\n\\toprule\n& \\multicolumn{8}{c}{Minimum observation window $T_{\\min}$} \\\\\n\\cmidrule(lr){2-9}\n& 3 & 4 & 5 & 6 & 7 & 8 & 9 & 10 \\\\\n\\midrule\nTier~3 pairs (/8)    & $\\dagger$ & $\\dagger$ & 6 & 6 & 6 & 6 & 6 & 6 \\\\\nTY pairs$^\\S$ (/6)   & $\\dagger$ & $\\dagger$ & 3--6 & 3--6 & 3--6 & 3--6 & 3--6 & 6 \\\\\nStable               & ---       & ---       & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark \\\\\n\\bottomrule\n\\multicolumn{9}{l}{\\footnotesize $\\dagger$~Insufficient degrees of freedom for Granger-type tests ($<6$ data points).} \\\\\n\\multicolumn{9}{l}{\\footnotesize $^\\S$~TY directional assignment under verification.}\n\\end{tabular}}\n\\end{table}\n\n\n\\section{Robustness Checks}\n\\label{app:robustness}\n\n\\paragraph{Permutation count stability.}\nTable~\\ref{tab:nperm_stability} compares permutation Granger $p$-values at 5{,}000 versus 10{,}000 permutations across all canary$\\to$downstream pairs at $\\alpha{=}0.75$ (3~seeds, 24~pairs).\nPermutation Granger $p$-values are stable to within 0.002 between 5{,}000 and 10{,}000 permutations, with zero significance decisions affected.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Permutation count stability analysis ($\\alpha{=}0.75$, 3~seeds, 24 canary$\\to$downstream pairs). $p$-values from permutation Granger tests at $n_{\\text{perm}}{=}5{,}000$ versus $n_{\\text{perm}}{=}10{,}000$.}\n\\label{tab:nperm_stability}\n\\begin{tabular}{lc}\n\\toprule\nMetric & Value \\\\\n\\midrule\nMax $|\\Delta p|$ & 0.010 \\\\\nMean $|\\Delta p|$ & 0.002 \\\\\nSignificance flips & 0 / 24 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{FDR threshold sensitivity.}\nTable~\\ref{tab:fdr_sensitivity} reports the effect of varying the BH FDR threshold $q$ on treatment ($\\alpha{=}0.75$, 3~seeds, 8-pair basis) versus null ($\\alpha{=}0.0$, 6~seeds 45--50, 6-pair basis) separation for permutation Granger tests.\nTreatment/null separation is qualitatively robust to FDR threshold choice, though the expanded null sample reveals a small number of false positives at each threshold (3--8 of 36 pairs).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{FDR threshold sensitivity for permutation Granger significance. Treatment: $\\alpha{=}0.75$ (3~seeds, 24 forward-direction pairs, 8-pair basis). Null: $\\alpha{=}0.0$ (6~seeds 45--50, 36 pairs, 6-pair basis). The expanded null sample reveals modest false positive rates that increase with $q$.}\n\\label{tab:fdr_sensitivity}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n$q$ & Null FDR-sig (/36) & Treatment FDR-sig (/24) & Separation \\\\\n\\midrule\n0.01 & 3 & 0  & Underpowered \\\\\n0.05 & 4 & 19 & Good \\\\\n0.10 & 8 & 24 & Good (elevated null) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{PermG $p$-value gradient at the onset boundary ($\\alpha{=}0.45$).}\nAt the onset boundary, PermG operates near its detection limit, and marginal $p$-values exhibit seed-dependent variation consistent with the statistical power interpretation (\\S\\ref{sec:theory}).\nTable~\\ref{tab:fdr_gradient_a045} reports BH-corrected $p$-values for all 8 canary$\\to$downstream pairs across two seeds at $\\alpha{=}0.45$.\nSeed~43 reaches a minimum FDR-corrected $p{=}0.059$ (18\\% above the $q{=}0.05$ threshold), while seed~42 reaches $p{=}0.091$ (82\\% above threshold).\nNo pair crosses the significance threshold at either seed, yielding the aggregate 0/8 detection rate reported in \\S\\ref{sec:regime}.\nThe gradient is consistent with a continuous power transition rather than a binary absence of signal: PermG operates near its detection limit at $\\alpha{=}0.45$, with seed-dependent variation in marginal $p$-values.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{BH-corrected PermG $p$-values at $\\alpha{=}0.45$ (8 canary$\\to$downstream pairs $\\times$ 2 seeds). Min $p_{\\mathrm{fdr}}$ per seed shown. All pairs remain above the $q{=}0.05$ threshold, yielding 0/8 aggregate detection.}\n\\label{tab:fdr_gradient_a045}\n\\begin{tabular}{lcc}\n\\toprule\n & Seed 42 & Seed 43 \\\\\n\\midrule\nMin FDR $p$ & 0.091 & 0.059 \\\\\nGap to $q{=}0.05$ & 82\\% & 18\\% \\\\\nPermG fwd sig (/8) & 0 & 0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Systematic Robustness Analysis}\n\\label{app:spec_curve}\n\nThe sharp detection onset reported in \\S\\ref{sec:regime} could in principle depend on specific analytical choices (pair selection, seed, $\\alpha$ level, method parameters).\nWe assess robustness via specification curve analysis~\\cite{simonsohn2020specification}, systematically varying analytical degrees of freedom to test whether the 0/8$\\to$6/8 transition is specification-invariant.\nOur specification curve varies data subsets and pair selections while holding the detection method (PermG) and its hyperparameters fixed, more closely resembling a systematic subset analysis than a full specification curve in the sense of \\citet{simonsohn2020specification}.\n\nWe construct 1{,}160 analytical specifications from the combinatorial space of: 13 contamination levels ($\\alpha$ grid), seed selection ($\\{42, 43, 44, 45\\}$ where available), 8 canonical canary$\\to$downstream pairs (\\{token entropy, ECE\\} $\\times$ \\{distinct-1, distinct-2, distinct-3, mauve\\}), and method parameters (all PermG with $n_\\text{perm}{=}5{,}000$, BH FDR $q{=}0.05$).\nAll specifications use the D120-canonical analysis pipeline with $3\\sigma$ threshold calibration (D105) as a hard filter.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Specification curve summary (1{,}160 specifications, D120-compliant). The blind$\\to$onset jump is robust across specifications: 0\\% significance rate through $\\alpha{=}0.45$, rising to 75\\% at $\\alpha{=}0.50$.}\n\\label{tab:spec_curve}\n\\begin{tabular}{lc}\n\\toprule\nMetric & Value \\\\\n\\midrule\nTotal specifications & 1{,}160 \\\\\nSignificant (FDR $q{<}0.05$) & 536 (46.2\\%) \\\\\n\\midrule\n\\emph{By regime} & \\\\\n\\quad Blind ($\\alpha \\leq 0.45$) & 0\\% \\\\\n\\quad Onset ($\\alpha{=}0.50$) & 75\\% \\\\\n\\quad Detection ($\\alpha \\geq 0.75$) & 62--75\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe specification curve confirms that the sharp detection onset is not an artifact of particular analytical choices: the categorical jump from 0\\% to ${\\geq}75\\%$ significance at $\\alpha_c{\\approx}0.50$ holds across the vast majority of specifications, supporting the main text claim (\\S\\ref{sec:regime}).\n\n\n\\section{Transfer Entropy Analysis}\n\\label{app:transfer_entropy}\n\nTable~\\ref{tab:te_results} reports transfer entropy (TE; \\citealp{schreiber2000measuring}) results aggregated across all baseline conditions.\nTE was estimated using 3-bin discretization with permutation testing ($n{=}5{,}000$).\nNo pair reaches BH-corrected significance ($q{=}0.05$) in any condition, confirming that non-parametric information-theoretic methods lack detection power at $T{=}11$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Transfer Entropy results (12 runs across all $\\alpha$ levels). TE\\textsubscript{fwd}: canary$\\to$downstream; TE\\textsubscript{rev}: downstream$\\to$canary. Mean uncorrected permutation $p$-values ($n{=}5{,}000$). No pair reaches BH-corrected $q{<}0.05$ in any run.}\n\\label{tab:te_results}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\nCanary & Downstream & TE\\textsubscript{fwd} (mean) & $p$\\textsubscript{fwd} (mean) & TE\\textsubscript{rev} (mean) & $p$\\textsubscript{rev} (mean) \\\\\n\\midrule\ntoken\\_entropy & distinct-1 & 0.289 & 0.559 & 0.480 & 0.490 \\\\\ntoken\\_entropy & distinct-2 & 0.300 & 0.529 & 0.496 & 0.447 \\\\\ntoken\\_entropy & distinct-3 & 0.255 & 0.645 & 0.484 & 0.459 \\\\\ntoken\\_entropy & perplexity & 0.257 & 0.676 & 0.386 & 0.626 \\\\\nECE & distinct-1 & 0.185 & 0.720 & 0.184 & 0.891 \\\\\nECE & distinct-2 & 0.208 & 0.683 & 0.216 & 0.846 \\\\\nECE & distinct-3 & 0.209 & 0.689 & 0.227 & 0.807 \\\\\nECE & perplexity & 0.296 & 0.572 & 0.263 & 0.747 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\phantomsection\\label{app:te_mi}\n\\paragraph{KNN-based TE/MI decomposition.}\nA $k$-nearest-neighbor TE estimator ($k{=}5$) provides a model-free complement to the parametric Granger framework.\nForward-dominant TE fraction increases monotonically with $\\alpha$: 4/8 pairs at $\\alpha{=}0.25$ (mean net TE${=}0.14$), 5/8 at $\\alpha{=}0.50$ (net TE${=}0.42$), 6/8 at $\\alpha{=}0.60$ (net TE${=}0.57$), and 8/8 at $\\alpha{=}1.0$ (net TE${=}1.59$).\nAll 120 forward TE bootstrap 95\\% CIs exclude zero at $T{=}10$; all 48 at $T{=}20$.\nThe ``high MI, low TE'' hypothesis for the non-monotonic dip is supported by only 2/8 pairs (ECE$\\to$perplexity and token entropy$\\to$perplexity); the remaining 6 pairs show elevated TE even at $\\alpha{=}0.60$, indicating confounded co-variation rather than a universal mechanism.\n\n\\section{Change-Point Detection Analysis}\n\\label{app:change_point}\n\nWe apply a max-split change-point test with bootstrap significance assessment ($n{=}5{,}000$, $p{<}0.05$) to each metric's generation-level time series ($T{=}11$).\n\nUnder the null control ($\\alpha{=}0.00$, 3~seeds), downstream diversity metrics (distinct-1, distinct-2, distinct-3) produce significant change-points at generation~2 in all seeds (9/9 tests). With additional significant tests from ECE (2/3 seeds) and token entropy (1/3 seeds), the overall false positive rate reaches 66.7\\% (12/18 tests; Table~\\ref{tab:cp_null}). The monotonic drift inherent in iterative self-training is sufficient to trigger change-point detection even without canary contamination. Individual change-point significance therefore cannot serve as standalone evidence for a canary-specific effect.\n\nAlthough individual significance is unreliable as a discriminator, the temporal ordering of detected change-points reverses between null and treatment conditions. In the null ($\\alpha{=}0.00$), downstream metrics show the earliest significant breaks at generation~2 (all seeds), while significant canary breaks appear later (ECE at generations~4--8). Under treatment conditions ($\\alpha{\\geq}0.75$), this ordering flips: canary metrics place their best splits at generation~1, followed by downstream diversity metrics at generations~2--4 and perplexity at generation~4 (Table~\\ref{tab:cp_results}). This ordering reversal provides complementary evidence from a distinct statistical framework, consistent with the Granger-precedence analysis in \\S\\ref{sec:experiments}.\n\nSeveral caveats apply. The 18 individual tests per condition were not corrected for multiple comparisons (BH or Bonferroni); primary inference rests on the cross-metric temporal ordering rather than on individual significance tests. Under treatment conditions, token entropy places its best split at generation~1 with large effect sizes ($|d|{>}2.5$) in all seeds, but the pre-change segment at a generation-1 split contains only a single data point, reducing bootstrap power (1/3 seeds significant at $\\alpha{=}0.75$). The short series length ($T{=}11$) further limits overall detection power.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Change-point detection under null control ($\\alpha{=}0.00$, 3 seeds). CP: detected change-point generation (mean across significant seeds); $|d|$: Cohen's $d$ effect size (mean across all seeds); Sig.\\ rate: fraction of seeds where $p{<}0.05$. Overall FPR: 12/18 = 66.7\\%.}\n\\label{tab:cp_null}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\nMetric & CP gen (mean) & $|d|$ (mean) & Sig.\\ rate & Type \\\\\n\\midrule\ntoken\\_entropy & 1.0 & 2.94 & 1/3 & canary \\\\\nECE & 6.0 & 1.62 & 2/3 & canary \\\\\ndistinct-1 & 2.0 & 2.27 & 3/3 & downstream \\\\\ndistinct-2 & 2.0 & 2.40 & 3/3 & downstream \\\\\ndistinct-3 & 2.0 & 2.27 & 3/3 & downstream \\\\\nperplexity & --- & 3.11 & 0/3 & downstream \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Change-point detection at $\\alpha{=}0.75$ (3 seeds). CP: detected change-point generation; $|d|$: Cohen's $d$ effect size between pre- and post-change segments. Sig.\\ rate: fraction of seeds where $p{<}0.05$.}\n\\label{tab:cp_results}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\nMetric & CP gen (mean) & $|d|$ (mean) & Sig.\\ rate & Type \\\\\n\\midrule\ntoken\\_entropy & 1.0 & 3.21 & 1/3 & canary \\\\\nECE & 1.0 & 3.10 & 1/3 & canary \\\\\ndistinct-1 & 2.3 & 2.18 & 3/3 & downstream \\\\\ndistinct-2 & 3.0 & 1.97 & 3/3 & downstream \\\\\ndistinct-3 & 3.7 & 1.86 & 3/3 & downstream \\\\\nperplexity & 4.0 & 1.70 & 3/3 & downstream \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Dose-response ordering pattern.}\nTable~\\ref{tab:cp_ordering} summarizes the ordering pattern across contamination levels.\nThe canary-to-downstream gap shifts monotonically from negative (downstream first) under the null to positive (canary first) under treatment, ruling out a methodological artifact in which canary metrics would systematically appear earlier regardless of condition.\nThe $\\alpha{=}1.0$ analysis is limited to a single seed (s42); all other conditions use 3 seeds.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccl}\n\\toprule\n$\\alpha$ & Canary cp & Downstream cp & Gap & Direction \\\\\n\\midrule\n0.00 & gen 4--8 & gen 2 & $-$2.5 & Downstream first \\\\\n0.25 & gen 3--4 & gen 3--4 & $\\approx$0 & Simultaneous \\\\\n0.75 & gen 1 & gen 2--4 & $+$2.25 & Canary first \\\\\n1.00 & gen 2 & gen 2--5 & $+$1.0 & Canary first \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Change-point ordering reversal across contamination levels. Under the null ($\\alpha{=}0.00$), downstream metrics break before canary metrics; this ordering reverses monotonically as $\\alpha$ increases, consistent with the Granger-precedence analysis.}\n\\label{tab:cp_ordering}\n\\end{table}\n\n\n\\section{Sequential Monitoring: CUSUM vs Calibrated Threshold}\n\\label{app:csmp}\n\nWe translate the Granger-precedence finding into a deployable monitoring protocol using CUSUM (cumulative sum) sequential testing~\\cite{page1954continuous}, calibrated against the $\\alpha{=}0.0$ null control.\nThe null-calibration procedure sets the alarm threshold $h$ such that the false alarm rate (FAR) is 0\\% on null data (3~seeds, $T{=}10$), providing controlled Type~I error guarantees.\n\n\\paragraph{Method.}\nCUSUM monitors the cumulative deviation of token entropy from its null-control baseline: $S_t = \\max(0,\\; S_{t-1} + (\\mu_0 - x_t) - k)$, where $\\mu_0$ is the null-control mean, $k$ is the allowance parameter, and the alarm triggers when $S_t > h$.\nWe calibrate $h$ for each $k$ from the $\\alpha{=}0.0$ null data (Table~\\ref{tab:csmp_calibration}).\nAs a baseline, we compare against a simple calibrated threshold: alarm when the metric crosses $\\mu_0 - 2\\sigma_0$ for $n{\\geq}1$ or $n{\\geq}2$ consecutive generations.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{CUSUM calibration parameters from $\\alpha{=}0.0$ null control (3~seeds). $h$: alarm threshold calibrated to achieve FAR${=}$0\\%. For $k{\\geq}0.25$, the null CUSUM statistic remains at zero, yielding $h \\approx 0$.}\n\\label{tab:csmp_calibration}\n\\begin{tabular}{lcc}\n\\toprule\n$k$ & $h$ & FAR \\\\\n\\midrule\n0.05 & 1.530 & 0\\% \\\\\n0.10 & 1.005 & 0\\% \\\\\n0.25 & $\\approx$0 & 0\\% \\\\\n0.50 & $\\approx$0 & 0\\% \\\\\n1.00 & $\\approx$0 & 0\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Results.}\nTable~\\ref{tab:csmp_comparison} compares CUSUM and simple threshold detection times across gradual contamination levels.\nAt the recommended operating point ($k{=}0.25$), CUSUM and the simple threshold ($n{\\geq}1$) produce identical alarm times (generation~1) across all seeds and contamination levels.\nMore conservative CUSUM settings ($k{=}0.1$, $k{=}0.05$) delay detection to match the $n{\\geq}2$ threshold or later.\nAt $k{=}1.0$ with $\\alpha{=}0.50$, CUSUM fails entirely ($S_t \\equiv 0$ for all seeds), demonstrating sensitivity to the allowance parameter.\nNo CUSUM configuration outperforms the simple calibrated threshold at any operating point tested.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{CUSUM vs simple calibrated threshold: alarm generation across contamination levels (3~seeds each; all seeds agree on the alarm generation shown). Threshold: metric crosses $\\mu_0 - 2\\sigma_0$. No CUSUM configuration outperforms the simple threshold at any operating point.}\n\\label{tab:csmp_comparison}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n$\\alpha$ & CUSUM $k{=}0.25$ & CUSUM $k{=}0.1$ & CUSUM $k{=}0.05$ & Thresh $n{\\geq}1$ & Thresh $n{\\geq}2$ \\\\\n\\midrule\n0.50 & gen 1 & gen 2 & gen 3 & gen 1 & gen 2 \\\\\n0.75 & gen 1 & gen 2 & gen 2 & gen 1 & gen 2 \\\\\n\\bottomrule\n\\multicolumn{6}{l}{\\footnotesize CUSUM $k{=}1.0$ at $\\alpha{=}0.50$: $S_t \\equiv 0$ for all seeds (complete detection failure).} \\\\\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Interpretation.}\nThe equivalence arises because the generation-0$\\to$1 entropy drop is large ($|\\Delta x| > 0.7$ for $\\alpha{=}0.50$, $> 1.0$ for $\\alpha{=}0.75$) relative to the null-control variability ($\\sigma_0 \\approx 0.03$).\nAny detector with a near-zero or small threshold triggers at generation~1; CUSUM's cumulative memory provides no advantage when the initial shift already exceeds the control limit.\nThis result extends Claim~3 (method sensitivity) beyond lead-lag detection to the monitoring domain: even a sequential testing procedure with stronger theoretical properties (optimal expected detection delay under continuous monitoring) does not improve over a calibrated baseline when the initial contamination signal dominates the allowance parameter.\nThe contribution of the null-calibrated monitoring framework is the calibration procedure itself (setting alarm boundaries from $\\alpha{=}0.0$ data to guarantee FAR${=}$0\\%), not the CUSUM algorithm.\n\n\\section{Background and Notation}\n\\label{app:background}\n\\label{sec:background}\n\nThis section establishes the formal setup and notation used throughout the paper.\n\n\\paragraph{Iterative training loop.}\nLet $M_0$ denote a pretrained language model and $\\mathcal{D}_\\text{real}$ a fixed corpus of human-written text.\nAt each generation $t \\geq 1$, the model $M_{t-1}$ generates a synthetic corpus $\\mathcal{D}_\\text{synth}^{(t-1)}$, and the next-generation model $M_t$ is fine-tuned on a mixture of $\\alpha$ fraction synthetic data and $(1{-}\\alpha)$ fraction real data:\n\\begin{equation}\n    \\mathcal{D}_\\text{train}^{(t)} = \\alpha \\cdot \\mathcal{D}_\\text{synth}^{(t-1)} \\;+\\; (1{-}\\alpha) \\cdot \\mathcal{D}_\\text{real}, \\quad \\alpha \\in [0, 1].\n    \\label{eq:mixing}\n\\end{equation}\nAt $\\alpha{=}1.0$, this reduces to the full-replacement paradigm of \\citet{shumailov2024curse}.\n\n\\paragraph{Metric families.}\n\\emph{Canary metrics}: token entropy ($H(p_\\theta | \\text{context})$ on held-out samples) and expected calibration error (ECE).\n\\emph{Downstream metrics}: distinct-$n$ ($n \\in \\{1, 2, 3\\}$)~\\cite{li2016diversity} and perplexity.\nEach metric produces a time series of $T{+}1$ observations.\n\n\\paragraph{Lead-lag testing.}\nGiven canary series $X$ and downstream series $Y$, the central question is whether changes in $X$ temporally precede changes in $Y$, requiring directionality and confounder control beyond simple correlation.\nWe employ five methods spanning permissive to conservative: naive cross-correlation, differenced cross-correlation, threshold onset detection, permutation Granger causality~\\cite{shojaie2022granger}, and Toda--Yamamoto Granger causality~\\cite{toda1995statistical}.\n\n\\section{MMCT Algorithm}\n\\label{app:mmct}\n\nAlgorithm~\\ref{alg:mmct} describes the Multi-Method Consensus Test (MMCT) introduced in \\S\\ref{sec:mmct}.\n\n\\begin{algorithm}[h]\n\\caption{Multi-Method Consensus Test (MMCT)}\n\\label{alg:mmct}\n\\begin{algorithmic}[1]\n\\Require Time series pair $(X, Y)$; methods $\\{m_1, \\ldots, m_K\\}$ ($K{=}5$); null-control data $\\mathcal{N}$ (from $\\alpha{=}0.0$); tolerance $\\epsilon{=}0.01$\n\\Ensure $p$-value, consensus level $\\hat{K}$\n\\For{each method $m_k$}\n    \\State Compute empirical FPR: $\\widehat{\\mathrm{FPR}}_k \\gets$ fraction of null-control pairs where $m_k$ rejects $H_0$\n    \\State Compute weight: $w_k \\gets 1 / \\max(\\widehat{\\mathrm{FPR}}_k,\\; \\epsilon)$\n    \\State Apply $m_k$ to $(X, Y)$: $d_k \\gets \\mathbf{1}[m_k \\text{ rejects } H_0]$\n\\EndFor\n\\State Weighted consensus: $W(X {\\to} Y) \\gets \\sum_{k} w_k \\, d_k \\;/\\; \\sum_{k} w_k$\n\\State Build empirical null distribution of $W$ from all null-control pairs in $\\mathcal{N}$\n\\State Compute $p$-value from empirical null: $p \\gets \\Pr_{\\mathcal{N}}(W \\geq W_{\\mathrm{obs}})$\n\\State Consensus level: $\\hat{K} \\gets \\sum_{k} d_k$\n\\State \\Return $p$, $\\hat{K}$\n\\end{algorithmic}\n\\end{algorithm}\n\n\\paragraph{Design rationale.}\nFPR-inverse weighting penalizes methods with high false positive rates on null-control data: naive cross-correlation (FPR${=}91.7\\%$) receives weight $w{=}1.09$, while PermG (FPR${=}11.1\\%$, the lowest among directional methods; DiffXCorr achieves 2.8\\% but lacks directional separation) receives $w{=}9.0$.\nThe empirical null distribution avoids parametric assumptions that are unreliable for short ($T{=}5$--$20$), non-stationary series typical of iterative training.\nMMCT is a consensus testing protocol, not a novel statistical method; its value lies in systematic method comparison and the identification of method-dependent conclusions.\n\n\n\\section{Methodological Comparison Table}\n\\label{app:method_comparison}\n\nTable~\\ref{tab:method-comparison} summarizes the methodological coverage of existing canary and monitoring analyses across the diagnostic dimensions identified in \\S\\ref{sec:method}.\nNo prior work combines all six dimensions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Methodological comparison of canary and monitoring analyses. \\checkmark\\ = present, $\\times$ = absent, $\\circ$ = partial (${\\leq}2$ levels or limited replication). Diff.\\ = differencing/stationarity controls. Multi-M.\\ = ${\\geq}2$ independent statistical methods. MTC = multiple testing correction. Regime = systematic variation of $\\alpha$. Seeds = ${\\geq}3$ independent seeds. Arch.\\ = ${\\geq}2$ architecturally distinct model families.}\n\\label{tab:method-comparison}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccccl}\n\\toprule\nWork & Diff. & Multi-M. & MTC & Regime & Seeds & Arch. & Metrics \\\\\n\\midrule\n\\citet{shumailov2024curse}     & $\\times$   & $\\times$   & $\\times$   & $\\circ$    & \\checkmark & \\checkmark & PPL \\\\\n\\citet{du2025scales}           & $\\times$   & $\\times$   & \\checkmark & \\checkmark & \\checkmark & $\\times$   & ECE, Acc, Dist-$n$ \\\\\n\\citet{gambetta2024surplexity} & $\\times$   & $\\times$   & $\\times$   & \\checkmark & \\checkmark & \\checkmark & Surplexity, Ent \\\\\nSIGMA~\\cite{sigma2026spectral} & $\\times$   & $\\times$   & $\\times$   & $\\times$   & $\\times$   & $\\times$   & Spectral \\\\\nDCES~\\cite{dces2026counter}    & $\\times$   & $\\times$   & $\\times$   & $\\times$   & $\\times$   & \\checkmark & ECE, Ent, PPL \\\\\n\\midrule\n\\textbf{Ours}                  & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark & Ent, ECE, PPL, Dist-$n$ \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\\section{Extended Discussion}\n\\label{app:extended_discussion}\n\n\\paragraph{Calibration scope and generalization.}\nAll FPR and FNR calibration results are specific to our experimental setup: Pythia-410M, WikiText-103 subset, $T{=}10$, and six contamination levels.\nCross-architecture validation across 15 conditions spanning six model families shows that the entropy-leads-diversity pattern generalizes in 11 of 15 architecture-seed combinations (Table~\\ref{tab:generalization}); GPT-2 bf16 (0/8), GPT-2 s43 (6/8 bidirectional), SmolLM3-3B (3/8, entropy decoupling), and Pythia-1.4B s42 (2/8) do not confirm the pattern.\n\n\\paragraph{Domain-dependent directionality.}\nThe unidirectional forward causation observed on WikiText (PermG reverse${=}$0/8 across all conditions) does not hold universally.\nOn C4 at $\\alpha{=}0.50$ (s42 fp32), PermG reverse reaches 7/8, indicating near-symmetric bidirectional coupling; however, this is seed-dependent (s43: 1/8) and noted as preliminary.\nThe practical implication is that directional asymmetry should be verified per domain.\n\n\\paragraph{Token entropy versus perplexity.}\nThe distinction lies in the evaluation domain: token entropy is $H(p_\\theta | \\text{context})$ on held-out real data, while perplexity is $\\exp(H_\\text{cross})$ on model-generated text.\nFirst-differencing removes their shared downward trend: the canary$\\to$diversity channel survives because entropy leads diversity by one generation, whereas the canary$\\to$perplexity channel vanishes because both co-move synchronously.\n\n\\paragraph{NLP-specific constraints.}\nOur application of Granger-type methods faces constraints absent in econometrics: (i)~observation length ($T{=}5$--$20$ vs.\\ $T{=}100$--$1000$); (ii)~non-stationarity by design rather than incidental; (iii)~small multiplicity for FDR correction (8--32 pairs per regime).\nTransfer entropy (0/192 FDR-significant results) confirms that method sensitivity extends beyond the five-method panel.\n\n\\paragraph{Prevention paradox.}\nEffective intervention truncates the collapse trajectory that established Granger precedence.\nDifferenced cross-correlation retains significance under intervention (31/32 pairs), while threshold onset fails entirely (0/8), reinforcing the multi-method rationale.\n\n\\paragraph{Grouped testing rationale.}\nWe test 8 canary$\\to$downstream pairs jointly (2 canaries $\\times$ 4 downstream metrics) rather than individual per-metric tests because: (i)~joint testing with BH-FDR correction controls family-wise error across the canary panel, avoiding the inflated false-positive rate that would result from reporting the single most significant pair; (ii)~the count of significant pairs ($k/8$) provides a natural effect-size measure that distinguishes isolated from systematic detection; (iii)~per-metric tests cannot capture the cross-metric consistency that separates genuine temporal precedence from metric-specific artifacts (e.g., MAUVE floor saturation affects 2/8 pairs universally, identifiable only in grouped results).\n\n\\paragraph{Canary metric choice.}\nSmolLM3-3B reveals that canary metric selection constitutes a sensitivity dimension beyond the five statistical methods: token entropy exhibits non-monotonic oscillations (0/4 significant pairs), while ECE maintains monotonic growth (3/4 pairs).\nNo single canary metric is universally optimal.\n\n\\paragraph{Exploratory CSD analysis.}\nCanary metrics show rising autocorrelation (Kendall $\\tau{=}0.79$--$0.82$) while downstream metrics show none ($\\tau{=}0.03$--$0.30$), but this pattern does not survive multiple testing correction (2/10 post-BH) and remains exploratory.\nWe note that \\citet{truong2026phase} show model collapse is a first-order transition, ruling out CSD as a structural detection mechanism; the rising autocorrelation likely reflects non-stationarity rather than critical slowing down.\n\n\\paragraph{Scale verification (Pythia-1.4B).}\n\\label{app:scale_14b}\nTo test whether the phase-diagram structure generalizes beyond 410M, we replicate the analysis at 1.4B scale ($T{=}10$--$15$, fp32, seed~42).\nTable~\\ref{tab:14b_phase} summarizes the available cells.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Pythia-1.4B phase-diagram cells (fp32, PermG forward, direction-checked).}\n\\label{tab:14b_phase}\n\\begin{tabular}{lcccc}\n\\toprule\n$\\alpha$ & \\multicolumn{2}{c}{$T{=}10$} & \\multicolumn{2}{c}{$T{=}15$} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\n         & s42 & s44 & s42 & s43 \\\\\n\\midrule\n0.45 & 0/6 & 0/6 & 3/6 & 5/6 \\\\\n0.50 & 4/6 & 6/6 & 3/6 & 3/6 \\\\\n0.60 & 4/6 & 6/6 & 6/6 & 6/6 \\\\\n0.75 & 5/6 & 6/6 & 6/6 & 6/6 \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\footnotesize All: PermG fwd, 6-pair basis (2 canaries $\\times$ 3 distinct-$n$;} \\\\\n\\multicolumn{5}{l}{\\footnotesize MAUVE excl.\\ due to floor ${\\sim}0.033$ at 1.4B).} \\\\\n\\multicolumn{5}{l}{\\footnotesize s42 rev.\\ 0/6 at all $\\alpha$; s43 rev.\\ see text.} \\\\\n\\end{tabular}\n\\end{table}\n\nThe phase-diagram structure is qualitatively preserved at 1.4B scale.\nECE maintains monotonic growth across all three tested $\\alpha$ levels (3/3 cross-scale robust), and the binary detection pattern (above vs.\\ below $\\alpha_c$) is consistent with the 410M phase diagram.\nOn the 6-pair basis (MAUVE excluded due to systematic floor ${\\sim}0.033$; Table~\\ref{tab:14b_phase}), PermG forward detection at 1.4B ranges from 0/6 ($\\alpha{=}0.45$, $T{=}10$) to 6/6 ($\\alpha{\\geq}0.60$, $T{=}15$); token entropy exhibits one-step saturation ($27$--$39\\%$ drop from generation~0 to~1), reducing temporal resolution for entropy-based pairs.\nSeed s42 shows PermG$_\\text{rev}{=}0/6$ across all eight 1.4B conditions ($4\\alpha{\\times}2T$), confirming that bidirectionality is seed-specific rather than scale-inherent.\nThe 410M sync-dip ($\\alpha{=}0.60$: 0/8 at $T{\\leq}20$) does not reproduce at 1.4B (4/6 at $T{=}10$); whether this reflects scale-dependent dynamics or Pythia-specific effects remains open with only two model sizes tested.\nAt $T{=}15$, scale effects are $\\alpha$-conditional: $\\alpha{=}0.60$ reaches 6/6, while $\\alpha{=}0.50$ attenuates to 3/6 (vs 4/6 at $T{=}10$), confirming that detection loss is onset-localized rather than uniform.\nThe boundary's $T$-dependence is preserved: $\\alpha{=}0.45$ rises from 0/6 ($T{=}10$) to 3/6 ($T{=}15$), mirroring the 410M boundary shift.\nHowever, method-level heterogeneity emerges: Toda--Yamamoto exhibits a non-monotonic pattern at $T{=}15$, inverting the PermG ordering in the mid-$\\alpha$ range; gradual low-$\\alpha$ dynamics preserve VAR lag structure, while rapid entropy saturation disrupts lag dependence at intermediate $\\alpha$, with recovery at $\\alpha{=}0.75$ where extreme collapse dynamics (PPL drift ${+}390\\%$) generate sufficient temporal variation to support VAR detection.\nOnset-zone attenuation is $\\alpha$-invariant at 1.4B: both $\\alpha{=}0.45$ and $0.50$ yield 3/6 at $T{=}15$.\nAt 1.4B with $T{=}10$ (11 data points), non-PermG methods (threshold onset, naive cross-correlation, Toda--Yamamoto) have insufficient power due to short sequence length, reducing $K{\\geq}3$ consensus to an effective single-method test; at $T{=}15$ (16 data points), detection recovers (6/6 at $\\alpha{=}0.60$, lead time ${=}$ 10 generations) and $K{\\geq}3$ recovers its multi-method character, with 3/4 $\\alpha$ conditions achieving $K{\\geq}3{\\geq}2/6$ (onset $\\alpha{=}0.50$ seed-dependent: s42 1/6, s43 3/6).\nCross-method consensus ($K{\\geq}3$) exhibits seed-dependent variability at onset ($\\alpha{\\approx}0.50$), consistent with the noisy transition expected at phase boundaries, while remaining robust above onset ($K{\\geq}3$ ${\\geq}5/6$ at $\\alpha{=}0.75$).\nOn a unified 6-pair basis (MAUVE excluded due to systematic floor at ${\\sim}0.033$; Table~\\ref{tab:14b_phase}), third-seed replication (s44) at $T{=}10$ confirms ceiling detection above onset (6/6 at $\\alpha{\\geq}0.50$) with 0/6 at $\\alpha{=}0.45$, validating the blind zone.\nCross-$T$ improvement holds at 3/4 $\\alpha$ values ($\\alpha{=}0.45$: $0/6{\\to}5/6$; $\\alpha{=}0.60$: $6/6{\\to}6/6$; $\\alpha{=}0.75$: $6/6{\\to}6/6$), validating the predicted $\\alpha_c(T)$ decrease; at onset ($\\alpha{=}0.50$), PermG shows a marginal decrease ($6/6{\\to}3/6$), consistent with phase-boundary variability.\nAt onset ($\\alpha{=}0.45$--$0.50$), ECE-based pairs achieve higher detection rates than entropy-based pairs (e.g., 3/3 vs 0/3 robust at $\\alpha{=}0.50$, $T{=}15$), consistent with entropy's one-step saturation reducing temporal resolution at 1.4B scale.\n\n\\paragraph{Future work.}\nExtensions include multivariate VAR models for confounder testing, multi-seed replication across all six architecture families, longer training runs ($T{\\geq}20$), online monitoring within training pipelines, and accumulate-mode experiments~\\cite{dey2024breaking}.\nThe sigmoid onset boundary ($\\alpha_c{=}0.483$) invites connection to the critical mixture ratio scaling law of \\citet{gu2024cmr} and the data-mixing transitions of \\citet{gu2025datamixing}.\n\n\n\\section{Per-Method Dose-Response Profiles}\n\\label{app:dose_response}\n\nTable~\\ref{tab:dose_response_full} reports FDR significance counts (/8 validated pairs) for all five detection methods across 12 contamination levels (seed~42, Pythia-410M, WikiText, fp32).\nPermG exhibits a sharp 0$\\to$6 jump at $\\alpha{=}0.50$ with a return to 0 at $\\alpha{=}0.55$--$0.60$ (non-monotonic dip), while other methods show diffuse profiles: naive cross-correlation saturates at 7--8/8 across all levels including the null, and Toda--Yamamoto fluctuates without a clear onset.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-method FDR significance (/8 pairs) across contamination levels (Pythia-410M, seed~42, WikiText, fp32). PermG and Diff.\\ XCorr use BH-corrected FDR ($q{=}0.05$); Naive XCorr, Threshold, and TY use uncorrected $p{<}0.05$ (no FDR field in pipeline). $\\alpha{=}1.0$ from Pythia-410M cross-architecture condition (same seed/domain/precision).}\n\\label{tab:dose_response_full}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n$\\alpha$ & Naive & Diff.\\ XCorr & Threshold & PermG & TY$^\\S$ \\\\\n\\midrule\n0.00 & 8 & 4 & 3 & \\textbf{0} & 1 \\\\\n0.10 & 7 & 6 & 0 & \\textbf{0} & 0 \\\\\n0.25 & 8 & 3 & 0 & \\textbf{0} & 2 \\\\\n0.30 & 8 & 4 & 0 & \\textbf{0} & 3 \\\\\n0.35 & 8 & 4 & 0 & \\textbf{0} & 1 \\\\\n0.40 & 8 & 3 & 0 & \\textbf{0} & 4 \\\\\n0.45 & 8 & 6 & 0 & \\textbf{0} & 1 \\\\\n0.50 & 8 & 7 & 4 & \\textbf{6} & 3 \\\\\n0.55 & 8 & 8 & 0 & \\textbf{0} & 1 \\\\\n0.60 & 8 & 6 & 0 & \\textbf{0} & 0 \\\\\n0.75 & 7 & 6 & 0 & \\textbf{6} & 3 \\\\\n1.00 & 8 & 6 & 2 & \\textbf{6} & 1 \\\\\n\\bottomrule\n\\multicolumn{6}{l}{\\footnotesize $^\\S$TY directional assignment under verification; column retained for completeness.} \\\\\n\\end{tabular}}\n\\end{table}\n\nThe table highlights PermG's combination of null-control detection at 0/8 for this seed ($\\alpha{=}0.00$; pooled FPR across 6 seeds: 11.1\\%, lowest among directional methods), sharp onset (0$\\to$6 at $\\alpha{=}0.50$), and non-monotonic dip (0 at $\\alpha{=}0.55$--$0.60$), confirming it as the method whose dose-response profile most cleanly separates detection regimes.\nNaive cross-correlation's persistently high counts (7--8/8 even at $\\alpha{=}0.00$) demonstrate the 91.7\\% pooled null-control FPR reported in \\S\\ref{sec:method}.\n\n\n\\paragraph{Comparison with naive baselines.}\n\\label{app:naive_baselines}\n\nTable~\\ref{tab:naive_baselines} compares PermG against two practitioner-facing monitoring rules across 26 experiments (18~$\\alpha$ values, Pythia-410M, $T{=}10$, fp32).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Naive baseline comparison (Pythia-410M, $T{=}10$, fp32, 3 null-control runs).}\n\\label{tab:naive_baselines}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & FPR ($\\alpha{=}0$) & Onset $\\alpha$ \\\\\n\\midrule\nPPL-slope (${\\geq}2$ consec.\\ rises) & 100\\% (3/3) & 0.10 \\\\\nVariance-threshold ($2\\sigma$) & 67\\% (2/3) & 0.10 \\\\\nPermG (fwd ${\\geq}1$) & 0\\% (0/3) & 0.50 \\\\\n\\bottomrule\n\\multicolumn{3}{l}{\\footnotesize Onset $\\alpha$: lowest $\\alpha$ where method fires (seed~42).} \\\\\n\\end{tabular}\n\\end{table}\n\nPPL-slope fires at $\\alpha{=}0$ because the first-generation learning effect (perplexity drops from 26.9 to 19.3 at generation~1, then rises monotonically from generation~2 onward) produces consecutive rises indistinguishable from contamination-driven drift.\nVariance-threshold similarly triggers on the natural perplexity recovery.\nPermG avoids these false alarms by testing canary$\\to$downstream Granger precedence rather than univariate trend, thereby excluding training-drift confounds from the detection signal.\nNaive monitoring rules cannot distinguish contamination from natural training dynamics; formal statistical testing is necessary for controlled FPR.\n\n\n\\section{PermG Power Analysis}\n\\label{app:power_analysis}\n\nWe characterize PermG detection power via simulation under a controlled data-generating process (DGP) that matches the structure of our iterative training time series.\n\n\\paragraph{DGP.}\nFor each trial, we generate a bivariate system $(X_t, Y_t)$ for $t = 1, \\ldots, T$ where $X_t = \\mu + \\epsilon_t^X$ and $Y_t = \\mu + \\beta X_{t-1} + \\epsilon_t^Y$, with $\\epsilon \\sim \\mathcal{N}(0, \\sigma^2)$ and $\\sigma{=}1$.\nThe coupling parameter $\\beta$ controls signal strength; $\\beta{=}0$ is the null.\nThe linear coupling provides a power lower bound; nonlinear dynamics in actual iterative training may yield different power characteristics.\nWe sweep $\\beta \\in [0, 2]$ across $T \\in \\{6, 8, 10, 15, 20\\}$, running 100 replications per $(\\beta, T)$ cell with 5{,}000 permutations each and BH FDR correction at $q{=}0.05$ across 8 hypothetical pairs (matching the experimental setup).\n\n\\paragraph{Results.}\nTable~\\ref{tab:beta50} reports $\\beta_{50}$, the coupling strength required for 50\\% detection power, at each observation length $T$.\nUnder $\\sqrt{T}$ scaling, the product $\\beta_{50} \\cdot \\sqrt{T}$ should be constant; the observed decrease from 5.09 ($T{=}8$) to 2.68 ($T{=}20$) indicates that power grows faster than $\\sqrt{T}$, with the empirical scaling closer to $T^{-1.1}$.\nThe $\\sqrt{T}$ formula in \\S\\ref{sec:theory} thus provides a conservative lower bound on detection power: actual power at $T{=}20$ exceeds the $\\sqrt{T}$ prediction.\nFalse positive rates under FDR correction remain at or below 2\\% across all $T$ values (raw: 1--9\\%; Table~\\ref{tab:beta50}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{PermG power analysis: $\\beta_{50}$ (coupling for 50\\% power) under BH-FDR correction ($q{=}0.05$, 8 pairs). $\\beta_{50} \\cdot \\sqrt{T}$ decreases with $T$, indicating power grows faster than $\\sqrt{T}$. FPR: false positive rate at $\\beta{=}0$ (raw / FDR-corrected). Dashes indicate $<$50\\% power not reached within $\\beta \\leq 2.0$.}\n\\label{tab:beta50}\n\\begin{tabular}{lcccc}\n\\toprule\n$T$ & $\\beta_{50}$ & $\\beta_{50} \\cdot \\sqrt{T}$ & FPR (raw) & FPR (FDR) \\\\\n\\midrule\n6  & ---  & ---  & 1\\% & 0\\% \\\\\n8  & ---  & ---  & 6\\% & 2\\% \\\\\n10 & 2.0  & 6.32 & 9\\% & 2\\% \\\\\n15 & 1.2  & 4.65 & 6\\% & 2\\% \\\\\n20 & 0.9  & 4.02 & 5\\% & 1\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/permg_power_curve.pdf}\n\\caption{PermG detection power as a function of coupling strength $\\beta$ for five observation lengths ($T{=}6$--$20$; 100 replications $\\times$ 5{,}000 permutations, BH FDR $q{=}0.05$). Power increases with both $\\beta$ and $T$; at $T{=}6$--$8$, PermG remains underpowered ($<$20\\%) even at $\\beta{=}2.0$, consistent with the $T{=}10$ minimum required for reliable detection in our experimental setting.}\n\\label{fig:permg_power}\n\\end{figure*}\n\nAt $T{=}6$ and $T{=}8$, 50\\% power is not reached within $\\beta \\leq 2.0$ under FDR correction, explaining why PermG is fundamentally underpowered for very short series.\nThe practical implication for our $T{=}10$ setting: $\\beta_{50}{=}2.0$ means that only strong coupling produces reliable detection, consistent with the sharp onset at $\\alpha_c{\\approx}0.50$ where signal strength first exceeds this threshold.\nAt $T{=}20$, $\\beta_{50}$ drops to 0.9, predicting a left-shift of $\\alpha_c$ and broader detection coverage, as formalized in the detection boundary model (\\S\\ref{sec:theory}).\n\n\n\\section{Non-Stationarity Robustness Analysis}\n\\label{app:nonstationarity}\n\nWe assess PermG's size and power under controlled non-stationarity via Monte Carlo simulation, then compare to the empirical autocorrelation structure of our experimental series.\n\n\\paragraph{Simulation design.}\nWe generate bivariate AR(1) series with unidirectional coupling ($x \\to y$):\n$x_t = \\varphi x_{t-1} + \\varepsilon_t^x$, $y_t = \\varphi y_{t-1} + \\beta x_{t-1} + \\varepsilon_t^y$,\nwith $T{=}11$, 1{,}000 replications, and 500 permutations per replication.\nSize is evaluated under $H_0{:}\\;\\beta{=}0$; power under $H_1{:}\\;\\beta{=}0.6$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Size (FPR at $\\beta{=}0$) and power ($\\beta{=}0.6$) under stationary and non-stationary AR(1) DGP ($T{=}11$, 1{,}000 reps, 500 perms). First-differencing maintains nominal size across all $\\varphi$; PermG FPR inflates to ${\\sim}10\\%$ at $\\varphi{\\geq}0.95$.}\n\\label{tab:nonstationarity_sim}\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{3}{c}{Size (\\%, $\\beta{=}0$)} & \\multicolumn{3}{c}{Power (\\%, $\\beta{=}0.6$)} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\n$\\varphi$ & Raw GC & First-Diff & PermG & Raw GC & First-Diff & PermG \\\\\n\\midrule\n0.50 & 6.4 & 6.6 & 6.8 & 37.7 & 17.7 & 36.8 \\\\\n0.95 & 10.0 & 5.9 & 9.5 & 44.3 & 28.7 & 41.5 \\\\\n0.99 & 11.2 & 4.2 & 10.7 & 46.4 & 24.6 & 41.7 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt $\\varphi{=}0.50$ (stationary), all three methods achieve near-nominal size ($6.4$--$6.8\\%$ vs.\\ $5\\%$ nominal).\nUnder strong non-stationarity ($\\varphi{\\geq}0.95$), PermG FPR inflates to ${\\sim}10\\%$ because permutation shuffling destroys temporal autocorrelation, shifting the null distribution.\nFirst-differencing maintains proper size ($4.2$--$6.6\\%$) at the cost of reduced power ($17.7$--$28.7\\%$ vs.\\ PermG's $36.8$--$41.7\\%$).\nOur pipeline applies first-differencing \\emph{before} permutation testing, combining PermG's power advantage with differencing's size control; the simulation isolates each component to characterize the tradeoff.\n\n\\paragraph{Empirical autocorrelation.}\nTable~\\ref{tab:empirical_ar1} reports AR(1) coefficients from seven experimental conditions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Empirical AR(1) coefficients for token entropy (te) and distinct-1 (d1), raw and first-differenced series. High raw $\\varphi$ in d1 reflects deterministic iterative-training decline, not stochastic AR persistence; first-differencing reduces $\\varphi$ to $< 0.44$.}\n\\label{tab:empirical_ar1}\n\\begin{tabular}{llrcccc}\n\\toprule\nExperiment & $\\alpha$ & $T$ & te $\\varphi_{\\text{raw}}$ & d1 $\\varphi_{\\text{raw}}$ & te $\\varphi_{\\text{diff}}$ & d1 $\\varphi_{\\text{diff}}$ \\\\\n\\midrule\na000\\_s42 & 0.00 & 10 & $-0.51$ & $0.86$ & $-0.57$ & $-0.14$ \\\\\na025\\_s42 & 0.25 & 10 & $-0.34$ & $0.95$ & $-0.45$ & $0.19$ \\\\\na050\\_s42 & 0.50 & 10 & $-0.28$ & $0.87$ & $0.31$ & $0.10$ \\\\\na075\\_s42 & 0.75 & 10 & $0.14$ & $0.91$ & $0.88$ & $0.24$ \\\\\na100\\_s42 & 1.00 & 10 & $1.00$ & $0.89$ & $0.98$ & $0.18$ \\\\\nt20\\_a050 & 0.50 & 20 & $-0.10$ & $0.97$ & $-0.25$ & $0.44$ \\\\\nt20\\_a100 & 1.00 & 20 & $0.98$ & $0.81$ & $0.87$ & $0.14$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Adequacy argument.}\nUnder null conditions ($\\alpha{=}0.0$), where FPR is defined, token entropy exhibits $\\varphi{=}-0.51$ (anti-correlated, far from the $\\varphi{\\geq}0.95$ regime where simulation reveals FPR inflation); at $\\varphi{=}0.50$, PermG FPR is $6.8\\%$, near nominal.\nThe high raw $\\varphi$ in distinct-1 ($0.81$--$0.97$ across all $\\alpha$ including null) reflects deterministic iterative-training diversity decline---a monotonic trend driven by the training protocol---not stochastic AR persistence.\nDeterministic trends differ fundamentally from the stochastic AR(1) DGP: they produce predictable trajectories rather than autocorrelated noise, and first-differencing effectively removes them (first-differenced distinct-1 $\\varphi$ ranges $-0.14$ to $0.44$, mean ${\\sim}0.17$).\nOur empirical FPR of 4/36 (11.1\\%) across six null seeds---the lowest among directional methods---confirms adequate size control in our experimental setting; all four false positives occur in token\\_entropy$\\to$distinct pairs in the forward direction, suggesting a structural pattern rather than random Type~I error.\nWe note that $T{=}10$ (11 data points) yields high-variance AR(1) estimates; the cross-experiment pattern is more informative than individual values.\n\n\\paragraph{DGP limitation.}\nThe bivariate AR(1) with linear coupling is a simplification; actual iterative training involves nonlinear dynamics (mode amplification, threshold-dependent diversity loss).\nThese simulation results characterize PermG's behavior under controlled conditions, not exact calibration for the experimental setting; they provide a lower bound on size control because the linear DGP represents a worst case for permutation-based tests (smooth autocorrelation that permutation destroys).\n\n\n\\section{Shapley Value Analysis}\n\\label{app:shapley}\n\nWe quantify each method's marginal contribution to the MMCT ensemble using Shapley values~\\cite{shapley1953value}, computed via exact enumeration over all $2^5{=}32$ coalitions of the five detection methods.\nFor a coalition $S \\subseteq \\{m_1, \\ldots, m_5\\}$, we define two performance metrics: the false positive rate FPR($S$), computed from 6 null experiments ($\\alpha{=}0.0$, seeds 45--50; 36 null pairs on the 6-pair basis excluding mauve), and the false negative rate FNR($S$), computed from 45 signal experiments across all non-null $\\alpha$ levels (270 signal pairs for the 6-pair variant excluding mauve).\nThe Shapley value $\\phi_k$ for method $m_k$ is the weighted average of its marginal contribution across all coalitions; positive FPR-Shapley indicates the method \\emph{increases} false positives, while negative FNR-Shapley indicates it \\emph{reduces} false negatives.\nThe combined Shapley value $\\phi_k^{\\text{comb}} = \\phi_k^{\\text{FPR}} + \\phi_k^{\\text{FNR}}$ balances both error types, with more negative values indicating greater net benefit.\n\nTable~\\ref{tab:shapley_6pair} reports the 6-pair analysis (excluding mauve).\nDiffXCorr achieves the lowest (best) combined Shapley ($-0.299$), driven by near-zero FPR contribution ($+0.007$) and strong FNR reduction ($-0.306$); however, DiffXCorr cannot separate forward from reverse causation (Table~\\ref{tab:null_fpr_methods}).\nAmong directional methods, PermG ranks best ($-0.141$ combined), with a modest FPR contribution ($+0.039$, reflecting 4/36 null false positives) offset by substantial FNR reduction ($-0.180$).\nNaive cross-correlation is the worst contributor ($+0.190$), with its massive FPR Shapley ($+0.609$) overwhelming its FNR benefit ($-0.419$).\nThreshold onset contributes almost nothing useful ($+0.084$ combined; FPR $+0.111$, FNR $-0.027$), confirming the near-zero detection power reported in Table~\\ref{tab:method_comparison}.\nFigure~\\ref{fig:shapley} visualizes the decomposition.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Shapley value decomposition (6-pair, mauve excluded). FPR-Shapley computed from 6 null seeds (36 pairs); FNR-Shapley from 45 signal experiments (270 pairs). Combined = FPR + FNR (more negative = better). $2^5{=}32$ coalitions, exact enumeration.}\n\\label{tab:shapley_6pair}\n\\begin{tabular}{lccc}\n\\toprule\nMethod & $\\phi^{\\text{FPR}}$ & $\\phi^{\\text{FNR}}$ & $\\phi^{\\text{comb}}$ \\\\\n\\midrule\nNaive XCorr          & $+0.609$ & $-0.419$ & $+0.190$ \\\\\n\\textbf{Diff.\\ XCorr}& $\\mathbf{+0.007}$ & $\\mathbf{-0.306}$ & $\\mathbf{-0.299}$ \\\\\nThreshold ($3\\sigma$) & $+0.111$ & $-0.027$ & $+0.084$ \\\\\nPerm.\\ Granger       & $+0.039$ & $-0.180$ & $-0.141$ \\\\\nToda--Yamamoto       & $+0.150$ & $-0.069$ & $+0.082$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/shapley_method_contribution.pdf}\n\\caption{Shapley value decomposition of each method's marginal contribution to FPR (positive bars) and FNR (negative bars), computed from 6 null seeds (36 pairs) and 45 signal experiments (270 pairs). DiffXCorr achieves the best combined Shapley ($-0.299$) via near-zero FPR; PermG ranks second ($-0.141$) as the best directional method.}\n\\label{fig:shapley}\n\\end{figure*}\n\nThe 8-pair variant (including mauve) yields qualitatively identical rankings: PermG remains the best contributor ($\\phi^{\\text{comb}}{=}-0.152$), naive cross-correlation the worst ($+0.170$), and threshold onset near-zero ($+0.063$).\n\n\\paragraph{FDR correction scope.}\nThis analysis applies BH-corrected significance (\\texttt{significant\\_fdr}) uniformly across all five methods, including naive cross-correlation and Toda--Yamamoto.\nIn contrast, the per-method dose-response profiles (Table~\\ref{tab:dose_response_full}) use uncorrected significance for naive cross-correlation, threshold onset, and Toda--Yamamoto because FDR-corrected fields are not available in the per-experiment pipeline output for these methods.\nThe Shapley analysis recomputes significance from raw $p$-values with BH correction applied post hoc, ensuring a fair comparison across methods within the coalition framework.\n\n\n\\section{MMCT Weight Robustness Ablation}\n\\label{app:weight_robustness}\n\nThe detection results reported in the main text use equal-weight majority voting ($K{\\geq}3$ of 5 methods, each contributing at most one vote per pair); PermG contributes at most $1/5 = 20\\%$ of the consensus weight.\nFPR-inverse weighting is used \\emph{only} in the exploratory method ranking below, not in the detection results.\nTo verify that PermG's top ranking is not an artifact of the FPR-inverse weighting scheme, we recompute Shapley values under four weight specifications (Table~\\ref{tab:weight_robustness}).\nEqual weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first ($\\phi^{\\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.\nUnder cap-5, the margin widens to 0.043 as the FPR penalty begins to differentiate high-FPR methods.\nCap-10 and original cap-100 yield identical Shapley values because the consensus threshold ($K{\\geq}3$) is determined by the three smallest method weights ($w_{\\text{naive}}{+}w_{\\text{diff}}{+}w_{\\text{thresh}} = 7.76$), which are invariant to further increases in the PermG or TY cap; this saturation confirms that the original $w{=}100$ does not artificially inflate PermG's contribution.\n% TODO-D219: recompute weight robustness table with 6-seed data; PermG φ^FPR will be >0\nAcross all schemes, PermG's advantage derives from the same structural property: zero FPR ($\\phi^{\\text{FPR}}{=}0$) combined with moderate FNR reduction ($\\phi^{\\text{FNR}}{=}-0.152$ to $-0.426$).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{MMCT weight robustness: PermG combined Shapley under four weighting schemes. PermG ranks first in all cases. Gap = $|\\phi^{\\text{comb}}_{\\text{PermG}} - \\phi^{\\text{comb}}_{\\text{runner-up}}|$. 48 experiments (3 null + 45 signal), exact Shapley enumeration ($2^5{=}32$ coalitions).}\n\\label{tab:weight_robustness}\n\\begin{tabular}{lrcrc}\n\\toprule\nScheme & $w_{\\text{PermG}}$ & $\\phi^{\\text{comb}}_{\\text{PermG}}$ & Runner-up & Gap \\\\\n\\midrule\nEqual ($w{=}1$)     & 1   & $-0.152$ & NaiveXCorr ($-0.137$) & 0.015 \\\\\nCap-5               & 5   & $-0.165$ & NaiveXCorr ($-0.123$) & 0.043 \\\\\nCap-10              & 10  & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\nFPR-inv.\\ (cap-100) & 100 & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{PermG FPR Independence Analysis}\n\\label{app:fpr_independence}\n\nTable~\\ref{tab:null_fpr_methods} reports null-control FPR for all five detection methods across six seeds ($6 \\times 6 = 36$ pairs, 6-pair basis excluding mauve).\nUnder identical BH-FDR correction ($q{=}0.05$), DiffXCorr achieves the lowest FPR (1/36, 2.8\\%) but lacks directional separation; PermG (4/36, 11.1\\%) is the lowest among directional methods.\nAll four PermG false positives occur in token\\_entropy$\\to$distinct pairs (seeds~45 and 50, forward direction only), suggesting a structural pattern concentrated in a single canary--downstream pair type.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Null-control FPR by method ($\\alpha{=}0.0$, 6~seeds 45--50, 6~pairs each). All p-value--based methods (DiffXCorr, PermG, TY) report BH-FDR--corrected rejections at $q{=}0.05$ for fair comparison. Threshold uses a deterministic $3\\sigma$ criterion; NaiveXCorr uses uncorrected correlation significance.}\n\\label{tab:null_fpr_methods}\n\\begin{tabular}{llrr}\n\\toprule\nMethod & Criterion & Rejections (/36) & FPR (\\%) \\\\\n\\midrule\nDiff.\\ XCorr$^\\dagger$ & BH-FDR & 1 & 2.8 \\\\\n\\textbf{Perm.\\ Granger} & \\textbf{BH-FDR} & \\textbf{4} & \\textbf{11.1} \\\\\nThreshold & $3\\sigma$ (det.) & 10 & 27.8 \\\\\nToda--Yamamoto & BH-FDR & 14 & 38.9 \\\\\nNaive XCorr & uncorr. & 33 & 91.7 \\\\\n\\bottomrule\n\\multicolumn{4}{l}{\\footnotesize $^\\dagger$Bidirectional; cannot separate forward from reverse.} \\\\\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cluster adjustment.}\nThe 36 null-control pairs are nested within 6~seeds (6~pairs per seed), introducing within-seed correlation.\nWithin-seed ICC${=}0.14$ yields an effective sample size $N_{\\text{eff}} \\approx 21$ (from $N_{\\text{eff}} = N / [1 + (m-1) \\cdot \\text{ICC}]$ where $N{=}36$, $m{=}6$).\nUnder the Clopper--Pearson exact method with $N_{\\text{eff}}{=}21$ and 4 successes (scaled), the cluster-adjusted 95\\% CI is $[1.2\\%, 30.4\\%]$, compared to $[3.1\\%, 26.1\\%]$ under independence ($N{=}36$).\nThe lower ICC compared to the 3-seed pilot ($0.14$ vs.\\ $0.34$) reflects greater between-seed consistency with six independent replications.\n\n\\paragraph{Direction filtering.}\nForward-direction filtering (retaining only pairs with peak lag${<}0$ for cross-correlation methods) reduces null-control $K{\\geq}3$ false positives.\nUnder the 6-seed, 6-pair basis, $K{\\geq}3$ consensus with filtering produces 6/36 false positives (16.7\\%; detail below); the 3-seed pilot underestimated this rate (0/8).\nDetection at $\\alpha{\\geq}0.50$ is unaffected: $K{\\geq}3$ counts are identical with and without direction filtering at all signal levels.\n\n\\paragraph{$K{\\geq}3$ false positive detail.}\nUnder the 6-pair basis (6~seeds, 36~pairs), $K{\\geq}3$ consensus produces 6 false positives (FPR${=}16.7\\%$).\nOf these, 4 are driven by naive cross-correlation, threshold onset, and Toda--Yamamoto (PermG does \\emph{not} vote); the remaining 2 (seeds~45 and 50, te$\\to$distinct) include PermG in the consensus.\nPermG thus contributes to only 2 of 6 consensus false positives, confirming that most $K{\\geq}3$ FPR is driven by the high-FPR methods (naive, threshold, TY).\n\n\\paragraph{Sensitivity to FPR assumption.}\nEven under the conservative upper bound of the cluster-adjusted CI (30.4\\%), PermG remains the lowest-FPR directional method: DiffXCorr achieves a lower FPR under identical BH-FDR correction (2.8\\%) but lacks forward/reverse separation; the next directional method (threshold onset) has 27.8\\% and Toda--Yamamoto 38.9\\%.\nOur primary results rely on equal-weight $K{\\geq}3$ majority voting, where each method contributes exactly one vote regardless of its FPR---this mechanism is completely unaffected by any FPR assumption.\nFor the exploratory FPR-inverse weighting, PermG's weight ($w{=}1/0.111{=}9.0$) exceeds all directional alternatives (threshold: 3.6, TY: 2.6, naive: 1.1); DiffXCorr ($w{=}1/0.028{=}35.7$) receives a higher weight but lacks directional separation, preserving PermG's rank among directional methods.\nThe insensitivity of both the voting mechanism and the method ranking to the upper CI bound provides evidence that the MMCT conclusions are robust to uncertainty in PermG's Type~I error rate.\n\n\\section{Sigmoid Transition Shape}\n\\label{app:sigmoid_shape}\n\nSigmoid regression on the original 13-point $T{=}10$ grid yields $\\alpha_c = 0.483 \\pm 0.006$ but $k = 478 \\pm 475$ ($\\mathrm{SE}(k) \\approx k$), indicating that the coarse grid cannot constrain the transition shape.\nDense $\\alpha$ sampling (17~values at $T{=}10$) resolves this ambiguity: formal likelihood-ratio testing strongly favors a smooth sigmoid over a literal step function ($\\Delta\\mathrm{AIC}{=}-110$), with fitted steepness $k{=}15.7$ (95\\% CI $[9.4, 28.2]$).\nThe transition is steep but finite-width, not a literal discontinuity.\nThis observed steepness exceeds what smooth signal models predict: VAR(1) simulations under H0 (linear, $k{=}6.1$) and H0$'$ (concave, $k{=}4.9$) produce onset sigmoids with $k{=}4.9$--$6.1$ (\\S\\ref{app:power_sim}), yielding steepness ratios $k_{\\mathrm{obs}} / k_{\\mathrm{H0}} \\approx 2.6$--$3.2$ (CI lower bound ratio ${\\approx}2$).\nWe do not fit a combined $T{=}10 + T{=}20$ sigmoid because $\\alpha{=}0.45$ yields contradictory counts under the two sequence lengths (0/8 vs.\\ 5/8), reflecting genuine power dependence on $T$ rather than a single dose-response curve.\n\n\n\\section{Intervention Threshold Sensitivity}\n\\label{app:intervention_sensitivity}\n\n\\paragraph{Within-$\\alpha$ sensitivity at $\\alpha{=}1.0$.}\nTable~\\ref{tab:threshold_sensitivity} reports the predictive cessation outcome under five entropy-drop thresholds (5\\%--25\\%) at $\\alpha{=}1.0$ (Pythia-410M, seed~42).\nAll five thresholds produce identical outcomes: token entropy drops 40.7\\% at generation~1, far exceeding even the most conservative threshold (25\\%), so every threshold triggers at the same generation.\nThe intervention conclusion---peak perplexity 57.0, recovery in one generation, final perplexity 21.3---is invariant to threshold choice within this range.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Threshold sensitivity at $\\alpha{=}1.0$ (Pythia-410M, s42, fp32). All thresholds trigger at generation~1 (entropy drop 40.7\\%$\\gg$threshold), producing identical recovery trajectories.}\n\\label{tab:threshold_sensitivity}\n\\begin{tabular}{rccr}\n\\toprule\nThreshold & Trigger gen & Peak PPL & Final PPL \\\\\n\\midrule\n5\\%  & 1 & 56.99 & 21.29 \\\\\n10\\% & 1 & 56.99 & 21.29 \\\\\n15\\% & 1 & 56.99 & 21.29 \\\\\n20\\% & 1 & 56.99 & 21.29 \\\\\n25\\% & 1 & 56.99 & 21.29 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cross-$\\alpha$ operating band.}\nThe within-$\\alpha$ analysis establishes threshold invariance at $\\alpha{=}1.0$ but does not address whether thresholds generalize across contamination levels.\nWe examine observed entropy trajectories from the alpha sweep (not actual intervention experiments at $\\alpha{<}1.0$) to characterize the operating band.\nThe maximum entropy drop across 10 generations varies by contamination level: 7.5\\% at $\\alpha{=}0.0$ (fine-tuning drift only), 7.7\\% at $\\alpha{=}0.10$, 7.8\\% at $\\alpha{=}0.25$, 22.4\\% at $\\alpha{=}0.50$, 35.3\\% at $\\alpha{=}0.75$, and 62.1\\% at $\\alpha{=}1.0$.\nThresholds below 7.5\\% (e.g., 5\\%) trigger on clean training data---a false alarm.\nThresholds above 22.4\\% (e.g., 25\\%) miss $\\alpha{=}0.50$, the lowest contamination level with meaningful entropy signal.\nThe safe operating band is therefore $[10\\%, 22\\%]$: any threshold in this range produces zero false alarms on $\\alpha{=}0.0$ while detecting contamination at $\\alpha{\\geq}0.50$.\nThe reported 15\\% threshold sits near the center of this band.\nThis analysis is based on entropy trajectories from non-intervention training runs; whether actual intervention at $\\alpha{<}1.0$ would produce the same triggering behavior remains unvalidated.\n\n\n\\section{Channel Effect Size Analysis}\n\\label{app:channel_effect_size}\n\nFirst-differencing eliminates all canary$\\to$perplexity Granger associations while preserving canary$\\to$diversity leads (\\S\\ref{sec:regime}).\nWe present three lines of evidence that this asymmetry reflects a genuine temporal structure difference rather than selective power loss from differencing.\n\n\\paragraph{Correlation retention parity.}\nFirst-differencing retains comparable correlation magnitude for both channel types (Table~\\ref{tab:channel_retention}).\nDiversity channels ($n{=}243$ pairs across all non-null experiments) retain a median $|r|$ of 0.952 after differencing, while perplexity channels ($n{=}8$ pairs; limited sample) retain 1.00.\nThis parity rules out a blanket power-loss explanation: if differencing selectively destroyed perplexity signal, $|r|$ retention would be substantially lower for perplexity than for diversity.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{First-differencing effect by channel type. $|r|$ retention = diff $|r|$ / naive $|r|$. Despite comparable $|r|$ retention, Granger $F$ differs by an order of magnitude. Perplexity channel has limited sample ($n{=}8$); all paired comparisons are from bf16 experiments.}\n\\label{tab:channel_retention}\n\\begin{tabular}{lrccrc}\n\\toprule\nChannel & $n$ & Naive $|r|$ & Diff $|r|$ & Retention & Med.\\ $F$ \\\\\n\\midrule\nDiversity   & 243 & 0.943 & 0.921 & 0.952 & 67.8 \\\\\nPerplexity  & 8   & 0.924 & 0.900 & 1.002 & 11.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Granger $F$-statistic asymmetry.}\nWithin matched experiments (same model, seed, $\\alpha$, precision), the Granger $F$-statistic is $20$--$28{\\times}$ higher for diversity than perplexity channels.\nAt $\\alpha{=}0.60$ (s42, bf16): diversity mean $F{=}229.4$ versus perplexity mean $F{=}8.3$ (ratio $27.8{\\times}$).\nAt $\\alpha{=}1.0$ reactive (s43, bf16): diversity mean $F{=}236.4$ versus perplexity mean $F{=}11.5$ (ratio $20.6{\\times}$).\nSince $|r|$ retention is comparable across channels, this $F$-statistic gap cannot be attributed to differencing-induced signal loss; it must reflect a difference in the temporal structure that Granger tests evaluate.\n\n\\paragraph{Temporal structure: lagged vs.\\ contemporaneous.}\nThe lag distribution of peak differenced cross-correlations reveals the structural difference.\nFor diversity channels, 81\\% of peak correlations occur at canary-leading lags (lag${<}0$), with a median lag of $-1$ generation---consistent with the one-generation temporal precedence visible in Figure~\\ref{fig:metric_trajectory}.\nFor perplexity channels, 50\\% of peak correlations occur at lag${=}0$ (contemporaneous co-movement), with a median lag of $0$.\nGranger precedence tests lagged predictive improvement; contemporaneous co-movement produces low $F$-statistics regardless of signal magnitude, which is the correct behavior for a test designed to detect temporal precedence.\nThe perplexity channel sample is limited ($n{=}8$ pairs from bf16 experiments), and these lag distributions should not be generalized to fp32 conditions without further validation.\n\n\n\\section{Mutual Information Analysis}\n\\label{app:mi_analysis}\n\nWe estimate the Gaussian mutual information lower bound between token entropy (canary) and each diversity metric across contamination levels, using $T{=}11$ data points per series ($T{=}10$ for two conditions).\nThe Gaussian estimator $\\hat{I}_G = -\\frac{1}{2}\\log_2(1 - r^2)$, where $r$ is the Pearson correlation, provides a conservative lower bound on MI; we do not report KSG nonparametric estimates due to uncorrected positive bias at $T{=}11$.\nThe $\\alpha{=}0.05$ data point is excluded because it uses an experiment excluded from the dose-response analysis.\n\nTable~\\ref{tab:mi_bounds} reports the mean Gaussian MI across the three distinct-$n$ metrics for each $\\alpha$ level.\nMI follows a V-shaped curve: it drops from 0.112~bits at $\\alpha{=}0.10$ to a minimum of 0.010~bits at $\\alpha{=}0.25$, then rises monotonically to 0.270~bits at $\\alpha{=}0.75$.\nMI remains positive throughout the blind zone ($\\alpha \\leq 0.45$; range 0.010--0.141~bits), confirming that canary--diversity coupling exists below the detection threshold but falls below PermG's statistical power floor at $T{=}10$.\nThere is no discontinuity at $\\alpha_c \\approx 0.50$: the detection onset reflects power accumulation, not an abrupt change in information coupling.\nBootstrap 95\\% CIs span 1--3 orders of magnitude at $T{=}11$, so individual point estimates should be interpreted cautiously.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Gaussian MI lower bound (bits) between token entropy and distinct-$n$ diversity metrics ($T{=}11$, Pythia-410M, fp32). Mean across distinct-1/2/3; $\\alpha{=}0.05$ excluded (see text). CIs omitted due to width at $T{=}11$.}\n\\label{tab:mi_bounds}\n\\begin{tabular}{rrc}\n\\toprule\n$\\alpha$ & Seeds & MI (bits) \\\\\n\\midrule\n0.10 & 2 & 0.112 \\\\\n0.25 & 3 & 0.010 \\\\\n0.30 & 1 & 0.062 \\\\\n0.35 & 1 & 0.098 \\\\\n0.40 & 1 & 0.119 \\\\\n0.45 & 2 & 0.141 \\\\\n0.50 & 3 & 0.107 \\\\\n0.60 & 2 & 0.209 \\\\\n0.75 & 1 & 0.270 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Moment Cascade Analysis}\n\\label{app:moment_cascade}\n\nWe analyze the temporal ordering of metric degradation onset across 6 WikiText seed${\\times}\\alpha$ conditions (2 seeds $\\times$ 3 non-trivial $\\alpha$ levels each) to test whether token entropy consistently degrades before diversity metrics.\nOnset is defined as the first generation where a metric's cumulative change exceeds 5\\% of its generation-0 value.\n\nTable~\\ref{tab:moment_cascade} reports the onset generation for each metric across conditions.\nToken entropy reaches onset at generation~1 in all 6 conditions; distinct-$n$ metrics reach onset at generation~2 in all 18 pairwise comparisons (6 conditions $\\times$ 3 distinct-$n$ metrics).\nAcross these 18 comparisons, entropy degrades first in 16 cases (Kendall $\\tau{=}0.337$, consistent with a weak but reliable temporal ordering).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Degradation onset generation (5\\% threshold) by metric and condition (Pythia-410M, WikiText, fp32). Token entropy reaches onset at generation~1 in all non-null conditions; distinct-$n$ metrics follow at generation~2.}\n\\label{tab:moment_cascade}\n\\begin{tabular}{llcccccc}\n\\toprule\nSeed & $\\alpha$ & Entropy & Dist-1 & Dist-2 & Dist-3 & ECE & PPL \\\\\n\\midrule\n42 & 0.10 & 1 & 2 & 2 & 2 & 2 & --- \\\\\n42 & 0.50 & 1 & 2 & 2 & 2 & 1 & 4 \\\\\n42 & 0.75 & 1 & 2 & 2 & 2 & 1 & 1 \\\\\n43 & 0.25 & 1 & 2 & 2 & 2 & 4 & --- \\\\\n43 & 0.50 & 1 & 2 & 2 & 2 & 1 & 4 \\\\\n43 & 0.75 & 1 & 2 & 2 & 2 & 1 & 1 \\\\\n\\bottomrule\n\\multicolumn{8}{l}{\\footnotesize ---: onset not reached within $T{=}10$ generations.} \\\\\n\\end{tabular}\n\\end{table}\n\nThe cascade ordering provides evidence for the canary mechanism independent of Granger-type tests: it does not depend on first-differencing, lag selection, or the permutation null distribution.\nECE shows onset at generation~1 at $\\alpha{\\geq}0.50$ (both seeds), consistent with its role as a secondary canary metric.\nAt low contamination ($\\alpha{=}0.10$ and $\\alpha{=}0.25$), perplexity never reaches the 5\\% onset threshold within $T{=}10$ generations, while entropy already shows generation-1 onset---consistent with entropy's higher sensitivity to distributional shifts.\n\n\n\\section{Cascade Ordering Theory: Proofs}\n\\label{app:cascade_theory}\n\nThis section provides the full proofs for Proposition~\\ref{thm:entropy_leads} and Proposition~\\ref{prop:div_lag} from \\S\\ref{sec:cascade}, plus supporting results.\n\n\\begin{assumption}[Mode Amplification]\\label{ass:mode_amp}\nThe training map $\\mathcal{T}$ redistributes probability mass from low-probability to high-probability tokens: there exists a threshold $\\bar{p}$ such that $\\mathcal{T}(p)_i > p_i \\Rightarrow p_i \\geq \\bar{p}$ and $\\mathcal{T}(p)_j < p_j \\Rightarrow p_j \\leq \\bar{p}$.\n\\end{assumption}\n\nThis captures the standard finite-capacity approximation effect: MLE on finite samples from a peaked distribution amplifies modes and suppresses the tail~\\cite{shumailov2024curse,dohmatob2024tale}.\n\n\\begin{proposition}[Entropy is a first-order indicator]\\label{prop:entropy_first}\nLet $p \\in \\Delta^{V-1}$ and $\\delta = \\alpha(\\mathcal{T}(p) - p)$ be a mode-amplifying perturbation with $\\sum_i \\delta_i = 0$. Then $\\Delta H = H(p+\\delta) - H(p) = -\\sum_i \\delta_i \\log p_i + O(\\|\\delta\\|^2) < 0$.\n\\end{proposition}\n\n\\begin{proof}\nTaylor-expanding $H$ around $p$:\n$H(p+\\delta) = H(p) - \\sum_i \\delta_i \\log p_i - \\sum_i \\delta_i - \\frac{1}{2}\\sum_i \\delta_i^2/p_i + O(\\|\\delta\\|^3)$.\nSince $\\sum_i \\delta_i = 0$: $\\Delta H = -\\sum_i \\delta_i \\log p_i - \\frac{1}{2}\\sum_i \\delta_i^2/p_i + O(\\|\\delta\\|^3)$.\nUnder mode amplification, tokens gaining mass ($\\delta_i > 0$) have $p_i \\geq \\bar{p}$ (hence $\\log p_i \\geq \\log \\bar{p}$) and tokens losing mass ($\\delta_j < 0$) have $p_j \\leq \\bar{p}$ (hence $\\log p_j \\leq \\log \\bar{p}$).\nWriting $m = \\sum_{i:\\delta_i > 0} \\delta_i$: $-\\sum_i \\delta_i \\log p_i = -m[\\overline{\\log p}^{+} - \\overline{\\log p}^{-}] < 0$, where $\\overline{\\log p}^{\\pm}$ are the $|\\delta|$-weighted means over gaining/losing tokens.\nThe second-order Fisher information term $-\\frac{1}{2}\\sum_i \\delta_i^2/p_i$ is always negative, reinforcing the decrease.\n\\end{proof}\n\n\\begin{proposition}[Diversity is a threshold indicator]\\label{prop:div_threshold}\nDefine the $\\epsilon$-effective support $S_\\epsilon(p) = |\\{i \\in [V]: p_i > \\epsilon\\}|$, where $\\epsilon \\approx c/N$ is the generation threshold for sample size $N$.\nUnder the same perturbation $\\delta$: $\\Delta S_\\epsilon = -|\\{i: p_i > \\epsilon \\text{ and } p_i + \\delta_i \\leq \\epsilon\\}|$.\nThis equals zero whenever $\\|\\delta\\|_\\infty < \\gamma(p,\\epsilon) := \\min_{i: p_i > \\epsilon}(p_i - \\epsilon)$.\n\\end{proposition}\n\n\\begin{proof}\nToken $i$ exits the effective support iff $p_i > \\epsilon$ and $p_i + \\delta_i \\leq \\epsilon$, requiring $|\\delta_i| \\geq p_i - \\epsilon$.\nIf $\\|\\delta\\|_\\infty < \\gamma$, no token satisfies this condition.\n\\end{proof}\n\n\\paragraph{Proof of Proposition~\\ref{thm:entropy_leads}.}\n\\emph{Part (a):} Take any mode-amplifying $\\delta$ with $\\|\\delta\\|_\\infty < \\gamma(p,\\epsilon)$.\nBy Proposition~\\ref{prop:div_threshold}, $\\Delta S_\\epsilon = 0$.\nBy Proposition~\\ref{prop:entropy_first}, $\\Delta H < 0$.\nSuch $\\delta$ exists for all $\\alpha < \\gamma / \\max_i |\\mathcal{T}(p)_i - p_i|$.\n\\emph{Part (b):} If $\\Delta S_\\epsilon < 0$, some token $k$ has $p_k > \\epsilon$ but $p_k + \\delta_k \\leq \\epsilon$, so $\\delta_k < 0$.\nUnder mode amplification, this implies $p_k \\leq \\bar{p}$; the total mass transferred to high-probability tokens ensures $\\overline{\\log p}^+ > \\overline{\\log p}^-$.\nBy Proposition~\\ref{prop:entropy_first}, $\\Delta H < 0$. $\\square$\n\n\\paragraph{Proof of Proposition~\\ref{prop:div_lag}.}\nBy the margin condition, at every generation $s \\leq t_H$ the perturbation norm $\\alpha\\|\\mathcal{T}(p_s) - p_s\\|_\\infty$ is less than $\\gamma(p_s, \\epsilon)$.\nBy Proposition~\\ref{prop:div_threshold}, no token exits the effective support at any $s \\leq t_H$, so $\\Delta S_\\epsilon = 0$ for all $s \\leq t_H$.\nSince time is discrete, $t_D \\geq t_H + 1$. $\\square$\n\n\\paragraph{ECE co-movement (qualitative argument).}\nUnder conditional mode amplification (peakier $q_\\theta(\\cdot|x)$ at each generation), per-token conditional entropy $h(x) = H(q_\\theta(\\cdot|x))$ decreases while confidence $c(x) = \\max_y q_\\theta(y|x) \\geq \\exp(-h(x))$ increases.\nAveraging: $\\bar{H}_t$ decreases, $C_t$ increases.\nWith accuracy approximately stationary in early collapse ($A_t \\approx A_0$), $\\Delta\\mathrm{ECE} \\approx \\Delta C_t > 0$ whenever $\\Delta\\bar{H}_t < 0$.\nThis argument establishes the direction of co-movement; the quantitative relationship depends on distribution geometry.\n$\\bar{H}_t$ denotes mean conditional entropy $\\mathbb{E}_{x \\sim p_{\\text{eval}}}[h(x)]$, which differs from the marginal entropy $H_t = -\\sum_i p_t(i)\\log p_t(i)$ used in Proposition~\\ref{thm:entropy_leads}; under mode amplification, both decrease monotonically, so the cascade ordering is consistent across both formulations.\n\n\\paragraph{MAUVE ordering (conjecture).}\nMAUVE measures divergence in a discretized embedding space via $k$-means quantization.\nMAUVE onset requires token-level shifts (detected by entropy) to propagate through $n$-gram distributions (detected by distinct-$n$) to aggregate embedding distributions.\nEmpirically, MAUVE onset lags diversity by 0--1 generations on WikiText; however, on C4, MAUVE onset occurs at generation~1 (simultaneous with entropy), suggesting this lag is corpus-dependent.\n\n\\paragraph{Empirical support.}\nAmong 15 experiments at $\\alpha \\geq 0.30$ (where entropy perturbation exceeds the detection threshold), cascade ordering $t_H \\leq t_D$ holds in 14/15 cases (GPT-2-medium s43 fp32 exhibits bidirectional Granger significance).\nTable~\\ref{tab:cascade_onset} reports onset generations for representative conditions, showing uniform Phase~1/2/3 ordering.\nFive low-$\\alpha$ experiments ($\\alpha \\leq 0.25$) show entropy perturbation below the detection threshold (gen-1 deviation $<2\\sigma$); cascade ordering is neither confirmed nor refuted in this regime.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cascade onset generations (5\\% threshold) for representative experiments (Pythia-410M, WikiText, fp32). Phase~1: entropy and ECE ($t_H$, $t_{\\mathrm{ECE}}$); Phase~2: diversity ($t_D$, min over distinct-$n$); Phase~3: MAUVE ($t_M$). All conditions confirm the predicted ordering $t_H = t_{\\mathrm{ECE}} \\leq t_D \\leq t_M$.}\n\\label{tab:cascade_onset}\n\\begin{tabular}{llcccc}\n\\toprule\nSeed & $\\alpha$ & $t_H$ & $t_{\\mathrm{ECE}}$ & $t_D$ & $t_M$ \\\\\n\\midrule\n42 & 0.50 & 1 & 1 & 2 & 3 \\\\\n43 & 0.50 & 1 & 1 & 2 & 2 \\\\\n42 & 0.75 & 1 & 1 & 2 & 3 \\\\\n43 & 0.75 & 1 & 1 & 2 & 2 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\phantomsection\\label{app:alpha_c_proof}\n\\paragraph{Proof of Proposition~\\ref{prop:phase-boundary}.}\nAt the detection threshold, $\\mathrm{Power}(\\alpha_c, T) = \\pi^*$.\nSince $\\alpha_c$ lies below the non-monotonic dip region ($\\alpha_c < 0.55$), the signal model applies directly.\nFrom the power function $\\mathrm{Power} = \\Phi(S(\\alpha) \\cdot \\sqrt{T} / \\sigma)$, setting $S(\\alpha_c) \\cdot \\sqrt{T} / \\sigma = z^*$ and substituting the signal model $S(\\alpha) = c\\,\\alpha^\\beta$ yields $c\\,\\alpha_c^\\beta = z^* \\sigma / \\sqrt{T}$.\nSolving: $\\alpha_c(T) = (z^* \\sigma / c)^{1/\\beta} \\cdot T^{-1/(2\\beta)}$, giving the stated form with exponent $\\gamma = 1/(2\\beta)$.\n\n\\paragraph{Calibration and consistency.}\nCross-$T$ validation avoids the circularity of fitting theory to model-extrapolated points.\nWe fit $P(\\mathrm{det}|\\alpha,T) = \\Phi(A \\cdot \\alpha^\\beta \\cdot \\sqrt{T} - z_0)$ to training data at $T \\in \\{10, 20\\}$ via profile likelihood over $(\\beta, \\alpha_\\infty)$, with $\\alpha_\\infty{=}0$ emerging as the optimum.\nThe held-out test set ($T \\in \\{5, 15\\}$) yields MAE${=}0.106$ with 95\\% CI coverage $6/6$: the model correctly predicts all $0/8$ at $T{=}5$ and detection at $T{=}15$ (predicted $0.49$--$0.71$ vs.\\ observed $6/8{=}0.75$; under-prediction reflects the $P_{\\max}{=}0.75$ ceiling from MAUVE saturation, which is modeled separately).\nA linear signal model ($\\beta{=}1$, $\\gamma{=}0.5$) is rejected.\nThe sub-linear exponent $\\beta{=}0.24$ implies that doubling contamination increases signal by only $2^{0.24} \\approx 1.18\\times$ (18\\%); since $\\alpha_\\infty{\\approx}0$, any nonzero contamination produces signal, but detection requires sufficient $T$ to amplify it.\nAt $T{=}5$, $\\alpha_c \\geq 1.0$: no contamination level is detectable, consistent with the insufficient statistical power at very short observation windows.\n\n\\paragraph{Leave-one-$T$-out cross-validation.}\nWe evaluate model generalization via leave-one-$T$-out CV on the $5T \\times 3\\alpha$ grid (sync-dip $\\alpha{=}0.60$ excluded; 15 cells).\nFor each fold, one observation length is held out and the probit model $P = P_{\\max} \\cdot \\Phi(A \\cdot \\alpha^{0.24} \\cdot \\sqrt{T} - z_0)$ is refit on the remaining data.\nOverall MAE${=}0.037$ with 95\\% CI coverage $15/15$.\nWhen sync-dip cells are included (20 cells), MAE rises to $0.203$ (CI $16/20$), with the largest residuals at sync-dip cells (predicted $0.75$, observed $0/8$).\nThe profile likelihood over $\\beta$ yields MLE $\\hat{\\beta}{=}0.66$ (95\\% CI $[0.24, 0.78]$); the wide interval reflects a flat likelihood surface, indicating that $\\beta$ is not well-identified from these data.\nModel comparison (AIC, 15-cell grid excluding sync-dip): $M_1$ (linear boundary) $\\Delta\\mathrm{AIC}{=}0.0$; $M_2$ (power-probit) $\\Delta\\mathrm{AIC}{=}2.43$.\nIncluding sync-dip data reverses the ranking ($M_2$ $\\Delta\\mathrm{AIC}{=}0.0$, $M_1$ $\\Delta\\mathrm{AIC}{=}4.15$), because the probit model naturally accommodates the dip's dissolution at higher $T$ while linear models cannot.\n\n\\section{Power Simulation: Shape Comparison}\n\\label{app:power_sim}\n\nTo assess whether the observed steep detection onset could arise from smooth signal models, we simulate PermG detection under three null hypotheses (1{,}000 replications per cell, $n_{\\text{perm}}{=}1{,}000$, $n_{\\text{pairs}}{=}8$, BH-FDR $q{=}0.05$):\n\n\\begin{itemize}\n\\item \\textbf{H0} (linear): $S(\\alpha) = c \\cdot \\alpha$, calibrated so $S(1.0) = S_{\\max}$.\n\\item \\textbf{H0$'$} (concave): $S(\\alpha) = c \\cdot \\alpha^{0.5}$, sub-linear but smooth.\n\\item \\textbf{H1} (step): $S(\\alpha) = S_{\\max} \\cdot \\mathbf{1}[\\alpha > \\alpha_c(T)]$, binary activation.\n\\end{itemize}\n\n\\noindent\\textbf{Scaling exponents.}\nAll three models produce apparent onset scaling in $T$: H0 $\\gamma{=}0.85$, H0$'$ $\\gamma{=}1.87$, H1 $\\gamma{=}1.96$ (observed: $\\gamma{=}2.08$).\nH0$'$ produces $\\gamma$ within $0.21$ of the observed value, demonstrating that the scaling exponent alone cannot distinguish smooth from step-function boundaries.\n\n\\noindent\\textbf{Shape differences.}\nAt $T{=}10$, $\\alpha{=}0.45$: H0 predicts 27\\% detection rate, H0$'$ predicts 45\\%, H1 predicts 5.5\\%, observed $0/8$.\nAt $T{=}10$, $\\alpha{=}0.50$: H0 predicts 36\\%, H0$'$ predicts 48\\%, H1 predicts 4.6\\%, observed $6/8$ (75\\%).\nSmooth models produce onset ramps with $k{=}4.9$--$6.1$ (H0$'$: $k{=}4.93$, $R^2{=}0.9974$; H0: $k{=}6.14$, $R^2{=}0.9998$); the observed onset steepness ($k{=}15.7$) is ${\\approx}3{\\times}$ higher.\n\n\\noindent\\textbf{Metric-specific ceiling.}\nAt high $\\alpha$ (${\\geq}0.75$) with $T{\\geq}20$, H0 and H0$'$ (which simulate 8 equal-signal pairs) reach mean detection fractions of $0.79$--$0.98$ (${\\approx}6.3$--$7.8/8$), whereas observed counts never exceed $6/8$.\nThis gap reflects metric structure rather than signal saturation: the 2/8 non-detected pairs consistently involve MAUVE, whose floor saturation (\\S\\ref{sec:t20}) prevents Granger detection regardless of signal strength.\n\n\\section{T=20 Predict-then-Verify Comparison}\n\\label{app:t20_comparison}\n\nTable~\\ref{tab:t20_comparison} reports the predict-then-verify results for the $T{=}20$ extension experiments.\nPredictions are derived from the detection boundary model (\\S\\ref{sec:theory}): detected pairs at $T{=}10$ are predicted to remain detected (saturated $F$-statistics), and undetected pairs are predicted to remain undetected (structural nulls or non-monotonic dip).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{T=20 predict-then-verify comparison (Pythia-410M, seed~42, WikiText, fp32). Excluding $\\alpha{=}1.0$, two of four predictions fall within CI ($\\alpha{=}0.50$, $0.75$); boundary cases show systematic bias---$\\alpha{=}0.45$ falsifies the ceiling hypothesis (under-prediction), $\\alpha{=}0.60$ over-predicts under raw $p$-values (v1; matches under FDR v2, not pre-committed).}\n\\label{tab:t20_comparison}\n\\begin{tabular}{lcccc}\n\\toprule\n$\\alpha$ & $T{=}10$ & Predicted $T{=}20$ & Observed $T{=}20$ & Match \\\\\n\\midrule\n0.45 & 0/8 & 0/8 (ceiling) & 5/8 & $\\times$ \\\\\n0.50 & 6/8 & 6/8 (saturated) & 6/8 & \\checkmark \\\\\n0.60 & 0/8 & 3/8 (v1 raw)$^\\dagger$ & 0/8 & $\\times$ \\\\\n0.75 & 6/8 & 6/8 (saturated) & 6/8 & \\checkmark \\\\\n1.00 & 6/8 & 6/8 (saturated) & 6/8 & \\checkmark \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\footnotesize $^\\dagger$V2 (BH--FDR corrected, created 44\\,min pre-analysis, not git-committed) predicts 0/8, matching observation.} \\\\\n\\end{tabular}\n\\end{table}\n\nAt $\\alpha \\geq 0.50$, consistency across $T{=}10$ and $T{=}20$ supports the detection boundary prediction: PermG counts are determined by signal structure, not observation length.\nSix diversity-based pairs show $F{=}449$--$2947$ at $T{=}20$ (all $\\gg F_{\\text{crit}}$); two MAUVE-based pairs show $F{<}2$ regardless of $T$, driven by floor saturation ($\\mu{=}0.029$, 100\\% ${<}0.05$) rather than high variance (CV$_{\\text{MAUVE}}{=}0.089$ vs CV$_{\\text{distinct-1}}{=}0.139$); SNR: MAUVE $4.68$ vs diversity $6.40$--$8.20$ ($p{<}0.001$).\nThe sole exception is $\\alpha{=}0.45$ at $T{=}20$ (5/8), consistent with boundary proximity.\nAt $\\alpha{=}0.45$, the shift from 0/8 to 5/8 falsifies Model~A (ceiling: $\\alpha{=}0.45$ structurally undetectable) in favor of Model~B (power-limited: $\\sqrt{T}$ boost crosses the detection threshold), lowering $\\alpha_c$ below~0.45.\nThe $\\alpha{=}0.60$ non-monotonic dip persists at $T{=}20$ (s42: 0/8; s43: 3/8) but dissolves at $T{=}25$ (5/8), confirming that $\\sqrt{T}$ power scaling eventually overcomes the dip; alternative methods detect signal throughout (DiffXCorr 6/8, TY 5/8 at $T{=}20$).\nPermG directional selectivity is consistent across tested $T$ ($T{=}10$, $20$): forward 6/8 versus reverse 0/8 at $\\alpha \\in \\{0.50, 0.75, 1.0\\}$.\n\n\n\\subsection{Prediction Timeline}\n\\label{app:t20_prediction_timeline}\n\nTwo versions of the $T{=}20$ prediction file exist, reflecting an evolving statistical protocol:\n\n\\paragraph{V1 (git-committed, \\texttt{bad72cc}).} Predictions derived from $T{=}10$ PermG results using \\emph{raw} $p$-values. At $\\alpha{=}0.60$, v1 counted 3/8 pairs with raw $p{<}0.05$, predicting 3/8 detections at $T{=}20$. The observed result (0/8 FDR-significant) does not match.\n\n\\paragraph{V2 (pre-analysis, not committed).} A revised file incorporating BH--FDR correction at $q{=}0.05$, consistent with the correction applied throughout the paper. Under FDR, $\\alpha{=}0.60$ drops from 3/8 (raw) to 0/8, matching the observation. V2 was created 44 minutes before the formal $T{=}20$ analysis began (filesystem timestamp) but was not git-committed, and therefore lacks the cryptographic verifiability of v1.\n\n\\paragraph{Scoring.} Primary (v1, committed): 3/5 exact matches ($\\alpha \\in \\{0.50, 0.75, 1.0\\}$, all saturated regimes). Excluding $\\alpha{=}1.0$, two of four predictions fall within CI. Both boundary predictions miss: $\\alpha{=}0.45$ (predicted 0/8, observed 5/8) falsifies the ceiling hypothesis in favor of $\\sqrt{T}$ power scaling; $\\alpha{=}0.60$ (predicted 3/8, observed 0/8) over-estimates detection due to the non-monotonic dip. Sensitivity (v2, FDR-corrected): 4/5 ($\\alpha{=}0.60$ matches). The systematic conservative bias at $\\alpha{=}0.45$ is consistent with the $\\sqrt{T}$ power increase predicted by Proposition~\\ref{prop:phase-boundary}.\n\n\n\\phantomsection\\label{app:task_degradation}\n\\paragraph{Task degradation.}\n\nTable~\\ref{tab:task_degradation} reports end-of-training task performance (generation~10, Pythia-410M, seed~42, fp32) across contamination levels.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Task degradation across contamination levels (Pythia-410M, seed~42, fp32, generation~10). Perplexity evaluated on held-out WikiText-103.}\n\\label{tab:task_degradation}\n\\begin{tabular}{lcc}\n\\toprule\n$\\alpha$ & Perplexity & Next-token acc. \\\\\n\\midrule\nBaseline & 26.6 & 0.390 \\\\\n0.05 & 20.8 & 0.431 \\\\\n0.25 & 22.9 & 0.424 \\\\\n0.46 & 31.6 & 0.400 \\\\\n0.50 & 31.3 & 0.399 \\\\\n0.52 & 41.1 & 0.389 \\\\\n0.60 & 53.5 & 0.375 \\\\\n0.75 & 80.3 & 0.354 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt $\\alpha{=}0.05$, perplexity improves over the uncontaminated baseline (20.8 vs.\\ 26.6), consistent with a mild data augmentation effect.\nThe sharpest degradation occurs between $\\alpha{=}0.50$ and $0.52$ ($+31\\%$ perplexity), aligning with the PermG detection onset (\\S\\ref{sec:regime}).\n\n\\section{Cross-Architecture FPR Sensitivity}\n\\label{app:cross_arch_fpr}\n\nAs preliminary cross-architecture evidence, we evaluate null-condition ($\\alpha{=}0$) false positive rates on GPT-2-medium (345M; OpenAI), a model outside the Pythia family used for all primary experiments.\nTwo seeds (s42, s43) are trained for $T{=}10$ generations under the same protocol as the Pythia-410M null runs.\nThis evaluation requires additional replication across architectures and seed counts before drawing definitive conclusions.\n\n\\begin{table}[h]\n\\centering\n\\caption{Null-condition FPR for GPT-2-medium ($\\alpha{=}0$, $T{=}10$, 6-pair basis). PermG forward detection shows extreme seed dependence; $K{\\geq}3$ consensus remains at 0\\% across both seeds.}\n\\label{tab:gpt2m_null_fpr}\n\\begin{tabular}{lccc}\n\\toprule\nSeed & PermG fwd & PermG rev & $K{\\geq}3$ \\\\\n\\midrule\ns42 & 6/6 (100\\%) & 0/6 & 0/6 \\\\\ns43 & 0/6 (0\\%) & 0/6 & 0/6 \\\\\n\\midrule\nPooled & 6/12 (50\\%) & 0/12 & 0/12 (0\\%) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe pooled PermG FPR is dramatically higher than on Pythia-410M (50\\% vs.\\ 11.1\\%, 6-pair basis) and shows extreme seed dependence (100\\% vs.\\ 0\\%).\nThis instability traces to the magnitude of null drift in GPT-2-medium's output distribution, which is substantially stronger than in Pythia-410M (Table~\\ref{tab:null_drift_comparison}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Null drift magnitude ($\\alpha{=}0$, gen\\,0$\\to$10; GPT-2-medium: 2 seeds; Pythia-410M: 4 seeds, s46/s48--s50). GPT-2-medium exhibits ${\\sim}4{\\times}$ stronger entropy drift and ${\\sim}7{\\times}$ stronger distinct-3 drift than Pythia-410M.}\n\\label{tab:null_drift_comparison}\n\\begin{tabular}{lcccc}\n\\toprule\n& \\multicolumn{2}{c}{GPT-2-medium} & \\multicolumn{2}{c}{Pythia-410M} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nMetric & gen\\,0 & gen\\,10 (\\%$\\Delta$) & gen\\,0 & gen\\,10 (\\%$\\Delta$) \\\\\n\\midrule\nToken entropy & 3.57 & 2.84 ($-$20.5\\%) & 3.23 & 3.076 ($-$4.9\\%) \\\\\nDistinct-3 & 0.84 & 0.54 ($-$35.8\\%) & 0.81 & 0.769 ($-$4.9\\%) \\\\\n$\\Delta$entropy (gen\\,0$\\to$1) & \\multicolumn{2}{c}{$-$0.60} & \\multicolumn{2}{c}{$-$0.25} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nGPT-2-medium's distinct-3 declines from 0.84 to 0.54 over ten null generations ($-$35.8\\%), compared with 0.81$\\to$0.77 ($-$4.9\\%) for Pythia-410M.\nThis steep diversity collapse under pure retraining, absent any synthetic contamination, creates a strong downward trend that PermG's permutation test interprets as a directional signal.\nThe initial entropy drop (gen\\,0$\\to$1: $-$0.60 vs.\\ $-$0.25) is similarly amplified, consistent with architecture-specific sensitivity to iterative retraining rather than a deficiency in the detection method.\n\nThe $K{\\geq}3$ multi-method consensus maintains 0\\% FPR on GPT-2-medium (0/12 pairs), though the margin of safety is narrow: in the worst case (s42), 2 of 5 methods vote for forward detection, one vote short of the $K{\\geq}3$ threshold.\nThis provides some protection against architecture-specific distributional variation, but two seeds constitute only preliminary evidence.\nFor reference, PermG successfully detects true contamination signal ($\\alpha{=}1.0$) on GPT-2-medium with 6/8 forward pairs (Table~\\ref{tab:generalization}), confirming that the method works when signal is present; the elevated null FPR is specific to the null condition where architecture-dependent drift dominates.\n\n\\section*{Use of AI Assistants}\n\\label{app:ai-assistants}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant throughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections, polishing prose, and reformatting LaTeX.\n    \\item \\textbf{Literature:} summarizing related papers to inform related-work section.\n\\end{itemize}\n\n",
    "structuredPatch": [
      {
        "oldStart": 755,
        "oldLines": 7,
        "newStart": 755,
        "newLines": 7,
        "lines": [
          " \\label{fig:shapley}",
          " \\end{figure*}",
          " ",
          "-The 8-pair variant (including mauve) yields qualitatively identical rankings: PermG remains the best contributor ($\\phi^{\\text{comb}}{=}-0.152$), naive cross-correlation the worst ($+0.170$), and threshold onset near-zero ($+0.063$).",
          "+The 8-pair variant (including mauve) yields qualitatively identical rankings: DiffXCorr remains the best contributor ($\\phi^{\\text{comb}}{=}-0.263$), PermG the best directional method ($-0.112$), naive cross-correlation the worst ($+0.157$), and threshold onset near-zero ($+0.073$).",
          " ",
          " \\paragraph{FDR correction scope.}",
          " This analysis applies BH-corrected significance (\\texttt{significant\\_fdr}) uniformly across all five methods, including naive cross-correlation and Toda--Yamamoto."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---


### Assistant

_source line 126_

Now TODO-D219 #6 — Weight robustness paragraph (L779).

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "8c624eae-b699-4f76-b2d5-5bb1390a232b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017wEevDh3uRmhaE4mrkWwY7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 369,
      "cache_read_input_tokens": 113302,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 369
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool call

_source line 127_

<details open><summary>🔧 Tool call — Read · `toolu_01W3UiLVoHbNeYdUmgt92AUH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
  "offset": 770,
  "limit": 30
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "356fb67e-4f16-435f-aece-11a78a059e6e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017wEevDh3uRmhaE4mrkWwY7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 369,
      "cache_read_input_tokens": 113302,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 369
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool result

_source line 128 · 2026-05-24T09:06:40.661Z_

<details><summary>↩ Tool result · `toolu_01W3UiLVoHbNeYdUmgt92AUH`</summary>

```text
770	FPR-inverse weighting is used \emph{only} in the exploratory method ranking below, not in the detection results.
771	To verify that PermG's top ranking is not an artifact of the FPR-inverse weighting scheme, we recompute Shapley values under four weight specifications (Table~\ref{tab:weight_robustness}).
772	Equal weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first ($\phi^{\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.
773	Under cap-5, the margin widens to 0.043 as the FPR penalty begins to differentiate high-FPR methods.
774	Cap-10 and original cap-100 yield identical Shapley values because the consensus threshold ($K{\geq}3$) is determined by the three smallest method weights ($w_{\text{naive}}{+}w_{\text{diff}}{+}w_{\text{thresh}} = 7.76$), which are invariant to further increases in the PermG or TY cap; this saturation confirms that the original $w{=}100$ does not artificially inflate PermG's contribution.
775	% TODO-D219: recompute weight robustness table with 6-seed data; PermG φ^FPR will be >0
776	Across all schemes, PermG's advantage derives from the same structural property: zero FPR ($\phi^{\text{FPR}}{=}0$) combined with moderate FNR reduction ($\phi^{\text{FNR}}{=}-0.152$ to $-0.426$).
777	
778	\begin{table}[h]
779	\centering
780	\small
781	\caption{MMCT weight robustness: PermG combined Shapley under four weighting schemes. PermG ranks first in all cases. Gap = $|\phi^{\text{comb}}_{\text{PermG}} - \phi^{\text{comb}}_{\text{runner-up}}|$. 48 experiments (3 null + 45 signal), exact Shapley enumeration ($2^5{=}32$ coalitions).}
782	\label{tab:weight_robustness}
783	\begin{tabular}{lrcrc}
784	\toprule
785	Scheme & $w_{\text{PermG}}$ & $\phi^{\text{comb}}_{\text{PermG}}$ & Runner-up & Gap \\
786	\midrule
787	Equal ($w{=}1$)     & 1   & $-0.152$ & NaiveXCorr ($-0.137$) & 0.015 \\
788	Cap-5               & 5   & $-0.165$ & NaiveXCorr ($-0.123$) & 0.043 \\
789	Cap-10              & 10  & $-0.426$ & TY ($-0.067$)         & 0.359 \\
790	FPR-inv.\ (cap-100) & 100 & $-0.426$ & TY ($-0.067$)         & 0.359 \\
791	\bottomrule
792	\end{tabular}
793	\end{table}
794	
795	
796	\section{PermG FPR Independence Analysis}
797	\label{app:fpr_independence}
798	
799	Table~\ref{tab:null_fpr_methods} reports null-control FPR for all five detection methods across six seeds ($6 \times 6 = 36$ pairs, 6-pair basis excluding mauve).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "23a0007d-f7e4-4e50-bcde-45e6e399f96e",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
      "content": "FPR-inverse weighting is used \\emph{only} in the exploratory method ranking below, not in the detection results.\nTo verify that PermG's top ranking is not an artifact of the FPR-inverse weighting scheme, we recompute Shapley values under four weight specifications (Table~\\ref{tab:weight_robustness}).\nEqual weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first ($\\phi^{\\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.\nUnder cap-5, the margin widens to 0.043 as the FPR penalty begins to differentiate high-FPR methods.\nCap-10 and original cap-100 yield identical Shapley values because the consensus threshold ($K{\\geq}3$) is determined by the three smallest method weights ($w_{\\text{naive}}{+}w_{\\text{diff}}{+}w_{\\text{thresh}} = 7.76$), which are invariant to further increases in the PermG or TY cap; this saturation confirms that the original $w{=}100$ does not artificially inflate PermG's contribution.\n% TODO-D219: recompute weight robustness table with 6-seed data; PermG φ^FPR will be >0\nAcross all schemes, PermG's advantage derives from the same structural property: zero FPR ($\\phi^{\\text{FPR}}{=}0$) combined with moderate FNR reduction ($\\phi^{\\text{FNR}}{=}-0.152$ to $-0.426$).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{MMCT weight robustness: PermG combined Shapley under four weighting schemes. PermG ranks first in all cases. Gap = $|\\phi^{\\text{comb}}_{\\text{PermG}} - \\phi^{\\text{comb}}_{\\text{runner-up}}|$. 48 experiments (3 null + 45 signal), exact Shapley enumeration ($2^5{=}32$ coalitions).}\n\\label{tab:weight_robustness}\n\\begin{tabular}{lrcrc}\n\\toprule\nScheme & $w_{\\text{PermG}}$ & $\\phi^{\\text{comb}}_{\\text{PermG}}$ & Runner-up & Gap \\\\\n\\midrule\nEqual ($w{=}1$)     & 1   & $-0.152$ & NaiveXCorr ($-0.137$) & 0.015 \\\\\nCap-5               & 5   & $-0.165$ & NaiveXCorr ($-0.123$) & 0.043 \\\\\nCap-10              & 10  & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\nFPR-inv.\\ (cap-100) & 100 & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{PermG FPR Independence Analysis}\n\\label{app:fpr_independence}\n\nTable~\\ref{tab:null_fpr_methods} reports null-control FPR for all five detection methods across six seeds ($6 \\times 6 = 36$ pairs, 6-pair basis excluding mauve).",
      "numLines": 30,
      "startLine": 770,
      "totalLines": 1269
    }
  }
}
```

</details>

---


### Assistant

_source line 129_

<details><summary>Logged reasoning block</summary>

```text
The weight robustness table uses a different value function (weighted K≥3 voting) from the union-based main Shapley table. I can't recompute the weight robustness without the full per-pair signal data.

Looking at the weight robustness table, it was computed with old null data (3 seeds, 24 pairs with FPR=0 for PermG). With the new null data (6 seeds, 36 pairs, PermG FPR=4/36=11.1%), the numbers in this table would change. But I can't recompute them.


I'm weighing whether to remove the TODO and add a note about the old null data, or keep the analysis as-is since the weighted Shapley results might differ from the union-based findings anyway. The safest move is probably to document that this analysis used the 3-seed null data and acknowledge that the conclusions about PermG's ranking advantage could shift with the updated data. the weight robustness table uses 3-seed null data, and I need to remove the "zero FPR" claim since the expanded 6-seed analysis shows PermG actually has a +0.039 FPR. I'll note that DiffXCorr emerges as the best contributor in the updated union-based analysis, but acknowledge that the weight robustness question itself needs recomputation with the new null data to properly address whether PermG's ranking holds across different weighting schemes.

Now I'm realizing the core issue: the weight robustness table's main conclusion—that PermG ranks first regardless of weighting—is no longer valid since DiffXCorr is now the top-ranked method overall. Rather than presenting an outdated table, I should either recompute it with the new null data or reframe what the table is actually testing. The weight robustness table was designed to test whether PermG's top ranking depended on the FPR-inverse weighting scheme, but that premise no longer holds since DiffXCorr now ranks higher in the union-based Shapley analysis. I should reframe this section to acknowledge the null data limitation and clarify that the weight robustness analysis is examining PermG's performance as a directional method rather than claiming it's the overall best approach.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "fd6f1ebd-5233-41e0-82a7-f85ba6c82970",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NruZszM5mbrkZcgpTC8KNc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1075,
      "cache_read_input_tokens": 113671,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1075
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool call

_source line 130_

<details open><summary>🔧 Tool call — Edit · `toolu_01Vh662it3kVHvovhuimAQ9Q`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
  "old_string": "To verify that PermG's top ranking is not an artifact of the FPR-inverse weighting scheme, we recompute Shapley values under four weight specifications (Table~\\ref{tab:weight_robustness}).\nEqual weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first ($\\phi^{\\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.\nUnder cap-5, the margin widens to 0.043 as the FPR penalty begins to differentiate high-FPR methods.\nCap-10 and original cap-100 yield identical Shapley values because the consensus threshold ($K{\\geq}3$) is determined by the three smallest method weights ($w_{\\text{naive}}{+}w_{\\text{diff}}{+}w_{\\text{thresh}} = 7.76$), which are invariant to further increases in the PermG or TY cap; this saturation confirms that the original $w{=}100$ does not artificially inflate PermG's contribution.\n% TODO-D219: recompute weight robustness table with 6-seed data; PermG φ^FPR will be >0\nAcross all schemes, PermG's advantage derives from the same structural property: zero FPR ($\\phi^{\\text{FPR}}{=}0$) combined with moderate FNR reduction ($\\phi^{\\text{FNR}}{=}-0.152$ to $-0.426$).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{MMCT weight robustness: PermG combined Shapley under four weighting schemes. PermG ranks first in all cases. Gap = $|\\phi^{\\text{comb}}_{\\text{PermG}} - \\phi^{\\text{comb}}_{\\text{runner-up}}|$. 48 experiments (3 null + 45 signal), exact Shapley enumeration ($2^5{=}32$ coalitions).}\n\\label{tab:weight_robustness}\n\\begin{tabular}{lrcrc}\n\\toprule\nScheme & $w_{\\text{PermG}}$ & $\\phi^{\\text{comb}}_{\\text{PermG}}$ & Runner-up & Gap \\\\\n\\midrule\nEqual ($w{=}1$)     & 1   & $-0.152$ & NaiveXCorr ($-0.137$) & 0.015 \\\\\nCap-5               & 5   & $-0.165$ & NaiveXCorr ($-0.123$) & 0.043 \\\\\nCap-10              & 10  & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\nFPR-inv.\\ (cap-100) & 100 & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}",
  "new_string": "To verify that PermG's directional-method ranking is not an artifact of the FPR-inverse weighting scheme, we recompute weighted Shapley values under four weight specifications (Table~\\ref{tab:weight_robustness}).\nThis analysis uses the 3-seed null control (seeds 42/43/44, 24 pairs), under which PermG had zero FPR; the union-based analysis with 6-seed null (Table~\\ref{tab:shapley_6pair}) yields a non-zero PermG FPR Shapley ($+0.039$) and shifts the overall best contributor to DiffXCorr ($-0.299$).\nEqual weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first among directional methods ($\\phi^{\\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.\nUnder cap-5, the margin widens to 0.043 as the FPR penalty begins to differentiate high-FPR methods.\nCap-10 and original cap-100 yield identical Shapley values because the consensus threshold ($K{\\geq}3$) is determined by the three smallest method weights ($w_{\\text{naive}}{+}w_{\\text{diff}}{+}w_{\\text{thresh}} = 7.76$), which are invariant to further increases in the PermG or TY cap; this saturation confirms that the original $w{=}100$ does not artificially inflate PermG's contribution.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{MMCT weight robustness (3-seed null, 48 experiments): PermG combined Shapley under four weighting schemes. PermG ranks first among directional methods in all cases. Gap = $|\\phi^{\\text{comb}}_{\\text{PermG}} - \\phi^{\\text{comb}}_{\\text{runner-up}}|$. $2^5{=}32$ coalitions, exact enumeration.}\n\\label{tab:weight_robustness}\n\\begin{tabular}{lrcrc}\n\\toprule\nScheme & $w_{\\text{PermG}}$ & $\\phi^{\\text{comb}}_{\\text{PermG}}$ & Runner-up & Gap \\\\\n\\midrule\nEqual ($w{=}1$)     & 1   & $-0.152$ & NaiveXCorr ($-0.137$) & 0.015 \\\\\nCap-5               & 5   & $-0.165$ & NaiveXCorr ($-0.123$) & 0.043 \\\\\nCap-10              & 10  & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\nFPR-inv.\\ (cap-100) & 100 & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "1fdf444c-45a4-447d-8a5f-d68535be74ba",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NruZszM5mbrkZcgpTC8KNc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1075,
      "cache_read_input_tokens": 113671,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1075
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool result

_source line 131 · 2026-05-24T09:07:30.724Z_

<details><summary>↩ Tool result · `toolu_01Vh662it3kVHvovhuimAQ9Q`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "2ed97fee-9048-413a-9c72-bf2627dbca62",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
    "oldString": "To verify that PermG's top ranking is not an artifact of the FPR-inverse weighting scheme, we recompute Shapley values under four weight specifications (Table~\\ref{tab:weight_robustness}).\nEqual weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first ($\\phi^{\\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.\nUnder cap-5, the margin widens to 0.043 as the FPR penalty begins to differentiate high-FPR methods.\nCap-10 and original cap-100 yield identical Shapley values because the consensus threshold ($K{\\geq}3$) is determined by the three smallest method weights ($w_{\\text{naive}}{+}w_{\\text{diff}}{+}w_{\\text{thresh}} = 7.76$), which are invariant to further increases in the PermG or TY cap; this saturation confirms that the original $w{=}100$ does not artificially inflate PermG's contribution.\n% TODO-D219: recompute weight robustness table with 6-seed data; PermG φ^FPR will be >0\nAcross all schemes, PermG's advantage derives from the same structural property: zero FPR ($\\phi^{\\text{FPR}}{=}0$) combined with moderate FNR reduction ($\\phi^{\\text{FNR}}{=}-0.152$ to $-0.426$).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{MMCT weight robustness: PermG combined Shapley under four weighting schemes. PermG ranks first in all cases. Gap = $|\\phi^{\\text{comb}}_{\\text{PermG}} - \\phi^{\\text{comb}}_{\\text{runner-up}}|$. 48 experiments (3 null + 45 signal), exact Shapley enumeration ($2^5{=}32$ coalitions).}\n\\label{tab:weight_robustness}\n\\begin{tabular}{lrcrc}\n\\toprule\nScheme & $w_{\\text{PermG}}$ & $\\phi^{\\text{comb}}_{\\text{PermG}}$ & Runner-up & Gap \\\\\n\\midrule\nEqual ($w{=}1$)     & 1   & $-0.152$ & NaiveXCorr ($-0.137$) & 0.015 \\\\\nCap-5               & 5   & $-0.165$ & NaiveXCorr ($-0.123$) & 0.043 \\\\\nCap-10              & 10  & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\nFPR-inv.\\ (cap-100) & 100 & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}",
    "newString": "To verify that PermG's directional-method ranking is not an artifact of the FPR-inverse weighting scheme, we recompute weighted Shapley values under four weight specifications (Table~\\ref{tab:weight_robustness}).\nThis analysis uses the 3-seed null control (seeds 42/43/44, 24 pairs), under which PermG had zero FPR; the union-based analysis with 6-seed null (Table~\\ref{tab:shapley_6pair}) yields a non-zero PermG FPR Shapley ($+0.039$) and shifts the overall best contributor to DiffXCorr ($-0.299$).\nEqual weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first among directional methods ($\\phi^{\\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.\nUnder cap-5, the margin widens to 0.043 as the FPR penalty begins to differentiate high-FPR methods.\nCap-10 and original cap-100 yield identical Shapley values because the consensus threshold ($K{\\geq}3$) is determined by the three smallest method weights ($w_{\\text{naive}}{+}w_{\\text{diff}}{+}w_{\\text{thresh}} = 7.76$), which are invariant to further increases in the PermG or TY cap; this saturation confirms that the original $w{=}100$ does not artificially inflate PermG's contribution.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{MMCT weight robustness (3-seed null, 48 experiments): PermG combined Shapley under four weighting schemes. PermG ranks first among directional methods in all cases. Gap = $|\\phi^{\\text{comb}}_{\\text{PermG}} - \\phi^{\\text{comb}}_{\\text{runner-up}}|$. $2^5{=}32$ coalitions, exact enumeration.}\n\\label{tab:weight_robustness}\n\\begin{tabular}{lrcrc}\n\\toprule\nScheme & $w_{\\text{PermG}}$ & $\\phi^{\\text{comb}}_{\\text{PermG}}$ & Runner-up & Gap \\\\\n\\midrule\nEqual ($w{=}1$)     & 1   & $-0.152$ & NaiveXCorr ($-0.137$) & 0.015 \\\\\nCap-5               & 5   & $-0.165$ & NaiveXCorr ($-0.123$) & 0.043 \\\\\nCap-10              & 10  & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\nFPR-inv.\\ (cap-100) & 100 & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}",
    "originalFile": "\\appendix\n\n\\section{Training Details and Metric Drift}\n\\label{app:training_details}\n\\label{app:drift}\n\n\\paragraph{Hyperparameters.}\nEach generation fine-tunes for 5{,}000 steps using AdamW (learning rate $5 \\times 10^{-5}$, 500 warmup steps, weight decay $0.01$, batch size 4 for Pythia-410M, 32 for GPT-2-medium).\nGeneration uses temperature $1.0$, top-$k{=}50$, max length 512 tokens, producing 5{,}000 samples per generation from 5{,}000-sample subsets of WikiText-103.\nCanary metrics: token entropy $H(p_\\theta | \\text{context})$ over 1{,}000 held-out samples; ECE with 15 bins.\nAdditional downstream metrics (distinct-3, effective rank, Self-BLEU) appear in subsequent appendix sections.\n\n\\paragraph{Metric drift.}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Metric drift (\\%, generation~0$\\to$10) for Pythia-410M across contamination levels. Diversity collapse occurs at all $\\alpha$ levels, with the strongest decline at low-to-moderate contamination ($\\alpha{=}0.25$: distinct-1 $-40.3{\\pm}0.3\\%$) rather than full replacement ($\\alpha{=}1.0$: $-27.8{\\pm}1.6\\%$). $^\\dagger$$\\alpha{=}0.10$: single seed (seed~42, preliminary). $\\alpha{=}0.00$, $\\alpha{=}0.25$, $\\alpha{=}0.50$, $\\alpha{=}0.75$: 3-seed mean${\\pm}$std (seeds 42, 43, 44); $\\alpha{=}1.0$: 4-seed mean${\\pm}$std (seeds 42, 43, 44, 45).}\n\\label{tab:drift_summary}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n$\\alpha$ & Entropy & ECE & Distinct-1 & Distinct-2 & Perplexity \\\\\n\\midrule\n0.00 & $-4.6{\\pm}0.4$ & $+37.6{\\pm}14$ & $-14.1{\\pm}0.4$ & $-9.6{\\pm}0.4$ & $-20.6{\\pm}1.0$ \\\\\n0.10$^\\dagger$ & $-5.3$ & $+57$ & $-39.6$ & $-56.4$ & $-21.0$ \\\\\n0.25 & $-4.7{\\pm}0.5$ & $+81.8{\\pm}15.9$ & $-40.3{\\pm}0.3$ & $-56.4{\\pm}0.7$ & $-18.1{\\pm}0.8$ \\\\\n0.50 & $-18.0{\\pm}0.5$ & $+822.6{\\pm}18.3$ & $-37.1{\\pm}0.4$ & $-50.4{\\pm}1.0$ & $+21.0{\\pm}0.1$ \\\\\n0.75 & $-27.6{\\pm}0.2$ & $+1791{\\pm}18$ & $-32.3{\\pm}0.5$ & $-41.0{\\pm}1.0$ & $+182.6{\\pm}0.7$ \\\\\n1.00 & $-60.8{\\pm}1.2$ & $+3780{\\pm}30$ & $-27.8{\\pm}1.6$ & $-34.0{\\pm}3.3$ & $+3674{\\pm}45$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\n\\section{Distinct-3 Results}\n\\label{app:distinct3}\n\nTable~\\ref{tab:distinct3_drift} reports distinct-3 drift across all contamination levels.\nDistinct-3 exhibits the largest absolute decline among diversity metrics at low contamination ($-58.9{\\pm}0.9\\%$ at $\\alpha{=}0.25$) but attenuates at higher levels ($-30.5\\%$ at $\\alpha{=}1.0$), consistent with the diversity--calibration dissociation discussed in \\S\\ref{sec:discussion}.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Distinct-3 drift (\\%, generation~0$\\to$10) across contamination levels. $\\alpha{=}0.00$, $\\alpha{=}0.25$, $\\alpha{=}0.75$: 3-seed mean${\\pm}$std; $\\alpha{=}1.0$: 4-seed mean${\\pm}$std; $\\alpha{=}0.50$: single seed.}\n\\label{tab:distinct3_drift}\n\\begin{tabular}{lc}\n\\toprule\n$\\alpha$ & Distinct-3 drift (\\%) \\\\\n\\midrule\n0.00 & $-4.4{\\pm}0.5$ \\\\\n0.25 & $-58.9{\\pm}0.9$ \\\\\n0.50 & $-52.4$ \\\\\n0.75 & $-38.6{\\pm}1.3$ \\\\\n1.00 & $-30.5{\\pm}4.0$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Lead-lag analysis.}\nAt $\\alpha{=}1.0$, token entropy Granger-precedes distinct-3 at the same consensus level as distinct-1 and distinct-2: $K{\\geq}4/5$ methods, $S{\\geq}3/4$ seeds (Tier~3).\nHowever, the optimal lag is less stable than for distinct-1/2: at max\\_lag${=}7$, the lag standard deviation across seeds exceeds 1.5 generations, compared to $<0.5$ for distinct-1/2.\nThis instability reflects bimodal lag distributions (modes at lag~1 and lag~3--4), suggesting that distinct-3 captures two temporally distinct diversity loss mechanisms: rapid n-gram homogenization (lag~1) and slower distributional narrowing (lag~3--4).\n\n\\paragraph{Sensitivity to sequence length.}\nHigher-order $n$-gram diversity metrics are more sensitive to generation length and random sampling variability.\nWith our 512-token generation length, distinct-3 has a smaller effective denominator (number of possible unique trigrams observed) than distinct-1 or distinct-2, amplifying stochastic fluctuations.\nThis partially explains the higher lag instability: the signal-to-noise ratio for temporal precedence is lower for distinct-3, requiring more observations (longer $T$ or more seeds) to achieve stable estimates.\nFor this reason, we report distinct-3 in this appendix rather than in the main text, where distinct-1 and distinct-2 provide cleaner evidence of the entropy-leads-diversity pattern.\n\n\n\\section{Observation Window Sensitivity}\n\\label{app:window_sensitivity}\n\nTable~\\ref{tab:window_sensitivity} reports how the Tier~3 consensus classification ($K{\\geq}4/5$ methods) varies as a function of the minimum observation window $T_{\\min}$, where analysis uses only generations $0$ through $T_{\\min}$.\nThe consensus classification stabilizes at $T_{\\min}{\\geq}5$ (6 data points), well below our full observation window of $T{=}10$: all six effect-size reference pairs (token entropy and ECE $\\to$ distinct-1, distinct-2, distinct-3) reach $K{\\geq}4/5$ agreement at every window length from $T_{\\min}{=}5$ through $T_{\\min}{=}10$, with no spurious pairs (canary$\\to$perplexity) admitted.\n\nToda--Yamamoto is the only method exhibiting window-dependent sensitivity (note: TY directional assignment is under verification; these counts are retained for completeness): TY consensus stabilizes at $T_{\\min}{\\geq}6$, slightly later than the primary methods, reflecting the additional degrees of freedom consumed by the augmentation order $d_{\\max}$.\nThis does not affect the consensus classification because the remaining four methods provide stable $K{\\geq}4/5$ agreement independently of Toda--Yamamoto's vote.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Observation window sensitivity for Tier~3 consensus ($K{\\geq}4/5$) at $\\alpha{=}1.0$ (Pythia-410M, 4~seeds). Tier~3 pairs: number of canary$\\to$downstream pairs (out of 8 validated) reaching $K{\\geq}4/5$ method agreement. TY pairs: number of effect-size reference pairs (out of 6) reaching Toda--Yamamoto significance (moderate supplementary method; \\S\\ref{sec:method}). Consensus stabilizes at $T_{\\min}{\\geq}5$; TY stabilizes at $T_{\\min}{\\geq}6$.}\n\\label{tab:window_sensitivity}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccccccc}\n\\toprule\n& \\multicolumn{8}{c}{Minimum observation window $T_{\\min}$} \\\\\n\\cmidrule(lr){2-9}\n& 3 & 4 & 5 & 6 & 7 & 8 & 9 & 10 \\\\\n\\midrule\nTier~3 pairs (/8)    & $\\dagger$ & $\\dagger$ & 6 & 6 & 6 & 6 & 6 & 6 \\\\\nTY pairs$^\\S$ (/6)   & $\\dagger$ & $\\dagger$ & 3--6 & 3--6 & 3--6 & 3--6 & 3--6 & 6 \\\\\nStable               & ---       & ---       & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark \\\\\n\\bottomrule\n\\multicolumn{9}{l}{\\footnotesize $\\dagger$~Insufficient degrees of freedom for Granger-type tests ($<6$ data points).} \\\\\n\\multicolumn{9}{l}{\\footnotesize $^\\S$~TY directional assignment under verification.}\n\\end{tabular}}\n\\end{table}\n\n\n\\section{Robustness Checks}\n\\label{app:robustness}\n\n\\paragraph{Permutation count stability.}\nTable~\\ref{tab:nperm_stability} compares permutation Granger $p$-values at 5{,}000 versus 10{,}000 permutations across all canary$\\to$downstream pairs at $\\alpha{=}0.75$ (3~seeds, 24~pairs).\nPermutation Granger $p$-values are stable to within 0.002 between 5{,}000 and 10{,}000 permutations, with zero significance decisions affected.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Permutation count stability analysis ($\\alpha{=}0.75$, 3~seeds, 24 canary$\\to$downstream pairs). $p$-values from permutation Granger tests at $n_{\\text{perm}}{=}5{,}000$ versus $n_{\\text{perm}}{=}10{,}000$.}\n\\label{tab:nperm_stability}\n\\begin{tabular}{lc}\n\\toprule\nMetric & Value \\\\\n\\midrule\nMax $|\\Delta p|$ & 0.010 \\\\\nMean $|\\Delta p|$ & 0.002 \\\\\nSignificance flips & 0 / 24 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{FDR threshold sensitivity.}\nTable~\\ref{tab:fdr_sensitivity} reports the effect of varying the BH FDR threshold $q$ on treatment ($\\alpha{=}0.75$, 3~seeds, 8-pair basis) versus null ($\\alpha{=}0.0$, 6~seeds 45--50, 6-pair basis) separation for permutation Granger tests.\nTreatment/null separation is qualitatively robust to FDR threshold choice, though the expanded null sample reveals a small number of false positives at each threshold (3--8 of 36 pairs).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{FDR threshold sensitivity for permutation Granger significance. Treatment: $\\alpha{=}0.75$ (3~seeds, 24 forward-direction pairs, 8-pair basis). Null: $\\alpha{=}0.0$ (6~seeds 45--50, 36 pairs, 6-pair basis). The expanded null sample reveals modest false positive rates that increase with $q$.}\n\\label{tab:fdr_sensitivity}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n$q$ & Null FDR-sig (/36) & Treatment FDR-sig (/24) & Separation \\\\\n\\midrule\n0.01 & 3 & 0  & Underpowered \\\\\n0.05 & 4 & 19 & Good \\\\\n0.10 & 8 & 24 & Good (elevated null) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{PermG $p$-value gradient at the onset boundary ($\\alpha{=}0.45$).}\nAt the onset boundary, PermG operates near its detection limit, and marginal $p$-values exhibit seed-dependent variation consistent with the statistical power interpretation (\\S\\ref{sec:theory}).\nTable~\\ref{tab:fdr_gradient_a045} reports BH-corrected $p$-values for all 8 canary$\\to$downstream pairs across two seeds at $\\alpha{=}0.45$.\nSeed~43 reaches a minimum FDR-corrected $p{=}0.059$ (18\\% above the $q{=}0.05$ threshold), while seed~42 reaches $p{=}0.091$ (82\\% above threshold).\nNo pair crosses the significance threshold at either seed, yielding the aggregate 0/8 detection rate reported in \\S\\ref{sec:regime}.\nThe gradient is consistent with a continuous power transition rather than a binary absence of signal: PermG operates near its detection limit at $\\alpha{=}0.45$, with seed-dependent variation in marginal $p$-values.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{BH-corrected PermG $p$-values at $\\alpha{=}0.45$ (8 canary$\\to$downstream pairs $\\times$ 2 seeds). Min $p_{\\mathrm{fdr}}$ per seed shown. All pairs remain above the $q{=}0.05$ threshold, yielding 0/8 aggregate detection.}\n\\label{tab:fdr_gradient_a045}\n\\begin{tabular}{lcc}\n\\toprule\n & Seed 42 & Seed 43 \\\\\n\\midrule\nMin FDR $p$ & 0.091 & 0.059 \\\\\nGap to $q{=}0.05$ & 82\\% & 18\\% \\\\\nPermG fwd sig (/8) & 0 & 0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Systematic Robustness Analysis}\n\\label{app:spec_curve}\n\nThe sharp detection onset reported in \\S\\ref{sec:regime} could in principle depend on specific analytical choices (pair selection, seed, $\\alpha$ level, method parameters).\nWe assess robustness via specification curve analysis~\\cite{simonsohn2020specification}, systematically varying analytical degrees of freedom to test whether the 0/8$\\to$6/8 transition is specification-invariant.\nOur specification curve varies data subsets and pair selections while holding the detection method (PermG) and its hyperparameters fixed, more closely resembling a systematic subset analysis than a full specification curve in the sense of \\citet{simonsohn2020specification}.\n\nWe construct 1{,}160 analytical specifications from the combinatorial space of: 13 contamination levels ($\\alpha$ grid), seed selection ($\\{42, 43, 44, 45\\}$ where available), 8 canonical canary$\\to$downstream pairs (\\{token entropy, ECE\\} $\\times$ \\{distinct-1, distinct-2, distinct-3, mauve\\}), and method parameters (all PermG with $n_\\text{perm}{=}5{,}000$, BH FDR $q{=}0.05$).\nAll specifications use the D120-canonical analysis pipeline with $3\\sigma$ threshold calibration (D105) as a hard filter.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Specification curve summary (1{,}160 specifications, D120-compliant). The blind$\\to$onset jump is robust across specifications: 0\\% significance rate through $\\alpha{=}0.45$, rising to 75\\% at $\\alpha{=}0.50$.}\n\\label{tab:spec_curve}\n\\begin{tabular}{lc}\n\\toprule\nMetric & Value \\\\\n\\midrule\nTotal specifications & 1{,}160 \\\\\nSignificant (FDR $q{<}0.05$) & 536 (46.2\\%) \\\\\n\\midrule\n\\emph{By regime} & \\\\\n\\quad Blind ($\\alpha \\leq 0.45$) & 0\\% \\\\\n\\quad Onset ($\\alpha{=}0.50$) & 75\\% \\\\\n\\quad Detection ($\\alpha \\geq 0.75$) & 62--75\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe specification curve confirms that the sharp detection onset is not an artifact of particular analytical choices: the categorical jump from 0\\% to ${\\geq}75\\%$ significance at $\\alpha_c{\\approx}0.50$ holds across the vast majority of specifications, supporting the main text claim (\\S\\ref{sec:regime}).\n\n\n\\section{Transfer Entropy Analysis}\n\\label{app:transfer_entropy}\n\nTable~\\ref{tab:te_results} reports transfer entropy (TE; \\citealp{schreiber2000measuring}) results aggregated across all baseline conditions.\nTE was estimated using 3-bin discretization with permutation testing ($n{=}5{,}000$).\nNo pair reaches BH-corrected significance ($q{=}0.05$) in any condition, confirming that non-parametric information-theoretic methods lack detection power at $T{=}11$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Transfer Entropy results (12 runs across all $\\alpha$ levels). TE\\textsubscript{fwd}: canary$\\to$downstream; TE\\textsubscript{rev}: downstream$\\to$canary. Mean uncorrected permutation $p$-values ($n{=}5{,}000$). No pair reaches BH-corrected $q{<}0.05$ in any run.}\n\\label{tab:te_results}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\nCanary & Downstream & TE\\textsubscript{fwd} (mean) & $p$\\textsubscript{fwd} (mean) & TE\\textsubscript{rev} (mean) & $p$\\textsubscript{rev} (mean) \\\\\n\\midrule\ntoken\\_entropy & distinct-1 & 0.289 & 0.559 & 0.480 & 0.490 \\\\\ntoken\\_entropy & distinct-2 & 0.300 & 0.529 & 0.496 & 0.447 \\\\\ntoken\\_entropy & distinct-3 & 0.255 & 0.645 & 0.484 & 0.459 \\\\\ntoken\\_entropy & perplexity & 0.257 & 0.676 & 0.386 & 0.626 \\\\\nECE & distinct-1 & 0.185 & 0.720 & 0.184 & 0.891 \\\\\nECE & distinct-2 & 0.208 & 0.683 & 0.216 & 0.846 \\\\\nECE & distinct-3 & 0.209 & 0.689 & 0.227 & 0.807 \\\\\nECE & perplexity & 0.296 & 0.572 & 0.263 & 0.747 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\phantomsection\\label{app:te_mi}\n\\paragraph{KNN-based TE/MI decomposition.}\nA $k$-nearest-neighbor TE estimator ($k{=}5$) provides a model-free complement to the parametric Granger framework.\nForward-dominant TE fraction increases monotonically with $\\alpha$: 4/8 pairs at $\\alpha{=}0.25$ (mean net TE${=}0.14$), 5/8 at $\\alpha{=}0.50$ (net TE${=}0.42$), 6/8 at $\\alpha{=}0.60$ (net TE${=}0.57$), and 8/8 at $\\alpha{=}1.0$ (net TE${=}1.59$).\nAll 120 forward TE bootstrap 95\\% CIs exclude zero at $T{=}10$; all 48 at $T{=}20$.\nThe ``high MI, low TE'' hypothesis for the non-monotonic dip is supported by only 2/8 pairs (ECE$\\to$perplexity and token entropy$\\to$perplexity); the remaining 6 pairs show elevated TE even at $\\alpha{=}0.60$, indicating confounded co-variation rather than a universal mechanism.\n\n\\section{Change-Point Detection Analysis}\n\\label{app:change_point}\n\nWe apply a max-split change-point test with bootstrap significance assessment ($n{=}5{,}000$, $p{<}0.05$) to each metric's generation-level time series ($T{=}11$).\n\nUnder the null control ($\\alpha{=}0.00$, 3~seeds), downstream diversity metrics (distinct-1, distinct-2, distinct-3) produce significant change-points at generation~2 in all seeds (9/9 tests). With additional significant tests from ECE (2/3 seeds) and token entropy (1/3 seeds), the overall false positive rate reaches 66.7\\% (12/18 tests; Table~\\ref{tab:cp_null}). The monotonic drift inherent in iterative self-training is sufficient to trigger change-point detection even without canary contamination. Individual change-point significance therefore cannot serve as standalone evidence for a canary-specific effect.\n\nAlthough individual significance is unreliable as a discriminator, the temporal ordering of detected change-points reverses between null and treatment conditions. In the null ($\\alpha{=}0.00$), downstream metrics show the earliest significant breaks at generation~2 (all seeds), while significant canary breaks appear later (ECE at generations~4--8). Under treatment conditions ($\\alpha{\\geq}0.75$), this ordering flips: canary metrics place their best splits at generation~1, followed by downstream diversity metrics at generations~2--4 and perplexity at generation~4 (Table~\\ref{tab:cp_results}). This ordering reversal provides complementary evidence from a distinct statistical framework, consistent with the Granger-precedence analysis in \\S\\ref{sec:experiments}.\n\nSeveral caveats apply. The 18 individual tests per condition were not corrected for multiple comparisons (BH or Bonferroni); primary inference rests on the cross-metric temporal ordering rather than on individual significance tests. Under treatment conditions, token entropy places its best split at generation~1 with large effect sizes ($|d|{>}2.5$) in all seeds, but the pre-change segment at a generation-1 split contains only a single data point, reducing bootstrap power (1/3 seeds significant at $\\alpha{=}0.75$). The short series length ($T{=}11$) further limits overall detection power.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Change-point detection under null control ($\\alpha{=}0.00$, 3 seeds). CP: detected change-point generation (mean across significant seeds); $|d|$: Cohen's $d$ effect size (mean across all seeds); Sig.\\ rate: fraction of seeds where $p{<}0.05$. Overall FPR: 12/18 = 66.7\\%.}\n\\label{tab:cp_null}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\nMetric & CP gen (mean) & $|d|$ (mean) & Sig.\\ rate & Type \\\\\n\\midrule\ntoken\\_entropy & 1.0 & 2.94 & 1/3 & canary \\\\\nECE & 6.0 & 1.62 & 2/3 & canary \\\\\ndistinct-1 & 2.0 & 2.27 & 3/3 & downstream \\\\\ndistinct-2 & 2.0 & 2.40 & 3/3 & downstream \\\\\ndistinct-3 & 2.0 & 2.27 & 3/3 & downstream \\\\\nperplexity & --- & 3.11 & 0/3 & downstream \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Change-point detection at $\\alpha{=}0.75$ (3 seeds). CP: detected change-point generation; $|d|$: Cohen's $d$ effect size between pre- and post-change segments. Sig.\\ rate: fraction of seeds where $p{<}0.05$.}\n\\label{tab:cp_results}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\nMetric & CP gen (mean) & $|d|$ (mean) & Sig.\\ rate & Type \\\\\n\\midrule\ntoken\\_entropy & 1.0 & 3.21 & 1/3 & canary \\\\\nECE & 1.0 & 3.10 & 1/3 & canary \\\\\ndistinct-1 & 2.3 & 2.18 & 3/3 & downstream \\\\\ndistinct-2 & 3.0 & 1.97 & 3/3 & downstream \\\\\ndistinct-3 & 3.7 & 1.86 & 3/3 & downstream \\\\\nperplexity & 4.0 & 1.70 & 3/3 & downstream \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Dose-response ordering pattern.}\nTable~\\ref{tab:cp_ordering} summarizes the ordering pattern across contamination levels.\nThe canary-to-downstream gap shifts monotonically from negative (downstream first) under the null to positive (canary first) under treatment, ruling out a methodological artifact in which canary metrics would systematically appear earlier regardless of condition.\nThe $\\alpha{=}1.0$ analysis is limited to a single seed (s42); all other conditions use 3 seeds.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccl}\n\\toprule\n$\\alpha$ & Canary cp & Downstream cp & Gap & Direction \\\\\n\\midrule\n0.00 & gen 4--8 & gen 2 & $-$2.5 & Downstream first \\\\\n0.25 & gen 3--4 & gen 3--4 & $\\approx$0 & Simultaneous \\\\\n0.75 & gen 1 & gen 2--4 & $+$2.25 & Canary first \\\\\n1.00 & gen 2 & gen 2--5 & $+$1.0 & Canary first \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Change-point ordering reversal across contamination levels. Under the null ($\\alpha{=}0.00$), downstream metrics break before canary metrics; this ordering reverses monotonically as $\\alpha$ increases, consistent with the Granger-precedence analysis.}\n\\label{tab:cp_ordering}\n\\end{table}\n\n\n\\section{Sequential Monitoring: CUSUM vs Calibrated Threshold}\n\\label{app:csmp}\n\nWe translate the Granger-precedence finding into a deployable monitoring protocol using CUSUM (cumulative sum) sequential testing~\\cite{page1954continuous}, calibrated against the $\\alpha{=}0.0$ null control.\nThe null-calibration procedure sets the alarm threshold $h$ such that the false alarm rate (FAR) is 0\\% on null data (3~seeds, $T{=}10$), providing controlled Type~I error guarantees.\n\n\\paragraph{Method.}\nCUSUM monitors the cumulative deviation of token entropy from its null-control baseline: $S_t = \\max(0,\\; S_{t-1} + (\\mu_0 - x_t) - k)$, where $\\mu_0$ is the null-control mean, $k$ is the allowance parameter, and the alarm triggers when $S_t > h$.\nWe calibrate $h$ for each $k$ from the $\\alpha{=}0.0$ null data (Table~\\ref{tab:csmp_calibration}).\nAs a baseline, we compare against a simple calibrated threshold: alarm when the metric crosses $\\mu_0 - 2\\sigma_0$ for $n{\\geq}1$ or $n{\\geq}2$ consecutive generations.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{CUSUM calibration parameters from $\\alpha{=}0.0$ null control (3~seeds). $h$: alarm threshold calibrated to achieve FAR${=}$0\\%. For $k{\\geq}0.25$, the null CUSUM statistic remains at zero, yielding $h \\approx 0$.}\n\\label{tab:csmp_calibration}\n\\begin{tabular}{lcc}\n\\toprule\n$k$ & $h$ & FAR \\\\\n\\midrule\n0.05 & 1.530 & 0\\% \\\\\n0.10 & 1.005 & 0\\% \\\\\n0.25 & $\\approx$0 & 0\\% \\\\\n0.50 & $\\approx$0 & 0\\% \\\\\n1.00 & $\\approx$0 & 0\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Results.}\nTable~\\ref{tab:csmp_comparison} compares CUSUM and simple threshold detection times across gradual contamination levels.\nAt the recommended operating point ($k{=}0.25$), CUSUM and the simple threshold ($n{\\geq}1$) produce identical alarm times (generation~1) across all seeds and contamination levels.\nMore conservative CUSUM settings ($k{=}0.1$, $k{=}0.05$) delay detection to match the $n{\\geq}2$ threshold or later.\nAt $k{=}1.0$ with $\\alpha{=}0.50$, CUSUM fails entirely ($S_t \\equiv 0$ for all seeds), demonstrating sensitivity to the allowance parameter.\nNo CUSUM configuration outperforms the simple calibrated threshold at any operating point tested.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{CUSUM vs simple calibrated threshold: alarm generation across contamination levels (3~seeds each; all seeds agree on the alarm generation shown). Threshold: metric crosses $\\mu_0 - 2\\sigma_0$. No CUSUM configuration outperforms the simple threshold at any operating point.}\n\\label{tab:csmp_comparison}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n$\\alpha$ & CUSUM $k{=}0.25$ & CUSUM $k{=}0.1$ & CUSUM $k{=}0.05$ & Thresh $n{\\geq}1$ & Thresh $n{\\geq}2$ \\\\\n\\midrule\n0.50 & gen 1 & gen 2 & gen 3 & gen 1 & gen 2 \\\\\n0.75 & gen 1 & gen 2 & gen 2 & gen 1 & gen 2 \\\\\n\\bottomrule\n\\multicolumn{6}{l}{\\footnotesize CUSUM $k{=}1.0$ at $\\alpha{=}0.50$: $S_t \\equiv 0$ for all seeds (complete detection failure).} \\\\\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Interpretation.}\nThe equivalence arises because the generation-0$\\to$1 entropy drop is large ($|\\Delta x| > 0.7$ for $\\alpha{=}0.50$, $> 1.0$ for $\\alpha{=}0.75$) relative to the null-control variability ($\\sigma_0 \\approx 0.03$).\nAny detector with a near-zero or small threshold triggers at generation~1; CUSUM's cumulative memory provides no advantage when the initial shift already exceeds the control limit.\nThis result extends Claim~3 (method sensitivity) beyond lead-lag detection to the monitoring domain: even a sequential testing procedure with stronger theoretical properties (optimal expected detection delay under continuous monitoring) does not improve over a calibrated baseline when the initial contamination signal dominates the allowance parameter.\nThe contribution of the null-calibrated monitoring framework is the calibration procedure itself (setting alarm boundaries from $\\alpha{=}0.0$ data to guarantee FAR${=}$0\\%), not the CUSUM algorithm.\n\n\\section{Background and Notation}\n\\label{app:background}\n\\label{sec:background}\n\nThis section establishes the formal setup and notation used throughout the paper.\n\n\\paragraph{Iterative training loop.}\nLet $M_0$ denote a pretrained language model and $\\mathcal{D}_\\text{real}$ a fixed corpus of human-written text.\nAt each generation $t \\geq 1$, the model $M_{t-1}$ generates a synthetic corpus $\\mathcal{D}_\\text{synth}^{(t-1)}$, and the next-generation model $M_t$ is fine-tuned on a mixture of $\\alpha$ fraction synthetic data and $(1{-}\\alpha)$ fraction real data:\n\\begin{equation}\n    \\mathcal{D}_\\text{train}^{(t)} = \\alpha \\cdot \\mathcal{D}_\\text{synth}^{(t-1)} \\;+\\; (1{-}\\alpha) \\cdot \\mathcal{D}_\\text{real}, \\quad \\alpha \\in [0, 1].\n    \\label{eq:mixing}\n\\end{equation}\nAt $\\alpha{=}1.0$, this reduces to the full-replacement paradigm of \\citet{shumailov2024curse}.\n\n\\paragraph{Metric families.}\n\\emph{Canary metrics}: token entropy ($H(p_\\theta | \\text{context})$ on held-out samples) and expected calibration error (ECE).\n\\emph{Downstream metrics}: distinct-$n$ ($n \\in \\{1, 2, 3\\}$)~\\cite{li2016diversity} and perplexity.\nEach metric produces a time series of $T{+}1$ observations.\n\n\\paragraph{Lead-lag testing.}\nGiven canary series $X$ and downstream series $Y$, the central question is whether changes in $X$ temporally precede changes in $Y$, requiring directionality and confounder control beyond simple correlation.\nWe employ five methods spanning permissive to conservative: naive cross-correlation, differenced cross-correlation, threshold onset detection, permutation Granger causality~\\cite{shojaie2022granger}, and Toda--Yamamoto Granger causality~\\cite{toda1995statistical}.\n\n\\section{MMCT Algorithm}\n\\label{app:mmct}\n\nAlgorithm~\\ref{alg:mmct} describes the Multi-Method Consensus Test (MMCT) introduced in \\S\\ref{sec:mmct}.\n\n\\begin{algorithm}[h]\n\\caption{Multi-Method Consensus Test (MMCT)}\n\\label{alg:mmct}\n\\begin{algorithmic}[1]\n\\Require Time series pair $(X, Y)$; methods $\\{m_1, \\ldots, m_K\\}$ ($K{=}5$); null-control data $\\mathcal{N}$ (from $\\alpha{=}0.0$); tolerance $\\epsilon{=}0.01$\n\\Ensure $p$-value, consensus level $\\hat{K}$\n\\For{each method $m_k$}\n    \\State Compute empirical FPR: $\\widehat{\\mathrm{FPR}}_k \\gets$ fraction of null-control pairs where $m_k$ rejects $H_0$\n    \\State Compute weight: $w_k \\gets 1 / \\max(\\widehat{\\mathrm{FPR}}_k,\\; \\epsilon)$\n    \\State Apply $m_k$ to $(X, Y)$: $d_k \\gets \\mathbf{1}[m_k \\text{ rejects } H_0]$\n\\EndFor\n\\State Weighted consensus: $W(X {\\to} Y) \\gets \\sum_{k} w_k \\, d_k \\;/\\; \\sum_{k} w_k$\n\\State Build empirical null distribution of $W$ from all null-control pairs in $\\mathcal{N}$\n\\State Compute $p$-value from empirical null: $p \\gets \\Pr_{\\mathcal{N}}(W \\geq W_{\\mathrm{obs}})$\n\\State Consensus level: $\\hat{K} \\gets \\sum_{k} d_k$\n\\State \\Return $p$, $\\hat{K}$\n\\end{algorithmic}\n\\end{algorithm}\n\n\\paragraph{Design rationale.}\nFPR-inverse weighting penalizes methods with high false positive rates on null-control data: naive cross-correlation (FPR${=}91.7\\%$) receives weight $w{=}1.09$, while PermG (FPR${=}11.1\\%$, the lowest among directional methods; DiffXCorr achieves 2.8\\% but lacks directional separation) receives $w{=}9.0$.\nThe empirical null distribution avoids parametric assumptions that are unreliable for short ($T{=}5$--$20$), non-stationary series typical of iterative training.\nMMCT is a consensus testing protocol, not a novel statistical method; its value lies in systematic method comparison and the identification of method-dependent conclusions.\n\n\n\\section{Methodological Comparison Table}\n\\label{app:method_comparison}\n\nTable~\\ref{tab:method-comparison} summarizes the methodological coverage of existing canary and monitoring analyses across the diagnostic dimensions identified in \\S\\ref{sec:method}.\nNo prior work combines all six dimensions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Methodological comparison of canary and monitoring analyses. \\checkmark\\ = present, $\\times$ = absent, $\\circ$ = partial (${\\leq}2$ levels or limited replication). Diff.\\ = differencing/stationarity controls. Multi-M.\\ = ${\\geq}2$ independent statistical methods. MTC = multiple testing correction. Regime = systematic variation of $\\alpha$. Seeds = ${\\geq}3$ independent seeds. Arch.\\ = ${\\geq}2$ architecturally distinct model families.}\n\\label{tab:method-comparison}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccccl}\n\\toprule\nWork & Diff. & Multi-M. & MTC & Regime & Seeds & Arch. & Metrics \\\\\n\\midrule\n\\citet{shumailov2024curse}     & $\\times$   & $\\times$   & $\\times$   & $\\circ$    & \\checkmark & \\checkmark & PPL \\\\\n\\citet{du2025scales}           & $\\times$   & $\\times$   & \\checkmark & \\checkmark & \\checkmark & $\\times$   & ECE, Acc, Dist-$n$ \\\\\n\\citet{gambetta2024surplexity} & $\\times$   & $\\times$   & $\\times$   & \\checkmark & \\checkmark & \\checkmark & Surplexity, Ent \\\\\nSIGMA~\\cite{sigma2026spectral} & $\\times$   & $\\times$   & $\\times$   & $\\times$   & $\\times$   & $\\times$   & Spectral \\\\\nDCES~\\cite{dces2026counter}    & $\\times$   & $\\times$   & $\\times$   & $\\times$   & $\\times$   & \\checkmark & ECE, Ent, PPL \\\\\n\\midrule\n\\textbf{Ours}                  & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark & \\checkmark & Ent, ECE, PPL, Dist-$n$ \\\\\n\\bottomrule\n\\end{tabular}%\n}\n\\end{table}\n\n\\section{Extended Discussion}\n\\label{app:extended_discussion}\n\n\\paragraph{Calibration scope and generalization.}\nAll FPR and FNR calibration results are specific to our experimental setup: Pythia-410M, WikiText-103 subset, $T{=}10$, and six contamination levels.\nCross-architecture validation across 15 conditions spanning six model families shows that the entropy-leads-diversity pattern generalizes in 11 of 15 architecture-seed combinations (Table~\\ref{tab:generalization}); GPT-2 bf16 (0/8), GPT-2 s43 (6/8 bidirectional), SmolLM3-3B (3/8, entropy decoupling), and Pythia-1.4B s42 (2/8) do not confirm the pattern.\n\n\\paragraph{Domain-dependent directionality.}\nThe unidirectional forward causation observed on WikiText (PermG reverse${=}$0/8 across all conditions) does not hold universally.\nOn C4 at $\\alpha{=}0.50$ (s42 fp32), PermG reverse reaches 7/8, indicating near-symmetric bidirectional coupling; however, this is seed-dependent (s43: 1/8) and noted as preliminary.\nThe practical implication is that directional asymmetry should be verified per domain.\n\n\\paragraph{Token entropy versus perplexity.}\nThe distinction lies in the evaluation domain: token entropy is $H(p_\\theta | \\text{context})$ on held-out real data, while perplexity is $\\exp(H_\\text{cross})$ on model-generated text.\nFirst-differencing removes their shared downward trend: the canary$\\to$diversity channel survives because entropy leads diversity by one generation, whereas the canary$\\to$perplexity channel vanishes because both co-move synchronously.\n\n\\paragraph{NLP-specific constraints.}\nOur application of Granger-type methods faces constraints absent in econometrics: (i)~observation length ($T{=}5$--$20$ vs.\\ $T{=}100$--$1000$); (ii)~non-stationarity by design rather than incidental; (iii)~small multiplicity for FDR correction (8--32 pairs per regime).\nTransfer entropy (0/192 FDR-significant results) confirms that method sensitivity extends beyond the five-method panel.\n\n\\paragraph{Prevention paradox.}\nEffective intervention truncates the collapse trajectory that established Granger precedence.\nDifferenced cross-correlation retains significance under intervention (31/32 pairs), while threshold onset fails entirely (0/8), reinforcing the multi-method rationale.\n\n\\paragraph{Grouped testing rationale.}\nWe test 8 canary$\\to$downstream pairs jointly (2 canaries $\\times$ 4 downstream metrics) rather than individual per-metric tests because: (i)~joint testing with BH-FDR correction controls family-wise error across the canary panel, avoiding the inflated false-positive rate that would result from reporting the single most significant pair; (ii)~the count of significant pairs ($k/8$) provides a natural effect-size measure that distinguishes isolated from systematic detection; (iii)~per-metric tests cannot capture the cross-metric consistency that separates genuine temporal precedence from metric-specific artifacts (e.g., MAUVE floor saturation affects 2/8 pairs universally, identifiable only in grouped results).\n\n\\paragraph{Canary metric choice.}\nSmolLM3-3B reveals that canary metric selection constitutes a sensitivity dimension beyond the five statistical methods: token entropy exhibits non-monotonic oscillations (0/4 significant pairs), while ECE maintains monotonic growth (3/4 pairs).\nNo single canary metric is universally optimal.\n\n\\paragraph{Exploratory CSD analysis.}\nCanary metrics show rising autocorrelation (Kendall $\\tau{=}0.79$--$0.82$) while downstream metrics show none ($\\tau{=}0.03$--$0.30$), but this pattern does not survive multiple testing correction (2/10 post-BH) and remains exploratory.\nWe note that \\citet{truong2026phase} show model collapse is a first-order transition, ruling out CSD as a structural detection mechanism; the rising autocorrelation likely reflects non-stationarity rather than critical slowing down.\n\n\\paragraph{Scale verification (Pythia-1.4B).}\n\\label{app:scale_14b}\nTo test whether the phase-diagram structure generalizes beyond 410M, we replicate the analysis at 1.4B scale ($T{=}10$--$15$, fp32, seed~42).\nTable~\\ref{tab:14b_phase} summarizes the available cells.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Pythia-1.4B phase-diagram cells (fp32, PermG forward, direction-checked).}\n\\label{tab:14b_phase}\n\\begin{tabular}{lcccc}\n\\toprule\n$\\alpha$ & \\multicolumn{2}{c}{$T{=}10$} & \\multicolumn{2}{c}{$T{=}15$} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\n         & s42 & s44 & s42 & s43 \\\\\n\\midrule\n0.45 & 0/6 & 0/6 & 3/6 & 5/6 \\\\\n0.50 & 4/6 & 6/6 & 3/6 & 3/6 \\\\\n0.60 & 4/6 & 6/6 & 6/6 & 6/6 \\\\\n0.75 & 5/6 & 6/6 & 6/6 & 6/6 \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\footnotesize All: PermG fwd, 6-pair basis (2 canaries $\\times$ 3 distinct-$n$;} \\\\\n\\multicolumn{5}{l}{\\footnotesize MAUVE excl.\\ due to floor ${\\sim}0.033$ at 1.4B).} \\\\\n\\multicolumn{5}{l}{\\footnotesize s42 rev.\\ 0/6 at all $\\alpha$; s43 rev.\\ see text.} \\\\\n\\end{tabular}\n\\end{table}\n\nThe phase-diagram structure is qualitatively preserved at 1.4B scale.\nECE maintains monotonic growth across all three tested $\\alpha$ levels (3/3 cross-scale robust), and the binary detection pattern (above vs.\\ below $\\alpha_c$) is consistent with the 410M phase diagram.\nOn the 6-pair basis (MAUVE excluded due to systematic floor ${\\sim}0.033$; Table~\\ref{tab:14b_phase}), PermG forward detection at 1.4B ranges from 0/6 ($\\alpha{=}0.45$, $T{=}10$) to 6/6 ($\\alpha{\\geq}0.60$, $T{=}15$); token entropy exhibits one-step saturation ($27$--$39\\%$ drop from generation~0 to~1), reducing temporal resolution for entropy-based pairs.\nSeed s42 shows PermG$_\\text{rev}{=}0/6$ across all eight 1.4B conditions ($4\\alpha{\\times}2T$), confirming that bidirectionality is seed-specific rather than scale-inherent.\nThe 410M sync-dip ($\\alpha{=}0.60$: 0/8 at $T{\\leq}20$) does not reproduce at 1.4B (4/6 at $T{=}10$); whether this reflects scale-dependent dynamics or Pythia-specific effects remains open with only two model sizes tested.\nAt $T{=}15$, scale effects are $\\alpha$-conditional: $\\alpha{=}0.60$ reaches 6/6, while $\\alpha{=}0.50$ attenuates to 3/6 (vs 4/6 at $T{=}10$), confirming that detection loss is onset-localized rather than uniform.\nThe boundary's $T$-dependence is preserved: $\\alpha{=}0.45$ rises from 0/6 ($T{=}10$) to 3/6 ($T{=}15$), mirroring the 410M boundary shift.\nHowever, method-level heterogeneity emerges: Toda--Yamamoto exhibits a non-monotonic pattern at $T{=}15$, inverting the PermG ordering in the mid-$\\alpha$ range; gradual low-$\\alpha$ dynamics preserve VAR lag structure, while rapid entropy saturation disrupts lag dependence at intermediate $\\alpha$, with recovery at $\\alpha{=}0.75$ where extreme collapse dynamics (PPL drift ${+}390\\%$) generate sufficient temporal variation to support VAR detection.\nOnset-zone attenuation is $\\alpha$-invariant at 1.4B: both $\\alpha{=}0.45$ and $0.50$ yield 3/6 at $T{=}15$.\nAt 1.4B with $T{=}10$ (11 data points), non-PermG methods (threshold onset, naive cross-correlation, Toda--Yamamoto) have insufficient power due to short sequence length, reducing $K{\\geq}3$ consensus to an effective single-method test; at $T{=}15$ (16 data points), detection recovers (6/6 at $\\alpha{=}0.60$, lead time ${=}$ 10 generations) and $K{\\geq}3$ recovers its multi-method character, with 3/4 $\\alpha$ conditions achieving $K{\\geq}3{\\geq}2/6$ (onset $\\alpha{=}0.50$ seed-dependent: s42 1/6, s43 3/6).\nCross-method consensus ($K{\\geq}3$) exhibits seed-dependent variability at onset ($\\alpha{\\approx}0.50$), consistent with the noisy transition expected at phase boundaries, while remaining robust above onset ($K{\\geq}3$ ${\\geq}5/6$ at $\\alpha{=}0.75$).\nOn a unified 6-pair basis (MAUVE excluded due to systematic floor at ${\\sim}0.033$; Table~\\ref{tab:14b_phase}), third-seed replication (s44) at $T{=}10$ confirms ceiling detection above onset (6/6 at $\\alpha{\\geq}0.50$) with 0/6 at $\\alpha{=}0.45$, validating the blind zone.\nCross-$T$ improvement holds at 3/4 $\\alpha$ values ($\\alpha{=}0.45$: $0/6{\\to}5/6$; $\\alpha{=}0.60$: $6/6{\\to}6/6$; $\\alpha{=}0.75$: $6/6{\\to}6/6$), validating the predicted $\\alpha_c(T)$ decrease; at onset ($\\alpha{=}0.50$), PermG shows a marginal decrease ($6/6{\\to}3/6$), consistent with phase-boundary variability.\nAt onset ($\\alpha{=}0.45$--$0.50$), ECE-based pairs achieve higher detection rates than entropy-based pairs (e.g., 3/3 vs 0/3 robust at $\\alpha{=}0.50$, $T{=}15$), consistent with entropy's one-step saturation reducing temporal resolution at 1.4B scale.\n\n\\paragraph{Future work.}\nExtensions include multivariate VAR models for confounder testing, multi-seed replication across all six architecture families, longer training runs ($T{\\geq}20$), online monitoring within training pipelines, and accumulate-mode experiments~\\cite{dey2024breaking}.\nThe sigmoid onset boundary ($\\alpha_c{=}0.483$) invites connection to the critical mixture ratio scaling law of \\citet{gu2024cmr} and the data-mixing transitions of \\citet{gu2025datamixing}.\n\n\n\\section{Per-Method Dose-Response Profiles}\n\\label{app:dose_response}\n\nTable~\\ref{tab:dose_response_full} reports FDR significance counts (/8 validated pairs) for all five detection methods across 12 contamination levels (seed~42, Pythia-410M, WikiText, fp32).\nPermG exhibits a sharp 0$\\to$6 jump at $\\alpha{=}0.50$ with a return to 0 at $\\alpha{=}0.55$--$0.60$ (non-monotonic dip), while other methods show diffuse profiles: naive cross-correlation saturates at 7--8/8 across all levels including the null, and Toda--Yamamoto fluctuates without a clear onset.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-method FDR significance (/8 pairs) across contamination levels (Pythia-410M, seed~42, WikiText, fp32). PermG and Diff.\\ XCorr use BH-corrected FDR ($q{=}0.05$); Naive XCorr, Threshold, and TY use uncorrected $p{<}0.05$ (no FDR field in pipeline). $\\alpha{=}1.0$ from Pythia-410M cross-architecture condition (same seed/domain/precision).}\n\\label{tab:dose_response_full}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccccc}\n\\toprule\n$\\alpha$ & Naive & Diff.\\ XCorr & Threshold & PermG & TY$^\\S$ \\\\\n\\midrule\n0.00 & 8 & 4 & 3 & \\textbf{0} & 1 \\\\\n0.10 & 7 & 6 & 0 & \\textbf{0} & 0 \\\\\n0.25 & 8 & 3 & 0 & \\textbf{0} & 2 \\\\\n0.30 & 8 & 4 & 0 & \\textbf{0} & 3 \\\\\n0.35 & 8 & 4 & 0 & \\textbf{0} & 1 \\\\\n0.40 & 8 & 3 & 0 & \\textbf{0} & 4 \\\\\n0.45 & 8 & 6 & 0 & \\textbf{0} & 1 \\\\\n0.50 & 8 & 7 & 4 & \\textbf{6} & 3 \\\\\n0.55 & 8 & 8 & 0 & \\textbf{0} & 1 \\\\\n0.60 & 8 & 6 & 0 & \\textbf{0} & 0 \\\\\n0.75 & 7 & 6 & 0 & \\textbf{6} & 3 \\\\\n1.00 & 8 & 6 & 2 & \\textbf{6} & 1 \\\\\n\\bottomrule\n\\multicolumn{6}{l}{\\footnotesize $^\\S$TY directional assignment under verification; column retained for completeness.} \\\\\n\\end{tabular}}\n\\end{table}\n\nThe table highlights PermG's combination of null-control detection at 0/8 for this seed ($\\alpha{=}0.00$; pooled FPR across 6 seeds: 11.1\\%, lowest among directional methods), sharp onset (0$\\to$6 at $\\alpha{=}0.50$), and non-monotonic dip (0 at $\\alpha{=}0.55$--$0.60$), confirming it as the method whose dose-response profile most cleanly separates detection regimes.\nNaive cross-correlation's persistently high counts (7--8/8 even at $\\alpha{=}0.00$) demonstrate the 91.7\\% pooled null-control FPR reported in \\S\\ref{sec:method}.\n\n\n\\paragraph{Comparison with naive baselines.}\n\\label{app:naive_baselines}\n\nTable~\\ref{tab:naive_baselines} compares PermG against two practitioner-facing monitoring rules across 26 experiments (18~$\\alpha$ values, Pythia-410M, $T{=}10$, fp32).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Naive baseline comparison (Pythia-410M, $T{=}10$, fp32, 3 null-control runs).}\n\\label{tab:naive_baselines}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & FPR ($\\alpha{=}0$) & Onset $\\alpha$ \\\\\n\\midrule\nPPL-slope (${\\geq}2$ consec.\\ rises) & 100\\% (3/3) & 0.10 \\\\\nVariance-threshold ($2\\sigma$) & 67\\% (2/3) & 0.10 \\\\\nPermG (fwd ${\\geq}1$) & 0\\% (0/3) & 0.50 \\\\\n\\bottomrule\n\\multicolumn{3}{l}{\\footnotesize Onset $\\alpha$: lowest $\\alpha$ where method fires (seed~42).} \\\\\n\\end{tabular}\n\\end{table}\n\nPPL-slope fires at $\\alpha{=}0$ because the first-generation learning effect (perplexity drops from 26.9 to 19.3 at generation~1, then rises monotonically from generation~2 onward) produces consecutive rises indistinguishable from contamination-driven drift.\nVariance-threshold similarly triggers on the natural perplexity recovery.\nPermG avoids these false alarms by testing canary$\\to$downstream Granger precedence rather than univariate trend, thereby excluding training-drift confounds from the detection signal.\nNaive monitoring rules cannot distinguish contamination from natural training dynamics; formal statistical testing is necessary for controlled FPR.\n\n\n\\section{PermG Power Analysis}\n\\label{app:power_analysis}\n\nWe characterize PermG detection power via simulation under a controlled data-generating process (DGP) that matches the structure of our iterative training time series.\n\n\\paragraph{DGP.}\nFor each trial, we generate a bivariate system $(X_t, Y_t)$ for $t = 1, \\ldots, T$ where $X_t = \\mu + \\epsilon_t^X$ and $Y_t = \\mu + \\beta X_{t-1} + \\epsilon_t^Y$, with $\\epsilon \\sim \\mathcal{N}(0, \\sigma^2)$ and $\\sigma{=}1$.\nThe coupling parameter $\\beta$ controls signal strength; $\\beta{=}0$ is the null.\nThe linear coupling provides a power lower bound; nonlinear dynamics in actual iterative training may yield different power characteristics.\nWe sweep $\\beta \\in [0, 2]$ across $T \\in \\{6, 8, 10, 15, 20\\}$, running 100 replications per $(\\beta, T)$ cell with 5{,}000 permutations each and BH FDR correction at $q{=}0.05$ across 8 hypothetical pairs (matching the experimental setup).\n\n\\paragraph{Results.}\nTable~\\ref{tab:beta50} reports $\\beta_{50}$, the coupling strength required for 50\\% detection power, at each observation length $T$.\nUnder $\\sqrt{T}$ scaling, the product $\\beta_{50} \\cdot \\sqrt{T}$ should be constant; the observed decrease from 5.09 ($T{=}8$) to 2.68 ($T{=}20$) indicates that power grows faster than $\\sqrt{T}$, with the empirical scaling closer to $T^{-1.1}$.\nThe $\\sqrt{T}$ formula in \\S\\ref{sec:theory} thus provides a conservative lower bound on detection power: actual power at $T{=}20$ exceeds the $\\sqrt{T}$ prediction.\nFalse positive rates under FDR correction remain at or below 2\\% across all $T$ values (raw: 1--9\\%; Table~\\ref{tab:beta50}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{PermG power analysis: $\\beta_{50}$ (coupling for 50\\% power) under BH-FDR correction ($q{=}0.05$, 8 pairs). $\\beta_{50} \\cdot \\sqrt{T}$ decreases with $T$, indicating power grows faster than $\\sqrt{T}$. FPR: false positive rate at $\\beta{=}0$ (raw / FDR-corrected). Dashes indicate $<$50\\% power not reached within $\\beta \\leq 2.0$.}\n\\label{tab:beta50}\n\\begin{tabular}{lcccc}\n\\toprule\n$T$ & $\\beta_{50}$ & $\\beta_{50} \\cdot \\sqrt{T}$ & FPR (raw) & FPR (FDR) \\\\\n\\midrule\n6  & ---  & ---  & 1\\% & 0\\% \\\\\n8  & ---  & ---  & 6\\% & 2\\% \\\\\n10 & 2.0  & 6.32 & 9\\% & 2\\% \\\\\n15 & 1.2  & 4.65 & 6\\% & 2\\% \\\\\n20 & 0.9  & 4.02 & 5\\% & 1\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/permg_power_curve.pdf}\n\\caption{PermG detection power as a function of coupling strength $\\beta$ for five observation lengths ($T{=}6$--$20$; 100 replications $\\times$ 5{,}000 permutations, BH FDR $q{=}0.05$). Power increases with both $\\beta$ and $T$; at $T{=}6$--$8$, PermG remains underpowered ($<$20\\%) even at $\\beta{=}2.0$, consistent with the $T{=}10$ minimum required for reliable detection in our experimental setting.}\n\\label{fig:permg_power}\n\\end{figure*}\n\nAt $T{=}6$ and $T{=}8$, 50\\% power is not reached within $\\beta \\leq 2.0$ under FDR correction, explaining why PermG is fundamentally underpowered for very short series.\nThe practical implication for our $T{=}10$ setting: $\\beta_{50}{=}2.0$ means that only strong coupling produces reliable detection, consistent with the sharp onset at $\\alpha_c{\\approx}0.50$ where signal strength first exceeds this threshold.\nAt $T{=}20$, $\\beta_{50}$ drops to 0.9, predicting a left-shift of $\\alpha_c$ and broader detection coverage, as formalized in the detection boundary model (\\S\\ref{sec:theory}).\n\n\n\\section{Non-Stationarity Robustness Analysis}\n\\label{app:nonstationarity}\n\nWe assess PermG's size and power under controlled non-stationarity via Monte Carlo simulation, then compare to the empirical autocorrelation structure of our experimental series.\n\n\\paragraph{Simulation design.}\nWe generate bivariate AR(1) series with unidirectional coupling ($x \\to y$):\n$x_t = \\varphi x_{t-1} + \\varepsilon_t^x$, $y_t = \\varphi y_{t-1} + \\beta x_{t-1} + \\varepsilon_t^y$,\nwith $T{=}11$, 1{,}000 replications, and 500 permutations per replication.\nSize is evaluated under $H_0{:}\\;\\beta{=}0$; power under $H_1{:}\\;\\beta{=}0.6$.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Size (FPR at $\\beta{=}0$) and power ($\\beta{=}0.6$) under stationary and non-stationary AR(1) DGP ($T{=}11$, 1{,}000 reps, 500 perms). First-differencing maintains nominal size across all $\\varphi$; PermG FPR inflates to ${\\sim}10\\%$ at $\\varphi{\\geq}0.95$.}\n\\label{tab:nonstationarity_sim}\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{3}{c}{Size (\\%, $\\beta{=}0$)} & \\multicolumn{3}{c}{Power (\\%, $\\beta{=}0.6$)} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\n$\\varphi$ & Raw GC & First-Diff & PermG & Raw GC & First-Diff & PermG \\\\\n\\midrule\n0.50 & 6.4 & 6.6 & 6.8 & 37.7 & 17.7 & 36.8 \\\\\n0.95 & 10.0 & 5.9 & 9.5 & 44.3 & 28.7 & 41.5 \\\\\n0.99 & 11.2 & 4.2 & 10.7 & 46.4 & 24.6 & 41.7 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt $\\varphi{=}0.50$ (stationary), all three methods achieve near-nominal size ($6.4$--$6.8\\%$ vs.\\ $5\\%$ nominal).\nUnder strong non-stationarity ($\\varphi{\\geq}0.95$), PermG FPR inflates to ${\\sim}10\\%$ because permutation shuffling destroys temporal autocorrelation, shifting the null distribution.\nFirst-differencing maintains proper size ($4.2$--$6.6\\%$) at the cost of reduced power ($17.7$--$28.7\\%$ vs.\\ PermG's $36.8$--$41.7\\%$).\nOur pipeline applies first-differencing \\emph{before} permutation testing, combining PermG's power advantage with differencing's size control; the simulation isolates each component to characterize the tradeoff.\n\n\\paragraph{Empirical autocorrelation.}\nTable~\\ref{tab:empirical_ar1} reports AR(1) coefficients from seven experimental conditions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Empirical AR(1) coefficients for token entropy (te) and distinct-1 (d1), raw and first-differenced series. High raw $\\varphi$ in d1 reflects deterministic iterative-training decline, not stochastic AR persistence; first-differencing reduces $\\varphi$ to $< 0.44$.}\n\\label{tab:empirical_ar1}\n\\begin{tabular}{llrcccc}\n\\toprule\nExperiment & $\\alpha$ & $T$ & te $\\varphi_{\\text{raw}}$ & d1 $\\varphi_{\\text{raw}}$ & te $\\varphi_{\\text{diff}}$ & d1 $\\varphi_{\\text{diff}}$ \\\\\n\\midrule\na000\\_s42 & 0.00 & 10 & $-0.51$ & $0.86$ & $-0.57$ & $-0.14$ \\\\\na025\\_s42 & 0.25 & 10 & $-0.34$ & $0.95$ & $-0.45$ & $0.19$ \\\\\na050\\_s42 & 0.50 & 10 & $-0.28$ & $0.87$ & $0.31$ & $0.10$ \\\\\na075\\_s42 & 0.75 & 10 & $0.14$ & $0.91$ & $0.88$ & $0.24$ \\\\\na100\\_s42 & 1.00 & 10 & $1.00$ & $0.89$ & $0.98$ & $0.18$ \\\\\nt20\\_a050 & 0.50 & 20 & $-0.10$ & $0.97$ & $-0.25$ & $0.44$ \\\\\nt20\\_a100 & 1.00 & 20 & $0.98$ & $0.81$ & $0.87$ & $0.14$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Adequacy argument.}\nUnder null conditions ($\\alpha{=}0.0$), where FPR is defined, token entropy exhibits $\\varphi{=}-0.51$ (anti-correlated, far from the $\\varphi{\\geq}0.95$ regime where simulation reveals FPR inflation); at $\\varphi{=}0.50$, PermG FPR is $6.8\\%$, near nominal.\nThe high raw $\\varphi$ in distinct-1 ($0.81$--$0.97$ across all $\\alpha$ including null) reflects deterministic iterative-training diversity decline---a monotonic trend driven by the training protocol---not stochastic AR persistence.\nDeterministic trends differ fundamentally from the stochastic AR(1) DGP: they produce predictable trajectories rather than autocorrelated noise, and first-differencing effectively removes them (first-differenced distinct-1 $\\varphi$ ranges $-0.14$ to $0.44$, mean ${\\sim}0.17$).\nOur empirical FPR of 4/36 (11.1\\%) across six null seeds---the lowest among directional methods---confirms adequate size control in our experimental setting; all four false positives occur in token\\_entropy$\\to$distinct pairs in the forward direction, suggesting a structural pattern rather than random Type~I error.\nWe note that $T{=}10$ (11 data points) yields high-variance AR(1) estimates; the cross-experiment pattern is more informative than individual values.\n\n\\paragraph{DGP limitation.}\nThe bivariate AR(1) with linear coupling is a simplification; actual iterative training involves nonlinear dynamics (mode amplification, threshold-dependent diversity loss).\nThese simulation results characterize PermG's behavior under controlled conditions, not exact calibration for the experimental setting; they provide a lower bound on size control because the linear DGP represents a worst case for permutation-based tests (smooth autocorrelation that permutation destroys).\n\n\n\\section{Shapley Value Analysis}\n\\label{app:shapley}\n\nWe quantify each method's marginal contribution to the MMCT ensemble using Shapley values~\\cite{shapley1953value}, computed via exact enumeration over all $2^5{=}32$ coalitions of the five detection methods.\nFor a coalition $S \\subseteq \\{m_1, \\ldots, m_5\\}$, we define two performance metrics: the false positive rate FPR($S$), computed from 6 null experiments ($\\alpha{=}0.0$, seeds 45--50; 36 null pairs on the 6-pair basis excluding mauve), and the false negative rate FNR($S$), computed from 45 signal experiments across all non-null $\\alpha$ levels (270 signal pairs for the 6-pair variant excluding mauve).\nThe Shapley value $\\phi_k$ for method $m_k$ is the weighted average of its marginal contribution across all coalitions; positive FPR-Shapley indicates the method \\emph{increases} false positives, while negative FNR-Shapley indicates it \\emph{reduces} false negatives.\nThe combined Shapley value $\\phi_k^{\\text{comb}} = \\phi_k^{\\text{FPR}} + \\phi_k^{\\text{FNR}}$ balances both error types, with more negative values indicating greater net benefit.\n\nTable~\\ref{tab:shapley_6pair} reports the 6-pair analysis (excluding mauve).\nDiffXCorr achieves the lowest (best) combined Shapley ($-0.299$), driven by near-zero FPR contribution ($+0.007$) and strong FNR reduction ($-0.306$); however, DiffXCorr cannot separate forward from reverse causation (Table~\\ref{tab:null_fpr_methods}).\nAmong directional methods, PermG ranks best ($-0.141$ combined), with a modest FPR contribution ($+0.039$, reflecting 4/36 null false positives) offset by substantial FNR reduction ($-0.180$).\nNaive cross-correlation is the worst contributor ($+0.190$), with its massive FPR Shapley ($+0.609$) overwhelming its FNR benefit ($-0.419$).\nThreshold onset contributes almost nothing useful ($+0.084$ combined; FPR $+0.111$, FNR $-0.027$), confirming the near-zero detection power reported in Table~\\ref{tab:method_comparison}.\nFigure~\\ref{fig:shapley} visualizes the decomposition.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Shapley value decomposition (6-pair, mauve excluded). FPR-Shapley computed from 6 null seeds (36 pairs); FNR-Shapley from 45 signal experiments (270 pairs). Combined = FPR + FNR (more negative = better). $2^5{=}32$ coalitions, exact enumeration.}\n\\label{tab:shapley_6pair}\n\\begin{tabular}{lccc}\n\\toprule\nMethod & $\\phi^{\\text{FPR}}$ & $\\phi^{\\text{FNR}}$ & $\\phi^{\\text{comb}}$ \\\\\n\\midrule\nNaive XCorr          & $+0.609$ & $-0.419$ & $+0.190$ \\\\\n\\textbf{Diff.\\ XCorr}& $\\mathbf{+0.007}$ & $\\mathbf{-0.306}$ & $\\mathbf{-0.299}$ \\\\\nThreshold ($3\\sigma$) & $+0.111$ & $-0.027$ & $+0.084$ \\\\\nPerm.\\ Granger       & $+0.039$ & $-0.180$ & $-0.141$ \\\\\nToda--Yamamoto       & $+0.150$ & $-0.069$ & $+0.082$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/shapley_method_contribution.pdf}\n\\caption{Shapley value decomposition of each method's marginal contribution to FPR (positive bars) and FNR (negative bars), computed from 6 null seeds (36 pairs) and 45 signal experiments (270 pairs). DiffXCorr achieves the best combined Shapley ($-0.299$) via near-zero FPR; PermG ranks second ($-0.141$) as the best directional method.}\n\\label{fig:shapley}\n\\end{figure*}\n\nThe 8-pair variant (including mauve) yields qualitatively identical rankings: DiffXCorr remains the best contributor ($\\phi^{\\text{comb}}{=}-0.263$), PermG the best directional method ($-0.112$), naive cross-correlation the worst ($+0.157$), and threshold onset near-zero ($+0.073$).\n\n\\paragraph{FDR correction scope.}\nThis analysis applies BH-corrected significance (\\texttt{significant\\_fdr}) uniformly across all five methods, including naive cross-correlation and Toda--Yamamoto.\nIn contrast, the per-method dose-response profiles (Table~\\ref{tab:dose_response_full}) use uncorrected significance for naive cross-correlation, threshold onset, and Toda--Yamamoto because FDR-corrected fields are not available in the per-experiment pipeline output for these methods.\nThe Shapley analysis recomputes significance from raw $p$-values with BH correction applied post hoc, ensuring a fair comparison across methods within the coalition framework.\n\n\n\\section{MMCT Weight Robustness Ablation}\n\\label{app:weight_robustness}\n\nThe detection results reported in the main text use equal-weight majority voting ($K{\\geq}3$ of 5 methods, each contributing at most one vote per pair); PermG contributes at most $1/5 = 20\\%$ of the consensus weight.\nFPR-inverse weighting is used \\emph{only} in the exploratory method ranking below, not in the detection results.\nTo verify that PermG's top ranking is not an artifact of the FPR-inverse weighting scheme, we recompute Shapley values under four weight specifications (Table~\\ref{tab:weight_robustness}).\nEqual weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first ($\\phi^{\\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.\nUnder cap-5, the margin widens to 0.043 as the FPR penalty begins to differentiate high-FPR methods.\nCap-10 and original cap-100 yield identical Shapley values because the consensus threshold ($K{\\geq}3$) is determined by the three smallest method weights ($w_{\\text{naive}}{+}w_{\\text{diff}}{+}w_{\\text{thresh}} = 7.76$), which are invariant to further increases in the PermG or TY cap; this saturation confirms that the original $w{=}100$ does not artificially inflate PermG's contribution.\n% TODO-D219: recompute weight robustness table with 6-seed data; PermG φ^FPR will be >0\nAcross all schemes, PermG's advantage derives from the same structural property: zero FPR ($\\phi^{\\text{FPR}}{=}0$) combined with moderate FNR reduction ($\\phi^{\\text{FNR}}{=}-0.152$ to $-0.426$).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{MMCT weight robustness: PermG combined Shapley under four weighting schemes. PermG ranks first in all cases. Gap = $|\\phi^{\\text{comb}}_{\\text{PermG}} - \\phi^{\\text{comb}}_{\\text{runner-up}}|$. 48 experiments (3 null + 45 signal), exact Shapley enumeration ($2^5{=}32$ coalitions).}\n\\label{tab:weight_robustness}\n\\begin{tabular}{lrcrc}\n\\toprule\nScheme & $w_{\\text{PermG}}$ & $\\phi^{\\text{comb}}_{\\text{PermG}}$ & Runner-up & Gap \\\\\n\\midrule\nEqual ($w{=}1$)     & 1   & $-0.152$ & NaiveXCorr ($-0.137$) & 0.015 \\\\\nCap-5               & 5   & $-0.165$ & NaiveXCorr ($-0.123$) & 0.043 \\\\\nCap-10              & 10  & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\nFPR-inv.\\ (cap-100) & 100 & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{PermG FPR Independence Analysis}\n\\label{app:fpr_independence}\n\nTable~\\ref{tab:null_fpr_methods} reports null-control FPR for all five detection methods across six seeds ($6 \\times 6 = 36$ pairs, 6-pair basis excluding mauve).\nUnder identical BH-FDR correction ($q{=}0.05$), DiffXCorr achieves the lowest FPR (1/36, 2.8\\%) but lacks directional separation; PermG (4/36, 11.1\\%) is the lowest among directional methods.\nAll four PermG false positives occur in token\\_entropy$\\to$distinct pairs (seeds~45 and 50, forward direction only), suggesting a structural pattern concentrated in a single canary--downstream pair type.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Null-control FPR by method ($\\alpha{=}0.0$, 6~seeds 45--50, 6~pairs each). All p-value--based methods (DiffXCorr, PermG, TY) report BH-FDR--corrected rejections at $q{=}0.05$ for fair comparison. Threshold uses a deterministic $3\\sigma$ criterion; NaiveXCorr uses uncorrected correlation significance.}\n\\label{tab:null_fpr_methods}\n\\begin{tabular}{llrr}\n\\toprule\nMethod & Criterion & Rejections (/36) & FPR (\\%) \\\\\n\\midrule\nDiff.\\ XCorr$^\\dagger$ & BH-FDR & 1 & 2.8 \\\\\n\\textbf{Perm.\\ Granger} & \\textbf{BH-FDR} & \\textbf{4} & \\textbf{11.1} \\\\\nThreshold & $3\\sigma$ (det.) & 10 & 27.8 \\\\\nToda--Yamamoto & BH-FDR & 14 & 38.9 \\\\\nNaive XCorr & uncorr. & 33 & 91.7 \\\\\n\\bottomrule\n\\multicolumn{4}{l}{\\footnotesize $^\\dagger$Bidirectional; cannot separate forward from reverse.} \\\\\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cluster adjustment.}\nThe 36 null-control pairs are nested within 6~seeds (6~pairs per seed), introducing within-seed correlation.\nWithin-seed ICC${=}0.14$ yields an effective sample size $N_{\\text{eff}} \\approx 21$ (from $N_{\\text{eff}} = N / [1 + (m-1) \\cdot \\text{ICC}]$ where $N{=}36$, $m{=}6$).\nUnder the Clopper--Pearson exact method with $N_{\\text{eff}}{=}21$ and 4 successes (scaled), the cluster-adjusted 95\\% CI is $[1.2\\%, 30.4\\%]$, compared to $[3.1\\%, 26.1\\%]$ under independence ($N{=}36$).\nThe lower ICC compared to the 3-seed pilot ($0.14$ vs.\\ $0.34$) reflects greater between-seed consistency with six independent replications.\n\n\\paragraph{Direction filtering.}\nForward-direction filtering (retaining only pairs with peak lag${<}0$ for cross-correlation methods) reduces null-control $K{\\geq}3$ false positives.\nUnder the 6-seed, 6-pair basis, $K{\\geq}3$ consensus with filtering produces 6/36 false positives (16.7\\%; detail below); the 3-seed pilot underestimated this rate (0/8).\nDetection at $\\alpha{\\geq}0.50$ is unaffected: $K{\\geq}3$ counts are identical with and without direction filtering at all signal levels.\n\n\\paragraph{$K{\\geq}3$ false positive detail.}\nUnder the 6-pair basis (6~seeds, 36~pairs), $K{\\geq}3$ consensus produces 6 false positives (FPR${=}16.7\\%$).\nOf these, 4 are driven by naive cross-correlation, threshold onset, and Toda--Yamamoto (PermG does \\emph{not} vote); the remaining 2 (seeds~45 and 50, te$\\to$distinct) include PermG in the consensus.\nPermG thus contributes to only 2 of 6 consensus false positives, confirming that most $K{\\geq}3$ FPR is driven by the high-FPR methods (naive, threshold, TY).\n\n\\paragraph{Sensitivity to FPR assumption.}\nEven under the conservative upper bound of the cluster-adjusted CI (30.4\\%), PermG remains the lowest-FPR directional method: DiffXCorr achieves a lower FPR under identical BH-FDR correction (2.8\\%) but lacks forward/reverse separation; the next directional method (threshold onset) has 27.8\\% and Toda--Yamamoto 38.9\\%.\nOur primary results rely on equal-weight $K{\\geq}3$ majority voting, where each method contributes exactly one vote regardless of its FPR---this mechanism is completely unaffected by any FPR assumption.\nFor the exploratory FPR-inverse weighting, PermG's weight ($w{=}1/0.111{=}9.0$) exceeds all directional alternatives (threshold: 3.6, TY: 2.6, naive: 1.1); DiffXCorr ($w{=}1/0.028{=}35.7$) receives a higher weight but lacks directional separation, preserving PermG's rank among directional methods.\nThe insensitivity of both the voting mechanism and the method ranking to the upper CI bound provides evidence that the MMCT conclusions are robust to uncertainty in PermG's Type~I error rate.\n\n\\section{Sigmoid Transition Shape}\n\\label{app:sigmoid_shape}\n\nSigmoid regression on the original 13-point $T{=}10$ grid yields $\\alpha_c = 0.483 \\pm 0.006$ but $k = 478 \\pm 475$ ($\\mathrm{SE}(k) \\approx k$), indicating that the coarse grid cannot constrain the transition shape.\nDense $\\alpha$ sampling (17~values at $T{=}10$) resolves this ambiguity: formal likelihood-ratio testing strongly favors a smooth sigmoid over a literal step function ($\\Delta\\mathrm{AIC}{=}-110$), with fitted steepness $k{=}15.7$ (95\\% CI $[9.4, 28.2]$).\nThe transition is steep but finite-width, not a literal discontinuity.\nThis observed steepness exceeds what smooth signal models predict: VAR(1) simulations under H0 (linear, $k{=}6.1$) and H0$'$ (concave, $k{=}4.9$) produce onset sigmoids with $k{=}4.9$--$6.1$ (\\S\\ref{app:power_sim}), yielding steepness ratios $k_{\\mathrm{obs}} / k_{\\mathrm{H0}} \\approx 2.6$--$3.2$ (CI lower bound ratio ${\\approx}2$).\nWe do not fit a combined $T{=}10 + T{=}20$ sigmoid because $\\alpha{=}0.45$ yields contradictory counts under the two sequence lengths (0/8 vs.\\ 5/8), reflecting genuine power dependence on $T$ rather than a single dose-response curve.\n\n\n\\section{Intervention Threshold Sensitivity}\n\\label{app:intervention_sensitivity}\n\n\\paragraph{Within-$\\alpha$ sensitivity at $\\alpha{=}1.0$.}\nTable~\\ref{tab:threshold_sensitivity} reports the predictive cessation outcome under five entropy-drop thresholds (5\\%--25\\%) at $\\alpha{=}1.0$ (Pythia-410M, seed~42).\nAll five thresholds produce identical outcomes: token entropy drops 40.7\\% at generation~1, far exceeding even the most conservative threshold (25\\%), so every threshold triggers at the same generation.\nThe intervention conclusion---peak perplexity 57.0, recovery in one generation, final perplexity 21.3---is invariant to threshold choice within this range.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Threshold sensitivity at $\\alpha{=}1.0$ (Pythia-410M, s42, fp32). All thresholds trigger at generation~1 (entropy drop 40.7\\%$\\gg$threshold), producing identical recovery trajectories.}\n\\label{tab:threshold_sensitivity}\n\\begin{tabular}{rccr}\n\\toprule\nThreshold & Trigger gen & Peak PPL & Final PPL \\\\\n\\midrule\n5\\%  & 1 & 56.99 & 21.29 \\\\\n10\\% & 1 & 56.99 & 21.29 \\\\\n15\\% & 1 & 56.99 & 21.29 \\\\\n20\\% & 1 & 56.99 & 21.29 \\\\\n25\\% & 1 & 56.99 & 21.29 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cross-$\\alpha$ operating band.}\nThe within-$\\alpha$ analysis establishes threshold invariance at $\\alpha{=}1.0$ but does not address whether thresholds generalize across contamination levels.\nWe examine observed entropy trajectories from the alpha sweep (not actual intervention experiments at $\\alpha{<}1.0$) to characterize the operating band.\nThe maximum entropy drop across 10 generations varies by contamination level: 7.5\\% at $\\alpha{=}0.0$ (fine-tuning drift only), 7.7\\% at $\\alpha{=}0.10$, 7.8\\% at $\\alpha{=}0.25$, 22.4\\% at $\\alpha{=}0.50$, 35.3\\% at $\\alpha{=}0.75$, and 62.1\\% at $\\alpha{=}1.0$.\nThresholds below 7.5\\% (e.g., 5\\%) trigger on clean training data---a false alarm.\nThresholds above 22.4\\% (e.g., 25\\%) miss $\\alpha{=}0.50$, the lowest contamination level with meaningful entropy signal.\nThe safe operating band is therefore $[10\\%, 22\\%]$: any threshold in this range produces zero false alarms on $\\alpha{=}0.0$ while detecting contamination at $\\alpha{\\geq}0.50$.\nThe reported 15\\% threshold sits near the center of this band.\nThis analysis is based on entropy trajectories from non-intervention training runs; whether actual intervention at $\\alpha{<}1.0$ would produce the same triggering behavior remains unvalidated.\n\n\n\\section{Channel Effect Size Analysis}\n\\label{app:channel_effect_size}\n\nFirst-differencing eliminates all canary$\\to$perplexity Granger associations while preserving canary$\\to$diversity leads (\\S\\ref{sec:regime}).\nWe present three lines of evidence that this asymmetry reflects a genuine temporal structure difference rather than selective power loss from differencing.\n\n\\paragraph{Correlation retention parity.}\nFirst-differencing retains comparable correlation magnitude for both channel types (Table~\\ref{tab:channel_retention}).\nDiversity channels ($n{=}243$ pairs across all non-null experiments) retain a median $|r|$ of 0.952 after differencing, while perplexity channels ($n{=}8$ pairs; limited sample) retain 1.00.\nThis parity rules out a blanket power-loss explanation: if differencing selectively destroyed perplexity signal, $|r|$ retention would be substantially lower for perplexity than for diversity.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{First-differencing effect by channel type. $|r|$ retention = diff $|r|$ / naive $|r|$. Despite comparable $|r|$ retention, Granger $F$ differs by an order of magnitude. Perplexity channel has limited sample ($n{=}8$); all paired comparisons are from bf16 experiments.}\n\\label{tab:channel_retention}\n\\begin{tabular}{lrccrc}\n\\toprule\nChannel & $n$ & Naive $|r|$ & Diff $|r|$ & Retention & Med.\\ $F$ \\\\\n\\midrule\nDiversity   & 243 & 0.943 & 0.921 & 0.952 & 67.8 \\\\\nPerplexity  & 8   & 0.924 & 0.900 & 1.002 & 11.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Granger $F$-statistic asymmetry.}\nWithin matched experiments (same model, seed, $\\alpha$, precision), the Granger $F$-statistic is $20$--$28{\\times}$ higher for diversity than perplexity channels.\nAt $\\alpha{=}0.60$ (s42, bf16): diversity mean $F{=}229.4$ versus perplexity mean $F{=}8.3$ (ratio $27.8{\\times}$).\nAt $\\alpha{=}1.0$ reactive (s43, bf16): diversity mean $F{=}236.4$ versus perplexity mean $F{=}11.5$ (ratio $20.6{\\times}$).\nSince $|r|$ retention is comparable across channels, this $F$-statistic gap cannot be attributed to differencing-induced signal loss; it must reflect a difference in the temporal structure that Granger tests evaluate.\n\n\\paragraph{Temporal structure: lagged vs.\\ contemporaneous.}\nThe lag distribution of peak differenced cross-correlations reveals the structural difference.\nFor diversity channels, 81\\% of peak correlations occur at canary-leading lags (lag${<}0$), with a median lag of $-1$ generation---consistent with the one-generation temporal precedence visible in Figure~\\ref{fig:metric_trajectory}.\nFor perplexity channels, 50\\% of peak correlations occur at lag${=}0$ (contemporaneous co-movement), with a median lag of $0$.\nGranger precedence tests lagged predictive improvement; contemporaneous co-movement produces low $F$-statistics regardless of signal magnitude, which is the correct behavior for a test designed to detect temporal precedence.\nThe perplexity channel sample is limited ($n{=}8$ pairs from bf16 experiments), and these lag distributions should not be generalized to fp32 conditions without further validation.\n\n\n\\section{Mutual Information Analysis}\n\\label{app:mi_analysis}\n\nWe estimate the Gaussian mutual information lower bound between token entropy (canary) and each diversity metric across contamination levels, using $T{=}11$ data points per series ($T{=}10$ for two conditions).\nThe Gaussian estimator $\\hat{I}_G = -\\frac{1}{2}\\log_2(1 - r^2)$, where $r$ is the Pearson correlation, provides a conservative lower bound on MI; we do not report KSG nonparametric estimates due to uncorrected positive bias at $T{=}11$.\nThe $\\alpha{=}0.05$ data point is excluded because it uses an experiment excluded from the dose-response analysis.\n\nTable~\\ref{tab:mi_bounds} reports the mean Gaussian MI across the three distinct-$n$ metrics for each $\\alpha$ level.\nMI follows a V-shaped curve: it drops from 0.112~bits at $\\alpha{=}0.10$ to a minimum of 0.010~bits at $\\alpha{=}0.25$, then rises monotonically to 0.270~bits at $\\alpha{=}0.75$.\nMI remains positive throughout the blind zone ($\\alpha \\leq 0.45$; range 0.010--0.141~bits), confirming that canary--diversity coupling exists below the detection threshold but falls below PermG's statistical power floor at $T{=}10$.\nThere is no discontinuity at $\\alpha_c \\approx 0.50$: the detection onset reflects power accumulation, not an abrupt change in information coupling.\nBootstrap 95\\% CIs span 1--3 orders of magnitude at $T{=}11$, so individual point estimates should be interpreted cautiously.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Gaussian MI lower bound (bits) between token entropy and distinct-$n$ diversity metrics ($T{=}11$, Pythia-410M, fp32). Mean across distinct-1/2/3; $\\alpha{=}0.05$ excluded (see text). CIs omitted due to width at $T{=}11$.}\n\\label{tab:mi_bounds}\n\\begin{tabular}{rrc}\n\\toprule\n$\\alpha$ & Seeds & MI (bits) \\\\\n\\midrule\n0.10 & 2 & 0.112 \\\\\n0.25 & 3 & 0.010 \\\\\n0.30 & 1 & 0.062 \\\\\n0.35 & 1 & 0.098 \\\\\n0.40 & 1 & 0.119 \\\\\n0.45 & 2 & 0.141 \\\\\n0.50 & 3 & 0.107 \\\\\n0.60 & 2 & 0.209 \\\\\n0.75 & 1 & 0.270 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{Moment Cascade Analysis}\n\\label{app:moment_cascade}\n\nWe analyze the temporal ordering of metric degradation onset across 6 WikiText seed${\\times}\\alpha$ conditions (2 seeds $\\times$ 3 non-trivial $\\alpha$ levels each) to test whether token entropy consistently degrades before diversity metrics.\nOnset is defined as the first generation where a metric's cumulative change exceeds 5\\% of its generation-0 value.\n\nTable~\\ref{tab:moment_cascade} reports the onset generation for each metric across conditions.\nToken entropy reaches onset at generation~1 in all 6 conditions; distinct-$n$ metrics reach onset at generation~2 in all 18 pairwise comparisons (6 conditions $\\times$ 3 distinct-$n$ metrics).\nAcross these 18 comparisons, entropy degrades first in 16 cases (Kendall $\\tau{=}0.337$, consistent with a weak but reliable temporal ordering).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Degradation onset generation (5\\% threshold) by metric and condition (Pythia-410M, WikiText, fp32). Token entropy reaches onset at generation~1 in all non-null conditions; distinct-$n$ metrics follow at generation~2.}\n\\label{tab:moment_cascade}\n\\begin{tabular}{llcccccc}\n\\toprule\nSeed & $\\alpha$ & Entropy & Dist-1 & Dist-2 & Dist-3 & ECE & PPL \\\\\n\\midrule\n42 & 0.10 & 1 & 2 & 2 & 2 & 2 & --- \\\\\n42 & 0.50 & 1 & 2 & 2 & 2 & 1 & 4 \\\\\n42 & 0.75 & 1 & 2 & 2 & 2 & 1 & 1 \\\\\n43 & 0.25 & 1 & 2 & 2 & 2 & 4 & --- \\\\\n43 & 0.50 & 1 & 2 & 2 & 2 & 1 & 4 \\\\\n43 & 0.75 & 1 & 2 & 2 & 2 & 1 & 1 \\\\\n\\bottomrule\n\\multicolumn{8}{l}{\\footnotesize ---: onset not reached within $T{=}10$ generations.} \\\\\n\\end{tabular}\n\\end{table}\n\nThe cascade ordering provides evidence for the canary mechanism independent of Granger-type tests: it does not depend on first-differencing, lag selection, or the permutation null distribution.\nECE shows onset at generation~1 at $\\alpha{\\geq}0.50$ (both seeds), consistent with its role as a secondary canary metric.\nAt low contamination ($\\alpha{=}0.10$ and $\\alpha{=}0.25$), perplexity never reaches the 5\\% onset threshold within $T{=}10$ generations, while entropy already shows generation-1 onset---consistent with entropy's higher sensitivity to distributional shifts.\n\n\n\\section{Cascade Ordering Theory: Proofs}\n\\label{app:cascade_theory}\n\nThis section provides the full proofs for Proposition~\\ref{thm:entropy_leads} and Proposition~\\ref{prop:div_lag} from \\S\\ref{sec:cascade}, plus supporting results.\n\n\\begin{assumption}[Mode Amplification]\\label{ass:mode_amp}\nThe training map $\\mathcal{T}$ redistributes probability mass from low-probability to high-probability tokens: there exists a threshold $\\bar{p}$ such that $\\mathcal{T}(p)_i > p_i \\Rightarrow p_i \\geq \\bar{p}$ and $\\mathcal{T}(p)_j < p_j \\Rightarrow p_j \\leq \\bar{p}$.\n\\end{assumption}\n\nThis captures the standard finite-capacity approximation effect: MLE on finite samples from a peaked distribution amplifies modes and suppresses the tail~\\cite{shumailov2024curse,dohmatob2024tale}.\n\n\\begin{proposition}[Entropy is a first-order indicator]\\label{prop:entropy_first}\nLet $p \\in \\Delta^{V-1}$ and $\\delta = \\alpha(\\mathcal{T}(p) - p)$ be a mode-amplifying perturbation with $\\sum_i \\delta_i = 0$. Then $\\Delta H = H(p+\\delta) - H(p) = -\\sum_i \\delta_i \\log p_i + O(\\|\\delta\\|^2) < 0$.\n\\end{proposition}\n\n\\begin{proof}\nTaylor-expanding $H$ around $p$:\n$H(p+\\delta) = H(p) - \\sum_i \\delta_i \\log p_i - \\sum_i \\delta_i - \\frac{1}{2}\\sum_i \\delta_i^2/p_i + O(\\|\\delta\\|^3)$.\nSince $\\sum_i \\delta_i = 0$: $\\Delta H = -\\sum_i \\delta_i \\log p_i - \\frac{1}{2}\\sum_i \\delta_i^2/p_i + O(\\|\\delta\\|^3)$.\nUnder mode amplification, tokens gaining mass ($\\delta_i > 0$) have $p_i \\geq \\bar{p}$ (hence $\\log p_i \\geq \\log \\bar{p}$) and tokens losing mass ($\\delta_j < 0$) have $p_j \\leq \\bar{p}$ (hence $\\log p_j \\leq \\log \\bar{p}$).\nWriting $m = \\sum_{i:\\delta_i > 0} \\delta_i$: $-\\sum_i \\delta_i \\log p_i = -m[\\overline{\\log p}^{+} - \\overline{\\log p}^{-}] < 0$, where $\\overline{\\log p}^{\\pm}$ are the $|\\delta|$-weighted means over gaining/losing tokens.\nThe second-order Fisher information term $-\\frac{1}{2}\\sum_i \\delta_i^2/p_i$ is always negative, reinforcing the decrease.\n\\end{proof}\n\n\\begin{proposition}[Diversity is a threshold indicator]\\label{prop:div_threshold}\nDefine the $\\epsilon$-effective support $S_\\epsilon(p) = |\\{i \\in [V]: p_i > \\epsilon\\}|$, where $\\epsilon \\approx c/N$ is the generation threshold for sample size $N$.\nUnder the same perturbation $\\delta$: $\\Delta S_\\epsilon = -|\\{i: p_i > \\epsilon \\text{ and } p_i + \\delta_i \\leq \\epsilon\\}|$.\nThis equals zero whenever $\\|\\delta\\|_\\infty < \\gamma(p,\\epsilon) := \\min_{i: p_i > \\epsilon}(p_i - \\epsilon)$.\n\\end{proposition}\n\n\\begin{proof}\nToken $i$ exits the effective support iff $p_i > \\epsilon$ and $p_i + \\delta_i \\leq \\epsilon$, requiring $|\\delta_i| \\geq p_i - \\epsilon$.\nIf $\\|\\delta\\|_\\infty < \\gamma$, no token satisfies this condition.\n\\end{proof}\n\n\\paragraph{Proof of Proposition~\\ref{thm:entropy_leads}.}\n\\emph{Part (a):} Take any mode-amplifying $\\delta$ with $\\|\\delta\\|_\\infty < \\gamma(p,\\epsilon)$.\nBy Proposition~\\ref{prop:div_threshold}, $\\Delta S_\\epsilon = 0$.\nBy Proposition~\\ref{prop:entropy_first}, $\\Delta H < 0$.\nSuch $\\delta$ exists for all $\\alpha < \\gamma / \\max_i |\\mathcal{T}(p)_i - p_i|$.\n\\emph{Part (b):} If $\\Delta S_\\epsilon < 0$, some token $k$ has $p_k > \\epsilon$ but $p_k + \\delta_k \\leq \\epsilon$, so $\\delta_k < 0$.\nUnder mode amplification, this implies $p_k \\leq \\bar{p}$; the total mass transferred to high-probability tokens ensures $\\overline{\\log p}^+ > \\overline{\\log p}^-$.\nBy Proposition~\\ref{prop:entropy_first}, $\\Delta H < 0$. $\\square$\n\n\\paragraph{Proof of Proposition~\\ref{prop:div_lag}.}\nBy the margin condition, at every generation $s \\leq t_H$ the perturbation norm $\\alpha\\|\\mathcal{T}(p_s) - p_s\\|_\\infty$ is less than $\\gamma(p_s, \\epsilon)$.\nBy Proposition~\\ref{prop:div_threshold}, no token exits the effective support at any $s \\leq t_H$, so $\\Delta S_\\epsilon = 0$ for all $s \\leq t_H$.\nSince time is discrete, $t_D \\geq t_H + 1$. $\\square$\n\n\\paragraph{ECE co-movement (qualitative argument).}\nUnder conditional mode amplification (peakier $q_\\theta(\\cdot|x)$ at each generation), per-token conditional entropy $h(x) = H(q_\\theta(\\cdot|x))$ decreases while confidence $c(x) = \\max_y q_\\theta(y|x) \\geq \\exp(-h(x))$ increases.\nAveraging: $\\bar{H}_t$ decreases, $C_t$ increases.\nWith accuracy approximately stationary in early collapse ($A_t \\approx A_0$), $\\Delta\\mathrm{ECE} \\approx \\Delta C_t > 0$ whenever $\\Delta\\bar{H}_t < 0$.\nThis argument establishes the direction of co-movement; the quantitative relationship depends on distribution geometry.\n$\\bar{H}_t$ denotes mean conditional entropy $\\mathbb{E}_{x \\sim p_{\\text{eval}}}[h(x)]$, which differs from the marginal entropy $H_t = -\\sum_i p_t(i)\\log p_t(i)$ used in Proposition~\\ref{thm:entropy_leads}; under mode amplification, both decrease monotonically, so the cascade ordering is consistent across both formulations.\n\n\\paragraph{MAUVE ordering (conjecture).}\nMAUVE measures divergence in a discretized embedding space via $k$-means quantization.\nMAUVE onset requires token-level shifts (detected by entropy) to propagate through $n$-gram distributions (detected by distinct-$n$) to aggregate embedding distributions.\nEmpirically, MAUVE onset lags diversity by 0--1 generations on WikiText; however, on C4, MAUVE onset occurs at generation~1 (simultaneous with entropy), suggesting this lag is corpus-dependent.\n\n\\paragraph{Empirical support.}\nAmong 15 experiments at $\\alpha \\geq 0.30$ (where entropy perturbation exceeds the detection threshold), cascade ordering $t_H \\leq t_D$ holds in 14/15 cases (GPT-2-medium s43 fp32 exhibits bidirectional Granger significance).\nTable~\\ref{tab:cascade_onset} reports onset generations for representative conditions, showing uniform Phase~1/2/3 ordering.\nFive low-$\\alpha$ experiments ($\\alpha \\leq 0.25$) show entropy perturbation below the detection threshold (gen-1 deviation $<2\\sigma$); cascade ordering is neither confirmed nor refuted in this regime.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cascade onset generations (5\\% threshold) for representative experiments (Pythia-410M, WikiText, fp32). Phase~1: entropy and ECE ($t_H$, $t_{\\mathrm{ECE}}$); Phase~2: diversity ($t_D$, min over distinct-$n$); Phase~3: MAUVE ($t_M$). All conditions confirm the predicted ordering $t_H = t_{\\mathrm{ECE}} \\leq t_D \\leq t_M$.}\n\\label{tab:cascade_onset}\n\\begin{tabular}{llcccc}\n\\toprule\nSeed & $\\alpha$ & $t_H$ & $t_{\\mathrm{ECE}}$ & $t_D$ & $t_M$ \\\\\n\\midrule\n42 & 0.50 & 1 & 1 & 2 & 3 \\\\\n43 & 0.50 & 1 & 1 & 2 & 2 \\\\\n42 & 0.75 & 1 & 1 & 2 & 3 \\\\\n43 & 0.75 & 1 & 1 & 2 & 2 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\phantomsection\\label{app:alpha_c_proof}\n\\paragraph{Proof of Proposition~\\ref{prop:phase-boundary}.}\nAt the detection threshold, $\\mathrm{Power}(\\alpha_c, T) = \\pi^*$.\nSince $\\alpha_c$ lies below the non-monotonic dip region ($\\alpha_c < 0.55$), the signal model applies directly.\nFrom the power function $\\mathrm{Power} = \\Phi(S(\\alpha) \\cdot \\sqrt{T} / \\sigma)$, setting $S(\\alpha_c) \\cdot \\sqrt{T} / \\sigma = z^*$ and substituting the signal model $S(\\alpha) = c\\,\\alpha^\\beta$ yields $c\\,\\alpha_c^\\beta = z^* \\sigma / \\sqrt{T}$.\nSolving: $\\alpha_c(T) = (z^* \\sigma / c)^{1/\\beta} \\cdot T^{-1/(2\\beta)}$, giving the stated form with exponent $\\gamma = 1/(2\\beta)$.\n\n\\paragraph{Calibration and consistency.}\nCross-$T$ validation avoids the circularity of fitting theory to model-extrapolated points.\nWe fit $P(\\mathrm{det}|\\alpha,T) = \\Phi(A \\cdot \\alpha^\\beta \\cdot \\sqrt{T} - z_0)$ to training data at $T \\in \\{10, 20\\}$ via profile likelihood over $(\\beta, \\alpha_\\infty)$, with $\\alpha_\\infty{=}0$ emerging as the optimum.\nThe held-out test set ($T \\in \\{5, 15\\}$) yields MAE${=}0.106$ with 95\\% CI coverage $6/6$: the model correctly predicts all $0/8$ at $T{=}5$ and detection at $T{=}15$ (predicted $0.49$--$0.71$ vs.\\ observed $6/8{=}0.75$; under-prediction reflects the $P_{\\max}{=}0.75$ ceiling from MAUVE saturation, which is modeled separately).\nA linear signal model ($\\beta{=}1$, $\\gamma{=}0.5$) is rejected.\nThe sub-linear exponent $\\beta{=}0.24$ implies that doubling contamination increases signal by only $2^{0.24} \\approx 1.18\\times$ (18\\%); since $\\alpha_\\infty{\\approx}0$, any nonzero contamination produces signal, but detection requires sufficient $T$ to amplify it.\nAt $T{=}5$, $\\alpha_c \\geq 1.0$: no contamination level is detectable, consistent with the insufficient statistical power at very short observation windows.\n\n\\paragraph{Leave-one-$T$-out cross-validation.}\nWe evaluate model generalization via leave-one-$T$-out CV on the $5T \\times 3\\alpha$ grid (sync-dip $\\alpha{=}0.60$ excluded; 15 cells).\nFor each fold, one observation length is held out and the probit model $P = P_{\\max} \\cdot \\Phi(A \\cdot \\alpha^{0.24} \\cdot \\sqrt{T} - z_0)$ is refit on the remaining data.\nOverall MAE${=}0.037$ with 95\\% CI coverage $15/15$.\nWhen sync-dip cells are included (20 cells), MAE rises to $0.203$ (CI $16/20$), with the largest residuals at sync-dip cells (predicted $0.75$, observed $0/8$).\nThe profile likelihood over $\\beta$ yields MLE $\\hat{\\beta}{=}0.66$ (95\\% CI $[0.24, 0.78]$); the wide interval reflects a flat likelihood surface, indicating that $\\beta$ is not well-identified from these data.\nModel comparison (AIC, 15-cell grid excluding sync-dip): $M_1$ (linear boundary) $\\Delta\\mathrm{AIC}{=}0.0$; $M_2$ (power-probit) $\\Delta\\mathrm{AIC}{=}2.43$.\nIncluding sync-dip data reverses the ranking ($M_2$ $\\Delta\\mathrm{AIC}{=}0.0$, $M_1$ $\\Delta\\mathrm{AIC}{=}4.15$), because the probit model naturally accommodates the dip's dissolution at higher $T$ while linear models cannot.\n\n\\section{Power Simulation: Shape Comparison}\n\\label{app:power_sim}\n\nTo assess whether the observed steep detection onset could arise from smooth signal models, we simulate PermG detection under three null hypotheses (1{,}000 replications per cell, $n_{\\text{perm}}{=}1{,}000$, $n_{\\text{pairs}}{=}8$, BH-FDR $q{=}0.05$):\n\n\\begin{itemize}\n\\item \\textbf{H0} (linear): $S(\\alpha) = c \\cdot \\alpha$, calibrated so $S(1.0) = S_{\\max}$.\n\\item \\textbf{H0$'$} (concave): $S(\\alpha) = c \\cdot \\alpha^{0.5}$, sub-linear but smooth.\n\\item \\textbf{H1} (step): $S(\\alpha) = S_{\\max} \\cdot \\mathbf{1}[\\alpha > \\alpha_c(T)]$, binary activation.\n\\end{itemize}\n\n\\noindent\\textbf{Scaling exponents.}\nAll three models produce apparent onset scaling in $T$: H0 $\\gamma{=}0.85$, H0$'$ $\\gamma{=}1.87$, H1 $\\gamma{=}1.96$ (observed: $\\gamma{=}2.08$).\nH0$'$ produces $\\gamma$ within $0.21$ of the observed value, demonstrating that the scaling exponent alone cannot distinguish smooth from step-function boundaries.\n\n\\noindent\\textbf{Shape differences.}\nAt $T{=}10$, $\\alpha{=}0.45$: H0 predicts 27\\% detection rate, H0$'$ predicts 45\\%, H1 predicts 5.5\\%, observed $0/8$.\nAt $T{=}10$, $\\alpha{=}0.50$: H0 predicts 36\\%, H0$'$ predicts 48\\%, H1 predicts 4.6\\%, observed $6/8$ (75\\%).\nSmooth models produce onset ramps with $k{=}4.9$--$6.1$ (H0$'$: $k{=}4.93$, $R^2{=}0.9974$; H0: $k{=}6.14$, $R^2{=}0.9998$); the observed onset steepness ($k{=}15.7$) is ${\\approx}3{\\times}$ higher.\n\n\\noindent\\textbf{Metric-specific ceiling.}\nAt high $\\alpha$ (${\\geq}0.75$) with $T{\\geq}20$, H0 and H0$'$ (which simulate 8 equal-signal pairs) reach mean detection fractions of $0.79$--$0.98$ (${\\approx}6.3$--$7.8/8$), whereas observed counts never exceed $6/8$.\nThis gap reflects metric structure rather than signal saturation: the 2/8 non-detected pairs consistently involve MAUVE, whose floor saturation (\\S\\ref{sec:t20}) prevents Granger detection regardless of signal strength.\n\n\\section{T=20 Predict-then-Verify Comparison}\n\\label{app:t20_comparison}\n\nTable~\\ref{tab:t20_comparison} reports the predict-then-verify results for the $T{=}20$ extension experiments.\nPredictions are derived from the detection boundary model (\\S\\ref{sec:theory}): detected pairs at $T{=}10$ are predicted to remain detected (saturated $F$-statistics), and undetected pairs are predicted to remain undetected (structural nulls or non-monotonic dip).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{T=20 predict-then-verify comparison (Pythia-410M, seed~42, WikiText, fp32). Excluding $\\alpha{=}1.0$, two of four predictions fall within CI ($\\alpha{=}0.50$, $0.75$); boundary cases show systematic bias---$\\alpha{=}0.45$ falsifies the ceiling hypothesis (under-prediction), $\\alpha{=}0.60$ over-predicts under raw $p$-values (v1; matches under FDR v2, not pre-committed).}\n\\label{tab:t20_comparison}\n\\begin{tabular}{lcccc}\n\\toprule\n$\\alpha$ & $T{=}10$ & Predicted $T{=}20$ & Observed $T{=}20$ & Match \\\\\n\\midrule\n0.45 & 0/8 & 0/8 (ceiling) & 5/8 & $\\times$ \\\\\n0.50 & 6/8 & 6/8 (saturated) & 6/8 & \\checkmark \\\\\n0.60 & 0/8 & 3/8 (v1 raw)$^\\dagger$ & 0/8 & $\\times$ \\\\\n0.75 & 6/8 & 6/8 (saturated) & 6/8 & \\checkmark \\\\\n1.00 & 6/8 & 6/8 (saturated) & 6/8 & \\checkmark \\\\\n\\bottomrule\n\\multicolumn{5}{l}{\\footnotesize $^\\dagger$V2 (BH--FDR corrected, created 44\\,min pre-analysis, not git-committed) predicts 0/8, matching observation.} \\\\\n\\end{tabular}\n\\end{table}\n\nAt $\\alpha \\geq 0.50$, consistency across $T{=}10$ and $T{=}20$ supports the detection boundary prediction: PermG counts are determined by signal structure, not observation length.\nSix diversity-based pairs show $F{=}449$--$2947$ at $T{=}20$ (all $\\gg F_{\\text{crit}}$); two MAUVE-based pairs show $F{<}2$ regardless of $T$, driven by floor saturation ($\\mu{=}0.029$, 100\\% ${<}0.05$) rather than high variance (CV$_{\\text{MAUVE}}{=}0.089$ vs CV$_{\\text{distinct-1}}{=}0.139$); SNR: MAUVE $4.68$ vs diversity $6.40$--$8.20$ ($p{<}0.001$).\nThe sole exception is $\\alpha{=}0.45$ at $T{=}20$ (5/8), consistent with boundary proximity.\nAt $\\alpha{=}0.45$, the shift from 0/8 to 5/8 falsifies Model~A (ceiling: $\\alpha{=}0.45$ structurally undetectable) in favor of Model~B (power-limited: $\\sqrt{T}$ boost crosses the detection threshold), lowering $\\alpha_c$ below~0.45.\nThe $\\alpha{=}0.60$ non-monotonic dip persists at $T{=}20$ (s42: 0/8; s43: 3/8) but dissolves at $T{=}25$ (5/8), confirming that $\\sqrt{T}$ power scaling eventually overcomes the dip; alternative methods detect signal throughout (DiffXCorr 6/8, TY 5/8 at $T{=}20$).\nPermG directional selectivity is consistent across tested $T$ ($T{=}10$, $20$): forward 6/8 versus reverse 0/8 at $\\alpha \\in \\{0.50, 0.75, 1.0\\}$.\n\n\n\\subsection{Prediction Timeline}\n\\label{app:t20_prediction_timeline}\n\nTwo versions of the $T{=}20$ prediction file exist, reflecting an evolving statistical protocol:\n\n\\paragraph{V1 (git-committed, \\texttt{bad72cc}).} Predictions derived from $T{=}10$ PermG results using \\emph{raw} $p$-values. At $\\alpha{=}0.60$, v1 counted 3/8 pairs with raw $p{<}0.05$, predicting 3/8 detections at $T{=}20$. The observed result (0/8 FDR-significant) does not match.\n\n\\paragraph{V2 (pre-analysis, not committed).} A revised file incorporating BH--FDR correction at $q{=}0.05$, consistent with the correction applied throughout the paper. Under FDR, $\\alpha{=}0.60$ drops from 3/8 (raw) to 0/8, matching the observation. V2 was created 44 minutes before the formal $T{=}20$ analysis began (filesystem timestamp) but was not git-committed, and therefore lacks the cryptographic verifiability of v1.\n\n\\paragraph{Scoring.} Primary (v1, committed): 3/5 exact matches ($\\alpha \\in \\{0.50, 0.75, 1.0\\}$, all saturated regimes). Excluding $\\alpha{=}1.0$, two of four predictions fall within CI. Both boundary predictions miss: $\\alpha{=}0.45$ (predicted 0/8, observed 5/8) falsifies the ceiling hypothesis in favor of $\\sqrt{T}$ power scaling; $\\alpha{=}0.60$ (predicted 3/8, observed 0/8) over-estimates detection due to the non-monotonic dip. Sensitivity (v2, FDR-corrected): 4/5 ($\\alpha{=}0.60$ matches). The systematic conservative bias at $\\alpha{=}0.45$ is consistent with the $\\sqrt{T}$ power increase predicted by Proposition~\\ref{prop:phase-boundary}.\n\n\n\\phantomsection\\label{app:task_degradation}\n\\paragraph{Task degradation.}\n\nTable~\\ref{tab:task_degradation} reports end-of-training task performance (generation~10, Pythia-410M, seed~42, fp32) across contamination levels.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Task degradation across contamination levels (Pythia-410M, seed~42, fp32, generation~10). Perplexity evaluated on held-out WikiText-103.}\n\\label{tab:task_degradation}\n\\begin{tabular}{lcc}\n\\toprule\n$\\alpha$ & Perplexity & Next-token acc. \\\\\n\\midrule\nBaseline & 26.6 & 0.390 \\\\\n0.05 & 20.8 & 0.431 \\\\\n0.25 & 22.9 & 0.424 \\\\\n0.46 & 31.6 & 0.400 \\\\\n0.50 & 31.3 & 0.399 \\\\\n0.52 & 41.1 & 0.389 \\\\\n0.60 & 53.5 & 0.375 \\\\\n0.75 & 80.3 & 0.354 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt $\\alpha{=}0.05$, perplexity improves over the uncontaminated baseline (20.8 vs.\\ 26.6), consistent with a mild data augmentation effect.\nThe sharpest degradation occurs between $\\alpha{=}0.50$ and $0.52$ ($+31\\%$ perplexity), aligning with the PermG detection onset (\\S\\ref{sec:regime}).\n\n\\section{Cross-Architecture FPR Sensitivity}\n\\label{app:cross_arch_fpr}\n\nAs preliminary cross-architecture evidence, we evaluate null-condition ($\\alpha{=}0$) false positive rates on GPT-2-medium (345M; OpenAI), a model outside the Pythia family used for all primary experiments.\nTwo seeds (s42, s43) are trained for $T{=}10$ generations under the same protocol as the Pythia-410M null runs.\nThis evaluation requires additional replication across architectures and seed counts before drawing definitive conclusions.\n\n\\begin{table}[h]\n\\centering\n\\caption{Null-condition FPR for GPT-2-medium ($\\alpha{=}0$, $T{=}10$, 6-pair basis). PermG forward detection shows extreme seed dependence; $K{\\geq}3$ consensus remains at 0\\% across both seeds.}\n\\label{tab:gpt2m_null_fpr}\n\\begin{tabular}{lccc}\n\\toprule\nSeed & PermG fwd & PermG rev & $K{\\geq}3$ \\\\\n\\midrule\ns42 & 6/6 (100\\%) & 0/6 & 0/6 \\\\\ns43 & 0/6 (0\\%) & 0/6 & 0/6 \\\\\n\\midrule\nPooled & 6/12 (50\\%) & 0/12 & 0/12 (0\\%) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe pooled PermG FPR is dramatically higher than on Pythia-410M (50\\% vs.\\ 11.1\\%, 6-pair basis) and shows extreme seed dependence (100\\% vs.\\ 0\\%).\nThis instability traces to the magnitude of null drift in GPT-2-medium's output distribution, which is substantially stronger than in Pythia-410M (Table~\\ref{tab:null_drift_comparison}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Null drift magnitude ($\\alpha{=}0$, gen\\,0$\\to$10; GPT-2-medium: 2 seeds; Pythia-410M: 4 seeds, s46/s48--s50). GPT-2-medium exhibits ${\\sim}4{\\times}$ stronger entropy drift and ${\\sim}7{\\times}$ stronger distinct-3 drift than Pythia-410M.}\n\\label{tab:null_drift_comparison}\n\\begin{tabular}{lcccc}\n\\toprule\n& \\multicolumn{2}{c}{GPT-2-medium} & \\multicolumn{2}{c}{Pythia-410M} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nMetric & gen\\,0 & gen\\,10 (\\%$\\Delta$) & gen\\,0 & gen\\,10 (\\%$\\Delta$) \\\\\n\\midrule\nToken entropy & 3.57 & 2.84 ($-$20.5\\%) & 3.23 & 3.076 ($-$4.9\\%) \\\\\nDistinct-3 & 0.84 & 0.54 ($-$35.8\\%) & 0.81 & 0.769 ($-$4.9\\%) \\\\\n$\\Delta$entropy (gen\\,0$\\to$1) & \\multicolumn{2}{c}{$-$0.60} & \\multicolumn{2}{c}{$-$0.25} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nGPT-2-medium's distinct-3 declines from 0.84 to 0.54 over ten null generations ($-$35.8\\%), compared with 0.81$\\to$0.77 ($-$4.9\\%) for Pythia-410M.\nThis steep diversity collapse under pure retraining, absent any synthetic contamination, creates a strong downward trend that PermG's permutation test interprets as a directional signal.\nThe initial entropy drop (gen\\,0$\\to$1: $-$0.60 vs.\\ $-$0.25) is similarly amplified, consistent with architecture-specific sensitivity to iterative retraining rather than a deficiency in the detection method.\n\nThe $K{\\geq}3$ multi-method consensus maintains 0\\% FPR on GPT-2-medium (0/12 pairs), though the margin of safety is narrow: in the worst case (s42), 2 of 5 methods vote for forward detection, one vote short of the $K{\\geq}3$ threshold.\nThis provides some protection against architecture-specific distributional variation, but two seeds constitute only preliminary evidence.\nFor reference, PermG successfully detects true contamination signal ($\\alpha{=}1.0$) on GPT-2-medium with 6/8 forward pairs (Table~\\ref{tab:generalization}), confirming that the method works when signal is present; the elevated null FPR is specific to the null condition where architecture-dependent drift dominates.\n\n\\section*{Use of AI Assistants}\n\\label{app:ai-assistants}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant throughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections, polishing prose, and reformatting LaTeX.\n    \\item \\textbf{Literature:} summarizing related papers to inform related-work section.\n\\end{itemize}\n\n",
    "structuredPatch": [
      {
        "oldStart": 768,
        "oldLines": 17,
        "newStart": 768,
        "newLines": 16,
        "lines": [
          " ",
          " The detection results reported in the main text use equal-weight majority voting ($K{\\geq}3$ of 5 methods, each contributing at most one vote per pair); PermG contributes at most $1/5 = 20\\%$ of the consensus weight.",
          " FPR-inverse weighting is used \\emph{only} in the exploratory method ranking below, not in the detection results.",
          "-To verify that PermG's top ranking is not an artifact of the FPR-inverse weighting scheme, we recompute Shapley values under four weight specifications (Table~\\ref{tab:weight_robustness}).",
          "-Equal weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first ($\\phi^{\\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.",
          "+To verify that PermG's directional-method ranking is not an artifact of the FPR-inverse weighting scheme, we recompute weighted Shapley values under four weight specifications (Table~\\ref{tab:weight_robustness}).",
          "+This analysis uses the 3-seed null control (seeds 42/43/44, 24 pairs), under which PermG had zero FPR; the union-based analysis with 6-seed null (Table~\\ref{tab:shapley_6pair}) yields a non-zero PermG FPR Shapley ($+0.039$) and shifts the overall best contributor to DiffXCorr ($-0.299$).",
          "+Equal weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first among directional methods ($\\phi^{\\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.",
          " Under cap-5, the margin widens to 0.043 as the FPR penalty begins to differentiate high-FPR methods.",
          " Cap-10 and original cap-100 yield identical Shapley values because the consensus threshold ($K{\\geq}3$) is determined by the three smallest method weights ($w_{\\text{naive}}{+}w_{\\text{diff}}{+}w_{\\text{thresh}} = 7.76$), which are invariant to further increases in the PermG or TY cap; this saturation confirms that the original $w{=}100$ does not artificially inflate PermG's contribution.",
          "-% TODO-D219: recompute weight robustness table with 6-seed data; PermG φ^FPR will be >0",
          "-Across all schemes, PermG's advantage derives from the same structural property: zero FPR ($\\phi^{\\text{FPR}}{=}0$) combined with moderate FNR reduction ($\\phi^{\\text{FNR}}{=}-0.152$ to $-0.426$).",
          " ",
          " \\begin{table}[h]",
          " \\centering",
          " \\small",
          "-\\caption{MMCT weight robustness: PermG combined Shapley under four weighting schemes. PermG ranks first in all cases. Gap = $|\\phi^{\\text{comb}}_{\\text{PermG}} - \\phi^{\\text{comb}}_{\\text{runner-up}}|$. 48 experiments (3 null + 45 signal), exact Shapley enumeration ($2^5{=}32$ coalitions).}",
          "+\\caption{MMCT weight robustness (3-seed null, 48 experiments): PermG combined Shapley under four weighting schemes. PermG ranks first among directional methods in all cases. Gap = $|\\phi^{\\text{comb}}_{\\text{PermG}} - \\phi^{\\text{comb}}_{\\text{runner-up}}|$. $2^5{=}32$ coalitions, exact enumeration.}",
          " \\label{tab:weight_robustness}",
          " \\begin{tabular}{lrcrc}",
          " \\toprule"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---


### Assistant

_source line 132_

Now TODO-D219 #7 — check the direction filtering paragraph around L832. Let me re-read that area.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "fc410b2d-6e0c-47ba-8eb6-3ea8497e39b3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Eh3RwnjpP7cZrQs3tkYbvc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3119,
      "cache_read_input_tokens": 114746,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3119
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool call

_source line 133_

<details open><summary>🔧 Tool call — Read · `toolu_013hneWmsNqwReTCfQaJrUou`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
  "offset": 828,
  "limit": 20
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "1dfaa2e2-afac-469f-92d5-a29046965c99",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Eh3RwnjpP7cZrQs3tkYbvc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3119,
      "cache_read_input_tokens": 114746,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3119
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool result

_source line 134 · 2026-05-24T09:07:37.057Z_

<details><summary>↩ Tool result · `toolu_013hneWmsNqwReTCfQaJrUou`</summary>

```text
828	Forward-direction filtering (retaining only pairs with peak lag${<}0$ for cross-correlation methods) reduces null-control $K{\geq}3$ false positives.
829	Under the 6-seed, 6-pair basis, $K{\geq}3$ consensus with filtering produces 6/36 false positives (16.7\%; detail below); the 3-seed pilot underestimated this rate (0/8).
830	Detection at $\alpha{\geq}0.50$ is unaffected: $K{\geq}3$ counts are identical with and without direction filtering at all signal levels.
831	
832	\paragraph{$K{\geq}3$ false positive detail.}
833	Under the 6-pair basis (6~seeds, 36~pairs), $K{\geq}3$ consensus produces 6 false positives (FPR${=}16.7\%$).
834	Of these, 4 are driven by naive cross-correlation, threshold onset, and Toda--Yamamoto (PermG does \emph{not} vote); the remaining 2 (seeds~45 and 50, te$\to$distinct) include PermG in the consensus.
835	PermG thus contributes to only 2 of 6 consensus false positives, confirming that most $K{\geq}3$ FPR is driven by the high-FPR methods (naive, threshold, TY).
836	
837	\paragraph{Sensitivity to FPR assumption.}
838	Even under the conservative upper bound of the cluster-adjusted CI (30.4\%), PermG remains the lowest-FPR directional method: DiffXCorr achieves a lower FPR under identical BH-FDR correction (2.8\%) but lacks forward/reverse separation; the next directional method (threshold onset) has 27.8\% and Toda--Yamamoto 38.9\%.
839	Our primary results rely on equal-weight $K{\geq}3$ majority voting, where each method contributes exactly one vote regardless of its FPR---this mechanism is completely unaffected by any FPR assumption.
840	For the exploratory FPR-inverse weighting, PermG's weight ($w{=}1/0.111{=}9.0$) exceeds all directional alternatives (threshold: 3.6, TY: 2.6, naive: 1.1); DiffXCorr ($w{=}1/0.028{=}35.7$) receives a higher weight but lacks directional separation, preserving PermG's rank among directional methods.
841	The insensitivity of both the voting mechanism and the method ranking to the upper CI bound provides evidence that the MMCT conclusions are robust to uncertainty in PermG's Type~I error rate.
842	
843	\section{Sigmoid Transition Shape}
844	\label{app:sigmoid_shape}
845	
846	Sigmoid regression on the original 13-point $T{=}10$ grid yields $\alpha_c = 0.483 \pm 0.006$ but $k = 478 \pm 475$ ($\mathrm{SE}(k) \approx k$), indicating that the coarse grid cannot constrain the transition shape.
847	Dense $\alpha$ sampling (17~values at $T{=}10$) resolves this ambiguity: formal likelihood-ratio testing strongly favors a smooth sigmoid over a literal step function ($\Delta\mathrm{AIC}{=}-110$), with fitted steepness $k{=}15.7$ (95\% CI $[9.4, 28.2]$).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "badf63ae-ca4e-4016-972f-f3f4ff27f255",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
      "content": "Forward-direction filtering (retaining only pairs with peak lag${<}0$ for cross-correlation methods) reduces null-control $K{\\geq}3$ false positives.\nUnder the 6-seed, 6-pair basis, $K{\\geq}3$ consensus with filtering produces 6/36 false positives (16.7\\%; detail below); the 3-seed pilot underestimated this rate (0/8).\nDetection at $\\alpha{\\geq}0.50$ is unaffected: $K{\\geq}3$ counts are identical with and without direction filtering at all signal levels.\n\n\\paragraph{$K{\\geq}3$ false positive detail.}\nUnder the 6-pair basis (6~seeds, 36~pairs), $K{\\geq}3$ consensus produces 6 false positives (FPR${=}16.7\\%$).\nOf these, 4 are driven by naive cross-correlation, threshold onset, and Toda--Yamamoto (PermG does \\emph{not} vote); the remaining 2 (seeds~45 and 50, te$\\to$distinct) include PermG in the consensus.\nPermG thus contributes to only 2 of 6 consensus false positives, confirming that most $K{\\geq}3$ FPR is driven by the high-FPR methods (naive, threshold, TY).\n\n\\paragraph{Sensitivity to FPR assumption.}\nEven under the conservative upper bound of the cluster-adjusted CI (30.4\\%), PermG remains the lowest-FPR directional method: DiffXCorr achieves a lower FPR under identical BH-FDR correction (2.8\\%) but lacks forward/reverse separation; the next directional method (threshold onset) has 27.8\\% and Toda--Yamamoto 38.9\\%.\nOur primary results rely on equal-weight $K{\\geq}3$ majority voting, where each method contributes exactly one vote regardless of its FPR---this mechanism is completely unaffected by any FPR assumption.\nFor the exploratory FPR-inverse weighting, PermG's weight ($w{=}1/0.111{=}9.0$) exceeds all directional alternatives (threshold: 3.6, TY: 2.6, naive: 1.1); DiffXCorr ($w{=}1/0.028{=}35.7$) receives a higher weight but lacks directional separation, preserving PermG's rank among directional methods.\nThe insensitivity of both the voting mechanism and the method ranking to the upper CI bound provides evidence that the MMCT conclusions are robust to uncertainty in PermG's Type~I error rate.\n\n\\section{Sigmoid Transition Shape}\n\\label{app:sigmoid_shape}\n\nSigmoid regression on the original 13-point $T{=}10$ grid yields $\\alpha_c = 0.483 \\pm 0.006$ but $k = 478 \\pm 475$ ($\\mathrm{SE}(k) \\approx k$), indicating that the coarse grid cannot constrain the transition shape.\nDense $\\alpha$ sampling (17~values at $T{=}10$) resolves this ambiguity: formal likelihood-ratio testing strongly favors a smooth sigmoid over a literal step function ($\\Delta\\mathrm{AIC}{=}-110$), with fitted steepness $k{=}15.7$ (95\\% CI $[9.4, 28.2]$).",
      "numLines": 20,
      "startLine": 828,
      "totalLines": 1268
    }
  }
}
```

</details>

---


### Assistant

_source line 135_

<details><summary>Logged reasoning block</summary>

```text
The direction filtering paragraph (L828-841) is already using 6-seed data and doesn't have a TODO-D219 marker. The task description says "L832 area: this is not a TODO marker but direction filtering paragraph references old data, check if needs updating."

Looking at the content:
- L829: "6/36 false positives (16.7%)" — this is 6-seed data, looks correct
- L833: "K≥3 consensus produces 6 false positives" — correct
- L834-835: PermG contributes to 2 of 6 — correct


- L838-840: The FPR values and weight calculations are all consistent with the 6-seed data, so no update is needed here either.

Now I'm checking whether all the TODO-D219 markers have been removed from the document.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "c9d22088-f848-4672-a825-154b16d34d36",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QqrXkwiGYYfQpfZvWUnLkr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1035,
      "cache_read_input_tokens": 117865,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1035
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Assistant

_source line 136_

The direction filtering paragraph (L828-841) already uses 6-seed data — no update needed. Let me verify all TODO-D219 markers are removed.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "2a7166c1-4ba9-488f-91c9-f7a7841c0e32",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QqrXkwiGYYfQpfZvWUnLkr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1035,
      "cache_read_input_tokens": 117865,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1035
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool call

_source line 137_

<details open><summary>🔧 Tool call — Grep · `toolu_01CT9utTvRXxtN9nyYXtCbof`</summary>

```json
{
  "pattern": "TODO-D219",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "e8686bd8-5f17-457e-b966-8bba1903f797",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QqrXkwiGYYfQpfZvWUnLkr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1035,
      "cache_read_input_tokens": 117865,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1035
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool result

_source line 138 · 2026-05-24T09:07:52.220Z_

<details><summary>↩ Tool result · `toolu_01CT9utTvRXxtN9nyYXtCbof`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "54b7637e-ccea-4a43-8ec1-98258d925a6f",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---


### Assistant

_source line 139_

All TODO-D219 markers removed. Now let me do final verification — check the appendix edits are consistent.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "8806ab71-cbaf-48b5-b4e5-3011ed1d81ce",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013iYyK3r7MF93oY4jakRMRY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 543,
      "cache_read_input_tokens": 118900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 543
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool call

_source line 140_

<details open><summary>🔧 Tool call — TodoWrite · `toolu_01QAyyudhc7S88nrn18EEAhZ`</summary>

```json
{
  "todos": [
    {
      "content": "Write and run Shapley computation script with 6-seed null data",
      "status": "completed",
      "activeForm": "Writing and running Shapley computation script"
    },
    {
      "content": "Update gen_shapley_contribution.py and regenerate figure",
      "status": "completed",
      "activeForm": "Updating figure generation script"
    },
    {
      "content": "Find treatment PermG data for FDR sensitivity table update",
      "status": "completed",
      "activeForm": "Finding treatment PermG data"
    },
    {
      "content": "Update appendix.tex — all 7 TODO-D219 locations",
      "status": "completed",
      "activeForm": "Updating appendix.tex"
    },
    {
      "content": "Verify all numbers and TODO removals",
      "status": "in_progress",
      "activeForm": "Verifying consistency"
    }
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "d5bdfbc6-815d-4300-a118-76c7880f38b9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013iYyK3r7MF93oY4jakRMRY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 543,
      "cache_read_input_tokens": 118900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 543
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool result

_source line 141 · 2026-05-24T09:08:01.864Z_

<details><summary>↩ Tool result · `toolu_01QAyyudhc7S88nrn18EEAhZ`</summary>

```text
Todos have been modified successfully. Ensure that you continue to use the todo list to track your progress. Please proceed with the current tasks if applicable
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "b3d2fa86-bbd8-47d3-b1cc-9d418cb39cee",
  "tool_use_result": {
    "oldTodos": [
      {
        "content": "Write and run Shapley computation script with 6-seed null data",
        "status": "completed",
        "activeForm": "Writing and running Shapley computation script"
      },
      {
        "content": "Update gen_shapley_contribution.py and regenerate figure",
        "status": "completed",
        "activeForm": "Updating figure generation script"
      },
      {
        "content": "Find treatment PermG data for FDR sensitivity table update",
        "status": "completed",
        "activeForm": "Finding treatment PermG data"
      },
      {
        "content": "Update appendix.tex — all 7 TODO-D219 locations",
        "status": "in_progress",
        "activeForm": "Updating appendix.tex"
      },
      {
        "content": "Verify all numbers and TODO removals",
        "status": "pending",
        "activeForm": "Verifying consistency"
      }
    ],
    "newTodos": [
      {
        "content": "Write and run Shapley computation script with 6-seed null data",
        "status": "completed",
        "activeForm": "Writing and running Shapley computation script"
      },
      {
        "content": "Update gen_shapley_contribution.py and regenerate figure",
        "status": "completed",
        "activeForm": "Updating figure generation script"
      },
      {
        "content": "Find treatment PermG data for FDR sensitivity table update",
        "status": "completed",
        "activeForm": "Finding treatment PermG data"
      },
      {
        "content": "Update appendix.tex — all 7 TODO-D219 locations",
        "status": "completed",
        "activeForm": "Updating appendix.tex"
      },
      {
        "content": "Verify all numbers and TODO removals",
        "status": "in_progress",
        "activeForm": "Verifying consistency"
      }
    ],
    "verificationNudgeNeeded": false
  }
}
```

</details>

---


### Tool call

_source line 142_

<details open><summary>🔧 Tool call — Read · `toolu_01YXV1vVGv5i9krHdGAQLNX2`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
  "offset": 126,
  "limit": 25
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "c5ee97b7-a576-47d6-8f26-a70f05dc0044",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XeDwJzj6Yo3my8NaZgpvXk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 310,
      "cache_read_input_tokens": 119443,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 310
      },
      "output_tokens": 59,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool result

_source line 143 · 2026-05-24T09:08:06.885Z_

<details><summary>↩ Tool result · `toolu_01YXV1vVGv5i9krHdGAQLNX2`</summary>

```text
126	\paragraph{FDR threshold sensitivity.}
127	Table~\ref{tab:fdr_sensitivity} reports the effect of varying the BH FDR threshold $q$ on treatment ($\alpha{=}0.75$, 3~seeds, 8-pair basis) versus null ($\alpha{=}0.0$, 6~seeds 45--50, 6-pair basis) separation for permutation Granger tests.
128	Treatment/null separation is qualitatively robust to FDR threshold choice, though the expanded null sample reveals a small number of false positives at each threshold (3--8 of 36 pairs).
129	
130	\begin{table}[h]
131	\centering
132	\small
133	\caption{FDR threshold sensitivity for permutation Granger significance. Treatment: $\alpha{=}0.75$ (3~seeds, 24 forward-direction pairs, 8-pair basis). Null: $\alpha{=}0.0$ (6~seeds 45--50, 36 pairs, 6-pair basis). The expanded null sample reveals modest false positive rates that increase with $q$.}
134	\label{tab:fdr_sensitivity}
135	\resizebox{\columnwidth}{!}{%
136	\begin{tabular}{lccc}
137	\toprule
138	$q$ & Null FDR-sig (/36) & Treatment FDR-sig (/24) & Separation \\
139	\midrule
140	0.01 & 3 & 0  & Underpowered \\
141	0.05 & 4 & 19 & Good \\
142	0.10 & 8 & 24 & Good (elevated null) \\
143	\bottomrule
144	\end{tabular}}
145	\end{table}
146	
147	\paragraph{PermG $p$-value gradient at the onset boundary ($\alpha{=}0.45$).}
148	At the onset boundary, PermG operates near its detection limit, and marginal $p$-values exhibit seed-dependent variation consistent with the statistical power interpretation (\S\ref{sec:theory}).
149	Table~\ref{tab:fdr_gradient_a045} reports BH-corrected $p$-values for all 8 canary$\to$downstream pairs across two seeds at $\alpha{=}0.45$.
150	Seed~43 reaches a minimum FDR-corrected $p{=}0.059$ (18\% above the $q{=}0.05$ threshold), while seed~42 reaches $p{=}0.091$ (82\% above threshold).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "d73f8dc9-7a35-4514-85e2-bb4c0b982504",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
      "content": "\\paragraph{FDR threshold sensitivity.}\nTable~\\ref{tab:fdr_sensitivity} reports the effect of varying the BH FDR threshold $q$ on treatment ($\\alpha{=}0.75$, 3~seeds, 8-pair basis) versus null ($\\alpha{=}0.0$, 6~seeds 45--50, 6-pair basis) separation for permutation Granger tests.\nTreatment/null separation is qualitatively robust to FDR threshold choice, though the expanded null sample reveals a small number of false positives at each threshold (3--8 of 36 pairs).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{FDR threshold sensitivity for permutation Granger significance. Treatment: $\\alpha{=}0.75$ (3~seeds, 24 forward-direction pairs, 8-pair basis). Null: $\\alpha{=}0.0$ (6~seeds 45--50, 36 pairs, 6-pair basis). The expanded null sample reveals modest false positive rates that increase with $q$.}\n\\label{tab:fdr_sensitivity}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n$q$ & Null FDR-sig (/36) & Treatment FDR-sig (/24) & Separation \\\\\n\\midrule\n0.01 & 3 & 0  & Underpowered \\\\\n0.05 & 4 & 19 & Good \\\\\n0.10 & 8 & 24 & Good (elevated null) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{PermG $p$-value gradient at the onset boundary ($\\alpha{=}0.45$).}\nAt the onset boundary, PermG operates near its detection limit, and marginal $p$-values exhibit seed-dependent variation consistent with the statistical power interpretation (\\S\\ref{sec:theory}).\nTable~\\ref{tab:fdr_gradient_a045} reports BH-corrected $p$-values for all 8 canary$\\to$downstream pairs across two seeds at $\\alpha{=}0.45$.\nSeed~43 reaches a minimum FDR-corrected $p{=}0.059$ (18\\% above the $q{=}0.05$ threshold), while seed~42 reaches $p{=}0.091$ (82\\% above threshold).",
      "numLines": 25,
      "startLine": 126,
      "totalLines": 1268
    }
  }
}
```

</details>

---


### Tool call

_source line 144_

<details open><summary>🔧 Tool call — Read · `toolu_01PhTusybq5MopAeC4RUgz9U`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
  "offset": 720,
  "limit": 80
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "553bb57b-97e7-44f2-9e84-bc5ce5f20871",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XeDwJzj6Yo3my8NaZgpvXk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 310,
      "cache_read_input_tokens": 119443,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 310
      },
      "output_tokens": 59,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool result

_source line 145 · 2026-05-24T09:08:07.394Z_

<details><summary>↩ Tool result · `toolu_01PhTusybq5MopAeC4RUgz9U`</summary>

```text
720	
721	We quantify each method's marginal contribution to the MMCT ensemble using Shapley values~\cite{shapley1953value}, computed via exact enumeration over all $2^5{=}32$ coalitions of the five detection methods.
722	For a coalition $S \subseteq \{m_1, \ldots, m_5\}$, we define two performance metrics: the false positive rate FPR($S$), computed from 6 null experiments ($\alpha{=}0.0$, seeds 45--50; 36 null pairs on the 6-pair basis excluding mauve), and the false negative rate FNR($S$), computed from 45 signal experiments across all non-null $\alpha$ levels (270 signal pairs for the 6-pair variant excluding mauve).
723	The Shapley value $\phi_k$ for method $m_k$ is the weighted average of its marginal contribution across all coalitions; positive FPR-Shapley indicates the method \emph{increases} false positives, while negative FNR-Shapley indicates it \emph{reduces} false negatives.
724	The combined Shapley value $\phi_k^{\text{comb}} = \phi_k^{\text{FPR}} + \phi_k^{\text{FNR}}$ balances both error types, with more negative values indicating greater net benefit.
725	
726	Table~\ref{tab:shapley_6pair} reports the 6-pair analysis (excluding mauve).
727	DiffXCorr achieves the lowest (best) combined Shapley ($-0.299$), driven by near-zero FPR contribution ($+0.007$) and strong FNR reduction ($-0.306$); however, DiffXCorr cannot separate forward from reverse causation (Table~\ref{tab:null_fpr_methods}).
728	Among directional methods, PermG ranks best ($-0.141$ combined), with a modest FPR contribution ($+0.039$, reflecting 4/36 null false positives) offset by substantial FNR reduction ($-0.180$).
729	Naive cross-correlation is the worst contributor ($+0.190$), with its massive FPR Shapley ($+0.609$) overwhelming its FNR benefit ($-0.419$).
730	Threshold onset contributes almost nothing useful ($+0.084$ combined; FPR $+0.111$, FNR $-0.027$), confirming the near-zero detection power reported in Table~\ref{tab:method_comparison}.
731	Figure~\ref{fig:shapley} visualizes the decomposition.
732	
733	\begin{table}[h]
734	\centering
735	\small
736	\caption{Shapley value decomposition (6-pair, mauve excluded). FPR-Shapley computed from 6 null seeds (36 pairs); FNR-Shapley from 45 signal experiments (270 pairs). Combined = FPR + FNR (more negative = better). $2^5{=}32$ coalitions, exact enumeration.}
737	\label{tab:shapley_6pair}
738	\begin{tabular}{lccc}
739	\toprule
740	Method & $\phi^{\text{FPR}}$ & $\phi^{\text{FNR}}$ & $\phi^{\text{comb}}$ \\
741	\midrule
742	Naive XCorr          & $+0.609$ & $-0.419$ & $+0.190$ \\
743	\textbf{Diff.\ XCorr}& $\mathbf{+0.007}$ & $\mathbf{-0.306}$ & $\mathbf{-0.299}$ \\
744	Threshold ($3\sigma$) & $+0.111$ & $-0.027$ & $+0.084$ \\
745	Perm.\ Granger       & $+0.039$ & $-0.180$ & $-0.141$ \\
746	Toda--Yamamoto       & $+0.150$ & $-0.069$ & $+0.082$ \\
747	\bottomrule
748	\end{tabular}
749	\end{table}
750	
751	\begin{figure*}[h]
752	\centering
753	\includegraphics[width=\linewidth]{figures/shapley_method_contribution.pdf}
754	\caption{Shapley value decomposition of each method's marginal contribution to FPR (positive bars) and FNR (negative bars), computed from 6 null seeds (36 pairs) and 45 signal experiments (270 pairs). DiffXCorr achieves the best combined Shapley ($-0.299$) via near-zero FPR; PermG ranks second ($-0.141$) as the best directional method.}
755	\label{fig:shapley}
756	\end{figure*}
757	
758	The 8-pair variant (including mauve) yields qualitatively identical rankings: DiffXCorr remains the best contributor ($\phi^{\text{comb}}{=}-0.263$), PermG the best directional method ($-0.112$), naive cross-correlation the worst ($+0.157$), and threshold onset near-zero ($+0.073$).
759	
760	\paragraph{FDR correction scope.}
761	This analysis applies BH-corrected significance (\texttt{significant\_fdr}) uniformly across all five methods, including naive cross-correlation and Toda--Yamamoto.
762	In contrast, the per-method dose-response profiles (Table~\ref{tab:dose_response_full}) use uncorrected significance for naive cross-correlation, threshold onset, and Toda--Yamamoto because FDR-corrected fields are not available in the per-experiment pipeline output for these methods.
763	The Shapley analysis recomputes significance from raw $p$-values with BH correction applied post hoc, ensuring a fair comparison across methods within the coalition framework.
764	
765	
766	\section{MMCT Weight Robustness Ablation}
767	\label{app:weight_robustness}
768	
769	The detection results reported in the main text use equal-weight majority voting ($K{\geq}3$ of 5 methods, each contributing at most one vote per pair); PermG contributes at most $1/5 = 20\%$ of the consensus weight.
770	FPR-inverse weighting is used \emph{only} in the exploratory method ranking below, not in the detection results.
771	To verify that PermG's directional-method ranking is not an artifact of the FPR-inverse weighting scheme, we recompute weighted Shapley values under four weight specifications (Table~\ref{tab:weight_robustness}).
772	This analysis uses the 3-seed null control (seeds 42/43/44, 24 pairs), under which PermG had zero FPR; the union-based analysis with 6-seed null (Table~\ref{tab:shapley_6pair}) yields a non-zero PermG FPR Shapley ($+0.039$) and shifts the overall best contributor to DiffXCorr ($-0.299$).
773	Equal weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first among directional methods ($\phi^{\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.
774	Under cap-5, the margin widens to 0.043 as the FPR penalty begins to differentiate high-FPR methods.
775	Cap-10 and original cap-100 yield identical Shapley values because the consensus threshold ($K{\geq}3$) is determined by the three smallest method weights ($w_{\text{naive}}{+}w_{\text{diff}}{+}w_{\text{thresh}} = 7.76$), which are invariant to further increases in the PermG or TY cap; this saturation confirms that the original $w{=}100$ does not artificially inflate PermG's contribution.
776	
777	\begin{table}[h]
778	\centering
779	\small
780	\caption{MMCT weight robustness (3-seed null, 48 experiments): PermG combined Shapley under four weighting schemes. PermG ranks first among directional methods in all cases. Gap = $|\phi^{\text{comb}}_{\text{PermG}} - \phi^{\text{comb}}_{\text{runner-up}}|$. $2^5{=}32$ coalitions, exact enumeration.}
781	\label{tab:weight_robustness}
782	\begin{tabular}{lrcrc}
783	\toprule
784	Scheme & $w_{\text{PermG}}$ & $\phi^{\text{comb}}_{\text{PermG}}$ & Runner-up & Gap \\
785	\midrule
786	Equal ($w{=}1$)     & 1   & $-0.152$ & NaiveXCorr ($-0.137$) & 0.015 \\
787	Cap-5               & 5   & $-0.165$ & NaiveXCorr ($-0.123$) & 0.043 \\
788	Cap-10              & 10  & $-0.426$ & TY ($-0.067$)         & 0.359 \\
789	FPR-inv.\ (cap-100) & 100 & $-0.426$ & TY ($-0.067$)         & 0.359 \\
790	\bottomrule
791	\end{tabular}
792	\end{table}
793	
794	
795	\section{PermG FPR Independence Analysis}
796	\label{app:fpr_independence}
797	
798	Table~\ref{tab:null_fpr_methods} reports null-control FPR for all five detection methods across six seeds ($6 \times 6 = 36$ pairs, 6-pair basis excluding mauve).
799	Under identical BH-FDR correction ($q{=}0.05$), DiffXCorr achieves the lowest FPR (1/36, 2.8\%) but lacks directional separation; PermG (4/36, 11.1\%) is the lowest among directional methods.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "cdfe20f0-73d6-4b9a-8aa6-06b12ded28ed",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/appendix.tex",
      "content": "\nWe quantify each method's marginal contribution to the MMCT ensemble using Shapley values~\\cite{shapley1953value}, computed via exact enumeration over all $2^5{=}32$ coalitions of the five detection methods.\nFor a coalition $S \\subseteq \\{m_1, \\ldots, m_5\\}$, we define two performance metrics: the false positive rate FPR($S$), computed from 6 null experiments ($\\alpha{=}0.0$, seeds 45--50; 36 null pairs on the 6-pair basis excluding mauve), and the false negative rate FNR($S$), computed from 45 signal experiments across all non-null $\\alpha$ levels (270 signal pairs for the 6-pair variant excluding mauve).\nThe Shapley value $\\phi_k$ for method $m_k$ is the weighted average of its marginal contribution across all coalitions; positive FPR-Shapley indicates the method \\emph{increases} false positives, while negative FNR-Shapley indicates it \\emph{reduces} false negatives.\nThe combined Shapley value $\\phi_k^{\\text{comb}} = \\phi_k^{\\text{FPR}} + \\phi_k^{\\text{FNR}}$ balances both error types, with more negative values indicating greater net benefit.\n\nTable~\\ref{tab:shapley_6pair} reports the 6-pair analysis (excluding mauve).\nDiffXCorr achieves the lowest (best) combined Shapley ($-0.299$), driven by near-zero FPR contribution ($+0.007$) and strong FNR reduction ($-0.306$); however, DiffXCorr cannot separate forward from reverse causation (Table~\\ref{tab:null_fpr_methods}).\nAmong directional methods, PermG ranks best ($-0.141$ combined), with a modest FPR contribution ($+0.039$, reflecting 4/36 null false positives) offset by substantial FNR reduction ($-0.180$).\nNaive cross-correlation is the worst contributor ($+0.190$), with its massive FPR Shapley ($+0.609$) overwhelming its FNR benefit ($-0.419$).\nThreshold onset contributes almost nothing useful ($+0.084$ combined; FPR $+0.111$, FNR $-0.027$), confirming the near-zero detection power reported in Table~\\ref{tab:method_comparison}.\nFigure~\\ref{fig:shapley} visualizes the decomposition.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Shapley value decomposition (6-pair, mauve excluded). FPR-Shapley computed from 6 null seeds (36 pairs); FNR-Shapley from 45 signal experiments (270 pairs). Combined = FPR + FNR (more negative = better). $2^5{=}32$ coalitions, exact enumeration.}\n\\label{tab:shapley_6pair}\n\\begin{tabular}{lccc}\n\\toprule\nMethod & $\\phi^{\\text{FPR}}$ & $\\phi^{\\text{FNR}}$ & $\\phi^{\\text{comb}}$ \\\\\n\\midrule\nNaive XCorr          & $+0.609$ & $-0.419$ & $+0.190$ \\\\\n\\textbf{Diff.\\ XCorr}& $\\mathbf{+0.007}$ & $\\mathbf{-0.306}$ & $\\mathbf{-0.299}$ \\\\\nThreshold ($3\\sigma$) & $+0.111$ & $-0.027$ & $+0.084$ \\\\\nPerm.\\ Granger       & $+0.039$ & $-0.180$ & $-0.141$ \\\\\nToda--Yamamoto       & $+0.150$ & $-0.069$ & $+0.082$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[h]\n\\centering\n\\includegraphics[width=\\linewidth]{figures/shapley_method_contribution.pdf}\n\\caption{Shapley value decomposition of each method's marginal contribution to FPR (positive bars) and FNR (negative bars), computed from 6 null seeds (36 pairs) and 45 signal experiments (270 pairs). DiffXCorr achieves the best combined Shapley ($-0.299$) via near-zero FPR; PermG ranks second ($-0.141$) as the best directional method.}\n\\label{fig:shapley}\n\\end{figure*}\n\nThe 8-pair variant (including mauve) yields qualitatively identical rankings: DiffXCorr remains the best contributor ($\\phi^{\\text{comb}}{=}-0.263$), PermG the best directional method ($-0.112$), naive cross-correlation the worst ($+0.157$), and threshold onset near-zero ($+0.073$).\n\n\\paragraph{FDR correction scope.}\nThis analysis applies BH-corrected significance (\\texttt{significant\\_fdr}) uniformly across all five methods, including naive cross-correlation and Toda--Yamamoto.\nIn contrast, the per-method dose-response profiles (Table~\\ref{tab:dose_response_full}) use uncorrected significance for naive cross-correlation, threshold onset, and Toda--Yamamoto because FDR-corrected fields are not available in the per-experiment pipeline output for these methods.\nThe Shapley analysis recomputes significance from raw $p$-values with BH correction applied post hoc, ensuring a fair comparison across methods within the coalition framework.\n\n\n\\section{MMCT Weight Robustness Ablation}\n\\label{app:weight_robustness}\n\nThe detection results reported in the main text use equal-weight majority voting ($K{\\geq}3$ of 5 methods, each contributing at most one vote per pair); PermG contributes at most $1/5 = 20\\%$ of the consensus weight.\nFPR-inverse weighting is used \\emph{only} in the exploratory method ranking below, not in the detection results.\nTo verify that PermG's directional-method ranking is not an artifact of the FPR-inverse weighting scheme, we recompute weighted Shapley values under four weight specifications (Table~\\ref{tab:weight_robustness}).\nThis analysis uses the 3-seed null control (seeds 42/43/44, 24 pairs), under which PermG had zero FPR; the union-based analysis with 6-seed null (Table~\\ref{tab:shapley_6pair}) yields a non-zero PermG FPR Shapley ($+0.039$) and shifts the overall best contributor to DiffXCorr ($-0.299$).\nEqual weighting ($w{=}1$ for all methods) eliminates any FPR-based advantage; PermG still ranks first among directional methods ($\\phi^{\\text{comb}}{=}-0.152$), though its margin over naive cross-correlation narrows to 0.015.\nUnder cap-5, the margin widens to 0.043 as the FPR penalty begins to differentiate high-FPR methods.\nCap-10 and original cap-100 yield identical Shapley values because the consensus threshold ($K{\\geq}3$) is determined by the three smallest method weights ($w_{\\text{naive}}{+}w_{\\text{diff}}{+}w_{\\text{thresh}} = 7.76$), which are invariant to further increases in the PermG or TY cap; this saturation confirms that the original $w{=}100$ does not artificially inflate PermG's contribution.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{MMCT weight robustness (3-seed null, 48 experiments): PermG combined Shapley under four weighting schemes. PermG ranks first among directional methods in all cases. Gap = $|\\phi^{\\text{comb}}_{\\text{PermG}} - \\phi^{\\text{comb}}_{\\text{runner-up}}|$. $2^5{=}32$ coalitions, exact enumeration.}\n\\label{tab:weight_robustness}\n\\begin{tabular}{lrcrc}\n\\toprule\nScheme & $w_{\\text{PermG}}$ & $\\phi^{\\text{comb}}_{\\text{PermG}}$ & Runner-up & Gap \\\\\n\\midrule\nEqual ($w{=}1$)     & 1   & $-0.152$ & NaiveXCorr ($-0.137$) & 0.015 \\\\\nCap-5               & 5   & $-0.165$ & NaiveXCorr ($-0.123$) & 0.043 \\\\\nCap-10              & 10  & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\nFPR-inv.\\ (cap-100) & 100 & $-0.426$ & TY ($-0.067$)         & 0.359 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\n\\section{PermG FPR Independence Analysis}\n\\label{app:fpr_independence}\n\nTable~\\ref{tab:null_fpr_methods} reports null-control FPR for all five detection methods across six seeds ($6 \\times 6 = 36$ pairs, 6-pair basis excluding mauve).\nUnder identical BH-FDR correction ($q{=}0.05$), DiffXCorr achieves the lowest FPR (1/36, 2.8\\%) but lacks directional separation; PermG (4/36, 11.1\\%) is the lowest among directional methods.",
      "numLines": 80,
      "startLine": 720,
      "totalLines": 1268
    }
  }
}
```

</details>

---


### Assistant

_source line 146_

<details><summary>Logged reasoning block</summary>

```text
Everything looks consistent. Let me verify:

1. **FDR sensitivity table** (L126-145): ✓
   - Null: 6 seeds, 36 pairs, counts 3/4/8 at q=0.01/0.05/0.10
   - Treatment: 3 seeds, 24 pairs, counts 0/19/24 (unchanged)
   - TODO removed ✓

2. **Shapley intro** (L721-722): ✓
   - "6 null experiments (α=0.0, seeds 45–50; 36 null pairs on the 6-pair basis)"
   - TODO removed ✓

3. **Shapley body** (L726-731): ✓
   - DiffXCorr best combined (-0.299)
   - PermG best directional (-0.141)
   - Numbers match JSON
   - TODO removed ✓

4. **Shapley table** (L736-748): ✓
   - DiffXCorr bolded as best
   - All values verified: naive +0.609/-0.419/+0.190, diff +0.007/-0.306/-0.299, thresh +0.111/-0.027/+0.084, perm +0.039/-0.180/-0.141

, equity +0.150/-0.069/+0.082
   - Match JSON ✓

5. **Figure caption** (L753-754): ✓
   - "6 null seeds (36 pairs) and 45 signal experiments (270 pairs)"
   - "DiffXCorr achieves the best combined Shapley (−0.299)"
   - TODO removed ✓

6. **Weight robustness** (L771-776): ✓
   - Notes 3-seed null basis
   - Mentions DiffXCorr shift
   - "zero FPR" claim removed
   - TODO removed ✓

7. **Direction filtering** (L828-841): ✓
   - Already uses 6-seed data, no changes needed

Now I'm cross-checking the Shapley values against the JSON source to make sure everything's accurate. Now I'm verifying the Shapley values across both the 6-pair and 8-pair datasets, checking that the combined metrics and individual FPR/FNR breakdowns match consistently across the different methods—naive, DiffXCorr, PermG, and threshold-based approaches all align with the expected values. I'm verifying the appendix text matches the raw data—the PermG false positive count of 4/36 aligns with what's recorded. Everything's consistent, so I'll finalize and register the artifact.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "56a42b62-561d-4387-999c-63df3a32ae08",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013ZeNAYz8PxEaFzqQqvbwvv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3513,
      "cache_read_input_tokens": 119753,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3513
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Assistant

_source line 147_

All edits verified — numbers match the JSON, no TODO-D219 markers remain. Let me register the new artifact and do a final check.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "1d3e794f-d884-472e-a81f-f7adfddfaae1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013ZeNAYz8PxEaFzqQqvbwvv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3513,
      "cache_read_input_tokens": 119753,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3513
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool call

_source line 148_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_015pzQGmUdEw6T2G67hLj3hG`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__register_artifact",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "0d595f18-7f40-40d2-aa3d-42fe5c973a2c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013ZeNAYz8PxEaFzqQqvbwvv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3513,
      "cache_read_input_tokens": 119753,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3513
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool result

_source line 149 · 2026-05-24T09:08:37.922Z_

<details><summary>↩ Tool result · `toolu_015pzQGmUdEw6T2G67hLj3hG`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__register_artifact"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "0ca1800f-f3b6-442b-b612-c62875c13f49",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__register_artifact"
    ],
    "query": "select:mcp__agent-ml-research__register_artifact",
    "total_deferred_tools": 29
  }
}
```

</details>

---


### Tool call

_source line 150_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact · `toolu_019wPsqURp33Fdf1TFJNbZXF`</summary>

```json
{
  "name": "shapley_values_v3",
  "type": "data",
  "description": "Shapley v3: FPR recomputed with 6-seed null (s45-s50, 36 pairs, 6-pair basis). DiffXCorr now best combined (-0.299), PermG second (-0.141). FNR unchanged from v2.",
  "project": "distrib_canary_collapse",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/shapley_v3/shapley_values_v3.json",
  "tags": [
    "shapley",
    "6seed-null",
    "D219"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "90d59254-92c0-45ad-b204-5aa3eb8494f0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DaYYmW58Qf3Fo3PYoaFFoS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2054,
      "cache_read_input_tokens": 123266,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2054
      },
      "output_tokens": 64,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool result

_source line 151 · 2026-05-24T09:08:59.706Z_

<details><summary>↩ Tool result · `toolu_019wPsqURp33Fdf1TFJNbZXF`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260524_eec99d\", \"name\": \"shapley_values_v3\", \"type\": \"data\", \"description\": \"Shapley v3: FPR recomputed with 6-seed null (s45-s50, 36 pairs, 6-pair basis). DiffXCorr now best combined (-0.299), PermG second (-0.141). FNR unchanged from v2.\", \"path\": \"projects/distrib_canary_collapse/artifacts/_project/data/shapley_values_v3.json\", \"url\": null, \"project\": \"distrib_canary_collapse\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-24T09:08:58.784130+00:00\", \"tags\": [\"shapley\", \"6seed-null\", \"D219\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "053f70af-7d87-413a-846b-9ff6bf3918b2",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"artifact\\\": {\\\"id\\\": \\\"art_20260524_eec99d\\\", \\\"name\\\": \\\"shapley_values_v3\\\", \\\"type\\\": \\\"data\\\", \\\"description\\\": \\\"Shapley v3: FPR recomputed with 6-seed null (s45-s50, 36 pairs, 6-pair basis). DiffXCorr now best combined (-0.299), PermG second (-0.141). FNR unchanged from v2.\\\", \\\"path\\\": \\\"projects/distrib_canary_collapse/artifacts/_project/data/shapley_values_v3.json\\\", \\\"url\\\": null, \\\"project\\\": \\\"distrib_canary_collapse\\\", \\\"exp_id\\\": null, \\\"skill\\\": \\\"\\\", \\\"created_at\\\": \\\"2026-05-24T09:08:58.784130+00:00\\\", \\\"tags\\\": [\\\"shapley\\\", \\\"6seed-null\\\", \\\"D219\\\"]}, \\\"manifest\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/manifest.yaml\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260524_eec99d\", \"name\": \"shapley_values_v3\", \"type\": \"data\", \"description\": \"Shapley v3: FPR recomputed with 6-seed null (s45-s50, 36 pairs, 6-pair basis). DiffXCorr now best combined (-0.299), PermG second (-0.141). FNR unchanged from v2.\", \"path\": \"projects/distrib_canary_collapse/artifacts/_project/data/shapley_values_v3.json\", \"url\": null, \"project\": \"distrib_canary_collapse\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-24T09:08:58.784130+00:00\", \"tags\": [\"shapley\", \"6seed-null\", \"D219\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 152_

<details open><summary>🔧 Tool call — TodoWrite · `toolu_01K4X4KsWUkC1aAspJWHoMQW`</summary>

```json
{
  "todos": [
    {
      "content": "Write and run Shapley computation script with 6-seed null data",
      "status": "completed",
      "activeForm": "Writing and running Shapley computation script"
    },
    {
      "content": "Update gen_shapley_contribution.py and regenerate figure",
      "status": "completed",
      "activeForm": "Updating figure generation script"
    },
    {
      "content": "Find treatment PermG data for FDR sensitivity table update",
      "status": "completed",
      "activeForm": "Finding treatment PermG data"
    },
    {
      "content": "Update appendix.tex — all 7 TODO-D219 locations",
      "status": "completed",
      "activeForm": "Updating appendix.tex"
    },
    {
      "content": "Verify all numbers and TODO removals",
      "status": "completed",
      "activeForm": "Verifying consistency"
    }
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "f751c8d6-c563-444a-858a-900420790793",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GpHxhtzyr75amumM85Jicj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 602,
      "cache_read_input_tokens": 125320,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 602
      },
      "output_tokens": 35,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Tool result

_source line 153 · 2026-05-24T09:09:06.255Z_

<details><summary>↩ Tool result · `toolu_01K4X4KsWUkC1aAspJWHoMQW`</summary>

```text
Todos have been modified successfully. Ensure that you continue to use the todo list to track your progress. Please proceed with the current tasks if applicable
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "aa42ddba-9559-4841-a36c-06feaa8e7655",
  "tool_use_result": {
    "oldTodos": [
      {
        "content": "Write and run Shapley computation script with 6-seed null data",
        "status": "completed",
        "activeForm": "Writing and running Shapley computation script"
      },
      {
        "content": "Update gen_shapley_contribution.py and regenerate figure",
        "status": "completed",
        "activeForm": "Updating figure generation script"
      },
      {
        "content": "Find treatment PermG data for FDR sensitivity table update",
        "status": "completed",
        "activeForm": "Finding treatment PermG data"
      },
      {
        "content": "Update appendix.tex — all 7 TODO-D219 locations",
        "status": "completed",
        "activeForm": "Updating appendix.tex"
      },
      {
        "content": "Verify all numbers and TODO removals",
        "status": "in_progress",
        "activeForm": "Verifying consistency"
      }
    ],
    "newTodos": [
      {
        "content": "Write and run Shapley computation script with 6-seed null data",
        "status": "completed",
        "activeForm": "Writing and running Shapley computation script"
      },
      {
        "content": "Update gen_shapley_contribution.py and regenerate figure",
        "status": "completed",
        "activeForm": "Updating figure generation script"
      },
      {
        "content": "Find treatment PermG data for FDR sensitivity table update",
        "status": "completed",
        "activeForm": "Finding treatment PermG data"
      },
      {
        "content": "Update appendix.tex — all 7 TODO-D219 locations",
        "status": "completed",
        "activeForm": "Updating appendix.tex"
      },
      {
        "content": "Verify all numbers and TODO removals",
        "status": "completed",
        "activeForm": "Verifying consistency"
      }
    ],
    "verificationNudgeNeeded": false
  }
}
```

</details>

---


### Assistant

_source line 154_

完成。总结：

**Shapley v3 结果 (6-seed null, 36 pairs)**

| Method | φ^FPR | φ^FNR | φ^comb |
|--------|-------|-------|--------|
| Naive | +0.609 | -0.419 | +0.190 |
| **DiffXCorr** | **+0.007** | **-0.306** | **-0.299** |
| Threshold | +0.111 | -0.027 | +0.084 |
| PermG | +0.039 | -0.180 | -0.141 |
| TY | +0.150 | -0.069 | +0.082 |

**关键变化**: DiffXCorr 取代 PermG 成为 combined Shapley 最优方法（-0.299 vs -0.141），因其 FPR 极低（1/36=2.8%）。PermG 仍是最优 directional method。

**更新清单**:
- `artifacts/shapley_v3/shapley_values_v3.json` — 新 Shapley 数据
- `docs/paper/figures/gen_shapley_contribution.py` — 指向 v3 数据，移除 "zero FPR" 标注
- `docs/paper/figures/shapley_method_contribution.pdf/png` — 重新生成
- `docs/paper/appendix.tex` — 7 处 TODO-D219 全部删除并更新：
  - FDR sensitivity table: null 改为 /36 (3/4/8 at q=0.01/0.05/0.10)
  - Shapley intro: 6 null seeds 45-50, 36 pairs
  - Shapley body: DiffXCorr best overall, PermG best directional
  - Shapley table: 新数值，DiffXCorr 加粗
  - Figure caption: 更新
  - 8-pair robustness: DiffXCorr -0.263, PermG -0.112
  - Weight robustness: 标注使用 3-seed null，注明 6-seed 结果偏移

**FDR sensitivity (null)**:
- q=0.01: 3/36, q=0.05: 4/36, q=0.10: 8/36

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "uuid": "cc152e5a-38e9-4f74-a404-75bb69dca433",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01P3hiZqmdtSMSPbc9UCwrup",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 282,
      "cache_read_input_tokens": 125922,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 282
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---


### Task result

_source line 155_

完成。总结：

**Shapley v3 结果 (6-seed null, 36 pairs)**

| Method | φ^FPR | φ^FNR | φ^comb |
|--------|-------|-------|--------|
| Naive | +0.609 | -0.419 | +0.190 |
| **DiffXCorr** | **+0.007** | **-0.306** | **-0.299** |
| Threshold | +0.111 | -0.027 | +0.084 |
| PermG | +0.039 | -0.180 | -0.141 |
| TY | +0.150 | -0.069 | +0.082 |

**关键变化**: DiffXCorr 取代 PermG 成为 combined Shapley 最优方法（-0.299 vs -0.141），因其 FPR 极低（1/36=2.8%）。PermG 仍是最优 directional method。

**更新清单**:
- `artifacts/shapley_v3/shapley_values_v3.json` — 新 Shapley 数据
- `docs/paper/figures/gen_shapley_contribution.py` — 指向 v3 数据，移除 "zero FPR" 标注
- `docs/paper/figures/shapley_method_contribution.pdf/png` — 重新生成
- `docs/paper/appendix.tex` — 7 处 TODO-D219 全部删除并更新：
  - FDR sensitivity table: null 改为 /36 (3/4/8 at q=0.01/0.05/0.10)
  - Shapley intro: 6 null seeds 45-50, 36 pairs
  - Shapley body: DiffXCorr best overall, PermG best directional
  - Shapley table: 新数值，DiffXCorr 加粗
  - Figure caption: 更新
  - 8-pair robustness: DiffXCorr -0.263, PermG -0.112
  - Weight robustness: 标注使用 3-seed null，注明 6-seed 结果偏移

**FDR sensitivity (null)**:
- q=0.01: 3/36, q=0.05: 4/36, q=0.10: 8/36

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 1097129,
  "duration_api_ms": 1104654,
  "num_turns": 55,
  "stop_reason": "end_turn",
  "session_id": "4aa5547a-5b80-412e-a200-b4e82bc1c8e7",
  "total_cost_usd": 3.939180250000001,
  "usage": {
    "input_tokens": 47,
    "cache_creation_input_tokens": 114363,
    "cache_read_input_tokens": 3771431,
    "output_tokens": 53400,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 114363,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 621,
        "cache_read_input_tokens": 125922,
        "cache_creation_input_tokens": 282,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 282
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-opus-4-6": {
      "inputTokens": 47,
      "outputTokens": 53400,
      "cacheReadInputTokens": 3771431,
      "cacheCreationInputTokens": 114363,
      "webSearchRequests": 0,
      "costUSD": 3.935719250000001,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    },
    "claude-haiku-4-5-20251001": {
      "inputTokens": 3336,
      "outputTokens": 25,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.003461,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "62ce6124-fe99-4c68-ae3b-ee06e0f751b5"
}
```

</details>

---
