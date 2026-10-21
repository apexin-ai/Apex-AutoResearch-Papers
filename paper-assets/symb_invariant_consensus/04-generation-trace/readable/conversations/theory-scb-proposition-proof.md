# theory scb proposition proof

**Beyond Self-Consistency: Self-Extracted Constraints Reduce to Majority Voting under Zero-Shot Extraction** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 43
- **Recorded user turns:** 0
- **Tool calls:** 21
- **Original source:** `logs/chats/worker_theory_scb-proposition-proof_20260523T010508.jsonl`
- **Structured JSON:** [`c4cf992066a3d16afc4b.json`](../../sessions/c4/c4cf992066a3d16afc4b.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

43 recorded events

### Tool call

_source line 1 · 2026-05-23T01:19:40.102355+00:00_

called Agent

<details open><summary>🔧 Tool call — Agent</summary>

```json
{
  "subagent_type": "Explore",
  "description": "Find existing paper notation",
  "prompt": "In /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/, find any .tex files that define notation related to SCB, BR (bias ratio), SICA, SC, traces, constraints, majority voting. Show relevant snippets with file paths. Also check if there's a main paper .tex file anywhere in the project."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Agent",
  "tool_args": {
    "subagent_type": "Explore",
    "description": "Find existing paper notation",
    "prompt": "In /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/, find any .tex files that define notation related to SCB, BR (bias ratio), SICA, SC, traces, constraints, majority voting. Show relevant snippets with file paths. Also check if there's a main paper .tex file anywhere in the project."
  }
}
```

</details>

---

### Tool call

_source line 2 · 2026-05-23T01:19:40.102713+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/**/*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Glob",
  "tool_args": {
    "pattern": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/**/*.tex"
  }
}
```

</details>

---

### Tool result

_source line 3 · 2026-05-23T01:19:40.102919+00:00_

artifacts/dream_reports/dream_20260516T051642/best/paper.tex
artifacts/dream_reports/dream_20260516T051642/median/paper.tex
artifacts/dream_reports/dream_20260516T054054/best/paper.tex
artifacts/dream_reports/dream_20260516T054054/median/paper.tex
artifacts/dream_reports/dream_20260516T054054/worst/paper.tex
artifacts/dream_reports/dream_20260516T124139/best/paper.tex
artifacts/dream_reports/dream_20260516T124139/median/paper.tex
artifacts/dream_reports/dream_20260516T124139/worst/paper.tex
artifacts/dream_reports/dream_20260516T155754/best/paper.tex
artifacts/dream_reports/dream_20260516T155754/median/paper.tex
artifacts/dream_reports/dream_20260516T155754/worst/paper.tex
artifacts/dream_reports/dream_20260517T144412/best/paper.tex
artifacts/dream_reports/dream_20260517T144412/median/paper.tex
artifacts/dream_reports/dream_20260517T144412/worst/paper.tex
artifacts/dream_reports/dream_20260517T165032/best/paper.tex
artifacts/_project/paper/experiments.tex
artifacts/dream_reports/dream_20260517T165032/median/paper.tex
artifacts/dream_reports/dream_20260517T165032/worst/paper.tex
artifacts/_project/paper/related_work.tex
artifacts/_project/paper/experiments_9ea847.tex
artifacts/_project/paper/discussion.tex
artifacts/_project/paper/related_work_b9688e.tex
artifacts/_project/paper/conclusion.tex
artifacts/_project/paper/introduction.tex
artifacts/_project/paper/abstract.tex
artifacts/dream_reports/dream_20260519T034058/best/paper.tex
artifacts/dream_reports/dream_20260519T034058/median/paper.tex
artifacts/dream_reports/dream_20260519T034058/worst/paper.tex
artifacts/_project/paper/sub_population_appendix_draft.tex
artifacts/sub_population_appendix_draft.tex
artifacts/table1_bh_draft.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 4 · 2026-05-23T01:19:40.103126+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/**/*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Glob",
  "tool_args": {
    "pattern": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/**/*.tex"
  }
}
```

</details>

---

### Tool result

_source line 5 · 2026-05-23T01:19:40.103268+00:00_

