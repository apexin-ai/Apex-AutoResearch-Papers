# paper writing related work

**Spectral Early Warning Signals for Model Collapse and Their Prevention–Detectability Tradeoff** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 21
- **Recorded user turns:** 0
- **Tool calls:** 10
- **Original source:** `logs/chats/worker_paper_writing_related_work_20260517T205658.jsonl`
- **Structured JSON:** [`d8267a56af25a0c8ee6e.json`](../../sessions/d8/d8267a56af25a0c8ee6e.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

21 recorded events

### Tool call

_source line 1 · 2026-05-17T20:58:47.352174+00:00_

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
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-17T20:58:47.352777+00:00_

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
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-17T20:58:47.352970+00:00_

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
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-17T20:58:47.353308+00:00_

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
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-17T20:58:47.353477+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-17T20:58:47.353653+00:00_

1	
2	Synthetic data has become integral to language model training.
3	Instruction tuning, knowledge distillation, and data augmentation all routinely use model-generated text, and as synthetic corpora are recycled into training pipelines, the process often becomes recursive: each generation of models is fine-tuned on outputs from the previous one.
4	Recent work demonstrates that such recursive synthetic training triggers \textit{model collapse}, a progressive erosion of distributional tails and downstream capability~\cite{shumailov2024collapse, dohmatob2024tails, alemohammad2024mad}.
5	The problem is especially pressing as web-scraped corpora increasingly contain model-generated content, a trend that introduces implicit recursive loops even without deliberate data reuse.
6	
7	While model collapse is now well-characterized through theoretical analysis of tail decay~\cite{dohmatob2024tails} and empirical studies across modalities~\cite{shumailov2024collapse, alemohammad2024mad}, its effect on the geometric structure of learned representations remains poorly understood.
8	As recursive training erodes distributional diversity, the embedding space should contract onto a lower-dimensional subspace.
9	Characterizing this spectral trajectory could yield computationally cheap collapse indicators from internal model states alone, without text generation or benchmark evaluation.
10	
11	Current collapse detection depends on downstream metrics such as perplexity and benchmark accuracy, or on analysis of generated text through lexical diversity measures.
12	Both approaches require either costly inference or external evaluation infrastructure at every generation.
13	SIGMA~\cite{gu2026sigma} introduced spectral monitoring through embedding covariance analysis and showed that spectral indicators can track collapse, but validated only on OPT-125M over short generation horizons.
14	Three gaps remain open.
15	First, no work has systematically characterized spectral dynamics beyond a fe
…[truncated 2288 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-17T20:58:47.353812+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections/method.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-17T20:58:47.353967+00:00_

1	\subsection{Spectral Metrics}
2	\label{subsec:spectral_metrics}
3	
4	Given a language model at generation $t$, we extract last-layer embeddings for $n{=}1{,}000$ held-out samples to form $\mathbf{E} \in \mathbb{R}^{n \times d}$ and compute the Gram matrix $\mathbf{G} = \mathbf{E}^\top \mathbf{E}$.
5	Let $\sigma_1 \geq \sigma_2 \geq \cdots \geq \sigma_d$ denote the singular values of $\mathbf{E}$.
6	We track three complementary spectral indicators:
7	
8	\paragraph{Spectral Log-Volume (SLV).}
9	$\text{SLV} = \sum_i \log \sigma_i = \frac{1}{2} \log \det \mathbf{G}$.
10	This quantity measures the total volume spanned by the embedding cloud in log-space.
11	Because it sums over all singular values, SLV is sensitive to contraction along any spectral direction, not only the dominant ones.
12	
13	\paragraph{Effective Rank.}
14	$r_{\text{eff}} = \exp(H(\mathbf{p}))$, where $p_i = \sigma_i / \sum_j \sigma_j$ and $H$ is the Shannon entropy.
15	Effective rank quantifies how many dimensions carry substantial variance.
16	A uniform spectrum yields $r_{\text{eff}} \approx d$; concentration onto few directions drives $r_{\text{eff}}$ toward~1.
17	
18	\paragraph{Leading Singular Value.}
19	$\sigma_1$ tracks the energy in the most dominant spectral direction.
20	Rising $\sigma_1$ under falling $r_{\text{eff}}$ signals that variance is concentrating into a low-dimensional subspace, a hallmark of representational collapse.
21	
22	These three metrics capture complementary collapse signatures: SLV detects global volume loss, $r_{\text{eff}}$ measures dimensionality reduction, and $\sigma_1$ isolates spectral concentration.
23	
24	\subsection{Adaptive Mixing Controller}
25	\label{subsec:controller}
26	
27	We propose a closed-loop controller that adjusts the real-data mixing ratio $r_t$ at each generation based on the rate of spectral change.
28	The update rule is:
29	\begin{equation}
30	\label{eq:controller}
31	r_{t+1} = \frac{B_{\text{rem}}}{T - t} + k \cdot \max(0,\; \Delta_t - \tau)

…[truncated 2057 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-17T20:58:47.354143+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections/related_work.tex 2>/dev/null; echo \"exit: $?\"",
  "description": "Check if related_work.tex exists"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Bash",
  "tool_args": {
    "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections/related_work.tex 2>/dev/null; echo \"exit: $?\"",
    "description": "Check if related_work.tex exists"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-17T20:58:47.354264+00:00_

/home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections/related_work.tex
exit: 0

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-17T20:58:47.354379+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections/related_work.tex"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-17T20:58:47.354491+00:00_

1	\todo{Related Work to be written in Step 4.}
2	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-17T20:58:47.354708+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "\\\\citet|\\\\citep|\\\\cite\\b|natbib|\\\\usepackage.*cite",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Grep",
  "tool_args": {
    "pattern": "\\\\citet|\\\\citep|\\\\cite\\b|natbib|\\\\usepackage.*cite",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-17T20:58:47.354884+00:00_

paper/acl.sty:186:\RequirePackage{natbib}
paper/acl.sty:188:% \citep, \citet, and \citeyearpar for compatibility with natbib, or
paper/acl.sty:189:% \cite, \newcite, and \shortcite for compatibility with older ACL .sty files
paper/acl.sty:190:\renewcommand\cite{\citep}  % to get "(Author Year)" with natbib
paper/acl.sty:191:\newcommand\shortcite{\citeyearpar}% to get "(Year)" with natbib
paper/acl.sty:192:\newcommand\newcite{\citet} % to get "Author (Year)" with natbib
paper/acl.sty:193:\newcommand{\citeposs}[1]{\citeauthor{#1}'s (\citeyear{#1})} % to get "Author's (Year)"
paper/acl.sty:195:\bibliographystyle{acl_natbib}
paper/acl.sty:299:% The hyperref manual (section 9) says hyperref should be loaded after natbib
paper/acl.sty:309:  % This is necessary because \href command is used in the acl_natbib.bst file.
paper/main.log:129:(/usr/share/texlive/texmf-dist/tex/latex/natbib/natbib.sty
paper/main.log:130:Package: natbib 2010/09/13 8.31b (PWD, AO)
paper/main.log:133:LaTeX Info: Redefining \cite on input line 694.
paper/sections/experiments.tex:5:We use Pythia-410M-deduped \cite{biderman2023pythia} as our base model and fine-tune on a 50K-subset of OpenWebText.
paper/sections/introduction.tex:4:Recent work demonstrates that such recursive synthetic training triggers \textit{model collapse}, a progressive erosion of distributional tails and downstream capability~\cite{shumailov2024collapse, dohmatob2024tails, alemohammad2024mad}.
paper/sections/introduction.tex:7:While model collapse is now well-characterized through theoretical analysis of tail decay~\cite{dohmatob2024tails} and empirical studies across modalities~\cite{shumailov2024collapse, alemohammad2024mad}, its effect on the geometric structure of learned representations remains poorly understood.
paper/sections/introduction.tex:13:SIGMA~\cite{gu2026sigma} introduced spectral monitoring through embedding covariance analysis and showed that spectral indicators can track collapse, but validated only on OPT-125M 
…[truncated 1650 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-17T20:58:47.355077+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections/related_work.tex",
  "content": "\n\\paragraph{Model Collapse.}\nRecursive training on synthetic data causes progressive distributional narrowing, a phenomenon termed model collapse.\n\\citet{shumailov2024collapse} provided the first systematic evidence across multiple model families, showing that tail distributions erode over successive generations.\nTheoretical analysis by \\citet{dohmatob2024tails} established scaling laws for this tail decay, and subsequent work demonstrated that contamination levels as low as 1\\% synthetic data can trigger strong collapse~\\cite{dohmatob2025strong}.\nThe MAD framework~\\cite{alemohammad2024mad} formalized the dynamics of self-consuming generative models, confirming that iterative loops converge to degenerate distributions without fresh data injection.\n\\citet{gerstgrasser2024inevitable} showed that accumulating real data across generations can prevent collapse entirely.\nThese studies characterize collapse through output distribution metrics, perplexity, or benchmark scores.\nOur work complements this line of research: we track collapse through the spectral geometry of learned representations and connect distributional tail decay to measurable contraction in the embedding space.\n\n\\paragraph{Spectral Analysis of Representations.}\nSpectral properties of neural networks have been studied from several angles.\n\\citet{martin2021implicit} applied Random Matrix Theory to weight matrices of pretrained networks, showing that heavy-tailed spectral density encodes implicit regularization.\n\\citet{roy2007effectiverank} defined effective rank as a continuous dimensionality measure based on singular value entropy, which has since become standard in representation analysis~\\cite{rankme2023}.\nIn training dynamics, \\citet{he2025spectral} linked spectral collapse of representation covariance matrices to catastrophic forgetting in continual learning.\nClosest to our setting, \\citet{gu2026sigma} proposed the SIGMA framework for spectral monitoring during recursive synthetic training, with validation on OPT-125M over short generation horizons.\nWe extend this direction along three axes: systematic tracking over 10 generations, validation at the 410M and 1B scale, and the connection from spectral indicators to closed-loop collapse prevention.\n\n\\paragraph{Data Mixing for LLM Training.}\nControlling training data composition is critical for language model quality.\nDoReMi~\\cite{xie2023doremi} trains a small proxy model to reweight domain mixtures before the main training run.\nData Mixing Laws~\\cite{ye2025mixinglaws, data_mixing_laws2024} predict optimal ratios from small-scale experiments so that mixture optimization does not require full-scale retraining.\nBoth paradigms determine ratios prior to training and hold them fixed throughout.\nOur adaptive controller differs fundamentally: it adjusts the real-synthetic mixing ratio online during recursive training, guided by real-time spectral feedback from the model's own representations rather than a priori proxy estimates.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections/related_work.tex",
    "content": "\n\\paragraph{Model Collapse.}\nRecursive training on synthetic data causes progressive distributional narrowing, a phenomenon termed model collapse.\n\\citet{shumailov2024collapse} provided the first systematic evidence across multiple model families, showing that tail distributions erode over successive generations.\nTheoretical analysis by \\citet{dohmatob2024tails} established scaling laws for this tail decay, and subsequent work demonstrated that contamination levels as low as 1\\% synthetic data can trigger strong collapse~\\cite{dohmatob2025strong}.\nThe MAD framework~\\cite{alemohammad2024mad} formalized the dynamics of self-consuming generative models, confirming that iterative loops converge to degenerate distributions without fresh data injection.\n\\citet{gerstgrasser2024inevitable} showed that accumulating real data across generations can prevent collapse entirely.\nThese studies characterize collapse through output distribution metrics, perplexity, or benchmark scores.\nOur work complements this line of research: we track collapse through the spectral geometry of learned representations and connect distributional tail decay to measurable contraction in the embedding space.\n\n\\paragraph{Spectral Analysis of Representations.}\nSpectral properties of neural networks have been studied from several angles.\n\\citet{martin2021implicit} applied Random Matrix Theory to weight matrices of pretrained networks, showing that heavy-tailed spectral density encodes implicit regularization.\n\\citet{roy2007effectiverank} defined effective rank as a continuous dimensionality measure based on singular value entropy, which has since become standard in representation analysis~\\cite{rankme2023}.\nIn training dynamics, \\citet{he2025spectral} linked spectral collapse of representation covariance matrices to catastrophic forgetting in continual learning.\nClosest to our setting, \\citet{gu2026sigma} proposed the SIGMA framework for spectral monitoring during recursive synthetic training, with validation on OPT-125M over short generation horizons.\nWe extend this direction along three axes: systematic tracking over 10 generations, validation at the 410M and 1B scale, and the connection from spectral indicators to closed-loop collapse prevention.\n\n\\paragraph{Data Mixing for LLM Training.}\nControlling training data composition is critical for language model quality.\nDoReMi~\\cite{xie2023doremi} trains a small proxy model to reweight domain mixtures before the main training run.\nData Mixing Laws~\\cite{ye2025mixinglaws, data_mixing_laws2024} predict optimal ratios from small-scale experiments so that mixture optimization does not require full-scale retraining.\nBoth paradigms determine ratios prior to training and hold them fixed throughout.\nOur adaptive controller differs fundamentally: it adjusts the real-synthetic mixing ratio online during recursive training, guided by real-time spectral feedback from the model's own representations rather than a priori proxy estimates.\n"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-17T20:58:47.355334+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections/related_work.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-17T20:58:47.355489+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections && echo \"=== em-dash ===\" && grep -n \"—\" related_work.tex; echo \"=== en-dash ===\" && grep -n \" – \" related_work.tex; echo \"=== -ing phrase endings ===\" && grep -n \"ing\\.$\" related_work.tex; echo \"=== leverage/utilize/facilitate ===\" && grep -ni \"leverage\\|utilize\\|facilitate\" related_work.tex; echo \"=== word count ===\" && wc -w related_work.tex",
  "description": "Check forbidden patterns and word count"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Bash",
  "tool_args": {
    "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper/sections && echo \"=== em-dash ===\" && grep -n \"—\" related_work.tex; echo \"=== en-dash ===\" && grep -n \" – \" related_work.tex; echo \"=== -ing phrase endings ===\" && grep -n \"ing\\.$\" related_work.tex; echo \"=== leverage/utilize/facilitate ===\" && grep -ni \"leverage\\|utilize\\|facilitate\" related_work.tex; echo \"=== word count ===\" && wc -w related_work.tex",
    "description": "Check forbidden patterns and word count"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-17T20:58:47.355674+00:00_

=== em-dash ===
=== en-dash ===
=== -ing phrase endings ===
15:In training dynamics, \citet{he2025spectral} linked spectral collapse of representation covariance matrices to catastrophic forgetting in continual learning.
22:Data Mixing Laws~\cite{ye2025mixinglaws, data_mixing_laws2024} predict optimal ratios from small-scale experiments so that mixture optimization does not require full-scale retraining.
=== leverage/utilize/facilitate ===
=== word count ===
355 related_work.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-17T20:58:47.355856+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper && for key in shumailov2024collapse dohmatob2024tails dohmatob2025strong alemohammad2024mad gerstgrasser2024inevitable martin2021implicit roy2007effectiverank rankme2023 he2025spectral gu2026sigma xie2023doremi ye2025mixinglaws data_mixing_laws2024; do if grep -q \"@.*{${key},\" references.bib; then echo \"OK: $key\"; else echo \"MISSING: $key\"; fi; done",
  "description": "Verify all citation keys exist in references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Bash",
  "tool_args": {
    "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0513_5/projects/spectral_collapse_ews/paper && for key in shumailov2024collapse dohmatob2024tails dohmatob2025strong alemohammad2024mad gerstgrasser2024inevitable martin2021implicit roy2007effectiverank rankme2023 he2025spectral gu2026sigma xie2023doremi ye2025mixinglaws data_mixing_laws2024; do if grep -q \"@.*{${key},\" references.bib; then echo \"OK: $key\"; else echo \"MISSING: $key\"; fi; done",
    "description": "Verify all citation keys exist in references.bib"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-17T20:58:47.355987+00:00_

OK: shumailov2024collapse
OK: dohmatob2024tails
OK: dohmatob2025strong
OK: alemohammad2024mad
OK: gerstgrasser2024inevitable
OK: martin2021implicit
OK: roy2007effectiverank
OK: rankme2023
OK: he2025spectral
OK: gu2026sigma
OK: xie2023doremi
OK: ye2025mixinglaws
OK: data_mixing_laws2024

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260517T205658",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 21 · 2026-05-17T20:58:47.356133+00:00_

All 13 citation keys verified. 

Related Work written to `paper/sections/related_work.tex`. Three paragraph groups (~355 words total): Model Collapse (7 citations, positioning our spectral approach), Spectral Analysis of Representations (5 citations, extending SIGMA along scale/generations/closed-loop), Data Mixing for LLM Training (3 citations, contrasting fixed a priori methods with our online spectral-guided controller).

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_related_work_20260517T205658"
}
```

</details>

---
