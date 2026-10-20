# paper appendix tost bootstrap

**Depth Profiling: Classifying Recursive Generation Depth in Base-Model LLM Text** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 11
- **Recorded user turns:** 0
- **Tool calls:** 5
- **Original source:** `logs/chats/worker_paper_appendix_tost_bootstrap_20260520T082345.jsonl`
- **Structured JSON:** [`b6c963d18bc26f7fa426.json`](../../sessions/b6/b6c963d18bc26f7fa426.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

11 recorded events

### Tool call

_source line 1 · 2026-05-20T08:24:23.743914+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
  "offset": "70",
  "limit": "20"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_appendix_tost_bootstrap_20260520T082345",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
    "offset": "70",
    "limit": "20"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-20T08:24:23.744237+00:00_

70	The six-fold magnitude gap between drifting ($|\rho| > 0.60$) and near-stationary features ($|\rho| < 0.10$) defines the DDR partition, with entropy std ($|\rho| = 0.16$, $d{=}0.55$) as the sole intermediate member.
71	The 3/1/3 partition is stable across $d$ thresholds in $[0.56, 0.75]$; data-driven clustering confirms the primary drifting/non-drifting split ($k{=}2$, silhouette\,=\,0.632; Appendix~\ref{app:ddr-validation}).
72	
73	\paragraph{Distributional shift quantification.}
74	Two-sample KS tests confirm the split: drifting-feature statistics (0.516--0.537) are ${\sim}10\times$ larger than shape-feature statistics (0.043--0.052; all $p \approx 0$ after Bonferroni correction).
75	Cohen's $d$ \cite{cohen1988statistical} (pooled, class-balanced) converges with $\rho$: drifting features show large effects (entropy mean $d{=}1.17$, TTR $d{=}0.88$, hapax ratio $d{=}0.76$), while shape features are near zero (entropy max $d{=}0.08$, tail decay $d{=}0.08$).
76	Levene tests reject strict equal-variance ($p < 10^{-10}$); Glass's $\Delta$ (using gen-1 SD) amplifies drifting effects (entropy mean $\Delta{=}1.41$, hapax $\Delta{=}0.94$) while near-stationary features remain negligible ($\Delta \leq 0.10$), yielding a ${\geq}9.5\times$ gap. Cliff's $\delta$ corroborates the partition (Appendix~\ref{app:ddr-validation}).
77	Shape-feature CV shift ($<$3\% vs.\ $>$15\% for drifting features) supports ``near-stationary'' as a practical characterization.
78	Five features fall cleanly into the drifting or near-stationary groups under both $\rho$ and $d$; the remaining two require qualification: entropy min's pooled $|\rho|$ (0.40) reflects change concentrated at the gen-0/gen-1 boundary, but for gen-1 vs.\ gen-2+ it is near-stationary ($d{=}0.03$), placing it in the near-stationary group; entropy std shows a substantial level shift ($d{=}0.55$) despite low monotonicity ($|\rho|{=}0.16$), making it the sole intermediate feature.
79	Entropy min exhibits a discrepancy between lo
…[truncated 1931 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_appendix_tost_bootstrap_20260520T082345",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-20T08:24:23.744420+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "artifacts/_project/paper/appendix_tost*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_appendix_tost_bootstrap_20260520T082345",
  "tool": "Glob",
  "tool_args": {
    "pattern": "artifacts/_project/paper/appendix_tost*.tex",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-20T08:24:23.744556+00:00_

artifacts/_project/paper/appendix_tost.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_appendix_tost_bootstrap_20260520T082345",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-20T08:24:23.744701+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_tost.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_appendix_tost_bootstrap_20260520T082345",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_tost.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-20T08:24:23.744861+00:00_

1	\section{Per-Generator Equivalence Testing}
2	\label{app:tost}
3	
4	To confirm that the near-stationary classification is not a pooling artifact, we apply two one-sided $t$-tests (TOST) \cite{lakens_equivalence} for each feature within each generator separately (gen-1 vs.\ gen-2+, equivalence bound $|d| < 0.20$).
5	We adopt Cohen's conventional small effect size ($d{=}0.20$) \cite{cohen1988statistical} as the smallest effect of practical significance (SESOI): effects below this threshold are unlikely to be practically meaningful for depth discrimination.
6	LOFO analysis independently supports this choice: removing any near-stationary feature changes classification F1 by $\leq$1.5\,pp (Appendix~\ref{app:lofo}), linking the statistical threshold to classification irrelevance.
7	Sensitivity analysis at $\varepsilon \in \{0.15, 0.20, 0.25\}$ confirms the partition is robust to the bound choice (see DDR Validation appendix).
8	Table~\ref{tab:tost-per-gen} reports observed $|d|$; \checkmark{} marks features for which the TOST null hypothesis (non-equivalence) is rejected at $\alpha = 0.05$.
9	
10	Entropy min passes equivalence for all eight generators; entropy max passes for six of eight (exceeding $\varepsilon$ only for Pythia-1B and Pythia-2.8B, where $|d| \approx 0.21$--$0.25$); tail decay passes for four of eight.
11	All drifting and intermediate features fail equivalence uniformly, with $|d|$ ranging from 0.23 (entropy std, Mistral) to 1.40 (entropy mean, Pythia-1B).
12	The partition is robust at the individual-generator level, with entropy min as the most consistently stationary feature.
13	Figure~\ref{fig:ddr-scatter} visualizes the DDR partition in ($|\rho|$, $d$) space, showing a clear gap between the three groups.
14	
15	\begin{table}[h]
16	\centering
17	\footnotesize
18	\caption{Per-generator TOST equivalence ($\varepsilon{=}|d|{<}0.20$, gen-1 vs.\ gen-2+). Observed $|d|$; \checkmark{} = equivalent ($p_{\mathrm{TOST}} < 0.05$). Features grouped by DDR partiti
…[truncated 1919 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_appendix_tost_bootstrap_20260520T082345",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-20T08:24:23.745032+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_tost_bootstrap.tex",
  "content": "\\section{TOST Bootstrap Stability}\\label{app:tost-bootstrap}\n\nTo verify that the equivalence conclusions in \\S\\ref{app:tost} are not sensitive to sample composition, we assess their stability under bootstrap resampling.\nFor each of four representative features, we run 1{,}000 bootstrap iterations (base seed\\,=\\,42): each iteration independently resamples with replacement from the gen-1 and gen-2+ pools, recomputes Cohen's $d$ and the TOST $p$-value (equivalence margin $|d| < 0.20$).\n\n\\begin{table}[h]\n\\centering\n\\footnotesize\n\\caption{Bootstrap stability of TOST equivalence ($B{=}1{,}000$, margin $|d|{<}0.20$). Rejection rate = fraction of bootstrap iterations where TOST rejects non-equivalence at $\\alpha{=}0.05$.}\n\\label{tab:tost-bootstrap}\n\\begin{tabular}{l c c c}\n\\toprule\n\\textbf{Feature} & \\textbf{Rejection rate} & \\textbf{Median $d$} & \\textbf{$d$ 95\\% CI} \\\\\n\\midrule\nentropy\\_max  & 100\\% (1000/1000) & 0.062  & [0.037, 0.088] \\\\\nentropy\\_min  & 100\\% (1000/1000) & $-$0.016 & [$-$0.042, 0.011] \\\\\ntail\\_decay   & 100\\% (1000/1000) & 0.088  & [0.065, 0.111] \\\\\n\\midrule\nentropy\\_std  & 0\\% (0/1000)      & 0.458  & [0.435, 0.479] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll three near-stationary features achieve a 100\\% rejection rate across 1{,}000 bootstrap iterations, and their effect-size 95\\% CIs fall entirely within the $\\pm 0.20$ equivalence margin.\nEntropy std, included as an intermediate control, is never rejected (0\\%), with its CI $[0.435, 0.479]$ lying entirely outside the margin.\nNo feature exhibits boundary-crossing---the classification of each feature is unanimous across all bootstrap samples, confirming that the equivalence conclusions are robust to resampling variability.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_appendix_tost_bootstrap_20260520T082345",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_tost_bootstrap.tex",
    "content": "\\section{TOST Bootstrap Stability}\\label{app:tost-bootstrap}\n\nTo verify that the equivalence conclusions in \\S\\ref{app:tost} are not sensitive to sample composition, we assess their stability under bootstrap resampling.\nFor each of four representative features, we run 1{,}000 bootstrap iterations (base seed\\,=\\,42): each iteration independently resamples with replacement from the gen-1 and gen-2+ pools, recomputes Cohen's $d$ and the TOST $p$-value (equivalence margin $|d| < 0.20$).\n\n\\begin{table}[h]\n\\centering\n\\footnotesize\n\\caption{Bootstrap stability of TOST equivalence ($B{=}1{,}000$, margin $|d|{<}0.20$). Rejection rate = fraction of bootstrap iterations where TOST rejects non-equivalence at $\\alpha{=}0.05$.}\n\\label{tab:tost-bootstrap}\n\\begin{tabular}{l c c c}\n\\toprule\n\\textbf{Feature} & \\textbf{Rejection rate} & \\textbf{Median $d$} & \\textbf{$d$ 95\\% CI} \\\\\n\\midrule\nentropy\\_max  & 100\\% (1000/1000) & 0.062  & [0.037, 0.088] \\\\\nentropy\\_min  & 100\\% (1000/1000) & $-$0.016 & [$-$0.042, 0.011] \\\\\ntail\\_decay   & 100\\% (1000/1000) & 0.088  & [0.065, 0.111] \\\\\n\\midrule\nentropy\\_std  & 0\\% (0/1000)      & 0.458  & [0.435, 0.479] \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll three near-stationary features achieve a 100\\% rejection rate across 1{,}000 bootstrap iterations, and their effect-size 95\\% CIs fall entirely within the $\\pm 0.20$ equivalence margin.\nEntropy std, included as an intermediate control, is never rejected (0\\%), with its CI $[0.435, 0.479]$ lying entirely outside the margin.\nNo feature exhibits boundary-crossing---the classification of each feature is unanimous across all bootstrap samples, confirming that the equivalence conclusions are robust to resampling variability.\n"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-20T08:24:23.745177+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_tost_bootstrap.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_appendix_tost_bootstrap_20260520T082345",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-20T08:24:23.745302+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
  "old_string": "Per-generator TOST equivalence testing confirms the partition is not a pooling artifact; holdout generator validation confirms stability across two 4/4 splits (Appendix~\\ref{app:tost}).",
  "new_string": "Per-generator TOST equivalence testing confirms the partition is not a pooling artifact; holdout generator validation confirms stability across two 4/4 splits (Appendix~\\ref{app:tost}).\nBootstrap resampling (1{,}000 iterations) confirms these equivalence conclusions are robust: all three near-stationary features achieve 100\\% rejection rate, with effect-size CIs well within the $d{=}0.20$ margin (Appendix~\\ref{app:tost-bootstrap})."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_appendix_tost_bootstrap_20260520T082345",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
    "old_string": "Per-generator TOST equivalence testing confirms the partition is not a pooling artifact; holdout generator validation confirms stability across two 4/4 splits (Appendix~\\ref{app:tost}).",
    "new_string": "Per-generator TOST equivalence testing confirms the partition is not a pooling artifact; holdout generator validation confirms stability across two 4/4 splits (Appendix~\\ref{app:tost}).\nBootstrap resampling (1{,}000 iterations) confirms these equivalence conclusions are robust: all three near-stationary features achieve 100\\% rejection rate, with effect-size CIs well within the $d{=}0.20$ margin (Appendix~\\ref{app:tost-bootstrap})."
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-20T08:24:23.745476+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_appendix_tost_bootstrap_20260520T082345",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 11 · 2026-05-20T08:24:23.745651+00:00_

已完成：

1. **新建 `appendix_tost_bootstrap.tex`** — 包含 section 标题、bootstrap 方法说明、booktabs 风格表格（4 features × rejection rate / median d / d 95% CI）、总结段落。
2. **`results.tex` 第 81 行** — 在 `(Appendix~\ref{app:tost}).` 后添加了 bootstrap 引用句。

你需要在 `main.tex` 中添加 `\input{appendix_tost_bootstrap}` 行。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_appendix_tost_bootstrap_20260520T082345"
}
```

</details>

---
