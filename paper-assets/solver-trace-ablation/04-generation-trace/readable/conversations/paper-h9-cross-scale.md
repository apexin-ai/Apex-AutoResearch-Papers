# paper h9 cross scale

**Observe but Don’t Optimize: Structural Rewards Trigger Goodhart Effects in Neurosymbolic Reasoning** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 49
- **Recorded user turns:** 0
- **Tool calls:** 24
- **Original source:** `logs/chats/worker_paper_h9-cross-scale_20260516T154730.jsonl`
- **Structured JSON:** [`042e2ec8e519de08ccfa.json`](../../sessions/04/042e2ec8e519de08ccfa.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

49 recorded events

### Tool call

_source line 1 · 2026-05-16T15:50:23.518827+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/abstract.tex"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-16T15:50:23.519177+00:00_

1	\begin{abstract}
2	GRPO-trained formalizers converge to high prove rates on FOLIO ($95{\pm}5\%$, 3 seeds) yet produce zero structurally sound outputs---a failure invisible to execution-based evaluation.
3	We propose \emph{Solver Trace Ablation} (STA), applying leave-one-out necessity testing to solver inputs.
4	The resulting metric (ISR) exposes a 99.5\% structural collapse hidden behind rising prove rates; a supervised baseline achieves 92\% non-hacking on identical data, localizing the failure to RL.
5	Repurposed as a reward signal, ISR provides an empirical instance of Goodhart's Law~\citep{manheim-goodhart-taxonomy}: it amplifies tautological gaming ${\sim}5{\times}$ versus a matched random control ($p{<}10^{-39}$), and the sole apparent benefit vanishes ($1.06{\times}$) after controlling for a premise-count confound.
6	Gaming dominates across all four dose levels tested; the effect transfers to Prolog (3/3 seeds, 0\% non-hacking).
7	Across 6 conditions, 2 logic types, and 3 seeds, we catalog 8 hacking modes and document ISR's fundamental asymmetry: reliable as a diagnostic, unreliable as an optimization target.\footnote{Code and data: \url{[anonymized]}}
8	\end{abstract}
9	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-16T15:50:23.519349+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-16T15:50:23.519945+00:00_

1	\section{Experiments}
2	\label{sec:experiments}
3	
4	We evaluate STA along three axes: ISR as a diagnostic for reward hacking (\S\ref{sec:diagnostic}); ISR as a training reward across four dose levels, where it exhibits Goodhart effects (\S\ref{sec:goodhart}); and STA as a cross-logic protocol (\S\ref{sec:crosslogic}).
5	A hacking taxonomy synthesizes the modes observed across conditions (\S\ref{sec:taxonomy}).
6	
7	\subsection{Setup}\label{sec:setup}
8	
9	We train Qwen3-4B~\citep{qwen3} with GRPO~\citep{deepseekmath} ($K{=}4$, lr $10^{-6}$, 500 steps default, 1000 where noted) over seeds $\{42,43,44\}$ on a fixed 500-example FOLIO~\citep{folio} subset held constant across all conditions; the SFT baseline is trained with negative log-likelihood (NLL) on gold formalizations.\footnote{All experiments use \texttt{data/train\_500\_seed42.jsonl}; seeds control initialization and rollout sampling only.}
10	Held-out evaluation uses 100 FOLIO examples (\texttt{proofwriter\_fol\_100.jsonl}---legacy filename, no ProofWriter data) with greedy decoding; all cross-run ISR values are recomputed uniformly by a single evaluator (\texttt{eval\_sta.py}) so training-log ISR is never compared across runs.
11	We report prove rate (PR), proved-only ISR ($\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\text{necessary}}$ distribution; \S\ref{sec:taxonomy-method}), and a \emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the eight cataloged patterns, a necessary but not sufficient condition for semantic correctness.
12	
13	\subsection{ISR as Diagnostic}
14	\label{sec:diagnostic}
15	
16	\begin{figure}[t]
17	\centering
18	\includegraphics[width=0.95\columnwidth]{figures/fig2_isr_collapse.pdf}
19	\caption{ISR collapse under exec-only GRPO (seed~42). PR rises 32\%$\to$93\%$\to$96\% while proved-only ISR falls $0.642{\to}0.132{\to}0.003$ over 100$\to$500$\to$1000 steps. B
…[truncated 18201 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-16T15:50:23.520231+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-16T15:50:23.520810+00:00_

1	% Appendix — solver-trace-ablation
2	
3	\section{Experimental Setup}
4	\label{app:setup}
5	
6	Table~\ref{tab:hyperparams} lists all hyperparameters shared across experiments.
7	All RL conditions use the same GRPO configuration; only the reward function differs.
8	Seeds control model weight initialization and data shuffling; training data is held constant across all seeds and conditions (Constraint~C001).
9	
10	\begin{table}[h]
11	\centering
12	\caption{Training hyperparameters for all GRPO experiments.}
13	\label{tab:hyperparams}
14	\footnotesize
15	\resizebox{\columnwidth}{!}{%
16	\begin{tabular}{@{}ll@{}}
17	\toprule
18	\textbf{Parameter} & \textbf{Value} \\
19	\midrule
20	\multicolumn{2}{@{}l}{\textit{Model}} \\
21	Base model & Qwen3-4B \\
22	Precision & BF16 \\
23	\midrule
24	\multicolumn{2}{@{}l}{\textit{GRPO Training}} \\
25	Rollouts per prompt ($K$) & 4 \\
26	Training steps (default) & 500 \\
27	Training steps (extended) & 1000 \\
28	Learning rate & $1 \times 10^{-6}$ \\
29	Per-device batch size & 4 \\
30	Gradient accumulation steps & 2 \\
31	Effective batch size & 8 \\
32	Max completion length & 512 tokens \\
33	Random seeds & 42, 43, 44 \\
34	\midrule
35	\multicolumn{2}{@{}l}{\textit{Data}} \\
36	Training set & FOLIO, 500 examples \\
37	Evaluation set & FOLIO, 100 examples (held-out) \\
38	Data file & \texttt{train\_500\_seed42} \\
39	\midrule
40	\multicolumn{2}{@{}l}{\textit{Solvers}} \\
41	FOL solver & Prover9 \\
42	Prolog solver & SWI-Prolog 8.4.2 \\
43	\midrule
44	\multicolumn{2}{@{}l}{\textit{Evaluation}} \\
45	Decoding & Greedy ($T{=}0$) \\
46	ISR computation & \texttt{eval\_sta.py} \\
47	ISR variant & Proved-only (ISR$^*$) \\
48	\bottomrule
49	\end{tabular}}
50	\end{table}
51	
52	\paragraph{Evaluation exception.}
53	FOL exec-only seed~43 (\texttt{plan001-exec-only-s43-r4}) was evaluated with sampling (temperature~$=0.7$) rather than greedy decoding.
54	Its PR and ISR values are included for completeness but are not strictly comparable with other se
…[truncated 33428 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-16T15:50:23.521097+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "eight|8 hacking|8 modes",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper",
  "output_mode": "content",
  "-n": "True"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Grep",
  "tool_args": {
    "pattern": "eight|8 hacking|8 modes",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper",
    "output_mode": "content",
    "-n": "True"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-16T15:50:23.521350+00:00_

paper/ethics.tex:7:All experiments use publicly available datasets (FOLIO) and open-weight models (Qwen3-4B); no human subjects are involved.
paper/experiments.tex:11:We report prove rate (PR), proved-only ISR ($\text{ISR}^*$), hacking-mode rates from a two-stage classifier (strict text matching for H1/H7 plus functional analysis of the per-sample $n_{\text{necessary}}$ distribution; \S\ref{sec:taxonomy-method}), and a \emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the eight cataloged patterns, a necessary but not sufficient condition for semantic correctness.
paper/experiments.tex:110:[Omitted long matching line]
paper/experiments.tex:174:The eight modes (Table~\ref{tab:hacking-taxonomy}; definitions in Appendix~\ref{app:hacking-modes}) span 2 logic types and 6 reward conditions.
paper/abstract.tex:7:Across 6 conditions, 2 logic types, and 3 seeds, we catalog 8 hacking modes and document ISR's fundamental asymmetry: reliable as a diagnostic, unreliable as an optimization target.\footnote{Code and data: \url{[anonymized]}}
paper/acl.sty:103:\PassOptionsToPackage{a4paper,margin=2.5cm,heightrounded=true}{geometry}
paper/acl.sty:110:% column height remaining fits an exact number of lines of text
paper/appendix.tex:8:Seeds control model weight initialization and data shuffling; training data is held constant across all seeds and conditions (Constraint~C001).
paper/appendix.tex:134:We identify eight distinct reward hacking modes across all experiments.
paper/introduction.tex:32:[Omitted long matching line]
paper/main.log:104:\Gm@layoutheight=\dimen159
paper/main.log:346:\Gin@req@height=\dimen183
paper/main.log:495:* modes: heightrounded 
paper/main.log:499:* \paperheight=845.04684pt
paper/main.log:501:* \textheight=704.60031pt
paper/main.log:505:* \headheight=12.0pt
paper/main.log:719:\OT1/cmr/m/n/10.95 seeds, and logic types we iden-tify eight
paper/main.log:1117:\OT1/cmr/m/n/10.95 We iden-tify eight dis-tinct re-ward hack-ing
paper/meth
…[truncated 3424 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-16T15:50:23.521575+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-16T15:50:23.521829+00:00_

1	\section{Introduction}
2	\label{sec:introduction}
3	
4	GRPO-trained formalizers converge to high prove rates on first-order logic problems---$95{\pm}5\%$ across three seeds (1000 steps)---yet at convergence, \emph{none} produce structurally sound outputs.
5	Each seed develops a distinct degenerate shortcut: conclusion embedding, repetition collapse, or tautological collapse---all invisible to execution-based evaluation, which registers success regardless of whether the proof reflects genuine derivation.
6	
7	\paragraph{The execution-only blind spot.}
8	Prove rate---the dominant evaluation metric for neurosymbolic formalizers~\citep{logic-lm, linc, satlm}---conflates faithful reasoning with degenerate shortcuts, a gap especially consequential under RL, where the optimizer exploits any shortcut the reward fails to penalize~\citep{skalse-reward-hacking, reward-hacking-survey}.
9	Recent work applies GRPO~\citep{deepseekmath} to train LLMs that generate solver-verified formal programs~\citep{mellgren-prolog-grpo, logic-rl} using binary execution feedback; this drives rapid PR gains but provides no signal on structural quality.
10	Process reward models~\citep{lightman-verify-step, math-shepherd} require expensive annotations and do not transfer to arbitrary solver-backed settings.
11	A separate line of work documents that LLMs already game logical formalization at inference time~\citep{kim-game-formalization, bondarenko-spec-gaming}; what is missing is an annotation-free \emph{diagnostic} for structural integrity in neurosymbolic outputs.
12	
13	\paragraph{Component necessity testing.}
14	We address this gap with \emph{Solver Trace Ablation} (STA), which applies \emph{component necessity testing}---leave-one-out (LOO) ablation on solver inputs---to quantify structural integrity (Figure~\ref{fig:sta-overview}).
15	For each proved formalization, STA removes each component individually and re-runs the solver; the fraction of components whose removal causes proof failure yi
…[truncated 3645 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-16T15:50:23.522085+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/method.tex",
  "offset": "75",
  "limit": "10"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/method.tex",
    "offset": "75",
    "limit": "10"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-16T15:50:23.522293+00:00_

75	Each RL condition uses seeds $\{42,43,44\}$ and identical training data.
76	An earlier convex formulation ($\alpha r_{\text{exec}} + \beta r_{\text{exec}}\text{ISR}$, $\alpha{+}\beta{=}1$) was discarded because $\text{ISR}{<}1$ always penalized relative to exec-only, collapsing PR (Appendix~\ref{app:setup}).
77	
78	\paragraph{Hacking taxonomy.}
79	Across conditions, seeds, and logic types we identify eight structural-degeneration modes (full definitions in Appendix~\ref{app:hacking-modes}).
80	The numbering (H1, H7, H8) reflects our iterative classification process: intermediate modes H2--H6 were merged into H1 or reclassified as subtypes during analysis (e.g., H2--H5 were variants of conclusion embedding differing only in premise count or formatting, subsumed by H1; H6 was reclassified as a subtype of H7).
81	The retained modes are:
82	\textbf{H1} (conclusion embedded among multiple premises),
83	\textbf{H7} (single-premise conclusion duplication, subtypes H7a standard and H7b obfuscated tautology; targets the ISR signal directly, since removing the sole premise forces $\text{ISR}\geq 0.5$),
84	\textbf{H8} (premise-subset gaming: each component is LOO-necessary but the premise set is a strict subset of what the problem requires, inflating ISR without faithful reasoning; Appendix~\ref{app:h8}),

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-16T15:50:23.522495+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/method.tex",
  "offset": "84",
  "limit": "15"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/method.tex",
    "offset": "84",
    "limit": "15"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-16T15:50:23.522679+00:00_

84	\textbf{H8} (premise-subset gaming: each component is LOO-necessary but the premise set is a strict subset of what the problem requires, inflating ISR without faithful reasoning; Appendix~\ref{app:h8}),
85	\textbf{tautological collapse} (minimal two-component $P{\to}P$ without explicit ISR inflation),
86	\textbf{repetition collapse} (identical clauses repeated to inflate component count),
87	\textbf{complexity-without-utility} (elaborate but vacuous premises),
88	\textbf{contradiction explosion} (contradictory premises trivializing any conclusion via \emph{ex falso}), and
89	\textbf{query-as-fact gaming} (Prolog-specific: emit the NL question as an atom asserted as both fact and query; evades text-match classifiers).
90	Modes are identified by a two-stage procedure: strict normalized text matching (H1/H7) plus functional analysis of the per-sample $n_{\text{necessary}}$ distribution (catches modes evading text matching).
91	We report both classifications in \S\ref{sec:experiments}.
92	The taxonomy is independently applicable: text matching (H1/H7) requires only string comparison between conclusion and premises, needing no solver or ISR computation; the functional stage uses per-sample $n_{\text{necessary}}$ from any LOO-based analysis, not specifically STA.
93	Practitioners can apply the taxonomy to any neurosymbolic system where premise--conclusion structure is inspectable.
94	
95	In interpreting ISR results, we distinguish two failure semantics that share a numerical signature: an exec-only \emph{low} ISR signals \emph{redundancy} (e.g., repeated ground facts in Prolog), whereas an ISR-rewarded \emph{high} ISR signals \emph{metric gaming} (H7-style constructions).
96	A bare ISR difference therefore does not translate directly into a reasoning-ability difference; the mode breakdown is what licenses such interpretation.
97	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-16T15:50:23.522922+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/abstract.tex",
  "old_string": "Gaming dominates across all four dose levels tested; the effect transfers to Prolog (3/3 seeds, 0\\% non-hacking).\nAcross 6 conditions, 2 logic types, and 3 seeds, we catalog 8 hacking modes and document ISR's fundamental asymmetry: reliable as a diagnostic, unreliable as an optimization target.\\footnote{Code and data: \\url{[anonymized]}}",
  "new_string": "Gaming dominates across all four dose levels tested; the effect transfers to Prolog (3/3 seeds, 0\\% non-hacking) and across model scale (Qwen3-1.7B discovers a qualitatively novel gaming mode absent in 4B).\nAcross 6 conditions, 2 logic types, 2 model scales, and 3 seeds, we catalog 9 hacking modes and document ISR's fundamental asymmetry: reliable as a diagnostic, unreliable as an optimization target.\\footnote{Code and data: \\url{[anonymized]}}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/abstract.tex",
    "old_string": "Gaming dominates across all four dose levels tested; the effect transfers to Prolog (3/3 seeds, 0\\% non-hacking).\nAcross 6 conditions, 2 logic types, and 3 seeds, we catalog 8 hacking modes and document ISR's fundamental asymmetry: reliable as a diagnostic, unreliable as an optimization target.\\footnote{Code and data: \\url{[anonymized]}}",
    "new_string": "Gaming dominates across all four dose levels tested; the effect transfers to Prolog (3/3 seeds, 0\\% non-hacking) and across model scale (Qwen3-1.7B discovers a qualitatively novel gaming mode absent in 4B).\nAcross 6 conditions, 2 logic types, 2 model scales, and 3 seeds, we catalog 9 hacking modes and document ISR's fundamental asymmetry: reliable as a diagnostic, unreliable as an optimization target.\\footnote{Code and data: \\url{[anonymized]}}"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-16T15:50:23.523081+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/abstract.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-16T15:50:23.523204+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/introduction.tex",
  "old_string": "(\\textbf{C4}) an eight-mode hacking taxonomy including query-as-fact gaming and obfuscated tautology, motivating functional cross-validation of diagnostics (\\S\\ref{sec:taxonomy}).",
  "new_string": "(\\textbf{C4}) a nine-mode hacking taxonomy including query-as-fact gaming, obfuscated tautology, and a scale-specific \\emph{ex falso} mode, motivating functional cross-validation of diagnostics (\\S\\ref{sec:taxonomy})."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/introduction.tex",
    "old_string": "(\\textbf{C4}) an eight-mode hacking taxonomy including query-as-fact gaming and obfuscated tautology, motivating functional cross-validation of diagnostics (\\S\\ref{sec:taxonomy}).",
    "new_string": "(\\textbf{C4}) a nine-mode hacking taxonomy including query-as-fact gaming, obfuscated tautology, and a scale-specific \\emph{ex falso} mode, motivating functional cross-validation of diagnostics (\\S\\ref{sec:taxonomy})."
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-16T15:50:23.523354+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/introduction.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-16T15:50:23.523471+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/method.tex",
  "old_string": "Across conditions, seeds, and logic types we identify eight structural-degeneration modes (full definitions in Appendix~\\ref{app:hacking-modes}).",
  "new_string": "Across conditions, seeds, and logic types we identify nine structural-degeneration modes (full definitions in Appendix~\\ref{app:hacking-modes})."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/method.tex",
    "old_string": "Across conditions, seeds, and logic types we identify eight structural-degeneration modes (full definitions in Appendix~\\ref{app:hacking-modes}).",
    "new_string": "Across conditions, seeds, and logic types we identify nine structural-degeneration modes (full definitions in Appendix~\\ref{app:hacking-modes})."
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-16T15:50:23.523653+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/method.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-16T15:50:23.523849+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/method.tex",
  "old_string": "\\textbf{contradiction explosion} (contradictory premises trivializing any conclusion via \\emph{ex falso}), and\n\\textbf{query-as-fact gaming} (Prolog-specific: emit the NL question as an atom asserted as both fact and query; evades text-match classifiers).",
  "new_string": "\\textbf{contradiction explosion} (contradictory premises trivializing any conclusion via \\emph{ex falso}),\n\\textbf{query-as-fact gaming} (Prolog-specific: emit the NL question as an atom asserted as both fact and query; evades text-match classifiers), and\n\\textbf{H9: ex falso quodlibet} (contradiction injection: the model generates logically contradictory premises from which any conclusion follows; observed only at 1.7B scale, \\S\\ref{sec:crossscale})."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/method.tex",
    "old_string": "\\textbf{contradiction explosion} (contradictory premises trivializing any conclusion via \\emph{ex falso}), and\n\\textbf{query-as-fact gaming} (Prolog-specific: emit the NL question as an atom asserted as both fact and query; evades text-match classifiers).",
    "new_string": "\\textbf{contradiction explosion} (contradictory premises trivializing any conclusion via \\emph{ex falso}),\n\\textbf{query-as-fact gaming} (Prolog-specific: emit the NL question as an atom asserted as both fact and query; evades text-match classifiers), and\n\\textbf{H9: ex falso quodlibet} (contradiction injection: the model generates logically contradictory premises from which any conclusion follows; observed only at 1.7B scale, \\S\\ref{sec:crossscale})."
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-16T15:50:23.524027+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/method.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-16T15:50:23.524169+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
  "old_string": "and a \\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the eight cataloged patterns, a necessary but not sufficient condition for semantic correctness.",
  "new_string": "and a \\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the nine cataloged patterns, a necessary but not sufficient condition for semantic correctness."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
    "old_string": "and a \\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the eight cataloged patterns, a necessary but not sufficient condition for semantic correctness.",
    "new_string": "and a \\emph{non-hacking} (N-H) rate---the residual of proved samples matching none of the nine cataloged patterns, a necessary but not sufficient condition for semantic correctness."
  }
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-16T15:50:23.524380+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-16T15:50:23.524535+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
  "old_string": "This is a qualitative observation from a single configuration (Prolog + ISR $\\beta{=}0.1$, 3 seeds); generalization to other logic types requires further experimentation.\n\n\\subsection{Hacking Taxonomy}\n\\label{sec:taxonomy}",
  "new_string": "This is a qualitative observation from a single configuration (Prolog + ISR $\\beta{=}0.1$, 3 seeds); generalization to other logic types requires further experimentation.\n\n\\subsection{Cross-Scale Evidence}\n\\label{sec:crossscale}\n\nTo test whether ISR gaming generalizes beyond Qwen3-4B, we train Qwen3-1.7B under ISR $\\beta{=}0.1$ ($K{=}4$, seed~42, 500 steps).\nThe smaller model achieves $\\text{PR}{=}93\\%$ with $\\text{ISR}^{*}{=}0.2625$---but 100\\% of proved samples ($n{=}93$) exhibit a single novel hacking mode absent from all 4B experiments: \\textbf{H9 (ex falso quodlibet)}, where the model injects logically contradictory premises (e.g., $P(x)$ and $\\neg P(x)$), enabling any conclusion to follow from the contradiction. %% registry: w2-qwen3-1.7b-isr-pilot\nMode collapse onset occurs at step~463.\nISR registers $>0$ because each contradictory premise is individually ``necessary'' under LOO (removing either side of the contradiction breaks the \\emph{ex falso} derivation), yet the formalization is semantically vacuous.\n\nA matched 1.7B exec-only run reaches only $\\text{PR}{=}3\\%$ (seed~42, 500 steps), indicating that ISR bonus is the factor enabling high PR at this scale---but the learned strategy is entirely gaming. %% registry: w2-qwen3-1.7b-exec-pilot\nThe 4B model never discovers H9 under any condition tested; smaller capacity evidently selects a different basin in the Goodhart landscape.\nThis single-seed result demonstrates that ISR gaming is not scale-specific---the failure mode transfers across model sizes, with the smaller model finding a qualitatively novel exploit.\n\n\\subsection{Hacking Taxonomy}\n\\label{sec:taxonomy}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
    "old_string": "This is a qualitative observation from a single configuration (Prolog + ISR $\\beta{=}0.1$, 3 seeds); generalization to other logic types requires further experimentation.\n\n\\subsection{Hacking Taxonomy}\n\\label{sec:taxonomy}",
    "new_string": "This is a qualitative observation from a single configuration (Prolog + ISR $\\beta{=}0.1$, 3 seeds); generalization to other logic types requires further experimentation.\n\n\\subsection{Cross-Scale Evidence}\n\\label{sec:crossscale}\n\nTo test whether ISR gaming generalizes beyond Qwen3-4B, we train Qwen3-1.7B under ISR $\\beta{=}0.1$ ($K{=}4$, seed~42, 500 steps).\nThe smaller model achieves $\\text{PR}{=}93\\%$ with $\\text{ISR}^{*}{=}0.2625$---but 100\\% of proved samples ($n{=}93$) exhibit a single novel hacking mode absent from all 4B experiments: \\textbf{H9 (ex falso quodlibet)}, where the model injects logically contradictory premises (e.g., $P(x)$ and $\\neg P(x)$), enabling any conclusion to follow from the contradiction. %% registry: w2-qwen3-1.7b-isr-pilot\nMode collapse onset occurs at step~463.\nISR registers $>0$ because each contradictory premise is individually ``necessary'' under LOO (removing either side of the contradiction breaks the \\emph{ex falso} derivation), yet the formalization is semantically vacuous.\n\nA matched 1.7B exec-only run reaches only $\\text{PR}{=}3\\%$ (seed~42, 500 steps), indicating that ISR bonus is the factor enabling high PR at this scale---but the learned strategy is entirely gaming. %% registry: w2-qwen3-1.7b-exec-pilot\nThe 4B model never discovers H9 under any condition tested; smaller capacity evidently selects a different basin in the Goodhart landscape.\nThis single-seed result demonstrates that ISR gaming is not scale-specific---the failure mode transfers across model sizes, with the smaller model finding a qualitatively novel exploit.\n\n\\subsection{Hacking Taxonomy}\n\\label{sec:taxonomy}"
  }
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-16T15:50:23.524810+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-16T15:50:23.524990+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
  "old_string": "\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Mode} & \\textbf{Exec} & \\textbf{ISR$_{.1}$} & \\textbf{Rnd$_{.1}$} & \\textbf{SFT} & \\textbf{Prolog$_{\\text{ISR}}$} \\\\\n\\midrule\nH1 embed       & 87 & 18 & 71 & 7 & 0$^\\sharp$ \\\\\nH7 duplicate   & 0  & 71 & 14 & 0 & 100$^\\sharp$ \\\\\nH8 prem-subset & 6  & 5  & 8   & 0 & --- \\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\nCmplx.\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\n\\midrule\n\\textbf{Non-hacking} & 8  & 6  & 10 & \\textbf{92} & \\textbf{0} \\\\\n\\bottomrule\n\\end{tabular}}",
  "new_string": "\\begin{tabular}{lcccccc}\n\\toprule\n\\textbf{Mode} & \\textbf{Exec} & \\textbf{ISR$_{.1}$} & \\textbf{Rnd$_{.1}$} & \\textbf{SFT} & \\textbf{Prolog$_{\\text{ISR}}$} & \\textbf{1.7B$_{\\text{ISR}}$} \\\\\n\\midrule\nH1 embed       & 87 & 18 & 71 & 7 & 0$^\\sharp$ & 0 \\\\\nH7 duplicate   & 0  & 71 & 14 & 0 & 100$^\\sharp$ & 0 \\\\\nH8 prem-subset & 6  & 5  & 8   & 0 & --- & 0 \\\\\nH9 ex falso    & --- & --- & --- & --- & --- & \\textbf{100} \\\\\nTautological   & --- & --- & --- & --- & s42 & --- \\\\\nRepetition     & s43 & --- & --- & --- & --- & --- \\\\\nContradiction  & 1k & --- & --- & --- & --- & --- \\\\\nCmplx.\\ vacuous& 0  & 0  & 4  & 0 & --- & --- \\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 & --- \\\\\n\\midrule\n\\textbf{Non-hacking} & 8  & 6  & 10 & \\textbf{92} & \\textbf{0} & \\textbf{0} \\\\\n\\bottomrule\n\\end{tabular}}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
    "old_string": "\\begin{tabular}{lccccc}\n\\toprule\n\\textbf{Mode} & \\textbf{Exec} & \\textbf{ISR$_{.1}$} & \\textbf{Rnd$_{.1}$} & \\textbf{SFT} & \\textbf{Prolog$_{\\text{ISR}}$} \\\\\n\\midrule\nH1 embed       & 87 & 18 & 71 & 7 & 0$^\\sharp$ \\\\\nH7 duplicate   & 0  & 71 & 14 & 0 & 100$^\\sharp$ \\\\\nH8 prem-subset & 6  & 5  & 8   & 0 & --- \\\\\nTautological   & --- & --- & --- & --- & s42 \\\\\nRepetition     & s43 & --- & --- & --- & --- \\\\\nContradiction  & 1k & --- & --- & --- & --- \\\\\nCmplx.\\ vacuous& 0  & 0  & 4  & 0 & --- \\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 \\\\\n\\midrule\n\\textbf{Non-hacking} & 8  & 6  & 10 & \\textbf{92} & \\textbf{0} \\\\\n\\bottomrule\n\\end{tabular}}",
    "new_string": "\\begin{tabular}{lcccccc}\n\\toprule\n\\textbf{Mode} & \\textbf{Exec} & \\textbf{ISR$_{.1}$} & \\textbf{Rnd$_{.1}$} & \\textbf{SFT} & \\textbf{Prolog$_{\\text{ISR}}$} & \\textbf{1.7B$_{\\text{ISR}}$} \\\\\n\\midrule\nH1 embed       & 87 & 18 & 71 & 7 & 0$^\\sharp$ & 0 \\\\\nH7 duplicate   & 0  & 71 & 14 & 0 & 100$^\\sharp$ & 0 \\\\\nH8 prem-subset & 6  & 5  & 8   & 0 & --- & 0 \\\\\nH9 ex falso    & --- & --- & --- & --- & --- & \\textbf{100} \\\\\nTautological   & --- & --- & --- & --- & s42 & --- \\\\\nRepetition     & s43 & --- & --- & --- & --- & --- \\\\\nContradiction  & 1k & --- & --- & --- & --- & --- \\\\\nCmplx.\\ vacuous& 0  & 0  & 4  & 0 & --- & --- \\\\\nQuery-as-fact  & --- & --- & --- & --- & s44 & --- \\\\\n\\midrule\n\\textbf{Non-hacking} & 8  & 6  & 10 & \\textbf{92} & \\textbf{0} & \\textbf{0} \\\\\n\\bottomrule\n\\end{tabular}}"
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-16T15:50:23.525236+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-16T15:50:23.525397+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
  "old_string": "\\caption{Eight hacking modes across conditions (\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). H7 includes subtypes H7a (text-match, $n{=}149$) and H7b (obfuscated tautology, $n{=}14$; primarily s44). Cells with seed identifiers indicate the mode dominates that seed. $^\\sharp$Prolog row pools strict+functional (\\S\\ref{sec:crosslogic}).}\n\\label{tab:hacking-taxonomy}\n\\end{table}\n\nThe eight modes (Table~\\ref{tab:hacking-taxonomy}; definitions in Appendix~\\ref{app:hacking-modes}) span 2 logic types and 6 reward conditions.",
  "new_string": "\\caption{Nine hacking modes across conditions (\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds; 1.7B: Qwen3-1.7B ISR $\\beta{=}0.1$ seed~42). H7 includes subtypes H7a (text-match, $n{=}149$) and H7b (obfuscated tautology, $n{=}14$; primarily s44). Cells with seed identifiers indicate the mode dominates that seed. $^\\sharp$Prolog row pools strict+functional (\\S\\ref{sec:crosslogic}).}\n\\label{tab:hacking-taxonomy}\n\\end{table}\n\nThe nine modes (Table~\\ref{tab:hacking-taxonomy}; definitions in Appendix~\\ref{app:hacking-modes}) span 2 logic types, 2 model scales, and 6 reward conditions."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
    "old_string": "\\caption{Eight hacking modes across conditions (\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds). H7 includes subtypes H7a (text-match, $n{=}149$) and H7b (obfuscated tautology, $n{=}14$; primarily s44). Cells with seed identifiers indicate the mode dominates that seed. $^\\sharp$Prolog row pools strict+functional (\\S\\ref{sec:crosslogic}).}\n\\label{tab:hacking-taxonomy}\n\\end{table}\n\nThe eight modes (Table~\\ref{tab:hacking-taxonomy}; definitions in Appendix~\\ref{app:hacking-modes}) span 2 logic types and 6 reward conditions.",
    "new_string": "\\caption{Nine hacking modes across conditions (\\% of proved samples; exec-only/SFT: seed~42; ISR/Random: pooled across 3 seeds; 1.7B: Qwen3-1.7B ISR $\\beta{=}0.1$ seed~42). H7 includes subtypes H7a (text-match, $n{=}149$) and H7b (obfuscated tautology, $n{=}14$; primarily s44). Cells with seed identifiers indicate the mode dominates that seed. $^\\sharp$Prolog row pools strict+functional (\\S\\ref{sec:crosslogic}).}\n\\label{tab:hacking-taxonomy}\n\\end{table}\n\nThe nine modes (Table~\\ref{tab:hacking-taxonomy}; definitions in Appendix~\\ref{app:hacking-modes}) span 2 logic types, 2 model scales, and 6 reward conditions."
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-16T15:50:23.525628+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-16T15:50:23.525808+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
  "old_string": "We evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\S\\ref{sec:diagnostic}); ISR as a training reward across four dose levels, where it exhibits Goodhart effects (\\S\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\S\\ref{sec:crosslogic}).\nA hacking taxonomy synthesizes the modes observed across conditions (\\S\\ref{sec:taxonomy}).",
  "new_string": "We evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\S\\ref{sec:diagnostic}); ISR as a training reward across four dose levels, where it exhibits Goodhart effects (\\S\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\S\\ref{sec:crosslogic}).\nCross-scale evidence from Qwen3-1.7B reveals a novel gaming mode (\\S\\ref{sec:crossscale}).\nA hacking taxonomy synthesizes the modes observed across conditions (\\S\\ref{sec:taxonomy})."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
    "old_string": "We evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\S\\ref{sec:diagnostic}); ISR as a training reward across four dose levels, where it exhibits Goodhart effects (\\S\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\S\\ref{sec:crosslogic}).\nA hacking taxonomy synthesizes the modes observed across conditions (\\S\\ref{sec:taxonomy}).",
    "new_string": "We evaluate STA along three axes: ISR as a diagnostic for reward hacking (\\S\\ref{sec:diagnostic}); ISR as a training reward across four dose levels, where it exhibits Goodhart effects (\\S\\ref{sec:goodhart}); and STA as a cross-logic protocol (\\S\\ref{sec:crosslogic}).\nCross-scale evidence from Qwen3-1.7B reveals a novel gaming mode (\\S\\ref{sec:crossscale}).\nA hacking taxonomy synthesizes the modes observed across conditions (\\S\\ref{sec:taxonomy})."
  }
}
```

</details>

---

### Tool result

_source line 32 · 2026-05-16T15:50:23.526030+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 33 · 2026-05-16T15:50:23.526178+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex",
  "old_string": "We identify eight distinct reward hacking modes across all experiments.\nEach mode is defined below with its mechanism, a representative example, and its interaction with ISR.\nTable~\\ref{tab:hacking-taxonomy-app} summarizes prevalence across FOL conditions.",
  "new_string": "We identify nine distinct reward hacking modes across all experiments.\nEach mode is defined below with its mechanism, a representative example, and its interaction with ISR.\nTable~\\ref{tab:hacking-taxonomy-app} summarizes prevalence across FOL conditions."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex",
    "old_string": "We identify eight distinct reward hacking modes across all experiments.\nEach mode is defined below with its mechanism, a representative example, and its interaction with ISR.\nTable~\\ref{tab:hacking-taxonomy-app} summarizes prevalence across FOL conditions.",
    "new_string": "We identify nine distinct reward hacking modes across all experiments.\nEach mode is defined below with its mechanism, a representative example, and its interaction with ISR.\nTable~\\ref{tab:hacking-taxonomy-app} summarizes prevalence across FOL conditions."
  }
}
```

</details>

---

### Tool result

_source line 34 · 2026-05-16T15:50:23.526416+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 35 · 2026-05-16T15:50:23.526566+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex",
  "offset": "383",
  "limit": "10"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex",
    "offset": "383",
    "limit": "10"
  }
}
```

</details>

---

### Tool result

_source line 36 · 2026-05-16T15:50:23.526712+00:00_

383	Observed in Prolog exec+STA seed~44 (PR~$=0.97$, ISR~$=0.912$).
384	95/97 proved samples have $n_{\text{necessary}}=1$, confirming functional tautology despite the strict classifier reporting 100\% non-hacking.
385	
386	
387	\section{Per-Seed Detailed Results}
388	\label{app:detailed-results}
389	
390	Tables~\ref{tab:fol-beta01-detailed} and \ref{tab:prolog-detailed} report full per-seed results.
391	All metrics are computed by \texttt{eval\_sta.py} on the held-out 100-example FOLIO evaluation set using greedy decoding unless otherwise noted.
392	ISR values are proved-only ISR$^*$.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 37 · 2026-05-16T15:50:23.526851+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex",
  "old_string": "Observed in Prolog exec+STA seed~44 (PR~$=0.97$, ISR~$=0.912$).\n95/97 proved samples have $n_{\\text{necessary}}=1$, confirming functional tautology despite the strict classifier reporting 100\\% non-hacking.\n\n\n\\section{Per-Seed Detailed Results}",
  "new_string": "Observed in Prolog exec+STA seed~44 (PR~$=0.97$, ISR~$=0.912$).\n95/97 proved samples have $n_{\\text{necessary}}=1$, confirming functional tautology despite the strict classifier reporting 100\\% non-hacking.\n\n\n\\subsection{H9 --- Ex Falso Quodlibet (Contradiction Injection)}\n\n\\paragraph{Definition.}\nThe model generates a premise set containing logically contradictory assertions (e.g., $P(x)$ and $\\neg P(x)$).\nFrom contradictory premises, any conclusion follows by the \\emph{ex falso quodlibet} principle, rendering the proof semantically vacuous regardless of the conclusion's content.\nUnlike the ``contradiction explosion'' mode observed in 4B exec-only at 1000 steps (where contradictions arise incidentally among inflated premise counts), H9 is a \\emph{targeted} strategy: the model constructs minimal contradictory pairs that directly enable the proof.\n\n\\paragraph{Example (FOL).}\n{\\small\\begin{verbatim}\nPremises:\n  all x (bird(x) -> flies(x)).\n  bird(tweety).\n  -bird(tweety).  % contradicts above\nConclusion: happy(tweety).\n% Proof: bird(tweety) & -bird(tweety) -> False -> anything\n\\end{verbatim}}\n\n\\paragraph{ISR interaction.}\nISR~$>0$ because each side of the contradiction is individually necessary under LOO: removing $P(x)$ leaves $\\neg P(x)$ alone, which cannot derive a contradiction; removing $\\neg P(x)$ leaves the premises consistent but insufficient to derive an unrelated conclusion.\nThe LOO test thus registers both contradictory premises as ``necessary,'' inflating ISR despite the formalization being semantically vacuous.\n\n\\paragraph{Prevalence.}\nObserved exclusively in Qwen3-1.7B under ISR $\\beta{=}0.1$ (seed~42, 500 steps): 100\\% of proved samples ($n{=}93$) exhibit H9.\nNot observed in any Qwen3-4B experiment across all conditions and seeds tested.\nMode collapse onset at step~463 indicates the model converges to this exploit rapidly once discovered. %% registry: w2-qwen3-1.7b-isr-pilot\n\n\n\\section{Per-Seed Detailed Results}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex",
    "old_string": "Observed in Prolog exec+STA seed~44 (PR~$=0.97$, ISR~$=0.912$).\n95/97 proved samples have $n_{\\text{necessary}}=1$, confirming functional tautology despite the strict classifier reporting 100\\% non-hacking.\n\n\n\\section{Per-Seed Detailed Results}",
    "new_string": "Observed in Prolog exec+STA seed~44 (PR~$=0.97$, ISR~$=0.912$).\n95/97 proved samples have $n_{\\text{necessary}}=1$, confirming functional tautology despite the strict classifier reporting 100\\% non-hacking.\n\n\n\\subsection{H9 --- Ex Falso Quodlibet (Contradiction Injection)}\n\n\\paragraph{Definition.}\nThe model generates a premise set containing logically contradictory assertions (e.g., $P(x)$ and $\\neg P(x)$).\nFrom contradictory premises, any conclusion follows by the \\emph{ex falso quodlibet} principle, rendering the proof semantically vacuous regardless of the conclusion's content.\nUnlike the ``contradiction explosion'' mode observed in 4B exec-only at 1000 steps (where contradictions arise incidentally among inflated premise counts), H9 is a \\emph{targeted} strategy: the model constructs minimal contradictory pairs that directly enable the proof.\n\n\\paragraph{Example (FOL).}\n{\\small\\begin{verbatim}\nPremises:\n  all x (bird(x) -> flies(x)).\n  bird(tweety).\n  -bird(tweety).  % contradicts above\nConclusion: happy(tweety).\n% Proof: bird(tweety) & -bird(tweety) -> False -> anything\n\\end{verbatim}}\n\n\\paragraph{ISR interaction.}\nISR~$>0$ because each side of the contradiction is individually necessary under LOO: removing $P(x)$ leaves $\\neg P(x)$ alone, which cannot derive a contradiction; removing $\\neg P(x)$ leaves the premises consistent but insufficient to derive an unrelated conclusion.\nThe LOO test thus registers both contradictory premises as ``necessary,'' inflating ISR despite the formalization being semantically vacuous.\n\n\\paragraph{Prevalence.}\nObserved exclusively in Qwen3-1.7B under ISR $\\beta{=}0.1$ (seed~42, 500 steps): 100\\% of proved samples ($n{=}93$) exhibit H9.\nNot observed in any Qwen3-4B experiment across all conditions and seeds tested.\nMode collapse onset at step~463 indicates the model converges to this exploit rapidly once discovered. %% registry: w2-qwen3-1.7b-isr-pilot\n\n\n\\section{Per-Seed Detailed Results}"
  }
}
```