artifacts/dream_reports/dream_20260516T051642/best/paper.tex
artifacts/dream_reports/dream_20260516T051642/median/paper.tex
artifacts/dream_reports/dream_20260516T054054/best/paper.tex
artifacts/dream_reports/dream_20260516T054054/median/paper.tex
artifacts/dream_reports/dream_20260516T054054/worst/paper.tex
artifacts/dream_reports/dream_20260516T124139/best/paper.tex
artifacts/dream_reports/dream_20260516T124139/median/paper.tex
artifacts/dream_reports/dream_20260516T124139/worst/paper.tex
artifacts/dream_reports/dream_20260516T155754/best/paper.tex
artifacts/dream_reports/dream_20260516T155754/median/paper.tex
artifacts/dream_reports/dream_20260516T155754/worst/paper.tex
artifacts/dream_reports/dream_20260517T144412/best/paper.tex
artifacts/dream_reports/dream_20260517T144412/median/paper.tex
artifacts/dream_reports/dream_20260517T144412/worst/paper.tex
artifacts/dream_reports/dream_20260517T165032/best/paper.tex
artifacts/_project/paper/experiments.tex
artifacts/dream_reports/dream_20260517T165032/median/paper.tex
artifacts/dream_reports/dream_20260517T165032/worst/paper.tex
artifacts/_project/paper/related_work.tex
artifacts/_project/paper/experiments_9ea847.tex
artifacts/_project/paper/discussion.tex
artifacts/_project/paper/related_work_b9688e.tex
artifacts/_project/paper/conclusion.tex
artifacts/_project/paper/introduction.tex
artifacts/_project/paper/abstract.tex
artifacts/dream_reports/dream_20260519T034058/best/paper.tex
artifacts/dream_reports/dream_20260519T034058/median/paper.tex
artifacts/dream_reports/dream_20260519T034058/worst/paper.tex
artifacts/_project/paper/sub_population_appendix_draft.tex
artifacts/sub_population_appendix_draft.tex
artifacts/table1_bh_draft.tex
docs/paper/main.tex
docs/paper/method.tex
docs/paper/limitations_content.tex
docs/paper/discussion.tex
docs/paper/experiments.tex
docs/paper/conclusion.tex
docs/paper/related_work.tex
docs/paper/analysis.tex
docs/paper/diagnosis.tex
docs/paper/appendix.tex
docs/paper/solutions.tex
docs/
…[truncated 46 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 6 · 2026-05-23T01:19:40.103428+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/main.tex"
  }
}
```

</details>

---

### Tool result

_source line 7 · 2026-05-23T01:19:40.103569+00:00_

1	\documentclass[11pt]{article}
2	\usepackage[review]{acl}
3	\usepackage{times}
4	\usepackage{latexsym}
5	\usepackage[T1]{fontenc}
6	\usepackage[utf8]{inputenc}
7	\usepackage{microtype}
8	% \usepackage{inconsolata} % removed: not available in this TeX distribution
9	\usepackage{graphicx}
10	\usepackage{amsmath}
11	\usepackage{amssymb}
12	\usepackage{amsthm}
13	\usepackage{tcolorbox}
14	\tcbuselibrary{skins}
15	\usepackage{booktabs}
16	\usepackage{multirow}
17	\usepackage{xcolor}
18	\usepackage{enumitem}
19	\usepackage{subcaption}
20	\usepackage{tikz}
21	\usetikzlibrary{arrows.meta,positioning,calc,fit}
22	\usepackage{listings}
23	\usepackage{algorithm}
24	\usepackage{algpseudocode}
25	\usepackage{hyperref}
26	\usepackage{cleveref}
27	
28	\lstset{
29	  basicstyle=\small\ttfamily,
30	  breaklines=true,
31	  frame=single,
32	  xleftmargin=1em,
33	  xrightmargin=1em,
34	  aboveskip=0.5em,
35	  belowskip=0.5em,
36	}
37	
38	\graphicspath{{../figures/paper/}{figures/}}
39	
40	\title{Beyond Self-Consistency: Why Self-Extracted Constraints\\Fail to Improve LLM Logical Reasoning}
41	
42	\author{Anonymous}
43	
44	\begin{document}
45	\maketitle
46	
47	% Tighten spacing for 8-page budget
48	\setlength{\textfloatsep}{5pt plus 2pt minus 4pt}
49	\setlength{\dbltextfloatsep}{5pt plus 2pt minus 4pt}
50	\setlength{\floatsep}{3pt plus 2pt minus 2pt}
51	\setlength{\dblfloatsep}{3pt plus 2pt minus 2pt}
52	\setlength{\abovecaptionskip}{2pt}
53	\setlength{\belowcaptionskip}{0pt}
54	\setlength{\abovedisplayskip}{4pt plus 1pt minus 2pt}
55	\setlength{\belowdisplayskip}{4pt plus 1pt minus 2pt}
56	\setlength{\intextsep}{5pt plus 1pt minus 2pt}
57	
58	\input{abstract}
59	
60	\input{introduction}
61	
62	\input{related_work}
63	
64	\input{method}
65	
66	\input{experiments}
67	
68	\input{analysis}
69	
70	\input{solutions}
71	
72	\input{discussion}
73	
74	\vspace{-1mm}
75	\section*{Limitations}
76	\input{limitations_content}
77	
78	\bibliography{references}
79	
80	\appendix
81	\input{appendix}
82	

…[truncated 21 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 8 · 2026-05-23T01:19:40.103720+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "SCB|bias ratio|SICA|SC|traces|constraints|majority voting|notation",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/_project/paper",
  "type": "tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Grep",
  "tool_args": {
    "pattern": "SCB|bias ratio|SICA|SC|traces|constraints|majority voting|notation",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/_project/paper",
    "type": "tex",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 9 · 2026-05-23T01:19:40.103917+00:00_

artifacts/_project/paper/related_work.tex:5:[Omitted long matching line]
artifacts/_project/paper/related_work.tex:8:[Omitted long matching line]
artifacts/_project/paper/related_work.tex:11:[Omitted long matching line]
artifacts/_project/paper/related_work.tex:14:[Omitted long matching line]
artifacts/_project/paper/related_work.tex:17:[Omitted long matching line]
artifacts/_project/paper/related_work.tex:20:[Omitted long matching line]
artifacts/_project/paper/experiments.tex:7:We evaluate SICA against Self-Consistency (SC) across five instruction-tuned models and four reasoning benchmarks.
artifacts/_project/paper/experiments.tex:11:\paragraph{Datasets.} FOLIO~\cite{han2022folio} provides formal logic problems with gold first-order logic (FOL) annotations ($n=204$), which enable the oracle control experiment (\S\ref{sec:oracle}). ProofWriter~\cite{tafjord2021proofwriter} tests multi-step deductive reasoning ($n=600$). StrategyQA~\cite{geva2021strategyqa} evaluates commonsense reasoning ($n=200$ for LLaMA-3.1-8B; $n=60$ for other models). ARC-Challenge~\cite{clark2018arc} covers science questions ($n=60$).
artifacts/_project/paper/experiments.tex:13:\paragraph{Parameters.} Unless otherwise noted, we sample $K=12$ reasoning traces per question at temperature $T=0.7$. Z3~\cite{demoura2008z3} solves each MAX-SAT instance with a 10-second timeout. Temperature ablation experiments vary $T \in \{0.3, 0.5, 0.7, 1.0\}$.
artifacts/_project/paper/experiments.tex:15:\paragraph{Metrics.} We report accuracy (\%), the multi-candidate rate $C_0$ (\S\ref{sec:c0}), and the accuracy gap $\Delta = \text{SICA} - \text{SC}$ in percentage points (pp). Statistical significance is assessed with the McNemar test for paired binary outcomes at $\alpha = 0.05$. For adequately powered conditions ($n \geq 200$), we also compute 95\% bootstrap confidence intervals with 1{,}000 resamples.
artifacts/_project/paper/experiments.tex:18:\subsection{Main Results: SICA Provides No Significant Gain}
art
…[truncated 16857 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 10 · 2026-05-23T01:19:40.104096+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "SCB|bias ratio|SICA|SC|traces|constraints|majority voting|notation",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper",
  "type": "tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Grep",
  "tool_args": {
    "pattern": "SCB|bias ratio|SICA|SC|traces|constraints|majority voting|notation",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper",
    "type": "tex",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 11 · 2026-05-23T01:19:40.104296+00:00_

&lt;persisted-output>
Output too large (41.7KB). Full output saved to: /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-3-projects-symb-invariant-consensus/5f08a0b3-198f-4f40-8b69-e8e76d016497/tool-results/toolu_011xaFd8LzqeayLX18HUdVNb.txt

Preview (first 2KB):
docs/paper/analysis.tex:9:[Omitted long matching line]
docs/paper/analysis.tex:15:[Omitted long matching line]
docs/paper/analysis.tex:17:[Omitted long matching line]
docs/paper/analysis.tex:23:[Omitted long matching line]
docs/paper/analysis.tex:27:Model & Ext. & SC (\%) & $n_\text{err}$ & BR & $\Delta$ (pp) \\
docs/paper/analysis.tex:43:\looseness=-1 Two controls rule out answer leakage. BR is uniform across early, mid, and late reasoning steps (Fisher $p = 0.71$); high-consensus errors amplify to $\text{BR} = 18.8\times$ versus $2.7\times$ for low-consensus ($p < 0.001$). Removing the answer sentence from traces before extraction yields no BR decrease (Wilcoxon $p \geq 0.12$) despite significant accuracy loss (McNemar $p < 0.013$). SCB reflects a distributional prior embedded throughout reasoning, not answer contamination.
docs/paper/analysis.tex:48:[Omitted long matching line]
docs/paper/analysis.tex:51:CCR analysis confirms the same pattern: cross-architecture NLI yields $\text{CCR} > 0$ while same-model SICA yields $\text{CCR} < 0$, with CCR correlating with combo gain ($\rho = 0.84$, $p = 0.014$; Appendix~\ref{app:cil}).
docs/paper/analysis.tex:58:[Omitted long matching line]
docs/paper/analysis.tex:63:\caption{Twenty-three of 27 training-free strategies across four categories (four additional strategies tested but omitted for clarity). All produce neutral-to-negative $\Delta$ vs.\ SC. Grey band: $\pm 1$\,pp noise zone.}
docs/paper/analysis.tex:68:\looseness=-1 Decision boundaries ($C_0 < 5\%$, $K_\text{eff} \leq 1.3$, SC $< 40\%$) were derived from Mistral-7B and Qwen2.5-14B conditions. We evaluate prospectively on held-out LLaMA-3.1-8B, a different model family not 
…[truncated 300 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 12 · 2026-05-23T01:19:40.104527+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex"
  }
}
```

