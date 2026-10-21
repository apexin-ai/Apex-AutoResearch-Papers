# paper writing abstract

**Beyond Self-Consistency: Self-Extracted Constraints Reduce to Majority Voting under Zero-Shot Extraction** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 21
- **Recorded user turns:** 0
- **Tool calls:** 10
- **Original source:** `logs/chats/worker_paper_writing_abstract_20260517T191146.jsonl`
- **Structured JSON:** [`013ccdc06bbfed9baa83.json`](../../sessions/01/013ccdc06bbfed9baa83.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

21 recorded events

### Tool call

_source line 1 · 2026-05-17T19:13:54.659072+00:00_

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
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-17T19:13:54.659700+00:00_

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
…[truncated 4866 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-17T19:13:54.659947+00:00_

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
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-17T19:13:54.660162+00:00_

1	\section{Introduction}\label{sec:introduction}
2	
3	Neuro-symbolic methods that augment large language model (LLM) reasoning with formal solvers have demonstrated clear gains on logical reasoning benchmarks. \citet{pan2023logiclm} translate natural language premises into symbolic formulations and delegate solving to an external prover, an approach shown to correct errors in LLM chain-of-thought reasoning. LINC pairs language models with first-order logic provers in a modular architecture that separates natural language understanding from formal inference \citep{olausson2023linc}. More recent systems push this integration further: \citet{xu2026dylos} adaptively route problems to specialized solver paradigms based on problem structure, \citet{li2025aristotle} apply logic-complete decomposition with structured search over proof trees, \citet{wang2025fover} train a dedicated first-order logic (FOL) verifier on supervised annotations, and \citet{luo2025logicagent} employ multi-perspective semiotic grounding to construct constraints from diverse viewpoints. These systems report positive results on overlapping formal reasoning benchmarks. A critical commonality unites them: each introduces capabilities beyond the reasoning model itself, whether trained verifiers, multi-paradigm solver selection, logic-complete decomposition modules, or external knowledge bases. The external machinery is effective, but it imposes practical costs in supervised training data for verifier construction, integration complexity for solver routing, and domain-specific engineering that limits portability across reasoning tasks.
4	
5	These results raise a direct question: does the reasoning model itself possess sufficient capability to extract useful formal constraints from its own reasoning traces? If the same LLM that generates chain-of-thought reasoning can also formalize the logical structure embedded in those traces, the external components become unnecessary, and neuro-symbolic reasoning red
…[truncated 7310 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-17T19:13:54.660320+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/experiments.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-17T19:13:54.660519+00:00_

1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\subsection{Experimental Setup}
5	\label{sec:exp-setup}
6	
7	We evaluate SICA against Self-Consistency (SC) across five models and three reasoning domains, with two additional benchmarks as operating-regime probes.
8	
9	\paragraph{Models.} We test Qwen2.5-14B-Instruct~\cite{yang2024qwen25}, Mistral-7B-Instruct-v0.3~\cite{jiang2023mistral}, LLaMA-3.1-8B-Instruct~\cite{dubey2024llama3}, DeepSeek-R1-Distill-Qwen-7B~\cite{guo2025deepseekr1}, and QwQ-32B~\cite{qwen2024qwq}. This selection spans 7B to 32B parameters and includes one reasoning-specialized model (QwQ-32B) and one distilled reasoning model (DeepSeek-R1-Distill-Qwen-7B) that, as our results show, behaves as an instruction-scale model rather than a reasoning model.
10	
11	\paragraph{Datasets.} FOLIO~\cite{han2022folio} provides formal logic problems with gold first-order logic (FOL) annotations ($n=204$), which enable the oracle control experiment (\S\ref{sec:oracle}). ProofWriter~\cite{tafjord2021proofwriter} tests multi-step deductive reasoning ($n=600$). StrategyQA~\cite{geva2021strategyqa} evaluates commonsense reasoning ($n=200$ for LLaMA-3.1-8B; $n=60$ for other models). ARC-Challenge~\cite{clark2018arc} covers science questions ($n=60$). We additionally include GSM8K~\cite{cobbe2021gsm8k} ($n=30$) and AIME 2024 ($n=22$) as operating-regime probes: both exhibit near-ceiling SC accuracy or near-zero $C_0$, confirming that SICA degenerates to SC when answer diversity is absent.
12	
13	\paragraph{Parameters.} Unless otherwise noted, we sample $K=12$ reasoning traces per question at temperature $T=0.7$. Z3~\cite{demoura2008z3} solves each MAX-SAT instance with a 10-second timeout. Temperature ablation experiments vary $T \in \{0.3, 0.5, 0.7, 1.0\}$.
14	
15	\paragraph{Metrics.} We report accuracy (\%), the multi-candidate rate $C_0$ (\S\ref{sec:c0}), and the accuracy gap $\Delta = \text{SICA} - \text{SC}$ in percentage points (pp). Statistical significanc
…[truncated 10049 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-17T19:13:54.660768+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "**/abstract.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Glob",
  "tool_args": {
    "pattern": "**/abstract.tex",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-17T19:13:54.660926+00:00_

docs/paper/abstract.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-17T19:13:54.661052+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-17T19:13:54.661177+00:00_

1	\begin{abstract}
2	Self-Consistency (SC), majority voting over sampled chain-of-thought traces, is a simple and effective method for improving Large Language Model (LLM) reasoning. A natural extension is to extract formal constraints from these traces and aggregate them with a symbolic solver, potentially recovering signal that vote counting discards. We investigate this idea through Symbolic Invariant Consensus Aggregation (SICA), a pipeline that uses the same LLM to extract First-Order Logic (FOL) constraints from its own reasoning traces and combines them via weighted partial MAX-SAT optimization. Our evaluation spans five models (7B to 32B parameters), three reasoning domains, and over 1,300 instances. The result is negative: SICA yields no statistically significant improvement over SC in any condition, with accuracy gaps between $-3.3$ and $+3.3$ percentage points. We identify the cause as a \emph{capability trap}: because the same model generates both answers and constraints, the extracted constraints are semantically coupled to their source answers, and MAX-SAT optimization degenerates to vote counting. MAX-SAT and a count-only baseline agree on 803 of 804 predictions. An oracle control that substitutes gold FOL annotations achieves $+8.82$ percentage points over SC ($p < 0.001$), confirming that the aggregation mechanism is effective when supplied with discriminative constraints. We further propose the multi-candidate rate $C_0$ as a zero-cost diagnostic: when $C_0$ falls below 5\%, constraint-based methods cannot outperform majority voting regardless of constraint quality.
3	\end{abstract}
4	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-17T19:13:54.661370+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex",
  "content": "\\begin{abstract}\nNeuro-symbolic methods propose extracting first-order logic (FOL) constraints from Large Language Model (LLM) reasoning traces to improve answer aggregation beyond majority voting. Whether the reasoning model itself can produce useful constraints through self-extraction has not been systematically evaluated. If self-extraction works, it eliminates the need for trained verifiers, external provers, or domain-specific infrastructure. We evaluate Symbolic Invariant Consensus Aggregation (SICA), which formulates a weighted partial Maximum Satisfiability (MAX-SAT) problem over self-extracted FOL constraints, across five model families (7B to 32B parameters) and three reasoning domains with more than 1,300 total instances. We include an oracle control that replaces self-extraction with gold FOL annotations verified by Z3 to isolate extraction quality from aggregation effectiveness. Self-extracted SICA provides no statistically significant improvement over Self-Consistency (SC) in any tested condition. The oracle variant achieves $+8.82$ percentage points over SC ($p < 0.001$), which proves the aggregation mechanism is sound when supplied with high-quality constraints. We identify this failure as a \\emph{capability trap}: because the same model that produced potentially flawed reasoning also extracts the constraints, those constraints are semantically coupled to their source answers and carry no independent discriminative signal. Only 11.5\\% of self-extracted constraints evaluate differently across candidate answers. This result establishes that same-model constraint extraction cannot improve LLM answer aggregation without independent sources of formal knowledge.\n\\end{abstract}\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex",
    "content": "\\begin{abstract}\nNeuro-symbolic methods propose extracting first-order logic (FOL) constraints from Large Language Model (LLM) reasoning traces to improve answer aggregation beyond majority voting. Whether the reasoning model itself can produce useful constraints through self-extraction has not been systematically evaluated. If self-extraction works, it eliminates the need for trained verifiers, external provers, or domain-specific infrastructure. We evaluate Symbolic Invariant Consensus Aggregation (SICA), which formulates a weighted partial Maximum Satisfiability (MAX-SAT) problem over self-extracted FOL constraints, across five model families (7B to 32B parameters) and three reasoning domains with more than 1,300 total instances. We include an oracle control that replaces self-extraction with gold FOL annotations verified by Z3 to isolate extraction quality from aggregation effectiveness. Self-extracted SICA provides no statistically significant improvement over Self-Consistency (SC) in any tested condition. The oracle variant achieves $+8.82$ percentage points over SC ($p < 0.001$), which proves the aggregation mechanism is sound when supplied with high-quality constraints. We identify this failure as a \\emph{capability trap}: because the same model that produced potentially flawed reasoning also extracts the constraints, those constraints are semantically coupled to their source answers and carry no independent discriminative signal. Only 11.5\\% of self-extracted constraints evaluate differently across candidate answers. This result establishes that same-model constraint extraction cannot improve LLM answer aggregation without independent sources of formal knowledge.\n\\end{abstract}\n"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-17T19:13:54.661533+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-17T19:13:54.661674+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "—|–",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Grep",
  "tool_args": {
    "pattern": "—|–",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-17T19:13:54.662088+00:00_

No matches found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-17T19:13:54.662220+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "ing[,.]",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Grep",
  "tool_args": {
    "pattern": "ing[,.]",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-17T19:13:54.662338+00:00_

2:[Omitted long matching line]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-17T19:13:54.662451+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "ing[,.]",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex",
  "output_mode": "content",
  "-n": "True"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Grep",
  "tool_args": {
    "pattern": "ing[,.]",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex",
    "output_mode": "content",
    "-n": "True"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-17T19:13:54.662563+00:00_

2:[Omitted long matching line]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-17T19:13:54.662687+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "grep -oP '\\w+ing[,.]' /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex",
  "description": "Find -ing words followed by comma or period"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Bash",
  "tool_args": {
    "command": "grep -oP '\\w+ing[,.]' /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/abstract.tex",
    "description": "Find -ing words followed by comma or period"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-17T19:13:54.662801+00:00_

voting.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260517T191146",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 21 · 2026-05-17T19:13:54.662961+00:00_

"voting." is part of "majority voting." which is a noun phrase (the object of the preposition), not a participial phrase ending. No issues.

Abstract written (~216 words). Key design choices:
- Opens with the research question (can self-extraction work?) rather than leading with the negative result
- Oracle-positive framing: proves aggregation is sound, localizes failure to extraction quality
- Three key numbers only: +8.82pp, p<0.001, 11.5% discriminative rate
- All abbreviations defined inline (FOL, LLM, SICA, MAX-SAT, SC)
- No em-dashes, no -ing phrase endings, no blacklisted words

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_abstract_20260517T191146"
}
```

</details>

---
