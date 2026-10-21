# paper writing prop1 integration

**Beyond Self-Consistency: Self-Extracted Constraints Reduce to Majority Voting under Zero-Shot Extraction** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 15
- **Recorded user turns:** 0
- **Tool calls:** 7
- **Original source:** `logs/chats/worker_paper_writing_prop1_integration_20260523T034856.jsonl`
- **Structured JSON:** [`69d60f828cf073ac1c63.json`](../../sessions/69/69d60f828cf073ac1c63.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

15 recorded events

### Tool call

_source line 1 · 2026-05-23T03:52:39.297850+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-23T03:52:39.298475+00:00_

1	---
2	name: paper-writing-norms
3	description: 顶会级别论文写作风格规范——章节写法（Abstract/Intro/Related Work）、去 AI 风格、视觉密度、叙事哲学。Paper Agent 和 Worker 写论文章节时必须加载。
4	allowed-tools: [Read, Write, Edit, Glob, Grep]
5	scope: global
6	version: 2
7	priority: 9
8	tags:
9	  - writing
10	  - paper
11	  - style
12	  - norms
13	roles:
14	  - agent
15	  - worker
16	  - paper_agent
17	---
18	
19	# 论文写作风格规范
20	
21	> 核心哲学：**论文是一个有说服力的故事，不是实验报告。** 审稿人在几十秒内判断论文价值——如果 Abstract 和 Introduction 读起来像实验日志，论文就已经失败了。
22	
23	---
24	
25	## 一、总体写作哲学
26	
27	### 1.1 故事驱动，不是数据堆砌
28	
29	- 论文必须以"故事线"为核心展开：问题 → 洞察 → 方法 → 验证
30	- 禁止大量实验数据堆砌——每个数字出现必须服务于叙事推进
31	- 附录内容必须在正文中有明确引用且融入叙事，禁止简单堆砌
32	- 如果附录数据对核心叙事有重大影响，根据附录数据调整论文 framing
33	
34	### 1.2 主线统一性
35	
36	- 当 idea 在研究过程中发生变化后，**必须重审全文逻辑**
37	- 常见问题：Introduction 讲的故事 A，Method 做的是故事 B，Results 又在讲故事 C
38	- 修复方式：从最终实验结论反推，重写 Introduction 的问题定义和动机
39	- 每次 idea 调整后检查：Abstract → Introduction → Method → Results → Discussion → Conclusion 是否形成一条连贯主线
40	
41	### 1.3 专有名词必须有定义
42	
43	- 首次出现的专有名词/缩写必须给出完整定义和解释
44	- Abstract 中使用的缩写也必须在 Abstract 内定义（如 LLM = Large Language Model）
45	- 不能假设读者知道你自己定义的术语——论文从来没解释过的概念不能直接使用
46	- 通用规则：如果一个非标准术语第一次出现时没有括号定义，就是写作 bug
47	
48	### 1.4 写作前必读同类优秀论文
49	
50	- 每个章节动笔前，找 **2-3 篇目标会议近 1-2 年的高分论文**作为风格参考——同类问题或同类方法皆可
51	- 重点学：
52	  - Abstract 怎么用最少篇幅讲完故事
53	  - Introduction 怎么从大问题切入到具体贡献
54	  - Related Work 怎么 positioning 自己（不是 survey）
55	  - Table/Figure 怎么压缩信息密度
56	- **不是抄袭**，是学习同行的故事节奏和审美——不同子领域叙事节奏差异很大
57	- 实操：Paper Agent 可以从 `literature_map.yaml` 中挑 `role=foundation` 或 `role=direct-competitor` 的论文，把 `{title, venue, year, abstract}` 附在 Worker 的 task_prompt 中作为概念参考；如需学习写作风格本身，让 Worker 通过 WebSearch 取得论文链接并 fetch 全文
58	
59	---
60	
61	## 二、Abstract 写作规范
62	
63	### 2.1 四个必答问题（150-250 words）
64	
65	Abstract 必须在很短的篇幅内清楚回答：
66	1. **研究什么问题** — 1-2 句话交代背景和痛点
67	2. **为什么重要** — 现有方法的不足（不用写太多）
68	3. **本文提出什么** — 核心贡献的关键机制（简要，不堆砌细节）
69	4. **结果说明什么** — 用具体实验结论支撑贡献
70	
71	### 2.2 禁忌
72	
73	- **禁止堆砌数据**：Abstract 不是 Results 的缩写。最多引用 2-3 个关键数字，要服务于 claim
74	- **
…[truncated 5709 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-23T03:52:39.298682+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/proposition1_scb_proof.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/artifacts/proposition1_scb_proof.tex"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-23T03:52:39.298928+00:00_

1	% Proposition 1: Symbolic Confirmation Bias is Structural
2	% Place after the empirical BR paragraph in §3.2 (analysis.tex, ~line 17),
3	% or at the end of §2.3 (method.tex) after Eq.(4) degeneration condition.
4	% Requires: amsmath, amssymb, enumitem (all already loaded in main.tex).
5	
6	\textbf{Proposition 1} \textit{(Symbolic Confirmation Bias is Structural).}\;%
7	Let $t_1, \dots, t_K \overset{\mathrm{i.i.d.}}{\sim} P_M(\cdot \mid q)$ be reasoning traces from model $M$ on question $q$.
8	Assume:
9	\begin{enumerate}[label=\textbf{A\arabic*.},leftmargin=2.5em,nosep]
10	\item Answers are trace-determined: $a_i = h(t_i)$.
11	\item Constraints are trace-determined: $c_i = f(t_i)$.
12	\end{enumerate}
13	Let $\hat{a} = \mathrm{mode}(a_1, \dots, a_K)$, $n_a = |\{i : a_i = a\}|$, and $Y$ the ground truth. Then:
14	\begin{enumerate}[label=\textit{(\roman*)},leftmargin=1.8em,itemsep=2pt,topsep=3pt]
15	\item \textit{Voting degeneration.}\;
16	Under source attribution $\sigma(c_i, a) \triangleq \mathbf{1}[a_i = a]$, the constraint score reduces to the majority-vote count: $\operatorname{score}(a) = n_a$.
17	When $|\{a : n_a > 0\}| \geq 2$, the bias ratio satisfies $\mathrm{BR} \triangleq n_{\hat{a}} \big/ \max_{a' \neq \hat{a}} n_{a'} \geq 1$.
18	
19	\item \textit{Information ceiling.}\;
20	$I(C_{1:K};\, Y) \leq I(T_{1:K};\, Y)$ and $I(C_{1:K};\, Y \mid A_{1:K}) \leq I(T_{1:K};\, Y \mid A_{1:K})$:
21	self-extracted constraints cannot carry more information about $Y$ than the source traces---even beyond what the answers already encode.
22	\end{enumerate}
23	\noindent
24	Both bounds hold for \emph{any} model $M$, task $q$, and extraction function $f$.
25	
26	\medskip
27	\textit{Proof.}\;%
28	\textit{(i)}\; By definition, $\operatorname{score}(a) = \sum_{i=1}^K \mathbf{1}[a_i = a] = n_a$, maximized at $\hat{a}$, so $\mathrm{BR} \geq 1$.
29	\textit{(ii)}\; $c_i = f(t_i)$ makes $C_{1:K}$ a deterministic function of $T_{1:K}$, so $Y \mathop{\text{---}} T_{1:K} \mathop{\text{---
…[truncated 3920 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-23T03:52:39.299110+00:00_

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
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-23T03:52:39.299307+00:00_

1	\section{The Symbolic Mirage}
2	\label{sec:analysis}
3	
4	\subsection{Symbolic Confirmation Bias}
5	\label{sec:confirmation-bias}
6	
7	\looseness=-1 Self-extracted constraints systematically align with the model's majority answer. On Mistral-7B FOLIO, when SICA errs, 83.3\% of constraints support the incorrect answer---bias ratio $4.97\times$ (Table~\ref{tab:cross-model-bias})---and 94\% of errors overlap with SC. A shuffle control reveals this bias is \emph{structural}: randomizing constraint--answer associations while preserving per-trace counts yields $\text{BR}_\text{null} \approx \text{BR}_\text{obs}$ ($p > 0.7$), indicating that BR reflects the trace-count distribution rather than extraction-specific error. Z3 rejects only 3.4\% of constraints, and MAX-SAT produces answers identical to count-only aggregation on 94.4\% of problems (Table~\ref{tab:ablation}), confirming that the formal verification layer is vacuous (Eq.~\ref{eq:degenerate}): 99\% of constraints pass Z3 validation yet add no information beyond majority voting. This vacuity is $\alpha$-insensitive: agreement $\geq$99\% across $\alpha \in \{0.1, \ldots, 0.9\}$ (Table~\ref{tab:alpha-ablation}).
8	
9	\looseness=-1 This bias is not an artifact of incorrect majority votes: on problems where SC selects the correct answer, constraints still disproportionately support the majority ($\text{BR}_\text{correct}$ $1.29$--$3.64\times$ across all six tested conditions, with 5/6 showing $\text{BR}_\text{correct} \geq \text{BR}_\text{wrong}$), confirming that self-extracted constraints track distributional frequency rather than logical validity.
10	
11	\looseness=-1 The pattern generalizes: $4.97\times$ (Mistral), $3.85\times$ (Qwen-14B), $2.88\times$ (LLaMA), all $> 1.0$ with 95\% bootstrap CIs (Table~\ref{tab:cross-model-bias}). Cross-model extraction confirms universality across nine models from 7B to frontier (BR $1.66$--$4.97\times$; Table~\ref{tab:frontier-scb}). BR $> 1$ further holds across all eight cel
…[truncated 6879 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-23T03:52:39.299492+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "eq:score|eq:mirage|eq:degenerate|\\\\sigma\\(c",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex",
  "output_mode": "content",
  "-C": "3"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Grep",
  "tool_args": {
    "pattern": "eq:score|eq:mirage|eq:degenerate|\\\\sigma\\(c",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex",
    "output_mode": "content",
    "-C": "3"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-23T03:52:39.299642+00:00_

27-
28-\paragraph{Scoring.} Let $\mathcal{C}^{\setminus} = \mathcal{C} \setminus \mathcal{C}^*$. Each candidate $a$ is scored by:
29-\begin{equation}
30:\label{eq:score}
31:\text{score}(a) = \sum_{c \in \mathcal{C}^*} w_c \cdot \sigma(c, a) - \alpha \sum_{c \in \mathcal{C}^{\setminus}} w_c \cdot \sigma(c, a),
32-\end{equation}
33:where $\sigma(c, a) = 1$ if $c$ was extracted from any trace producing answer $a$, and $\alpha = 0.5$. The selected answer is $a^* = \arg\max_{a} \text{score}(a)$.
34-
35-\paragraph{Degeneration condition.} If self-extracted constraints are coupled to their source answer, MAX-SAT retains nearly all ($|\mathcal{C}^{\setminus}| \approx 0$), and scoring degenerates to:
36-\begin{equation}
37:\label{eq:degenerate}
38-\text{score}(a) \approx \sum_{\substack{c \in \mathcal{C}^* \\ \text{source}(c) \to a}} w_c,
39-\end{equation}
40-equivalent to majority voting. We show in \S\ref{sec:confirmation-bias} that this degeneration occurs in practice.
--
42-\paragraph{The $C_0$ diagnostic.} The multi-candidate rate $C_0 = |\{q : |\mathcal{A}(q)| > 1\}| / |\mathcal{Q}|$ is a zero-cost diagnostic: $C_0 < 5\%$ means SICA reduces to SC. $\alpha = 0.5$ is not critical (${\pm}0.49$\,pp across $\alpha \in [0, 1]$).
43-
44-\paragraph{Bias ratio.} We quantify extraction bias via the \emph{bias ratio}:
45:\begin{equation}\label{eq:mirage}
46-\text{BR}(M,T) = \frac{P(c \text{ supports } a_M \mid a_M \neq a^*)}{P(c \text{ supports } a^* \mid a_M \neq a^*)},
47-\end{equation}
48-where $c$ is a self-extracted constraint, $a_M$ the model's majority answer, and $a^*$ the ground truth. $\text{BR} > 1$ indicates constraints project model bias rather than provide independent verification; $\text{BR} = 1$ indicates unbiased extraction. We validate this metric empirically in \S\ref{sec:confirmation-bias}.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-23T03:52:39.299963+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex",
  "old_string": "\\looseness=-1 Self-extracted constraints systematically align with the model's majority answer. On Mistral-7B FOLIO, when SICA errs, 83.3\\% of constraints support the incorrect answer---bias ratio $4.97\\times$ (Table~\\ref{tab:cross-model-bias})---and 94\\% of errors overlap with SC. A shuffle control reveals this bias is \\emph{structural}: randomizing constraint--answer associations while preserving per-trace counts yields $\\text{BR}_\\text{null} \\approx \\text{BR}_\\text{obs}$ ($p > 0.7$), indicating that BR reflects the trace-count distribution rather than extraction-specific error. Z3 rejects only 3.4\\% of constraints, and MAX-SAT produces answers identical to count-only aggregation on 94.4\\% of problems (Table~\\ref{tab:ablation}), confirming that the formal verification layer is vacuous (Eq.~\\ref{eq:degenerate}): 99\\% of constraints pass Z3 validation yet add no information beyond majority voting. This vacuity is $\\alpha$-insensitive: agreement $\\geq$99\\% across $\\alpha \\in \\{0.1, \\ldots, 0.9\\}$ (Table~\\ref{tab:alpha-ablation}).\n\n\\looseness=-1 This bias is not an artifact of incorrect majority votes: on problems where SC selects the correct answer, constraints still disproportionately support the majority ($\\text{BR}_\\text{correct}$ $1.29$--$3.64\\times$ across all six tested conditions, with 5/6 showing $\\text{BR}_\\text{correct} \\geq \\text{BR}_\\text{wrong}$), confirming that self-extracted constraints track distributional frequency rather than logical validity.",
  "new_string": "\\looseness=-1 Self-extracted constraints systematically align with the model's majority answer. On Mistral-7B FOLIO, when SICA errs, 83.3\\% of constraints support the incorrect answer---bias ratio $4.97\\times$ (Table~\\ref{tab:cross-model-bias})---and 94\\% of errors overlap with SC. Z3 rejects only 3.4\\% of constraints, and MAX-SAT produces answers identical to count-only aggregation on 94.4\\% of problems (Table~\\ref{tab:ablation}), confirming that the formal verification layer is vacuous (Eq.~\\ref{eq:degenerate}): 99\\% of constraints pass Z3 validation yet add no information beyond majority voting. This vacuity is $\\alpha$-insensitive: agreement $\\geq$99\\% across $\\alpha \\in \\{0.1, \\ldots, 0.9\\}$ (Table~\\ref{tab:alpha-ablation}).\nThe following result formalizes this degeneration.\n\n\\medskip\\noindent\n\\textbf{Proposition 1} \\textit{(Symbolic Confirmation Bias is Structural).}\\;%\nLet $t_1, \\ldots, t_K \\overset{\\mathrm{i.i.d.}}{\\sim} P_M(\\cdot \\mid q)$ be reasoning traces from model $M$ on question $q$.\nAssume:\n\\begin{enumerate}[label=\\textbf{A\\arabic*.},leftmargin=2.5em,nosep]\n\\item Answers are trace-determined: $a_i = h(t_i)$.\n\\item Constraints are trace-determined: $c_i = f(t_i)$.\n\\end{enumerate}\nLet $\\hat{a} = \\mathrm{mode}(a_1, \\ldots, a_K)$, $n_a = |\\{i : a_i = a\\}|$, and $Y$ the ground truth. Then:\n\\begin{enumerate}[label=\\textit{(\\roman*)},leftmargin=1.8em,itemsep=2pt,topsep=3pt]\n\\item \\textit{Voting degeneration.}\\;\nUnder source attribution (Eq.~\\ref{eq:score}), the constraint score reduces to the majority-vote count: $\\operatorname{score}(a) = n_a$.\nWhen $|\\{a : n_a > 0\\}| \\geq 2$, the bias ratio satisfies $\\mathrm{BR} \\triangleq n_{\\hat{a}} \\big/ \\max_{a' \\neq \\hat{a}} n_{a'} \\geq 1$.\n\n\\item \\textit{Information ceiling.}\\;\n$I(C_{1:K};\\, Y) \\leq I(T_{1:K};\\, Y)$ and $I(C_{1:K};\\, Y \\mid A_{1:K}) \\leq I(T_{1:K};\\, Y \\mid A_{1:K})$:\nself-extracted constraints cannot carry more information about $Y$ than the source traces, even beyond what the answers already encode.\n\\end{enumerate}\n\\noindent\nBoth bounds hold for \\emph{any} model $M$, task $q$, and extraction function $f$.\n\n\\medskip\n\\textit{Proof.}\\;%\n\\textit{(i)}\\; By definition, $\\operatorname{score}(a) = \\sum_{i=1}^K \\mathbf{1}[a_i = a] = n_a$, maximized at $\\hat{a}$, so $\\mathrm{BR} \\geq 1$.\n\\textit{(ii)}\\; $c_i = f(t_i)$ makes $C_{1:K}$ a deterministic function of $T_{1:K}$, so $Y \\mathop{\\text{---}} T_{1:K} \\mathop{\\text{---}} C_{1:K}$ forms a Markov chain and the data processing inequality gives $I(C_{1:K}; Y) \\leq I(T_{1:K}; Y)$.\nThe conditional bound follows identically: $c_i = f(t_i)$ holds unconditionally, so the Markov property and DPI apply within each stratum $\\{A_{1:K} = \\mathbf{a}\\}$.\\hfill$\\square$\n\n\\medskip\\noindent\nEach constraint is a downstream product of a trace that simultaneously determines an answer; constraint-based aggregation therefore cannot escape the distributional bias of the answer vote.\nNeither bound depends on model capability, task difficulty, or extraction quality. The bias is a structural artifact of the self-extraction pipeline.\n\n\\medskip\\noindent\n\\textbf{Remark.}\\;%\nPart~\\textit{(i)} relies on source attribution (Eq.~\\ref{eq:score}), the mechanism used by SICA.\nUnder \\emph{semantic} evaluation (checking whether $c_i$ is logically consistent with answer $a$ directly), $\\mathrm{BR} \\geq 1$ additionally requires \\emph{answer alignment}: $P(c_i \\text{ supports } a_i) \\geq P(c_i \\text{ supports } a')$ for $a' \\neq a_i$.\nThis property is structurally motivated (the reasoning chain producing $a_i$ generates intermediate steps aligned with $a_i$) and is empirically validated across all nine model--task conditions ($\\mathrm{BR} \\in [1.66,\\, 4.97]$; Table~\\ref{tab:frontier-scb}), but is not a mathematical necessity of self-extraction alone; it could fail if $f$ systematically extracted premises that contradict their source trace's conclusion.\n\n\\looseness=-1 Empirically, confirmation bias extends beyond incorrect instances. On problems where SC selects the correct answer, constraints still disproportionately support the majority ($\\text{BR}_\\text{correct}$ $1.29$--$3.64\\times$ across all six tested conditions, with 5/6 showing $\\text{BR}_\\text{correct} \\geq \\text{BR}_\\text{wrong}$), confirming that self-extracted constraints track distributional frequency rather than logical validity. A shuffle control further confirms the structural nature of this bias: randomizing constraint--answer associations while preserving per-trace counts yields $\\text{BR}_\\text{null} \\approx \\text{BR}_\\text{obs}$ ($p > 0.7$), indicating that BR reflects the trace-count distribution rather than extraction-specific error."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex",
    "old_string": "\\looseness=-1 Self-extracted constraints systematically align with the model's majority answer. On Mistral-7B FOLIO, when SICA errs, 83.3\\% of constraints support the incorrect answer---bias ratio $4.97\\times$ (Table~\\ref{tab:cross-model-bias})---and 94\\% of errors overlap with SC. A shuffle control reveals this bias is \\emph{structural}: randomizing constraint--answer associations while preserving per-trace counts yields $\\text{BR}_\\text{null} \\approx \\text{BR}_\\text{obs}$ ($p > 0.7$), indicating that BR reflects the trace-count distribution rather than extraction-specific error. Z3 rejects only 3.4\\% of constraints, and MAX-SAT produces answers identical to count-only aggregation on 94.4\\% of problems (Table~\\ref{tab:ablation}), confirming that the formal verification layer is vacuous (Eq.~\\ref{eq:degenerate}): 99\\% of constraints pass Z3 validation yet add no information beyond majority voting. This vacuity is $\\alpha$-insensitive: agreement $\\geq$99\\% across $\\alpha \\in \\{0.1, \\ldots, 0.9\\}$ (Table~\\ref{tab:alpha-ablation}).\n\n\\looseness=-1 This bias is not an artifact of incorrect majority votes: on problems where SC selects the correct answer, constraints still disproportionately support the majority ($\\text{BR}_\\text{correct}$ $1.29$--$3.64\\times$ across all six tested conditions, with 5/6 showing $\\text{BR}_\\text{correct} \\geq \\text{BR}_\\text{wrong}$), confirming that self-extracted constraints track distributional frequency rather than logical validity.",
    "new_string": "\\looseness=-1 Self-extracted constraints systematically align with the model's majority answer. On Mistral-7B FOLIO, when SICA errs, 83.3\\% of constraints support the incorrect answer---bias ratio $4.97\\times$ (Table~\\ref{tab:cross-model-bias})---and 94\\% of errors overlap with SC. Z3 rejects only 3.4\\% of constraints, and MAX-SAT produces answers identical to count-only aggregation on 94.4\\% of problems (Table~\\ref{tab:ablation}), confirming that the formal verification layer is vacuous (Eq.~\\ref{eq:degenerate}): 99\\% of constraints pass Z3 validation yet add no information beyond majority voting. This vacuity is $\\alpha$-insensitive: agreement $\\geq$99\\% across $\\alpha \\in \\{0.1, \\ldots, 0.9\\}$ (Table~\\ref{tab:alpha-ablation}).\nThe following result formalizes this degeneration.\n\n\\medskip\\noindent\n\\textbf{Proposition 1} \\textit{(Symbolic Confirmation Bias is Structural).}\\;%\nLet $t_1, \\ldots, t_K \\overset{\\mathrm{i.i.d.}}{\\sim} P_M(\\cdot \\mid q)$ be reasoning traces from model $M$ on question $q$.\nAssume:\n\\begin{enumerate}[label=\\textbf{A\\arabic*.},leftmargin=2.5em,nosep]\n\\item Answers are trace-determined: $a_i = h(t_i)$.\n\\item Constraints are trace-determined: $c_i = f(t_i)$.\n\\end{enumerate}\nLet $\\hat{a} = \\mathrm{mode}(a_1, \\ldots, a_K)$, $n_a = |\\{i : a_i = a\\}|$, and $Y$ the ground truth. Then:\n\\begin{enumerate}[label=\\textit{(\\roman*)},leftmargin=1.8em,itemsep=2pt,topsep=3pt]\n\\item \\textit{Voting degeneration.}\\;\nUnder source attribution (Eq.~\\ref{eq:score}), the constraint score reduces to the majority-vote count: $\\operatorname{score}(a) = n_a$.\nWhen $|\\{a : n_a > 0\\}| \\geq 2$, the bias ratio satisfies $\\mathrm{BR} \\triangleq n_{\\hat{a}} \\big/ \\max_{a' \\neq \\hat{a}} n_{a'} \\geq 1$.\n\n\\item \\textit{Information ceiling.}\\;\n$I(C_{1:K};\\, Y) \\leq I(T_{1:K};\\, Y)$ and $I(C_{1:K};\\, Y \\mid A_{1:K}) \\leq I(T_{1:K};\\, Y \\mid A_{1:K})$:\nself-extracted constraints cannot carry more information about $Y$ than the source traces, even beyond what the answers already encode.\n\\end{enumerate}\n\\noindent\nBoth bounds hold for \\emph{any} model $M$, task $q$, and extraction function $f$.\n\n\\medskip\n\\textit{Proof.}\\;%\n\\textit{(i)}\\; By definition, $\\operatorname{score}(a) = \\sum_{i=1}^K \\mathbf{1}[a_i = a] = n_a$, maximized at $\\hat{a}$, so $\\mathrm{BR} \\geq 1$.\n\\textit{(ii)}\\; $c_i = f(t_i)$ makes $C_{1:K}$ a deterministic function of $T_{1:K}$, so $Y \\mathop{\\text{---}} T_{1:K} \\mathop{\\text{---}} C_{1:K}$ forms a Markov chain and the data processing inequality gives $I(C_{1:K}; Y) \\leq I(T_{1:K}; Y)$.\nThe conditional bound follows identically: $c_i = f(t_i)$ holds unconditionally, so the Markov property and DPI apply within each stratum $\\{A_{1:K} = \\mathbf{a}\\}$.\\hfill$\\square$\n\n\\medskip\\noindent\nEach constraint is a downstream product of a trace that simultaneously determines an answer; constraint-based aggregation therefore cannot escape the distributional bias of the answer vote.\nNeither bound depends on model capability, task difficulty, or extraction quality. The bias is a structural artifact of the self-extraction pipeline.\n\n\\medskip\\noindent\n\\textbf{Remark.}\\;%\nPart~\\textit{(i)} relies on source attribution (Eq.~\\ref{eq:score}), the mechanism used by SICA.\nUnder \\emph{semantic} evaluation (checking whether $c_i$ is logically consistent with answer $a$ directly), $\\mathrm{BR} \\geq 1$ additionally requires \\emph{answer alignment}: $P(c_i \\text{ supports } a_i) \\geq P(c_i \\text{ supports } a')$ for $a' \\neq a_i$.\nThis property is structurally motivated (the reasoning chain producing $a_i$ generates intermediate steps aligned with $a_i$) and is empirically validated across all nine model--task conditions ($\\mathrm{BR} \\in [1.66,\\, 4.97]$; Table~\\ref{tab:frontier-scb}), but is not a mathematical necessity of self-extraction alone; it could fail if $f$ systematically extracted premises that contradict their source trace's conclusion.\n\n\\looseness=-1 Empirically, confirmation bias extends beyond incorrect instances. On problems where SC selects the correct answer, constraints still disproportionately support the majority ($\\text{BR}_\\text{correct}$ $1.29$--$3.64\\times$ across all six tested conditions, with 5/6 showing $\\text{BR}_\\text{correct} \\geq \\text{BR}_\\text{wrong}$), confirming that self-extracted constraints track distributional frequency rather than logical validity. A shuffle control further confirms the structural nature of this bias: randomizing constraint--answer associations while preserving per-trace counts yields $\\text{BR}_\\text{null} \\approx \\text{BR}_\\text{obs}$ ($p > 0.7$), indicating that BR reflects the trace-count distribution rather than extraction-specific error."
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-23T03:52:39.300271+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-23T03:52:39.300430+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex",
  "limit": "60"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex",
    "limit": "60"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-23T03:52:39.300610+00:00_

1	\section{The Symbolic Mirage}
2	\label{sec:analysis}
3	
4	\subsection{Symbolic Confirmation Bias}
5	\label{sec:confirmation-bias}
6	
7	\looseness=-1 Self-extracted constraints systematically align with the model's majority answer. On Mistral-7B FOLIO, when SICA errs, 83.3\% of constraints support the incorrect answer---bias ratio $4.97\times$ (Table~\ref{tab:cross-model-bias})---and 94\% of errors overlap with SC. Z3 rejects only 3.4\% of constraints, and MAX-SAT produces answers identical to count-only aggregation on 94.4\% of problems (Table~\ref{tab:ablation}), confirming that the formal verification layer is vacuous (Eq.~\ref{eq:degenerate}): 99\% of constraints pass Z3 validation yet add no information beyond majority voting. This vacuity is $\alpha$-insensitive: agreement $\geq$99\% across $\alpha \in \{0.1, \ldots, 0.9\}$ (Table~\ref{tab:alpha-ablation}).
8	The following result formalizes this degeneration.
9	
10	\medskip\noindent
11	\textbf{Proposition 1} \textit{(Symbolic Confirmation Bias is Structural).}\;%
12	Let $t_1, \ldots, t_K \overset{\mathrm{i.i.d.}}{\sim} P_M(\cdot \mid q)$ be reasoning traces from model $M$ on question $q$.
13	Assume:
14	\begin{enumerate}[label=\textbf{A\arabic*.},leftmargin=2.5em,nosep]
15	\item Answers are trace-determined: $a_i = h(t_i)$.
16	\item Constraints are trace-determined: $c_i = f(t_i)$.
17	\end{enumerate}
18	Let $\hat{a} = \mathrm{mode}(a_1, \ldots, a_K)$, $n_a = |\{i : a_i = a\}|$, and $Y$ the ground truth. Then:
19	\begin{enumerate}[label=\textit{(\roman*)},leftmargin=1.8em,itemsep=2pt,topsep=3pt]
20	\item \textit{Voting degeneration.}\;
21	Under source attribution (Eq.~\ref{eq:score}), the constraint score reduces to the majority-vote count: $\operatorname{score}(a) = n_a$.
22	When $|\{a : n_a > 0\}| \geq 2$, the bias ratio satisfies $\mathrm{BR} \triangleq n_{\hat{a}} \big/ \max_{a' \neq \hat{a}} n_{a'} \geq 1$.
23	
24	\item \textit{Information ceiling.}\;
25	$I(C_{1:K};\, Y) \leq I(T_{1:K};\, Y)$ and $I(C_{1:K
…[truncated 4496 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-23T03:52:39.300805+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex",
  "offset": "60"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex",
    "offset": "60"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-23T03:52:39.301042+00:00_

60	\midrule
61	Mistral-7B & $^a$ & 55.88 & 90 & 4.97 & 0.00 \\
62	LLaMA-8B & $^a$ & \textrm{---} & \textrm{---} & 2.88 & \textrm{---} \\
63	Qwen-14B & $^a$ & 75.98 & 49 & 3.85 & $-$0.49 \\
64	\addlinespace
65	R1-Distill-8B & $^b$ & 74.51 & 52 & 2.92 & $+$2.45 \\
66	gpt-4o & $^a$ & 73.91 & 53 & 2.94 & $-$1.80 \\
67	gpt-4.1 & $^b$ & 82.84 & 35 & 2.70 & $-$1.47 \\
68	gpt-5.5 & $^b$ & 84.31 & 32 & 3.48 & $+$0.49 \\
69	o3 & $^b$ & 82.65 & 35 & 1.66 & 0.00 \\
70	Gemini-2.5-Pro$^*$ & $^b$ & 87.37 & 12 & 2.79 & $-$1.10 \\
71	\bottomrule
72	\end{tabular}}
73	\end{table}
74	
75	\looseness=-1 Two controls rule out answer leakage. BR is uniform across early, mid, and late reasoning steps (Fisher $p = 0.71$); high-consensus errors amplify to $\text{BR} = 18.8\times$ versus $2.7\times$ for low-consensus ($p < 0.001$). Removing the answer sentence from traces before extraction yields no BR decrease (Wilcoxon $p \geq 0.12$) despite significant accuracy loss (McNemar $p < 0.013$). Symbolic confirmation bias reflects a distributional prior embedded throughout reasoning, not answer contamination.
76	
77	\looseness=-1 Reasoning-process overlap exceeds answer-level correlation: on Mistral-7B FOLIO, mean process similarity (pairwise TF-IDF cosine; Appendix~\ref{app:process-gradient}) reaches 0.69, far exceeding answer-level $\kappa = 0.46$. The gap generalizes across four families (Table~\ref{tab:cross-model-process}). Under cross-model extraction, SICA gain decreases monotonically with process similarity ($\rho = -1.0$, $p = 0.008$; Table~\ref{tab:process-gradient}). Conditional correction analysis confirms the same pattern: cross-architecture NLI yields positive correction ratios while same-model SICA yields negative ones, with correction ratio correlating with combo gain ($\rho = 0.84$, $p = 0.014$; Appendix~\ref{app:cil}).
78	
79	\subsection{Why Remediation Fails}
80	\label{sec:remediation}
81	\label{sec:interventions}
82	
83	\looseness=-1 All 27 training-free remediation strategies 
…[truncated 3692 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_prop1_integration_20260523T034856",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 15 · 2026-05-23T03:52:39.301236+00:00_

§5.2, §5.3, and all tables are intact. Verification against all criteria:

1. **Proposition after SCB quantitative, before shuffle control** — lines 7–8 (empirical observation + transition), lines 10–45 (Proposition+Proof+Remark), line 47 (BR_correct + shuffle control) ✓
2. **Notation aligned with method.tex** — `\ldots` (not `\dots`), Part (i) references `Eq.~\ref{eq:score}` instead of redefining σ ✓
3. **BR_correct follows Proposition** — line 47 ✓
4. **No tcolorbox, no theorem environment** — uses `\textbf{Proposition 1} \textit{(...)}` ✓
5. **No AUTHOR NOTE comments, no deduplication caveat** — all removed ✓
6. **Em-dashes in new text eliminated** — replaced with commas, parentheses, semicolons, or periods ✓
7. **§5.2, §5.3, tables untouched** ✓

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_prop1_integration_20260523T034856"
}
```

</details>

---