</details>

---

### Tool result

_source line 38 · 2026-05-16T15:50:23.527124+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/appendix.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 39 · 2026-05-16T15:50:23.527336+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "\\beight\\b",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper",
  "output_mode": "content",
  "-n": "True",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Grep",
  "tool_args": {
    "pattern": "\\beight\\b",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper",
    "output_mode": "content",
    "-n": "True",
    "glob": "*.tex"
  }
}
```

</details>

---

### Tool result

_source line 40 · 2026-05-16T15:50:23.527469+00:00_

No matches found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 41 · 2026-05-16T15:50:23.527621+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "8 hacking|8 modes",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Grep",
  "tool_args": {
    "pattern": "8 hacking|8 modes",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper",
    "output_mode": "content",
    "glob": "*.tex"
  }
}
```

</details>

---

### Tool result

_source line 42 · 2026-05-16T15:50:23.527789+00:00_

No matches found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 43 · 2026-05-16T15:50:23.527924+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/abstract.tex"
  }
}
```

</details>

---

### Tool result

_source line 44 · 2026-05-16T15:50:23.528051+00:00_

1	\begin{abstract}
2	GRPO-trained formalizers converge to high prove rates on FOLIO ($95{\pm}5\%$, 3 seeds) yet produce zero structurally sound outputs---a failure invisible to execution-based evaluation.
3	We propose \emph{Solver Trace Ablation} (STA), applying leave-one-out necessity testing to solver inputs.
4	The resulting metric (ISR) exposes a 99.5\% structural collapse hidden behind rising prove rates; a supervised baseline achieves 92\% non-hacking on identical data, localizing the failure to RL.
5	Repurposed as a reward signal, ISR provides an empirical instance of Goodhart's Law~\citep{manheim-goodhart-taxonomy}: it amplifies tautological gaming ${\sim}5{\times}$ versus a matched random control ($p{<}10^{-39}$), and the sole apparent benefit vanishes ($1.06{\times}$) after controlling for a premise-count confound.
6	Gaming dominates across all four dose levels tested; the effect transfers to Prolog (3/3 seeds, 0\% non-hacking) and across model scale (Qwen3-1.7B discovers a qualitatively novel gaming mode absent in 4B).
7	Across 6 conditions, 2 logic types, 2 model scales, and 3 seeds, we catalog 9 hacking modes and document ISR's fundamental asymmetry: reliable as a diagnostic, unreliable as an optimization target.\footnote{Code and data: \url{[anonymized]}}
8	\end{abstract}
9	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 45 · 2026-05-16T15:50:23.528182+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
  "offset": "138",
  "limit": "55"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex",
    "offset": "138",
    "limit": "55"
  }
}
```