</details>

---

### Tool result

_source line 13 · 2026-05-23T01:19:40.104733+00:00_

1	\section{Background \& Setup}
2	\label{sec:method}
3	
4	\subsection{Self-Consistency and the Condorcet Independence Assumption}
5	\label{sec:condorcet}
6	
7	Self-Consistency (SC) \citep{wang2023sc} samples $K$ reasoning traces and selects the majority answer. The Condorcet Jury Theorem (CJT) \citep{condorcet1785} guarantees majority convergence under independent voters \citep{austensmith1996}, but LLM traces violate this independence. Following \citet{ladha1992correlated} and \citet{kish1965survey}, we define effective sample size using Fleiss' $\kappa$ \citep{fleiss1971kappa} as proxy for intraclass correlation:
8	\begin{equation}
9	\label{eq:effk}
10	K_{\text{eff}} = K \,/\, [1 + (K{-}1) \cdot \kappa].
11	\end{equation} In our experiments (\S\ref{sec:effective-k}), $\kappa = 0.21$--$0.82$ yields $K_{\text{eff}} \approx 1.2$--$3.6$ for $K{=}12$, serving as an ordinal diagnostic of vote diversity rather than a literal effective sample size. This independence limitation motivates our investigation.
12	
13	\subsection{SICA Pipeline}
14	\label{sec:pipeline}
15	
16	Symbolic Invariant Consensus Aggregation (SICA) extends SC by extracting formal constraints from traces and selecting the answer best supported by the satisfiable subset (Figure~\ref{fig:pipeline}).
17	
18	\paragraph{Trace generation.} Given question $q$, an LLM generates $K$ traces $\{t_1, \ldots, t_K\}$ at temperature $T = 0.7$. Each trace $t_i$ yields answer $a_i$.
19	
20	\paragraph{Constraint extraction.}\label{sec:constraint-extraction} The same LLM extracts logical constraints from each trace at $T_{\text{ext}} = 0.3$. The extraction prompt requests JSON output with constraint type, expression, and Z3-compatible formula (Appendix~\ref{app:prompts}); in practice, 99.0\% of extracted constraints are propositional at the Z3 level, with only 1.0\% using true quantifiers. The \emph{extraction rate} is the fraction of traces yielding at least one parseable constraint.
21	
22	\paragraph{Deduplication and MAX
…[truncated 5426 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 14 · 2026-05-23T01:19:40.105022+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex"
  }
}
```

</details>

---

### Tool result

_source line 15 · 2026-05-23T01:19:40.105239+00:00_

1	\section{Analysis}
2	\label{sec:analysis}
3	
4	\looseness=-1 We test the three predictions of the symbolic mirage hypothesis (\S\ref{sec:mirage}).
5	
6	\subsection{Condorcet Effective-K}
7	\label{sec:effective-k}
8	
9	\looseness=-1 Table~\ref{tab:independence} (Appendix) reports Fleiss' $\kappa$ and Effective-K (Eq.~\ref{eq:effk}) across 15 conditions at $K = 12$. Among instruction-tuned models, $\kappa$ ranges from 0.21 to 0.82, yielding $K_{\text{eff}} = 1.20\text{--}3.62$ as an ordinal diagnostic: higher $K_{\text{eff}}$ indicates greater vote diversity, though it should not be interpreted as a literal effective sample size (\S\ref{sec:condorcet}). Across four Mistral-7B seeds, $\kappa \in [0.41, 0.51]$ yet $\Delta$ ranges from $+3.43$ to $-0.49$\,pp, indicating seed-level constraint quality matters beyond independence. Positive $\Delta$ requires both sufficient $K_{\text{eff}}$ ($\leq 1.30$ never improves) and SC accuracy ($K_{\text{eff}} = 3.62$ with SC $= 39\%$ degrades). All four model families produce $\kappa \geq 0.41$ (Table~\ref{tab:kappa_generalization}).
10	
11	
12	\subsection{Symbolic Confirmation Bias}
13	\label{sec:confirmation-bias}
14	
15	\looseness=-1 Self-extracted constraints systematically align with the model's majority answer. On Mistral-7B FOLIO, when SICA errs, 83.3\% of constraints support the incorrect answer---bias ratio $4.97\times$ (Table~\ref{tab:cross-model-bias})---and 94\% of errors overlap with SC. A shuffle control reveals this bias is \emph{structural}: randomizing constraint--answer associations while preserving per-trace counts yields $\text{BR}_\text{null} \approx \text{BR}_\text{obs}$ ($p > 0.7$), indicating that BR reflects the trace-count distribution rather than extraction-specific error. Z3 rejects only 3.4\% of constraints, and MAX-SAT produces answers identical to count-only aggregation on 94.4\% of problems on Mistral-7B FOLIO (Table~\ref{tab:ablation}), confirming that the formal verification layer is vacuous (Eq.~
…[truncated 6924 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 16 · 2026-05-23T01:19:40.105456+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/appendix.tex"
  }
}
```

</details>

---

### Tool result

_source line 17 · 2026-05-23T01:19:40.105621+00:00_

File content (30865 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 18 · 2026-05-23T01:19:40.105791+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "\\\\(SCB|BR|SICA|C_0|K_\\\\\\\\text\\{eff\\}|\\\\\\\\sigma|\\\\\\\\mathcal\\{C\\})",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper",
  "type": "tex",
  "output_mode": "content",
  "head_limit": "100"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Grep",
  "tool_args": {
    "pattern": "\\\\(SCB|BR|SICA|C_0|K_\\\\\\\\text\\{eff\\}|\\\\\\\\sigma|\\\\\\\\mathcal\\{C\\})",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper",
    "type": "tex",
    "output_mode": "content",
    "head_limit": "100"
  }
}
```

</details>

---

### Tool result

_source line 19 · 2026-05-23T01:19:40.105974+00:00_

No matches found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 20 · 2026-05-23T01:19:40.106139+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/appendix.tex",
  "limit": "150"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/appendix.tex",
    "limit": "150"
  }
}
```

</details>

---

### Tool result

_source line 21 · 2026-05-23T01:19:40.106332+00:00_

