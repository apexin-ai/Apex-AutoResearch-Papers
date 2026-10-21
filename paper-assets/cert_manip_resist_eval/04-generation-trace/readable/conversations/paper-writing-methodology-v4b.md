# paper writing methodology v4b

**The Weakest Link Across Panel Sizes: Predictor Relevance Patterns in Multi-Judge LLM Evaluation under Adversarial Manipulation** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 23
- **Recorded user turns:** 0
- **Tool calls:** 11
- **Original source:** `logs/chats/worker_paper_writing_methodology_v4b_20260522T182359.jsonl`
- **Structured JSON:** [`661577a37583bf65224c.json`](../../sessions/66/661577a37583bf65224c.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

23 recorded events

### Tool call

_source line 1 · 2026-05-22T18:27:55.811033+00:00_

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
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-22T18:27:55.811609+00:00_

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
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-22T18:27:55.811847+00:00_

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
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/threat_model.tex"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-22T18:27:55.812032+00:00_

1	\section{Threat Model and Problem Formulation}
2	
3	A \emph{panel} $\mathcal{P} = \{J_1, \ldots, J_K\}$ consists of $K$ judges (with $K$ odd) that evaluate a candidate text via majority vote: the text is accepted if at least $t = \lceil K/2 \rceil$ judges approve it. Under an attack $a$, each judge $J_j$ is compromised with marginal failure probability $\eta_j(a) = \Pr(X_j^a = 1)$, where $X_j^a \in \{0,1\}$ denotes the failure indicator. We write $\eta_{\max} = \max_j \eta_j$ for the vulnerability of the weakest judge. The \emph{panel attack success rate} is $\mathrm{ASR}(\mathcal{P}, a) = \Pr\!\bigl(\sum_{j=1}^K X_j^a \geq t\bigr)$.
4	
5	To quantify diversity, we define the \emph{effective independence} $K_{\mathrm{eff}}$ directly from pairwise mutual information among judges:
6	\begin{equation}
7	\label{eq:keff}
8	K_{\mathrm{eff}} = \frac{1}{K}\sum_{i=1}^{K} \Bigl[1 + \sum_{j \neq i} \exp\!\bigl(-2 \cdot \mathrm{MI}(i,j)\bigr)\Bigr].
9	\end{equation}
10	This formulation computes effective independence from pairwise MI estimates without matrix decomposition, and is more stable for small panels ($K{=}3$). It ranges from $K_{\mathrm{eff}} \approx K$ when judges are nearly independent ($\mathrm{MI} \to 0$) to $K_{\mathrm{eff}} \approx 1$ when judges are highly correlated ($\mathrm{MI} \to \infty$). Under the strong data-processing inequality (SDPI), the joint vulnerability satisfies $\eta_{\mathrm{joint}} \leq \min(1,\; K_{\mathrm{eff}} \cdot \eta_{\max})$, suggesting that diversity should help---but this bound assumes non-adaptive faults.
11	
12	\begin{definition}[Adaptive Adversary]
13	\label{def:adversary}
14	An \emph{adaptive adversary} has full knowledge of the panel composition $\mathcal{P}$, the per-judge vulnerability profiles $\{\eta_j(\cdot)\}_{j=1}^K$, and the inter-judge correlation structure. It selects the attack $a^* = \arg\max_{a \in \mathcal{A}} \mathrm{ASR}(\mathcal{P}, a)$ to maximize the panel ASR, yielding $\mathrm{ASR}^*(\mathcal{P}) = \sup_{a 
…[truncated 2880 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-22T18:27:55.812184+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-22T18:27:55.812333+00:00_

1	\section{Introduction}
2	
3	Multi-judge panels have emerged as the dominant defense against bias and manipulation in LLM-based evaluation. After \citet{zheng2023judging} demonstrated that individual LLM judges can rival human annotators, subsequent work revealed systematic vulnerabilities: position bias, verbosity preferences, and sycophancy compromise the reliability of any single judge \citep{wang2023fair}. The natural response has been to aggregate decisions across diverse models, drawing on an implicit analogy to Byzantine fault tolerance (BFT), where majority voting among $n$ independent nodes tolerates up to $f < n/3$ faulty members \citep{lamport1982byzantine,castro1999practical}. A recent systematization of LLM-judge security reinforces this assumption, reporting that 7-model committees reduce attack success rates from 50--68\% to 10--19\% \citep{almasoud2026security}. Diversity, by this logic, is the key ingredient for secure evaluation.
4	
5	Yet the evidence for diversity as a causal defense mechanism is weaker than it appears. The observed ASR reduction in multi-judge panels \citep{almasoud2026security} conflates two distinct factors: the diversity of the panel (how independently judges respond to attacks) and the individual robustness of the strongest members. No existing work disentangles these contributions. The theoretical justification rests on similarly uncertain ground: the strong data-processing inequality (SDPI) bounds joint failure in terms of effective independence, but assumes non-adaptive faults. BFT guarantees tolerate arbitrary failures up to a threshold count, yet do not model adversaries that observe panel composition and strategically select attacks \citep{schneier2000secrets}. When the threat shifts from random noise to adaptive manipulation, the assumptions underlying the diversity defense no longer hold.
6	
7	Adding more diverse judges to an evaluation panel predominantly increases, rather than decreases, vulnerability to adversaria
…[truncated 2671 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-22T18:27:55.812480+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/related_work.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-22T18:27:55.812630+00:00_

1	\section{Related Work}
2	
3	\paragraph{LLM-as-Judge and Evaluation Biases.}
4	The use of large language models as automatic evaluators gained traction after \citet{zheng2023judging} introduced MT-Bench and Chatbot Arena, establishing LLM judges as scalable alternatives to human annotation. Subsequent work documented systematic failure modes: \citet{wang2023fair} showed that individual LLM judges exhibit position bias, verbosity preferences, and sycophancy, all of which compromise evaluation reliability. Multi-judge panels have been proposed to mitigate these biases by aggregating decisions across diverse models. A recent systematization of knowledge on LLM-judge security \cite{almasoud2026security} reports that 7-model committees reduce attack success rates to 10--19\%, down from 50--68\% for individual open-source judges. However, this empirical observation lacks a causal explanation: it does not disentangle whether the reduction stems from judge diversity per se or from the inclusion of individually robust models. We address precisely this gap, providing the first controlled analysis that separates the contributions of panel diversity and individual judge robustness under adaptive attack.
5	
6	\paragraph{Adversarial Robustness and Transferability.}
7	Adversarial vulnerability in neural networks was formalized by \citet{goodfellow2015adversarial}, who showed that imperceptible input perturbations can cause misclassification. A key property of such adversarial examples is transferability: \citet{papernot2016transferability} demonstrated that adversarial inputs crafted for one model frequently fool others, and \citet{papernot2017practical} exploited this for black-box attacks via substitute models. \citet{tramer2018ensemble} showed that ensemble adversarial training improves robustness but does not eliminate cross-model vulnerability, because transferred perturbations remain effective across architectures. In the LLM domain, prompt injection attacks \cite{greshake2
…[truncated 4321 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-22T18:27:55.812817+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/references.bib"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-22T18:27:55.813057+00:00_

1	% Bibliography for cert_manip_resist_eval
2	% All entries verified via WebSearch on 2026-05-22
3	% ============================================================
4	
5	% ============================================================
6	% Part A: Papers from literature_map.yaml (12 papers)
7	% ============================================================
8	
9	@article{robertson2025stepwise,
10	  author    = {Robertson, Zachary and Koyejo, Sanmi},
11	  title     = {Let's Measure Information Step-by-Step: {LLM}-Based Evaluation Beyond Vibes},
12	  journal   = {arXiv preprint arXiv:2508.05469},
13	  year      = {2025},
14	  url       = {https://arxiv.org/abs/2508.05469},
15	  note      = {arXiv:2508.05469}
16	}
17	
18	@inproceedings{yang2026diversity,
19	  author    = {Yang, Yingxuan and Qu, Chengrui and Wen, Muning and Shi, Laixi and Wen, Ying and Zhang, Weinan and Wierman, Adam and Gu, Shangding},
20	  title     = {Understanding Agent Scaling in {LLM}-Based Multi-Agent Systems via Diversity},
21	  booktitle = {ICLR 2026 Workshop on AIMS},
22	  year      = {2026},
23	  url       = {https://arxiv.org/abs/2602.03794},
24	  note      = {arXiv:2602.03794}
25	}
26	
27	@article{turkmen2026ensemble,
28	  author    = {Turkmen, Yigit and Buyukates, Baturalp and Bastopcu, Melih},
29	  title     = {Don't Always Pick the Highest-Performing Model: An Information Theoretic View of {LLM} Ensemble Selection},
30	  journal   = {arXiv preprint arXiv:2602.08003},
31	  year      = {2026},
32	  url       = {https://arxiv.org/abs/2602.08003},
33	  note      = {arXiv:2602.08003}
34	}
35	
36	@inproceedings{kaneko2025bits,
37	  author    = {Kaneko, Masahiro and Baldwin, Timothy},
38	  title     = {Bits Leaked per Query: Information-Theoretic Bounds on Adversarial Attacks against {LLMs}},
39	  booktitle = {Advances in Neural Information Processing Systems (NeurIPS)},
40	  year      = {2025},
41	  url       = {https://arxiv.org/abs/2510.17000},
42	  note      = {arXiv:2510.17000. Spotlight}
43	}
44	

…[truncated 12184 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-22T18:27:55.813218+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/",
  "description": "List paper directory contents"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Bash",
  "tool_args": {
    "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/",
    "description": "List paper directory contents"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-22T18:27:55.813344+00:00_

acl.sty
acl_natbib.bst
analysis.tex
conclusion.tex
introduction.tex
main.aux
main.bbl
main.blg
main.fdb_latexmk
main.fls
main.log
main.out
main.pdf
main.tex
methodology.tex
references.bib
related_work.tex
results.tex
threat_model.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-22T18:27:55.813484+00:00_

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
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/methodology.tex"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-22T18:27:55.813604+00:00_

1	\section{Experimental Methodology}
2	% [PLACEHOLDER — to be written by Worker]
3	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-22T18:27:55.813744+00:00_

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
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/main.tex"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-22T18:27:55.813881+00:00_

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
40	% [PLACEHOLDER — short paragraph, ~3 points per EMNLP rules]
41	
42	\bibliography{references}
43	\bibliographystyle{acl_natbib}
44	
45	\end{document}
46	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-22T18:27:55.814127+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/methodology.tex",
  "content": "\\section{Experimental Methodology}\n\\label{sec:experiments}\n\n\\subsection{Models and Panel Construction}\n\nWe select 15 models spanning 6 provider families: Qwen, Llama, Mistral, Anthropic (Claude), OpenAI (GPT), and Google (Gemini). Models are grouped into three capability tiers: \\emph{frontier} (GPT-4o, Claude-3.5-Sonnet, Gemini-1.5-Pro), \\emph{mid-tier} (Qwen2.5-72B, Llama-3.1-70B, Mistral-Large), and \\emph{lightweight} (Qwen2.5-7B, Llama-3.1-8B, and others at comparable scale). This selection covers the full range of model sizes and training lineages deployed in practice for LLM-based evaluation. All panels consist of $K{=}3$ judges with majority-vote threshold $t{=}2$. Exhaustive enumeration of all 3-judge subsets yields $\\binom{15}{3} = 455$ unique panels, covering every combination of provider families and capability tiers. Each panel evaluates all benchmark items under all attack types, producing a complete panel $\\times$ item $\\times$ attack tensor.\n\n\\subsection{Benchmarks and Attack Types}\n\nTwo benchmarks test distinct evaluation capabilities: MMLU \\citep{hendrycks2021mmlu}, a knowledge-intensive multiple-choice benchmark spanning 57 subjects, and ARC \\citep{clark2018arc}, a reasoning-intensive science question benchmark. MMLU probes factual recall and broad domain knowledge; ARC requires multi-step scientific reasoning.\n\nEach benchmark is paired with six attack types that target different judge vulnerabilities: (1)~\\textbf{prompt injection}, adversarial instructions embedded in candidate text that override the evaluation prompt \\citep{perez2022ignore,greshake2023not}; (2)~\\textbf{sycophancy}, responses engineered to agree with or flatter the judge \\citep{wang2023fair}; (3)~\\textbf{score manipulation}, explicit numerical cues (e.g., ``this answer deserves a 10/10'') injected into the candidate to anchor scoring; (4)~\\textbf{verbosity bias}, padding correct answers with excessive irrelevant detail to exploit length preferences \\citep{zheng2023judging}; (5)~\\textbf{position bias}, reordering candidate answers to place the target in the position judges systematically favor \\citep{wang2023fair}; and (6)~\\textbf{authority bias}, prefacing candidate text with fabricated credentials or citations to inflate perceived credibility. The combination of 2 benchmarks and 6 attacks produces 12 experimental conditions, each evaluated across all 455 panels.\n\n\\subsection{Vulnerability Metrics}\n\nPer-judge vulnerability under attack $a$ is the fraction of items where judge $j$ is fooled: $\\eta_j(a) = \\Pr(X_j^a {=} 1)$, estimated empirically over the item set. The weakest-link vulnerability $\\eta_{\\max}(a) = \\max_{j \\in \\mathcal{P}} \\eta_j(a)$ captures the most susceptible member of each panel. The panel attack success rate $\\mathrm{ASR}(\\mathcal{P}, a)$ is the fraction of items where at least $t$ judges are simultaneously fooled. Panel diversity is quantified by $K_{\\mathrm{eff}}$ (Equation~\\ref{eq:keff}), computed from pairwise mutual information \\citep{kraskov2004estimating} between judges' binary failure indicators on clean (unattacked) data. Together, $\\eta_{\\max}$ and $K_{\\mathrm{eff}}$ serve as the two predictors in the regression framework below: $\\eta_{\\max}$ indexes the weakest-link channel and $K_{\\mathrm{eff}}$ indexes the diversity channel.\n\n\\subsection{Aggregation Methods}\n\nBeyond the default majority vote, we evaluate three alternative aggregation rules to test whether the diversity trap persists under different decision mechanisms.\n\n\\paragraph{Majority Vote.} Accept if $\\sum_{j=1}^K \\mathbf{1}[J_j \\text{ approves}] \\geq \\lceil K/2 \\rceil$. This is the standard baseline aggregation.\n\n\\paragraph{Accuracy-Weighted Vote.} Accept if $\\sum_{j=1}^K w_j \\cdot \\mathbf{1}[J_j \\text{ approves}] > 0.5$, where $w_j \\propto \\mathrm{acc}_j$ on held-out clean data, normalized so that $\\sum_j w_j = 1$. Judges with higher clean-data accuracy receive proportionally greater influence.\n\n\\paragraph{Threshold Vote (Unanimity).} Accept only if all $K$ judges approve ($t = K$). A single dissenting judge suffices to reject, making this the most conservative rule.\n\n\\paragraph{Bayesian Calibration.} Compute $P(\\text{correct} \\mid \\mathbf{v}) \\propto P(\\text{correct}) \\prod_j P(v_j \\mid \\text{correct})$, where $P(v_j \\mid \\cdot)$ is derived from judge $j$'s confusion matrix on clean data and $\\mathbf{v}$ is the observed vote vector. Accept if the posterior exceeds 0.5. This rule uses each judge's calibrated reliability rather than treating all votes equally.\n\n\\subsection{Statistical Framework}\n\\label{sec:stat_framework}\n\nTo disentangle the contributions of panel diversity and individual judge robustness, we fit a log-log OLS regression for each of the 12 conditions:\n\\begin{equation}\n\\label{eq:regression}\n\\log(\\mathrm{ASR} + \\epsilon) = \\alpha + \\beta_1 \\log(K_{\\mathrm{eff}}) + \\beta_2 \\log(\\eta_{\\max} + \\epsilon),\n\\end{equation}\nwith $\\epsilon = 10^{-6}$ to handle zero values. Standardized coefficients $\\hat{\\beta}_{\\mathrm{std}} = \\hat{\\beta} \\cdot \\mathrm{SD}(\\log x) / \\mathrm{SD}(\\log y)$ enable direct comparison of effect magnitudes across predictors and conditions. We apply Benjamini-Hochberg correction for multiple testing, controlling the false discovery rate per predictor across the 12 conditions.\n\nTo assess relative predictor importance beyond regression coefficients, we perform dominance analysis [CITE NEEDED: Budescu 1993 dominance analysis]. This method decomposes $R^2$ by averaging each predictor's incremental $R^2$ contribution across all possible subsets of predictors. A predictor is \\emph{dominant} if its average contribution exceeds that of the competing predictor in every subset ordering. With two predictors, dominance reduces to comparing each predictor's solo $R^2$ with its incremental $R^2$ conditional on the other.\n\n\\subsection{Sensitivity Analysis}\n\nJudges with clean-data accuracy below 0.5 perform at or below chance and could drive regression results through extreme outlier behavior rather than meaningful vulnerability patterns. We exclude such judges from panel construction and re-run the log-log regression (Equation~\\ref{eq:regression}) to verify that the $K_{\\mathrm{eff}}$ effect remains stable after removing these potential confounds.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/methodology.tex",
    "content": "\\section{Experimental Methodology}\n\\label{sec:experiments}\n\n\\subsection{Models and Panel Construction}\n\nWe select 15 models spanning 6 provider families: Qwen, Llama, Mistral, Anthropic (Claude), OpenAI (GPT), and Google (Gemini). Models are grouped into three capability tiers: \\emph{frontier} (GPT-4o, Claude-3.5-Sonnet, Gemini-1.5-Pro), \\emph{mid-tier} (Qwen2.5-72B, Llama-3.1-70B, Mistral-Large), and \\emph{lightweight} (Qwen2.5-7B, Llama-3.1-8B, and others at comparable scale). This selection covers the full range of model sizes and training lineages deployed in practice for LLM-based evaluation. All panels consist of $K{=}3$ judges with majority-vote threshold $t{=}2$. Exhaustive enumeration of all 3-judge subsets yields $\\binom{15}{3} = 455$ unique panels, covering every combination of provider families and capability tiers. Each panel evaluates all benchmark items under all attack types, producing a complete panel $\\times$ item $\\times$ attack tensor.\n\n\\subsection{Benchmarks and Attack Types}\n\nTwo benchmarks test distinct evaluation capabilities: MMLU \\citep{hendrycks2021mmlu}, a knowledge-intensive multiple-choice benchmark spanning 57 subjects, and ARC \\citep{clark2018arc}, a reasoning-intensive science question benchmark. MMLU probes factual recall and broad domain knowledge; ARC requires multi-step scientific reasoning.\n\nEach benchmark is paired with six attack types that target different judge vulnerabilities: (1)~\\textbf{prompt injection}, adversarial instructions embedded in candidate text that override the evaluation prompt \\citep{perez2022ignore,greshake2023not}; (2)~\\textbf{sycophancy}, responses engineered to agree with or flatter the judge \\citep{wang2023fair}; (3)~\\textbf{score manipulation}, explicit numerical cues (e.g., ``this answer deserves a 10/10'') injected into the candidate to anchor scoring; (4)~\\textbf{verbosity bias}, padding correct answers with excessive irrelevant detail to exploit length preferences \\citep{zheng2023judging}; (5)~\\textbf{position bias}, reordering candidate answers to place the target in the position judges systematically favor \\citep{wang2023fair}; and (6)~\\textbf{authority bias}, prefacing candidate text with fabricated credentials or citations to inflate perceived credibility. The combination of 2 benchmarks and 6 attacks produces 12 experimental conditions, each evaluated across all 455 panels.\n\n\\subsection{Vulnerability Metrics}\n\nPer-judge vulnerability under attack $a$ is the fraction of items where judge $j$ is fooled: $\\eta_j(a) = \\Pr(X_j^a {=} 1)$, estimated empirically over the item set. The weakest-link vulnerability $\\eta_{\\max}(a) = \\max_{j \\in \\mathcal{P}} \\eta_j(a)$ captures the most susceptible member of each panel. The panel attack success rate $\\mathrm{ASR}(\\mathcal{P}, a)$ is the fraction of items where at least $t$ judges are simultaneously fooled. Panel diversity is quantified by $K_{\\mathrm{eff}}$ (Equation~\\ref{eq:keff}), computed from pairwise mutual information \\citep{kraskov2004estimating} between judges' binary failure indicators on clean (unattacked) data. Together, $\\eta_{\\max}$ and $K_{\\mathrm{eff}}$ serve as the two predictors in the regression framework below: $\\eta_{\\max}$ indexes the weakest-link channel and $K_{\\mathrm{eff}}$ indexes the diversity channel.\n\n\\subsection{Aggregation Methods}\n\nBeyond the default majority vote, we evaluate three alternative aggregation rules to test whether the diversity trap persists under different decision mechanisms.\n\n\\paragraph{Majority Vote.} Accept if $\\sum_{j=1}^K \\mathbf{1}[J_j \\text{ approves}] \\geq \\lceil K/2 \\rceil$. This is the standard baseline aggregation.\n\n\\paragraph{Accuracy-Weighted Vote.} Accept if $\\sum_{j=1}^K w_j \\cdot \\mathbf{1}[J_j \\text{ approves}] > 0.5$, where $w_j \\propto \\mathrm{acc}_j$ on held-out clean data, normalized so that $\\sum_j w_j = 1$. Judges with higher clean-data accuracy receive proportionally greater influence.\n\n\\paragraph{Threshold Vote (Unanimity).} Accept only if all $K$ judges approve ($t = K$). A single dissenting judge suffices to reject, making this the most conservative rule.\n\n\\paragraph{Bayesian Calibration.} Compute $P(\\text{correct} \\mid \\mathbf{v}) \\propto P(\\text{correct}) \\prod_j P(v_j \\mid \\text{correct})$, where $P(v_j \\mid \\cdot)$ is derived from judge $j$'s confusion matrix on clean data and $\\mathbf{v}$ is the observed vote vector. Accept if the posterior exceeds 0.5. This rule uses each judge's calibrated reliability rather than treating all votes equally.\n\n\\subsection{Statistical Framework}\n\\label{sec:stat_framework}\n\nTo disentangle the contributions of panel diversity and individual judge robustness, we fit a log-log OLS regression for each of the 12 conditions:\n\\begin{equation}\n\\label{eq:regression}\n\\log(\\mathrm{ASR} + \\epsilon) = \\alpha + \\beta_1 \\log(K_{\\mathrm{eff}}) + \\beta_2 \\log(\\eta_{\\max} + \\epsilon),\n\\end{equation}\nwith $\\epsilon = 10^{-6}$ to handle zero values. Standardized coefficients $\\hat{\\beta}_{\\mathrm{std}} = \\hat{\\beta} \\cdot \\mathrm{SD}(\\log x) / \\mathrm{SD}(\\log y)$ enable direct comparison of effect magnitudes across predictors and conditions. We apply Benjamini-Hochberg correction for multiple testing, controlling the false discovery rate per predictor across the 12 conditions.\n\nTo assess relative predictor importance beyond regression coefficients, we perform dominance analysis [CITE NEEDED: Budescu 1993 dominance analysis]. This method decomposes $R^2$ by averaging each predictor's incremental $R^2$ contribution across all possible subsets of predictors. A predictor is \\emph{dominant} if its average contribution exceeds that of the competing predictor in every subset ordering. With two predictors, dominance reduces to comparing each predictor's solo $R^2$ with its incremental $R^2$ conditional on the other.\n\n\\subsection{Sensitivity Analysis}\n\nJudges with clean-data accuracy below 0.5 perform at or below chance and could drive regression results through extreme outlier behavior rather than meaningful vulnerability patterns. We exclude such judges from panel construction and re-run the log-log regression (Equation~\\ref{eq:regression}) to verify that the $K_{\\mathrm{eff}}$ effect remains stable after removing these potential confounds.\n"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-22T18:27:55.814309+00:00_

&lt;tool_use_error>File has been modified since read, either by the user or by a linter. Read it again before attempting to write it.&lt;/tool_use_error>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-22T18:27:55.814435+00:00_

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
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/methodology.tex"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-22T18:27:55.814583+00:00_

1	\section{Experimental Methodology}
2	\label{sec:experiments}
3	
4	\subsection{Models and Panel Construction}
5	
6	We evaluate 15 LLM judges spanning 6 model families (Qwen, Llama, Mistral, Anthropic, OpenAI, Google) and 3 capability tiers: frontier models (GPT-4o, Claude-3.5-Sonnet, Gemini-1.5-Pro), mid-tier models (Qwen2.5-72B, Llama-3.1-70B, Mistral-Large), and lightweight models (Qwen2.5-7B, Llama-3.1-8B, Mistral-7B, among others). Each panel $\mathcal{P}$ consists of $K{=}3$ judges evaluated under majority vote ($t{=}2$). We enumerate all $\binom{15}{3} = 455$ unique 3-judge panels, providing dense coverage of the diversity--robustness space without sampling bias.
7	
8	\subsection{Benchmarks and Attack Types}
9	
10	Panels are evaluated on two benchmarks: MMLU \citep{hendrycks2021mmlu}, which tests broad knowledge, and ARC \citep{clark2018arc}, which tests scientific reasoning. Each panel faces 6 attack types: \emph{prompt injection} (adversarial instructions prepended to the evaluation prompt), \emph{sycophancy} (flattery and agreement-seeking phrasing), \emph{score manipulation} (explicitly requesting inflated scores), \emph{verbosity bias} (padding responses with irrelevant detail), \emph{position bias} (exploiting serial-position effects in pairwise comparison), and \emph{authority bias} (invoking fictitious expert endorsements). This yields $2 \times 6 = 12$ experimental conditions.
11	
12	\subsection{Vulnerability Metrics}
13	
14	Per-judge vulnerability under attack $a$ is $\eta_j(a) = \Pr(X_j^a {=} 1)$, the fraction of benchmark items on which judge $j$ is fooled. The panel's weakest-link vulnerability is $\eta_{\max} = \max_j \eta_j$. The panel attack success rate $\mathrm{ASR}(\mathcal{P}, a)$ is the fraction of items on which $\geq t$ judges are simultaneously fooled. Panel diversity is quantified by effective independence $K_{\mathrm{eff}}$ (Equation~\ref{eq:keff}), computed from pairwise mutual information on judge decision vectors.
15	
16	\subsecti
…[truncated 2620 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-22T18:27:55.814795+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/methodology.tex",
  "content": "\\section{Experimental Methodology}\n\\label{sec:experiments}\n\n\\subsection{Models and Panel Construction}\n\nWe select 15 models spanning 6 provider families: Qwen, Llama, Mistral, Anthropic (Claude), OpenAI (GPT), and Google (Gemini). Models are grouped into three capability tiers: \\emph{frontier} (GPT-4o, Claude-3.5-Sonnet, Gemini-1.5-Pro), \\emph{mid-tier} (Qwen2.5-72B, Llama-3.1-70B, Mistral-Large), and \\emph{lightweight} (Qwen2.5-7B, Llama-3.1-8B, and others at comparable scale). This selection covers the full range of model sizes and training lineages deployed in practice for LLM-based evaluation. All panels consist of $K{=}3$ judges with majority-vote threshold $t{=}2$. Exhaustive enumeration of all 3-judge subsets yields $\\binom{15}{3} = 455$ unique panels, covering every combination of provider families and capability tiers. Each panel evaluates all benchmark items under all attack types, producing a complete panel $\\times$ item $\\times$ attack tensor.\n\n\\subsection{Benchmarks and Attack Types}\n\nTwo benchmarks test distinct evaluation capabilities: MMLU \\citep{hendrycks2021mmlu}, a knowledge-intensive multiple-choice benchmark spanning 57 subjects, and ARC \\citep{clark2018arc}, a reasoning-intensive science question benchmark. MMLU probes factual recall and broad domain knowledge; ARC requires multi-step scientific reasoning.\n\nEach benchmark is paired with six attack types that target different judge vulnerabilities: (1)~\\textbf{prompt injection}, adversarial instructions embedded in candidate text that override the evaluation prompt \\citep{perez2022ignore,greshake2023not}; (2)~\\textbf{sycophancy}, responses engineered to agree with or flatter the judge \\citep{wang2023fair}; (3)~\\textbf{score manipulation}, explicit numerical cues (e.g., ``this answer deserves a 10/10'') injected into the candidate to anchor scoring; (4)~\\textbf{verbosity bias}, padding correct answers with excessive irrelevant detail to exploit length preferences \\citep{zheng2023judging}; (5)~\\textbf{position bias}, reordering candidate answers to place the target in the position judges systematically favor \\citep{wang2023fair}; and (6)~\\textbf{authority bias}, prefacing candidate text with fabricated credentials or citations to inflate perceived credibility. The combination of 2 benchmarks and 6 attacks produces 12 experimental conditions, each evaluated across all 455 panels.\n\n\\subsection{Vulnerability Metrics}\n\nPer-judge vulnerability under attack $a$ is the fraction of items where judge $j$ is fooled: $\\eta_j(a) = \\Pr(X_j^a {=} 1)$, estimated empirically over the item set. The weakest-link vulnerability $\\eta_{\\max}(a) = \\max_{j \\in \\mathcal{P}} \\eta_j(a)$ captures the most susceptible member of each panel. The panel attack success rate $\\mathrm{ASR}(\\mathcal{P}, a)$ is the fraction of items where at least $t$ judges are simultaneously fooled. Panel diversity is quantified by $K_{\\mathrm{eff}}$ (Equation~\\ref{eq:keff}), computed from pairwise mutual information \\citep{kraskov2004estimating} between judges' binary failure indicators on clean (unattacked) data. Together, $\\eta_{\\max}$ and $K_{\\mathrm{eff}}$ serve as the two predictors in the regression framework below: $\\eta_{\\max}$ indexes the weakest-link channel and $K_{\\mathrm{eff}}$ indexes the diversity channel.\n\n\\subsection{Aggregation Methods}\n\nBeyond the default majority vote, we evaluate three alternative aggregation rules to test whether the diversity trap persists under different decision mechanisms.\n\n\\paragraph{Majority Vote.} Accept if $\\sum_{j=1}^K \\mathbf{1}[J_j \\text{ approves}] \\geq \\lceil K/2 \\rceil$. This is the standard baseline aggregation assumed throughout the main analysis.\n\n\\paragraph{Accuracy-Weighted Vote.} Accept if $\\sum_{j=1}^K w_j \\cdot \\mathbf{1}[J_j \\text{ approves}] > 0.5$, where $w_j \\propto \\mathrm{acc}_j$ on held-out clean data, normalized so that $\\sum_j w_j = 1$. Judges with higher clean-data accuracy receive proportionally greater influence.\n\n\\paragraph{Threshold Vote (Unanimity).} Accept only if all $K$ judges approve ($t = K$). A single dissenting judge suffices to reject, making this the most conservative rule.\n\n\\paragraph{Bayesian Calibration.} Compute $P(\\text{correct} \\mid \\mathbf{v}) \\propto P(\\text{correct}) \\prod_j P(v_j \\mid \\text{correct})$, where $P(v_j \\mid \\cdot)$ is derived from judge $j$'s confusion matrix on clean data and $\\mathbf{v}$ is the observed vote vector. Accept if the posterior exceeds 0.5. This rule uses each judge's calibrated reliability rather than treating all votes equally.\n\n\\subsection{Statistical Framework}\n\\label{sec:stat_framework}\n\nTo disentangle the contributions of panel diversity and individual judge robustness, we fit a log-log OLS regression for each of the 12 conditions:\n\\begin{equation}\n\\label{eq:regression}\n\\log(\\mathrm{ASR} + \\epsilon) = \\alpha + \\beta_1 \\log(K_{\\mathrm{eff}}) + \\beta_2 \\log(\\eta_{\\max} + \\epsilon),\n\\end{equation}\nwith $\\epsilon = 10^{-6}$ to handle zero values. Standardized coefficients $\\hat{\\beta}_{\\mathrm{std}} = \\hat{\\beta} \\cdot \\mathrm{SD}(\\log x) / \\mathrm{SD}(\\log y)$ enable direct comparison of effect magnitudes across predictors and conditions. We apply Benjamini-Hochberg correction for multiple testing, controlling the false discovery rate per predictor across the 12 conditions.\n\nTo assess relative predictor importance beyond regression coefficients, we perform dominance analysis [CITE NEEDED: Budescu 1993 dominance analysis]. This method decomposes $R^2$ by averaging each predictor's incremental $R^2$ contribution across all possible subsets of predictors. A predictor is \\emph{dominant} if its average contribution exceeds that of the competing predictor in every subset ordering. With two predictors, dominance reduces to comparing each predictor's solo $R^2$ with its incremental $R^2$ conditional on the other.\n\n\\subsection{Sensitivity Analysis}\n\nJudges with clean-data accuracy below 0.5 perform at or below chance and could drive regression results through extreme outlier behavior rather than meaningful vulnerability patterns. We exclude such judges from panel construction and re-run the log-log regression (Equation~\\ref{eq:regression}) to verify that the $K_{\\mathrm{eff}}$ effect remains stable after removing these potential confounds.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/methodology.tex",
    "content": "\\section{Experimental Methodology}\n\\label{sec:experiments}\n\n\\subsection{Models and Panel Construction}\n\nWe select 15 models spanning 6 provider families: Qwen, Llama, Mistral, Anthropic (Claude), OpenAI (GPT), and Google (Gemini). Models are grouped into three capability tiers: \\emph{frontier} (GPT-4o, Claude-3.5-Sonnet, Gemini-1.5-Pro), \\emph{mid-tier} (Qwen2.5-72B, Llama-3.1-70B, Mistral-Large), and \\emph{lightweight} (Qwen2.5-7B, Llama-3.1-8B, and others at comparable scale). This selection covers the full range of model sizes and training lineages deployed in practice for LLM-based evaluation. All panels consist of $K{=}3$ judges with majority-vote threshold $t{=}2$. Exhaustive enumeration of all 3-judge subsets yields $\\binom{15}{3} = 455$ unique panels, covering every combination of provider families and capability tiers. Each panel evaluates all benchmark items under all attack types, producing a complete panel $\\times$ item $\\times$ attack tensor.\n\n\\subsection{Benchmarks and Attack Types}\n\nTwo benchmarks test distinct evaluation capabilities: MMLU \\citep{hendrycks2021mmlu}, a knowledge-intensive multiple-choice benchmark spanning 57 subjects, and ARC \\citep{clark2018arc}, a reasoning-intensive science question benchmark. MMLU probes factual recall and broad domain knowledge; ARC requires multi-step scientific reasoning.\n\nEach benchmark is paired with six attack types that target different judge vulnerabilities: (1)~\\textbf{prompt injection}, adversarial instructions embedded in candidate text that override the evaluation prompt \\citep{perez2022ignore,greshake2023not}; (2)~\\textbf{sycophancy}, responses engineered to agree with or flatter the judge \\citep{wang2023fair}; (3)~\\textbf{score manipulation}, explicit numerical cues (e.g., ``this answer deserves a 10/10'') injected into the candidate to anchor scoring; (4)~\\textbf{verbosity bias}, padding correct answers with excessive irrelevant detail to exploit length preferences \\citep{zheng2023judging}; (5)~\\textbf{position bias}, reordering candidate answers to place the target in the position judges systematically favor \\citep{wang2023fair}; and (6)~\\textbf{authority bias}, prefacing candidate text with fabricated credentials or citations to inflate perceived credibility. The combination of 2 benchmarks and 6 attacks produces 12 experimental conditions, each evaluated across all 455 panels.\n\n\\subsection{Vulnerability Metrics}\n\nPer-judge vulnerability under attack $a$ is the fraction of items where judge $j$ is fooled: $\\eta_j(a) = \\Pr(X_j^a {=} 1)$, estimated empirically over the item set. The weakest-link vulnerability $\\eta_{\\max}(a) = \\max_{j \\in \\mathcal{P}} \\eta_j(a)$ captures the most susceptible member of each panel. The panel attack success rate $\\mathrm{ASR}(\\mathcal{P}, a)$ is the fraction of items where at least $t$ judges are simultaneously fooled. Panel diversity is quantified by $K_{\\mathrm{eff}}$ (Equation~\\ref{eq:keff}), computed from pairwise mutual information \\citep{kraskov2004estimating} between judges' binary failure indicators on clean (unattacked) data. Together, $\\eta_{\\max}$ and $K_{\\mathrm{eff}}$ serve as the two predictors in the regression framework below: $\\eta_{\\max}$ indexes the weakest-link channel and $K_{\\mathrm{eff}}$ indexes the diversity channel.\n\n\\subsection{Aggregation Methods}\n\nBeyond the default majority vote, we evaluate three alternative aggregation rules to test whether the diversity trap persists under different decision mechanisms.\n\n\\paragraph{Majority Vote.} Accept if $\\sum_{j=1}^K \\mathbf{1}[J_j \\text{ approves}] \\geq \\lceil K/2 \\rceil$. This is the standard baseline aggregation assumed throughout the main analysis.\n\n\\paragraph{Accuracy-Weighted Vote.} Accept if $\\sum_{j=1}^K w_j \\cdot \\mathbf{1}[J_j \\text{ approves}] > 0.5$, where $w_j \\propto \\mathrm{acc}_j$ on held-out clean data, normalized so that $\\sum_j w_j = 1$. Judges with higher clean-data accuracy receive proportionally greater influence.\n\n\\paragraph{Threshold Vote (Unanimity).} Accept only if all $K$ judges approve ($t = K$). A single dissenting judge suffices to reject, making this the most conservative rule.\n\n\\paragraph{Bayesian Calibration.} Compute $P(\\text{correct} \\mid \\mathbf{v}) \\propto P(\\text{correct}) \\prod_j P(v_j \\mid \\text{correct})$, where $P(v_j \\mid \\cdot)$ is derived from judge $j$'s confusion matrix on clean data and $\\mathbf{v}$ is the observed vote vector. Accept if the posterior exceeds 0.5. This rule uses each judge's calibrated reliability rather than treating all votes equally.\n\n\\subsection{Statistical Framework}\n\\label{sec:stat_framework}\n\nTo disentangle the contributions of panel diversity and individual judge robustness, we fit a log-log OLS regression for each of the 12 conditions:\n\\begin{equation}\n\\label{eq:regression}\n\\log(\\mathrm{ASR} + \\epsilon) = \\alpha + \\beta_1 \\log(K_{\\mathrm{eff}}) + \\beta_2 \\log(\\eta_{\\max} + \\epsilon),\n\\end{equation}\nwith $\\epsilon = 10^{-6}$ to handle zero values. Standardized coefficients $\\hat{\\beta}_{\\mathrm{std}} = \\hat{\\beta} \\cdot \\mathrm{SD}(\\log x) / \\mathrm{SD}(\\log y)$ enable direct comparison of effect magnitudes across predictors and conditions. We apply Benjamini-Hochberg correction for multiple testing, controlling the false discovery rate per predictor across the 12 conditions.\n\nTo assess relative predictor importance beyond regression coefficients, we perform dominance analysis [CITE NEEDED: Budescu 1993 dominance analysis]. This method decomposes $R^2$ by averaging each predictor's incremental $R^2$ contribution across all possible subsets of predictors. A predictor is \\emph{dominant} if its average contribution exceeds that of the competing predictor in every subset ordering. With two predictors, dominance reduces to comparing each predictor's solo $R^2$ with its incremental $R^2$ conditional on the other.\n\n\\subsection{Sensitivity Analysis}\n\nJudges with clean-data accuracy below 0.5 perform at or below chance and could drive regression results through extreme outlier behavior rather than meaningful vulnerability patterns. We exclude such judges from panel construction and re-run the log-log regression (Equation~\\ref{eq:regression}) to verify that the $K_{\\mathrm{eff}}$ effect remains stable after removing these potential confounds.\n"
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-22T18:27:55.815181+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/methodology.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 23 · 2026-05-22T18:27:55.815430+00:00_

Methodology section written to `methodology.tex`. Key properties:

- 6 subsections as specified, with `\label{sec:experiments}` matching introduction references
- All citations use keys from `references.bib` (hendrycks2021mmlu, clark2018arc, perez2022ignore, greshake2023not, wang2023fair, zheng2023judging, kraskov2004estimating)
- Budescu 1993 marked as `[CITE NEEDED: Budescu 1993 dominance analysis]`
- References Equation~\ref{eq:keff} from threat model without redefining $K_{\mathrm{eff}}$
- No em-dashes, no AI-style words, no -ing phrase endings
- Compact layout (~1.5 pages): attacks listed inline with semicolons, aggregation methods use \paragraph{} blocks

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_methodology_v4b_20260522T182359"
}
```

</details>

---
