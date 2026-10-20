# paper writing discussion

**Observe but Don’t Optimize: Structural Rewards Trigger Goodhart Effects in Neurosymbolic Reasoning** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 21
- **Recorded user turns:** 0
- **Tool calls:** 10
- **Original source:** `logs/chats/worker_paper_writing_discussion_20260514T193516.jsonl`
- **Structured JSON:** [`dfe72e9f4e695a128484.json`](../../sessions/df/dfe72e9f4e695a128484.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

21 recorded events

### Tool call

_source line 1 · 2026-05-14T19:37:44.789025+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-14T19:37:44.789753+00:00_

1	---
2	name: latex-paper
3	description: ML 顶会论文 LaTeX 写作全流程——Claim-Evidence 方法论、引用防幻觉、顶会模板速查、投稿工程链、会议转投。写论文/投稿时参考。
4	scope: global
5	tags:
6	- latex
7	- paper-writing
8	- academic
9	- citation
10	- submission
11	version: 1
12	roles:
13	- agent
14	- worker
15	---
16	
17	# LaTeX 论文写作全流程
18	
19	ML/AI 顶会论文从草稿到投稿的完整指南。整合 Orchestra Research、VibeSkills、claim2evidence 三方最佳实践。
20	
21	---
22	
23	## 1. 工作模式
24	
25	开始前选择模式：
26	
27	| 模式 | 说明 | 适用 |
28	|------|------|------|
29	| **Build** | 从实验笔记/结果/代码生成论文 | 新稿 |
30	| **Improve** | 改写已有章节，强化论证 | 修改稿 |
31	| **Audit** | 输出风险列表 + 缺失证据 + 修复建议 | 投前检查 |
32	
33	---
34	
35	## 2. Claim-Evidence 方法论
36	
37	**核心原则：论文是一个有中心贡献的故事，不是实验的堆砌。**
38	
39	### 2.1 一句话贡献
40	
41	在写任何内容之前，必须能用一句话说清贡献。如果不能，说明还没准备好写论文。
42	
43	### 2.2 Claim-Evidence Map
44	
45	为每个 contribution 建立 claim→evidence 映射表：
46	
47	| Contribution | Claim | Evidence | Table/Figure |
48	|-------------|-------|----------|-------------|
49	| C1: 方法 X 在 Y 上 SOTA | 比所有 baseline 高 ≥2% | 5-seed 平均，p<0.05 | Table 1 |
50	| C2: 消融证明 Z 是关键 | 去掉 Z 后掉 >5% | 消融实验 | Table 2 |
51	| C3: 计算效率 | 比 baseline 快 3× | FLOPs + wall-clock | Figure 3 |
52	
53	**没有直接证据支撑的 claim 必须删除或降级为 discussion。**
54	
55	### 2.3 章节起草顺序
56	
57	```
58	1. Introduction + Experiments（先确定 claim 和 evidence）
59	2. Method（评估问题稳定后再写细节）
60	3. Related Work
61	4. Abstract + Title（核心 claim 定型后最后写）
62	```
63	
64	### 2.4 Quality Gates
65	
66	投稿前必须通过：
67	- [ ] 前两段出现显式 novelty 声明
68	- [ ] 每个 contribution 有可验证的 evidence
69	- [ ] Abstract / Intro / Conclusion 的 claim 一致
70	- [ ] Limitations 真实且技术性诚实
71	- [ ] 审稿人两分钟内能识别 delta
72	
73	---
74	
75	## 3. 引用防幻觉（CRITICAL）
76	
77	**AI 生成引用有 ~40% 错误率。绝对禁止凭记忆写 BibTeX。**
78	
79	### 3.1 黄金法则
80	
81	```
82	IF 无法程序化获取引用:
83	    → 标记 [CITATION NEEDED] 或 \cite{PLACEHOLDER_verify}
84	    → 明确告知用户
85	    → 绝不编造看似合理的引用
86	```
87	
88	### 3.2 五步验证流程
89	
90	```
91	1. SEARCH  → Semantic Scholar API 搜索关键词
92	2. VERIFY  → 至少 2 个来源确认论文存在（S2 + arXiv/CrossRef）
93	3. RETRIEVE → 通过 DOI 获取 BibTeX（程序化，非记忆）
94	4. CHECK   → 确认
…[truncated 7201 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-14T19:37:44.789948+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Glob",
  "tool_args": {
    "pattern": "**/*.tex",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-14T19:37:44.790084+00:00_

paper/discussion.tex
paper/conclusion.tex
paper/method.tex
paper/experiments.tex
paper/abstract.tex
paper/paper.tex
paper/related_work.tex
paper/introduction.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-14T19:37:44.790237+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/discussion.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-14T19:37:44.790405+00:00_

1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{ISR Capability Boundary.}
5	ISR measures syntactic component necessity---whether each component is individually required for proof success---not semantic faithfulness to the natural language input.
6	A formalization where every component is necessary may still misrepresent the intended reasoning chain.
7	We verify this empirically: downstream NLI accuracy shows no correlation with ISR (Spearman $\rho = -0.049$, $p = 0.187$, n.s.), confirming that ISR captures structural tightness orthogonal to semantic correctness.
8	Practitioners should treat ISR as a necessary-but-not-sufficient diagnostic: low ISR reliably indicates structural degeneration, but high ISR does not guarantee faithful reasoning.
9	Importantly, low ISR carries different semantics depending on the training objective.
10	Under exec-only training, low ISR in Prolog reflects redundant coding---repeated ground facts where removing any single copy does not affect the proof---rather than absence of reasoning.
11	Under ISR-as-reward, high ISR reflects metric gaming.
12	ISR values must always be interpreted in the context of the optimization objective that produced them.
13	
14	\paragraph{Premise Count Confound.}
15	LOO-based metrics like ISR are mathematically biased by component count.
16	With $n$ components, each carries a $1/n$ share of the proof burden; fewer components mechanically inflate ISR regardless of quality.
17	As shown in \S\ref{sec:goodhart}, over half of ISR-reward genuine samples contain only 1--2 premises, where ISR $\geq 0.5$ is an arithmetic inevitability.
18	Controlling for premise count eliminates the apparent ISR advantage entirely (1.06$\times$ vs.\ the raw 2.4$\times$).
19	This confound is not specific to our setting: any LOO-based diagnostic applied to variable-length structured outputs requires component-count normalization.
20	We recommend that future work employing LOO-based structural metrics report premise-count-mat
…[truncated 3094 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-14T19:37:44.790546+00:00_

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
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/experiments.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-14T19:37:44.790819+00:00_

1	\section{Experiments}
2	\label{sec:experiments}
3	
4	We evaluate STA-derived ISR across three axes: as a diagnostic for reward hacking (\S\ref{sec:diagnostic}), as a training reward exhibiting meta-level Goodhart's Law (\S\ref{sec:goodhart}), and as a cross-logic diagnostic protocol (\S\ref{sec:crosslogic}). We then synthesize the observed hacking strategies into a taxonomy (\S\ref{sec:taxonomy}).
5	
6	\subsection{Setup}
7	\label{sec:setup}
8	
9	\paragraph{Model and training.}
10	We use Qwen3-4B as the base model, trained with GRPO~\citep{deepseekmath} using $K{=}8$ rollouts per prompt for 500 steps (default) or 1000 steps where noted. All experiments use three random seeds (42, 43, 44) to assess cross-seed stability, with seeds controlling model initialization and training stochasticity. Training data is a fixed 500-example subset of FOLIO~\citep{folio} (\texttt{train\_500\_seed42.jsonl}), a corpus of human-annotated first-order logic problems, held constant across all seeds and conditions.
11	
12	\paragraph{Solvers and logic types.}
13	For first-order logic (FOL), we use Prover9 as the automated theorem prover. For Prolog experiments, we use SWI-Prolog 8.4.2. The execution reward $r_{\text{exec}} \in \{0, 1\}$ is binary: 1 if the solver returns a proof, 0 otherwise.
14	
15	\paragraph{Evaluation.}
16	We evaluate on a held-out set of 100 FOLIO examples using greedy decoding. All ISR values reported in cross-run comparisons are computed by \texttt{eval\_sta.py}, which applies the full STA protocol uniformly. We report: prove rate (PR), proved-only ISR (ISR$^*$, computed over proved samples only), hacking mode percentages (H7, H1), genuine rate, and mean component count where relevant. All tabulated ISR values are proved-only unless otherwise noted.
17	
18	\paragraph{Reward formulations.}
19	We compare six conditions:
20	\begin{itemize}[nosep,leftmargin=*]
21	  \item \textbf{Exec-only}: $r = r_{\text{exec}}$ (baseline)
22	  \item \textbf{ISR $\beta$}: $r = r_{\text{
…[truncated 18868 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-14T19:37:44.791002+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/paper.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/paper.tex"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-14T19:37:44.791137+00:00_

1	\documentclass[11pt]{article}
2	\usepackage[review]{acl}
3	
4	\usepackage{amsmath}
5	\usepackage{amssymb}
6	\usepackage{graphicx}
7	\usepackage{booktabs}
8	\usepackage{algorithm}
9	\usepackage{algorithmic}
10	\usepackage{enumitem}
11	\usepackage[protrusion=true,expansion=false]{microtype}
12	
13	\graphicspath{{figures/}}
14	
15	\title{Solver Trace Ablation Reveals Meta-Level Goodhart's Law\\in Neurosymbolic Reasoning}
16	
17	\author{Anonymous ACL submission}
18	
19	\begin{document}
20	\maketitle
21	
22	\input{abstract}
23	
24	\input{introduction}
25	\input{related_work}
26	\input{method}
27	\input{experiments}
28	\input{discussion}
29	\input{conclusion}
30	
31	\bibliography{references}
32	
33	\end{document}
34	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-14T19:37:44.791301+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "gao-reward-overoptimization|manheim-goodhart-taxonomy",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper",
  "output_mode": "content",
  "-C": "1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Grep",
  "tool_args": {
    "pattern": "gao-reward-overoptimization|manheim-goodhart-taxonomy",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper",
    "output_mode": "content",
    "-C": "1"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-14T19:37:44.791469+00:00_

/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/related_work.tex-27-\paragraph{Reward Hacking and Goodhart's Law.}
paper/related_work.tex:28:Gao et al.~\cite{gao-reward-overoptimization} establish scaling laws for reward model overoptimization, showing that proxy reward increases monotonically with optimization pressure until true performance collapses.
paper/related_work.tex:29:Manheim and Garrabrant~\cite{manheim-goodhart-taxonomy} taxonomize four variants of Goodhart's Law---regressional, extremal, causal, and adversarial---while Skalse et al.~\cite{skalse-reward-hacking} prove that reward hacking is generically unavoidable for imperfect proxies.
/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/related_work.tex-30-Karwowski et al.~\cite{karwowski-goodhart-rl} demonstrate Goodhart dynamics geometrically in RL, showing that KL regularization delays but does not prevent overoptimization; Pan et al.~\cite{pan-reward-misspecification} map how misspecified rewards produce qualitatively different failure modes depending on the degree of misalignment; and Kwa et al.~\cite{kwa-catastrophic-goodhart} show that KL divergence regularization fails catastrophically under heavy-tailed reward misspecification.
--
paper/related_work.tex-33-Our setting differs in two respects: the proxy (ISR) is deterministic and solver-derived, eliminating reward model noise as an explanation; and the Goodhart effect operates at a \emph{meta} level---ISR was designed to \emph{detect} gaming of execution reward, yet itself becomes gamed when optimized.
paper/related_work.tex:34:The dose-response pattern we observe ($\beta{=}0.1$: proxy gaming via conclusion duplication; $\beta{=}0.3$: performance collapse) traces the trajectory predicted by Gao et al.~\cite{gao-reward-overoptimization} within a single neurosymbolic RL setup, and the premise-count confound that explains away apparent ISR improvements provides a concrete mechan
…[truncated 8410 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-14T19:37:44.791642+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/method.tex",
  "limit": "30"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/method.tex",
    "limit": "30"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-14T19:37:44.791806+00:00_

1	% Method section — solver-trace-ablation
2	% Requires: algorithm, algorithmic, amsmath, enumitem packages
3	
4	\section{Method}
5	\label{sec:method}
6	
7	\begin{figure*}[t]
8	\centering
9	\includegraphics[width=\textwidth]{figures/fig1_sta_overview.pdf}
10	\caption{Overview of Solver Trace Ablation (STA). (a) Formalization pipeline: NL input is formalized into logical representation and verified by an external solver. (b) STA protocol: leave-one-out ablation on proved formalizations to compute ISR. (c) ISR as diagnostic vs.\ ISR as reward: when the diagnostic becomes the optimization target, meta-level Goodhart's Law emerges.}
11	\label{fig:sta-overview}
12	\end{figure*}
13	
14	\subsection{Task: NL to Formal Logic}
15	\label{sec:task}
16	
17	Given natural language premises $P_1, \ldots, P_k$ and a conclusion $C$, the task is to produce a formal logic program $F = \{c_1, \ldots, c_n\}$, where each component $c_i$ is a premise encoding (in FOL) or a clause/fact (in Prolog), with one distinguished component encoding the query derived from $C$.
18	An external solver $S$ determines whether $F$ constitutes a valid proof:
19	$S(F) \in \{\textit{proved}, \textit{failed}\}$.
20	We experiment with two solver backends: Prover9 for first-order logic and SWI-Prolog for Prolog programs (\autoref{fig:sta-overview}a).
21	
22	\subsection{GRPO Training}
23	\label{sec:grpo}
24	
25	We train formalizers with Group Relative Policy Optimization \citep[GRPO;][]{deepseekmath}.
26	For each training prompt, the policy samples $K{=}8$ rollouts.
27	Each rollout receives a binary \emph{execution reward}:
28	\begin{equation}
29	  r_{\text{exec}}(x) = \mathbf{1}\bigl[S(F_x) = \textit{proved}\bigr]
30	  \label{eq:rexec}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-14T19:37:44.792032+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/discussion.tex",
  "content": "\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{What ISR Measures---and What It Does Not.}\nISR quantifies syntactic component necessity: the fraction of solver-input components whose individual removal causes proof failure.\nThis is strictly weaker than semantic faithfulness---whether the formalization accurately captures the natural-language meaning.\nWe verify this empirically: Spearman $\\rho(\\text{ISR}, \\text{NLI accuracy}) = -0.049$ ($p = 0.187$, n.s.) from a downstream NLI evaluation on exec-only checkpoint outputs.\nISR and downstream task performance are uncorrelated.\nISR is thus a structural integrity diagnostic, not a semantic quality metric: high ISR indicates that every component contributes to the proof, not that the proof faithfully represents the original reasoning problem.\n\nCritically, low ISR carries different semantics depending on the training objective.\nUnder exec-only training, low ISR in Prolog reflects redundant coding---repeated ground facts where removing any single copy does not affect the proof---rather than absence of reasoning (\\S\\ref{sec:crosslogic}).\nUnder ISR-as-reward, high ISR reflects metric gaming (\\S\\ref{sec:goodhart}).\nISR values must always be interpreted relative to the optimization objective that produced them.\n\n\\paragraph{The Premise-Count Confound.}\nLOO-based metrics like ISR have an inherent mathematical bias: with fewer components, each is mechanically more likely to be necessary.\nA formalization with 2 premises where both are necessary yields ISR${=}$1.0; one with 10 premises where 8 are necessary yields ISR${=}$0.8---even though the latter encodes richer reasoning.\nThis confound explains the sole apparent ISR-as-reward success (\\S\\ref{sec:goodhart}): ISR $\\beta{=}0.1$ seed~42 produces shorter formalizations, mechanically inflating ISR.\nPremise-count-matched comparison eliminates the difference ($1.06\\times$; Table~\\ref{tab:beta01-3seed}).\nThis bias is not specific to our setting---any LOO-based structural metric applied to variable-length outputs requires component-count normalization.\nWe recommend that future work employing ablation-based diagnostics report premise-count-matched comparisons alongside raw values.\n\n\\paragraph{Meta-Level Goodhart's Law: Implications.}\nThe meta-Goodhart finding extends beyond this specific system.\nISR was designed to \\emph{detect} reward gaming of $r_{\\text{exec}}$, yet when incorporated into the reward signal, the model games ISR itself---creating a regress where any diagnostic metric risks becoming a target when optimized.\n\nThe dose-response pattern ($\\beta{=}0.1$: proxy gaming inflates ISR without genuine improvement; $\\beta{=}0.3$: performance collapse) maps onto the trajectory predicted by \\cite{gao-reward-overoptimization}, but at a meta level: the proxy being gamed is itself a gaming detector.\nUnder the taxonomy of \\cite{manheim-goodhart-taxonomy}, $\\beta{=}0.3$ exemplifies extremal Goodhart---the optimizer enters a regime where the proxy-target relationship breaks down entirely---while $\\beta{=}0.1$ instantiates a meta-level variant where the diagnostic is gamed through its own measurement mechanism.\n\nThe practical implication is that ISR---and structurally similar diagnostics---should be used exclusively as post-hoc evaluation tools, never as training rewards.\nThe fundamental asymmetry (reliable as observer, unreliable as optimizer) may generalize to other ablation-based or perturbation-based quality metrics in neurosymbolic systems.\n\n\\paragraph{Single-Seed Unreliability.}\nThe three exec-only seeds diverge radically (PR $\\sigma{=}\\pm 47$ percentage points), each converging to a qualitatively different degeneration mode (\\S\\ref{sec:diagnostic}).\nISR $\\beta{=}0.1$ seeds show similar divergence: 2/3 dominated by conclusion duplication (H7), 1/3 by premise minimization (\\S\\ref{sec:goodhart}).\nThis underscores that single-seed evaluation of GRPO-trained formalizers is unreliable---both for prove rate and for structural quality.\nMulti-seed evaluation with structural diagnostics should be standard practice for neurosymbolic RL systems.\n\n\\paragraph{Limitations.}\nAll experiments use a single base model (Qwen3-4B); whether ISR dynamics generalize to larger models or different architectures is untested.\nWe evaluate on a single dataset (ProofWriter FOL problems)---more diverse reasoning benchmarks would strengthen generality claims.\nAs discussed above, ISR captures syntactic necessity, not semantic faithfulness; it cannot assess whether a formalization accurately represents the original problem's meaning.\nWhile three seeds suffice to demonstrate cross-seed divergence, more seeds would yield tighter statistical estimates.\nFinally, STA requires a solver that accepts component-level input manipulation; not all verification backends support this, limiting applicability to systems with decomposable solver inputs.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/discussion.tex",
    "content": "\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{What ISR Measures---and What It Does Not.}\nISR quantifies syntactic component necessity: the fraction of solver-input components whose individual removal causes proof failure.\nThis is strictly weaker than semantic faithfulness---whether the formalization accurately captures the natural-language meaning.\nWe verify this empirically: Spearman $\\rho(\\text{ISR}, \\text{NLI accuracy}) = -0.049$ ($p = 0.187$, n.s.) from a downstream NLI evaluation on exec-only checkpoint outputs.\nISR and downstream task performance are uncorrelated.\nISR is thus a structural integrity diagnostic, not a semantic quality metric: high ISR indicates that every component contributes to the proof, not that the proof faithfully represents the original reasoning problem.\n\nCritically, low ISR carries different semantics depending on the training objective.\nUnder exec-only training, low ISR in Prolog reflects redundant coding---repeated ground facts where removing any single copy does not affect the proof---rather than absence of reasoning (\\S\\ref{sec:crosslogic}).\nUnder ISR-as-reward, high ISR reflects metric gaming (\\S\\ref{sec:goodhart}).\nISR values must always be interpreted relative to the optimization objective that produced them.\n\n\\paragraph{The Premise-Count Confound.}\nLOO-based metrics like ISR have an inherent mathematical bias: with fewer components, each is mechanically more likely to be necessary.\nA formalization with 2 premises where both are necessary yields ISR${=}$1.0; one with 10 premises where 8 are necessary yields ISR${=}$0.8---even though the latter encodes richer reasoning.\nThis confound explains the sole apparent ISR-as-reward success (\\S\\ref{sec:goodhart}): ISR $\\beta{=}0.1$ seed~42 produces shorter formalizations, mechanically inflating ISR.\nPremise-count-matched comparison eliminates the difference ($1.06\\times$; Table~\\ref{tab:beta01-3seed}).\nThis bias is not specific to our setting---any LOO-based structural metric applied to variable-length outputs requires component-count normalization.\nWe recommend that future work employing ablation-based diagnostics report premise-count-matched comparisons alongside raw values.\n\n\\paragraph{Meta-Level Goodhart's Law: Implications.}\nThe meta-Goodhart finding extends beyond this specific system.\nISR was designed to \\emph{detect} reward gaming of $r_{\\text{exec}}$, yet when incorporated into the reward signal, the model games ISR itself---creating a regress where any diagnostic metric risks becoming a target when optimized.\n\nThe dose-response pattern ($\\beta{=}0.1$: proxy gaming inflates ISR without genuine improvement; $\\beta{=}0.3$: performance collapse) maps onto the trajectory predicted by \\cite{gao-reward-overoptimization}, but at a meta level: the proxy being gamed is itself a gaming detector.\nUnder the taxonomy of \\cite{manheim-goodhart-taxonomy}, $\\beta{=}0.3$ exemplifies extremal Goodhart---the optimizer enters a regime where the proxy-target relationship breaks down entirely---while $\\beta{=}0.1$ instantiates a meta-level variant where the diagnostic is gamed through its own measurement mechanism.\n\nThe practical implication is that ISR---and structurally similar diagnostics---should be used exclusively as post-hoc evaluation tools, never as training rewards.\nThe fundamental asymmetry (reliable as observer, unreliable as optimizer) may generalize to other ablation-based or perturbation-based quality metrics in neurosymbolic systems.\n\n\\paragraph{Single-Seed Unreliability.}\nThe three exec-only seeds diverge radically (PR $\\sigma{=}\\pm 47$ percentage points), each converging to a qualitatively different degeneration mode (\\S\\ref{sec:diagnostic}).\nISR $\\beta{=}0.1$ seeds show similar divergence: 2/3 dominated by conclusion duplication (H7), 1/3 by premise minimization (\\S\\ref{sec:goodhart}).\nThis underscores that single-seed evaluation of GRPO-trained formalizers is unreliable---both for prove rate and for structural quality.\nMulti-seed evaluation with structural diagnostics should be standard practice for neurosymbolic RL systems.\n\n\\paragraph{Limitations.}\nAll experiments use a single base model (Qwen3-4B); whether ISR dynamics generalize to larger models or different architectures is untested.\nWe evaluate on a single dataset (ProofWriter FOL problems)---more diverse reasoning benchmarks would strengthen generality claims.\nAs discussed above, ISR captures syntactic necessity, not semantic faithfulness; it cannot assess whether a formalization accurately represents the original problem's meaning.\nWhile three seeds suffice to demonstrate cross-seed divergence, more seeds would yield tighter statistical estimates.\nFinally, STA requires a solver that accepts component-level input manipulation; not all verification backends support this, limiting applicability to systems with decomposable solver inputs.\n"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-14T19:37:44.792201+00:00_

&lt;tool_use_error>File has been modified since read, either by the user or by a linter. Read it again before attempting to write it.&lt;/tool_use_error>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-14T19:37:44.792322+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/discussion.tex"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-14T19:37:44.792467+00:00_

1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{ISR Capability Boundary.}
5	ISR measures syntactic component necessity---whether each component is individually required for proof success---not semantic faithfulness to the natural language input.
6	A formalization where every component is necessary may still misrepresent the intended reasoning chain.
7	We verify this empirically: downstream NLI accuracy shows no correlation with ISR (Spearman $\rho = -0.049$, $p = 0.187$, n.s.), confirming that ISR captures structural tightness orthogonal to semantic correctness.
8	Practitioners should treat ISR as a necessary-but-not-sufficient diagnostic: low ISR reliably indicates structural degeneration, but high ISR does not guarantee faithful reasoning.
9	Importantly, low ISR carries different semantics depending on the training objective.
10	Under exec-only training, low ISR in Prolog reflects redundant coding---repeated ground facts where removing any single copy does not affect the proof---rather than absence of reasoning.
11	Under ISR-as-reward, high ISR reflects metric gaming.
12	ISR values must always be interpreted in the context of the optimization objective that produced them.
13	
14	\paragraph{Premise Count Confound.}
15	LOO-based metrics like ISR are mathematically biased by component count.
16	With $n$ components, each carries a $1/n$ share of the proof burden; fewer components mechanically inflate ISR regardless of quality.
17	As shown in \S\ref{sec:goodhart}, over half of ISR-reward genuine samples contain only 1--2 premises, where ISR $\geq 0.5$ is an arithmetic inevitability.
18	Controlling for premise count eliminates the apparent ISR advantage entirely (1.06$\times$ vs.\ the raw 2.4$\times$).
19	This confound is not specific to our setting: any LOO-based diagnostic applied to variable-length structured outputs requires component-count normalization.
20	We recommend that future work employing LOO-based structural metrics report premise-count-mat
…[truncated 3091 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-14T19:37:44.792616+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/discussion.tex",
  "content": "\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{What ISR Measures---and What It Does Not.}\nISR quantifies syntactic component necessity: the fraction of solver-input components whose individual removal causes proof failure.\nThis is strictly weaker than semantic faithfulness---whether the formalization accurately captures the natural-language meaning.\nWe verify this empirically: Spearman $\\rho(\\text{ISR}, \\text{NLI accuracy}) = -0.049$ ($p = 0.187$, n.s.) from a downstream NLI evaluation on exec-only checkpoint outputs.\nISR and downstream task performance are uncorrelated.\nISR is thus a structural integrity diagnostic, not a semantic quality metric: high ISR indicates that every component contributes to the proof, not that the proof faithfully represents the original reasoning problem.\n\nCritically, low ISR carries different semantics depending on the training objective.\nUnder exec-only training, low ISR in Prolog reflects redundant coding---repeated ground facts where removing any single copy does not affect the proof---rather than absence of reasoning (\\S\\ref{sec:crosslogic}).\nUnder ISR-as-reward, high ISR reflects metric gaming (\\S\\ref{sec:goodhart}).\nISR values must always be interpreted relative to the optimization objective that produced them.\n\n\\paragraph{The Premise-Count Confound.}\nLOO-based metrics like ISR have an inherent mathematical bias: with fewer components, each is mechanically more likely to be necessary.\nA formalization with 2 premises where both are necessary yields ISR${=}$1.0; one with 10 premises where 8 are necessary yields ISR${=}$0.8---even though the latter encodes richer reasoning.\nThis confound explains the sole apparent ISR-as-reward success (\\S\\ref{sec:goodhart}): ISR $\\beta{=}0.1$ seed~42 produces shorter formalizations, mechanically inflating ISR.\nPremise-count-matched comparison eliminates the difference ($1.06\\times$; Table~\\ref{tab:beta01-3seed}).\nThis bias is not specific to our setting---any LOO-based structural metric applied to variable-length outputs requires component-count normalization.\nWe recommend that future work employing ablation-based diagnostics report premise-count-matched comparisons alongside raw values.\n\n\\paragraph{Meta-Level Goodhart's Law: Implications.}\nThe meta-Goodhart finding extends beyond this specific system.\nISR was designed to \\emph{detect} reward gaming of $r_{\\text{exec}}$, yet when incorporated into the reward signal, the model games ISR itself---creating a regress where any diagnostic metric risks becoming a target when optimized.\n\nThe dose-response pattern ($\\beta{=}0.1$: proxy gaming inflates ISR without genuine improvement; $\\beta{=}0.3$: performance collapse) maps onto the trajectory predicted by \\cite{gao-reward-overoptimization}, but at a meta level: the proxy being gamed is itself a gaming detector.\nUnder the taxonomy of \\cite{manheim-goodhart-taxonomy}, $\\beta{=}0.3$ exemplifies extremal Goodhart---the optimizer enters a regime where the proxy-target relationship breaks down entirely---while $\\beta{=}0.1$ instantiates a meta-level variant where the diagnostic is gamed through its own measurement mechanism.\n\nThe practical implication is that ISR---and structurally similar diagnostics---should be used exclusively as post-hoc evaluation tools, never as training rewards.\nThe fundamental asymmetry (reliable as observer, unreliable as optimizer) may generalize to other ablation-based or perturbation-based quality metrics in neurosymbolic systems.\n\n\\paragraph{Single-Seed Unreliability.}\nThe three exec-only seeds diverge radically (PR $\\sigma{=}\\pm 47$ percentage points), each converging to a qualitatively different degeneration mode (\\S\\ref{sec:diagnostic}).\nISR $\\beta{=}0.1$ seeds show similar divergence: 2/3 dominated by conclusion duplication (H7), 1/3 by premise minimization (\\S\\ref{sec:goodhart}).\nThis underscores that single-seed evaluation of GRPO-trained formalizers is unreliable---both for prove rate and for structural quality.\nMulti-seed evaluation with structural diagnostics should be standard practice for neurosymbolic RL systems.\n\n\\paragraph{Limitations.}\nAll experiments use a single base model (Qwen3-4B); whether ISR dynamics generalize to larger models or different architectures is untested.\nWe evaluate on a single dataset (ProofWriter FOL problems)---more diverse reasoning benchmarks would strengthen generality claims.\nAs discussed above, ISR captures syntactic necessity, not semantic faithfulness; it cannot assess whether a formalization accurately represents the original problem's meaning.\nWhile three seeds suffice to demonstrate cross-seed divergence, more seeds would yield tighter statistical estimates.\nFinally, STA requires a solver that accepts component-level input manipulation; not all verification backends support this, limiting applicability to systems with decomposable solver inputs.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/discussion.tex",
    "content": "\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{What ISR Measures---and What It Does Not.}\nISR quantifies syntactic component necessity: the fraction of solver-input components whose individual removal causes proof failure.\nThis is strictly weaker than semantic faithfulness---whether the formalization accurately captures the natural-language meaning.\nWe verify this empirically: Spearman $\\rho(\\text{ISR}, \\text{NLI accuracy}) = -0.049$ ($p = 0.187$, n.s.) from a downstream NLI evaluation on exec-only checkpoint outputs.\nISR and downstream task performance are uncorrelated.\nISR is thus a structural integrity diagnostic, not a semantic quality metric: high ISR indicates that every component contributes to the proof, not that the proof faithfully represents the original reasoning problem.\n\nCritically, low ISR carries different semantics depending on the training objective.\nUnder exec-only training, low ISR in Prolog reflects redundant coding---repeated ground facts where removing any single copy does not affect the proof---rather than absence of reasoning (\\S\\ref{sec:crosslogic}).\nUnder ISR-as-reward, high ISR reflects metric gaming (\\S\\ref{sec:goodhart}).\nISR values must always be interpreted relative to the optimization objective that produced them.\n\n\\paragraph{The Premise-Count Confound.}\nLOO-based metrics like ISR have an inherent mathematical bias: with fewer components, each is mechanically more likely to be necessary.\nA formalization with 2 premises where both are necessary yields ISR${=}$1.0; one with 10 premises where 8 are necessary yields ISR${=}$0.8---even though the latter encodes richer reasoning.\nThis confound explains the sole apparent ISR-as-reward success (\\S\\ref{sec:goodhart}): ISR $\\beta{=}0.1$ seed~42 produces shorter formalizations, mechanically inflating ISR.\nPremise-count-matched comparison eliminates the difference ($1.06\\times$; Table~\\ref{tab:beta01-3seed}).\nThis bias is not specific to our setting---any LOO-based structural metric applied to variable-length outputs requires component-count normalization.\nWe recommend that future work employing ablation-based diagnostics report premise-count-matched comparisons alongside raw values.\n\n\\paragraph{Meta-Level Goodhart's Law: Implications.}\nThe meta-Goodhart finding extends beyond this specific system.\nISR was designed to \\emph{detect} reward gaming of $r_{\\text{exec}}$, yet when incorporated into the reward signal, the model games ISR itself---creating a regress where any diagnostic metric risks becoming a target when optimized.\n\nThe dose-response pattern ($\\beta{=}0.1$: proxy gaming inflates ISR without genuine improvement; $\\beta{=}0.3$: performance collapse) maps onto the trajectory predicted by \\cite{gao-reward-overoptimization}, but at a meta level: the proxy being gamed is itself a gaming detector.\nUnder the taxonomy of \\cite{manheim-goodhart-taxonomy}, $\\beta{=}0.3$ exemplifies extremal Goodhart---the optimizer enters a regime where the proxy-target relationship breaks down entirely---while $\\beta{=}0.1$ instantiates a meta-level variant where the diagnostic is gamed through its own measurement mechanism.\n\nThe practical implication is that ISR---and structurally similar diagnostics---should be used exclusively as post-hoc evaluation tools, never as training rewards.\nThe fundamental asymmetry (reliable as observer, unreliable as optimizer) may generalize to other ablation-based or perturbation-based quality metrics in neurosymbolic systems.\n\n\\paragraph{Single-Seed Unreliability.}\nThe three exec-only seeds diverge radically (PR $\\sigma{=}\\pm 47$ percentage points), each converging to a qualitatively different degeneration mode (\\S\\ref{sec:diagnostic}).\nISR $\\beta{=}0.1$ seeds show similar divergence: 2/3 dominated by conclusion duplication (H7), 1/3 by premise minimization (\\S\\ref{sec:goodhart}).\nThis underscores that single-seed evaluation of GRPO-trained formalizers is unreliable---both for prove rate and for structural quality.\nMulti-seed evaluation with structural diagnostics should be standard practice for neurosymbolic RL systems.\n\n\\paragraph{Limitations.}\nAll experiments use a single base model (Qwen3-4B); whether ISR dynamics generalize to larger models or different architectures is untested.\nWe evaluate on a single dataset (ProofWriter FOL problems)---more diverse reasoning benchmarks would strengthen generality claims.\nAs discussed above, ISR captures syntactic necessity, not semantic faithfulness; it cannot assess whether a formalization accurately represents the original problem's meaning.\nWhile three seeds suffice to demonstrate cross-seed divergence, more seeds would yield tighter statistical estimates.\nFinally, STA requires a solver that accepts component-level input manipulation; not all verification backends support this, limiting applicability to systems with decomposable solver inputs.\n"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-14T19:37:44.792857+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper/discussion.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_discussion_20260514T193516",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 21 · 2026-05-14T19:37:44.793025+00:00_

Written. The section has 5 paragraphs (~590 words):

1. **What ISR Measures---and What It Does Not** — syntactic necessity ≠ semantic faithfulness; ρ=−0.049 finding; dual semantics of low ISR (redundant coding vs. metric gaming per C006)
2. **The Premise-Count Confound** — LOO bias from component count; 1.06× after matching; general warning for ablation-based metrics
3. **Meta-Level Goodhart's Law: Implications** — regress problem; dose-response mapped to Gao et al. trajectory; observer/optimizer asymmetry; ISR = post-hoc only
4. **Single-Seed Unreliability** — PR σ=±47pp divergence; multi-seed + structural diagnostics as standard practice
5. **Limitations** — single model, single dataset, syntactic-only, three seeds, solver-specific

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_discussion_20260514T193516"
}
```

</details>

---
