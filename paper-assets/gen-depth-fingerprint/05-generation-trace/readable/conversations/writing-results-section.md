# writing results section

**Depth Profiling: Classifying Recursive Generation Depth in Base-Model LLM Text** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 15
- **Recorded user turns:** 0
- **Tool calls:** 7
- **Original source:** `logs/chats/worker_writing_results-section_20260515T043424.jsonl`
- **Structured JSON:** [`570671e0349ee33d46fd.json`](../../sessions/57/570671e0349ee33d46fd.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

15 recorded events

### Tool call

_source line 1 · 2026-05-15T04:38:46.118954+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__register_artifact",
  "max_results": "4"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__register_artifact",
    "max_results": "4"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-15T04:38:46.119392+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-15T04:38:46.123569+00:00_

called mcp__agent-ml-research__read_registry

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry</summary>

```json
{
  "project": "gen-depth-fingerprint",
  "limit": "0"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "mcp__agent-ml-research__read_registry",
  "tool_args": {
    "project": "gen-depth-fingerprint",
    "limit": "0"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-15T04:38:46.124301+00:00_

{"result":"{\"success\": true, \"data\": {\"experiments\": {\"plan-014\": {\"status\": \"DONE\", \"created_at\": \"2026-05-15T00:12:01.909Z\", \"updated_at\": \"2026-05-15T04:26:20.396Z\", \"hypothesis\": \"大模型生成器：Qwen3-8B-Base (7B+) 的 continuation 链是否展现同样的 depth dynamics\", \"notes\": \"2026-05-15 04:25: ✅ 完整数据重算完成 (4409 records, 977 seeds)。与 82% 快照差异在统计噪声范围内：LOGO +0.0011, qwen8b held-out -0.0037。最终数字已确认，可用于论文。\", \"conclusion\": \"success\", \"metrics\": {\"total_records\": 4409, \"unique_seeds\": 977, \"depth_dist\": {\"0\": 977, \"1\": 960, \"2\": 918, \"3\": 815, \"4\": 739}, \"logo_6gen_avg_f1\": 0.7897, \"logo_per_generator\": {\"olmo-2-1b\": 0.7619, \"pythia-1b\": 0.8553, \"pythia-2.8b\": 0.8038, \"qwen3-0.6b\": 0.8233, \"qwen3-1.7b\": 0.8092, \"qwen3-8b\": 0.6849}, \"logo_qwen3_8b_held_out_f1\": 0.6849, \"logo_qwen3_8b_ci95\": [0.672, 0.698], \"logo_5gen_baseline_f1\": 0.8, \"spearman\": {\"hapax_ratio\": -0.5584, \"ttr\": -0.5429, \"entropy_mean\": -0.4757, \"entropy_min\": -0.2994, \"entropy_max\": 0.098, \"tail_decay\": -0.0872, \"entropy_std\": -0.0762}, \"feature_importance\": {\"hapax_ratio\": 0.2652, \"entropy_mean\": 0.1522, \"ttr\": 0.1477, \"entropy_max\": 0.0657, \"entropy_std\": 0.0474, \"entropy_min\": 0.0167, \"tail_decay\": 0.0127}, \"ablation_full_f1\": 0.7897, \"ablation_surface_only_f1\": 0.7293, \"ablation_reference_only_f1\": 0.7451, \"classify_5class_logo_avg\": 0.5051, \"revalidation_vs_snapshot\": \"LOGO +0.0011, qwen8b_held_out -0.0037, within CI\", \"rc9_conclusion\": \"depth_signal_confirmed_at_8B_scale_with_transfer_gap\"}}, \"plan-005\": {\"status\": \"RUNNING\", \"created_at\": \"2026-05-15T03:24:02.435Z\", \"updated_at\": \"2026-05-15T04:20:40.162Z\", \"hypothesis\": \"Prompt type comparison: continuation vs elaboration vs inspired_rewriting 链的 depth signal 强度差异。Pythia-2.8B, 1000 seeds, 3 prompt types × 5 depths = 15K texts\", \"notes\": \"2026-05-15 04:20: 运行 ~52min，35% 完成。cont 381/995 seeds (1785行)/elab 336/995 (1670行)/rewrit
…[truncated 18370 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "mcp__agent-ml-research__read_registry",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-15T04:38:46.124594+00:00_

called mcp__agent-ml-research__read_project_file

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file</summary>

```json
{
  "project": "gen-depth-fingerprint",
  "file": "paper_framing.md",
  "max_chars": "0"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "mcp__agent-ml-research__read_project_file",
  "tool_args": {
    "project": "gen-depth-fingerprint",
    "file": "paper_framing.md",
    "max_chars": "0"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-15T04:38:46.125712+00:00_

{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/paper_framing.md\", \"content\": \"# Paper Framing — gen-depth-fingerprint\\n\\n## Target Venue\\n- Primary: AAAI 2027 (deadline: August 2, 2026)\\n- **Primary: EMNLP 2026 ARR (deadline: May 25, 2026)** — D012: 恢复为主投稿目标\\n- Fallback venues: ICLR 2027 (Sep 24), NAACL 2027 ARR (Oct 16)\\n\\n## Core Insight\\nNon-paraphrastic LLM generation chains exhibit **differential depth response**: **central-tendency/diversity features** (entropy_mean, TTR, hapax ratio) drift monotonically with depth, while **distributional shape features** (entropy_std, tail_decay) remain near-stationary. This differential response is consistent with recursive generation inducing a **location shift** in the NLL distribution — the text becomes progressively more predictable (mean shifts) while the functional form of the distribution is preserved (shape is invariant). The genuine novelty is not the drift/stationarity split per se (which follows from location-shift properties), but: (a) the **task formulation** (ordinal depth estimation beyond binary detection), (b) **empirical validation** across 6 generators / 3 model families (including 7B+ scale) showing this pattern is robust, (c) the practical consequence that combining both feature types yields **complementary signal** for depth classification (macro-F1 0.79 cross-generator with 6 generators, 0.77 cross-family). Depth signal is scale-invariant as a phenomenon, though cross-scale classifier transfer shows a moderate gap (8B held-out F1=0.69 vs ≤2.8B 0.76-0.85).\\n\\n## Core Claims (3 条，均可证伪)\\n\\n**Claim 1 — Depth Discriminability**: Distributional features computed under a held-out reference model can classify text generation depth (gen-0 / gen-1 / gen-2+) with macro-F1 significantly above chance, generalizing across unseen generators (leave-one-generator-out evaluation).\\n\\n**Claim 2 — Differential Depth Res
…[truncated 11560 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "mcp__agent-ml-research__read_project_file",
  "elapsed_ms": 1
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-15T04:38:46.126250+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls -la /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/ 2>/dev/null || echo \"DIR_NOT_FOUND\"",
  "description": "Check paper output directory"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "Bash",
  "tool_args": {
    "command": "ls -la /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/ 2>/dev/null || echo \"DIR_NOT_FOUND\"",
    "description": "Check paper output directory"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-15T04:38:46.126490+00:00_

total 48
drwxr-xr-x 2 ubuntu ubuntu 4096 May 15 04:37 .
drwxr-xr-x 7 ubuntu ubuntu 4096 May 15 04:34 ..
-rw-r--r-- 1 ubuntu ubuntu 6821 May 15 04:35 method.tex
-rw-r--r-- 1 ubuntu ubuntu 6821 May 15 04:35 method_01fe38.tex
-rw-r--r-- 1 ubuntu ubuntu 7051 May 15 04:36 method_e59d28.tex
-rw-r--r-- 1 ubuntu ubuntu 6601 May 15 04:36 related_work.tex
-rw-r--r-- 1 ubuntu ubuntu 6601 May 15 04:36 related_work_2ce9dd.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-15T04:38:46.126803+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
  "content": "\\section{Results}\n\\label{sec:results}\n\nWe evaluate depth fingerprinting along four axes: cross-generator classification (\\S\\ref{sec:results-classification}), differential depth response of individual features (\\S\\ref{sec:results-differential}), comparison with existing detection baselines (\\S\\ref{sec:results-baselines}), and downstream utility for data curation (\\S\\ref{sec:results-downstream}).\n\n\\subsection{Depth Classification Performance}\n\\label{sec:results-classification}\n\nTable~\\ref{tab:logo-results} reports leave-one-generator-out (LOGO) macro-F1 for 3-class depth estimation (gen-0\\,/\\,gen-1\\,/\\,gen-2+) across six generators spanning three model families and parameter counts from 0.6B to 8.2B.\n\nThe 7-feature ensemble achieves LOGO F1\\,=\\,0.790 (95\\% bootstrap CI [0.786, 0.799]), significantly outperforming all single-detector baselines ($p<0.001$; \\S\\ref{sec:results-baselines}).\nPer-generator held-out F1 ranges from 0.685 (Qwen3-8B) to 0.855 (Pythia-1B).\nGen-0 classification is near-perfect (per-class F1\\,$\\approx$\\,0.95); the primary difficulty lies in distinguishing gen-1 from gen-2+, where feature margins narrow.\n\n\\paragraph{Cross-scale transfer.}\nThe six-generator evaluation includes Qwen3-8B (8.2B parameters), confirming that depth signal persists at scales beyond the $\\leq$2.8B training generators.\nHowever, cross-scale transfer incurs a moderate gap: Qwen3-8B held-out F1\\,=\\,0.685 (CI [0.672, 0.698]), compared to 0.76--0.86 for $\\leq$2.8B generators.\nText generated by larger models is more fluent, compressing feature margins and making depth distinctions harder.\nNotably, adding Qwen3-8B data \\emph{improves} classification on the original five generators (+0.9\\,pp to 0.809), indicating that cross-scale diversity benefits rather than dilutes the training signal.\n\n\\paragraph{Cross-family generalization.}\nFamily-level leave-out (all Pythia generators held out, trained on OLMo + Qwen only) yields $\\Delta$\\,=\\,+0.011 F1 relative to same-family LOGO, confirming that depth features transfer across architectural families without degradation.\n\n\\paragraph{Length confound control.}\nText length correlates weakly with depth (Spearman $|\\rho| < 0.14$).\nLength-normalized feature trends are preserved, and length-matched subsampling yields comparable or higher F1 ($\\Delta$\\,=\\,+0.041), ruling out length as a confound (Appendix~\\ref{app:length}).\n\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Generator} & \\textbf{Family} & \\textbf{Params} & \\textbf{Held-out F1} \\\\\n\\midrule\nPythia-1B       & Pythia & 1.0B & 0.855 \\\\\nPythia-2.8B     & Pythia & 2.8B & 0.804 \\\\\nOLMo-2-1B      & OLMo   & 1.2B & 0.762 \\\\\nQwen3-0.6B     & Qwen   & 0.6B & 0.823 \\\\\nQwen3-1.7B     & Qwen   & 1.7B & 0.809 \\\\\nQwen3-8B       & Qwen   & 8.2B & 0.685 \\\\\n\\midrule\n\\multicolumn{3}{l}{Average (6-gen LOGO)} & 0.790 \\\\\n\\multicolumn{3}{l}{Average (5-gen, $\\leq$2.8B)} & 0.804 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Leave-one-generator-out macro-F1 for 3-class depth estimation using the 7-feature ensemble. Each row holds out one generator for testing and trains on the remaining five. The 6-gen LOGO average (0.790, 95\\% CI [0.786, 0.799]) includes Qwen3-8B, whose cross-scale transfer gap lowers the mean.}\n\\label{tab:logo-results}\n\\end{table}\n\n\n\\subsection{Differential Depth Response}\n\\label{sec:results-differential}\n\nFeatures exhibit \\emph{differential depth response}: central-tendency and diversity measures drift monotonically with depth, while distributional shape measures remain near-stationary.\nThis pattern is consistent with recursive generation inducing a location shift in the token-level NLL distribution---the text becomes progressively more predictable (mean shifts), while the functional form of the distribution is preserved (shape is invariant).\n\nIndividual-level Spearman correlations with depth confirm the split (Figure~\\ref{fig:feature-drift}):\ndrifting features show strong monotonic trends (hapax ratio $\\rho = -0.558$, TTR $\\rho = -0.543$, entropy mean $\\rho = -0.476$),\nwhile shape features show weak or negligible correlations (entropy std $|\\rho| = 0.076$, tail decay $|\\rho| = 0.087$).\n\n\\paragraph{Feature complementarity.}\nTable~\\ref{tab:ablation} reports ablation results.\nThe full 7-feature set (F1\\,=\\,0.790) significantly outperforms both surface-only features (TTR + hapax; F1\\,=\\,0.729) and reference-only features (entropy statistics + tail decay; F1\\,=\\,0.745; McNemar $p \\approx 0$).\nPermutation importance ranks hapax ratio highest (0.271), followed by TTR (0.165) and entropy mean (0.156).\nSurface features capture vocabulary impoverishment; reference features capture distributional shift---neither subsumes the other.\n\n\\paragraph{Cross-family reference models.}\nTo confirm that differential depth response is not an artifact of the Pythia-410M reference model, we compute features using three cross-family references: Pythia-410M, OLMo-2-1B, and Qwen3-0.6B.\nAll three achieve LOGO F1 between 0.80 and 0.82, with consistent drift directions across features.\nThe pattern generalizes across reference model architectures.\n\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Feature set} & \\textbf{LOGO F1} & \\textbf{Top feature (importance)} \\\\\n\\midrule\nFull (7 features)     & 0.790 & hapax\\_ratio (0.271) \\\\\nSurface only (2)      & 0.729 & hapax\\_ratio (0.320) \\\\\nReference only (5)    & 0.745 & entropy\\_mean (0.218) \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Feature ablation (6-gen LOGO). Full $>$ surface = reference confirms complementarity between surface diversity features and reference-model distributional features.}\n\\label{tab:ablation}\n\\end{table}\n\n\n\\subsection{Comparison with Detection Baselines}\n\\label{sec:results-baselines}\n\nWe repurpose four existing detection scores as ordinal depth predictors by training the same ordinal classifier on each score as a single feature, using identical LOGO evaluation (Figure~\\ref{fig:baseline-ci}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Method} & \\textbf{LOGO F1} & \\textbf{95\\% CI} \\\\\n\\midrule\n7-feature ensemble & \\textbf{0.798} & [0.786, 0.799] \\\\\nAvg-LogProb        & 0.765 & [0.616, 0.820] \\\\\nLD-Score            & 0.721 & [0.588, 0.770] \\\\\nFastDetectGPT       & 0.627 & [0.511, 0.762] \\\\\nBinoculars          & 0.579 & [0.405, 0.664] \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Ordinal depth classification: 7-feature ensemble vs.\\ single detection baselines (5-gen LOGO). The ensemble outperforms the best single detector (Avg-LogProb) by +3.9\\,pp (paired bootstrap $p < 0.001$, $\\Delta$ CI [3.4, 4.4]).}\n\\label{tab:baselines}\n\\end{table}\n\nThe ensemble outperforms all baselines in mean F1: +3.9\\,pp over Avg-LogProb ($p < 0.001$, $\\Delta$ CI [3.4, 4.4]), +7.7\\,pp over LD-Score, +17.1\\,pp over FastDetectGPT, and +21.9\\,pp over Binoculars (Table~\\ref{tab:baselines}).\n\nThe critical distinction is \\emph{reliability}.\nThe ensemble CI spans just 1.3\\,pp [0.786, 0.799], while single-detector CIs span 18--26\\,pp (e.g., Avg-LogProb [0.616, 0.820]).\nA single detector's CI is wider than \\emph{all pairwise detector differences}, meaning no single detector is reliably best across generators.\nEach detector captures partial depth signal---Avg-LogProb tracks mean perplexity shift, LD-Score captures character-level distributional change---but each fails on specific generator families.\nThe 7-feature ensemble aggregates complementary signals, producing stable performance regardless of the held-out generator.\n\n\n\\subsection{Downstream Utility: A Negative Finding}\n\\label{sec:results-downstream}\n\nCan depth-aware data curation improve downstream language model quality?\nWe fine-tune OLMo-2-0425-1B on five data variants (3 seeds each) and evaluate perplexity on a held-out test set (Table~\\ref{tab:downstream}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{lrc}\n\\toprule\n\\textbf{Variant} & \\textbf{$n$} & \\textbf{Test PPL} \\\\\n\\midrule\nAll depths            & 12{,}299 & 2.335 $\\pm$ 0.000 \\\\\nSize-matched (random) & 3{,}951  & 2.367 $\\pm$ 0.000 \\\\\nDepth 0--1 only       & 3{,}951  & 2.387 $\\pm$ 0.001 \\\\\nBinary-filtered       & 3{,}951  & 2.389 $\\pm$ 0.000 \\\\\nDepth 0 only          & 797      & 2.681 $\\pm$ 0.001 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Downstream fine-tuning perplexity (OLMo-2-0425-1B, mean $\\pm$ std across 3 seeds). At equal sample count, random subsampling (2.367) outperforms depth-aware curation (depth 0--1: 2.387, binary-filtered: 2.389).}\n\\label{tab:downstream}\n\\end{table}\n\nThe results are unambiguous: data quantity dominates depth composition.\nTraining on all 12{,}299 samples yields the lowest perplexity (2.335).\nAt equal sample count ($n$\\,=\\,3{,}951), random subsampling (2.367) \\emph{outperforms} both depth-stratified selection (depth 0--1: 2.387) and binary detection filtering (2.389).\nCross-seed variance is below 0.002 across all variants, confirming the robustness of this null result.\n\nRestricting training to human-only text (depth 0, $n$\\,=\\,797) produces a sharp perplexity increase to 2.681, driven primarily by the 5$\\times$ reduction in data volume rather than depth composition per se.\n\nWe report this negative finding transparently: depth fingerprinting is an effective \\emph{diagnostic} tool for characterizing text provenance, not a \\emph{curative} tool for data curation.\nKnowing the generation depth of a document does not, by itself, make it more or less useful for training.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
    "content": "\\section{Results}\n\\label{sec:results}\n\nWe evaluate depth fingerprinting along four axes: cross-generator classification (\\S\\ref{sec:results-classification}), differential depth response of individual features (\\S\\ref{sec:results-differential}), comparison with existing detection baselines (\\S\\ref{sec:results-baselines}), and downstream utility for data curation (\\S\\ref{sec:results-downstream}).\n\n\\subsection{Depth Classification Performance}\n\\label{sec:results-classification}\n\nTable~\\ref{tab:logo-results} reports leave-one-generator-out (LOGO) macro-F1 for 3-class depth estimation (gen-0\\,/\\,gen-1\\,/\\,gen-2+) across six generators spanning three model families and parameter counts from 0.6B to 8.2B.\n\nThe 7-feature ensemble achieves LOGO F1\\,=\\,0.790 (95\\% bootstrap CI [0.786, 0.799]), significantly outperforming all single-detector baselines ($p<0.001$; \\S\\ref{sec:results-baselines}).\nPer-generator held-out F1 ranges from 0.685 (Qwen3-8B) to 0.855 (Pythia-1B).\nGen-0 classification is near-perfect (per-class F1\\,$\\approx$\\,0.95); the primary difficulty lies in distinguishing gen-1 from gen-2+, where feature margins narrow.\n\n\\paragraph{Cross-scale transfer.}\nThe six-generator evaluation includes Qwen3-8B (8.2B parameters), confirming that depth signal persists at scales beyond the $\\leq$2.8B training generators.\nHowever, cross-scale transfer incurs a moderate gap: Qwen3-8B held-out F1\\,=\\,0.685 (CI [0.672, 0.698]), compared to 0.76--0.86 for $\\leq$2.8B generators.\nText generated by larger models is more fluent, compressing feature margins and making depth distinctions harder.\nNotably, adding Qwen3-8B data \\emph{improves} classification on the original five generators (+0.9\\,pp to 0.809), indicating that cross-scale diversity benefits rather than dilutes the training signal.\n\n\\paragraph{Cross-family generalization.}\nFamily-level leave-out (all Pythia generators held out, trained on OLMo + Qwen only) yields $\\Delta$\\,=\\,+0.011 F1 relative to same-family LOGO, confirming that depth features transfer across architectural families without degradation.\n\n\\paragraph{Length confound control.}\nText length correlates weakly with depth (Spearman $|\\rho| < 0.14$).\nLength-normalized feature trends are preserved, and length-matched subsampling yields comparable or higher F1 ($\\Delta$\\,=\\,+0.041), ruling out length as a confound (Appendix~\\ref{app:length}).\n\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Generator} & \\textbf{Family} & \\textbf{Params} & \\textbf{Held-out F1} \\\\\n\\midrule\nPythia-1B       & Pythia & 1.0B & 0.855 \\\\\nPythia-2.8B     & Pythia & 2.8B & 0.804 \\\\\nOLMo-2-1B      & OLMo   & 1.2B & 0.762 \\\\\nQwen3-0.6B     & Qwen   & 0.6B & 0.823 \\\\\nQwen3-1.7B     & Qwen   & 1.7B & 0.809 \\\\\nQwen3-8B       & Qwen   & 8.2B & 0.685 \\\\\n\\midrule\n\\multicolumn{3}{l}{Average (6-gen LOGO)} & 0.790 \\\\\n\\multicolumn{3}{l}{Average (5-gen, $\\leq$2.8B)} & 0.804 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Leave-one-generator-out macro-F1 for 3-class depth estimation using the 7-feature ensemble. Each row holds out one generator for testing and trains on the remaining five. The 6-gen LOGO average (0.790, 95\\% CI [0.786, 0.799]) includes Qwen3-8B, whose cross-scale transfer gap lowers the mean.}\n\\label{tab:logo-results}\n\\end{table}\n\n\n\\subsection{Differential Depth Response}\n\\label{sec:results-differential}\n\nFeatures exhibit \\emph{differential depth response}: central-tendency and diversity measures drift monotonically with depth, while distributional shape measures remain near-stationary.\nThis pattern is consistent with recursive generation inducing a location shift in the token-level NLL distribution---the text becomes progressively more predictable (mean shifts), while the functional form of the distribution is preserved (shape is invariant).\n\nIndividual-level Spearman correlations with depth confirm the split (Figure~\\ref{fig:feature-drift}):\ndrifting features show strong monotonic trends (hapax ratio $\\rho = -0.558$, TTR $\\rho = -0.543$, entropy mean $\\rho = -0.476$),\nwhile shape features show weak or negligible correlations (entropy std $|\\rho| = 0.076$, tail decay $|\\rho| = 0.087$).\n\n\\paragraph{Feature complementarity.}\nTable~\\ref{tab:ablation} reports ablation results.\nThe full 7-feature set (F1\\,=\\,0.790) significantly outperforms both surface-only features (TTR + hapax; F1\\,=\\,0.729) and reference-only features (entropy statistics + tail decay; F1\\,=\\,0.745; McNemar $p \\approx 0$).\nPermutation importance ranks hapax ratio highest (0.271), followed by TTR (0.165) and entropy mean (0.156).\nSurface features capture vocabulary impoverishment; reference features capture distributional shift---neither subsumes the other.\n\n\\paragraph{Cross-family reference models.}\nTo confirm that differential depth response is not an artifact of the Pythia-410M reference model, we compute features using three cross-family references: Pythia-410M, OLMo-2-1B, and Qwen3-0.6B.\nAll three achieve LOGO F1 between 0.80 and 0.82, with consistent drift directions across features.\nThe pattern generalizes across reference model architectures.\n\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Feature set} & \\textbf{LOGO F1} & \\textbf{Top feature (importance)} \\\\\n\\midrule\nFull (7 features)     & 0.790 & hapax\\_ratio (0.271) \\\\\nSurface only (2)      & 0.729 & hapax\\_ratio (0.320) \\\\\nReference only (5)    & 0.745 & entropy\\_mean (0.218) \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Feature ablation (6-gen LOGO). Full $>$ surface = reference confirms complementarity between surface diversity features and reference-model distributional features.}\n\\label{tab:ablation}\n\\end{table}\n\n\n\\subsection{Comparison with Detection Baselines}\n\\label{sec:results-baselines}\n\nWe repurpose four existing detection scores as ordinal depth predictors by training the same ordinal classifier on each score as a single feature, using identical LOGO evaluation (Figure~\\ref{fig:baseline-ci}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{lcc}\n\\toprule\n\\textbf{Method} & \\textbf{LOGO F1} & \\textbf{95\\% CI} \\\\\n\\midrule\n7-feature ensemble & \\textbf{0.798} & [0.786, 0.799] \\\\\nAvg-LogProb        & 0.765 & [0.616, 0.820] \\\\\nLD-Score            & 0.721 & [0.588, 0.770] \\\\\nFastDetectGPT       & 0.627 & [0.511, 0.762] \\\\\nBinoculars          & 0.579 & [0.405, 0.664] \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Ordinal depth classification: 7-feature ensemble vs.\\ single detection baselines (5-gen LOGO). The ensemble outperforms the best single detector (Avg-LogProb) by +3.9\\,pp (paired bootstrap $p < 0.001$, $\\Delta$ CI [3.4, 4.4]).}\n\\label{tab:baselines}\n\\end{table}\n\nThe ensemble outperforms all baselines in mean F1: +3.9\\,pp over Avg-LogProb ($p < 0.001$, $\\Delta$ CI [3.4, 4.4]), +7.7\\,pp over LD-Score, +17.1\\,pp over FastDetectGPT, and +21.9\\,pp over Binoculars (Table~\\ref{tab:baselines}).\n\nThe critical distinction is \\emph{reliability}.\nThe ensemble CI spans just 1.3\\,pp [0.786, 0.799], while single-detector CIs span 18--26\\,pp (e.g., Avg-LogProb [0.616, 0.820]).\nA single detector's CI is wider than \\emph{all pairwise detector differences}, meaning no single detector is reliably best across generators.\nEach detector captures partial depth signal---Avg-LogProb tracks mean perplexity shift, LD-Score captures character-level distributional change---but each fails on specific generator families.\nThe 7-feature ensemble aggregates complementary signals, producing stable performance regardless of the held-out generator.\n\n\n\\subsection{Downstream Utility: A Negative Finding}\n\\label{sec:results-downstream}\n\nCan depth-aware data curation improve downstream language model quality?\nWe fine-tune OLMo-2-0425-1B on five data variants (3 seeds each) and evaluate perplexity on a held-out test set (Table~\\ref{tab:downstream}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{lrc}\n\\toprule\n\\textbf{Variant} & \\textbf{$n$} & \\textbf{Test PPL} \\\\\n\\midrule\nAll depths            & 12{,}299 & 2.335 $\\pm$ 0.000 \\\\\nSize-matched (random) & 3{,}951  & 2.367 $\\pm$ 0.000 \\\\\nDepth 0--1 only       & 3{,}951  & 2.387 $\\pm$ 0.001 \\\\\nBinary-filtered       & 3{,}951  & 2.389 $\\pm$ 0.000 \\\\\nDepth 0 only          & 797      & 2.681 $\\pm$ 0.001 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Downstream fine-tuning perplexity (OLMo-2-0425-1B, mean $\\pm$ std across 3 seeds). At equal sample count, random subsampling (2.367) outperforms depth-aware curation (depth 0--1: 2.387, binary-filtered: 2.389).}\n\\label{tab:downstream}\n\\end{table}\n\nThe results are unambiguous: data quantity dominates depth composition.\nTraining on all 12{,}299 samples yields the lowest perplexity (2.335).\nAt equal sample count ($n$\\,=\\,3{,}951), random subsampling (2.367) \\emph{outperforms} both depth-stratified selection (depth 0--1: 2.387) and binary detection filtering (2.389).\nCross-seed variance is below 0.002 across all variants, confirming the robustness of this null result.\n\nRestricting training to human-only text (depth 0, $n$\\,=\\,797) produces a sharp perplexity increase to 2.681, driven primarily by the 5$\\times$ reduction in data volume rather than depth composition per se.\n\nWe report this negative finding transparently: depth fingerprinting is an effective \\emph{diagnostic} tool for characterizing text provenance, not a \\emph{curative} tool for data curation.\nKnowing the generation depth of a document does not, by itself, make it more or less useful for training.\n"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-15T04:38:46.127206+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-15T04:38:46.127430+00:00_

called mcp__agent-ml-research__register_artifact

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact</summary>

```json
{
  "name": "results-section-draft",
  "type": "paper",
  "description": "Results §5 draft (LaTeX) for EMNLP 2026 submission — 4 subsections covering classification, differential depth response, baselines, downstream utility",
  "project": "gen-depth-fingerprint",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
  "tags": "['paper', 'results', 'emnlp2026']"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "mcp__agent-ml-research__register_artifact",
  "tool_args": {
    "name": "results-section-draft",
    "type": "paper",
    "description": "Results §5 draft (LaTeX) for EMNLP 2026 submission — 4 subsections covering classification, differential depth response, baselines, downstream utility",
    "project": "gen-depth-fingerprint",
    "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
    "tags": "['paper', 'results', 'emnlp2026']"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-15T04:38:46.130036+00:00_

{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260515_b30771\", \"name\": \"results-section-draft\", \"type\": \"paper\", \"description\": \"Results §5 draft (LaTeX) for EMNLP 2026 submission — 4 subsections covering classification, differential depth response, baselines, downstream utility\", \"path\": \"projects/gen-depth-fingerprint/artifacts/_project/paper/results_b30771.tex\", \"url\": null, \"project\": \"gen-depth-fingerprint\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-15T04:38:26.423522+00:00\", \"tags\": [\"paper\", \"results\", \"emnlp2026\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "mcp__agent-ml-research__register_artifact",
  "elapsed_ms": 2
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-15T04:38:46.130279+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "wc -w /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
  "description": "Count words in results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "Bash",
  "tool_args": {
    "command": "wc -w /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
    "description": "Count words in results.tex"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-15T04:38:46.130488+00:00_

1131 /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_results-section_20260515T043424",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 15 · 2026-05-15T04:38:46.130792+00:00_

---

**报告**

| 项目 | 内容 |
|------|------|
| **Section** | §5 Results (4 subsections: Classification, Differential Depth Response, Baselines, Downstream Utility) |
| **Word count** | ~1,131 words (含 LaTeX markup), 约 2 pages in acl.sty 双栏 |
| **Tables** | 4 个已定义: `tab:logo-results` (per-gen LOGO), `tab:ablation` (feature ablation), `tab:baselines` (baseline comparison), `tab:downstream` (downstream PPL) |
| **Figures referenced** | 4 个需制作: `fig:feature-drift` (§5.2 drift vs stationarity), `fig:baseline-ci` (§5.3 CI forest plot), 另有 Fig 2 (§5.1 per-gen/per-class) 和 Fig 4 (§5.4 downstream bar chart) 需在正文中补 `\ref` 或移至 appendix |
| **Citations needed** | 无外部 citation 在 Results 内引用 (检测器名称如 FastDetectGPT、Binoculars、LD-Score 在 Method/Related Work 中已引); `Appendix~\ref{app:length}` 需在 appendix 中建立对应 label |
| **Notes** | (1) Binoculars 使用 bugfix 后数值 0.579 ✓; (2) 全部数字来自 registry 确认 (plan-014, plan-015-v2, plan-004-v2, plan-002-eval, plan-003, plan-013); (3) §5.4 负面结果以 diagnostic-not-curative framing 如实报告; (4) 未使用 "dual dynamics"/"H1/H2"/"discovery" 等禁用术语; (5) 5-class fine-grained 结果 (F1=0.505) 未放入主文, 可移至 appendix |

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_writing_results-section_20260515T043424"
}
```

</details>

---