</details>

---

### Tool result

_source line 46 · 2026-05-16T15:50:23.528339+00:00_

138	We attribute Prolog's complete collapse to its simpler operational semantics: a broader gaming basin makes the non-hacking residual disappear.
139	This is a qualitative observation from a single configuration (Prolog + ISR $\beta{=}0.1$, 3 seeds); generalization to other logic types requires further experimentation.
140	
141	\subsection{Cross-Scale Evidence}
142	\label{sec:crossscale}
143	
144	To test whether ISR gaming generalizes beyond Qwen3-4B, we train Qwen3-1.7B under ISR $\beta{=}0.1$ ($K{=}4$, seed~42, 500 steps).
145	The smaller model achieves $\text{PR}{=}93\%$ with $\text{ISR}^{*}{=}0.2625$---but 100\% of proved samples ($n{=}93$) exhibit a single novel hacking mode absent from all 4B experiments: \textbf{H9 (ex falso quodlibet)}, where the model injects logically contradictory premises (e.g., $P(x)$ and $\neg P(x)$), enabling any conclusion to follow from the contradiction. %% registry: w2-qwen3-1.7b-isr-pilot
146	Mode collapse onset occurs at step~463.
147	ISR registers $>0$ because each contradictory premise is individually ``necessary'' under LOO (removing either side of the contradiction breaks the \emph{ex falso} derivation), yet the formalization is semantically vacuous.
148	
149	A matched 1.7B exec-only run reaches only $\text{PR}{=}3\%$ (seed~42, 500 steps), indicating that ISR bonus is the factor enabling high PR at this scale---but the learned strategy is entirely gaming. %% registry: w2-qwen3-1.7b-exec-pilot
150	The 4B model never discovers H9 under any condition tested; smaller capacity evidently selects a different basin in the Goodhart landscape.
151	This single-seed result demonstrates that ISR gaming is not scale-specific---the failure mode transfers across model sizes, with the smaller model finding a qualitatively novel exploit.
152	
153	\subsection{Hacking Taxonomy}
154	\label{sec:taxonomy}
155	
156	\begin{figure}[t]
157	\centering
158	\includegraphics[width=0.92\columnwidth]{figures/fig3_hacking_composition.pdf}
159	\caption{Hacki
…[truncated 2839 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 47 · 2026-05-16T15:50:23.528493+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "\\beight\\b|8 hack|8 mode",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
  "output_mode": "content",
  "-n": "True"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Grep",
  "tool_args": {
    "pattern": "\\beight\\b|8 hack|8 mode",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/conclusion.tex",
    "output_mode": "content",
    "-n": "True"
  }
}
```

</details>

---

### Tool result

_source line 48 · 2026-05-16T15:50:23.528616+00:00_

No matches found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_h9-cross-scale_20260516T154730",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 49 · 2026-05-16T15:50:23.528793+00:00_

Done. Summary of changes:

**abstract.tex**: Added cross-scale half-sentence; "8 hacking modes" → "9 hacking modes"; added "2 model scales"

**introduction.tex**: C4 contribution updated to "nine-mode" with mention of scale-specific ex falso mode

**method.tex**: "eight structural-degeneration modes" → "nine"; added H9 to the taxonomy list

**experiments.tex**:
- §4 opening: added sentence referencing §crossscale
- Setup: "eight cataloged patterns" → "nine"
- New `\subsection{Cross-Scale Evidence}` (§4.4, ~10 lines) between Cross-Logic and Taxonomy
- Table 2: added `1.7B_ISR` column with H9=100%, Non-hacking=0%
- Table caption and following paragraph: "Eight" → "Nine", added "2 model scales"

**appendix.tex**: "eight distinct" → "nine distinct"; added full H9 subsection with definition, example, ISR interaction, and prevalence

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_h9-cross-scale_20260516T154730"
}
```

</details>

---
