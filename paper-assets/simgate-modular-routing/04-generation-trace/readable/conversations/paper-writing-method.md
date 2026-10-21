# paper writing method

**Death Avoidance as the Dominant Routing Signal: A Counterfactual Analysis on ScienceWorld** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 15
- **Recorded user turns:** 0
- **Tool calls:** 7
- **Original source:** `logs/chats/worker_paper_writing_method_20260514T020639.jsonl`
- **Structured JSON:** [`b4373f168c32c2933864.json`](../../sessions/b4/b4373f168c32c2933864.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

15 recorded events

### Tool call

_source line 1 · 2026-05-14T02:08:13.901766+00:00_

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
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-14T02:08:13.902452+00:00_

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
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-14T02:08:13.903006+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/artifacts/_project/paper/ 2>/dev/null"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "Bash",
  "tool_args": {
    "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/artifacts/_project/paper/ 2>/dev/null"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-14T02:08:13.903269+00:00_

experiment_tables.md
introduction_draft.md
introduction_draft_d860d5.md
related_work_draft.md

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-14T02:08:13.903510+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/artifacts/_project/paper/introduction_draft.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/artifacts/_project/paper/introduction_draft.md"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-14T02:08:13.903756+00:00_

1	# Introduction — Draft v1
2	
3	\section{Introduction}
4	
5	When LLM agents interact with rule-governed environments---manipulating temperatures, mixing chemicals, navigating physical constraints---they face a failure mode qualitatively distinct from suboptimality: \emph{catastrophic death}. A single hallucinated state transition can trigger an irreversible termination penalty, collapsing the episode score to $-100$. Deterministic external computation---environment simulators or code interpreters---eliminates such hallucinations by providing exact state transitions. But what does a router actually learn when trained to select between internal LLM reasoning and deterministic computation? Recent work on tool-use learning \cite{toolformer-2024,art-2023,chameleon-2024,retool-2026} and adaptive computation \cite{cogrouter-2026,ares-2026,mixture-of-recursions-2025} has developed methods for deciding when and how to invoke external modules, yet these approaches frame routing as a general capability or efficiency question---selecting the right tool, calibrating reasoning depth---without examining whether \emph{failure avoidance} constitutes a distinct and potentially dominant routing signal.
6	
7	We address this question by analyzing routing between internal reasoning, following the ReAct interleaved reasoning-and-acting paradigm \cite{react-2023}, and deterministic computation on ScienceWorld, an interactive science environment with sparse rewards and catastrophic failure penalties. A natural first approach is per-step oracle comparison: at each decision point, run both modalities and prefer the one yielding higher immediate reward. However, in sparse-reward environments where non-zero reward arrives only at episode termination, this strategy degenerates. On ScienceWorld, per-step oracle labeling produces \textbf{[PLACEHOLDER: 98\%]} ties---neither modality shows a per-step advantage on the vast majority of steps---rendering the resulting labels uninformative for router t
…[truncated 2276 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-14T02:08:13.903966+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/artifacts/_project/paper/related_work_draft.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/artifacts/_project/paper/related_work_draft.md"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-14T02:08:13.904234+00:00_

1	# Related Work — Draft v1
2	
3	\section{Related Work}
4	
5	\paragraph{Tool-Use Learning.}
6	A line of work teaches LLMs when and how to invoke external tools.
7	Toolformer \cite{toolformer-2024} inserts API calls via self-supervised filtering, while ART \cite{art-2023} uses LLM reasoning chains to select tools automatically, and Chameleon \cite{chameleon-2024} composes diverse tool modules under LLM-as-planner orchestration.
8	More recently, ReTool \cite{retool-2026} applies reinforcement learning to learn implicit code-interpreter invocation strategies for mathematical reasoning.
9	Our work differs along three axes: (1) we generate routing labels via \emph{episode-level counterfactual analysis}---running complete trajectories under competing strategies---rather than self-supervised or RL-based signals; (2) we frame routing as \emph{catastrophic failure prevention} rather than general tool selection; and (3) we train an explicit lightweight router decoupled from the backbone LLM, enabling diagnostic analysis of what the routing signal encodes.
10	
11	\paragraph{Adaptive Computation.}
12	Several recent methods adapt reasoning effort per step.
13	CogRouter \cite{cogrouter-2026} achieves 82.3\% on ScienceWorld by routing among cognitive depth levels (instinct to strategic planning) via Cooperative Policy Optimization, while ARES \cite{ares-2026} trains a lightweight router to select per-step reasoning effort (low/medium/high), reducing token cost by 52.7\%.
14	Mixture-of-Recursions \cite{mixture-of-recursions-2025} applies adaptive depth at the architecture level via per-token recursive routing.
15	These methods route \emph{how much} to reason; we route \emph{which modality} to use (internal LLM reasoning vs.\ deterministic computation) and contribute the empirical finding that death avoidance accounts for ${\sim}99\%$ of the learned routing signal.
16	
17	\paragraph{World Model Routing.}
18	ITP \cite{itp-2026} augments agents with LLM-based world model lookahead, ad
…[truncated 993 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-14T02:08:13.904530+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/artifacts/_project/paper/method_draft.md",
  "content": "# Method — Draft v1\n\n\\section{Method}\n\nWe describe our methodology in four parts: counterfactual episode collection (\\S\\ref{sec:collection}), death-aware labeling (\\S\\ref{sec:labeling}), the death avoidance factor (\\S\\ref{sec:daf}), and a rule-based baseline analysis (\\S\\ref{sec:rule}).\n\n\\subsection{Counterfactual Episode Collection}\n\\label{sec:collection}\n\nAs motivated in \\S1, per-step oracle labeling degenerates under sparse rewards. We instead adopt \\emph{episode-level counterfactual analysis}: for each task instance, we run two complete episodes under identical initial conditions (same random seed):\n\n\\begin{itemize}\n    \\item \\textbf{Pure-internal}: all steps use the LLM's internal reasoning following the ReAct paradigm \\cite{react-2023}, where the agent interleaves chain-of-thought reasoning with environment actions.\n    \\item \\textbf{Pure-deterministic}: all steps use deterministic external computation via the environment simulator, providing exact state transitions.\n\\end{itemize}\n\nEach episode produces a tuple $(s^{\\text{int}}, s^{\\text{det}}, d^{\\text{int}}, d^{\\text{det}})$, where $s$ denotes episode score and $d \\in \\{0, 1\\}$ indicates whether the agent died. Episodes are capped at [PLACEHOLDER: 30] steps. We use Qwen2.5-7B-Instruct as the LLM backbone, served via vLLM.\n\nWe evaluate on ScienceWorld \\cite{scienceworld-2022}, which provides [PLACEHOLDER: 30] task types spanning physical and chemical reasoning. For each task type, we first run a prescreening phase (5 episodes) to identify tasks where both strategies can be meaningfully compared, then collect the full dataset of [PLACEHOLDER: 20] episodes per task. The final dataset comprises [PLACEHOLDER: 249] episodes across all [PLACEHOLDER: 30] task types.\n\n\\subsection{Death-Aware Labeling}\n\\label{sec:labeling}\n\nWe assign an episode-level routing label to each counterfactual pair based on the four-tuple $(s^{\\text{int}}, s^{\\text{det}}, d^{\\text{int}}, d^{\\text{det}})$, distinguishing four signal types ordered by priority:\n\n\\begin{enumerate}\n    \\item \\textbf{Death asymmetry}: one strategy results in agent death while the other survives ($d^{\\text{int}} \\neq d^{\\text{det}}$). The surviving strategy is labeled as preferred. This constitutes the strongest routing signal, as it reflects a catastrophic outcome difference rather than a marginal score gap.\n    \\item \\textbf{Tied alive}: both strategies survive and their scores differ by at most a threshold $\\tau$ ($|s^{\\text{int}} - s^{\\text{det}}| \\leq \\tau$, $d^{\\text{int}} = d^{\\text{det}} = 0$). Label: \\texttt{no\\_preference}.\n    \\item \\textbf{Both dead}: both strategies result in death ($d^{\\text{int}} = d^{\\text{det}} = 1$). Label: \\texttt{no\\_preference}, as neither strategy provides a viable routing signal.\n    \\item \\textbf{Score comparison}: both survive but scores differ beyond $\\tau$ ($|s^{\\text{int}} - s^{\\text{det}}| > \\tau$, $d^{\\text{int}} = d^{\\text{det}} = 0$). The higher-scoring strategy is preferred.\n\\end{enumerate}\n\nThe resulting label distribution across [PLACEHOLDER: 249] episodes is: [PLACEHOLDER: 41\\%] \\texttt{det\\_preferred}, [PLACEHOLDER: 0.5\\%] \\texttt{internal\\_preferred}, and [PLACEHOLDER: 59\\%] \\texttt{no\\_preference}. The near-absence of \\texttt{internal\\_preferred} labels and the dominance of \\texttt{det\\_preferred} labels---driven overwhelmingly by death asymmetry---indicate that deterministic computation's primary advantage lies in avoiding catastrophic failures rather than achieving higher task scores.\n\n\\subsection{Death Avoidance Factor}\n\\label{sec:daf}\n\nTo quantify the contribution of death avoidance to routing signal, we define the \\emph{Death Avoidance Factor} (DAF). Let $\\Delta_{\\text{full}}$ be the mean score gap between deterministic and internal strategies across all episodes, and $\\Delta_{\\text{no\\_death}}$ be the same gap computed only over episodes where neither strategy results in death:\n\\begin{equation}\n    \\text{DAF} = 1 - \\frac{\\Delta_{\\text{no\\_death}}}{\\Delta_{\\text{full}}}\n\\end{equation}\nDAF $= 1$ indicates that the routing signal is entirely attributable to death avoidance; DAF $= 0$ indicates it derives entirely from non-death performance differences.\n\nAcross the full dataset, [PLACEHOLDER: $\\Delta_{\\text{full}} = +37.9$] and [PLACEHOLDER: $\\Delta_{\\text{no\\_death}} = +0.2$], yielding [PLACEHOLDER: DAF $= 0.99$]. Death avoidance accounts for virtually all of the observed routing advantage. Per-task analysis further confirms this: [PLACEHOLDER: 25] of [PLACEHOLDER: 30] tasks exhibit DAF $\\geq 0.95$, while a small number of tasks show genuine non-death advantages (e.g., \\texttt{measure-melting-point-unknown} with DAF $= 0.594$). The Pearson correlation between per-task death rate differential and score gap is [PLACEHOLDER: $r = 0.989$] ([PLACEHOLDER: $p < 0.0001$]), demonstrating that knowing how much more frequently the internal strategy dies is nearly sufficient to predict the full performance gap.\n\n\\subsection{Rule-Based Baseline}\n\\label{sec:rule}\n\nA natural question is whether simple heuristics can approximate learned routing. We test keyword-based rules that route to deterministic computation when the current action contains science-related verbs, under the hypothesis that actions involving physical or chemical state changes benefit most from exact computation.\n\nWe evaluate three keyword lists of decreasing breadth:\n\\begin{itemize}\n    \\item \\textbf{v1} (20 generic verbs including \\texttt{connect}, \\texttt{move}): matches [PLACEHOLDER: 85.8\\%] of actions, degenerating to an always-deterministic policy.\n    \\item \\textbf{v2} (17 science-specific: \\texttt{heat}, \\texttt{boil}, \\texttt{melt}, \\texttt{freeze}): matches [PLACEHOLDER: 4.9\\%], degenerating to always-internal.\n    \\item \\textbf{v3} (12 state-change verbs): matches [PLACEHOLDER: 2.8\\%], similarly degenerating.\n\\end{itemize}\n\nThe structural cause is that ScienceWorld actions use generic interaction verbs (\\texttt{pick up}, \\texttt{move}, \\texttt{connect}) rather than science-specific terms, making keyword overlap with the underlying task semantics either near-total or negligible. No keyword granularity provides meaningful routing discrimination, motivating observation-based or learned routing approaches.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/artifacts/_project/paper/method_draft.md",
    "content": "# Method — Draft v1\n\n\\section{Method}\n\nWe describe our methodology in four parts: counterfactual episode collection (\\S\\ref{sec:collection}), death-aware labeling (\\S\\ref{sec:labeling}), the death avoidance factor (\\S\\ref{sec:daf}), and a rule-based baseline analysis (\\S\\ref{sec:rule}).\n\n\\subsection{Counterfactual Episode Collection}\n\\label{sec:collection}\n\nAs motivated in \\S1, per-step oracle labeling degenerates under sparse rewards. We instead adopt \\emph{episode-level counterfactual analysis}: for each task instance, we run two complete episodes under identical initial conditions (same random seed):\n\n\\begin{itemize}\n    \\item \\textbf{Pure-internal}: all steps use the LLM's internal reasoning following the ReAct paradigm \\cite{react-2023}, where the agent interleaves chain-of-thought reasoning with environment actions.\n    \\item \\textbf{Pure-deterministic}: all steps use deterministic external computation via the environment simulator, providing exact state transitions.\n\\end{itemize}\n\nEach episode produces a tuple $(s^{\\text{int}}, s^{\\text{det}}, d^{\\text{int}}, d^{\\text{det}})$, where $s$ denotes episode score and $d \\in \\{0, 1\\}$ indicates whether the agent died. Episodes are capped at [PLACEHOLDER: 30] steps. We use Qwen2.5-7B-Instruct as the LLM backbone, served via vLLM.\n\nWe evaluate on ScienceWorld \\cite{scienceworld-2022}, which provides [PLACEHOLDER: 30] task types spanning physical and chemical reasoning. For each task type, we first run a prescreening phase (5 episodes) to identify tasks where both strategies can be meaningfully compared, then collect the full dataset of [PLACEHOLDER: 20] episodes per task. The final dataset comprises [PLACEHOLDER: 249] episodes across all [PLACEHOLDER: 30] task types.\n\n\\subsection{Death-Aware Labeling}\n\\label{sec:labeling}\n\nWe assign an episode-level routing label to each counterfactual pair based on the four-tuple $(s^{\\text{int}}, s^{\\text{det}}, d^{\\text{int}}, d^{\\text{det}})$, distinguishing four signal types ordered by priority:\n\n\\begin{enumerate}\n    \\item \\textbf{Death asymmetry}: one strategy results in agent death while the other survives ($d^{\\text{int}} \\neq d^{\\text{det}}$). The surviving strategy is labeled as preferred. This constitutes the strongest routing signal, as it reflects a catastrophic outcome difference rather than a marginal score gap.\n    \\item \\textbf{Tied alive}: both strategies survive and their scores differ by at most a threshold $\\tau$ ($|s^{\\text{int}} - s^{\\text{det}}| \\leq \\tau$, $d^{\\text{int}} = d^{\\text{det}} = 0$). Label: \\texttt{no\\_preference}.\n    \\item \\textbf{Both dead}: both strategies result in death ($d^{\\text{int}} = d^{\\text{det}} = 1$). Label: \\texttt{no\\_preference}, as neither strategy provides a viable routing signal.\n    \\item \\textbf{Score comparison}: both survive but scores differ beyond $\\tau$ ($|s^{\\text{int}} - s^{\\text{det}}| > \\tau$, $d^{\\text{int}} = d^{\\text{det}} = 0$). The higher-scoring strategy is preferred.\n\\end{enumerate}\n\nThe resulting label distribution across [PLACEHOLDER: 249] episodes is: [PLACEHOLDER: 41\\%] \\texttt{det\\_preferred}, [PLACEHOLDER: 0.5\\%] \\texttt{internal\\_preferred}, and [PLACEHOLDER: 59\\%] \\texttt{no\\_preference}. The near-absence of \\texttt{internal\\_preferred} labels and the dominance of \\texttt{det\\_preferred} labels---driven overwhelmingly by death asymmetry---indicate that deterministic computation's primary advantage lies in avoiding catastrophic failures rather than achieving higher task scores.\n\n\\subsection{Death Avoidance Factor}\n\\label{sec:daf}\n\nTo quantify the contribution of death avoidance to routing signal, we define the \\emph{Death Avoidance Factor} (DAF). Let $\\Delta_{\\text{full}}$ be the mean score gap between deterministic and internal strategies across all episodes, and $\\Delta_{\\text{no\\_death}}$ be the same gap computed only over episodes where neither strategy results in death:\n\\begin{equation}\n    \\text{DAF} = 1 - \\frac{\\Delta_{\\text{no\\_death}}}{\\Delta_{\\text{full}}}\n\\end{equation}\nDAF $= 1$ indicates that the routing signal is entirely attributable to death avoidance; DAF $= 0$ indicates it derives entirely from non-death performance differences.\n\nAcross the full dataset, [PLACEHOLDER: $\\Delta_{\\text{full}} = +37.9$] and [PLACEHOLDER: $\\Delta_{\\text{no\\_death}} = +0.2$], yielding [PLACEHOLDER: DAF $= 0.99$]. Death avoidance accounts for virtually all of the observed routing advantage. Per-task analysis further confirms this: [PLACEHOLDER: 25] of [PLACEHOLDER: 30] tasks exhibit DAF $\\geq 0.95$, while a small number of tasks show genuine non-death advantages (e.g., \\texttt{measure-melting-point-unknown} with DAF $= 0.594$). The Pearson correlation between per-task death rate differential and score gap is [PLACEHOLDER: $r = 0.989$] ([PLACEHOLDER: $p < 0.0001$]), demonstrating that knowing how much more frequently the internal strategy dies is nearly sufficient to predict the full performance gap.\n\n\\subsection{Rule-Based Baseline}\n\\label{sec:rule}\n\nA natural question is whether simple heuristics can approximate learned routing. We test keyword-based rules that route to deterministic computation when the current action contains science-related verbs, under the hypothesis that actions involving physical or chemical state changes benefit most from exact computation.\n\nWe evaluate three keyword lists of decreasing breadth:\n\\begin{itemize}\n    \\item \\textbf{v1} (20 generic verbs including \\texttt{connect}, \\texttt{move}): matches [PLACEHOLDER: 85.8\\%] of actions, degenerating to an always-deterministic policy.\n    \\item \\textbf{v2} (17 science-specific: \\texttt{heat}, \\texttt{boil}, \\texttt{melt}, \\texttt{freeze}): matches [PLACEHOLDER: 4.9\\%], degenerating to always-internal.\n    \\item \\textbf{v3} (12 state-change verbs): matches [PLACEHOLDER: 2.8\\%], similarly degenerating.\n\\end{itemize}\n\nThe structural cause is that ScienceWorld actions use generic interaction verbs (\\texttt{pick up}, \\texttt{move}, \\texttt{connect}) rather than science-specific terms, making keyword overlap with the underlying task semantics either near-total or negligible. No keyword granularity provides meaningful routing discrimination, motivating observation-based or learned routing approaches.\n"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-14T02:08:13.904850+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/artifacts/_project/paper/method_draft.md

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-14T02:08:13.905068+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__register_artifact",
  "max_results": "1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__register_artifact",
    "max_results": "1"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-14T02:08:13.905278+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-14T02:08:13.905458+00:00_

called mcp__agent-ml-research__register_artifact

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact</summary>

```json
{
  "name": "method_draft",
  "type": "paper",
  "description": "Method section draft v1 for EMNLP 2026 short paper — 4 subsections: Counterfactual Episode Collection, Death-Aware Labeling, Death Avoidance Factor (DAF), Rule-Based Baseline. ~850 words, LaTeX format with PLACEHOLDER annotations.",
  "project": "simgate-modular-routing",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/artifacts/_project/paper/method_draft.md",
  "tags": "['paper', 'method', 'draft-v1', 'emnlp2026']"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "mcp__agent-ml-research__register_artifact",
  "tool_args": {
    "name": "method_draft",
    "type": "paper",
    "description": "Method section draft v1 for EMNLP 2026 short paper — 4 subsections: Counterfactual Episode Collection, Death-Aware Labeling, Death Avoidance Factor (DAF), Rule-Based Baseline. ~850 words, LaTeX format with PLACEHOLDER annotations.",
    "project": "simgate-modular-routing",
    "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/artifacts/_project/paper/method_draft.md",
    "tags": "['paper', 'method', 'draft-v1', 'emnlp2026']"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-14T02:08:13.905691+00:00_

{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260514_e328fe\", \"name\": \"method_draft\", \"type\": \"paper\", \"description\": \"Method section draft v1 for EMNLP 2026 short paper — 4 subsections: Counterfactual Episode Collection, Death-Aware Labeling, Death Avoidance Factor (DAF), Rule-Based Baseline. ~850 words, LaTeX format with PLACEHOLDER annotations.\", \"path\": \"projects/simgate-modular-routing/artifacts/_project/paper/method_draft_e328fe.md\", \"url\": null, \"project\": \"simgate-modular-routing\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-14T02:08:01.449321+00:00\", \"tags\": [\"paper\", \"method\", \"draft-v1\", \"emnlp2026\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_method_20260514T020639",
  "tool": "mcp__agent-ml-research__register_artifact",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 15 · 2026-05-14T02:08:13.905931+00:00_

Method draft v1 已写入 `artifacts/_project/paper/method_draft.md` 并注册 (`art_20260514_e328fe`)。

**结构**：4 个 subsection，约 850 words，符合 ~1 页篇幅：
- §3.1 Counterfactual Episode Collection — pure-internal vs pure-deterministic 对比设计，seed-matched episodes
- §3.2 Death-Aware Labeling — 四元组 → 四类 signal 的优先级规则，label 分布
- §3.3 Death Avoidance Factor — DAF 公式（编号 equation），全局 DAF=0.99，per-task 分析，Pearson r=0.989
- §3.4 Rule-Based Baseline — 三版 keyword list 均退化，结构性原因分析

**一致性**：术语、符号（$\Delta_{\text{full}}$, $\Delta_{\text{no\_death}}$, DAF）、引用 keys 均与 Introduction/Related Work 对齐。所有可能更新的数字标注了 `[PLACEHOLDER]`。Introduction 已论述的 oracle degeneracy 仅用 "as motivated in §1" 回指，未重复。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_method_20260514T020639"
}
```

</details>

---