1	\section{Regime Scatter Plot}
2	\label{app:regime-scatter}
3	
4	\begin{figure}[t]
5	\centering
6	\includegraphics[width=\columnwidth]{f2_regime_scatter}
7	\caption{SICA $\Delta$ (pp) vs.\ SC baseline. Filled: $n \geq 100$; open: $n < 100$. The intermediate-SC region (50--60\%, shaded) contains the only positive trends (none reaching $p < 0.05$). Type~C: nominally significant degradation (raw $p = 0.014$; BH adj.\ $p = 0.112$).}
8	\label{fig:regime-scatter}
9	\end{figure}
10	
11	\section{Prompt Templates}
12	\label{app:prompts}
13	
14	SICA uses domain-specific prompt templates for constraint extraction: one for mathematical reasoning (GSM8K, AIME) and one for logical reasoning (ProofWriter, FOLIO). Both share the same system prompt. The LLM is called with temperature $T{=}0.3$, max tokens $1024$, and structured JSON output mode. Up to 6 traces are processed in parallel via thread pooling, with 2 retries on failure (exponential backoff, base 0.5s).
15	
16	\paragraph{System Prompt.}
17	
18	\begin{lstlisting}
19	You are a constraint extraction tool. Output ONLY
20	valid JSON. Do NOT solve problems, reason about
21	correctness, or think step-by-step. Extract
22	constraints from the given trace exactly as stated.
23	\end{lstlisting}
24	
25	\paragraph{Mathematical Constraint Extraction (EXTRACTION\_PROMPT).}
26	
27	Used for GSM8K and AIME datasets. The placeholder \texttt{\{trace\}} is replaced with the reasoning trace at runtime.
28	
29	\begin{lstlisting}
30	Extract mathematical constraints from this reasoning
31	trace as a JSON object.
32	
33	Rules:
34	- type: "equation", "inequality", or "predicate"
35	- expression: human-readable, e.g. "x + y == 14"
36	- z3_formula: a single comparison expression in
37	  Python Z3 syntax
38	- source_step: step number where the constraint
39	  appears
40	- Use variable names from the trace
41	
42	z3_formula MUST follow these rules:
43	- Allowed operators: ==, !=, <, >, <=, >=, +, -, *,
44	  /, **, %
45	- Use individual named variables
…[truncated 3308 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 22 · 2026-05-23T01:19:40.106570+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 23 · 2026-05-23T01:19:40.106784+00:00_

1	\section{Introduction}\label{sec:introduction}
2	
3	Test-time computation scaling through multiple reasoning samples has emerged as a practical alternative to scaling model parameters \citep{snell2025scaling, guo2025deepseekr1}.
4	The dominant aggregation strategy, Self-Consistency (SC) \citep{wang2023sc}, samples $K$ chain-of-thought traces and selects the majority answer.
5	SC is simple, model-agnostic, and effective---but it is hitting a ceiling.
6	\citet{loo2025reevaluating} demonstrate that gains from increasing $K$ plateau and even decline for strong models.
7	The gap between SC's theoretical promise (independent correct voters converge to truth) and its practical behavior (saturating gains) points to a structural mismatch: same-model traces carry correlated errors, and majority voting has no mechanism to correct shared bias.
8	
9	Confidence-weighted \citep{taubenfeld2025cisc} and universal \citep{chen2024usc} extensions alleviate this, but the core limitation persists.
10	Recent neuro-symbolic methods \citep{pan2023logiclm, olausson2023linc, xu2026dylos, li2025aristotle, wang2025fover, luo2025logicagent} report gains on logical reasoning but introduce components beyond the reasoning model.
11	A simpler question precedes these: can the \emph{same} model extract useful formal constraints from its own traces---a zero-cost upgrade requiring no additional model or data?
12	No prior work has systematically evaluated this.
13	
14	We ground our analysis in the Condorcet Jury Theorem (CJT) \citep{condorcet1785}: if $K$ independent voters each answer correctly with probability $p > 0.5$, the majority converges to truth \citep{austensmith1996}.
15	When independence fails \citep{ladha1992correlated}, additional samples carry diminishing information.
16	Measuring inter-trace agreement with Fleiss' $\kappa$ \citep{fleiss1971kappa}, we find $\kappa = 0.21$--$0.82$ across instruction-tuned conditions, yielding $K_{\text{eff}}$ as an ordinal diagnostic of vote diversity ($K
…[truncated 6808 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-23T01:19:40.107028+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/experiments.tex",
  "limit": "100"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/experiments.tex",
    "limit": "100"
  }
}
```

</details>

---

### Tool result

_source line 25 · 2026-05-23T01:19:40.107232+00:00_

1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\subsection{Setup}
5	\label{sec:exp-setup}
6	
7	We evaluate SICA against Self-Consistency (SC) across six models, three reasoning domains, and over 3,000 condition-evaluations (${\sim}$1,250 unique instances), with diagnostic analyses of confirmation bias and process-level independence (\S\ref{sec:analysis}).
8	
9	\paragraph{Models.} Qwen2.5-14B-Instruct, Qwen2.5-7B-Instruct, Qwen3-14B (non-thinking mode)~\citep{yang2024qwen25}, Mistral-7B-Instruct-v0.3~\citep{jiang2023mistral}, LLaMA-3.1-8B-Instruct~\citep{dubey2024llama3}, and QwQ-32B~\citep{qwen2024qwq} (7B--32B). We additionally evaluate SCB universality via cross-model extraction on five frontier models (gpt-4o, gpt-4.1, gpt-5.5, o3, Gemini-2.5-Pro; Table~\ref{tab:frontier-scb}), where Mistral-7B extracts constraints from the target model's traces since closed-source APIs do not expose internals suitable for self-extraction.
10	
11	\paragraph{Datasets.} FOLIO~\citep{han2022folio} ($n{=}204$, with gold logical annotations), ProofWriter depth-5~\citep{tafjord2021proofwriter} ($n{=}600$), LogiQA~\citep{liu2020logiqa} ($n{=}200$). StrategyQA~\citep{geva2021strategyqa} ($n{=}200$) serves as a domain-formalizability diagnostic. GSM8K~\citep{cobbe2021gsm8k} (exploratory, $n{=}30$) and AIME 2024 ($n{=}22$) probe the degenerate regime ($C_0 < 5\%$).
12	
13	\paragraph{Parameters.} $K{=}12$ traces at $T{=}0.7$, extraction at $T_{\text{ext}}{=}0.3$, $\alpha{=}0.5$, Z3 timeout 10s. McNemar exact test ($\alpha{=}0.05$); 95\% bootstrap CIs ($10{,}000$ resamples) for $n \geq 200$. SICA incurs $4.5{\times}$ SC wall-clock; extraction accounts for 76\% of overhead.
14	
15	
16	\subsection{Main Results}
17	\label{sec:main-results}
18	
19	Table~\ref{tab:main_results} reports accuracy across all conditions sorted by SC baseline, revealing three observation-driven accuracy regimes.
20	
21	\begin{table*}[t]
22	\centering
23	\small
24	\caption{SICA vs.\ SC across all non-degenerate 
…[truncated 4100 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-23T01:19:40.107441+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "C_0|multi-candidate|trace|reasoning trace|constraint",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex",
  "output_mode": "content",
  "context": "3"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Grep",
  "tool_args": {
    "pattern": "C_0|multi-candidate|trace|reasoning trace|constraint",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex",
    "output_mode": "content",
    "context": "3"
  }
}
```

</details>

---

### Tool result

_source line 27 · 2026-05-23T01:19:40.107634+00:00_

