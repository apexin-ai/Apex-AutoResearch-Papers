# paper writing abstract

**The Weakest Link Across Panel Sizes: Predictor Relevance Patterns in Multi-Judge LLM Evaluation under Adversarial Manipulation** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 19
- **Recorded user turns:** 0
- **Tool calls:** 9
- **Original source:** `logs/chats/worker_paper_writing_abstract_20260522T195705.jsonl`
- **Structured JSON:** [`acddacbaa9d376e1a91c.json`](../../sessions/ac/acddacbaa9d376e1a91c.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

19 recorded events

### Tool call

_source line 1 · 2026-05-22T19:59:14.629924+00:00_

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
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-22T19:59:14.630470+00:00_

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
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-22T19:59:14.630682+00:00_

called Agent

<details open><summary>🔧 Tool call — Agent</summary>

```json
{
  "description": "Find paper title and context",
  "subagent_type": "Explore",
  "prompt": "In the project at /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/, find:\n1. The actual title in main.tex (look for \\title{...})\n2. Any existing abstract.tex content\n3. The structure of the paper (section files, what's included)\nReport the exact title, any existing abstract text, and list of section files."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Agent",
  "tool_args": {
    "description": "Find paper title and context",
    "subagent_type": "Explore",
    "prompt": "In the project at /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/, find:\n1. The actual title in main.tex (look for \\title{...})\n2. Any existing abstract.tex content\n3. The structure of the paper (section files, what's included)\nReport the exact title, any existing abstract text, and list of section files."
  }
}
```

</details>

---

### Tool call

_source line 4 · 2026-05-22T19:59:14.630856+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "find /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper -type f -name \"*.tex\" | head -20"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Bash",
  "tool_args": {
    "command": "find /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper -type f -name \"*.tex\" | head -20"
  }
}
```

</details>

---

### Tool result

_source line 5 · 2026-05-22T19:59:14.630987+00:00_

/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/results.tex
/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/threat_model.tex
/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/methodology.tex
/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/conclusion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/main.tex
/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/related_work.tex
/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/analysis.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 6 · 2026-05-22T19:59:14.631116+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/main.tex"
  }
}
```

</details>

---

### Tool result

_source line 7 · 2026-05-22T19:59:14.631251+00:00_

