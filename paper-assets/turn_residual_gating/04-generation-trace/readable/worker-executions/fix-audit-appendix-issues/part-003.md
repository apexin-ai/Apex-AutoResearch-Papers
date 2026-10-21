# fix audit appendix issues — Part 3 of 3

**Exposure Bias Collapses Auxiliary Attention Losses in Multi-Turn Dialogue** · Worker execution logs

[← Part 2](part-002.md) · [Transcript overview](../fix-audit-appendix-issues.md) · [Structured JSON](../../../sessions/98/98553b1a7a71e14dedc7.json)

## Before a recorded user message

### Tool result

_source line 112 · 2026-05-25T20:40:47.211Z_

<details><summary>↩ Tool result · `toolu_012rE3wman9QAxtDwng6h3Fm`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "5777d1fd-57b9-4212-a1a7-9c25af3a14b8",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex",
    "oldString": "Gap compression & 6.5$\\times$ & 9.3$\\times$",
    "newString": "Gap compression & 6.6$\\times$ & 9.3$\\times$",
    "originalFile": "\\section{Training Configuration}\\label{sec:appendix-hyper}\n\nTable~\\ref{tab:hyperparams} lists the full training configuration shared across all fine-tuned variants. ThreadGate gate parameters receive a $10\\times$ learning rate multiplier and are initialized with bias 1.5 ($\\sigma(1.5) \\approx 0.82$); the gate MLP adds ${\\sim}$57K parameters per variant ($<$0.001\\% of 7B). The scheduled sampling variant (v8b) linearly increases the model-generated context ratio from 0 to 0.3 over 3 epochs (29.7--37.1\\% effective usage due to per-sample Bernoulli sampling). All experiments were conducted on a single NVIDIA RTX PRO 6000 Blackwell Server Edition GPU (96\\,GB VRAM), requiring 6--8 hours per variant.\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Training hyperparameters for all fine-tuned variants. Entries marked $\\dagger$ apply only to ThreadGate and its ablations.}\n\\label{tab:hyperparams}\n\\begin{tabular}{l@{\\hspace{8pt}}l}\n\\toprule\n\\textbf{Parameter} & \\textbf{Value} \\\\\n\\midrule\nBase model & Qwen-2.5-7B-Instruct \\\\\nLoRA rank / $\\alpha$ & 16 / 32 \\\\\nLoRA targets & \\texttt{q\\_proj}, \\texttt{v\\_proj} \\\\\nOptimizer & AdamW ($\\beta_1$\\!=\\!0.9, $\\beta_2$\\!=\\!0.999) \\\\\nLearning rate & $2 \\times 10^{-4}$ \\\\\nGate LR mult.$^\\dagger$ & $10\\times$ \\\\\nBatch / grad accum & 1 / 8 (eff.\\ 8) \\\\\nEpochs & 3 \\\\\nMax seq length & 2048 \\\\\nTraining data & 8K UltraChat convs \\\\\nSeed & 42 (+123 for TG, SS) \\\\\n$\\lambda_\\text{GAR}$/$\\lambda_\\text{div}$ & 1.0 / 1.0 \\\\\nGAR target $\\tau$ & 0.5 \\\\\nGate init bias$^\\dagger$ & 1.5 ($\\sigma\\!\\approx\\!0.82$) \\\\\nGate hidden dim$^\\dagger$ & 64 \\\\\nTurn embed dim$^\\dagger$ & 16 \\\\\nGPU & RTX PRO 6000 (96\\,GB) \\\\\nTraining time & 6--8 h / variant \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Loss Formulation Search}\\label{sec:appendix-loss}\n\nThe final MSE + gate diversity loss (\\S\\ref{sec:loss}) emerged from seven iterations spanning four loss families. Table~\\ref{tab:loss-iterations} summarizes the progression. The search was motivated by a consistent failure mode: naive formulations either collapse to trivial solutions (cumulative losses) or drive gates toward identity (maximize-family losses). We describe each family below.\n\n\\paragraph{Cumulative losses (v1--v2).} These losses accumulate GAR contributions across layers, rewarding monotonically increasing attention. v1 collapsed because once the cumulative GAR exceeded the threshold, the loss gradient vanished and gates froze. v2 added an $\\varepsilon$-stabilization term to the cumulative product, but numerical instability from the product of 28 per-layer terms dominated, and training followed the same trajectory.\n\n\\paragraph{Maximize losses (v3--v5).} These losses directly maximize mean GAR ($-\\text{mean}(\\text{GAR})$). The unbounded objective rewards full pass-through ($g \\to 1.0$), collapsing gate diversity (std $<$ 0.025). At $\\lambda$=2 (v3), gates froze within 100 steps; at $\\lambda$=10 (v3b), convergence to identity accelerated; at $\\lambda$=1 (v5), rebalancing delayed but did not prevent the same degenerate solution.\n\n\\paragraph{Smooth saturation (v6).} This bounded the reward using a saturating function, intended to prevent the unbounded growth of maximize losses. In practice, the loss landscape remained monotonic in $g$, and training followed the same terminal trajectory as the maximize family, only more slowly.\n\n\\paragraph{MSE + gate diversity (v7).} The MSE formulation provides bidirectional pressure: GAR above $\\tau$ incurs the same penalty as GAR below $\\tau$, preventing the runaway optimization of maximize losses. The gate diversity regularizer ($\\mathcal{L}_\\text{div}$) enforces a minimum standard deviation across per-layer gate values, preventing all gates from collapsing to a uniform value. This combination is the only one that achieved stable convergence (GAR-ours = 0.50, PPL = 2.78).\n\n\\begin{table*}[t]\n\\centering\\footnotesize\n\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration (v7).}\n\\label{tab:loss-iterations}\n\\begin{tabular}{l l l p{5.8cm} c c}\n\\toprule\n & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{Failure Mechanism} & \\textbf{GAR} & \\textbf{PPL} \\\\\n\\midrule\nv1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & GAR loss collapses to zero once threshold is reached; gate gradients vanish at equilibrium & ---  & ---  \\\\\nv2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & Numerical instability from cumulative product; $\\varepsilon$-stabilization insufficient & ---  & ---  \\\\\nv3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & Unbounded reward drives gates toward identity (all-pass); no layer selectivity & ---  & ---  \\\\\nv3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & Higher $\\lambda$ accelerates convergence to same degenerate identity solution & ---  & ---  \\\\\nv5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & Rebalancing delays but does not prevent identity collapse & ---  & ---  \\\\\nv6  & Smooth saturation       & \\texttimes~identity collapse   & Monotonic reward identical to maximize in practice; boundedness slows but does not alter terminal trajectory & ---  & ---  \\\\\nv7  & MSE + gate div          & \\checkmark~\\textbf{converged}  & \\textbf{Bidirectional penalty prevents identity collapse; gate diversity regularizer enforces layer selectivity} & 0.50 & 2.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\section{Instruction Retention Details}\\label{sec:appendix-ir}\n\nTo evaluate whether GAR improvements translate to downstream task performance, we test instruction retention across 18 system-prompt constraint types using the ThreadGate checkpoint with $\\beta$\\,=\\,3 steering on $N$\\,=\\,200 held-out conversations. Each constraint type requires the model to follow a specific instruction embedded in the system prompt (e.g., ``always respond in bullet points'', ``never use the word X'', ``include a summary at the end''). This evaluation bridges the gap between our attention-level metric (GAR) and observable model behavior.\n\n\\paragraph{Evaluation protocol.} For each conversation, we inject a constraint into the system prompt and evaluate compliance across all assistant turns. A turn is compliant if it satisfies the constraint according to rule-based checkers (for format, count, and position constraints) or GPT-4-based evaluation (for content constraints, which require semantic judgment). We use the same 18 constraint types across all conversations, yielding $N$\\,=\\,54 paired evaluations (18 types $\\times$ 3 conversations per type) for the McNemar analysis.\n\n\\paragraph{Per-category results.} Table~\\ref{tab:ir-results} reports per-category compliance rates. Content constraints---which require attending to and recalling specific system-prompt instructions across turns---show the largest improvement (+23.8\\,pp), consistent with GAR measuring attention to goal tokens. This category includes constraints like ``mention X in every response'' and ``always reference the original topic,'' which require sustained attention to the system prompt. Position constraints (e.g., ``start each response with Y'') show a modest improvement (+6.7\\,pp), as they partially depend on goal-token attention. Format (e.g., ``use bullet points'') and count constraints (e.g., ``exactly 3 sentences'') show no change, consistent with these being procedural patterns that are cached in the model's generation routine rather than requiring ongoing attention to the system prompt.\n\n\\paragraph{Correlation analysis.} The GAR-compliance correlation ($r$\\,=\\,0.200, $p$\\,=\\,0.007) is statistically significant but modest, suggesting that attention to goal tokens is one of several factors in instruction compliance. Other factors likely include the model's procedural memory for format constraints, the specificity of the constraint (vague constraints are harder regardless of attention), and the interaction between constraint type and conversation topic. McNemar's test ($p$\\,=\\,0.077) is marginally significant for the overall compliance improvement, reflecting the small sample size (18 constraint types). These results are exploratory and pending multi-model confirmation.\n\nFigure~\\ref{fig:ir-bar} visualizes the per-category breakdown.\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_instruction_retention.pdf}\n  \\caption{Instruction retention by constraint category under $\\beta$\\,=\\,3 steering. Content constraints benefit most (+23.8\\,pp); format and count constraints are unaffected.}\n  \\label{fig:ir-bar}\n\\end{figure}\n\n\\FloatBarrier\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Instruction retention by constraint category ($\\beta$\\,=\\,3 steering on ThreadGate checkpoint). Content constraints benefit most from increased goal attention.}\n\\label{tab:ir-results}\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Category} & $\\beta$\\,=\\,0 & $\\beta$\\,=\\,3 & $\\Delta$ \\\\\n\\midrule\nContent    & 61.9\\% & 85.7\\% & +23.8\\,pp \\\\\nPosition   & 66.7\\% & 73.3\\% & +6.7\\,pp \\\\\nCount      & 100\\%  & 100\\%  & 0 \\\\\nFormat     & 100\\%  & 100\\%  & 0 \\\\\n\\midrule\n\\textbf{Overall} & 75.9\\% & 87.0\\% & +11.1\\,pp \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Long-Conversation AR Evaluation}\\label{sec:appendix-n5}\n\nThe main results (Table~\\ref{tab:five-way}) report AR GAR from $N$\\,=\\,50 held-out conversations with a mean of 3.6 user turns. Table~\\ref{tab:n5-ar} presents complementary results on $N$\\,=\\,5 conversations with 10 turns each, testing whether the observed patterns generalize beyond the training distribution's conversation length.\n\n\\paragraph{Gating advantage vanishes at length.} In these longer dialogues, the gating advantage observed in shorter conversations vanishes: all fine-tuned variants collapse to AR GAR-ours of 0.015--0.025, compared to 0.030--0.064 in the shorter evaluation. ThreadGate's advantage over LoRA-only shrinks from 1.7$\\times$ (0.064 vs.\\ 0.037 in the $N$\\,=\\,50 evaluation) to 0.64$\\times$ (0.016 vs.\\ 0.025), actually reversing the ordering. This reversal is not statistically robust given the small sample ($N$\\,=\\,5) but directionally suggests that architectural modifications provide diminishing returns as conversation length increases and exposure bias accumulates.\n\n\\paragraph{Convergence to base.} By turn~10, all fine-tuned variants converge to within 2$\\times$ of the base model's GAR, compared to 3.4$\\times$ at turn~1 in the shorter evaluation. This convergence is consistent with exposure bias compounding multiplicatively over turns: each model-generated turn introduces additional distributional drift from the teacher-forced training regime, and by turn~10 the accumulated drift overwhelms any gating or LoRA signal, leaving only the base model's intrinsic attention patterns.\n\n\\paragraph{Caveats.} The $N$\\,=\\,5 sample size limits statistical power, and the 10-turn conversations may differ systematically from the 3--5 turn training distribution in ways beyond length (e.g., topic complexity, user engagement patterns). We present these results as directional evidence rather than definitive conclusions.\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{AR GAR-ours on $N$\\,=\\,5 ten-turn conversations. The gating advantage observed in Table~\\ref{tab:five-way} ($N$\\,=\\,50, mean 3.6 turns) diminishes with conversation length.}\n\\label{tab:n5-ar}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Configuration} & \\textbf{AR GAR-O} & \\textbf{$\\Delta$ vs.\\ Table~\\ref{tab:five-way}} \\\\\n\\midrule\nBase & 0.012 & $-$0.007 \\\\\n\\midrule\nThreadGate & 0.016 & $-$0.048 \\\\\n\\;+\\,PCGrad & 0.015 & $-$0.015 \\\\\nUniform Gate & 0.015 & $-$0.018 \\\\\nLoRA-only & 0.025 & $-$0.012 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Statistical Test Details}\\label{sec:appendix-stats}\n\nAll statistical tests reported in the main text use non-parametric methods due to the non-normal, heavy-tailed distribution of per-conversation GAR values. Table~\\ref{tab:stat-tests} consolidates the full results.\n\n\\paragraph{Wilcoxon signed-rank tests.} We use paired Wilcoxon signed-rank tests for all pairwise configuration comparisons under AR evaluation, treating each conversation as a paired observation. The TG vs.\\ LoRA-only comparison ($p$\\,=\\,0.004, $r$\\,=\\,0.454) confirms that turn-conditioned gating provides a statistically significant but modest improvement. The TG vs.\\ +PCGrad comparison ($p$\\,=\\,0.002) shows that resolving gradient conflict is actively harmful. Gate turn conditioning uses an unpaired Wilcoxon test across 28 layers.\n\n\\paragraph{Bootstrap confidence intervals.} The 95\\% CIs in Table~\\ref{tab:five-way} are computed via 10,000 bootstrap resamples of per-conversation mid-turn GAR averages (turns 2--$T$), using the percentile method.\n\n\\paragraph{Effect sizes.} We report rank-biserial correlation $r = Z / \\sqrt{N}$ as the effect size for Wilcoxon tests, where $Z$ is the standardized test statistic and $N$ is the number of observations. By standard conventions: $r < 0.3$ is small, $0.3 \\leq r < 0.5$ is medium, and $r \\geq 0.5$ is large. The TG vs.\\ LoRA-only effect ($r$\\,=\\,0.454) is medium, and TG vs.\\ Base ($r$\\,=\\,0.802) is large.\n\n\\paragraph{Multiple comparisons.} We report uncorrected $p$-values throughout, as our comparisons are hypothesis-driven (each tests a specific causal exclusion) rather than exploratory. Applying Bonferroni correction to the 4 primary AR comparisons would adjust the significance threshold to 0.0125; all reported significant results ($p \\leq 0.004$) survive this correction.\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Consolidated statistical tests. All AR comparisons use $N$\\,=\\,50 conversations (39 with $\\geq$3 turns); gate conditioning uses 28 layers.}\n\\label{tab:stat-tests}\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Comparison} & \\textbf{Test} & $p$ & $r$ \\\\\n\\midrule\n\\multicolumn{4}{l}{\\emph{AR GAR-ours ($\\beta$\\,=\\,0)}} \\\\\nTG vs.\\ Base & Wilcoxon & $<$0.001 & 0.802 \\\\\nTG vs.\\ LoRA-only & Wilcoxon & 0.004 & 0.454 \\\\\nTG vs.\\ +PCGrad & Wilcoxon & 0.002 & --- \\\\\nSS vs.\\ TG & Wilcoxon & $<$0.001 & 0.869 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\emph{Gate conditioning (28 layers)}} \\\\\nTurn 1 vs.\\ Turn 21 & Wilcoxon & $3.7\\!\\times\\!10^{-8}$ & 0.975 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\emph{Instruction retention}} \\\\\n$\\beta$\\,=\\,0 vs.\\ $\\beta$\\,=\\,3 & McNemar & 0.077 & --- \\\\\nGAR--compliance & Pearson & 0.007 & 0.200 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Llama-3.1-8B Complete Results}\\label{sec:appendix-llama}\n\nTable~\\ref{tab:llama-full} presents the complete Llama-3.1-8B-Instruct results, complementing the summary in \\S\\ref{subsec:cross-model}. Three configurations were trained (Base, ThreadGate, LoRA-only) using the same training pipeline as Qwen-2.5-7B (8K UltraChat, 3 epochs, LoRA rank 16). Training required 7.0--7.3 hours per variant on the same GPU.\n\n\\paragraph{Teacher-forced evaluation.} TF GAR-ours is 0.484 (TG) and 0.481 (LoRA-only), confirming that gating provides zero benefit under teacher forcing on Llama, consistent with the Qwen results (0.50 vs.\\ 0.50).\n\n\\paragraph{Autoregressive evaluation.} AR evaluation uses $N$\\,=\\,20 mid-turn conversations (turns 3--$T$, excluding the first two turns to avoid initialization effects). The AR GAR distribution is heavy-tailed: the coefficient of variation exceeds 100\\% for ThreadGate (mean 0.043, std 0.100), and 5\\% of turn-level measurements exhibit sporadic attention spikes (GAR $\\geq$ 0.4). We therefore report both mean and median.\n\n\\paragraph{Gate profile.} Llama's gate profile differs qualitatively from Qwen's: Qwen shows minimum attenuation at early layers (L1\\,=\\,0.793, L5\\,=\\,0.797), while Llama shows a V-shaped valley at mid-to-late layers (L25\\,=\\,0.719, L24\\,=\\,0.809). Despite this architectural difference, both models converge toward identity under NTP pressure, and the TF-AR gap is comparable (27$\\times$ by median for Llama vs.\\ 8--17$\\times$ for Qwen).\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Llama-3.1-8B-Instruct complete results. TF: teacher-forced ($N$\\,=\\,50); AR: autoregressive ($N$\\,=\\,20 for Base/TG/LoRA-only, $N$\\,=\\,50 for SS). Median is more representative due to heavy-tailed AR distributions (SS uses mean only).}\n\\label{tab:llama-full}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n& \\multicolumn{2}{c}{\\textbf{TF}} & \\multicolumn{2}{c}{\\textbf{AR}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\n& GAR-O & PPL & GAR-O (mean) & GAR-O (med) \\\\\n\\midrule\nBase & 0.017 & 3.45 & 0.009 & 0.009 \\\\\nThreadGate & 0.484 & 2.57 & 0.043 & 0.018 \\\\\nLoRA-only & 0.481 & 2.60 & 0.028 & 0.018 \\\\\n\\textbf{SS} & 0.477 & 2.82 & \\textbf{0.166} & --- \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\FloatBarrier\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_crossmodel.pdf}\n  \\caption{Cross-architecture validation. (a)~The TF-AR gap persists on Llama-3.1-8B (27$\\times$ by median), exceeding Qwen's 8$\\times$. (b)~Gate profiles on normalized depth: Qwen dips at early layers, Llama at late layers; architecture-dependent patterns, but both converge toward identity.}\n  \\label{fig:crossmodel}\n\\end{figure}\n\n\\paragraph{Cross-model summary.} Table~\\ref{tab:crossmodel-detail} consolidates the cross-model comparison, showing TF GAR, AR GAR, PPL, and gap ratios side by side for both architectures. The consistent pattern---TF GAR $\\approx$ 0.5, AR GAR $\\ll$ 0.1, gap $\\geq$ 7.9$\\times$---across two architectures with different layer counts, attention head configurations, and pre-training corpora provides strong evidence that exposure bias is architecture-independent. Notably, Llama's larger gaps (27$\\times$ by median for TG; mean-based range 11.2--17.2$\\times$) compared to Qwen's (7.9--13.5$\\times$) may reflect its deeper architecture (32 vs.\\ 28 layers), which allows more layers for distributional drift to compound through.\n\n\\input{../artifacts/appendix_expansion/tab_crossmodel_detail.tex}\n\n\\paragraph{GAR-Dongre cross-model comparison.} GAR-Dongre shows negligible distribution shift on Llama (AR/TF ratio 1.002$\\times$), compared to 1.28$\\times$ on Qwen. This confirms the mechanism specificity finding: exposure bias selectively disrupts the concentrated last-token attention pattern (GAR-ours) while leaving the diffuse all-token attention (GAR-Dongre) unaffected across both architectures.\n\n\\paragraph{Training details.} Llama variants used the same pipeline as Qwen: 8K UltraChat conversations, LoRA rank 16 targeting $q$/$v$ projections, 3 epochs. Training loss converged to 0.929 (LoRA-only) and 0.934 (ThreadGate); the slight difference is attributable to the additional GAR loss component. Wall-clock time was 7.0h (LoRA-only) and 7.3h (ThreadGate), approximately 17\\% longer than Qwen due to Llama's larger layer count (32 vs.\\ 28 layers).\n\n\\paragraph{Phase 1 diagnostics.} Before fine-tuning, we confirmed that Llama exhibits the same goal attention decay as Qwen. Base model GAR decays from 0.026 (turn 1) to 0.003 (turn 10), a 90\\% decline. This is steeper than Qwen's 70.8\\% decline, suggesting that attention decay may be more severe in Llama's architecture despite its larger head count (32 vs.\\ 28 KV heads).\n\n\\paragraph{Cross-model gradient analysis.} Table~\\ref{tab:gradient-crossmodel} compares NTP--GAR gradient interaction between the two architectures. Both models exhibit near-orthogonal gradients (cosine similarity $\\approx$\\,0), not systematic conflict: Qwen shows a slight negative mean ($-$0.042) while Llama is marginally positive (+0.005). NTP gradients dominate GAR by 14.7$\\times$ on Qwen and 25.7$\\times$ on Llama, indicating that the auxiliary signal is overwhelmed by magnitude rather than opposed by direction. The cross-model consistency---near-zero cosine similarity and order-of-magnitude NTP dominance on both architectures---reinforces the \\emph{modus tollens} argument (\\S\\ref{subsec:pcgrad}): gradient direction conflict is not the primary cause of the TF-AR gap.\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Cross-model NTP--GAR gradient interaction. Gradients are near-orthogonal on both architectures; NTP magnitude dominates GAR by 15--26$\\times$.}\n\\label{tab:gradient-crossmodel}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Metric} & \\textbf{Qwen-7B} & \\textbf{Llama-8B} \\\\\n\\midrule\nMean cos sim & $-$0.042 & +0.005 \\\\\nNeg-layer \\% & 67.9\\% & 53.1\\% \\\\\nNTP/GAR mag ratio & 14.7$\\times$ & 25.7$\\times$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Additional Visualizations}\\label{sec:appendix-viz}\n\nThis section presents extended visualizations referenced in the main text. Each figure examines a different aspect of the gating behavior and its failure under autoregressive generation.\n\n\\subsection{Gate Profile Heatmap}\n\nFigure~\\ref{fig:gate-heatmap} shows the per-layer gate values across all training configurations for both Qwen-2.5-7B (28 layers) and Llama-3.1-8B (32 layers). The key observation is that early layers consistently receive the lowest gate values across all conditions, suggesting that these layers contribute more dispensable computations for the NTP objective. The pattern is remarkably consistent across ThreadGate, Uniform Gate, and PCGrad variants, indicating that gate-value allocation is driven primarily by the NTP loss landscape rather than the GAR auxiliary objective.\n\n\\begin{figure}[H]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_gate_profile_heatmap.pdf}\n\\caption{Per-layer gate values across training for Qwen-2.5-7B (28 layers $\\times$ 5 conditions) and Llama-3.1-8B (32 layers $\\times$ 1 condition). Early layers (L1, L4--5) consistently receive the lowest gate values across conditions.}\n\\label{fig:gate-heatmap}\n\\end{figure}\n\n\\subsection{Cross-Model Gate Profile Comparison}\n\nFigure~\\ref{fig:gate-crossmodel} compares gate profiles between the two architectures. Qwen-2.5-7B shows minimum gate values at early layers (L1\\,=\\,0.793, L5\\,=\\,0.797), suggesting these layers are most amenable to attenuation without disrupting NTP. Llama-3.1-8B instead shows a V-shaped valley at mid-to-late layers (L25\\,=\\,0.719), indicating that architecturally distinct models learn different layer-importance hierarchies. Both profiles converge toward identity at their respective final layers, consistent with NTP gradient pressure dominating gate optimization at output-adjacent layers.\n\n\\begin{figure}[H]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_gate_profile_crossmodel.pdf}\n\\caption{Side-by-side gate profiles for Qwen-2.5-7B and Llama-3.1-8B. Qwen dips at early layers (L1\\,=\\,0.793, L5\\,=\\,0.797), while Llama shows a V-shaped valley at mid-to-late layers (L25\\,=\\,0.719). Both models learn layer-selective gating but with architecture-dependent patterns.}\n\\label{fig:gate-crossmodel}\n\\end{figure}\n\n\\subsection{Per-Turn AR GAR Decay}\n\nFigure~\\ref{fig:ar-gar-perturn} visualizes the monotonic decay of GAR across conversation turns under autoregressive generation. Qwen base drops 85\\% from turn 1 to turn 10; Llama base drops 90\\%. The ThreadGate-trained model shows slight elevation in absolute GAR values but follows the same decay pattern, confirming that training-time GAR optimization does not alter the fundamental decay dynamic during generation. This per-turn view complements the aggregate TF-AR gap reported in Table~\\ref{tab:five-way}: the gap is not a fixed offset but grows with conversation length, consistent with cumulative exposure bias.\n\n\\begin{figure}[H]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_ar_gar_perturn.pdf}\n\\caption{GAR decays monotonically across turns under autoregressive generation. Qwen base drops 85\\% (turn 1$\\to$10), Llama base drops 90\\%. The ThreadGate-trained model (AR) shows slight elevation but the same decay pattern, confirming that training-time GAR optimization does not transfer to generation.}\n\\label{fig:ar-gar-perturn}\n\\end{figure}\n\n\\subsection{Bootstrap Confidence Intervals}\n\nFigure~\\ref{fig:bootstrap-ci} shows the bootstrap resampling distributions underlying the 95\\% CIs reported in Table~\\ref{tab:five-way}.\n\n\\begin{figure}[H]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_bootstrap_ci.pdf}\n  \\caption{Bootstrap CI distributions for AR GAR-ours (ThreadGate vs.\\ LoRA-only, $N$\\,=\\,50, 10K resamples). Distributions overlap substantially, consistent with the modest effect size ($r$\\,=\\,0.454).}\n  \\label{fig:bootstrap-ci}\n\\end{figure}\n\n\\subsection{Gate Value Distributions}\n\nFigure~\\ref{fig:gate-distribution} shows the full distribution of per-layer gate values for ThreadGate, Uniform Gate, and PCGrad variants. All three converge to similar distributions (mean $\\sim$0.94--0.96, concentrated between 0.9 and 1.0), confirming that the gating mechanism provides minimal modulation regardless of the specific variant. The distributions are right-skewed with a sharp cutoff at 1.0, reflecting NTP pressure pushing gates toward identity.\n\n\\begin{figure}[H]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_gate_distribution.pdf}\n\\caption{Per-layer gate value distributions for ThreadGate, Uniform Gate, and PCGrad variants. All three converge to similar distributions (mean $\\sim$0.94--0.96), confirming minimal modulation from the gating mechanism.}\n\\label{fig:gate-distribution}\n\\end{figure}\n\n\\subsection{Training Loss Curves}\n\nFigure~\\ref{fig:training-loss} shows the NTP, GAR, and total loss trajectories during training. GAR loss collapses to near-zero within the first epoch across all variants, indicating rapid convergence of the auxiliary objective under teacher forcing. NTP loss converges normally to ${\\sim}$0.93 by epoch 3. The fast GAR convergence is not itself pathological---it indicates successful optimization under the training distribution. The pathology emerges only at the transition to autoregressive generation, where the learned attention patterns fail to transfer.\n\n\\begin{figure}[H]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_training_loss_curves.pdf}\n\\caption{NTP, GAR, and total loss trajectories. GAR loss collapses to near-zero within the first epoch across all variants, while NTP loss converges normally.}\n\\label{fig:training-loss}\n\\end{figure}\n\n\\subsection{Full Attention Steering Results}\\label{sec:appendix-steering}\n\n\\begin{table*}[t]\n\\centering\\small\n\\caption{Full attention steering results across evaluation settings.\n\\textbf{Bold} indicates the operating point cited in the main text ($\\beta$\\,=\\,5).\nA visual gap separates the phase-transition boundary: GAR jumps sharply between $\\beta$\\,=\\,2 and $\\beta$\\,=\\,3 across all settings.}\n\\label{tab:steering-full}\n\\begin{tabular}{r cc cc cc}\n\\toprule\n & \\multicolumn{2}{c}{\\textbf{$N$\\,=\\,5, Gen}} & \\multicolumn{2}{c}{\\textbf{$N$\\,=\\,50, Gen}} & \\multicolumn{2}{c}{\\textbf{$N$\\,=\\,200, TF}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5} \\cmidrule(lr){6-7}\n$\\beta$ & GAR & PPL & GAR & PPL & GAR & PPL \\\\\n\\midrule\n0   & .028 & 1.41 & $.064 \\pm .081$ & $1.43 \\pm .10$ & .535 & 2.62 \\\\\n0.5 & .029 & 1.39 & ---             & ---             & ---  & ---  \\\\\n1   & .035 & 1.36 & ---             & ---             & ---  & ---  \\\\\n2   & .062 & 1.41 & $.128 \\pm .110$ & $1.48 \\pm .14$ & .611 & 2.69 \\\\\n\\addlinespace[3pt]\n3   & ---  & ---  & $.556 \\pm .060$ & $1.56 \\pm .17$ & .788 & 2.93 \\\\\n4   & ---  & ---  & $.644 \\pm .061$ & $1.67 \\pm .22$ & .817 & 3.49 \\\\\n\\textbf{5}  & \\textbf{.680} & \\textbf{1.91} & $\\mathbf{.727 \\pm .061}$ & $\\mathbf{1.77 \\pm .27}$ & \\textbf{.833} & \\textbf{6.15} \\\\\n10  & .959 & 4.22 & $.961 \\pm .015$ & $3.45 \\pm 1.78$ & .977 & 505.2 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_steering_standalone.pdf}\n  \\caption{Detailed $\\beta$-steering trade-off ($N$\\,=\\,50). GAR-ours (top) increases monotonically with $\\beta$; PPL (bottom) remains stable below $\\beta$\\,=\\,3 (9\\% cost), then rises sharply. The $\\beta$\\,=\\,3 operating point (circled) achieves 8.7$\\times$ GAR recovery while crossing the TF baseline, representing the optimal trade-off.}\n  \\label{fig:steering-standalone}\n\\end{figure}\n\n\\section{Per-Layer Gate Profile}\\label{sec:appendix-gate-profile}\n\nTable~\\ref{tab:gate-profile} reports the final per-layer gate values for ThreadGate (seed 123) on Qwen-2.5-7B-Instruct (28 layers). Gate values are averaged across all tokens in the evaluation set. Layers 1 and 5 show the lowest gate values (0.793 and 0.797), indicating these layers are most amenable to attenuation without disrupting NTP. Layers 26--27 converge to $\\geq$0.988, consistent with NTP gradient pressure dominating at output-adjacent layers. The mean across all layers is 0.947 ($\\sigma$\\,=\\,0.051).\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Per-layer gate values for ThreadGate (seed 123) on Qwen-2.5-7B-Instruct. Min values (L1, L5) in bold.}\n\\label{tab:gate-profile}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{cccccccc}\n\\toprule\nL0 & L1 & L2 & L3 & L4 & L5 & L6 & L7 \\\\\n.883 & \\textbf{.793} & .996 & .988 & .984 & \\textbf{.797} & .961 & .918 \\\\\n\\midrule\nL8 & L9 & L10 & L11 & L12 & L13 & L14 & L15 \\\\\n.965 & .934 & .969 & .918 & .926 & .941 & .930 & .965 \\\\\n\\midrule\nL16 & L17 & L18 & L19 & L20 & L21 & L22 & L23 \\\\\n.941 & .910 & .961 & .965 & .973 & .988 & .969 & .980 \\\\\n\\midrule\nL24 & L25 & L26 & L27 & \\multicolumn{4}{c}{Summary} \\\\\n.980 & .984 & .988 & 1.00 & \\multicolumn{4}{c}{$\\bar{g}$\\,=\\,.947, $\\sigma$\\,=\\,.051} \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nThe gate profile exhibits two notable patterns: (1)~a bimodal dip at L1 and L5, suggesting two distinct ``dispensable'' layer clusters in Qwen's architecture; (2)~monotonic increase from L17 to L27, indicating output-adjacent layers are progressively more critical for NTP. Seed 42 produces a similar profile (mean 0.934, min at L3--L5), confirming the pattern is not seed-dependent.\n\n\\paragraph{Cross-model comparison.} See \\S\\ref{sec:appendix-viz} for the full cross-model gate profile comparison (Figure~\\ref{fig:gate-crossmodel}). Llama-3.1-8B shows a qualitatively different profile---a V-shaped valley at mid-to-late layers rather than early-layer dips---suggesting architecture-dependent layer importance hierarchies.\n\n\\section{Scheduled Sampling Implementation}\\label{sec:appendix-ss}\n\nOur scheduled sampling implementation follows \\citet{bengio2015scheduled} with modifications for multi-turn transformer training:\n\n\\paragraph{Sampling schedule.} The model-generated context ratio $\\rho$ increases linearly from 0 to 0.3 over 3 epochs. At each training step, a Bernoulli trial with probability $\\rho$ determines whether the input prefix is replaced with model-generated tokens. The effective usage rate (29.7--37.1\\%) is lower than the nominal schedule due to per-sample Bernoulli variance.\n\n\\paragraph{Context generation.} When model-generated context is selected, the model autoregressively generates the assistant turns from the conversation prefix up to the current training position. The generated tokens replace the ground-truth assistant tokens in the input, while user turns remain unchanged. This preserves the multi-turn structure while introducing distributional diversity in the conditioning context.\n\n\\paragraph{Training dynamics.} The scheduled sampling variant converges to similar final loss (NTP 0.932 vs.\\ 0.930 for standard ThreadGate) but with higher variance in early epochs due to the stochastic context mixing (Figure~\\ref{fig:ss-dynamics}). Gate profiles remain similar (mean 0.953 vs.\\ 0.947, min at L4 vs.\\ L1), indicating that scheduled sampling does not fundamentally alter gate optimization but rather improves the robustness of the learned attention patterns to distributional shift. Training time increases by 8--80\\% across seeds (seed-dependent; dominated by GAR forward pass overhead): 6.5h (seed 42), 10.8h (seed 123), and 6.5h (seed 456) vs.\\ 6.0h for standard ThreadGate on Qwen. Seed 456 exhibits consistent training dynamics with seeds 42 and 123.\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_ss_training_dynamics.pdf}\n  \\caption{Scheduled sampling training dynamics: sampling ratio $\\rho$ ramps linearly from 0 to 0.3 (left axis); GAR loss (right axis) shows higher early-epoch variance due to stochastic context mixing.}\n  \\label{fig:ss-dynamics}\n\\end{figure}\n\n\\section{Computational Cost Analysis}\\label{sec:appendix-cost}\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Computational cost across training configurations. All experiments use a single NVIDIA RTX PRO 6000 (96\\,GB VRAM). VRAM reports peak allocated memory (excluding optimizer states).}\n\\label{tab:cost}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Config} & \\textbf{Params} & \\textbf{Time (h)} & \\textbf{VRAM} & \\textbf{Overhead} \\\\\n\\midrule\n\\multicolumn{5}{l}{\\emph{Qwen-2.5-7B-Instruct}} \\\\\nLoRA-only & 4.2M & 5.7 & 42\\,GB & baseline \\\\\nThreadGate & 4.3M & 6.0 & 43\\,GB & $+$57K \\\\\n\\;+\\,PCGrad & 4.3M & 8.0 & 43\\,GB & $+$33\\% \\\\\nUniform Gate & 4.3M & 6.0 & 43\\,GB & $+$57K \\\\\nSS (s42) & 4.3M & 6.5 & 43\\,GB & $+$8\\% \\\\\nSS (s123) & 4.3M & 10.8 & 43\\,GB & $+$80\\% \\\\\nSS (s456) & 4.3M & 6.5 & 43\\,GB & $+$8\\% \\\\\n\\midrule\n\\multicolumn{5}{l}{\\emph{Llama-3.1-8B-Instruct}} \\\\\nLoRA-only & 4.2M & 7.0 & 45\\,GB & baseline \\\\\nThreadGate & 4.3M & 7.3 & 46\\,GB & $+$65K \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Parameter overhead.} ThreadGate adds ${\\sim}$57K gate parameters for Qwen-2.5-7B (28 layers $\\times$ 2K per gate MLP) and ${\\sim}$65K for Llama-3.1-8B (32 layers), representing $<$0.001\\% of the base model. LoRA adapters (rank 16, targeting $q$/$v$ projections) contribute 4.2M parameters across both architectures.\n\n\\paragraph{Training time.} Standard variants (ThreadGate, Uniform Gate, LoRA-only) train in 5.7--7.3 hours. PCGrad adds ${\\sim}$33\\% overhead due to the per-step gradient projection computation. Scheduled sampling overhead varies: seed 42 adds only 8\\% (6.5h) due to efficient batched generation, while seed 123 adds 80\\% (10.8h) because of a longer generation schedule. The difference is due to the extended AR generation schedule in the seed 123 variant.\n\n\\paragraph{Inference overhead.} Gate computation at inference time is negligible: a single 32$\\to$64$\\to$1 MLP forward pass per layer adds $<$0.1\\% latency. $\\beta$-steering requires identifying goal tokens (a one-time operation per conversation) and adding a constant bias to attention logits, with zero additional parameters.\n\n\\section{Qualitative Steering Examples}\\label{sec:appendix-examples}\n\nTable~\\ref{tab:examples} illustrates the effect of $\\beta$-steering on model behavior in a 4-turn conversation where the system prompt instructs ``Always respond in exactly three bullet points.''\n\n\\begin{table*}[t]\n\\centering\\small\n\\caption{Qualitative effect of $\\beta$-steering on instruction following across conversation turns. System prompt: ``Always respond in exactly three bullet points.'' ThreadGate checkpoint, 4-turn conversation.}\n\\label{tab:examples}\n\\begin{tabular}{c p{5.5cm} p{5.5cm}}\n\\toprule\n\\textbf{Turn} & \\textbf{$\\beta$\\,=\\,0 (unsteered)} & \\textbf{$\\beta$\\,=\\,3 (steered)} \\\\\n\\midrule\n1 & \\checkmark~Three bullet points, on-topic & \\checkmark~Three bullet points, on-topic \\\\\n2 & \\checkmark~Three bullet points, relevant & \\checkmark~Three bullet points, relevant \\\\\n3 & $\\sim$~Four bullet points, partially on-topic & \\checkmark~Three bullet points, on-topic \\\\\n4 & \\texttimes~Free-form paragraph, no bullets & \\checkmark~Three bullet points, on-topic \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\nThe pattern is consistent with the GAR decay analysis (\\S\\ref{sec:analysis}): unsteered models progressively lose attention to the system-prompt constraint, leading to format violations at later turns. Steering maintains goal-token attention, preserving instruction compliance. The per-category breakdown in Table~\\ref{tab:ir-results} shows that content constraints benefit most from this effect.\n\n\\section{Gradient Conflict Analysis}\\label{sec:appendix-gradient}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth,height=0.42\\textheight,keepaspectratio]{fig2_training_pcgrad.pdf}\n  \\caption{(a)~Training GAR convergence to target ($\\tau$\\,=\\,0.5). (b)~PCGrad removes gradient conflict but $\\mathcal{L}_\\text{GAR}$ still collapses, confirming that gradient direction conflict is not the primary cause (\\S\\ref{subsec:pcgrad}).}\n  \\label{fig:training-pcgrad}\n\\end{figure}\n\nThis section provides extended gradient interaction analysis supporting the PCGrad exclusion argument in \\S\\ref{subsec:pcgrad}. We measure per-layer cosine similarity between NTP and GAR gradients, gradient magnitude ratios, and the effect of PCGrad projection on these quantities.\n\n\\paragraph{Gradient direction analysis.} Figure~\\ref{fig:gradient-heatmap} visualizes the per-layer cosine similarity between NTP and GAR gradients across training epochs for both standard ThreadGate and PCGrad training. Under standard training, 79\\% of layers show negative cosine similarity (gradient conflict) at epoch~0, declining to 68\\% by epoch~2 as GAR loss converges to near-zero. This decline reflects diminishing GAR gradient magnitude rather than alignment improvement---as GAR loss approaches zero, the GAR gradient shrinks proportionally, making cosine similarity measurements less reliable (small gradients produce noisy direction estimates). Under PCGrad training, the conflict percentage decreases more slowly (79\\%$\\to$71\\%), consistent with PCGrad projecting conflicting gradients onto the other's normal plane but not eliminating the underlying gradient conflict.\n\n\\paragraph{Spatial patterns.} The early layers (L0--L5) and output-adjacent layers (L24--L27) show the strongest conflict, corresponding to the layers where gate values deviate most from identity (Figure~\\ref{fig:gate-heatmap}). This spatial correlation is not causal: removing gradient conflict via PCGrad does not improve AR GAR, and gates at high-conflict layers are not systematically different from gates at low-conflict layers (Spearman $\\rho$\\,=\\,$-$0.12, $p$\\,=\\,0.54 between gate value and conflict magnitude).\n\n\\paragraph{Magnitude dominance.} NTP gradient magnitude dominates GAR by 7.5$\\times$ at epoch~0 and 14.7$\\times$ by epoch~2, as GAR loss converges while NTP loss remains at $\\sim$0.93. This growing dominance means that even when directions oppose, the effective update direction is determined almost entirely by NTP. PCGrad addresses gradient conflict but not magnitude dominance---it projects conflicting gradients onto the other's normal plane (changing direction) but preserves relative magnitudes. The 7.5--14.7$\\times$ magnitude ratio means that even after PCGrad projection, GAR contributes $<$7\\% of the effective update magnitude, explaining why PCGrad is ineffective.\n\n\\paragraph{Cross-model consistency.} Table~\\ref{tab:gradient-crossmodel} confirms the pattern on Llama-3.1-8B: gradients are near-orthogonal (mean cosine $+$0.005, essentially zero) rather than systematically conflicting, with 25.7$\\times$ NTP dominance. The Llama result is particularly informative because it shows that even without systematic gradient conflict (53\\% negative layers, near chance), the same TF-AR gap persists. This cross-model evidence strengthens the \\textit{modus tollens} argument: if gradient conflict were the cause, it should be present on both architectures; it is absent on Llama, yet the gap persists; therefore gradient direction conflict is not the primary cause.\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{fig_gradient_conflict_heatmap.pdf}\n\\caption{Per-layer cosine similarity between NTP and GAR gradients across training epochs. (a)~Standard training: conflict decreases from 79\\% to 68\\% of layers as GAR loss vanishes. (b)~PCGrad training: projection reduces conflict more slowly (79\\%$\\to$71\\%) but does not improve AR GAR, ruling out gradient direction conflict as the primary cause (\\S\\ref{subsec:pcgrad}).}\n\\label{fig:gradient-heatmap}\n\\end{figure*}\n\n\\section{Training Data Characteristics}\\label{sec:appendix-data}\n\nAll experiments use 8,000 multi-turn conversations sampled from the UltraChat \\citep{ding2023ultrachat} training split. Table~\\ref{tab:data-stats} summarizes the dataset characteristics. Conversations are truncated to 2,048 tokens; conversations shorter than 3 user turns are excluded to ensure sufficient multi-turn structure for GAR computation. The held-out evaluation sets use separate non-overlapping samples: $N$\\,=\\,50 conversations (mean 3.6 user turns) for the primary AR evaluation and $N$\\,=\\,5 conversations (10 turns each) for the long-conversation analysis (Appendix~\\ref{sec:appendix-n5}).\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Training and evaluation data characteristics. All data from UltraChat \\citep{ding2023ultrachat}.}\n\\label{tab:data-stats}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Property} & \\textbf{Train} & \\textbf{Eval (primary)} \\\\\n\\midrule\nConversations & 8,000 & 50 \\\\\nMin user turns & 3 & 3 \\\\\nMax sequence length & 2,048 & 2,048 \\\\\nSource & UltraChat train & UltraChat train \\\\\nOverlap & --- & non-overlapping \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Exposure Bias Scaling}\\label{sec:appendix-eb-scaling}\n\nFigure~\\ref{fig:eb-scaling} quantifies two scaling dimensions of the exposure bias phenomenon: cross-variant gap ratios (panel~a) and length-dependent gap compounding (panel~b).\n\n\\paragraph{Cross-variant gaps.} On Qwen, ThreadGate achieves the smallest gap among standard variants (7.9$\\times$) while PCGrad shows the largest (16.7$\\times$, consistent with its counterproductive effect on AR GAR). Scheduled sampling reduces the gap to ${\\sim}$1.2$\\times$, the only variant approaching parity. The ordering of gap ratios (SS $\\ll$ TG $<$ LoRA $<$ UG $<$ PCGrad) differs from the ordering of TF GAR (all $\\approx$ 0.50), confirming that training-time optimization success does not predict inference-time robustness. On Llama, both ThreadGate and LoRA-only show $\\sim$27$\\times$ gaps (by median), larger than any Qwen variant. The consistently larger Llama gaps may reflect its deeper architecture (32 vs.\\ 28 layers), which provides more layers for distributional drift to compound through.\n\n\\paragraph{Length-dependent compounding.} Panel~(b) shows that the gap compounds with conversation length: at 3.6 mean turns ($N$\\,=\\,50), ThreadGate's gap is 8$\\times$; at 10 turns ($N$\\,=\\,5), it widens to 31$\\times$. The relationship is approximately linear in the number of turns on a log scale, suggesting that the per-turn drift contribution is roughly multiplicative. Extrapolating this trend suggests that at 20 turns the gap would exceed 100$\\times$, making any training-time attention signal essentially undetectable. This length dependence is consistent with cumulative distributional drift---each model-generated turn introduces additional divergence from the teacher-forced training distribution, and by turn~10 the accumulated drift overwhelms any gating signal.\n\n\\paragraph{Implications for deployment.} These scaling results have practical implications: (1)~for applications requiring sustained attention over many turns (e.g., long-form tutoring, multi-step reasoning), architectural modifications alone are insufficient---distributional robustification or inference-time intervention is necessary; (2)~the near-parity of scheduled sampling (${\\sim}$1.2$\\times$ gap) suggests that bridging the training-inference distribution gap is both necessary and sufficient for maintaining attention; (3)~the $\\beta$-steering approach provides a complementary inference-time solution, but its effectiveness also depends on conversation length (Appendix~\\ref{sec:appendix-steering-viz}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_eb_scaling.pdf}\n\\caption{Exposure bias scaling analysis. (a)~TF/AR gap ratio across training variants; scheduled sampling (SS, ${\\sim}$1.3$\\times$) is the only variant near parity. Llama gaps ($\\sim$27$\\times$) exceed all Qwen variants. (b)~Gap compounds with conversation length: ThreadGate's gap widens from 8$\\times$ (3.6 turns) to 31$\\times$ (10 turns).}\n\\label{fig:eb-scaling}\n\\end{figure}\n\n\\section{Per-Turn AR GAR Dynamics}\\label{sec:appendix-ar-gar-dynamics}\n\nTo characterize how goal attention evolves across conversation turns under autoregressive generation, we compute per-turn AR GAR for all six Qwen-2.5-7B training configurations (Base, LoRA-only, Uniform Gate, PCGrad, Scheduled Sampling, ThreadGate) on the held-out evaluation set. Figure~\\ref{fig:kl_ar_gar_curves} plots per-turn AR GAR trajectories across turns 1--5, and Figure~\\ref{fig:kl_ar_gar_bar} compares mid-turn AR GAR levels across configurations.\n\nAll six configurations exhibit monotonic GAR decay as turn index increases, consistent with cumulative exposure bias eroding attention to goal tokens. The decay rate varies substantially: Scheduled Sampling retains by far the highest mid-turn GAR (0.423), followed distantly by ThreadGate (0.064), LoRA-only (0.037), Uniform Gate (0.033), PCGrad (0.030), and Base (0.019). Base decays most rapidly, losing the majority of its initial GAR within the first few turns. The large SS--TG gap mirrors Table~\\ref{tab:five-way} and confirms that distributional robustification---not gating architecture alone---is the primary driver of AR GAR retention.\\footnote{SS configuration uses seed 123 data; all other configurations use seed 42. Cross-seed trends are consistent (\\S\\ref{subsec:ss}).}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_kl_ar_gar_curves.pdf}\n\\caption{Per-turn AR GAR trajectories for six Qwen-2.5-7B configurations (turns 1--5). All models show monotonic decay; Scheduled Sampling retains far higher GAR throughout (0.53$\\to$0.39), while the remaining five variants cluster below 0.13 and decay rapidly.}\n\\label{fig:kl_ar_gar_curves}\n\\end{figure}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_kl_ar_gar_bar.pdf}\n\\caption{Mid-turn AR GAR comparison across six training configurations. Ranking from highest to lowest: Scheduled Sampling (0.423), ThreadGate (0.064), LoRA-only (0.037), Uniform Gate (0.033), PCGrad (0.030), Base (0.019).}\n\\label{fig:kl_ar_gar_bar}\n\\end{figure}\n\nThis pattern contrasts with teacher-forced evaluation, where GAR remains relatively stable across turns for all configurations. Under teacher forcing, the model conditions on ground-truth context at each turn, preventing the distributional drift that causes GAR erosion in AR mode. The divergence between TF stability and AR decay provides turn-level evidence for the exposure bias mechanism described in \\S\\ref{sec:analysis}: training-time attention patterns are optimized for a distribution that AR generation progressively departs from.\n\n\\section{Per-Head KL Divergence Analysis}\\label{sec:appendix-kl}\n\nTo test whether exposure bias selectively disrupts goal-attending heads rather than uniformly affecting all attention patterns, we compute per-head TF vs.\\ AR attention divergence on 30 held-out conversations. For each of the 28 attention heads per layer (784 heads total), we measure the KL divergence $D_\\text{KL}(p_\\text{TF} \\| p_\\text{AR})$ between teacher-forced and autoregressive attention distributions, and the absolute GAR shift $\\Delta\\text{GAR} = |\\text{GAR}_\\text{TF} - \\text{GAR}_\\text{AR}|$. This head-level analysis provides diagnostic evidence for the exposure bias interpretation beyond the aggregate TF-AR gap.\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Per-head TF-AR divergence statistics for Base and ThreadGate (Qwen-2.5-7B, 30 conversations). TG trains more concentrated goal attention under TF, but these high-GAR heads shift most under AR ($r$\\,=\\,0.743).}\n\\label{tab:kl-perhead}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Metric} & \\textbf{Base} & \\textbf{TG} \\\\\n\\midrule\nMean $\\Delta$GAR & 0.012 & 0.016 \\\\\nMean KL & 0.043 & 0.054 \\\\\nCorr(TF\\_GAR, $\\Delta$GAR) & 0.673 & 0.743 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Selective disruption.} ThreadGate exhibits 35\\% larger mean $\\Delta$GAR (0.016 vs.\\ 0.012) and 26\\% larger mean KL (0.054 vs.\\ 0.043) than Base. This is counterintuitive: the auxiliary GAR loss successfully trains more concentrated goal attention (higher TF GAR per head), but these very same heads shift more under AR generation. The correlation between per-head TF GAR and $\\Delta$GAR is strong for both models ($r$\\,=\\,0.673 for Base, 0.743 for TG), confirming that heads with higher goal attention under teacher forcing are disproportionately disrupted under autoregressive generation. This selectivity is a hallmark of exposure bias: the training-time optimization succeeds at creating a specific attention pattern (concentrated goal attention), but precisely this pattern has no autoregressive counterpart because it depends on conditioning on ground-truth context.\n\n\\paragraph{Layer-depth dependence.} The highest-KL heads concentrate at output-adjacent layers (L23--L27, KL\\,$>$\\,0.077) and L9 (KL\\,$\\approx$\\,0.068). Output-adjacent layers participate most directly in next-token prediction, so their attention distributions are most sensitive to changes in the conditioning context. L9's elevated KL may reflect a ``routing layer'' phenomenon observed in multi-layer transformers, where specific intermediate layers specialize in long-range information routing. The depth dependence is consistent with cumulative error propagation: distributional drift from model-generated tokens accumulates as information flows through successive layers, producing the largest attention shifts at the deepest layers.\n\n\\paragraph{Gate--KL independence.} Gate magnitude does not predict per-layer exposure bias severity: Spearman correlation between gate value and per-layer KL is 0.061 ($p$\\,=\\,0.757). The highest KL values concentrate at deep layers (L22--L27) where gates are near identity ($\\approx$1.0), while the lowest-gate layers show below-average KL (0.041 vs.\\ 0.056 for highest-gate layers). This independence confirms that the gating mechanism and the exposure bias phenomenon operate on different axes: gates modulate the magnitude of residual contributions, while exposure bias disrupts the direction (attention distribution) of those contributions. Even a ``perfect'' gate that could fully attenuate certain layers' residuals would not address the fundamental distributional mismatch that causes the attention shift.\n\n\\section{GAR Definition Robustness}\\label{sec:appendix-gar-robust}\n\nTo assess whether our conclusions depend on the specific GAR definition, we evaluate four alternative token-position variants on 50 held-out conversations (Table~\\ref{tab:gar-robust}): (1)~\\emph{ours} (last-token): attention from the last token to goal tokens (standard GAR-ours); (2)~\\emph{all-token}: average attention from all tokens to goal tokens; (3)~\\emph{first-token}: attention from the first assistant token to goal tokens; (4)~\\emph{goal-only}: attention from the last token to system-prompt-only tokens (excluding conversation content).\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Mid-turn GAR under four alternative definitions ($N$\\,=\\,50 conversations). ThreadGate only improves query-position-specific definitions (last-token, goal-only); Scheduled Sampling raises all four definitions above 0.36.}\n\\label{tab:gar-robust}\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Definition} & \\textbf{Base} & \\textbf{TG} & \\textbf{SS} \\\\\n\\midrule\nOurs (last-token) & 0.015 & \\textbf{0.325} & \\textbf{0.458} \\\\\nAll-token & 0.015 & 0.025 & \\textbf{0.366} \\\\\nFirst-token & 0.022 & 0.039 & \\textbf{0.412} \\\\\nGoal-only & 0.005 & \\textbf{0.310} & \\textbf{0.444} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThreadGate improvements are query-position-specific: the two definitions using the last token as query (ours: $0.015 \\to 0.325$; goal-only: $0.005 \\to 0.310$) show large gains, while all-token ($0.025$) and first-token ($0.039$) remain near base levels. This is expected: the GAR loss optimizes attention at the last-token position, so the learned routing does not generalize to other query positions.\n\nScheduled Sampling raises all four definitions above 0.36, with no definition falling below Base-relative gains. This confirms that SS builds a broad goal-attention pattern across token positions, rather than overfitting to the specific position targeted by the GAR loss. The pattern holds regardless of GAR definition: both the exposure bias diagnosis and the SS mitigation are robust to metric choice.\n\n\\section{General Capability Preservation (MMLU)}\\label{sec:appendix-mmlu}\n\nTo confirm that auxiliary GAR losses and attention steering do not degrade general language understanding, we evaluate all six Qwen-2.5-7B variants on MMLU 5-shot \\citep{hendrycks2021measuring} ($N$\\,=\\,14{,}042 questions).\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{MMLU 5-shot accuracy on Qwen-2.5-7B-Instruct. All fine-tuned variants remain within 0.8\\,pp of the base LoRA-only checkpoint.}\n\\label{tab:mmlu}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Model} & \\textbf{Acc (\\%)} & \\textbf{$\\Delta$ vs Base} \\\\\n\\midrule\nBase (pretrained) & 74.23 & --- \\\\\nPCGrad & 73.86 & $-$0.38 \\\\\nSS & 73.75 & $-$0.48 \\\\\nLoRA-only & 73.57 & $-$0.66 \\\\\nThreadGate & 73.47 & $-$0.77 \\\\\nUniform Gate & 73.46 & $-$0.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll variants degrade by $<$0.8\\,pp, confirming that attention steering and auxiliary GAR losses do not harm general language understanding. The ordering does not track GAR performance (e.g., PCGrad shows the smallest MMLU drop despite the worst AR GAR), consistent with GAR and NTP occupying largely orthogonal subspaces.\n\n\\section{Cross-Scale Validation (Qwen-2.5-1.5B)}\\label{sec:appendix-1.5b}\n\nWe validate cross-scale on Qwen-2.5-1.5B-Instruct to test whether goal attention decay and $\\beta$-steering generalize to smaller models.\n\n\\paragraph{Phase~1 GAR decay.} The 1.5B base model exhibits 79.8\\% GAR decline from turn~1 to mid-turns (vs.\\ 70.8\\% on 7B), confirming that attention decay is present across scales and is more severe at smaller model sizes.\n\n\\paragraph{Steering evaluation.} Table~\\ref{tab:1.5b-steering} reports AR evaluation ($N$\\,=\\,50). We report median PPL because Base $\\beta$\\,=\\,3 contains a catastrophic outlier (conversation~\\#11, PPL\\,$>$\\,$10^8$) that inflates the mean.\\footnote{The outlier occurs in a single conversation where $\\beta$-steering causes the base model to enter a degenerate repetition loop. ThreadGate produces zero such outliers across all $\\beta$ values, suggesting the gate provides stability against catastrophic steering failures.}\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Cross-scale $\\beta$-steering on Qwen-2.5-1.5B ($N$\\,=\\,50, AR). PPL is median due to catastrophic Base outlier at $\\beta$\\,=\\,3. TG eliminates outliers across all $\\beta$ values.}\n\\label{tab:1.5b-steering}\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Model} & $\\beta$ & \\textbf{AR GAR} & \\textbf{PPL (med)} \\\\\n\\midrule\nBase & 0 & 0.017 & 1.909 \\\\\nTG & 0 & 0.023 & 1.897 \\\\\n\\midrule\nBase & 3 & 0.120 & 2.216 \\\\\nTG & 3 & 0.114 & 1.975 \\\\\n\\midrule\nBase & 5 & 0.657 & 2.804 \\\\\nTG & 5 & 0.715 & 2.624 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe steering pattern mirrors the 7B results: $\\beta$\\,=\\,5 recovers GAR to 0.657--0.715 ($p < 0.001$), confirming that attention misallocation is the proximal cause of GAR collapse across scales. At $\\beta$\\,=\\,0, TG shows a small but significant GAR advantage ($p$\\,=\\,0.005); at $\\beta$\\,=\\,3, the TG--Base difference is not statistically significant ($p$\\,=\\,0.815), unlike the 7B pattern where TG consistently outperforms Base. This scale-specific difference may reflect the 1.5B model's limited capacity to maintain learned routing at intermediate steering strengths. ThreadGate does provide a stability advantage---zero catastrophic PPL outliers vs.\\ one in Base---suggesting that residual gating regularizes attention distributions even when aggregate GAR is comparable.\n\n\\section{Per-Seed Detailed Results}\\label{sec:appendix-perseed}\n\nTables~\\ref{tab:perseed-ss} and~\\ref{tab:perseed-tg} report full per-seed breakdowns for the two multi-seed configurations, providing evidence that our main findings are robust to random initialization.\n\n\\paragraph{Scheduled sampling (3 seeds).} TF GAR-ours averages $0.517\\pm0.032$ across seeds under the held-out protocol (Table~\\ref{tab:perseed-ss}); under IID evaluation, TF is more stable ($0.499\\pm0.003$), with the held-out variance driven by seed~123's higher value on the larger $N$\\,=\\,200 sample. AR GAR shows meaningful variance (std\\,=\\,0.047): seed 42 produces the lowest AR GAR (0.347, gap 1.4$\\times$), seed 123 is intermediate (0.423, gap 1.3$\\times$), and seed 456 is highest (0.433, gap 1.2$\\times$). This variance is expected: AR evaluation involves free-form generation where small differences in learned attention patterns can compound across turns. The variance is asymmetric---all seeds remain well above the non-SS baseline (0.064)---so the qualitative conclusion (SS provides order-of-magnitude improvement) holds across seeds. At $\\beta$\\,=\\,5, the cross-seed variance nearly vanishes ($0.717\\pm0.001$), confirming that strong steering converges to a seed-independent attention equilibrium that overwhelms initialization differences.\n\n\\paragraph{ThreadGate (2 seeds).} Two seeds produce nearly identical TF metrics ($0.504\\pm0.001$) and similar AR GAR (0.064 vs.\\ 0.055), with gap ratios of 7.9$\\times$ and 9.1$\\times$ respectively. The 15\\% relative difference in AR GAR is small compared to the order-of-magnitude TF-AR gap, confirming that the exposure bias phenomenon is not seed-dependent.\n\n\\paragraph{Training dynamics.} Seed variance in training time is non-trivial for scheduled sampling: seed 123 requires 10.8 hours (80\\% overhead) vs.\\ 6.5 hours for seeds 42 and 456 (8\\% overhead). This variance is driven by the stochastic Bernoulli sampling of model-generated contexts: seed 123 happens to trigger longer autoregressive generation episodes early in training, where the model produces longer outputs before hitting the max-length cutoff. Despite this training-time variance, all three seeds converge to similar final metrics, suggesting the optimization landscape is robust.\n\n\\input{../artifacts/appendix_expansion/tab_perseed_ss.tex}\n\n\\input{../artifacts/appendix_expansion/tab_perseed_tg.tex}\n\n\\section{Per-Turn GAR Decay Analysis}\\label{sec:appendix-perturn-detail}\n\nTables~\\ref{tab:perturn-qwen} and~\\ref{tab:perturn-llama} present per-turn AR GAR values for all configurations on both architectures, complementing the aggregate mid-turn GAR reported in the main text (Table~\\ref{tab:five-way}).\n\n\\paragraph{Qwen per-turn dynamics.} On Qwen (Table~\\ref{tab:perturn-qwen}), all non-SS variants show rapid monotonic decay: turn-1 GAR ranges from 0.085 (Base) to 0.130 (ThreadGate), but by turn~5 all collapse below 0.07. The decay rate is approximately exponential for the first 3 turns, then plateaus near a floor value that varies by configuration (Base: 0.004, ThreadGate: 0.043--0.066, LoRA-only: 0.040). ThreadGate and LoRA-only show occasional turn-level fluctuations (e.g., TG turn~5 = 0.066 $>$ turn~4 = 0.043), which reflect stochastic variation in individual conversations rather than systematic recovery. Scheduled sampling retains substantially higher GAR throughout (turn-5 GAR\\,=\\,0.365 vs.\\ 0.066 for ThreadGate), with a much flatter decay profile (15\\% decline from turn~1 to turn~5 vs.\\ 49\\% for ThreadGate). This flatter profile is the signature of distributional robustification: SS-trained models encounter model-generated context during training, so the attention patterns are calibrated for the distribution they actually face during inference.\n\n\\paragraph{Llama per-turn dynamics.} On Llama (Table~\\ref{tab:perturn-llama}), the decay is steeper: Base GAR drops from 0.028 to 0.008 over 4 turns (71\\% decline in the $N$\\,=\\,20 evaluation), and from 0.026 to 0.003 over 10 turns (88\\% decline in the $N$\\,=\\,5 long-conversation evaluation). ThreadGate on Llama shows a distinctive pattern: turn-level GAR is roughly constant (0.038--0.049) rather than monotonically declining, suggesting that the gating mechanism maintains a stable floor on Llama that it fails to maintain on Qwen. However, this floor (0.04) is still an order of magnitude below the TF target (0.484), confirming that the fundamental TF-AR gap persists.\n\n\\paragraph{Cross-architecture comparison.} The per-turn decay profiles reveal an architectural difference: Qwen shows a sharper initial decline (turn~1 to turn~2: $-$62\\% for Base) followed by a plateau, while Llama shows a more gradual and sustained decline throughout. This difference may reflect the two architectures' different attention head configurations and layer counts, but the qualitative pattern---monotonic or near-monotonic decline toward a near-zero floor---is universal.\n\nFigures~\\ref{fig:perturn-qwen-detail} and~\\ref{fig:perturn-llama-detail} visualize these trajectories.\n\n\\input{../artifacts/appendix_expansion/tab_perturn_qwen.tex}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_perturn_qwen_detail.pdf}\n  \\caption{Per-turn AR GAR-ours across six Qwen-2.5-7B configurations. Scheduled sampling (green) retains far higher GAR than all other variants, which cluster below 0.13 and decay rapidly.}\n  \\label{fig:perturn-qwen-detail}\n\\end{figure}\n\n\\input{../artifacts/appendix_expansion/tab_perturn_llama.tex}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_perturn_llama_detail.pdf}\n  \\caption{Per-turn AR GAR decay on Llama-3.1-8B. (a)~Three-way comparison (Base, TG, LoRA-only; $N$\\,=\\,20, 4 turns). (b)~Extended Base decay profile ($N$\\,=\\,5, 10 turns), showing 90\\% decline.}\n  \\label{fig:perturn-llama-detail}\n\\end{figure}\n\n\\section{Extended Dataset Statistics}\\label{sec:appendix-dataset-ext}\n\nTable~\\ref{tab:dataset_stats} provides detailed statistics for the UltraChat training and evaluation splits. From the full UltraChat-200K corpus (207,865 conversations in the \\texttt{train\\_sft} split), we filter for conversations with $\\geq$5 assistant turns, yielding 17,302 candidates (8.3\\% of the full corpus). We randomly sample 8,000 for training, 50 for primary AR evaluation (mean 3.6 user turns), 50 for IID GAR diagnostics, and 200 for the instruction retention evaluation.\n\n\\paragraph{Filtering rationale.} The $\\geq$5 assistant turns threshold was chosen empirically: conversations with fewer than 3 assistant turns do not exhibit measurable attention decay (turn-1 to turn-3 GAR decline $<$5\\%), making them uninformative for studying multi-turn exposure bias. The 5-turn threshold provides sufficient turn depth while retaining a reasonable fraction of the corpus. The average conversation in the filtered set contains 5.6 assistant turns (range: 5--7), with a mean sequence length of 1,247 tokens after tokenization with the Qwen-2.5 tokenizer.\n\n\\paragraph{Evaluation split design.} We maintain four non-overlapping evaluation sets to avoid contamination: (1)~the primary AR evaluation ($N$\\,=\\,50) uses the same conversation structure as training but with held-out conversations, enabling direct comparison of TF vs.\\ AR behavior; (2)~the IID GAR diagnostic ($N$\\,=\\,50) uses a separate sample for ablation studies that require independent measurements; (3)~the large instruction retention set ($N$\\,=\\,200) provides sufficient statistical power for per-category compliance analysis across 18 constraint types; (4)~the long-conversation set ($N$\\,=\\,5, 10 turns each) tests scaling behavior beyond the training distribution.\n\n\\paragraph{Domain diversity.} UltraChat covers a broad range of conversational topics including knowledge Q\\&A, creative writing, reasoning, and open-ended discussion. We do not stratify by topic, as our focus is on the architectural mechanism (attention routing) rather than domain-specific performance. The topic diversity serves as implicit regularization against overfitting to specific conversation patterns.\n\n\\input{../artifacts/appendix_expansion/tab_dataset_stats.tex}\n\n\\section{Extended GAR Robustness Analysis}\\label{sec:appendix-gar-ext}\n\nTable~\\ref{tab:gar_robustness} and Figure~\\ref{fig:gar-robust-grouped} extend the GAR robustness analysis from \\S\\ref{sec:appendix-gar-robust} with turn-1 GAR and gap ratio metrics across all four token-position variants. We evaluate four ways to select the query token position for gradient attribution: (1)~\\textit{Last} (our default): the final token of each assistant turn, which captures the model's ``summary'' attention pattern at the prediction boundary; (2)~\\textit{All}: the mean over all assistant tokens, providing a position-averaged view; (3)~\\textit{First}: the first assistant token, which reflects initial attention allocation; (4)~\\textit{Goal-only}: attention to goal tokens as defined by \\citet{dongre2026attention}, which restricts the target set to system-prompt tokens.\n\n\\paragraph{Position-specific vs.\\ broad improvement.} The key finding is a clear dichotomy between ThreadGate and Scheduled Sampling. ThreadGate improvements are restricted to last-token and goal-only positions (the two definitions sharing the query position targeted by the GAR loss): gap ratios drop to 1.21$\\times$ and 1.07$\\times$ respectively. All-token (5.04$\\times$) and first-token (8.24$\\times$) GAR remain near base levels, confirming that the learned routing is position-specific. Scheduled Sampling raises all four definitions above 0.36 with gap ratios $\\leq$1.83$\\times$, demonstrating that distributional robustification builds broad goal attention across token positions rather than overfitting to the position targeted by the loss.\n\n\\paragraph{Turn-1 vs.\\ mid-turn dynamics.} Turn-1 GAR is consistently higher than mid-turn GAR across all definitions and conditions, reflecting the first turn's proximity to the ground-truth prefix in training. The gap ratio quantifies how much of this initial attention survives into later turns. First-token GAR shows the largest gap ratios (Base: 13.3$\\times$, TG: 8.2$\\times$), indicating that the first-token position is most vulnerable to distributional drift---the initial token's attention pattern is highly dependent on the conditioning context, which diverges most from training under autoregressive generation.\n\n\\input{../artifacts/appendix_expansion/tab_gar_robustness.tex}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_gar_robustness_grouped.pdf}\n  \\caption{Mid-turn GAR across four token-position definitions. SS raises all four above 0.36; TG only improves last-token and goal-only.}\n  \\label{fig:gar-robust-grouped}\n\\end{figure}\n\n\\section{MMLU Category Breakdown}\\label{sec:appendix-mmlu-ext}\n\nTable~\\ref{tab:mmlu_detail} breaks down MMLU 5-shot accuracy by category (STEM, Social Sciences, Humanities, Other) for all six Qwen-2.5-7B training configurations. This analysis addresses a potential concern: that auxiliary attention objectives might divert representational capacity from general language understanding, particularly in knowledge-intensive STEM domains.\n\n\\paragraph{Per-category analysis.} The maximum per-category degradation is 1.5\\,pp (ThreadGate on STEM), and no category shows systematic degradation across all variants. Notably, the ordering of variants differs across categories: ThreadGate shows the largest STEM drop but the smallest Humanities drop, while PCGrad shows the smallest overall drop despite having the worst AR GAR. This lack of correlation between GAR performance and MMLU degradation is consistent with GAR and NTP occupying largely orthogonal parameter subspaces---the LoRA adapter capacity (4.2M parameters) is sufficient to accommodate both objectives without interference.\n\n\\paragraph{Statistical significance.} The per-category differences are small relative to the evaluation noise: with $N$\\,=\\,14,042 questions total ($\\sim$3,500 per category), a 0.8\\,pp accuracy difference corresponds to $\\sim$28 questions, well within expected stochastic variation for 5-shot in-context learning. A chi-squared test comparing the best (PCGrad, 73.86\\%) and worst (Uniform Gate, 73.46\\%) variants yields $p$\\,=\\,0.503, confirming no significant difference. The category-level stability confirms that auxiliary GAR losses and gating do not selectively harm any knowledge domain.\n\nFigure~\\ref{fig:mmlu-comparison} visualizes the per-category comparison, showing tight clustering across all variants within each category.\n\n\\input{../artifacts/appendix_expansion/tab_mmlu_detail.tex}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_mmlu_comparison.pdf}\n  \\caption{MMLU 5-shot accuracy by category across training configurations. All variants remain within 1.5\\,pp of the LoRA-only baseline across all categories.}\n  \\label{fig:mmlu-comparison}\n\\end{figure}\n\n\\section{Extended Cross-Scale Results (Qwen-2.5-1.5B)}\\label{sec:appendix-1.5b-ext}\n\nTable~\\ref{tab:qwen15b_results} extends the cross-scale analysis with Phase~1 GAR diagnostics, detailed Phase~2 training results, and $\\beta$-steering evaluation on the Qwen-2.5-1.5B-Instruct model.\n\n\\paragraph{Phase 1: GAR decay.} The 1.5B base model exhibits 79.8\\% relative GAR decline from turn~1 to mid-turns, more severe than the 7B model's 70.8\\% decline. This scale-dependent decay severity is consistent with smaller models having less redundant attention capacity: with 28 layers but only 1.5B parameters (vs.\\ 7B), each layer carries proportionally more of the total representational burden, leaving less room for goal-oriented attention to persist alongside the primary NTP objective.\n\n\\paragraph{Phase 2: Training.} ThreadGate training on 1.5B converges to TF GAR-ours of 0.498 with PPL of 2.67, closely matching the 7B results (0.504 / 2.78). The gate parameter count scales linearly with layer count (identical architecture, so ${\\sim}$57K gate parameters). Training completes in 2.1 hours vs.\\ 6.0 hours for 7B, reflecting the smaller model's reduced forward/backward pass cost.\n\n\\paragraph{Steering evaluation.} At $\\beta$\\,=\\,5, ThreadGate recovers GAR to 0.715 ($p < 0.001$), closely matching the 7B result (0.727). The recovery is essentially scale-independent at the strong steering regime: the attention bias added by $\\beta$-steering overwhelms any capacity differences. At $\\beta$\\,=\\,3, the picture differs: the TG--Base difference is not statistically significant ($p$\\,=\\,0.815) on 1.5B, unlike the significant difference on 7B ($p$\\,=\\,0.039). This scale-dependent response at intermediate $\\beta$ may reflect the 1.5B model's reduced capacity for fine-grained attention routing: with fewer parameters per layer, the model cannot sustain the subtle attention reweighting that $\\beta$\\,=\\,3 attempts.\n\n\\paragraph{Catastrophic outliers.} Base 1.5B at $\\beta$\\,=\\,3 produces one catastrophic PPL outlier (conversation \\#11, PPL $> 10^8$) caused by a degenerate repetition loop. ThreadGate produces zero such outliers across all $\\beta$ values, suggesting the gate provides a stabilizing effect on attention distributions even when aggregate GAR is comparable. We report median PPL to avoid this outlier dominating the central tendency estimate.\n\n\\input{../artifacts/appendix_expansion/tab_qwen15b_results.tex}\n\n\\section{Extended Statistical Analysis}\\label{sec:appendix-stats-ext}\n\nTable~\\ref{tab:statistical_tests} consolidates all statistical tests reported in this paper, including effect sizes, 95\\% bootstrap confidence intervals, and significance levels. This section provides methodological detail beyond the summary in Appendix~\\ref{sec:appendix-stats}.\n\n\\paragraph{Test selection rationale.} All primary comparisons use paired Wilcoxon signed-rank tests on $N$\\,=\\,39 conversations (those with $\\geq$3 turns from the 50-conversation held-out set). We use non-parametric tests because per-conversation GAR distributions are heavily right-skewed (skewness $>$ 2.0 for Base and PCGrad at $\\beta$\\,=\\,0), violating normality assumptions required by parametric alternatives. The pairing structure (same conversations evaluated under different training configurations) controls for conversation-level confounds (topic difficulty, conversation length, system-prompt complexity).\n\n\\paragraph{Effect size interpretation.} Effect sizes are computed as rank-biserial correlations ($r = Z / \\sqrt{N}$), following standard practice. The largest effect is SS vs.\\ TG ($r$\\,=\\,0.869, $p < 0.001$), a large effect by conventional thresholds ($r \\geq 0.5$), confirming that scheduled sampling produces a qualitatively different outcome. The TG vs.\\ Base effect ($r$\\,=\\,0.802) is also large, while TG vs.\\ LoRA-only ($r$\\,=\\,0.454) is medium, reflecting the modest incremental benefit of gating over LoRA alone.\n\n\\paragraph{Steering dose-response pattern.} At $\\beta$\\,=\\,0, all four comparisons are significant ($p \\leq 0.004$). At $\\beta$\\,=\\,3 (the phase transition), TG vs.\\ Base becomes marginally significant ($p$\\,=\\,0.039) and SS vs.\\ TG remains significant ($p$\\,=\\,0.010), but TG vs.\\ LoRA-only and PCGrad vs.\\ TG lose significance ($p > 0.7$). At $\\beta$\\,=\\,5, no pairwise comparison reaches significance---steering dominates and equalizes all variants. This dose-response pattern confirms that the training-time variant effects are real but small relative to the inference-time steering effect.\n\n\\paragraph{Instruction retention.} The instruction retention analysis uses McNemar's test on $N$\\,=\\,54 paired constraint evaluations (18 constraint types $\\times$ 3 conversations). The marginal significance ($p$\\,=\\,0.077) reflects the small sample size rather than a null effect: the point-biserial correlation ($r$\\,=\\,0.200, $p$\\,=\\,0.007) is significant when treating compliance as a continuous variable, and the per-category breakdown (Table~\\ref{tab:ir-results}) shows a clear content-constraint improvement (+23.8\\,pp).\n\n\\paragraph{Multiple comparisons.} We report uncorrected $p$-values for the same reason described in Appendix~\\ref{sec:appendix-stats}: comparisons are hypothesis-driven (each tests a specific causal exclusion in the analysis chain), not exploratory. All reported significant results ($p \\leq 0.039$) survive Holm-Bonferroni correction for the 4 primary comparisons within each $\\beta$ level.\n\n\\input{../artifacts/appendix_expansion/tab_statistical_tests.tex}\n\n\\section{Extended Training Dynamics}\\label{sec:appendix-training-ext}\n\nFigure~\\ref{fig:training-6panel} presents the complete training loss landscape for all five Qwen-2.5-7B conditions (ThreadGate, +PCGrad, Uniform Gate, LoRA-only, Scheduled Sampling) plus the base model, showing NTP loss, GAR loss, and total loss across three epochs.\n\n\\paragraph{NTP loss convergence.} All fine-tuned variants converge to NTP loss ${\\sim}$0.93 by epoch~3, with final-epoch values ranging from 0.929 (LoRA-only) to 0.934 (ThreadGate). PCGrad shows marginally higher variance due to gradient projection, but converges to the same terminal value. The uniformity of NTP convergence across variants---including those with auxiliary losses (ThreadGate, PCGrad) and those without (LoRA-only)---confirms that the GAR auxiliary objective does not interfere with the primary language modeling task during training.\n\n\\paragraph{GAR loss dynamics.} GAR loss collapses to near-zero within the first epoch under teacher forcing across all variants, consistent with the auxiliary objective being easy to optimize when the model conditions on ground-truth context. This rapid convergence is a double-edged sword: while it confirms that the MSE formulation (v7) achieves stable optimization, the ease of convergence also means the model never learns to maintain attention under distributional drift. The scheduled sampling variant shows distinctive dynamics: higher initial GAR loss variance from stochastic context mixing, with occasional spikes when a particularly challenging model-generated context is sampled, followed by convergence to a similar final value.\n\n\\paragraph{Training-inference disconnect.} The key observation is that training-time convergence is indistinguishable across variants: an observer with access only to training curves could not predict the 5.4$\\times$ AR GAR difference between SS and TG. This disconnect reinforces the diagnosis that the failure occurs at the training-to-inference transition, not during optimization, and explains why architectural modifications (gating, PCGrad) that operate during training cannot address the fundamental distributional mismatch.\n\n\\begin{figure*}[t]\n  \\centering\n  \\includegraphics[width=0.75\\textwidth]{fig_training_curves_6panel.pdf}\n  \\caption{Training loss curves for all five Qwen conditions. NTP loss (left) converges to ${\\sim}$0.93 across variants; GAR loss (center) collapses within epoch~1; total loss (right) is NTP-dominated. Training-time behavior is indistinguishable; the failure emerges only at inference.}\n  \\label{fig:training-6panel}\n\\end{figure*}\n\n\\section{Per-$\\beta$ Steering Visualization}\\label{sec:appendix-steering-viz}\n\nFigure~\\ref{fig:steering-4panel} visualizes per-turn GAR trajectories under four steering strengths ($\\beta$\\,=\\,0, 3, 5, 10), revealing the turn-level dynamics that underlie the aggregate steering results in Table~\\ref{tab:steering-full}.\n\n\\paragraph{Unsteered baseline ($\\beta$\\,=\\,0).} GAR decays monotonically from 0.12 to 0.02 over five turns, with the steepest decline between turns~1 and~2 ($-$44\\%). This trajectory matches the per-turn profiles in Appendix~\\ref{sec:appendix-perturn-detail} and confirms that the decay is a smooth, progressive phenomenon rather than a discrete failure at a specific turn.\n\n\\paragraph{Phase transition ($\\beta$\\,=\\,3).} Turn-1 GAR jumps to ${\\sim}$0.55, but per-turn decay persists (${\\sim}$15\\% decline from turn~1 to turn~5). This indicates that steering partially compensates for the distributional drift but does not eliminate it: the attention bias adds a constant offset to goal-token logits, while the drift compounds multiplicatively across turns. The residual decay at $\\beta$\\,=\\,3 explains why this operating point shows the strongest training-variant effects in the dose-response analysis (Appendix~\\ref{sec:appendix-stats-ext}).\n\n\\paragraph{Sustained recovery ($\\beta$\\,=\\,5).} GAR is sustained above 0.6 throughout, with minimal per-turn decay ($<$5\\% decline). At this steering strength, the constant attention bias dominates the per-turn drift, effectively replacing the lost training-time signal with an inference-time substitute. The 9\\% PPL cost (1.43 $\\to$ 1.77) is modest compared to the order-of-magnitude GAR recovery.\n\n\\paragraph{Saturation regime ($\\beta$\\,=\\,10).} GAR saturates near 1.0 across all turns but PPL degrades catastrophically ($>$3.5), as the excessive attention bias distorts the attention distribution beyond the model's capacity for coherent generation. This regime is impractical and serves as an upper bound on the steering approach.\n\n\\paragraph{Operating region.} The region $\\beta \\in [3, 5]$ balances GAR recovery against PPL cost, and the per-turn profiles confirm that steering must counteract an ongoing distributional drift rather than a one-time initialization failure---a key diagnostic that distinguishes exposure bias from alternative hypotheses (e.g., capacity limitations or optimization failures).\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_steering_perturn_4panel.pdf}\n  \\caption{Per-turn GAR under four $\\beta$-steering strengths. At $\\beta$\\,=\\,0, monotonic decay; at $\\beta$\\,=\\,3, partial recovery with residual decay; at $\\beta$\\,=\\,5, sustained high GAR; at $\\beta$\\,=\\,10, saturation with catastrophic PPL.}\n  \\label{fig:steering-4panel}\n\\end{figure}\n\n\\section{Llama-3.1-8B Scheduled Sampling Details}\\label{sec:appendix-llama-ss}\n\nLlama-3.1-8B-Instruct was trained with scheduled sampling using the same protocol as Qwen (\\S\\ref{sec:appendix-ss}), with one key difference: training was stopped at 2 epochs (${\\sim}$14{,}400 steps) instead of 3, because Llama's per-step wall-clock time was ${\\sim}$4$\\times$ slower than Qwen on the same hardware (624 steps/h vs.\\ ${\\sim}$2{,}400 steps/h for Qwen). This is attributable to different vocabulary sizes (Llama 128K vs.\\ Qwen 152K tokens) and attention implementation. The 2-epoch checkpoint was selected based on convergence of TF GAR (0.477, within 0.02 of Qwen's 3-epoch value 0.498).\n\n\\paragraph{$\\beta$-steering on Llama SS.}\nTable~\\ref{tab:llama-ss-steering} reports $\\beta$-steering results on the Llama SS model. Unlike Qwen, $\\beta$\\,=\\,3 does not trigger recovery on Llama (GAR 0.173 vs.\\ 0.166 at $\\beta$\\,=\\,0). At $\\beta$\\,=\\,5, GAR reaches 0.791---higher than Qwen's 0.717---suggesting that Llama's attention distribution is more responsive to the additive bias at higher steering strengths, possibly because the lower baseline AR GAR leaves more headroom for steering to exploit.\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{$\\beta$-steering on Llama-3.1-8B SS model ($N$\\,=\\,50, $T$\\,=\\,4).}\n\\label{tab:llama-ss-steering}\n\\begin{tabular}{@{}l ccc@{}}\n\\toprule\n& $\\beta$\\,=\\,0 & $\\beta$\\,=\\,3 & $\\beta$\\,=\\,5 \\\\\n\\midrule\nAR GAR & 0.166 & 0.173 & 0.791 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cross-model comparison.}\nTable~\\ref{tab:llama-vs-qwen-ss} compares scheduled sampling across both architectures. Both models show large gap compression relative to their ThreadGate baselines, but the residual gap on Llama (2.9$\\times$) is larger than Qwen's (1.2$\\times$). We attribute this to training duration: Llama received only 2 epochs of scheduled sampling exposure versus Qwen's 3 epochs. Llama reduces its median-based gap by 9.3$\\times$ (from 27$\\times$ to 2.9$\\times$) while Qwen reduces by 6.6$\\times$ (from 7.9$\\times$ to 1.2$\\times$), suggesting that a third epoch would likely narrow the residual gap further. Notably, $\\beta$-steering is more effective on Llama (0.791 vs.\\ 0.717 at $\\beta$\\,=\\,5), partially compensating for the weaker training-time compression.\n\n\\paragraph{Architectural differences.}\nSeveral architectural differences between Qwen-2.5-7B and Llama-3.1-8B may contribute to the cross-model gap variation. Llama uses Grouped Query Attention (GQA) with 8 KV heads (vs.\\ Qwen's full 28-head multi-head attention, MHA), which reduces the number of independently steerable attention heads by 3.5$\\times$. Llama also uses Rotary Position Embedding (RoPE) with a longer default context (128K tokens vs.\\ Qwen's 32K), which may affect how positional information interacts with goal-token attention at different conversation depths. Despite these differences, the qualitative pattern is identical: TF convergence, AR collapse, and SS-mediated recovery, confirming that exposure bias on auxiliary attention losses is architecture-general rather than an artifact of a specific attention implementation.\n\n\\paragraph{Training dynamics.}\nThe Llama SS training loss trajectory closely mirrors Qwen's during the first two epochs: NTP loss converges within epoch~1 (final NTP loss 0.62 for Llama vs.\\ 0.58 for Qwen), while GAR loss continues to decrease throughout epoch~2. The scheduled sampling ratio reaches ${\\sim}$0.20 at the end of epoch~2 (vs.\\ 0.30 at end of epoch~3 for Qwen), meaning Llama was exposed to less model-generated context during training. This partial exposure is sufficient to achieve meaningful gap compression (27$\\times$ $\\to$ 2.9$\\times$ by median) but leaves a larger residual gap than Qwen's full 3-epoch schedule.\n\n\\begin{table}[t]\n\\raggedright\\small\n\\caption{Scheduled sampling comparison: Qwen-2.5-7B vs.\\ Llama-3.1-8B.}\n\\label{tab:llama-vs-qwen-ss}\n\\begin{tabular}{@{}l cc@{}}\n\\toprule\n\\textbf{Metric} & \\textbf{Qwen-7B} & \\textbf{Llama-8B} \\\\\n\\midrule\nSS epochs & 3 & 2 \\\\\nTF GAR & 0.498 & 0.477 \\\\\nAR GAR ($\\beta$\\,=\\,0) & 0.401 & 0.166 \\\\\nTF/AR gap & 1.2$\\times$ & 2.9$\\times$ \\\\\nBaseline TG gap & 7.9$\\times$ & 27$\\times$ (median) \\\\\nGap compression & 6.5$\\times$ & 9.3$\\times$ \\\\\nAR GAR ($\\beta$\\,=\\,5) & 0.717 & 0.791 \\\\\nTF PPL & 2.78 & 2.82 \\\\\nAR PPL & 1.441 & 1.370 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Use of AI Assistants}\\label{sec:appendix-ai}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant\nthroughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing\n    pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections,\n    polishing prose, and reformatting LaTeX.\n    \\item \\textbf{Literature:} summarizing related papers to inform\n    related-work section.\n\\end{itemize}\n",
    "structuredPatch": [
      {
        "oldStart": 828,
        "oldLines": 7,
        "newStart": 828,
        "newLines": 7,
        "lines": [
          " AR GAR ($\\beta$\\,=\\,0) & 0.401 & 0.166 \\\\",
          " TF/AR gap & 1.2$\\times$ & 2.9$\\times$ \\\\",
          " Baseline TG gap & 7.9$\\times$ & 27$\\times$ (median) \\\\",
          "-Gap compression & 6.5$\\times$ & 9.3$\\times$ \\\\",
          "+Gap compression & 6.6$\\times$ & 9.3$\\times$ \\\\",
          " AR GAR ($\\beta$\\,=\\,5) & 0.717 & 0.791 \\\\",
          " TF PPL & 2.78 & 2.82 \\\\",
          " AR PPL & 1.441 & 1.370 \\\\"
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

_source line 113_

Now let me verify there are no remaining 7.8× or ~1.3× occurrences:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "1bcc1a68-ffc3-4b72-bfc3-bbcdd4d86487",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012znn5oG3wPMvsremERfoyy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 345,
      "cache_read_input_tokens": 66278,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 345
      },
      "output_tokens": 4,
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

_source line 114_

<details open><summary>🔧 Tool call — Grep · `toolu_01UnMbANtxVLAmPxXNJhbFnA`</summary>

```json
{
  "pattern": "7\\.8\\$",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections",
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
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "a09866aa-4bff-44fe-adfd-ba937fae6aa5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012znn5oG3wPMvsremERfoyy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 345,
      "cache_read_input_tokens": 66278,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 345
      },
      "output_tokens": 4,
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

_source line 115 · 2026-05-25T20:40:50.363Z_

<details><summary>↩ Tool result · `toolu_01UnMbANtxVLAmPxXNJhbFnA`</summary>

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
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "f86b747e-c9d5-47f8-8154-1416be4f9ca4",
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


### Tool call

_source line 116_

<details open><summary>🔧 Tool call — Grep · `toolu_01BJz4dBvGiqiZazoUAvxcPx`</summary>

```json
{
  "pattern": "1\\.3.\\\\times",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections",
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
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "4e161b98-59fe-45a4-98d1-f54798f5872b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012znn5oG3wPMvsremERfoyy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 345,
      "cache_read_input_tokens": 66278,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 345
      },
      "output_tokens": 4,
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

_source line 117 · 2026-05-25T20:40:51.217Z_

<details><summary>↩ Tool result · `toolu_01BJz4dBvGiqiZazoUAvxcPx`</summary>

```text
paper/sections/conclusion.tex:3:[Omitted long matching line]
paper/sections/discussion.tex:3:[Omitted long matching line]
paper/sections/appendix.tex:500:\caption{Exposure bias scaling analysis. (a)~TF/AR gap ratio across training variants; scheduled sampling (SS, ${\sim}$1.3$\times$) is the only variant near parity. Llama gaps ($\sim$27$\times$) exceed all Qwen variants. (b)~Gap compounds with conversation length: ThreadGate's gap widens from 8$\times$ (3.6 turns) to 31$\times$ (10 turns).}
paper/sections/appendix.tex:633:[Omitted long matching line]
paper/sections/introduction.tex:21:    \item \textbf{Scheduled sampling as remedy.} The first application of scheduled sampling to auxiliary attention objectives in multi-turn transformers, compressing the TF--AR gap to ${\sim}$1.3$\times$ on Qwen and ${\sim}$2.9$\times$ on Llama with no perplexity degradation, robust across three seeds.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "30212cfc-e8d0-4d56-a67c-79b128f5b680",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "paper/sections/conclusion.tex:3:[Omitted long matching line]\npaper/sections/discussion.tex:3:[Omitted long matching line]\npaper/sections/appendix.tex:500:\\caption{Exposure bias scaling analysis. (a)~TF/AR gap ratio across training variants; scheduled sampling (SS, ${\\sim}$1.3$\\times$) is the only variant near parity. Llama gaps ($\\sim$27$\\times$) exceed all Qwen variants. (b)~Gap compounds with conversation length: ThreadGate's gap widens from 8$\\times$ (3.6 turns) to 31$\\times$ (10 turns).}\npaper/sections/appendix.tex:633:[Omitted long matching line]\npaper/sections/introduction.tex:21:    \\item \\textbf{Scheduled sampling as remedy.} The first application of scheduled sampling to auxiliary attention objectives in multi-turn transformers, compressing the TF--AR gap to ${\\sim}$1.3$\\times$ on Qwen and ${\\sim}$2.9$\\times$ on Llama with no perplexity degradation, robust across three seeds.",
    "numLines": 5
  }
}
```

</details>

---


### Assistant

_source line 118_

<details><summary>Logged reasoning block</summary>

```text
There are more ~1.3× occurrences that need to be changed:

1. appendix.tex:500 - caption: "${\sim}$1.3$\times$" in "(SS, ${\sim}$1.3$\times$)"
2. appendix.tex:633 - need to check
3. introduction.tex:21 - "${\sim}$1.3$\times$"
4. conclusion.tex:3 - need to check
5. discussion.tex:3 - need to check

Let me read these to see the full context.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "6ad92b78-ec7b-4e01-b031-6c11670e8cfe",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Uq9kTAFuk2FQU1j1rZ6VML",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 597,
      "cache_read_input_tokens": 66623,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 597
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

_source line 119_

More ~1.3× occurrences found. Let me fix them:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "282695bb-a530-440c-9708-545a411bb227",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Uq9kTAFuk2FQU1j1rZ6VML",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 597,
      "cache_read_input_tokens": 66623,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 597
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

_source line 120_

<details open><summary>🔧 Tool call — Read · `toolu_01DFHmiMiaFEnk8RUJ1Jwok3`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex",
  "offset": 498,
  "limit": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "19d4daf6-6549-4a12-a01c-6e27180bcafa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Uq9kTAFuk2FQU1j1rZ6VML",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 597,
      "cache_read_input_tokens": 66623,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 597
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

_source line 121 · 2026-05-25T20:40:56.353Z_

<details><summary>↩ Tool result · `toolu_01DFHmiMiaFEnk8RUJ1Jwok3`</summary>

```text
498	\centering
499	\includegraphics[width=\columnwidth]{fig_eb_scaling.pdf}
500	\caption{Exposure bias scaling analysis. (a)~TF/AR gap ratio across training variants; scheduled sampling (SS, ${\sim}$1.3$\times$) is the only variant near parity. Llama gaps ($\sim$27$\times$) exceed all Qwen variants. (b)~Gap compounds with conversation length: ThreadGate's gap widens from 8$\times$ (3.6 turns) to 31$\times$ (10 turns).}
501	\label{fig:eb-scaling}
502	\end{figure}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "66698fcf-f14a-4aca-8cc2-2bad9a17f989",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex",
      "content": "\\centering\n\\includegraphics[width=\\columnwidth]{fig_eb_scaling.pdf}\n\\caption{Exposure bias scaling analysis. (a)~TF/AR gap ratio across training variants; scheduled sampling (SS, ${\\sim}$1.3$\\times$) is the only variant near parity. Llama gaps ($\\sim$27$\\times$) exceed all Qwen variants. (b)~Gap compounds with conversation length: ThreadGate's gap widens from 8$\\times$ (3.6 turns) to 31$\\times$ (10 turns).}\n\\label{fig:eb-scaling}\n\\end{figure}",
      "numLines": 5,
      "startLine": 498,
      "totalLines": 851
    }
  }
}
```

</details>

---


### Tool call

_source line 122_

<details open><summary>🔧 Tool call — Read · `toolu_01EEnb8yPtTy1RNYXR5MxtML`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex",
  "offset": 630,
  "limit": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "afac71f3-c969-45b5-ba8f-93e11645ec11",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Uq9kTAFuk2FQU1j1rZ6VML",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 597,
      "cache_read_input_tokens": 66623,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 597
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

_source line 123 · 2026-05-25T20:40:57.302Z_

<details><summary>↩ Tool result · `toolu_01EEnb8yPtTy1RNYXR5MxtML`</summary>

```text
630	
631	Tables~\ref{tab:perseed-ss} and~\ref{tab:perseed-tg} report full per-seed breakdowns for the two multi-seed configurations, providing evidence that our main findings are robust to random initialization.
632	
633	\paragraph{Scheduled sampling (3 seeds).} TF GAR-ours averages $0.517\pm0.032$ across seeds under the held-out protocol (Table~\ref{tab:perseed-ss}); under IID evaluation, TF is more stable ($0.499\pm0.003$), with the held-out variance driven by seed~123's higher value on the larger $N$\,=\,200 sample. AR GAR shows meaningful variance (std\,=\,0.047): seed 42 produces the lowest AR GAR (0.347, gap 1.4$\times$), seed 123 is intermediate (0.423, gap 1.3$\times$), and seed 456 is highest (0.433, gap 1.2$\times$). This variance is expected: AR evaluation involves free-form generation where small differences in learned attention patterns can compound across turns. The variance is asymmetric---all seeds remain well above the non-SS baseline (0.064)---so the qualitative conclusion (SS provides order-of-magnitude improvement) holds across seeds. At $\beta$\,=\,5, the cross-seed variance nearly vanishes ($0.717\pm0.001$), confirming that strong steering converges to a seed-independent attention equilibrium that overwhelms initialization differences.
634	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "6eac236f-44c4-4747-94a1-9b6fabd75680",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex",
      "content": "\nTables~\\ref{tab:perseed-ss} and~\\ref{tab:perseed-tg} report full per-seed breakdowns for the two multi-seed configurations, providing evidence that our main findings are robust to random initialization.\n\n\\paragraph{Scheduled sampling (3 seeds).} TF GAR-ours averages $0.517\\pm0.032$ across seeds under the held-out protocol (Table~\\ref{tab:perseed-ss}); under IID evaluation, TF is more stable ($0.499\\pm0.003$), with the held-out variance driven by seed~123's higher value on the larger $N$\\,=\\,200 sample. AR GAR shows meaningful variance (std\\,=\\,0.047): seed 42 produces the lowest AR GAR (0.347, gap 1.4$\\times$), seed 123 is intermediate (0.423, gap 1.3$\\times$), and seed 456 is highest (0.433, gap 1.2$\\times$). This variance is expected: AR evaluation involves free-form generation where small differences in learned attention patterns can compound across turns. The variance is asymmetric---all seeds remain well above the non-SS baseline (0.064)---so the qualitative conclusion (SS provides order-of-magnitude improvement) holds across seeds. At $\\beta$\\,=\\,5, the cross-seed variance nearly vanishes ($0.717\\pm0.001$), confirming that strong steering converges to a seed-independent attention equilibrium that overwhelms initialization differences.\n",
      "numLines": 5,
      "startLine": 630,
      "totalLines": 851
    }
  }
}
```

</details>

---


### Tool call

_source line 124_

<details open><summary>🔧 Tool call — Read · `toolu_01ERiz8qTLvuFjCE4KtRa3hg`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/introduction.tex",
  "offset": 19,
  "limit": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "ac034875-488a-43ab-8536-4efe0e1ed7a9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Uq9kTAFuk2FQU1j1rZ6VML",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 597,
      "cache_read_input_tokens": 66623,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 597
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

_source line 125 · 2026-05-25T20:40:57.786Z_

<details><summary>↩ Tool result · `toolu_01ERiz8qTLvuFjCE4KtRa3hg`</summary>

```text
19	    \item \textbf{Causal exclusion testbed.} A five-way diagnostic design, informed by seven loss-formulation iterations, that isolates the failure mechanism via causal exclusion, including a PCGrad \emph{modus tollens} argument ruling out gradient direction conflict ($p$\,=\,0.002, effect reverses).
20	    \item \textbf{Attention misallocation diagnosis.} Inference-time $\beta$-steering recovers goal attention with modest perplexity cost, evidence that the collapse is an attention routing failure, not a representational one.
21	    \item \textbf{Scheduled sampling as remedy.} The first application of scheduled sampling to auxiliary attention objectives in multi-turn transformers, compressing the TF--AR gap to ${\sim}$1.3$\times$ on Qwen and ${\sim}$2.9$\times$ on Llama with no perplexity degradation, robust across three seeds.
22	\end{enumerate}
23	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "26ab403f-9f87-4878-b96f-bab6f12203e8",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/introduction.tex",
      "content": "    \\item \\textbf{Causal exclusion testbed.} A five-way diagnostic design, informed by seven loss-formulation iterations, that isolates the failure mechanism via causal exclusion, including a PCGrad \\emph{modus tollens} argument ruling out gradient direction conflict ($p$\\,=\\,0.002, effect reverses).\n    \\item \\textbf{Attention misallocation diagnosis.} Inference-time $\\beta$-steering recovers goal attention with modest perplexity cost, evidence that the collapse is an attention routing failure, not a representational one.\n    \\item \\textbf{Scheduled sampling as remedy.} The first application of scheduled sampling to auxiliary attention objectives in multi-turn transformers, compressing the TF--AR gap to ${\\sim}$1.3$\\times$ on Qwen and ${\\sim}$2.9$\\times$ on Llama with no perplexity degradation, robust across three seeds.\n\\end{enumerate}\n",
      "numLines": 5,
      "startLine": 19,
      "totalLines": 23
    }
  }
}
```

</details>

---


### Tool call

_source line 126_

<details open><summary>🔧 Tool call — Read · `toolu_014mt4WjPN8aSZNi49FR3Qf9`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/conclusion.tex",
  "offset": 1,
  "limit": 10
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "b04d9d07-2b27-4818-988f-36e326c2fcd1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Uq9kTAFuk2FQU1j1rZ6VML",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 597,
      "cache_read_input_tokens": 66623,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 597
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

_source line 127 · 2026-05-25T20:40:58.720Z_

<details><summary>↩ Tool result · `toolu_014mt4WjPN8aSZNi49FR3Qf9`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	\looseness=-1 Auxiliary attention losses converge under teacher forcing (GAR\,=\,0.50) but collapse by an order of magnitude under autoregressive generation on two architectures. A five-way diagnostic comparison identifies exposure bias as a primary contributing factor; $\beta$-steering recovers GAR above the TF baseline, consistent with attention misallocation as a proximal cause (KV cache drift remains untested). Scheduled sampling compresses the gap to ${\sim}$1.3$\times$ (Qwen) and ${\sim}$2.9$\times$ (Llama), generalizing across architectures and seeds; to our knowledge, the first such transfer to auxiliary attention objectives in multi-turn transformers.
4	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "c327aa71-23d4-4d2d-8470-9d407560fd70",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/conclusion.tex",
      "content": "\\section{Conclusion}\\label{sec:conclusion}\n\n\\looseness=-1 Auxiliary attention losses converge under teacher forcing (GAR\\,=\\,0.50) but collapse by an order of magnitude under autoregressive generation on two architectures. A five-way diagnostic comparison identifies exposure bias as a primary contributing factor; $\\beta$-steering recovers GAR above the TF baseline, consistent with attention misallocation as a proximal cause (KV cache drift remains untested). Scheduled sampling compresses the gap to ${\\sim}$1.3$\\times$ (Qwen) and ${\\sim}$2.9$\\times$ (Llama), generalizing across architectures and seeds; to our knowledge, the first such transfer to auxiliary attention objectives in multi-turn transformers.\n",
      "numLines": 4,
      "startLine": 1,
      "totalLines": 4
    }
  }
}
```