4-\subsection{Self-Consistency and the Condorcet Independence Assumption}
5-\label{sec:condorcet}
6-
7:Self-Consistency (SC) \citep{wang2023sc} samples $K$ reasoning traces and selects the majority answer. The Condorcet Jury Theorem (CJT) \citep{condorcet1785} guarantees majority convergence under independent voters \citep{austensmith1996}, but LLM traces violate this independence. Following \citet{ladha1992correlated} and \citet{kish1965survey}, we define effective sample size using Fleiss' $\kappa$ \citep{fleiss1971kappa} as proxy for intraclass correlation:
8-\begin{equation}
9-\label{eq:effk}
10-K_{\text{eff}} = K \,/\, [1 + (K{-}1) \cdot \kappa].
--
13-\subsection{SICA Pipeline}
14-\label{sec:pipeline}
15-
16:Symbolic Invariant Consensus Aggregation (SICA) extends SC by extracting formal constraints from traces and selecting the answer best supported by the satisfiable subset (Figure~\ref{fig:pipeline}).
17-
18:\paragraph{Trace generation.} Given question $q$, an LLM generates $K$ traces $\{t_1, \ldots, t_K\}$ at temperature $T = 0.7$. Each trace $t_i$ yields answer $a_i$.
19-
20:[Omitted long matching line]
21-
22:\paragraph{Deduplication and MAX-SAT.} Constraints are deduplicated by syntactic equivalence (global average deduplication ratio: 46.0\%); each unique constraint $c_m$ receives weight $w_m$ equal to the number of source traces. The objective finds the largest-weight satisfiable subset:
23-\begin{equation}
24-\label{eq:maxsat}
25-\mathcal{C}^* = \arg\max_{\mathcal{S} \subseteq \mathcal{C}} \sum_{c \in \mathcal{S}} w_c \quad \text{s.t.} \quad \mathcal{S} \text{ is satisfiable.}
26-\end{equation}
27:Z3 \citep{demoura2008z3} solves this with a 10-second timeout. Answer assertion constraints ($\texttt{answer\_a} == \texttt{True}$, weight 1) ensure every candidate receives a nonzero base score, making SICA a strict generalization of SC.
28-
29-\paragraph{Scoring.} Let $\mathcal{C}^{\setminus} = \mathcal{C} \setminus \mathcal{C}^*$. Each candidate $a$ is sc
…[truncated 2090 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-23T01:19:40.107854+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "find /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus -name \"main.tex\" -o -name \"paper.tex\" | head -20"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Bash",
  "tool_args": {
    "command": "find /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus -name \"main.tex\" -o -name \"paper.tex\" | head -20"
  }
}
```

</details>

---

### Tool result

_source line 29 · 2026-05-23T01:19:40.108057+00:00_

/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/main.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260516T124139/median/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260516T124139/worst/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260516T124139/best/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260516T155754/median/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260516T155754/worst/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260516T155754/best/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260516T054054/median/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260516T054054/worst/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260516T054054/best/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260519T034058/median/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260519T034058/worst/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260519T034058/best/paper.tex
/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/dream_reports/dream_20260517T144412/median/paper.tex
/home/ubuntu/.agent-ml-re
…[truncated 838 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 30 · 2026-05-23T01:19:40.108262+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "degeneration|majority voting|answer assertion|deduplication",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper",
  "type": "tex",
  "output_mode": "content",
  "head_limit": "50"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Grep",
  "tool_args": {
    "pattern": "degeneration|majority voting|answer assertion|deduplication",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper",
    "type": "tex",
    "output_mode": "content",
    "head_limit": "50"
  }
}
```

</details>

---

### Tool result

_source line 31 · 2026-05-23T01:19:40.108440+00:00_