1	\documentclass[11pt]{article}
2	\usepackage[review]{acl}
3	\usepackage{times}
4	\usepackage{latexsym}
5	\usepackage[T1]{fontenc}
6	\usepackage[utf8]{inputenc}
7	\usepackage{microtype}
8	\usepackage{graphicx}
9	\usepackage{amsmath,amssymb,amsthm}
10	\usepackage{booktabs}
11	\usepackage{multirow}
12	\usepackage{xcolor}
13	\usepackage{subcaption}
14	
15	\newtheorem{theorem}{Theorem}
16	\newtheorem{definition}{Definition}
17	\newtheorem{proposition}{Proposition}
18	
19	\title{The Weakest Link: Why Judge Diversity Fails Under\\Adaptive Adversaries in Multi-LLM Evaluation}
20	
21	\author{Anonymous}
22	
23	\begin{document}
24	\maketitle
25	
26	\begin{abstract}
27	% [PLACEHOLDER — waiting for plan_001 results]
28	\end{abstract}
29	
30	% Section files managed by write_paper_section
31	\input{introduction}    % [PLACEHOLDER — waiting for plan_001 results]
32	\input{related_work}
33	\input{threat_model}
34	\input{methodology}
35	\input{results}          % [PLACEHOLDER — waiting for plan_001 results]
36	\input{analysis}         % [PLACEHOLDER — waiting for plan_001 results]
37	\input{conclusion}       % [PLACEHOLDER — waiting for plan_001 results]
38	
39	\section*{Limitations}
40	
41	Our study has three principal limitations. First, the 15-model pool, while spanning 6 families and 3 capability tiers, does not cover all commercially deployed LLMs; the generality of the diversity-vulnerability association to larger or differently composed pools remains to be tested. Second, the six local models are served with AWQ INT4 quantization, which substantially reduces judge accuracy on the pairwise judgment task (Table~\ref{tab:models}). Although the sensitivity analysis (\S\ref{sec:stat_framework}) excludes judges with accuracy below 0.5, the quantization-induced capability reduction may affect vulnerability patterns in ways that do not transfer to full-precision deployments. Third, the analysis is observational: the $K_{\mathrm{eff}}$--$\eta_{\max}$ correlation ($r = 0.70$) prevents 
…[truncated 299 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 8 · 2026-05-22T19:59:14.631406+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls -la /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/ | grep -E \"\\.tex$\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Bash",
  "tool_args": {
    "command": "ls -la /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/ | grep -E \"\\.tex$\""
  }
}
```

</details>

---

### Tool result

_source line 9 · 2026-05-22T19:59:14.631525+00:00_

-rw-r--r-- 1 ubuntu ubuntu  5052 May 22 19:29 analysis.tex
-rw-r--r-- 1 ubuntu ubuntu  1886 May 22 19:39 conclusion.tex
-rw-r--r-- 1 ubuntu ubuntu  5087 May 22 19:24 introduction.tex
-rw-r--r-- 1 ubuntu ubuntu  2177 May 22 19:56 main.tex
-rw-r--r-- 1 ubuntu ubuntu  8813 May 22 19:19 methodology.tex
-rw-r--r-- 1 ubuntu ubuntu  9121 May 22 19:25 related_work.tex
-rw-r--r-- 1 ubuntu ubuntu  7443 May 22 19:36 results.tex
-rw-r--r-- 1 ubuntu ubuntu  5077 May 22 19:24 threat_model.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-22T19:59:14.631737+00:00_

Based on my search, here are my findings:

## Paper Information

**1. Actual Title (from main.tex):**
```
The Weakest Link: Why Judge Diversity Fails Under Adaptive Adversaries in Multi-LLM Evaluation
```

**2. Abstract Content:**
The abstract is currently a placeholder - it's empty with only a comment:
```latex
\begin{abstract}
% [PLACEHOLDER — waiting for plan_001 results]
\end{abstract}
```

**3. Paper Structure:**
The paper includes the following section files (all located in `/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/`):

| Section File | Status |
|---|---|
| introduction.tex | Placeholder (waiting for plan_001 results) |
| related_work.tex | Complete |
| threat_model.tex | Complete |
| methodology.tex | Complete |
| results.tex | Placeholder (waiting for plan_001 results) |
| analysis.tex | Placeholder (waiting for plan_001 results) |
| conclusion.tex | Placeholder (waiting for plan_001 results) |
| Limitations section | Inline in main.tex (complete) |

The paper also includes:
- A bibliography section that references `references.bib`
- Uses the ACL paper format (`\usepackage[review]{acl}`)
- Author listed as "Anonymous"
- Uses ACL citation style (`acl_natbib`)

Several sections are marked as waiting for `plan_001` results, indicating they depend on experimental outcomes that haven't been finalized yet.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Agent",
  "elapsed_ms": 1
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-22T19:59:14.631913+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/methodology.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/methodology.tex"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-22T19:59:14.632090+00:00_

1	\section{Experimental Methodology}
2	\label{sec:experiments}
3	
4	\subsection{Models and Panel Construction}
5	
6	We select 15 LLM judges spanning 6 provider families and 3 capability tiers, listed in Table~\ref{tab:models}. Nine models are accessed via the OpenRouter API; six open-weight models are served locally using vLLM~0.21.0 with AWQ INT4 quantization on an NVIDIA RTX~6000 (96\,GB). API models are assigned to \emph{frontier}, \emph{mid-tier}, or \emph{lightweight} tiers following the provider capability classification; all six local models fall into the lightweight tier, as INT4 quantization substantially reduces judge accuracy on the pairwise judgment task (Table~\ref{tab:models}). All panels consist of $K{=}3$ judges with majority-vote threshold $t{=}2$. Exhaustive enumeration yields $\binom{15}{3} = 455$ unique panels, covering every combination of families and tiers. Each panel evaluates all benchmark items under all attack types, producing a complete panel $\times$ item $\times$ attack tensor.
7	
8	\begin{table}[t]
9	\centering
10	\small
11	\begin{tabular}{lllccc}
12	\toprule
13	\textbf{Model} & \textbf{Family} & \textbf{Tier} & \textbf{Deploy} & \textbf{MMLU} & \textbf{ARC} \\
14	\midrule
15	gpt-5.5              & OpenAI    & frontier    & API   & .957 & .983 \\
16	gemini-3.1-pro-preview & Google  & frontier    & API   & .955 & .987 \\
17	claude-opus-4-6       & Anthropic & frontier   & API   & .890 & .987 \\
18	\addlinespace
19	gemini-3.5-flash      & Google    & mid-tier   & API   & .968 & 1.00$^\dagger$ \\
20	gpt-4.1               & OpenAI    & mid-tier   & API   & .837 & .967 \\
21	claude-sonnet-4-6     & Anthropic & mid-tier   & API   & .810 & .953 \\
22	\addlinespace
23	gpt-4.1-mini          & OpenAI    & lightweight & API  & .800 & .963 \\
24	gpt-4.1-nano          & OpenAI    & lightweight & API  & .633 & .853 \\
25	claude-3-haiku        & Anthropic & lightweight & API  & .767 & .450 \\
26	mistral-large (123B)  & Mistral   & lightweight & local
…[truncated 7029 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-22T19:59:14.632249+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/threat_model.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/threat_model.tex"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-22T19:59:14.632412+00:00_

1	\section{Threat Model and Problem Formulation}
2	
3	A \emph{panel} $\mathcal{P} = \{J_1, \ldots, J_K\}$ consists of $K$ judges (with $K$ odd) that evaluate a candidate text via majority vote: the text is accepted if at least $t = \lceil K/2 \rceil$ judges approve it. Under an attack $a$, each judge $J_j$ is compromised with marginal failure probability $\eta_j(a) = \Pr(X_j^a = 1)$, where $X_j^a \in \{0,1\}$ denotes the failure indicator. We write $\eta_{\max} = \max_j \eta_j$ for the vulnerability of the weakest judge. The \emph{panel attack success rate} is $\mathrm{ASR}(\mathcal{P}, a) = \Pr\!\bigl(\sum_{j=1}^K X_j^a \geq t\bigr)$.
4	
5	To quantify diversity, we define the \emph{effective independence} $K_{\mathrm{eff}}$ directly from pairwise mutual information among judges:
6	\begin{equation}
7	\label{eq:keff}
8	K_{\mathrm{eff}} = \frac{1}{K}\sum_{i=1}^{K} \Bigl[1 + \sum_{j \neq i} \exp\!\bigl(-2 \cdot \mathrm{MI}(i,j)\bigr)\Bigr].
9	\end{equation}
10	This formulation computes effective independence from pairwise MI estimates without matrix decomposition, and is more stable for small panels ($K{=}3$). It ranges from $K_{\mathrm{eff}} \approx K$ when judges are nearly independent ($\mathrm{MI} \to 0$) to $K_{\mathrm{eff}} \approx 1$ when judges are highly correlated ($\mathrm{MI} \to \infty$). Under the strong data-processing inequality (SDPI), the joint vulnerability satisfies $\eta_{\mathrm{joint}} \leq \min(1,\; K_{\mathrm{eff}} \cdot \eta_{\max})$, suggesting that diversity should help, but this bound assumes non-adaptive faults.
11	
12	\begin{definition}[Adaptive Adversary]
13	\label{def:adversary}
14	A \emph{full-knowledge (oracle) adaptive adversary} has complete knowledge of the panel composition $\mathcal{P}$, the per-judge vulnerability profiles $\{\eta_j(\cdot)\}_{j=1}^K$, and the inter-judge correlation structure. It selects the attack $a^* = \arg\max_{a \in \mathcal{A}} \mathrm{ASR}(\mathcal{P}, a)$ to maximize the panel ASR, yielding $\mathrm{ASR}
…[truncated 3152 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-22T19:59:14.632556+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/main.tex"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-22T19:59:14.632721+00:00_

1	\documentclass[11pt]{article}
2	\usepackage[review]{acl}
3	\usepackage{times}
4	\usepackage{latexsym}
5	\usepackage[T1]{fontenc}
6	\usepackage[utf8]{inputenc}
7	\usepackage{microtype}
8	\usepackage{graphicx}
9	\usepackage{amsmath,amssymb,amsthm}
10	\usepackage{booktabs}
11	\usepackage{multirow}
12	\usepackage{xcolor}
13	\usepackage{subcaption}
14	
15	\newtheorem{theorem}{Theorem}
16	\newtheorem{definition}{Definition}
17	\newtheorem{proposition}{Proposition}
18	
19	\title{The Weakest Link: Why Judge Diversity Fails Under\\Adaptive Adversaries in Multi-LLM Evaluation}
20	
21	\author{Anonymous}
22	
23	\begin{document}
24	\maketitle
25	
26	\begin{abstract}
27	% [PLACEHOLDER — waiting for plan_001 results]
28	\end{abstract}
29	
30	% Section files managed by write_paper_section
31	\input{introduction}    % [PLACEHOLDER — waiting for plan_001 results]
32	\input{related_work}
33	\input{threat_model}
34	\input{methodology}
35	\input{results}          % [PLACEHOLDER — waiting for plan_001 results]
36	\input{analysis}         % [PLACEHOLDER — waiting for plan_001 results]
37	\input{conclusion}       % [PLACEHOLDER — waiting for plan_001 results]
38	
39	\section*{Limitations}
40	
41	Our study has three principal limitations. First, the 15-model pool, while spanning 6 families and 3 capability tiers, does not cover all commercially deployed LLMs; the generality of the diversity-vulnerability association to larger or differently composed pools remains to be tested. Second, the six local models are served with AWQ INT4 quantization, which substantially reduces judge accuracy on the pairwise judgment task (Table~\ref{tab:models}). Although the sensitivity analysis (\S\ref{sec:stat_framework}) excludes judges with accuracy below 0.5, the quantization-induced capability reduction may affect vulnerability patterns in ways that do not transfer to full-precision deployments. Third, the analysis is observational: the $K_{\mathrm{eff}}$--$\eta_{\max}$ correlation ($r = 0.70$) prevents 
…[truncated 299 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-22T19:59:14.632952+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/abstract.tex",
  "content": "Multi-judge panels of Large Language Models (LLMs) are widely assumed to resist adversarial manipulation through judge diversity, by analogy to Byzantine fault tolerance. This assumption remains empirically untested, and no prior work disentangles the contributions of panel diversity and individual judge robustness to panel vulnerability.\n\nWe construct 455 three-judge panels from 15 LLMs across 6 model families and evaluate them under six attack types on two benchmarks (MMLU and ARC). A log-log regression framework with dominance analysis decomposes panel attack success rate into two channels: weakest-link vulnerability ($\\eta_{\\max}$) and effective independence ($K_{\\mathrm{eff}}$), a mutual-information-based diversity measure.\n\nThe weakest-link channel dominates: $\\eta_{\\max}$ is significant in 11 of 12 conditions after FDR correction and is the sole or co-dominant predictor in all but one. The diversity channel reveals what we term the \\emph{diversity trap}: higher $K_{\\mathrm{eff}}$ is associated with \\emph{higher} panel vulnerability in 7 of 12 conditions, consistent with diverse panels presenting a wider attack surface rather than mutual protection. Bayesian calibration, which weights judges by empirical reliability, reverses this association. These observational findings suggest that strengthening the weakest judge matters more than increasing panel diversity, and that aggregation design can mitigate the diversity trap without reducing panel variety.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/abstract.tex",
    "content": "Multi-judge panels of Large Language Models (LLMs) are widely assumed to resist adversarial manipulation through judge diversity, by analogy to Byzantine fault tolerance. This assumption remains empirically untested, and no prior work disentangles the contributions of panel diversity and individual judge robustness to panel vulnerability.\n\nWe construct 455 three-judge panels from 15 LLMs across 6 model families and evaluate them under six attack types on two benchmarks (MMLU and ARC). A log-log regression framework with dominance analysis decomposes panel attack success rate into two channels: weakest-link vulnerability ($\\eta_{\\max}$) and effective independence ($K_{\\mathrm{eff}}$), a mutual-information-based diversity measure.\n\nThe weakest-link channel dominates: $\\eta_{\\max}$ is significant in 11 of 12 conditions after FDR correction and is the sole or co-dominant predictor in all but one. The diversity channel reveals what we term the \\emph{diversity trap}: higher $K_{\\mathrm{eff}}$ is associated with \\emph{higher} panel vulnerability in 7 of 12 conditions, consistent with diverse panels presenting a wider attack surface rather than mutual protection. Bayesian calibration, which weights judges by empirical reliability, reverses this association. These observational findings suggest that strengthening the weakest judge matters more than increasing panel diversity, and that aggregation design can mitigate the diversity trap without reducing panel variety.\n"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-22T19:59:14.633128+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/abstract.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_20260522T195705",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 19 · 2026-05-22T19:59:14.633360+00:00_

Abstract written (~200 words). Three paragraphs mapping to the four required elements:

1. **Problem + why important** (P1): BFT-diversity assumption untested, diversity vs robustness not disentangled
2. **What we do** (P2): 455 panels, 15 models, 6 families, 6 attacks, 2 benchmarks; log-log regression + dominance analysis separating η_max and K_eff channels
3. **Results** (P3): η_max significant 11/12, K_eff positively associated with vulnerability 7/12 ("diversity trap"), Bayesian calibration reverses the association; framed as observational

Key numbers used: 11/12 (η_max) and 7/12 (K_eff positive), with setup numbers kept to one compact sentence. All red lines checked: no em-dash, no -ing endings, no causal language, LLM expanded, "observational" explicit.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_abstract_20260522T195705"
}
```

</details>

---