</details>

---


### Tool call

_source line 128_

<details open><summary>🔧 Tool call — Read · `toolu_01K5EanHf1voYeCpDdkNnygi`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/discussion.tex",
  "offset": 1,
  "limit": 10
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "9f0562ed-d782-4b43-8367-fa9a1640b802",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Uq9kTAFuk2FQU1j1rZ6VML",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 597,
      "cache_read_input_tokens": 66623,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 597
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

_source line 129 · 2026-05-25T20:40:59.372Z_

<details><summary>↩ Tool result · `toolu_01K5EanHf1voYeCpDdkNnygi`</summary>

```text
1	\section{Discussion}\label{sec:discussion}
2	
3	\looseness=-1 NTP self-recovers because prediction is the same task at both regimes \citep{he2019exposure}; GAR optimizes a \emph{global property} (attention allocation to goal tokens) with no autoregressive counterpart. The collapse is selective: GAR-ours collapses by an order of magnitude while GAR-Dongre shows negligible shift (${\leq}$1.3$\times$). Per-head analysis confirms selectivity: heads with higher TF GAR shift most under AR ($r$\,=\,0.743; Appendix~\ref{sec:appendix-kl}). Any auxiliary attention objective targeting distributional properties rather than prediction itself should face the same barrier under teacher forcing.
4	
5	\looseness=-1 Our exclusion identifies exposure bias as a primary contributing factor, but cannot fully rule out KV cache drift (\S\ref{sec:limitations}). The PCGrad exclusion rules out direction conflict but not magnitude imbalance (7.5--25.7$\times$ NTP dominance; \citealp{chen2018gradnorm}). The GAR--compliance correlation is weak ($r$\,=\,0.200; Appendix~\ref{sec:appendix-ir}), reinforcing GAR's role as a diagnostic probe. Our $\beta$-steering is likewise a \emph{diagnostic}, distinct from inference-time remedies such as split-softmax \citep{li2024measuring} and Rhea \citep{hong2025rhea}. SS and inference-time fixes are complementary: SS modifies representations without inference cost; inference-time methods cannot recover patterns never learned. At $\beta$\,=\,5 the two converge (SS\,=\,0.717 vs.\ TG\,=\,0.727).
6	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "4665aec6-295b-47cb-ac1b-2b7a67a150e7",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/discussion.tex",
      "content": "\\section{Discussion}\\label{sec:discussion}\n\n\\looseness=-1 NTP self-recovers because prediction is the same task at both regimes \\citep{he2019exposure}; GAR optimizes a \\emph{global property} (attention allocation to goal tokens) with no autoregressive counterpart. The collapse is selective: GAR-ours collapses by an order of magnitude while GAR-Dongre shows negligible shift (${\\leq}$1.3$\\times$). Per-head analysis confirms selectivity: heads with higher TF GAR shift most under AR ($r$\\,=\\,0.743; Appendix~\\ref{sec:appendix-kl}). Any auxiliary attention objective targeting distributional properties rather than prediction itself should face the same barrier under teacher forcing.\n\n\\looseness=-1 Our exclusion identifies exposure bias as a primary contributing factor, but cannot fully rule out KV cache drift (\\S\\ref{sec:limitations}). The PCGrad exclusion rules out direction conflict but not magnitude imbalance (7.5--25.7$\\times$ NTP dominance; \\citealp{chen2018gradnorm}). The GAR--compliance correlation is weak ($r$\\,=\\,0.200; Appendix~\\ref{sec:appendix-ir}), reinforcing GAR's role as a diagnostic probe. Our $\\beta$-steering is likewise a \\emph{diagnostic}, distinct from inference-time remedies such as split-softmax \\citep{li2024measuring} and Rhea \\citep{hong2025rhea}. SS and inference-time fixes are complementary: SS modifies representations without inference cost; inference-time methods cannot recover patterns never learned. At $\\beta$\\,=\\,5 the two converge (SS\\,=\\,0.717 vs.\\ TG\\,=\\,0.727).\n",
      "numLines": 6,
      "startLine": 1,
      "totalLines": 6
    }
  }
}
```