docs/paper/analysis.tex:15:[Omitted long matching line]
docs/paper/analysis.tex:17:[Omitted long matching line]
docs/paper/method.tex:22:\paragraph{Deduplication and MAX-SAT.} Constraints are deduplicated by syntactic equivalence (global average deduplication ratio: 46.0\%); each unique constraint $c_m$ receives weight $w_m$ equal to the number of source traces. The objective finds the largest-weight satisfiable subset:
docs/paper/method.tex:41:equivalent to majority voting. We show in \S\ref{sec:confirmation-bias} that this degeneration occurs in practice.
docs/paper/method.tex:48:[Omitted long matching line]
docs/paper/limitations_content.tex:1:[Omitted long matching line]
docs/paper/abstract.tex:1:Self-Consistency (SC) majority voting over chain-of-thought traces saturates as sample count grows because same-model traces are correlated voters.
docs/paper/abstract.tex:4:[Omitted long matching line]
docs/paper/appendix.tex:162:Domain constraint variables (e.g., \texttt{x + y == 14}) and answer assertion variables (e.g., \texttt{\_\_sica\_answer\_42 == True}) are logically independent in the Z3 formulation. Discriminative signal arises solely from conflicts among domain constraints: when traces supporting different answers produce mutually contradictory constraints, the solver excludes the lower-weight subset, and the scorer penalizes the corresponding answers.
docs/paper/appendix.tex:312:All three intervals contain zero. The narrowest interval (Qwen-14B, [$-$1.12, $+$1.62]) rules out practically meaningful gains ($>$2pp) even in the most favorable case. The widest interval (LLaMA-8B FOLIO, [$-$5.88, $+$0.98]) skews negative, indicating that SICA may slightly hurt accuracy in this condition. These results corroborate the McNemar tests and power analysis: no condition provides evidence that logical constraint aggregation improves over majority voting.
docs/paper/appendix.tex:524:[Omitted long matching line]
docs/paper/appendix.tex:1190:\emph{Effective-K} ($K_\text{eff
…[truncated 833 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 32 · 2026-05-23T01:19:40.108744+00:00_

Perfect! I have gathered comprehensive information. Let me compile the final report with all the relevant findings.

## Summary: Notation and Definitions in the Symb_Invariant_Consensus Project

### Main Paper File
**Primary location:** `/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/main.tex`

This is the main paper file that orchestrates the entire document structure through includes of specialized sections.

---

### Key Notation Definitions Found

#### **1. SCB (Symbolic Confirmation Bias)**
**File:** `/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex` (lines 12-18)

SCB is defined as the systematic alignment of self-extracted constraints with the model's majority answer:
- On Mistral-7B FOLIO: when SICA errs, 83.3% of constraints support the incorrect answer
- Bias ratio values across nine models: 1.66--4.97× all greater than 1.0
- SCB reflects a distributional prior embedded throughout reasoning, not answer contamination
- The bias is structural: randomizing constraint-answer associations while preserving per-trace counts yields the same BR distribution

#### **2. BR (Bias Ratio)**
**File:** `/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex` (lines 48-52)

Formal definition (Equation 1 - eq:mirage):
```tex
BR(M,T) = P(c supports a_M | a_M ≠ a*) / P(c supports a* | a_M ≠ a*)
```
Where:
- c = self-extracted constraint
- a_M = model's answer
- a* = ground truth answer
- BR > 1 indicates constraints project model bias rather than provide independent verification
- Empirical findings: BR > 1.0 across all tested self-extraction conditions

#### **3. SICA (Symbolic Invariant Consensus Aggregation)**
**Files:** `/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex` (lines 13-42)

SICA extends SC by extracting formal constraints from traces and selecting the answer
…[truncated 6138 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Agent",
  "elapsed_ms": 6
}
```

</details>

---

### Tool call

_source line 33 · 2026-05-23T01:19:40.109645+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex",
  "limit": "80"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex",
    "limit": "80"
  }
}
```

</details>

---

### Tool result

_source line 34 · 2026-05-23T01:19:40.109974+00:00_

1	\section{Analysis}
2	\label{sec:analysis}
3	
4	\looseness=-1 We test the three predictions of the symbolic mirage hypothesis (\S\ref{sec:mirage}).
5	
6	\subsection{Condorcet Effective-K}
7	\label{sec:effective-k}
8	
9	\looseness=-1 Table~\ref{tab:independence} (Appendix) reports Fleiss' $\kappa$ and Effective-K (Eq.~\ref{eq:effk}) across 15 conditions at $K = 12$. Among instruction-tuned models, $\kappa$ ranges from 0.21 to 0.82, yielding $K_{\text{eff}} = 1.20\text{--}3.62$ as an ordinal diagnostic: higher $K_{\text{eff}}$ indicates greater vote diversity, though it should not be interpreted as a literal effective sample size (\S\ref{sec:condorcet}). Across four Mistral-7B seeds, $\kappa \in [0.41, 0.51]$ yet $\Delta$ ranges from $+3.43$ to $-0.49$\,pp, indicating seed-level constraint quality matters beyond independence. Positive $\Delta$ requires both sufficient $K_{\text{eff}}$ ($\leq 1.30$ never improves) and SC accuracy ($K_{\text{eff}} = 3.62$ with SC $= 39\%$ degrades). All four model families produce $\kappa \geq 0.41$ (Table~\ref{tab:kappa_generalization}).
10	
11	
12	\subsection{Symbolic Confirmation Bias}
13	\label{sec:confirmation-bias}
14	
15	\looseness=-1 Self-extracted constraints systematically align with the model's majority answer. On Mistral-7B FOLIO, when SICA errs, 83.3\% of constraints support the incorrect answer---bias ratio $4.97\times$ (Table~\ref{tab:cross-model-bias})---and 94\% of errors overlap with SC. A shuffle control reveals this bias is \emph{structural}: randomizing constraint--answer associations while preserving per-trace counts yields $\text{BR}_\text{null} \approx \text{BR}_\text{obs}$ ($p > 0.7$), indicating that BR reflects the trace-count distribution rather than extraction-specific error. Z3 rejects only 3.4\% of constraints, and MAX-SAT produces answers identical to count-only aggregation on 94.4\% of problems on Mistral-7B FOLIO (Table~\ref{tab:ablation}), confirming that the formal verification layer is vacuous (Eq.~
…[truncated 6924 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 35 · 2026-05-23T01:19:40.110206+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex",
  "limit": "70"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex",
    "limit": "70"
  }
}
```

</details>

---

### Tool result

_source line 36 · 2026-05-23T01:19:40.110464+00:00_

1	\section{Background \& Setup}
2	\label{sec:method}
3	
4	\subsection{Self-Consistency and the Condorcet Independence Assumption}
5	\label{sec:condorcet}
6	
7	Self-Consistency (SC) \citep{wang2023sc} samples $K$ reasoning traces and selects the majority answer. The Condorcet Jury Theorem (CJT) \citep{condorcet1785} guarantees majority convergence under independent voters \citep{austensmith1996}, but LLM traces violate this independence. Following \citet{ladha1992correlated} and \citet{kish1965survey}, we define effective sample size using Fleiss' $\kappa$ \citep{fleiss1971kappa} as proxy for intraclass correlation:
8	\begin{equation}
9	\label{eq:effk}
10	K_{\text{eff}} = K \,/\, [1 + (K{-}1) \cdot \kappa].
11	\end{equation} In our experiments (\S\ref{sec:effective-k}), $\kappa = 0.21$--$0.82$ yields $K_{\text{eff}} \approx 1.2$--$3.6$ for $K{=}12$, serving as an ordinal diagnostic of vote diversity rather than a literal effective sample size. This independence limitation motivates our investigation.
12	
13	\subsection{SICA Pipeline}
14	\label{sec:pipeline}
15	
16	Symbolic Invariant Consensus Aggregation (SICA) extends SC by extracting formal constraints from traces and selecting the answer best supported by the satisfiable subset (Figure~\ref{fig:pipeline}).
17	
18	\paragraph{Trace generation.} Given question $q$, an LLM generates $K$ traces $\{t_1, \ldots, t_K\}$ at temperature $T = 0.7$. Each trace $t_i$ yields answer $a_i$.
19	
20	\paragraph{Constraint extraction.}\label{sec:constraint-extraction} The same LLM extracts logical constraints from each trace at $T_{\text{ext}} = 0.3$. The extraction prompt requests JSON output with constraint type, expression, and Z3-compatible formula (Appendix~\ref{app:prompts}); in practice, 99.0\% of extracted constraints are propositional at the Z3 level, with only 1.0\% using true quantifiers. The \emph{extraction rate} is the fraction of traces yielding at least one parseable constraint.
21	
22	\paragraph{Deduplication and MAX
…[truncated 5426 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 37 · 2026-05-23T01:19:40.110731+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/ 2>/dev/null | head -20",
  "description": "List artifacts directory"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Bash",
  "tool_args": {
    "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/ 2>/dev/null | head -20",
    "description": "List artifacts directory"
  }
}
```

</details>

---

### Tool result

_source line 38 · 2026-05-23T01:19:40.110938+00:00_

_extracted
_project
ablation_text.py
aime30_v2_partial_analysis.md
aime_bias_ratio_results.json
analysis_exp045.md
analysis_prove_verify.py
analyze_adaptive_sica.py
analyze_discriminative_rate.py
analyze_expanded.py
analyze_seed_replication.py
appendix_prompt_template.md
backward_verification.py
baf_decoupled_results.json
bootstrap_br.py
br_bootstrap_ci.json
capability_gap_scatter_v2.pdf
capability_gap_scatter_v2.png
case_study_materials.md
causal_dag_tikz.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 39 · 2026-05-23T01:19:40.111220+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/proposition1_scb_proof.tex",
  "content": "% Proposition 1: Symbolic Confirmation Bias is Structural\n% Place after the empirical BR paragraph in §3.2 (analysis.tex, ~line 17),\n% or at the end of §2.3 (method.tex) after Eq.(4) degeneration condition.\n% Requires: amsmath, amssymb, enumitem (all already loaded in main.tex).\n\n\\textbf{Proposition 1} \\textit{(Symbolic Confirmation Bias is Structural).}\\;%\nLet $t_1, \\dots, t_K \\overset{\\mathrm{i.i.d.}}{\\sim} P_M(\\cdot \\mid q)$ be reasoning traces from model $M$ on question $q$.\nAssume:\n\\begin{enumerate}[label=\\textbf{A\\arabic*.},leftmargin=2.5em,nosep]\n\\item Answers are trace-determined: $a_i = h(t_i)$.\n\\item Constraints are trace-determined: $c_i = f(t_i)$.\n\\end{enumerate}\nLet $\\hat{a} = \\mathrm{mode}(a_1, \\dots, a_K)$, $n_a = |\\{i : a_i = a\\}|$, and $Y$ the ground truth. Then:\n\\begin{enumerate}[label=\\textit{(\\roman*)},leftmargin=1.8em,itemsep=2pt,topsep=3pt]\n\\item \\textit{Voting degeneration.}\\;\nUnder source attribution $\\sigma(c_i, a) \\triangleq \\mathbf{1}[a_i = a]$, the constraint score reduces to the majority-vote count: $\\operatorname{score}(a) = n_a$.\nWhen $|\\{a : n_a > 0\\}| \\geq 2$, the bias ratio satisfies $\\mathrm{BR} \\triangleq n_{\\hat{a}} \\big/ \\max_{a' \\neq \\hat{a}} n_{a'} \\geq 1$.\n\n\\item \\textit{Information ceiling.}\\;\n$I(C_{1:K};\\, Y) \\leq I(T_{1:K};\\, Y)$ and $I(C_{1:K};\\, Y \\mid A_{1:K}) \\leq I(T_{1:K};\\, Y \\mid A_{1:K})$:\nself-extracted constraints cannot carry more information about $Y$ than the source traces---even beyond what the answers already encode.\n\\end{enumerate}\n\\noindent\nBoth bounds hold for \\emph{any} model $M$, task $q$, and extraction function $f$.\n\n\\medskip\n\\textit{Proof.}\\;%\n\\textit{(i)}\\; By definition, $\\operatorname{score}(a) = \\sum_{i=1}^K \\mathbf{1}[a_i = a] = n_a$, maximized at $\\hat{a}$, so $\\mathrm{BR} \\geq 1$.\n\\textit{(ii)}\\; $c_i = f(t_i)$ makes $C_{1:K}$ a deterministic function of $T_{1:K}$, so $Y \\mathop{\\text{---}} T_{1:K} \\mathop{\\text{---}} C_{1:K}$ forms a Markov chain and the data processing inequality gives $I(C_{1:K}; Y) \\leq I(T_{1:K}; Y)$.\nThe conditional bound follows identically: $c_i = f(t_i)$ holds unconditionally, so the Markov property and DPI apply within each stratum $\\{A_{1:K} = \\mathbf{a}\\}$.\\hfill$\\square$\n\n\\medskip\\noindent\nEach constraint is a downstream product of a trace that simultaneously determines an answer; constraint-based aggregation therefore cannot escape the distributional bias of the answer vote.\nNeither bound depends on model capability, task difficulty, or extraction quality---the bias is a structural artifact of the self-extraction pipeline.\n\n\\medskip\\noindent\n\\textbf{Remark.}\\;%\nPart~\\textit{(i)} relies on source attribution (Eq.~\\ref{eq:score}), the mechanism used by SICA.\nUnder \\emph{semantic} evaluation---checking whether $c_i$ is logically consistent with answer $a$ directly---$\\mathrm{BR} \\geq 1$ additionally requires \\emph{answer alignment}: $P(c_i \\text{ supports } a_i) \\geq P(c_i \\text{ supports } a')$ for $a' \\neq a_i$.\nThis property is structurally motivated (the reasoning chain producing $a_i$ generates intermediate steps aligned with $a_i$) and is empirically validated across all nine model--task conditions ($\\mathrm{BR} \\in [1.66,\\, 4.97]$; Table~\\ref{tab:frontier-scb}), but is not a mathematical necessity of self-extraction alone---it could fail if $f$ systematically extracted premises that contradict their source trace's conclusion.\n\n% ============================================================\n% AUTHOR NOTE: Honesty check on proof strength\n% ============================================================\n%\n% 1. Part (i) is intentionally trivial. The triviality IS the contribution:\n%    it makes explicit that source attribution (σ function) renders the\n%    constraint layer exactly redundant with answer counting. The simplicity\n%    underscores that SCB is not a subtle empirical phenomenon but an\n%    immediate structural consequence.\n%\n% 2. Part (ii) uses only the standard DPI, requiring no assumptions beyond\n%    A1-A2. The conditional form I(C;Y|A) ≤ I(T;Y|A) is the stronger\n%    result: it says constraints add no *independent* verification signal\n%    beyond the traces themselves. Note this does NOT say I(C;Y|A) = 0;\n%    constraints may carry some info about Y beyond A, but only info already\n%    present in T. True independence requires breaking the T→C pipeline.\n%\n% 3. BR ≥ 1 is deterministic (holds for every realization), not just\n%    E[BR] ≥ 1. It equals 1 iff â ties with a runner-up. This is stronger\n%    than the empirical finding and explains why BR > 1 universally.\n%\n% 4. The Remark is essential for intellectual honesty: under semantic\n%    attribution, answer alignment is needed and is NOT a pure structural\n%    guarantee. However, since SICA actually uses source attribution, the\n%    main Proposition stands unconditionally.\n%\n% 5. Potential reviewer pushback: \"This is obvious.\" Response: if it were\n%    obvious, prior work (including the original SICA paper) would not have\n%    proposed self-extraction as a verification mechanism. The proposition\n%    formalizes why that mechanism is structurally vacuous.\n%\n% 6. Deduplication caveat: with constraint deduplication, a constraint\n%    shared across answer groups contributes equally to all scores (cancels\n%    out). Answer-specific constraints drive the ranking, and these are\n%    proportional to trace counts. In the degenerate case where minority\n%    traces produce disproportionately more *unique* constraints, BR could\n%    theoretically drop below 1. Empirically this never happens (Table 5).\n%    The proposition covers the pre-deduplication base case; the\n%    degeneration condition (Eq.4) covers the practical case.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/proposition1_scb_proof.tex",
    "content": "% Proposition 1: Symbolic Confirmation Bias is Structural\n% Place after the empirical BR paragraph in §3.2 (analysis.tex, ~line 17),\n% or at the end of §2.3 (method.tex) after Eq.(4) degeneration condition.\n% Requires: amsmath, amssymb, enumitem (all already loaded in main.tex).\n\n\\textbf{Proposition 1} \\textit{(Symbolic Confirmation Bias is Structural).}\\;%\nLet $t_1, \\dots, t_K \\overset{\\mathrm{i.i.d.}}{\\sim} P_M(\\cdot \\mid q)$ be reasoning traces from model $M$ on question $q$.\nAssume:\n\\begin{enumerate}[label=\\textbf{A\\arabic*.},leftmargin=2.5em,nosep]\n\\item Answers are trace-determined: $a_i = h(t_i)$.\n\\item Constraints are trace-determined: $c_i = f(t_i)$.\n\\end{enumerate}\nLet $\\hat{a} = \\mathrm{mode}(a_1, \\dots, a_K)$, $n_a = |\\{i : a_i = a\\}|$, and $Y$ the ground truth. Then:\n\\begin{enumerate}[label=\\textit{(\\roman*)},leftmargin=1.8em,itemsep=2pt,topsep=3pt]\n\\item \\textit{Voting degeneration.}\\;\nUnder source attribution $\\sigma(c_i, a) \\triangleq \\mathbf{1}[a_i = a]$, the constraint score reduces to the majority-vote count: $\\operatorname{score}(a) = n_a$.\nWhen $|\\{a : n_a > 0\\}| \\geq 2$, the bias ratio satisfies $\\mathrm{BR} \\triangleq n_{\\hat{a}} \\big/ \\max_{a' \\neq \\hat{a}} n_{a'} \\geq 1$.\n\n\\item \\textit{Information ceiling.}\\;\n$I(C_{1:K};\\, Y) \\leq I(T_{1:K};\\, Y)$ and $I(C_{1:K};\\, Y \\mid A_{1:K}) \\leq I(T_{1:K};\\, Y \\mid A_{1:K})$:\nself-extracted constraints cannot carry more information about $Y$ than the source traces---even beyond what the answers already encode.\n\\end{enumerate}\n\\noindent\nBoth bounds hold for \\emph{any} model $M$, task $q$, and extraction function $f$.\n\n\\medskip\n\\textit{Proof.}\\;%\n\\textit{(i)}\\; By definition, $\\operatorname{score}(a) = \\sum_{i=1}^K \\mathbf{1}[a_i = a] = n_a$, maximized at $\\hat{a}$, so $\\mathrm{BR} \\geq 1$.\n\\textit{(ii)}\\; $c_i = f(t_i)$ makes $C_{1:K}$ a deterministic function of $T_{1:K}$, so $Y \\mathop{\\text{---}} T_{1:K} \\mathop{\\text{---}} C_{1:K}$ forms a Markov chain and the data processing inequality gives $I(C_{1:K}; Y) \\leq I(T_{1:K}; Y)$.\nThe conditional bound follows identically: $c_i = f(t_i)$ holds unconditionally, so the Markov property and DPI apply within each stratum $\\{A_{1:K} = \\mathbf{a}\\}$.\\hfill$\\square$\n\n\\medskip\\noindent\nEach constraint is a downstream product of a trace that simultaneously determines an answer; constraint-based aggregation therefore cannot escape the distributional bias of the answer vote.\nNeither bound depends on model capability, task difficulty, or extraction quality---the bias is a structural artifact of the self-extraction pipeline.\n\n\\medskip\\noindent\n\\textbf{Remark.}\\;%\nPart~\\textit{(i)} relies on source attribution (Eq.~\\ref{eq:score}), the mechanism used by SICA.\nUnder \\emph{semantic} evaluation---checking whether $c_i$ is logically consistent with answer $a$ directly---$\\mathrm{BR} \\geq 1$ additionally requires \\emph{answer alignment}: $P(c_i \\text{ supports } a_i) \\geq P(c_i \\text{ supports } a')$ for $a' \\neq a_i$.\nThis property is structurally motivated (the reasoning chain producing $a_i$ generates intermediate steps aligned with $a_i$) and is empirically validated across all nine model--task conditions ($\\mathrm{BR} \\in [1.66,\\, 4.97]$; Table~\\ref{tab:frontier-scb}), but is not a mathematical necessity of self-extraction alone---it could fail if $f$ systematically extracted premises that contradict their source trace's conclusion.\n\n% ============================================================\n% AUTHOR NOTE: Honesty check on proof strength\n% ============================================================\n%\n% 1. Part (i) is intentionally trivial. The triviality IS the contribution:\n%    it makes explicit that source attribution (σ function) renders the\n%    constraint layer exactly redundant with answer counting. The simplicity\n%    underscores that SCB is not a subtle empirical phenomenon but an\n%    immediate structural consequence.\n%\n% 2. Part (ii) uses only the standard DPI, requiring no assumptions beyond\n%    A1-A2. The conditional form I(C;Y|A) ≤ I(T;Y|A) is the stronger\n%    result: it says constraints add no *independent* verification signal\n%    beyond the traces themselves. Note this does NOT say I(C;Y|A) = 0;\n%    constraints may carry some info about Y beyond A, but only info already\n%    present in T. True independence requires breaking the T→C pipeline.\n%\n% 3. BR ≥ 1 is deterministic (holds for every realization), not just\n%    E[BR] ≥ 1. It equals 1 iff â ties with a runner-up. This is stronger\n%    than the empirical finding and explains why BR > 1 universally.\n%\n% 4. The Remark is essential for intellectual honesty: under semantic\n%    attribution, answer alignment is needed and is NOT a pure structural\n%    guarantee. However, since SICA actually uses source attribution, the\n%    main Proposition stands unconditionally.\n%\n% 5. Potential reviewer pushback: \"This is obvious.\" Response: if it were\n%    obvious, prior work (including the original SICA paper) would not have\n%    proposed self-extraction as a verification mechanism. The proposition\n%    formalizes why that mechanism is structurally vacuous.\n%\n% 6. Deduplication caveat: with constraint deduplication, a constraint\n%    shared across answer groups contributes equally to all scores (cancels\n%    out). Answer-specific constraints drive the ranking, and these are\n%    proportional to trace counts. In the degenerate case where minority\n%    traces produce disproportionately more *unique* constraints, BR could\n%    theoretically drop below 1. Empirically this never happens (Table 5).\n%    The proposition covers the pre-deduplication base case; the\n%    degeneration condition (Eq.4) covers the practical case.\n"
  }
}
```

</details>

---

### Tool result

_source line 40 · 2026-05-23T01:19:40.111536+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/proposition1_scb_proof.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 41 · 2026-05-23T01:19:40.111718+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__save_project_file",
  "max_results": "1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__save_project_file",
    "max_results": "1"
  }
}
```

</details>

---

### Tool result

_source line 42 · 2026-05-23T01:19:40.111902+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_theory_scb-proposition-proof_20260523T010508",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 43 · 2026-05-23T01:19:40.112117+00:00_

文件已写入。核心结构：

**Part (i) — Voting Degeneration:** 在 source attribution σ(c_i, a) = **1**[a_i = a] 下，score(a) = n_a，与 majority voting 完全等价。BR = n_â / max_{a'≠â} n_{a'} ≥ 1 是确定性结论（every realization），不仅仅是期望意义。

**Part (ii) — Information Ceiling:** C = f(T) 形成 Markov chain Y—T—C，DPI 给出 I(C;Y) ≤ I(T;Y)。条件版本 I(C;Y|A) ≤ I(T;Y|A) 说明即使已知答案，约束也无法提供超出 trace 本身的独立验证信号。

**Remark** 诚实处理了 semantic attribution 的边界情况：此时需要 answer alignment 假设（经验上成立，但非纯结构保证）。由于 SICA 实际使用 source attribution，主命题无条件成立。

证明只依赖 A1（a_i = h(t_i)）和 A2（c_i = f(t_i)），不需要 A3（answer-aware）。文件末尾的 author note 预判了 6 个潜在 reviewer pushback 点（包括 deduplication caveat 和"too trivial"反驳）。

产出：`artifacts/proposition1_scb_proof.tex`

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_theory_scb-proposition-proof_20260523T010508"
}
```

</details>

---