</details>

---


### Assistant

_source line 130_

<details><summary>Logged reasoning block</summary>

```text
Now I see more occurrences to fix:

1. appendix.tex:500 - "(SS, ${\sim}$1.3$\times$)" → "(SS, ${\sim}$1.2$\times$)"
2. appendix.tex:633 - per-seed breakdowns mention "gap 1.4$\times$", "gap 1.3$\times$", "gap 1.2$\times$" - these are per-seed values, so they should stay. The ~1.3× elsewhere is a summary/average.
3. introduction.tex:21 - "${\sim}$1.3$\times$" → "${\sim}$1.2$\times$"


4. conclusion.tex:3 - "${\sim}$1.3$\times$" → "${\sim}$1.2$\times$"
5. discussion.tex:3 - "${\leq}$1.3$\times$" is about GAR-Dongre's shift, not the SS gap, so this stays unchanged.

Let me apply these fixes now.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "fcc332c2-e168-46af-bedb-b4b891a62222",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U6YJeUEnxob2yKRkCoKyWd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2259,
      "cache_read_input_tokens": 67220,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2259
      },
      "output_tokens": 10,
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

_source line 131_

<details open><summary>🔧 Tool call — Edit · `toolu_017rWP31mfB4gPm6TwR8eB7A`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex",
  "old_string": "(SS, ${\\sim}$1.3$\\times$) is the only variant near parity",
  "new_string": "(SS, ${\\sim}$1.2$\\times$) is the only variant near parity"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "a266a4d1-3583-4b3c-a78c-007de7990f44",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U6YJeUEnxob2yKRkCoKyWd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2259,
      "cache_read_input_tokens": 67220,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2259
      },
      "output_tokens": 10,
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

_source line 132 · 2026-05-25T20:41:10.942Z_

<details><summary>↩ Tool result · `toolu_017rWP31mfB4gPm6TwR8eB7A`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "9342e1e7-0afc-43bb-bc42-407cd5f5c2e2",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/appendix.tex",
    "oldString": "(SS, ${\\sim}$1.3$\\times$) is the only variant near parity",
    "newString": "(SS, ${\\sim}$1.2$\\times$) is the only variant near parity",
    "originalFile": "\\section{Training Configuration}\\label{sec:appendix-hyper}\n\nTable~\\ref{tab:hyperparams} lists the full training configuration shared across all fine-tuned variants. ThreadGate gate parameters receive a $10\\times$ learning rate multiplier and are initialized with bias 1.5 ($\\sigma(1.5) \\approx 0.82$); the gate MLP adds ${\\sim}$57K parameters per variant ($<$0.001\\% of 7B). The scheduled sampling variant (v8b) linearly increases the model-generated context ratio from 0 to 0.3 over 3 epochs (29.7--37.1\\% effective usage due to per-sample Bernoulli sampling). All experiments were conducted on a single NVIDIA RTX PRO 6000 Blackwell Server Edition GPU (96\\,GB VRAM), requiring 6--8 hours per variant.\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Training hyperparameters for all fine-tuned variants. Entries marked $\\dagger$ apply only to ThreadGate and its ablations.}\n\\label{tab:hyperparams}\n\\begin{tabular}{l@{\\hspace{8pt}}l}\n\\toprule\n\\textbf{Parameter} & \\textbf{Value} \\\\\n\\midrule\nBase model & Qwen-2.5-7B-Instruct \\\\\nLoRA rank / $\\alpha$ & 16 / 32 \\\\\nLoRA targets & \\texttt{q\\_proj}, \\texttt{v\\_proj} \\\\\nOptimizer & AdamW ($\\beta_1$\\!=\\!0.9, $\\beta_2$\\!=\\!0.999) \\\\\nLearning rate & $2 \\times 10^{-4}$ \\\\\nGate LR mult.$^\\dagger$ & $10\\times$ \\\\\nBatch / grad accum & 1 / 8 (eff.\\ 8) \\\\\nEpochs & 3 \\\\\nMax seq length & 2048 \\\\\nTraining data & 8K UltraChat convs \\\\\nSeed & 42 (+123 for TG, SS) \\\\\n$\\lambda_\\text{GAR}$/$\\lambda_\\text{div}$ & 1.0 / 1.0 \\\\\nGAR target $\\tau$ & 0.5 \\\\\nGate init bias$^\\dagger$ & 1.5 ($\\sigma\\!\\approx\\!0.82$) \\\\\nGate hidden dim$^\\dagger$ & 64 \\\\\nTurn embed dim$^\\dagger$ & 16 \\\\\nGPU & RTX PRO 6000 (96\\,GB) \\\\\nTraining time & 6--8 h / variant \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Loss Formulation Search}\\label{sec:appendix-loss}\n\nThe final MSE + gate diversity loss (\\S\\ref{sec:loss}) emerged from seven iterations spanning four loss families. Table~\\ref{tab:loss-iterations} summarizes the progression. The search was motivated by a consistent failure mode: naive formulations either collapse to trivial solutions (cumulative losses) or drive gates toward identity (maximize-family losses). We describe each family below.\n\n\\paragraph{Cumulative losses (v1--v2).} These losses accumulate GAR contributions across layers, rewarding monotonically increasing attention. v1 collapsed because once the cumulative GAR exceeded the threshold, the loss gradient vanished and gates froze. v2 added an $\\varepsilon$-stabilization term to the cumulative product, but numerical instability from the product of 28 per-layer terms dominated, and training followed the same trajectory.\n\n\\paragraph{Maximize losses (v3--v5).} These losses directly maximize mean GAR ($-\\text{mean}(\\text{GAR})$). The unbounded objective rewards full pass-through ($g \\to 1.0$), collapsing gate diversity (std $<$ 0.025). At $\\lambda$=2 (v3), gates froze within 100 steps; at $\\lambda$=10 (v3b), convergence to identity accelerated; at $\\lambda$=1 (v5), rebalancing delayed but did not prevent the same degenerate solution.\n\n\\paragraph{Smooth saturation (v6).} This bounded the reward using a saturating function, intended to prevent the unbounded growth of maximize losses. In practice, the loss landscape remained monotonic in $g$, and training followed the same terminal trajectory as the maximize family, only more slowly.\n\n\\paragraph{MSE + gate diversity (v7).} The MSE formulation provides bidirectional pressure: GAR above $\\tau$ incurs the same penalty as GAR below $\\tau$, preventing the runaway optimization of maximize losses. The gate diversity regularizer ($\\mathcal{L}_\\text{div}$) enforces a minimum standard deviation across per-layer gate values, preventing all gates from collapsing to a uniform value. This combination is the only one that achieved stable convergence (GAR-ours = 0.50, PPL = 2.78).\n\n\\begin{table*}[t]\n\\centering\\footnotesize\n\\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration (v7).}\n\\label{tab:loss-iterations}\n\\begin{tabular}{l l l p{5.8cm} c c}\n\\toprule\n & \\textbf{Loss Family} & \\textbf{Status} & \\textbf{Failure Mechanism} & \\textbf{GAR} & \\textbf{PPL} \\\\\n\\midrule\nv1  & Cumulative            & \\texttimes~GAR loss $\\to$ 0     & GAR loss collapses to zero once threshold is reached; gate gradients vanish at equilibrium & ---  & ---  \\\\\nv2  & Cumulative + $\\varepsilon$ & \\texttimes~same trajectory & Numerical instability from cumulative product; $\\varepsilon$-stabilization insufficient & ---  & ---  \\\\\nv3  & Maximize ($\\lambda$=2)  & \\texttimes~gate frozen        & Unbounded reward drives gates toward identity (all-pass); no layer selectivity & ---  & ---  \\\\\nv3b & Maximize ($\\lambda$=10) & \\texttimes~identity collapse   & Higher $\\lambda$ accelerates convergence to same degenerate identity solution & ---  & ---  \\\\\nv5  & Maximize ($\\lambda$=1)  & \\texttimes~identity collapse   & Rebalancing delays but does not prevent identity collapse & ---  & ---  \\\\\nv6  & Smooth saturation       & \\texttimes~identity collapse   & Monotonic reward identical to maximize in practice; boundedness slows but does not alter terminal trajectory & ---  & ---  \\\\\nv7  & MSE + gate div          & \\checkmark~\\textbf{converged}  & \\textbf{Bidirectional penalty prevents identity collapse; gate diversity regularizer enforces layer selectivity} & 0.50 & 2.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\section{Instruction Retention Details}\\label{sec:appendix-ir}\n\nTo evaluate whether GAR improvements translate to downstream task performance, we test instruction retention across 18 system-prompt constraint types using the ThreadGate checkpoint with $\\beta$\\,=\\,3 steering on $N$\\,=\\,200 held-out conversations. Each constraint type requires the model to follow a specific instruction embedded in the system prompt (e.g., ``always respond in bullet points'', ``never use the word X'', ``include a summary at the end''). This evaluation bridges the gap between our attention-level metric (GAR) and observable model behavior.\n\n\\paragraph{Evaluation protocol.} For each conversation, we inject a constraint into the system prompt and evaluate compliance across all assistant turns. A turn is compliant if it satisfies the constraint according to rule-based checkers (for format, count, and position constraints) or GPT-4-based evaluation (for content constraints, which require semantic judgment). We use the same 18 constraint types across all conversations, yielding $N$\\,=\\,54 paired evaluations (18 types $\\times$ 3 conversations per type) for the McNemar analysis.\n\n\\paragraph{Per-category results.} Table~\\ref{tab:ir-results} reports per-category compliance rates. Content constraints---which require attending to and recalling specific system-prompt instructions across turns---show the largest improvement (+23.8\\,pp), consistent with GAR measuring attention to goal tokens. This category includes constraints like ``mention X in every response'' and ``always reference the original topic,'' which require sustained attention to the system prompt. Position constraints (e.g., ``start each response with Y'') show a modest improvement (+6.7\\,pp), as they partially depend on goal-token attention. Format (e.g., ``use bullet points'') and count constraints (e.g., ``exactly 3 sentences'') show no change, consistent with these being procedural patterns that are cached in the model's generation routine rather than requiring ongoing attention to the system prompt.\n\n\\paragraph{Correlation analysis.} The GAR-compliance correlation ($r$\\,=\\,0.200, $p$\\,=\\,0.007) is statistically significant but modest, suggesting that attention to goal tokens is one of several factors in instruction compliance. Other factors likely include the model's procedural memory for format constraints, the specificity of the constraint (vague constraints are harder regardless of attention), and the interaction between constraint type and conversation topic. McNemar's test ($p$\\,=\\,0.077) is marginally significant for the overall compliance improvement, reflecting the small sample size (18 constraint types). These results are exploratory and pending multi-model confirmation.\n\nFigure~\\ref{fig:ir-bar} visualizes the per-category breakdown.\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_instruction_retention.pdf}\n  \\caption{Instruction retention by constraint category under $\\beta$\\,=\\,3 steering. Content constraints benefit most (+23.8\\,pp); format and count constraints are unaffected.}\n  \\label{fig:ir-bar}\n\\end{figure}\n\n\\FloatBarrier\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Instruction retention by constraint category ($\\beta$\\,=\\,3 steering on ThreadGate checkpoint). Content constraints benefit most from increased goal attention.}\n\\label{tab:ir-results}\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Category} & $\\beta$\\,=\\,0 & $\\beta$\\,=\\,3 & $\\Delta$ \\\\\n\\midrule\nContent    & 61.9\\% & 85.7\\% & +23.8\\,pp \\\\\nPosition   & 66.7\\% & 73.3\\% & +6.7\\,pp \\\\\nCount      & 100\\%  & 100\\%  & 0 \\\\\nFormat     & 100\\%  & 100\\%  & 0 \\\\\n\\midrule\n\\textbf{Overall} & 75.9\\% & 87.0\\% & +11.1\\,pp \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Long-Conversation AR Evaluation}\\label{sec:appendix-n5}\n\nThe main results (Table~\\ref{tab:five-way}) report AR GAR from $N$\\,=\\,50 held-out conversations with a mean of 3.6 user turns. Table~\\ref{tab:n5-ar} presents complementary results on $N$\\,=\\,5 conversations with 10 turns each, testing whether the observed patterns generalize beyond the training distribution's conversation length.\n\n\\paragraph{Gating advantage vanishes at length.} In these longer dialogues, the gating advantage observed in shorter conversations vanishes: all fine-tuned variants collapse to AR GAR-ours of 0.015--0.025, compared to 0.030--0.064 in the shorter evaluation. ThreadGate's advantage over LoRA-only shrinks from 1.7$\\times$ (0.064 vs.\\ 0.037 in the $N$\\,=\\,50 evaluation) to 0.64$\\times$ (0.016 vs.\\ 0.025), actually reversing the ordering. This reversal is not statistically robust given the small sample ($N$\\,=\\,5) but directionally suggests that architectural modifications provide diminishing returns as conversation length increases and exposure bias accumulates.\n\n\\paragraph{Convergence to base.} By turn~10, all fine-tuned variants converge to within 2$\\times$ of the base model's GAR, compared to 3.4$\\times$ at turn~1 in the shorter evaluation. This convergence is consistent with exposure bias compounding multiplicatively over turns: each model-generated turn introduces additional distributional drift from the teacher-forced training regime, and by turn~10 the accumulated drift overwhelms any gating or LoRA signal, leaving only the base model's intrinsic attention patterns.\n\n\\paragraph{Caveats.} The $N$\\,=\\,5 sample size limits statistical power, and the 10-turn conversations may differ systematically from the 3--5 turn training distribution in ways beyond length (e.g., topic complexity, user engagement patterns). We present these results as directional evidence rather than definitive conclusions.\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{AR GAR-ours on $N$\\,=\\,5 ten-turn conversations. The gating advantage observed in Table~\\ref{tab:five-way} ($N$\\,=\\,50, mean 3.6 turns) diminishes with conversation length.}\n\\label{tab:n5-ar}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Configuration} & \\textbf{AR GAR-O} & \\textbf{$\\Delta$ vs.\\ Table~\\ref{tab:five-way}} \\\\\n\\midrule\nBase & 0.012 & $-$0.007 \\\\\n\\midrule\nThreadGate & 0.016 & $-$0.048 \\\\\n\\;+\\,PCGrad & 0.015 & $-$0.015 \\\\\nUniform Gate & 0.015 & $-$0.018 \\\\\nLoRA-only & 0.025 & $-$0.012 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Statistical Test Details}\\label{sec:appendix-stats}\n\nAll statistical tests reported in the main text use non-parametric methods due to the non-normal, heavy-tailed distribution of per-conversation GAR values. Table~\\ref{tab:stat-tests} consolidates the full results.\n\n\\paragraph{Wilcoxon signed-rank tests.} We use paired Wilcoxon signed-rank tests for all pairwise configuration comparisons under AR evaluation, treating each conversation as a paired observation. The TG vs.\\ LoRA-only comparison ($p$\\,=\\,0.004, $r$\\,=\\,0.454) confirms that turn-conditioned gating provides a statistically significant but modest improvement. The TG vs.\\ +PCGrad comparison ($p$\\,=\\,0.002) shows that resolving gradient conflict is actively harmful. Gate turn conditioning uses an unpaired Wilcoxon test across 28 layers.\n\n\\paragraph{Bootstrap confidence intervals.} The 95\\% CIs in Table~\\ref{tab:five-way} are computed via 10,000 bootstrap resamples of per-conversation mid-turn GAR averages (turns 2--$T$), using the percentile method.\n\n\\paragraph{Effect sizes.} We report rank-biserial correlation $r = Z / \\sqrt{N}$ as the effect size for Wilcoxon tests, where $Z$ is the standardized test statistic and $N$ is the number of observations. By standard conventions: $r < 0.3$ is small, $0.3 \\leq r < 0.5$ is medium, and $r \\geq 0.5$ is large. The TG vs.\\ LoRA-only effect ($r$\\,=\\,0.454) is medium, and TG vs.\\ Base ($r$\\,=\\,0.802) is large.\n\n\\paragraph{Multiple comparisons.} We report uncorrected $p$-values throughout, as our comparisons are hypothesis-driven (each tests a specific causal exclusion) rather than exploratory. Applying Bonferroni correction to the 4 primary AR comparisons would adjust the significance threshold to 0.0125; all reported significant results ($p \\leq 0.004$) survive this correction.\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Consolidated statistical tests. All AR comparisons use $N$\\,=\\,50 conversations (39 with $\\geq$3 turns); gate conditioning uses 28 layers.}\n\\label{tab:stat-tests}\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Comparison} & \\textbf{Test} & $p$ & $r$ \\\\\n\\midrule\n\\multicolumn{4}{l}{\\emph{AR GAR-ours ($\\beta$\\,=\\,0)}} \\\\\nTG vs.\\ Base & Wilcoxon & $<$0.001 & 0.802 \\\\\nTG vs.\\ LoRA-only & Wilcoxon & 0.004 & 0.454 \\\\\nTG vs.\\ +PCGrad & Wilcoxon & 0.002 & --- \\\\\nSS vs.\\ TG & Wilcoxon & $<$0.001 & 0.869 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\emph{Gate conditioning (28 layers)}} \\\\\nTurn 1 vs.\\ Turn 21 & Wilcoxon & $3.7\\!\\times\\!10^{-8}$ & 0.975 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\emph{Instruction retention}} \\\\\n$\\beta$\\,=\\,0 vs.\\ $\\beta$\\,=\\,3 & McNemar & 0.077 & --- \\\\\nGAR--compliance & Pearson & 0.007 & 0.200 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Llama-3.1-8B Complete Results}\\label{sec:appendix-llama}\n\nTable~\\ref{tab:llama-full} presents the complete Llama-3.1-8B-Instruct results, complementing the summary in \\S\\ref{subsec:cross-model}. Three configurations were trained (Base, ThreadGate, LoRA-only) using the same training pipeline as Qwen-2.5-7B (8K UltraChat, 3 epochs, LoRA rank 16). Training required 7.0--7.3 hours per variant on the same GPU.\n\n\\paragraph{Teacher-forced evaluation.} TF GAR-ours is 0.484 (TG) and 0.481 (LoRA-only), confirming that gating provides zero benefit under teacher forcing on Llama, consistent with the Qwen results (0.50 vs.\\ 0.50).\n\n\\paragraph{Autoregressive evaluation.} AR evaluation uses $N$\\,=\\,20 mid-turn conversations (turns 3--$T$, excluding the first two turns to avoid initialization effects). The AR GAR distribution is heavy-tailed: the coefficient of variation exceeds 100\\% for ThreadGate (mean 0.043, std 0.100), and 5\\% of turn-level measurements exhibit sporadic attention spikes (GAR $\\geq$ 0.4). We therefore report both mean and median.\n\n\\paragraph{Gate profile.} Llama's gate profile differs qualitatively from Qwen's: Qwen shows minimum attenuation at early layers (L1\\,=\\,0.793, L5\\,=\\,0.797), while Llama shows a V-shaped valley at mid-to-late layers (L25\\,=\\,0.719, L24\\,=\\,0.809). Despite this architectural difference, both models converge toward identity under NTP pressure, and the TF-AR gap is comparable (27$\\times$ by median for Llama vs.\\ 8--17$\\times$ for Qwen).\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Llama-3.1-8B-Instruct complete results. TF: teacher-forced ($N$\\,=\\,50); AR: autoregressive ($N$\\,=\\,20 for Base/TG/LoRA-only, $N$\\,=\\,50 for SS). Median is more representative due to heavy-tailed AR distributions (SS uses mean only).}\n\\label{tab:llama-full}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n& \\multicolumn{2}{c}{\\textbf{TF}} & \\multicolumn{2}{c}{\\textbf{AR}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\n& GAR-O & PPL & GAR-O (mean) & GAR-O (med) \\\\\n\\midrule\nBase & 0.017 & 3.45 & 0.009 & 0.009 \\\\\nThreadGate & 0.484 & 2.57 & 0.043 & 0.018 \\\\\nLoRA-only & 0.481 & 2.60 & 0.028 & 0.018 \\\\\n\\textbf{SS} & 0.477 & 2.82 & \\textbf{0.166} & --- \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\FloatBarrier\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_crossmodel.pdf}\n  \\caption{Cross-architecture validation. (a)~The TF-AR gap persists on Llama-3.1-8B (27$\\times$ by median), exceeding Qwen's 8$\\times$. (b)~Gate profiles on normalized depth: Qwen dips at early layers, Llama at late layers; architecture-dependent patterns, but both converge toward identity.}\n  \\label{fig:crossmodel}\n\\end{figure}\n\n\\paragraph{Cross-model summary.} Table~\\ref{tab:crossmodel-detail} consolidates the cross-model comparison, showing TF GAR, AR GAR, PPL, and gap ratios side by side for both architectures. The consistent pattern---TF GAR $\\approx$ 0.5, AR GAR $\\ll$ 0.1, gap $\\geq$ 7.9$\\times$---across two architectures with different layer counts, attention head configurations, and pre-training corpora provides strong evidence that exposure bias is architecture-independent. Notably, Llama's larger gaps (27$\\times$ by median for TG; mean-based range 11.2--17.2$\\times$) compared to Qwen's (7.9--13.5$\\times$) may reflect its deeper architecture (32 vs.\\ 28 layers), which allows more layers for distributional drift to compound through.\n\n\\input{../artifacts/appendix_expansion/tab_crossmodel_detail.tex}\n\n\\paragraph{GAR-Dongre cross-model comparison.} GAR-Dongre shows negligible distribution shift on Llama (AR/TF ratio 1.002$\\times$), compared to 1.28$\\times$ on Qwen. This confirms the mechanism specificity finding: exposure bias selectively disrupts the concentrated last-token attention pattern (GAR-ours) while leaving the diffuse all-token attention (GAR-Dongre) unaffected across both architectures.\n\n\\paragraph{Training details.} Llama variants used the same pipeline as Qwen: 8K UltraChat conversations, LoRA rank 16 targeting $q$/$v$ projections, 3 epochs. Training loss converged to 0.929 (LoRA-only) and 0.934 (ThreadGate); the slight difference is attributable to the additional GAR loss component. Wall-clock time was 7.0h (LoRA-only) and 7.3h (ThreadGate), approximately 17\\% longer than Qwen due to Llama's larger layer count (32 vs.\\ 28 layers).\n\n\\paragraph{Phase 1 diagnostics.} Before fine-tuning, we confirmed that Llama exhibits the same goal attention decay as Qwen. Base model GAR decays from 0.026 (turn 1) to 0.003 (turn 10), a 90\\% decline. This is steeper than Qwen's 70.8\\% decline, suggesting that attention decay may be more severe in Llama's architecture despite its larger head count (32 vs.\\ 28 KV heads).\n\n\\paragraph{Cross-model gradient analysis.} Table~\\ref{tab:gradient-crossmodel} compares NTP--GAR gradient interaction between the two architectures. Both models exhibit near-orthogonal gradients (cosine similarity $\\approx$\\,0), not systematic conflict: Qwen shows a slight negative mean ($-$0.042) while Llama is marginally positive (+0.005). NTP gradients dominate GAR by 14.7$\\times$ on Qwen and 25.7$\\times$ on Llama, indicating that the auxiliary signal is overwhelmed by magnitude rather than opposed by direction. The cross-model consistency---near-zero cosine similarity and order-of-magnitude NTP dominance on both architectures---reinforces the \\emph{modus tollens} argument (\\S\\ref{subsec:pcgrad}): gradient direction conflict is not the primary cause of the TF-AR gap.\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Cross-model NTP--GAR gradient interaction. Gradients are near-orthogonal on both architectures; NTP magnitude dominates GAR by 15--26$\\times$.}\n\\label{tab:gradient-crossmodel}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Metric} & \\textbf{Qwen-7B} & \\textbf{Llama-8B} \\\\\n\\midrule\nMean cos sim & $-$0.042 & +0.005 \\\\\nNeg-layer \\% & 67.9\\% & 53.1\\% \\\\\nNTP/GAR mag ratio & 14.7$\\times$ & 25.7$\\times$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Additional Visualizations}\\label{sec:appendix-viz}\n\nThis section presents extended visualizations referenced in the main text. Each figure examines a different aspect of the gating behavior and its failure under autoregressive generation.\n\n\\subsection{Gate Profile Heatmap}\n\nFigure~\\ref{fig:gate-heatmap} shows the per-layer gate values across all training configurations for both Qwen-2.5-7B (28 layers) and Llama-3.1-8B (32 layers). The key observation is that early layers consistently receive the lowest gate values across all conditions, suggesting that these layers contribute more dispensable computations for the NTP objective. The pattern is remarkably consistent across ThreadGate, Uniform Gate, and PCGrad variants, indicating that gate-value allocation is driven primarily by the NTP loss landscape rather than the GAR auxiliary objective.\n\n\\begin{figure}[H]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_gate_profile_heatmap.pdf}\n\\caption{Per-layer gate values across training for Qwen-2.5-7B (28 layers $\\times$ 5 conditions) and Llama-3.1-8B (32 layers $\\times$ 1 condition). Early layers (L1, L4--5) consistently receive the lowest gate values across conditions.}\n\\label{fig:gate-heatmap}\n\\end{figure}\n\n\\subsection{Cross-Model Gate Profile Comparison}\n\nFigure~\\ref{fig:gate-crossmodel} compares gate profiles between the two architectures. Qwen-2.5-7B shows minimum gate values at early layers (L1\\,=\\,0.793, L5\\,=\\,0.797), suggesting these layers are most amenable to attenuation without disrupting NTP. Llama-3.1-8B instead shows a V-shaped valley at mid-to-late layers (L25\\,=\\,0.719), indicating that architecturally distinct models learn different layer-importance hierarchies. Both profiles converge toward identity at their respective final layers, consistent with NTP gradient pressure dominating gate optimization at output-adjacent layers.\n\n\\begin{figure}[H]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_gate_profile_crossmodel.pdf}\n\\caption{Side-by-side gate profiles for Qwen-2.5-7B and Llama-3.1-8B. Qwen dips at early layers (L1\\,=\\,0.793, L5\\,=\\,0.797), while Llama shows a V-shaped valley at mid-to-late layers (L25\\,=\\,0.719). Both models learn layer-selective gating but with architecture-dependent patterns.}\n\\label{fig:gate-crossmodel}\n\\end{figure}\n\n\\subsection{Per-Turn AR GAR Decay}\n\nFigure~\\ref{fig:ar-gar-perturn} visualizes the monotonic decay of GAR across conversation turns under autoregressive generation. Qwen base drops 85\\% from turn 1 to turn 10; Llama base drops 90\\%. The ThreadGate-trained model shows slight elevation in absolute GAR values but follows the same decay pattern, confirming that training-time GAR optimization does not alter the fundamental decay dynamic during generation. This per-turn view complements the aggregate TF-AR gap reported in Table~\\ref{tab:five-way}: the gap is not a fixed offset but grows with conversation length, consistent with cumulative exposure bias.\n\n\\begin{figure}[H]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_ar_gar_perturn.pdf}\n\\caption{GAR decays monotonically across turns under autoregressive generation. Qwen base drops 85\\% (turn 1$\\to$10), Llama base drops 90\\%. The ThreadGate-trained model (AR) shows slight elevation but the same decay pattern, confirming that training-time GAR optimization does not transfer to generation.}\n\\label{fig:ar-gar-perturn}\n\\end{figure}\n\n\\subsection{Bootstrap Confidence Intervals}\n\nFigure~\\ref{fig:bootstrap-ci} shows the bootstrap resampling distributions underlying the 95\\% CIs reported in Table~\\ref{tab:five-way}.\n\n\\begin{figure}[H]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_bootstrap_ci.pdf}\n  \\caption{Bootstrap CI distributions for AR GAR-ours (ThreadGate vs.\\ LoRA-only, $N$\\,=\\,50, 10K resamples). Distributions overlap substantially, consistent with the modest effect size ($r$\\,=\\,0.454).}\n  \\label{fig:bootstrap-ci}\n\\end{figure}\n\n\\subsection{Gate Value Distributions}\n\nFigure~\\ref{fig:gate-distribution} shows the full distribution of per-layer gate values for ThreadGate, Uniform Gate, and PCGrad variants. All three converge to similar distributions (mean $\\sim$0.94--0.96, concentrated between 0.9 and 1.0), confirming that the gating mechanism provides minimal modulation regardless of the specific variant. The distributions are right-skewed with a sharp cutoff at 1.0, reflecting NTP pressure pushing gates toward identity.\n\n\\begin{figure}[H]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_gate_distribution.pdf}\n\\caption{Per-layer gate value distributions for ThreadGate, Uniform Gate, and PCGrad variants. All three converge to similar distributions (mean $\\sim$0.94--0.96), confirming minimal modulation from the gating mechanism.}\n\\label{fig:gate-distribution}\n\\end{figure}\n\n\\subsection{Training Loss Curves}\n\nFigure~\\ref{fig:training-loss} shows the NTP, GAR, and total loss trajectories during training. GAR loss collapses to near-zero within the first epoch across all variants, indicating rapid convergence of the auxiliary objective under teacher forcing. NTP loss converges normally to ${\\sim}$0.93 by epoch 3. The fast GAR convergence is not itself pathological---it indicates successful optimization under the training distribution. The pathology emerges only at the transition to autoregressive generation, where the learned attention patterns fail to transfer.\n\n\\begin{figure}[H]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_training_loss_curves.pdf}\n\\caption{NTP, GAR, and total loss trajectories. GAR loss collapses to near-zero within the first epoch across all variants, while NTP loss converges normally.}\n\\label{fig:training-loss}\n\\end{figure}\n\n\\subsection{Full Attention Steering Results}\\label{sec:appendix-steering}\n\n\\begin{table*}[t]\n\\centering\\small\n\\caption{Full attention steering results across evaluation settings.\n\\textbf{Bold} indicates the operating point cited in the main text ($\\beta$\\,=\\,5).\nA visual gap separates the phase-transition boundary: GAR jumps sharply between $\\beta$\\,=\\,2 and $\\beta$\\,=\\,3 across all settings.}\n\\label{tab:steering-full}\n\\begin{tabular}{r cc cc cc}\n\\toprule\n & \\multicolumn{2}{c}{\\textbf{$N$\\,=\\,5, Gen}} & \\multicolumn{2}{c}{\\textbf{$N$\\,=\\,50, Gen}} & \\multicolumn{2}{c}{\\textbf{$N$\\,=\\,200, TF}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5} \\cmidrule(lr){6-7}\n$\\beta$ & GAR & PPL & GAR & PPL & GAR & PPL \\\\\n\\midrule\n0   & .028 & 1.41 & $.064 \\pm .081$ & $1.43 \\pm .10$ & .535 & 2.62 \\\\\n0.5 & .029 & 1.39 & ---             & ---             & ---  & ---  \\\\\n1   & .035 & 1.36 & ---             & ---             & ---  & ---  \\\\\n2   & .062 & 1.41 & $.128 \\pm .110$ & $1.48 \\pm .14$ & .611 & 2.69 \\\\\n\\addlinespace[3pt]\n3   & ---  & ---  & $.556 \\pm .060$ & $1.56 \\pm .17$ & .788 & 2.93 \\\\\n4   & ---  & ---  & $.644 \\pm .061$ & $1.67 \\pm .22$ & .817 & 3.49 \\\\\n\\textbf{5}  & \\textbf{.680} & \\textbf{1.91} & $\\mathbf{.727 \\pm .061}$ & $\\mathbf{1.77 \\pm .27}$ & \\textbf{.833} & \\textbf{6.15} \\\\\n10  & .959 & 4.22 & $.961 \\pm .015$ & $3.45 \\pm 1.78$ & .977 & 505.2 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_steering_standalone.pdf}\n  \\caption{Detailed $\\beta$-steering trade-off ($N$\\,=\\,50). GAR-ours (top) increases monotonically with $\\beta$; PPL (bottom) remains stable below $\\beta$\\,=\\,3 (9\\% cost), then rises sharply. The $\\beta$\\,=\\,3 operating point (circled) achieves 8.7$\\times$ GAR recovery while crossing the TF baseline, representing the optimal trade-off.}\n  \\label{fig:steering-standalone}\n\\end{figure}\n\n\\section{Per-Layer Gate Profile}\\label{sec:appendix-gate-profile}\n\nTable~\\ref{tab:gate-profile} reports the final per-layer gate values for ThreadGate (seed 123) on Qwen-2.5-7B-Instruct (28 layers). Gate values are averaged across all tokens in the evaluation set. Layers 1 and 5 show the lowest gate values (0.793 and 0.797), indicating these layers are most amenable to attenuation without disrupting NTP. Layers 26--27 converge to $\\geq$0.988, consistent with NTP gradient pressure dominating at output-adjacent layers. The mean across all layers is 0.947 ($\\sigma$\\,=\\,0.051).\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Per-layer gate values for ThreadGate (seed 123) on Qwen-2.5-7B-Instruct. Min values (L1, L5) in bold.}\n\\label{tab:gate-profile}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{cccccccc}\n\\toprule\nL0 & L1 & L2 & L3 & L4 & L5 & L6 & L7 \\\\\n.883 & \\textbf{.793} & .996 & .988 & .984 & \\textbf{.797} & .961 & .918 \\\\\n\\midrule\nL8 & L9 & L10 & L11 & L12 & L13 & L14 & L15 \\\\\n.965 & .934 & .969 & .918 & .926 & .941 & .930 & .965 \\\\\n\\midrule\nL16 & L17 & L18 & L19 & L20 & L21 & L22 & L23 \\\\\n.941 & .910 & .961 & .965 & .973 & .988 & .969 & .980 \\\\\n\\midrule\nL24 & L25 & L26 & L27 & \\multicolumn{4}{c}{Summary} \\\\\n.980 & .984 & .988 & 1.00 & \\multicolumn{4}{c}{$\\bar{g}$\\,=\\,.947, $\\sigma$\\,=\\,.051} \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nThe gate profile exhibits two notable patterns: (1)~a bimodal dip at L1 and L5, suggesting two distinct ``dispensable'' layer clusters in Qwen's architecture; (2)~monotonic increase from L17 to L27, indicating output-adjacent layers are progressively more critical for NTP. Seed 42 produces a similar profile (mean 0.934, min at L3--L5), confirming the pattern is not seed-dependent.\n\n\\paragraph{Cross-model comparison.} See \\S\\ref{sec:appendix-viz} for the full cross-model gate profile comparison (Figure~\\ref{fig:gate-crossmodel}). Llama-3.1-8B shows a qualitatively different profile---a V-shaped valley at mid-to-late layers rather than early-layer dips---suggesting architecture-dependent layer importance hierarchies.\n\n\\section{Scheduled Sampling Implementation}\\label{sec:appendix-ss}\n\nOur scheduled sampling implementation follows \\citet{bengio2015scheduled} with modifications for multi-turn transformer training:\n\n\\paragraph{Sampling schedule.} The model-generated context ratio $\\rho$ increases linearly from 0 to 0.3 over 3 epochs. At each training step, a Bernoulli trial with probability $\\rho$ determines whether the input prefix is replaced with model-generated tokens. The effective usage rate (29.7--37.1\\%) is lower than the nominal schedule due to per-sample Bernoulli variance.\n\n\\paragraph{Context generation.} When model-generated context is selected, the model autoregressively generates the assistant turns from the conversation prefix up to the current training position. The generated tokens replace the ground-truth assistant tokens in the input, while user turns remain unchanged. This preserves the multi-turn structure while introducing distributional diversity in the conditioning context.\n\n\\paragraph{Training dynamics.} The scheduled sampling variant converges to similar final loss (NTP 0.932 vs.\\ 0.930 for standard ThreadGate) but with higher variance in early epochs due to the stochastic context mixing (Figure~\\ref{fig:ss-dynamics}). Gate profiles remain similar (mean 0.953 vs.\\ 0.947, min at L4 vs.\\ L1), indicating that scheduled sampling does not fundamentally alter gate optimization but rather improves the robustness of the learned attention patterns to distributional shift. Training time increases by 8--80\\% across seeds (seed-dependent; dominated by GAR forward pass overhead): 6.5h (seed 42), 10.8h (seed 123), and 6.5h (seed 456) vs.\\ 6.0h for standard ThreadGate on Qwen. Seed 456 exhibits consistent training dynamics with seeds 42 and 123.\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_ss_training_dynamics.pdf}\n  \\caption{Scheduled sampling training dynamics: sampling ratio $\\rho$ ramps linearly from 0 to 0.3 (left axis); GAR loss (right axis) shows higher early-epoch variance due to stochastic context mixing.}\n  \\label{fig:ss-dynamics}\n\\end{figure}\n\n\\section{Computational Cost Analysis}\\label{sec:appendix-cost}\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Computational cost across training configurations. All experiments use a single NVIDIA RTX PRO 6000 (96\\,GB VRAM). VRAM reports peak allocated memory (excluding optimizer states).}\n\\label{tab:cost}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Config} & \\textbf{Params} & \\textbf{Time (h)} & \\textbf{VRAM} & \\textbf{Overhead} \\\\\n\\midrule\n\\multicolumn{5}{l}{\\emph{Qwen-2.5-7B-Instruct}} \\\\\nLoRA-only & 4.2M & 5.7 & 42\\,GB & baseline \\\\\nThreadGate & 4.3M & 6.0 & 43\\,GB & $+$57K \\\\\n\\;+\\,PCGrad & 4.3M & 8.0 & 43\\,GB & $+$33\\% \\\\\nUniform Gate & 4.3M & 6.0 & 43\\,GB & $+$57K \\\\\nSS (s42) & 4.3M & 6.5 & 43\\,GB & $+$8\\% \\\\\nSS (s123) & 4.3M & 10.8 & 43\\,GB & $+$80\\% \\\\\nSS (s456) & 4.3M & 6.5 & 43\\,GB & $+$8\\% \\\\\n\\midrule\n\\multicolumn{5}{l}{\\emph{Llama-3.1-8B-Instruct}} \\\\\nLoRA-only & 4.2M & 7.0 & 45\\,GB & baseline \\\\\nThreadGate & 4.3M & 7.3 & 46\\,GB & $+$65K \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Parameter overhead.} ThreadGate adds ${\\sim}$57K gate parameters for Qwen-2.5-7B (28 layers $\\times$ 2K per gate MLP) and ${\\sim}$65K for Llama-3.1-8B (32 layers), representing $<$0.001\\% of the base model. LoRA adapters (rank 16, targeting $q$/$v$ projections) contribute 4.2M parameters across both architectures.\n\n\\paragraph{Training time.} Standard variants (ThreadGate, Uniform Gate, LoRA-only) train in 5.7--7.3 hours. PCGrad adds ${\\sim}$33\\% overhead due to the per-step gradient projection computation. Scheduled sampling overhead varies: seed 42 adds only 8\\% (6.5h) due to efficient batched generation, while seed 123 adds 80\\% (10.8h) because of a longer generation schedule. The difference is due to the extended AR generation schedule in the seed 123 variant.\n\n\\paragraph{Inference overhead.} Gate computation at inference time is negligible: a single 32$\\to$64$\\to$1 MLP forward pass per layer adds $<$0.1\\% latency. $\\beta$-steering requires identifying goal tokens (a one-time operation per conversation) and adding a constant bias to attention logits, with zero additional parameters.\n\n\\section{Qualitative Steering Examples}\\label{sec:appendix-examples}\n\nTable~\\ref{tab:examples} illustrates the effect of $\\beta$-steering on model behavior in a 4-turn conversation where the system prompt instructs ``Always respond in exactly three bullet points.''\n\n\\begin{table*}[t]\n\\centering\\small\n\\caption{Qualitative effect of $\\beta$-steering on instruction following across conversation turns. System prompt: ``Always respond in exactly three bullet points.'' ThreadGate checkpoint, 4-turn conversation.}\n\\label{tab:examples}\n\\begin{tabular}{c p{5.5cm} p{5.5cm}}\n\\toprule\n\\textbf{Turn} & \\textbf{$\\beta$\\,=\\,0 (unsteered)} & \\textbf{$\\beta$\\,=\\,3 (steered)} \\\\\n\\midrule\n1 & \\checkmark~Three bullet points, on-topic & \\checkmark~Three bullet points, on-topic \\\\\n2 & \\checkmark~Three bullet points, relevant & \\checkmark~Three bullet points, relevant \\\\\n3 & $\\sim$~Four bullet points, partially on-topic & \\checkmark~Three bullet points, on-topic \\\\\n4 & \\texttimes~Free-form paragraph, no bullets & \\checkmark~Three bullet points, on-topic \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\nThe pattern is consistent with the GAR decay analysis (\\S\\ref{sec:analysis}): unsteered models progressively lose attention to the system-prompt constraint, leading to format violations at later turns. Steering maintains goal-token attention, preserving instruction compliance. The per-category breakdown in Table~\\ref{tab:ir-results} shows that content constraints benefit most from this effect.\n\n\\section{Gradient Conflict Analysis}\\label{sec:appendix-gradient}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth,height=0.42\\textheight,keepaspectratio]{fig2_training_pcgrad.pdf}\n  \\caption{(a)~Training GAR convergence to target ($\\tau$\\,=\\,0.5). (b)~PCGrad removes gradient conflict but $\\mathcal{L}_\\text{GAR}$ still collapses, confirming that gradient direction conflict is not the primary cause (\\S\\ref{subsec:pcgrad}).}\n  \\label{fig:training-pcgrad}\n\\end{figure}\n\nThis section provides extended gradient interaction analysis supporting the PCGrad exclusion argument in \\S\\ref{subsec:pcgrad}. We measure per-layer cosine similarity between NTP and GAR gradients, gradient magnitude ratios, and the effect of PCGrad projection on these quantities.\n\n\\paragraph{Gradient direction analysis.} Figure~\\ref{fig:gradient-heatmap} visualizes the per-layer cosine similarity between NTP and GAR gradients across training epochs for both standard ThreadGate and PCGrad training. Under standard training, 79\\% of layers show negative cosine similarity (gradient conflict) at epoch~0, declining to 68\\% by epoch~2 as GAR loss converges to near-zero. This decline reflects diminishing GAR gradient magnitude rather than alignment improvement---as GAR loss approaches zero, the GAR gradient shrinks proportionally, making cosine similarity measurements less reliable (small gradients produce noisy direction estimates). Under PCGrad training, the conflict percentage decreases more slowly (79\\%$\\to$71\\%), consistent with PCGrad projecting conflicting gradients onto the other's normal plane but not eliminating the underlying gradient conflict.\n\n\\paragraph{Spatial patterns.} The early layers (L0--L5) and output-adjacent layers (L24--L27) show the strongest conflict, corresponding to the layers where gate values deviate most from identity (Figure~\\ref{fig:gate-heatmap}). This spatial correlation is not causal: removing gradient conflict via PCGrad does not improve AR GAR, and gates at high-conflict layers are not systematically different from gates at low-conflict layers (Spearman $\\rho$\\,=\\,$-$0.12, $p$\\,=\\,0.54 between gate value and conflict magnitude).\n\n\\paragraph{Magnitude dominance.} NTP gradient magnitude dominates GAR by 7.5$\\times$ at epoch~0 and 14.7$\\times$ by epoch~2, as GAR loss converges while NTP loss remains at $\\sim$0.93. This growing dominance means that even when directions oppose, the effective update direction is determined almost entirely by NTP. PCGrad addresses gradient conflict but not magnitude dominance---it projects conflicting gradients onto the other's normal plane (changing direction) but preserves relative magnitudes. The 7.5--14.7$\\times$ magnitude ratio means that even after PCGrad projection, GAR contributes $<$7\\% of the effective update magnitude, explaining why PCGrad is ineffective.\n\n\\paragraph{Cross-model consistency.} Table~\\ref{tab:gradient-crossmodel} confirms the pattern on Llama-3.1-8B: gradients are near-orthogonal (mean cosine $+$0.005, essentially zero) rather than systematically conflicting, with 25.7$\\times$ NTP dominance. The Llama result is particularly informative because it shows that even without systematic gradient conflict (53\\% negative layers, near chance), the same TF-AR gap persists. This cross-model evidence strengthens the \\textit{modus tollens} argument: if gradient conflict were the cause, it should be present on both architectures; it is absent on Llama, yet the gap persists; therefore gradient direction conflict is not the primary cause.\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=0.95\\textwidth]{fig_gradient_conflict_heatmap.pdf}\n\\caption{Per-layer cosine similarity between NTP and GAR gradients across training epochs. (a)~Standard training: conflict decreases from 79\\% to 68\\% of layers as GAR loss vanishes. (b)~PCGrad training: projection reduces conflict more slowly (79\\%$\\to$71\\%) but does not improve AR GAR, ruling out gradient direction conflict as the primary cause (\\S\\ref{subsec:pcgrad}).}\n\\label{fig:gradient-heatmap}\n\\end{figure*}\n\n\\section{Training Data Characteristics}\\label{sec:appendix-data}\n\nAll experiments use 8,000 multi-turn conversations sampled from the UltraChat \\citep{ding2023ultrachat} training split. Table~\\ref{tab:data-stats} summarizes the dataset characteristics. Conversations are truncated to 2,048 tokens; conversations shorter than 3 user turns are excluded to ensure sufficient multi-turn structure for GAR computation. The held-out evaluation sets use separate non-overlapping samples: $N$\\,=\\,50 conversations (mean 3.6 user turns) for the primary AR evaluation and $N$\\,=\\,5 conversations (10 turns each) for the long-conversation analysis (Appendix~\\ref{sec:appendix-n5}).\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Training and evaluation data characteristics. All data from UltraChat \\citep{ding2023ultrachat}.}\n\\label{tab:data-stats}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Property} & \\textbf{Train} & \\textbf{Eval (primary)} \\\\\n\\midrule\nConversations & 8,000 & 50 \\\\\nMin user turns & 3 & 3 \\\\\nMax sequence length & 2,048 & 2,048 \\\\\nSource & UltraChat train & UltraChat train \\\\\nOverlap & --- & non-overlapping \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Exposure Bias Scaling}\\label{sec:appendix-eb-scaling}\n\nFigure~\\ref{fig:eb-scaling} quantifies two scaling dimensions of the exposure bias phenomenon: cross-variant gap ratios (panel~a) and length-dependent gap compounding (panel~b).\n\n\\paragraph{Cross-variant gaps.} On Qwen, ThreadGate achieves the smallest gap among standard variants (7.9$\\times$) while PCGrad shows the largest (16.7$\\times$, consistent with its counterproductive effect on AR GAR). Scheduled sampling reduces the gap to ${\\sim}$1.2$\\times$, the only variant approaching parity. The ordering of gap ratios (SS $\\ll$ TG $<$ LoRA $<$ UG $<$ PCGrad) differs from the ordering of TF GAR (all $\\approx$ 0.50), confirming that training-time optimization success does not predict inference-time robustness. On Llama, both ThreadGate and LoRA-only show $\\sim$27$\\times$ gaps (by median), larger than any Qwen variant. The consistently larger Llama gaps may reflect its deeper architecture (32 vs.\\ 28 layers), which provides more layers for distributional drift to compound through.\n\n\\paragraph{Length-dependent compounding.} Panel~(b) shows that the gap compounds with conversation length: at 3.6 mean turns ($N$\\,=\\,50), ThreadGate's gap is 8$\\times$; at 10 turns ($N$\\,=\\,5), it widens to 31$\\times$. The relationship is approximately linear in the number of turns on a log scale, suggesting that the per-turn drift contribution is roughly multiplicative. Extrapolating this trend suggests that at 20 turns the gap would exceed 100$\\times$, making any training-time attention signal essentially undetectable. This length dependence is consistent with cumulative distributional drift---each model-generated turn introduces additional divergence from the teacher-forced training distribution, and by turn~10 the accumulated drift overwhelms any gating signal.\n\n\\paragraph{Implications for deployment.} These scaling results have practical implications: (1)~for applications requiring sustained attention over many turns (e.g., long-form tutoring, multi-step reasoning), architectural modifications alone are insufficient---distributional robustification or inference-time intervention is necessary; (2)~the near-parity of scheduled sampling (${\\sim}$1.2$\\times$ gap) suggests that bridging the training-inference distribution gap is both necessary and sufficient for maintaining attention; (3)~the $\\beta$-steering approach provides a complementary inference-time solution, but its effectiveness also depends on conversation length (Appendix~\\ref{sec:appendix-steering-viz}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_eb_scaling.pdf}\n\\caption{Exposure bias scaling analysis. (a)~TF/AR gap ratio across training variants; scheduled sampling (SS, ${\\sim}$1.3$\\times$) is the only variant near parity. Llama gaps ($\\sim$27$\\times$) exceed all Qwen variants. (b)~Gap compounds with conversation length: ThreadGate's gap widens from 8$\\times$ (3.6 turns) to 31$\\times$ (10 turns).}\n\\label{fig:eb-scaling}\n\\end{figure}\n\n\\section{Per-Turn AR GAR Dynamics}\\label{sec:appendix-ar-gar-dynamics}\n\nTo characterize how goal attention evolves across conversation turns under autoregressive generation, we compute per-turn AR GAR for all six Qwen-2.5-7B training configurations (Base, LoRA-only, Uniform Gate, PCGrad, Scheduled Sampling, ThreadGate) on the held-out evaluation set. Figure~\\ref{fig:kl_ar_gar_curves} plots per-turn AR GAR trajectories across turns 1--5, and Figure~\\ref{fig:kl_ar_gar_bar} compares mid-turn AR GAR levels across configurations.\n\nAll six configurations exhibit monotonic GAR decay as turn index increases, consistent with cumulative exposure bias eroding attention to goal tokens. The decay rate varies substantially: Scheduled Sampling retains by far the highest mid-turn GAR (0.423), followed distantly by ThreadGate (0.064), LoRA-only (0.037), Uniform Gate (0.033), PCGrad (0.030), and Base (0.019). Base decays most rapidly, losing the majority of its initial GAR within the first few turns. The large SS--TG gap mirrors Table~\\ref{tab:five-way} and confirms that distributional robustification---not gating architecture alone---is the primary driver of AR GAR retention.\\footnote{SS configuration uses seed 123 data; all other configurations use seed 42. Cross-seed trends are consistent (\\S\\ref{subsec:ss}).}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_kl_ar_gar_curves.pdf}\n\\caption{Per-turn AR GAR trajectories for six Qwen-2.5-7B configurations (turns 1--5). All models show monotonic decay; Scheduled Sampling retains far higher GAR throughout (0.53$\\to$0.39), while the remaining five variants cluster below 0.13 and decay rapidly.}\n\\label{fig:kl_ar_gar_curves}\n\\end{figure}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_kl_ar_gar_bar.pdf}\n\\caption{Mid-turn AR GAR comparison across six training configurations. Ranking from highest to lowest: Scheduled Sampling (0.423), ThreadGate (0.064), LoRA-only (0.037), Uniform Gate (0.033), PCGrad (0.030), Base (0.019).}\n\\label{fig:kl_ar_gar_bar}\n\\end{figure}\n\nThis pattern contrasts with teacher-forced evaluation, where GAR remains relatively stable across turns for all configurations. Under teacher forcing, the model conditions on ground-truth context at each turn, preventing the distributional drift that causes GAR erosion in AR mode. The divergence between TF stability and AR decay provides turn-level evidence for the exposure bias mechanism described in \\S\\ref{sec:analysis}: training-time attention patterns are optimized for a distribution that AR generation progressively departs from.\n\n\\section{Per-Head KL Divergence Analysis}\\label{sec:appendix-kl}\n\nTo test whether exposure bias selectively disrupts goal-attending heads rather than uniformly affecting all attention patterns, we compute per-head TF vs.\\ AR attention divergence on 30 held-out conversations. For each of the 28 attention heads per layer (784 heads total), we measure the KL divergence $D_\\text{KL}(p_\\text{TF} \\| p_\\text{AR})$ between teacher-forced and autoregressive attention distributions, and the absolute GAR shift $\\Delta\\text{GAR} = |\\text{GAR}_\\text{TF} - \\text{GAR}_\\text{AR}|$. This head-level analysis provides diagnostic evidence for the exposure bias interpretation beyond the aggregate TF-AR gap.\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Per-head TF-AR divergence statistics for Base and ThreadGate (Qwen-2.5-7B, 30 conversations). TG trains more concentrated goal attention under TF, but these high-GAR heads shift most under AR ($r$\\,=\\,0.743).}\n\\label{tab:kl-perhead}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Metric} & \\textbf{Base} & \\textbf{TG} \\\\\n\\midrule\nMean $\\Delta$GAR & 0.012 & 0.016 \\\\\nMean KL & 0.043 & 0.054 \\\\\nCorr(TF\\_GAR, $\\Delta$GAR) & 0.673 & 0.743 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Selective disruption.} ThreadGate exhibits 35\\% larger mean $\\Delta$GAR (0.016 vs.\\ 0.012) and 26\\% larger mean KL (0.054 vs.\\ 0.043) than Base. This is counterintuitive: the auxiliary GAR loss successfully trains more concentrated goal attention (higher TF GAR per head), but these very same heads shift more under AR generation. The correlation between per-head TF GAR and $\\Delta$GAR is strong for both models ($r$\\,=\\,0.673 for Base, 0.743 for TG), confirming that heads with higher goal attention under teacher forcing are disproportionately disrupted under autoregressive generation. This selectivity is a hallmark of exposure bias: the training-time optimization succeeds at creating a specific attention pattern (concentrated goal attention), but precisely this pattern has no autoregressive counterpart because it depends on conditioning on ground-truth context.\n\n\\paragraph{Layer-depth dependence.} The highest-KL heads concentrate at output-adjacent layers (L23--L27, KL\\,$>$\\,0.077) and L9 (KL\\,$\\approx$\\,0.068). Output-adjacent layers participate most directly in next-token prediction, so their attention distributions are most sensitive to changes in the conditioning context. L9's elevated KL may reflect a ``routing layer'' phenomenon observed in multi-layer transformers, where specific intermediate layers specialize in long-range information routing. The depth dependence is consistent with cumulative error propagation: distributional drift from model-generated tokens accumulates as information flows through successive layers, producing the largest attention shifts at the deepest layers.\n\n\\paragraph{Gate--KL independence.} Gate magnitude does not predict per-layer exposure bias severity: Spearman correlation between gate value and per-layer KL is 0.061 ($p$\\,=\\,0.757). The highest KL values concentrate at deep layers (L22--L27) where gates are near identity ($\\approx$1.0), while the lowest-gate layers show below-average KL (0.041 vs.\\ 0.056 for highest-gate layers). This independence confirms that the gating mechanism and the exposure bias phenomenon operate on different axes: gates modulate the magnitude of residual contributions, while exposure bias disrupts the direction (attention distribution) of those contributions. Even a ``perfect'' gate that could fully attenuate certain layers' residuals would not address the fundamental distributional mismatch that causes the attention shift.\n\n\\section{GAR Definition Robustness}\\label{sec:appendix-gar-robust}\n\nTo assess whether our conclusions depend on the specific GAR definition, we evaluate four alternative token-position variants on 50 held-out conversations (Table~\\ref{tab:gar-robust}): (1)~\\emph{ours} (last-token): attention from the last token to goal tokens (standard GAR-ours); (2)~\\emph{all-token}: average attention from all tokens to goal tokens; (3)~\\emph{first-token}: attention from the first assistant token to goal tokens; (4)~\\emph{goal-only}: attention from the last token to system-prompt-only tokens (excluding conversation content).\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Mid-turn GAR under four alternative definitions ($N$\\,=\\,50 conversations). ThreadGate only improves query-position-specific definitions (last-token, goal-only); Scheduled Sampling raises all four definitions above 0.36.}\n\\label{tab:gar-robust}\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Definition} & \\textbf{Base} & \\textbf{TG} & \\textbf{SS} \\\\\n\\midrule\nOurs (last-token) & 0.015 & \\textbf{0.325} & \\textbf{0.458} \\\\\nAll-token & 0.015 & 0.025 & \\textbf{0.366} \\\\\nFirst-token & 0.022 & 0.039 & \\textbf{0.412} \\\\\nGoal-only & 0.005 & \\textbf{0.310} & \\textbf{0.444} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThreadGate improvements are query-position-specific: the two definitions using the last token as query (ours: $0.015 \\to 0.325$; goal-only: $0.005 \\to 0.310$) show large gains, while all-token ($0.025$) and first-token ($0.039$) remain near base levels. This is expected: the GAR loss optimizes attention at the last-token position, so the learned routing does not generalize to other query positions.\n\nScheduled Sampling raises all four definitions above 0.36, with no definition falling below Base-relative gains. This confirms that SS builds a broad goal-attention pattern across token positions, rather than overfitting to the specific position targeted by the GAR loss. The pattern holds regardless of GAR definition: both the exposure bias diagnosis and the SS mitigation are robust to metric choice.\n\n\\section{General Capability Preservation (MMLU)}\\label{sec:appendix-mmlu}\n\nTo confirm that auxiliary GAR losses and attention steering do not degrade general language understanding, we evaluate all six Qwen-2.5-7B variants on MMLU 5-shot \\citep{hendrycks2021measuring} ($N$\\,=\\,14{,}042 questions).\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{MMLU 5-shot accuracy on Qwen-2.5-7B-Instruct. All fine-tuned variants remain within 0.8\\,pp of the base LoRA-only checkpoint.}\n\\label{tab:mmlu}\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Model} & \\textbf{Acc (\\%)} & \\textbf{$\\Delta$ vs Base} \\\\\n\\midrule\nBase (pretrained) & 74.23 & --- \\\\\nPCGrad & 73.86 & $-$0.38 \\\\\nSS & 73.75 & $-$0.48 \\\\\nLoRA-only & 73.57 & $-$0.66 \\\\\nThreadGate & 73.47 & $-$0.77 \\\\\nUniform Gate & 73.46 & $-$0.78 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll variants degrade by $<$0.8\\,pp, confirming that attention steering and auxiliary GAR losses do not harm general language understanding. The ordering does not track GAR performance (e.g., PCGrad shows the smallest MMLU drop despite the worst AR GAR), consistent with GAR and NTP occupying largely orthogonal subspaces.\n\n\\section{Cross-Scale Validation (Qwen-2.5-1.5B)}\\label{sec:appendix-1.5b}\n\nWe validate cross-scale on Qwen-2.5-1.5B-Instruct to test whether goal attention decay and $\\beta$-steering generalize to smaller models.\n\n\\paragraph{Phase~1 GAR decay.} The 1.5B base model exhibits 79.8\\% GAR decline from turn~1 to mid-turns (vs.\\ 70.8\\% on 7B), confirming that attention decay is present across scales and is more severe at smaller model sizes.\n\n\\paragraph{Steering evaluation.} Table~\\ref{tab:1.5b-steering} reports AR evaluation ($N$\\,=\\,50). We report median PPL because Base $\\beta$\\,=\\,3 contains a catastrophic outlier (conversation~\\#11, PPL\\,$>$\\,$10^8$) that inflates the mean.\\footnote{The outlier occurs in a single conversation where $\\beta$-steering causes the base model to enter a degenerate repetition loop. ThreadGate produces zero such outliers across all $\\beta$ values, suggesting the gate provides stability against catastrophic steering failures.}\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{Cross-scale $\\beta$-steering on Qwen-2.5-1.5B ($N$\\,=\\,50, AR). PPL is median due to catastrophic Base outlier at $\\beta$\\,=\\,3. TG eliminates outliers across all $\\beta$ values.}\n\\label{tab:1.5b-steering}\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Model} & $\\beta$ & \\textbf{AR GAR} & \\textbf{PPL (med)} \\\\\n\\midrule\nBase & 0 & 0.017 & 1.909 \\\\\nTG & 0 & 0.023 & 1.897 \\\\\n\\midrule\nBase & 3 & 0.120 & 2.216 \\\\\nTG & 3 & 0.114 & 1.975 \\\\\n\\midrule\nBase & 5 & 0.657 & 2.804 \\\\\nTG & 5 & 0.715 & 2.624 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe steering pattern mirrors the 7B results: $\\beta$\\,=\\,5 recovers GAR to 0.657--0.715 ($p < 0.001$), confirming that attention misallocation is the proximal cause of GAR collapse across scales. At $\\beta$\\,=\\,0, TG shows a small but significant GAR advantage ($p$\\,=\\,0.005); at $\\beta$\\,=\\,3, the TG--Base difference is not statistically significant ($p$\\,=\\,0.815), unlike the 7B pattern where TG consistently outperforms Base. This scale-specific difference may reflect the 1.5B model's limited capacity to maintain learned routing at intermediate steering strengths. ThreadGate does provide a stability advantage---zero catastrophic PPL outliers vs.\\ one in Base---suggesting that residual gating regularizes attention distributions even when aggregate GAR is comparable.\n\n\\section{Per-Seed Detailed Results}\\label{sec:appendix-perseed}\n\nTables~\\ref{tab:perseed-ss} and~\\ref{tab:perseed-tg} report full per-seed breakdowns for the two multi-seed configurations, providing evidence that our main findings are robust to random initialization.\n\n\\paragraph{Scheduled sampling (3 seeds).} TF GAR-ours averages $0.517\\pm0.032$ across seeds under the held-out protocol (Table~\\ref{tab:perseed-ss}); under IID evaluation, TF is more stable ($0.499\\pm0.003$), with the held-out variance driven by seed~123's higher value on the larger $N$\\,=\\,200 sample. AR GAR shows meaningful variance (std\\,=\\,0.047): seed 42 produces the lowest AR GAR (0.347, gap 1.4$\\times$), seed 123 is intermediate (0.423, gap 1.3$\\times$), and seed 456 is highest (0.433, gap 1.2$\\times$). This variance is expected: AR evaluation involves free-form generation where small differences in learned attention patterns can compound across turns. The variance is asymmetric---all seeds remain well above the non-SS baseline (0.064)---so the qualitative conclusion (SS provides order-of-magnitude improvement) holds across seeds. At $\\beta$\\,=\\,5, the cross-seed variance nearly vanishes ($0.717\\pm0.001$), confirming that strong steering converges to a seed-independent attention equilibrium that overwhelms initialization differences.\n\n\\paragraph{ThreadGate (2 seeds).} Two seeds produce nearly identical TF metrics ($0.504\\pm0.001$) and similar AR GAR (0.064 vs.\\ 0.055), with gap ratios of 7.9$\\times$ and 9.1$\\times$ respectively. The 15\\% relative difference in AR GAR is small compared to the order-of-magnitude TF-AR gap, confirming that the exposure bias phenomenon is not seed-dependent.\n\n\\paragraph{Training dynamics.} Seed variance in training time is non-trivial for scheduled sampling: seed 123 requires 10.8 hours (80\\% overhead) vs.\\ 6.5 hours for seeds 42 and 456 (8\\% overhead). This variance is driven by the stochastic Bernoulli sampling of model-generated contexts: seed 123 happens to trigger longer autoregressive generation episodes early in training, where the model produces longer outputs before hitting the max-length cutoff. Despite this training-time variance, all three seeds converge to similar final metrics, suggesting the optimization landscape is robust.\n\n\\input{../artifacts/appendix_expansion/tab_perseed_ss.tex}\n\n\\input{../artifacts/appendix_expansion/tab_perseed_tg.tex}\n\n\\section{Per-Turn GAR Decay Analysis}\\label{sec:appendix-perturn-detail}\n\nTables~\\ref{tab:perturn-qwen} and~\\ref{tab:perturn-llama} present per-turn AR GAR values for all configurations on both architectures, complementing the aggregate mid-turn GAR reported in the main text (Table~\\ref{tab:five-way}).\n\n\\paragraph{Qwen per-turn dynamics.} On Qwen (Table~\\ref{tab:perturn-qwen}), all non-SS variants show rapid monotonic decay: turn-1 GAR ranges from 0.085 (Base) to 0.130 (ThreadGate), but by turn~5 all collapse below 0.07. The decay rate is approximately exponential for the first 3 turns, then plateaus near a floor value that varies by configuration (Base: 0.004, ThreadGate: 0.043--0.066, LoRA-only: 0.040). ThreadGate and LoRA-only show occasional turn-level fluctuations (e.g., TG turn~5 = 0.066 $>$ turn~4 = 0.043), which reflect stochastic variation in individual conversations rather than systematic recovery. Scheduled sampling retains substantially higher GAR throughout (turn-5 GAR\\,=\\,0.365 vs.\\ 0.066 for ThreadGate), with a much flatter decay profile (15\\% decline from turn~1 to turn~5 vs.\\ 49\\% for ThreadGate). This flatter profile is the signature of distributional robustification: SS-trained models encounter model-generated context during training, so the attention patterns are calibrated for the distribution they actually face during inference.\n\n\\paragraph{Llama per-turn dynamics.} On Llama (Table~\\ref{tab:perturn-llama}), the decay is steeper: Base GAR drops from 0.028 to 0.008 over 4 turns (71\\% decline in the $N$\\,=\\,20 evaluation), and from 0.026 to 0.003 over 10 turns (88\\% decline in the $N$\\,=\\,5 long-conversation evaluation). ThreadGate on Llama shows a distinctive pattern: turn-level GAR is roughly constant (0.038--0.049) rather than monotonically declining, suggesting that the gating mechanism maintains a stable floor on Llama that it fails to maintain on Qwen. However, this floor (0.04) is still an order of magnitude below the TF target (0.484), confirming that the fundamental TF-AR gap persists.\n\n\\paragraph{Cross-architecture comparison.} The per-turn decay profiles reveal an architectural difference: Qwen shows a sharper initial decline (turn~1 to turn~2: $-$62\\% for Base) followed by a plateau, while Llama shows a more gradual and sustained decline throughout. This difference may reflect the two architectures' different attention head configurations and layer counts, but the qualitative pattern---monotonic or near-monotonic decline toward a near-zero floor---is universal.\n\nFigures~\\ref{fig:perturn-qwen-detail} and~\\ref{fig:perturn-llama-detail} visualize these trajectories.\n\n\\input{../artifacts/appendix_expansion/tab_perturn_qwen.tex}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_perturn_qwen_detail.pdf}\n  \\caption{Per-turn AR GAR-ours across six Qwen-2.5-7B configurations. Scheduled sampling (green) retains far higher GAR than all other variants, which cluster below 0.13 and decay rapidly.}\n  \\label{fig:perturn-qwen-detail}\n\\end{figure}\n\n\\input{../artifacts/appendix_expansion/tab_perturn_llama.tex}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_perturn_llama_detail.pdf}\n  \\caption{Per-turn AR GAR decay on Llama-3.1-8B. (a)~Three-way comparison (Base, TG, LoRA-only; $N$\\,=\\,20, 4 turns). (b)~Extended Base decay profile ($N$\\,=\\,5, 10 turns), showing 90\\% decline.}\n  \\label{fig:perturn-llama-detail}\n\\end{figure}\n\n\\section{Extended Dataset Statistics}\\label{sec:appendix-dataset-ext}\n\nTable~\\ref{tab:dataset_stats} provides detailed statistics for the UltraChat training and evaluation splits. From the full UltraChat-200K corpus (207,865 conversations in the \\texttt{train\\_sft} split), we filter for conversations with $\\geq$5 assistant turns, yielding 17,302 candidates (8.3\\% of the full corpus). We randomly sample 8,000 for training, 50 for primary AR evaluation (mean 3.6 user turns), 50 for IID GAR diagnostics, and 200 for the instruction retention evaluation.\n\n\\paragraph{Filtering rationale.} The $\\geq$5 assistant turns threshold was chosen empirically: conversations with fewer than 3 assistant turns do not exhibit measurable attention decay (turn-1 to turn-3 GAR decline $<$5\\%), making them uninformative for studying multi-turn exposure bias. The 5-turn threshold provides sufficient turn depth while retaining a reasonable fraction of the corpus. The average conversation in the filtered set contains 5.6 assistant turns (range: 5--7), with a mean sequence length of 1,247 tokens after tokenization with the Qwen-2.5 tokenizer.\n\n\\paragraph{Evaluation split design.} We maintain four non-overlapping evaluation sets to avoid contamination: (1)~the primary AR evaluation ($N$\\,=\\,50) uses the same conversation structure as training but with held-out conversations, enabling direct comparison of TF vs.\\ AR behavior; (2)~the IID GAR diagnostic ($N$\\,=\\,50) uses a separate sample for ablation studies that require independent measurements; (3)~the large instruction retention set ($N$\\,=\\,200) provides sufficient statistical power for per-category compliance analysis across 18 constraint types; (4)~the long-conversation set ($N$\\,=\\,5, 10 turns each) tests scaling behavior beyond the training distribution.\n\n\\paragraph{Domain diversity.} UltraChat covers a broad range of conversational topics including knowledge Q\\&A, creative writing, reasoning, and open-ended discussion. We do not stratify by topic, as our focus is on the architectural mechanism (attention routing) rather than domain-specific performance. The topic diversity serves as implicit regularization against overfitting to specific conversation patterns.\n\n\\input{../artifacts/appendix_expansion/tab_dataset_stats.tex}\n\n\\section{Extended GAR Robustness Analysis}\\label{sec:appendix-gar-ext}\n\nTable~\\ref{tab:gar_robustness} and Figure~\\ref{fig:gar-robust-grouped} extend the GAR robustness analysis from \\S\\ref{sec:appendix-gar-robust} with turn-1 GAR and gap ratio metrics across all four token-position variants. We evaluate four ways to select the query token position for gradient attribution: (1)~\\textit{Last} (our default): the final token of each assistant turn, which captures the model's ``summary'' attention pattern at the prediction boundary; (2)~\\textit{All}: the mean over all assistant tokens, providing a position-averaged view; (3)~\\textit{First}: the first assistant token, which reflects initial attention allocation; (4)~\\textit{Goal-only}: attention to goal tokens as defined by \\citet{dongre2026attention}, which restricts the target set to system-prompt tokens.\n\n\\paragraph{Position-specific vs.\\ broad improvement.} The key finding is a clear dichotomy between ThreadGate and Scheduled Sampling. ThreadGate improvements are restricted to last-token and goal-only positions (the two definitions sharing the query position targeted by the GAR loss): gap ratios drop to 1.21$\\times$ and 1.07$\\times$ respectively. All-token (5.04$\\times$) and first-token (8.24$\\times$) GAR remain near base levels, confirming that the learned routing is position-specific. Scheduled Sampling raises all four definitions above 0.36 with gap ratios $\\leq$1.83$\\times$, demonstrating that distributional robustification builds broad goal attention across token positions rather than overfitting to the position targeted by the loss.\n\n\\paragraph{Turn-1 vs.\\ mid-turn dynamics.} Turn-1 GAR is consistently higher than mid-turn GAR across all definitions and conditions, reflecting the first turn's proximity to the ground-truth prefix in training. The gap ratio quantifies how much of this initial attention survives into later turns. First-token GAR shows the largest gap ratios (Base: 13.3$\\times$, TG: 8.2$\\times$), indicating that the first-token position is most vulnerable to distributional drift---the initial token's attention pattern is highly dependent on the conditioning context, which diverges most from training under autoregressive generation.\n\n\\input{../artifacts/appendix_expansion/tab_gar_robustness.tex}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_gar_robustness_grouped.pdf}\n  \\caption{Mid-turn GAR across four token-position definitions. SS raises all four above 0.36; TG only improves last-token and goal-only.}\n  \\label{fig:gar-robust-grouped}\n\\end{figure}\n\n\\section{MMLU Category Breakdown}\\label{sec:appendix-mmlu-ext}\n\nTable~\\ref{tab:mmlu_detail} breaks down MMLU 5-shot accuracy by category (STEM, Social Sciences, Humanities, Other) for all six Qwen-2.5-7B training configurations. This analysis addresses a potential concern: that auxiliary attention objectives might divert representational capacity from general language understanding, particularly in knowledge-intensive STEM domains.\n\n\\paragraph{Per-category analysis.} The maximum per-category degradation is 1.5\\,pp (ThreadGate on STEM), and no category shows systematic degradation across all variants. Notably, the ordering of variants differs across categories: ThreadGate shows the largest STEM drop but the smallest Humanities drop, while PCGrad shows the smallest overall drop despite having the worst AR GAR. This lack of correlation between GAR performance and MMLU degradation is consistent with GAR and NTP occupying largely orthogonal parameter subspaces---the LoRA adapter capacity (4.2M parameters) is sufficient to accommodate both objectives without interference.\n\n\\paragraph{Statistical significance.} The per-category differences are small relative to the evaluation noise: with $N$\\,=\\,14,042 questions total ($\\sim$3,500 per category), a 0.8\\,pp accuracy difference corresponds to $\\sim$28 questions, well within expected stochastic variation for 5-shot in-context learning. A chi-squared test comparing the best (PCGrad, 73.86\\%) and worst (Uniform Gate, 73.46\\%) variants yields $p$\\,=\\,0.503, confirming no significant difference. The category-level stability confirms that auxiliary GAR losses and gating do not selectively harm any knowledge domain.\n\nFigure~\\ref{fig:mmlu-comparison} visualizes the per-category comparison, showing tight clustering across all variants within each category.\n\n\\input{../artifacts/appendix_expansion/tab_mmlu_detail.tex}\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_mmlu_comparison.pdf}\n  \\caption{MMLU 5-shot accuracy by category across training configurations. All variants remain within 1.5\\,pp of the LoRA-only baseline across all categories.}\n  \\label{fig:mmlu-comparison}\n\\end{figure}\n\n\\section{Extended Cross-Scale Results (Qwen-2.5-1.5B)}\\label{sec:appendix-1.5b-ext}\n\nTable~\\ref{tab:qwen15b_results} extends the cross-scale analysis with Phase~1 GAR diagnostics, detailed Phase~2 training results, and $\\beta$-steering evaluation on the Qwen-2.5-1.5B-Instruct model.\n\n\\paragraph{Phase 1: GAR decay.} The 1.5B base model exhibits 79.8\\% relative GAR decline from turn~1 to mid-turns, more severe than the 7B model's 70.8\\% decline. This scale-dependent decay severity is consistent with smaller models having less redundant attention capacity: with 28 layers but only 1.5B parameters (vs.\\ 7B), each layer carries proportionally more of the total representational burden, leaving less room for goal-oriented attention to persist alongside the primary NTP objective.\n\n\\paragraph{Phase 2: Training.} ThreadGate training on 1.5B converges to TF GAR-ours of 0.498 with PPL of 2.67, closely matching the 7B results (0.504 / 2.78). The gate parameter count scales linearly with layer count (identical architecture, so ${\\sim}$57K gate parameters). Training completes in 2.1 hours vs.\\ 6.0 hours for 7B, reflecting the smaller model's reduced forward/backward pass cost.\n\n\\paragraph{Steering evaluation.} At $\\beta$\\,=\\,5, ThreadGate recovers GAR to 0.715 ($p < 0.001$), closely matching the 7B result (0.727). The recovery is essentially scale-independent at the strong steering regime: the attention bias added by $\\beta$-steering overwhelms any capacity differences. At $\\beta$\\,=\\,3, the picture differs: the TG--Base difference is not statistically significant ($p$\\,=\\,0.815) on 1.5B, unlike the significant difference on 7B ($p$\\,=\\,0.039). This scale-dependent response at intermediate $\\beta$ may reflect the 1.5B model's reduced capacity for fine-grained attention routing: with fewer parameters per layer, the model cannot sustain the subtle attention reweighting that $\\beta$\\,=\\,3 attempts.\n\n\\paragraph{Catastrophic outliers.} Base 1.5B at $\\beta$\\,=\\,3 produces one catastrophic PPL outlier (conversation \\#11, PPL $> 10^8$) caused by a degenerate repetition loop. ThreadGate produces zero such outliers across all $\\beta$ values, suggesting the gate provides a stabilizing effect on attention distributions even when aggregate GAR is comparable. We report median PPL to avoid this outlier dominating the central tendency estimate.\n\n\\input{../artifacts/appendix_expansion/tab_qwen15b_results.tex}\n\n\\section{Extended Statistical Analysis}\\label{sec:appendix-stats-ext}\n\nTable~\\ref{tab:statistical_tests} consolidates all statistical tests reported in this paper, including effect sizes, 95\\% bootstrap confidence intervals, and significance levels. This section provides methodological detail beyond the summary in Appendix~\\ref{sec:appendix-stats}.\n\n\\paragraph{Test selection rationale.} All primary comparisons use paired Wilcoxon signed-rank tests on $N$\\,=\\,39 conversations (those with $\\geq$3 turns from the 50-conversation held-out set). We use non-parametric tests because per-conversation GAR distributions are heavily right-skewed (skewness $>$ 2.0 for Base and PCGrad at $\\beta$\\,=\\,0), violating normality assumptions required by parametric alternatives. The pairing structure (same conversations evaluated under different training configurations) controls for conversation-level confounds (topic difficulty, conversation length, system-prompt complexity).\n\n\\paragraph{Effect size interpretation.} Effect sizes are computed as rank-biserial correlations ($r = Z / \\sqrt{N}$), following standard practice. The largest effect is SS vs.\\ TG ($r$\\,=\\,0.869, $p < 0.001$), a large effect by conventional thresholds ($r \\geq 0.5$), confirming that scheduled sampling produces a qualitatively different outcome. The TG vs.\\ Base effect ($r$\\,=\\,0.802) is also large, while TG vs.\\ LoRA-only ($r$\\,=\\,0.454) is medium, reflecting the modest incremental benefit of gating over LoRA alone.\n\n\\paragraph{Steering dose-response pattern.} At $\\beta$\\,=\\,0, all four comparisons are significant ($p \\leq 0.004$). At $\\beta$\\,=\\,3 (the phase transition), TG vs.\\ Base becomes marginally significant ($p$\\,=\\,0.039) and SS vs.\\ TG remains significant ($p$\\,=\\,0.010), but TG vs.\\ LoRA-only and PCGrad vs.\\ TG lose significance ($p > 0.7$). At $\\beta$\\,=\\,5, no pairwise comparison reaches significance---steering dominates and equalizes all variants. This dose-response pattern confirms that the training-time variant effects are real but small relative to the inference-time steering effect.\n\n\\paragraph{Instruction retention.} The instruction retention analysis uses McNemar's test on $N$\\,=\\,54 paired constraint evaluations (18 constraint types $\\times$ 3 conversations). The marginal significance ($p$\\,=\\,0.077) reflects the small sample size rather than a null effect: the point-biserial correlation ($r$\\,=\\,0.200, $p$\\,=\\,0.007) is significant when treating compliance as a continuous variable, and the per-category breakdown (Table~\\ref{tab:ir-results}) shows a clear content-constraint improvement (+23.8\\,pp).\n\n\\paragraph{Multiple comparisons.} We report uncorrected $p$-values for the same reason described in Appendix~\\ref{sec:appendix-stats}: comparisons are hypothesis-driven (each tests a specific causal exclusion in the analysis chain), not exploratory. All reported significant results ($p \\leq 0.039$) survive Holm-Bonferroni correction for the 4 primary comparisons within each $\\beta$ level.\n\n\\input{../artifacts/appendix_expansion/tab_statistical_tests.tex}\n\n\\section{Extended Training Dynamics}\\label{sec:appendix-training-ext}\n\nFigure~\\ref{fig:training-6panel} presents the complete training loss landscape for all five Qwen-2.5-7B conditions (ThreadGate, +PCGrad, Uniform Gate, LoRA-only, Scheduled Sampling) plus the base model, showing NTP loss, GAR loss, and total loss across three epochs.\n\n\\paragraph{NTP loss convergence.} All fine-tuned variants converge to NTP loss ${\\sim}$0.93 by epoch~3, with final-epoch values ranging from 0.929 (LoRA-only) to 0.934 (ThreadGate). PCGrad shows marginally higher variance due to gradient projection, but converges to the same terminal value. The uniformity of NTP convergence across variants---including those with auxiliary losses (ThreadGate, PCGrad) and those without (LoRA-only)---confirms that the GAR auxiliary objective does not interfere with the primary language modeling task during training.\n\n\\paragraph{GAR loss dynamics.} GAR loss collapses to near-zero within the first epoch under teacher forcing across all variants, consistent with the auxiliary objective being easy to optimize when the model conditions on ground-truth context. This rapid convergence is a double-edged sword: while it confirms that the MSE formulation (v7) achieves stable optimization, the ease of convergence also means the model never learns to maintain attention under distributional drift. The scheduled sampling variant shows distinctive dynamics: higher initial GAR loss variance from stochastic context mixing, with occasional spikes when a particularly challenging model-generated context is sampled, followed by convergence to a similar final value.\n\n\\paragraph{Training-inference disconnect.} The key observation is that training-time convergence is indistinguishable across variants: an observer with access only to training curves could not predict the 5.4$\\times$ AR GAR difference between SS and TG. This disconnect reinforces the diagnosis that the failure occurs at the training-to-inference transition, not during optimization, and explains why architectural modifications (gating, PCGrad) that operate during training cannot address the fundamental distributional mismatch.\n\n\\begin{figure*}[t]\n  \\centering\n  \\includegraphics[width=0.75\\textwidth]{fig_training_curves_6panel.pdf}\n  \\caption{Training loss curves for all five Qwen conditions. NTP loss (left) converges to ${\\sim}$0.93 across variants; GAR loss (center) collapses within epoch~1; total loss (right) is NTP-dominated. Training-time behavior is indistinguishable; the failure emerges only at inference.}\n  \\label{fig:training-6panel}\n\\end{figure*}\n\n\\section{Per-$\\beta$ Steering Visualization}\\label{sec:appendix-steering-viz}\n\nFigure~\\ref{fig:steering-4panel} visualizes per-turn GAR trajectories under four steering strengths ($\\beta$\\,=\\,0, 3, 5, 10), revealing the turn-level dynamics that underlie the aggregate steering results in Table~\\ref{tab:steering-full}.\n\n\\paragraph{Unsteered baseline ($\\beta$\\,=\\,0).} GAR decays monotonically from 0.12 to 0.02 over five turns, with the steepest decline between turns~1 and~2 ($-$44\\%). This trajectory matches the per-turn profiles in Appendix~\\ref{sec:appendix-perturn-detail} and confirms that the decay is a smooth, progressive phenomenon rather than a discrete failure at a specific turn.\n\n\\paragraph{Phase transition ($\\beta$\\,=\\,3).} Turn-1 GAR jumps to ${\\sim}$0.55, but per-turn decay persists (${\\sim}$15\\% decline from turn~1 to turn~5). This indicates that steering partially compensates for the distributional drift but does not eliminate it: the attention bias adds a constant offset to goal-token logits, while the drift compounds multiplicatively across turns. The residual decay at $\\beta$\\,=\\,3 explains why this operating point shows the strongest training-variant effects in the dose-response analysis (Appendix~\\ref{sec:appendix-stats-ext}).\n\n\\paragraph{Sustained recovery ($\\beta$\\,=\\,5).} GAR is sustained above 0.6 throughout, with minimal per-turn decay ($<$5\\% decline). At this steering strength, the constant attention bias dominates the per-turn drift, effectively replacing the lost training-time signal with an inference-time substitute. The 9\\% PPL cost (1.43 $\\to$ 1.77) is modest compared to the order-of-magnitude GAR recovery.\n\n\\paragraph{Saturation regime ($\\beta$\\,=\\,10).} GAR saturates near 1.0 across all turns but PPL degrades catastrophically ($>$3.5), as the excessive attention bias distorts the attention distribution beyond the model's capacity for coherent generation. This regime is impractical and serves as an upper bound on the steering approach.\n\n\\paragraph{Operating region.} The region $\\beta \\in [3, 5]$ balances GAR recovery against PPL cost, and the per-turn profiles confirm that steering must counteract an ongoing distributional drift rather than a one-time initialization failure---a key diagnostic that distinguishes exposure bias from alternative hypotheses (e.g., capacity limitations or optimization failures).\n\n\\begin{figure}[t]\n  \\centering\n  \\includegraphics[width=\\columnwidth]{fig_steering_perturn_4panel.pdf}\n  \\caption{Per-turn GAR under four $\\beta$-steering strengths. At $\\beta$\\,=\\,0, monotonic decay; at $\\beta$\\,=\\,3, partial recovery with residual decay; at $\\beta$\\,=\\,5, sustained high GAR; at $\\beta$\\,=\\,10, saturation with catastrophic PPL.}\n  \\label{fig:steering-4panel}\n\\end{figure}\n\n\\section{Llama-3.1-8B Scheduled Sampling Details}\\label{sec:appendix-llama-ss}\n\nLlama-3.1-8B-Instruct was trained with scheduled sampling using the same protocol as Qwen (\\S\\ref{sec:appendix-ss}), with one key difference: training was stopped at 2 epochs (${\\sim}$14{,}400 steps) instead of 3, because Llama's per-step wall-clock time was ${\\sim}$4$\\times$ slower than Qwen on the same hardware (624 steps/h vs.\\ ${\\sim}$2{,}400 steps/h for Qwen). This is attributable to different vocabulary sizes (Llama 128K vs.\\ Qwen 152K tokens) and attention implementation. The 2-epoch checkpoint was selected based on convergence of TF GAR (0.477, within 0.02 of Qwen's 3-epoch value 0.498).\n\n\\paragraph{$\\beta$-steering on Llama SS.}\nTable~\\ref{tab:llama-ss-steering} reports $\\beta$-steering results on the Llama SS model. Unlike Qwen, $\\beta$\\,=\\,3 does not trigger recovery on Llama (GAR 0.173 vs.\\ 0.166 at $\\beta$\\,=\\,0). At $\\beta$\\,=\\,5, GAR reaches 0.791---higher than Qwen's 0.717---suggesting that Llama's attention distribution is more responsive to the additive bias at higher steering strengths, possibly because the lower baseline AR GAR leaves more headroom for steering to exploit.\n\n\\begin{table}[t]\n\\centering\\small\n\\caption{$\\beta$-steering on Llama-3.1-8B SS model ($N$\\,=\\,50, $T$\\,=\\,4).}\n\\label{tab:llama-ss-steering}\n\\begin{tabular}{@{}l ccc@{}}\n\\toprule\n& $\\beta$\\,=\\,0 & $\\beta$\\,=\\,3 & $\\beta$\\,=\\,5 \\\\\n\\midrule\nAR GAR & 0.166 & 0.173 & 0.791 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cross-model comparison.}\nTable~\\ref{tab:llama-vs-qwen-ss} compares scheduled sampling across both architectures. Both models show large gap compression relative to their ThreadGate baselines, but the residual gap on Llama (2.9$\\times$) is larger than Qwen's (1.2$\\times$). We attribute this to training duration: Llama received only 2 epochs of scheduled sampling exposure versus Qwen's 3 epochs. Llama reduces its median-based gap by 9.3$\\times$ (from 27$\\times$ to 2.9$\\times$) while Qwen reduces by 6.6$\\times$ (from 7.9$\\times$ to 1.2$\\times$), suggesting that a third epoch would likely narrow the residual gap further. Notably, $\\beta$-steering is more effective on Llama (0.791 vs.\\ 0.717 at $\\beta$\\,=\\,5), partially compensating for the weaker training-time compression.\n\n\\paragraph{Architectural differences.}\nSeveral architectural differences between Qwen-2.5-7B and Llama-3.1-8B may contribute to the cross-model gap variation. Llama uses Grouped Query Attention (GQA) with 8 KV heads (vs.\\ Qwen's full 28-head multi-head attention, MHA), which reduces the number of independently steerable attention heads by 3.5$\\times$. Llama also uses Rotary Position Embedding (RoPE) with a longer default context (128K tokens vs.\\ Qwen's 32K), which may affect how positional information interacts with goal-token attention at different conversation depths. Despite these differences, the qualitative pattern is identical: TF convergence, AR collapse, and SS-mediated recovery, confirming that exposure bias on auxiliary attention losses is architecture-general rather than an artifact of a specific attention implementation.\n\n\\paragraph{Training dynamics.}\nThe Llama SS training loss trajectory closely mirrors Qwen's during the first two epochs: NTP loss converges within epoch~1 (final NTP loss 0.62 for Llama vs.\\ 0.58 for Qwen), while GAR loss continues to decrease throughout epoch~2. The scheduled sampling ratio reaches ${\\sim}$0.20 at the end of epoch~2 (vs.\\ 0.30 at end of epoch~3 for Qwen), meaning Llama was exposed to less model-generated context during training. This partial exposure is sufficient to achieve meaningful gap compression (27$\\times$ $\\to$ 2.9$\\times$ by median) but leaves a larger residual gap than Qwen's full 3-epoch schedule.\n\n\\begin{table}[t]\n\\raggedright\\small\n\\caption{Scheduled sampling comparison: Qwen-2.5-7B vs.\\ Llama-3.1-8B.}\n\\label{tab:llama-vs-qwen-ss}\n\\begin{tabular}{@{}l cc@{}}\n\\toprule\n\\textbf{Metric} & \\textbf{Qwen-7B} & \\textbf{Llama-8B} \\\\\n\\midrule\nSS epochs & 3 & 2 \\\\\nTF GAR & 0.498 & 0.477 \\\\\nAR GAR ($\\beta$\\,=\\,0) & 0.401 & 0.166 \\\\\nTF/AR gap & 1.2$\\times$ & 2.9$\\times$ \\\\\nBaseline TG gap & 7.9$\\times$ & 27$\\times$ (median) \\\\\nGap compression & 6.6$\\times$ & 9.3$\\times$ \\\\\nAR GAR ($\\beta$\\,=\\,5) & 0.717 & 0.791 \\\\\nTF PPL & 2.78 & 2.82 \\\\\nAR PPL & 1.441 & 1.370 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Use of AI Assistants}\\label{sec:appendix-ai}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant\nthroughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing\n    pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections,\n    polishing prose, and reformatting LaTeX.\n    \\item \\textbf{Literature:} summarizing related papers to inform\n    related-work section.\n\\end{itemize}\n",
    "structuredPatch": [
      {
        "oldStart": 497,
        "oldLines": 7,
        "newStart": 497,
        "newLines": 7,
        "lines": [
          " \\begin{figure}[t]",
          " \\centering",
          " \\includegraphics[width=\\columnwidth]{fig_eb_scaling.pdf}",
          "-\\caption{Exposure bias scaling analysis. (a)~TF/AR gap ratio across training variants; scheduled sampling (SS, ${\\sim}$1.3$\\times$) is the only variant near parity. Llama gaps ($\\sim$27$\\times$) exceed all Qwen variants. (b)~Gap compounds with conversation length: ThreadGate's gap widens from 8$\\times$ (3.6 turns) to 31$\\times$ (10 turns).}",
          "+\\caption{Exposure bias scaling analysis. (a)~TF/AR gap ratio across training variants; scheduled sampling (SS, ${\\sim}$1.2$\\times$) is the only variant near parity. Llama gaps ($\\sim$27$\\times$) exceed all Qwen variants. (b)~Gap compounds with conversation length: ThreadGate's gap widens from 8$\\times$ (3.6 turns) to 31$\\times$ (10 turns).}",
          " \\label{fig:eb-scaling}",
          " \\end{figure}",
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


### Tool call

_source line 133_

<details open><summary>🔧 Tool call — Edit · `toolu_01W4Q2Q6MPjL7Ti3ZD5aLPFm`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/introduction.tex",
  "old_string": "compressing the TF--AR gap to ${\\sim}$1.3$\\times$ on Qwen",
  "new_string": "compressing the TF--AR gap to ${\\sim}$1.2$\\times$ on Qwen"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "3a066f39-e220-496a-82bc-4d6543dcee92",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U6YJeUEnxob2yKRkCoKyWd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2259,
      "cache_read_input_tokens": 67220,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2259
      },
      "output_tokens": 10,
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

_source line 134 · 2026-05-25T20:41:12.325Z_

<details><summary>↩ Tool result · `toolu_01W4Q2Q6MPjL7Ti3ZD5aLPFm`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/introduction.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "a1324973-6e24-4502-b167-4798a7770986",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/introduction.tex",
    "oldString": "compressing the TF--AR gap to ${\\sim}$1.3$\\times$ on Qwen",
    "newString": "compressing the TF--AR gap to ${\\sim}$1.2$\\times$ on Qwen",
    "originalFile": "\\section{Introduction}\\label{sec:introduction}\n\nMulti-turn dialogue is central to how large language models are deployed, from customer service to tutoring to long-form reasoning. Yet a persistent failure accompanies even the most fluent generation: as conversations grow longer, models pay progressively less attention to the system-prompt goals that define their task. \\citet{dongre2026attention} measured significant Goal Accessibility Ratio (GAR) decline across 12 models over extended conversations; in our own evaluation, goal attention drops by over 70\\% within just five turns. Crucially, this is not a representation problem: residual stream probes confirm that goal information persists (AUC\\,=\\,0.98). The model retains the knowledge of what it should attend to; it simply stops attending.\n\nExisting remedies address this decay at inference time. Split-softmax \\citep{li2024measuring} separates instruction from conversation tokens; StreamingLLM \\citep{xiao2024streaming} retains anchor tokens; Gated Attention \\citep{qiu2025gated} applies per-head sigmoid gates within a single forward pass. A natural alternative is to intervene during training: optimize goal attention directly through auxiliary losses trained alongside next-token prediction (NTP). Yet this strategy rests on an untested assumption: attention patterns learned under teacher forcing (TF) transfer to autoregressive (AR) generation. Classical exposure bias research \\citep{bengio2015scheduled,lamb2016professor} has shown that TF creates a training--inference distribution mismatch for RNN sequence models, but whether this mismatch extends to auxiliary attention objectives in multi-turn transformers remains unknown.\n\nWe test this assumption and find it fails. We introduce a controlled five-way testbed (ThreadGate, +PCGrad, Uniform Gate, LoRA-only, and Base) designed not as competing solutions but as a causal exclusion chain (\\S\\ref{sec:comparison-design}), where each adjacent pair isolates one candidate failure mechanism. The result is unambiguous: every variant converges to target GAR under teacher forcing, yet goal attention collapses by an order of magnitude once the model generates its own context (Figure~\\ref{fig:headline}). The exclusion chain traces this collapse to exposure bias, the training--inference distribution mismatch, ruling out gradient direction conflict (PCGrad removes conflict yet \\emph{worsens} AR GAR), gating mechanism (Uniform Gate matches ThreadGate), and parameter capacity (LoRA-only shows the same pattern). Inference-time $\\beta$-steering confirms that the collapse reflects attention misallocation rather than representation degradation; scheduled sampling bridges the gap by exposing the model to its own generations during training.\n\n\\begin{figure*}[!ht]\n  \\centering\n  \\includegraphics[width=\\textwidth]{fig1_headline.pdf}\n  \\caption{Exposure bias collapses auxiliary attention losses. \\textbf{(a)}~Goal attention decays 85--90\\% across turns under AR generation on both Qwen-2.5-7B and Llama-3.1-8B. \\textbf{(b)}~Under TF evaluation all variants reach GAR$\\approx$0.50, but AR generation collapses GAR by 8--17$\\times$ (log scale). \\textbf{(c)}~Scheduled sampling compresses the TF--AR gap from 7.9$\\times$ to 1.2$\\times$ (Qwen) and ${\\sim}$27$\\times$ to 2.9$\\times$ (Llama).}\n  \\label{fig:headline}\n\\end{figure*}\n\nOur contributions are:\n\\begin{enumerate}\\raggedright\n    \\item \\textbf{Exposure bias characterization.} To our knowledge, the first empirical demonstration that exposure bias collapses auxiliary attention objectives in multi-turn transformers, with an order-of-magnitude TF--AR gap reproduced across two architectures (Qwen-2.5-7B, Llama-3.1-8B) and model scales (1.5B--8B).\n    \\item \\textbf{Causal exclusion testbed.} A five-way diagnostic design, informed by seven loss-formulation iterations, that isolates the failure mechanism via causal exclusion, including a PCGrad \\emph{modus tollens} argument ruling out gradient direction conflict ($p$\\,=\\,0.002, effect reverses).\n    \\item \\textbf{Attention misallocation diagnosis.} Inference-time $\\beta$-steering recovers goal attention with modest perplexity cost, evidence that the collapse is an attention routing failure, not a representational one.\n    \\item \\textbf{Scheduled sampling as remedy.} The first application of scheduled sampling to auxiliary attention objectives in multi-turn transformers, compressing the TF--AR gap to ${\\sim}$1.3$\\times$ on Qwen and ${\\sim}$2.9$\\times$ on Llama with no perplexity degradation, robust across three seeds.\n\\end{enumerate}\n",
    "structuredPatch": [
      {
        "oldStart": 18,
        "oldLines": 5,
        "newStart": 18,
        "newLines": 5,
        "lines": [
          "     \\item \\textbf{Exposure bias characterization.} To our knowledge, the first empirical demonstration that exposure bias collapses auxiliary attention objectives in multi-turn transformers, with an order-of-magnitude TF--AR gap reproduced across two architectures (Qwen-2.5-7B, Llama-3.1-8B) and model scales (1.5B--8B).",
          "     \\item \\textbf{Causal exclusion testbed.} A five-way diagnostic design, informed by seven loss-formulation iterations, that isolates the failure mechanism via causal exclusion, including a PCGrad \\emph{modus tollens} argument ruling out gradient direction conflict ($p$\\,=\\,0.002, effect reverses).",
          "     \\item \\textbf{Attention misallocation diagnosis.} Inference-time $\\beta$-steering recovers goal attention with modest perplexity cost, evidence that the collapse is an attention routing failure, not a representational one.",
          "-    \\item \\textbf{Scheduled sampling as remedy.} The first application of scheduled sampling to auxiliary attention objectives in multi-turn transformers, compressing the TF--AR gap to ${\\sim}$1.3$\\times$ on Qwen and ${\\sim}$2.9$\\times$ on Llama with no perplexity degradation, robust across three seeds.",
          "+    \\item \\textbf{Scheduled sampling as remedy.} The first application of scheduled sampling to auxiliary attention objectives in multi-turn transformers, compressing the TF--AR gap to ${\\sim}$1.2$\\times$ on Qwen and ${\\sim}$2.9$\\times$ on Llama with no perplexity degradation, robust across three seeds.",
          " \\end{enumerate}"
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


### Tool call

_source line 135_

<details open><summary>🔧 Tool call — Edit · `toolu_01KGa9LLiQxXDQmbXqLfFPPR`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/conclusion.tex",
  "old_string": "Scheduled sampling compresses the gap to ${\\sim}$1.3$\\times$ (Qwen)",
  "new_string": "Scheduled sampling compresses the gap to ${\\sim}$1.2$\\times$ (Qwen)"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "89587ae5-1497-41b0-899e-336044f426c8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U6YJeUEnxob2yKRkCoKyWd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2259,
      "cache_read_input_tokens": 67220,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2259
      },
      "output_tokens": 10,
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

_source line 136 · 2026-05-25T20:41:13.315Z_

<details><summary>↩ Tool result · `toolu_01KGa9LLiQxXDQmbXqLfFPPR`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/conclusion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "6bac5377-7300-46f1-ae3f-2a6470598723",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections/conclusion.tex",
    "oldString": "Scheduled sampling compresses the gap to ${\\sim}$1.3$\\times$ (Qwen)",
    "newString": "Scheduled sampling compresses the gap to ${\\sim}$1.2$\\times$ (Qwen)",
    "originalFile": "\\section{Conclusion}\\label{sec:conclusion}\n\n\\looseness=-1 Auxiliary attention losses converge under teacher forcing (GAR\\,=\\,0.50) but collapse by an order of magnitude under autoregressive generation on two architectures. A five-way diagnostic comparison identifies exposure bias as a primary contributing factor; $\\beta$-steering recovers GAR above the TF baseline, consistent with attention misallocation as a proximal cause (KV cache drift remains untested). Scheduled sampling compresses the gap to ${\\sim}$1.3$\\times$ (Qwen) and ${\\sim}$2.9$\\times$ (Llama), generalizing across architectures and seeds; to our knowledge, the first such transfer to auxiliary attention objectives in multi-turn transformers.\n",
    "structuredPatch": [
      {
        "oldStart": 1,
        "oldLines": 3,
        "newStart": 1,
        "newLines": 3,
        "lines": [
          " \\section{Conclusion}\\label{sec:conclusion}",
          " ",
          "-\\looseness=-1 Auxiliary attention losses converge under teacher forcing (GAR\\,=\\,0.50) but collapse by an order of magnitude under autoregressive generation on two architectures. A five-way diagnostic comparison identifies exposure bias as a primary contributing factor; $\\beta$-steering recovers GAR above the TF baseline, consistent with attention misallocation as a proximal cause (KV cache drift remains untested). Scheduled sampling compresses the gap to ${\\sim}$1.3$\\times$ (Qwen) and ${\\sim}$2.9$\\times$ (Llama), generalizing across architectures and seeds; to our knowledge, the first such transfer to auxiliary attention objectives in multi-turn transformers.",
          "+\\looseness=-1 Auxiliary attention losses converge under teacher forcing (GAR\\,=\\,0.50) but collapse by an order of magnitude under autoregressive generation on two architectures. A five-way diagnostic comparison identifies exposure bias as a primary contributing factor; $\\beta$-steering recovers GAR above the TF baseline, consistent with attention misallocation as a proximal cause (KV cache drift remains untested). Scheduled sampling compresses the gap to ${\\sim}$1.2$\\times$ (Qwen) and ${\\sim}$2.9$\\times$ (Llama), generalizing across architectures and seeds; to our knowledge, the first such transfer to auxiliary attention objectives in multi-turn transformers."
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

_source line 137_

Now let me do a final sweep to catch any remaining stale values:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "3dac6802-5e2e-4edf-b6c5-37cbdf33fc72",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CFEXa9BydhXfbk8mwLzXmP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1199,
      "cache_read_input_tokens": 69479,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1199
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

_source line 138_

<details open><summary>🔧 Tool call — Grep · `toolu_01Geay1CqRcdH8HtjjYKXFRn`</summary>

```json
{
  "pattern": "1\\.3.\\\\times",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "c3f8f16d-b5aa-452f-a63b-0ea1658ec5ad",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CFEXa9BydhXfbk8mwLzXmP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1199,
      "cache_read_input_tokens": 69479,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1199
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

_source line 139 · 2026-05-25T20:41:17.052Z_

<details><summary>↩ Tool result · `toolu_01Geay1CqRcdH8HtjjYKXFRn`</summary>

```text
paper/sections/discussion.tex:3:[Omitted long matching line]
paper/sections/appendix.tex:633:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "287b8572-c27e-451a-a25e-21d4a48d198b",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "paper/sections/discussion.tex:3:[Omitted long matching line]\npaper/sections/appendix.tex:633:[Omitted long matching line]",
    "numLines": 2
  }
}
```

</details>

---


### Tool call

_source line 140_

<details open><summary>🔧 Tool call — Grep · `toolu_01MwnAqAK5MSEmjiMGZYpZTh`</summary>

```json
{
  "pattern": "7\\.8",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/paper/sections",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "14651b0d-303d-45aa-ad10-43cb301466ab",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CFEXa9BydhXfbk8mwLzXmP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1199,
      "cache_read_input_tokens": 69479,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1199
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

_source line 141 · 2026-05-25T20:41:18.038Z_

<details><summary>↩ Tool result · `toolu_01MwnAqAK5MSEmjiMGZYpZTh`</summary>

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
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "eefa1920-f8c5-40c1-a225-4c6c39c6c8b8",
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

_source line 142_

The remaining 1.3× occurrences are:
- `discussion.tex:3` — "${\leq}$1.3$\times$" for GAR-Dongre shift (different metric, correct as-is)
- `appendix.tex:633` — per-seed values "gap 1.3$\times$" (individual seed data, correct as-is)

Both are unrelated to the SS aggregate gap. All edits complete. Summary:

| # | Issue | File(s) | Fix |
|---|-------|---------|-----|
| 1 | Table 1 IID column | related_work.tex | TG: 0.50→0.49, 2.78→2.63; UG: 2.78→2.62; LoRA: 0.50→0.49, 2.78→2.63 |
| 2 | Gap ratio 7.8×→7.9× | experiments/intro/appendix | All 7.8× → 7.9× (6 locations) |
| 3 | SS gap ~1.3×→~1.2× | experiments/analysis/intro/conclusion/appendix | All ~1.3× → ~1.2× (8 locations) |
| 4 | ≤1pp→≤2pp | experiments.tex | "$\leq$1\,pp" → "$\leq$2\,pp"; also "PPL is 2.78 for all" → "PPL is 2.62--2.78" |
| 5 | MMLU max degradation | appendix.tex | 1.2pp → 1.5pp (text + figure caption) |
| 6 | "Base (LoRA-only)" label | appendix.tex | → "Base (pretrained)" |
| 7 | SS ρ_max 0.5→0.3 | appendix.tex | intro paragraph fixed |
| 8 | SS PPL std | experiments.tex | 0.001 → 0.002 |
| 9 | Llama VRAM caption | appendix.tex | Added "VRAM reports peak allocated memory (excluding optimizer states)." |
| 10 | LoRA-only training time | appendix.tex | 6.0h → 5.7h (table + paragraph range) |

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "uuid": "f4fea1b5-fecb-4d89-943b-e3597819d58b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01N9YwM8TYUqws3yjetSSJYo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 382,
      "cache_read_input_tokens": 70678,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 382
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

_source line 143_

The remaining 1.3× occurrences are:
- `discussion.tex:3` — "${\leq}$1.3$\times$" for GAR-Dongre shift (different metric, correct as-is)
- `appendix.tex:633` — per-seed values "gap 1.3$\times$" (individual seed data, correct as-is)

Both are unrelated to the SS aggregate gap. All edits complete. Summary:

| # | Issue | File(s) | Fix |
|---|-------|---------|-----|
| 1 | Table 1 IID column | related_work.tex | TG: 0.50→0.49, 2.78→2.63; UG: 2.78→2.62; LoRA: 0.50→0.49, 2.78→2.63 |
| 2 | Gap ratio 7.8×→7.9× | experiments/intro/appendix | All 7.8× → 7.9× (6 locations) |
| 3 | SS gap ~1.3×→~1.2× | experiments/analysis/intro/conclusion/appendix | All ~1.3× → ~1.2× (8 locations) |
| 4 | ≤1pp→≤2pp | experiments.tex | "$\leq$1\,pp" → "$\leq$2\,pp"; also "PPL is 2.78 for all" → "PPL is 2.62--2.78" |
| 5 | MMLU max degradation | appendix.tex | 1.2pp → 1.5pp (text + figure caption) |
| 6 | "Base (LoRA-only)" label | appendix.tex | → "Base (pretrained)" |
| 7 | SS ρ_max 0.5→0.3 | appendix.tex | intro paragraph fixed |
| 8 | SS PPL std | experiments.tex | 0.001 → 0.002 |
| 9 | Llama VRAM caption | appendix.tex | Added "VRAM reports peak allocated memory (excluding optimizer states)." |
| 10 | LoRA-only training time | appendix.tex | 6.0h → 5.7h (table + paragraph range) |

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 362190,
  "duration_api_ms": 363040,
  "num_turns": 59,
  "stop_reason": "end_turn",
  "session_id": "58041882-0719-4816-9243-ca5845e8faf2",
  "total_cost_usd": 1.51532175,
  "usage": {
    "input_tokens": 1895,
    "cache_creation_input_tokens": 59613,
    "cache_read_input_tokens": 1212617,
    "output_tokens": 20984,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 59613,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 567,
        "cache_read_input_tokens": 70678,
        "cache_creation_input_tokens": 382,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 382
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2277,
      "outputTokens": 16,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.0023569999999999997,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 1895,
      "outputTokens": 20984,
      "cacheReadInputTokens": 1212617,
      "cacheCreationInputTokens": 59613,
      "webSearchRequests": 0,
      "costUSD": 1.51296475,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "5d1ad73f-a00f-4894-9a6f-a815626622eb"
}
```

</details>

---
