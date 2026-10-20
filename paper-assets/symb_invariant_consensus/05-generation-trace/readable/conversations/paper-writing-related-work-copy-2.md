# paper writing related work

**Beyond Self-Consistency: Self-Extracted Constraints Reduce to Majority Voting under Zero-Shot Extraction** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 29
- **Recorded user turns:** 0
- **Tool calls:** 14
- **Original source:** `logs/chats/worker_paper_writing_related_work_20260519T043455.jsonl`
- **Structured JSON:** [`42675d495091703b2575.json`](../../sessions/42/42675d495091703b2575.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

29 recorded events

### Tool call

_source line 1 · 2026-05-19T04:38:05.126855+00:00_

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
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-19T04:38:05.127416+00:00_

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
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-19T04:38:05.127607+00:00_

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
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-19T04:38:05.127992+00:00_

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
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-19T04:38:05.128180+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/references.bib"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-19T04:38:05.128413+00:00_

1	% References for SICA Capability Trap paper
2	% Generated from literature_map.yaml — 2026-05-17
3	
4	%%% Theoretical Foundations %%%
5	
6	@book{condorcet1785,
7	  title={Essai sur l'application de l'analyse \`a la probabilit\'e des d\'ecisions rendues \`a la pluralit\'e des voix},
8	  author={de Condorcet, Marie Jean Antoine Nicolas de Caritat},
9	  year={1785},
10	  publisher={Imprimerie Royale},
11	  address={Paris}
12	}
13	
14	@article{austensmith1996,
15	  title={Information Aggregation, Rationality, and the {C}ondorcet Jury Theorem},
16	  author={Austen-Smith, David and Banks, Jeffrey S.},
17	  journal={American Political Science Review},
18	  volume={90},
19	  number={1},
20	  pages={34--45},
21	  year={1996}
22	}
23	
24	@article{ladha1992correlated,
25	  title={The {C}ondorcet Jury Theorem, Free Speech, and Correlated Votes},
26	  author={Ladha, Krishna K.},
27	  journal={American Journal of Political Science},
28	  volume={36},
29	  number={3},
30	  pages={617--634},
31	  year={1992}
32	}
33	
34	@article{fleiss1971kappa,
35	  title={Measuring Nominal Scale Agreement Among Many Raters},
36	  author={Fleiss, Joseph L.},
37	  journal={Psychological Bulletin},
38	  volume={76},
39	  number={5},
40	  pages={378--382},
41	  year={1971}
42	}
43	
44	%%% Self-Consistency and Variants %%%
45	
46	@inproceedings{wang2023sc,
47	  title={Self-Consistency Improves Chain of Thought Reasoning in Language Models},
48	  author={Wang, Xuezhi and Wei, Jason and Schuurmans, Dale and Le, Quoc and Chi, Ed and Narang, Sharan and Chowdhery, Aakanksha and Zhou, Denny},
49	  booktitle={ICLR},
50	  year={2023}
51	}
52	
53	@inproceedings{chen2024usc,
54	  title={Universal Self-Consistency for Large Language Model Generation},
55	  author={Chen, Xinyun and Aksitov, Renat and Alon, Uri and Ren, Jie and Xiao, Kefan and Yin, Pengcheng and Prakash, Sushant and Sutton, Charles and Wang, Xuezhi and Zhou, Denny},
56	  booktitle={ICML},
57	  year={2024}
58	}
59	
60	@inproceedings{taubenfeld2025
…[truncated 14449 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-19T04:38:05.128687+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Glob",
  "tool_args": {
    "pattern": "**/*.tex",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-19T04:38:05.128925+00:00_

docs/paper/limitations_content.tex
docs/paper/related_work.tex
docs/paper/appendix.tex
docs/paper/abstract.tex
docs/paper/discussion.tex
docs/paper/conclusion.tex
docs/paper/introduction.tex
docs/paper/main.tex
docs/paper/experiments.tex
docs/paper/method.tex
docs/paper/analysis.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-19T04:38:05.129178+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-19T04:38:05.129425+00:00_

1	\section{Related Work}
2	\label{sec:related-work}
3	
4	\paragraph{Self-Consistency, Scaling, and Test-Time Compute.}
5	Self-Consistency (SC) selects the most frequent answer from multiple sampled chain-of-thought traces \citep{wang2023sc}. Extensions include Universal SC for free-form generation \citep{chen2024usc}, confidence-weighted voting \citep{taubenfeld2025cisc}, and diverse prompting with step-aware verification \citep{li2023diverse}. Scaling plateaus limit the returns from additional traces \citep{loo2025reevaluating}, motivating richer aggregation mechanisms. In parallel, test-time compute scaling has emerged as an alternative to parameter scaling \citep{snell2025scaling}, and reasoning-specialized models such as DeepSeek-R1 \citep{guo2025deepseekr1} internalize extended chain-of-thought through reinforcement learning. Diversity-aware training explicitly optimizes trace diversity \citep{diverseaware2026}. These developments interact with our findings through the $C_0$ diagnostic: reasoning models produce highly consistent outputs (QwQ-32B achieves $C_0 = 2.6\%$), reducing any aggregation method to the unanimous output. SICA replaces plurality voting with symbolic constraint satisfaction over self-extracted FOL formulas. Our results show this is regime-dependent: self-extracted constraints provide gains when SC $\leq$ 55\% but become non-discriminative above approximately 63\%.
6	
7	\paragraph{Neuro-Symbolic Reasoning and Constraint Satisfaction.}
8	A growing line of work combines LLMs with symbolic solvers. Logic-LM \citep{pan2023logiclm} and LINC \citep{olausson2023linc} delegate solving to external provers; DyLoS \citep{xu2026dylos}, Aristotle \citep{li2025aristotle}, FoVer \citep{wang2025fover}, and LogicAgent \citep{luo2025logicagent} push this integration further through multi-paradigm solvers, trained verifiers, or semiotic grounding. All introduce knowledge beyond the reasoning model itself. SICA instead asks whether the same model can extract use
…[truncated 2672 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-19T04:38:05.129681+00:00_

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
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-19T04:38:05.129957+00:00_

1	\section{Introduction}\label{sec:introduction}
2	
3	Scaling test-time computation has emerged as a key strategy for improving large language model (LLM) reasoning \citep{snell2025scaling}. Majority voting over multiple chain-of-thought samples, known as Self-Consistency (SC) \citep{wang2023sc}, remains the dominant aggregation method but faces diminishing returns from additional traces \citep{loo2025reevaluating}. Verification-based approaches that extract richer signal from reasoning traces offer a path to break this plateau. Symbolic verification through formal constraints and satisfiability solvers is one such direction, as it provides logical guarantees that natural language self-critique lacks \citep{huang2024selfcorrect}.
4	
5	Neuro-symbolic methods that augment LLM reasoning with formal solvers have demonstrated gains on logical reasoning benchmarks. Logic-LM \citep{pan2023logiclm} and LINC \citep{olausson2023linc} delegate formalization to external provers. More recent systems route problems to specialized solver paradigms \citep{xu2026dylos}, apply logic-complete decomposition \citep{li2025aristotle}, train dedicated first-order logic (FOL) verifiers on supervised data \citep{wang2025fover}, or employ multi-perspective grounding \citep{luo2025logicagent}. These systems report positive results, but each introduces capabilities beyond the reasoning model itself: trained verifiers, multi-paradigm solver selection, or external knowledge bases. The external machinery is effective but imposes practical costs in training data, integration complexity, and domain-specific engineering.
6	
7	These results raise a direct question: can the reasoning model itself extract useful formal constraints from its own traces, and if so, under what conditions? Same-model self-extraction would require no training data, no external prover, and no second model. Practitioners could augment any LLM with symbolic verification by adding a single extraction prompt and a satisfiability s
…[truncated 4616 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-19T04:38:05.130194+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex",
  "limit": "60"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/method.tex",
    "limit": "60"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-19T04:38:05.130466+00:00_

1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Self-Consistency and the Condorcet Independence Assumption}
5	\label{sec:condorcet}
6	
7	Self-Consistency (SC) \citep{wang2023sc} samples $K$ reasoning traces from a language model and selects the answer by majority vote: $a^* = \arg\max_{a} \sum_{i=1}^{K} \mathbf{1}[a_i = a]$. The theoretical justification for this approach follows the Condorcet Jury Theorem (CJT) \citep{condorcet1785}: given $K$ independent voters each correct with probability $p > 0.5$, the probability that the majority is correct approaches 1 as $K \to \infty$ \citep{austensmith1996}.
8	
9	CJT requires that voters be conditionally independent given the correct answer. LLM traces violate this assumption: all $K$ samples come from the same model, conditioned on the same prompt, with only sampling temperature as a source of variation. Correlated voters reduce the effective ensemble size. \citet{ladha1992correlated} show that under uniform pairwise correlation $\rho$, the effective number of independent voters is $K_{\text{eff}} = K / (1 + (K{-}1)\rho)$. We use Fleiss' $\kappa$ \citep{fleiss1971kappa} as an empirical proxy for inter-trace agreement:
10	\begin{equation}
11	\label{eq:effk}
12	K_{\text{eff}} = \frac{K}{1 + (K - 1) \cdot \kappa}.
13	\end{equation}
14	
15	In our experiments (\S\ref{sec:effective-k}), $\kappa$ ranges from 0.21 to 0.82 across model-dataset pairs, yielding $K_{\text{eff}} \approx 1.2\text{--}3.6$ for $K = 12$. At $K_{\text{eff}} \approx 1$, additional traces provide almost no new information, and the CJT guarantee collapses. This \emph{independence bottleneck} motivates our investigation: can structured constraint extraction recover discriminative signal that majority voting cannot?
16	
17	\subsection{SICA Pipeline}
18	\label{sec:pipeline}
19	
20	Symbolic Invariant Consensus Aggregation (SICA) extends SC by extracting formal constraints from reasoning traces and selecting the answer best supported by the satisfiable s
…[truncated 5302 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-19T04:38:05.130806+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex",
  "limit": "30"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/analysis.tex",
    "limit": "30"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-19T04:38:05.131088+00:00_

1	\section{Analysis}
2	\label{sec:analysis}
3	
4	The regime-dependent pattern in \S\ref{sec:main-results} and the failure modes in \S\ref{sec:failure-modes} establish \emph{where} SICA succeeds and fails. This section investigates \emph{why}, through six quantitative lenses: trace correlation (\S\ref{sec:effective-k}), extraction quality (\S\ref{sec:extraction-taxonomy}), hyperparameter sensitivity (\S\ref{sec:k-sensitivity}, \S\ref{sec:t-sensitivity}), the entropy structure of gains (\S\ref{sec:entropy}), solver contribution (\S\ref{sec:ablation}), and remediation failure (\S\ref{sec:remediation}).
5	
6	\subsection{Condorcet Effective-K}
7	\label{sec:effective-k}
8	
9	Table~\ref{tab:independence} reports Fleiss' $\kappa$ and the resulting Effective-K (Eq.~\ref{eq:effk}) across model-dataset conditions with $K = 12$ traces. $\kappa$ ranges from 0.21 to 0.82, and the resulting $K_{\text{eff}}$ spans $1.20\text{--}3.63$. The strongest model-dataset pair (Qwen2.5-14B on LogiQA, $\kappa = 0.82$) retains $K_{\text{eff}} = 1.20$: twelve traces carry barely more information than a single sample. Mistral-7B on FOLIO produces moderate agreement ($\kappa = 0.50$ for seed 42, $K_{\text{eff}} = 1.85$), consistent with its position in the Goldilocks zone. Mistral-7B on ProofWriter has the lowest agreement ($\kappa = 0.21$, $K_{\text{eff}} = 3.63$), yet SICA hurts ($\Delta = -2.83$\,pp) because trace quality is too low (SC $= 39.33\%$). High $K_{\text{eff}}$ alone does not guarantee improvement; the model must also produce sufficiently accurate traces. Qwen2.5-14B on FOLIO reaches 58.3\% unanimous problems and 63.0\% on LogiQA; Mistral-7B on FOLIO has only 14.2\%. Unanimous problems leave zero room for constraint-based reranking, and models with high unanimity rates offer SICA a vanishingly small operating window.
10	
11	\begin{table}[t]
12	\centering
13	\small
14	\caption{Trace independence metrics ($K = 12$). $\kappa$: Fleiss' Kappa. $K_{\text{eff}}$: Effective-K (Eq.~\ref{eq:e
…[truncated 894 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-19T04:38:05.131396+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex",
  "content": "\\section{Related Work}\n\\label{sec:related-work}\n\n\\paragraph{Self-Consistency and Extensions.}\nSelf-Consistency (SC) selects the most frequent answer across multiple chain-of-thought traces \\citep{wang2023sc}. Universal SC extends this to free-form generation by using an LLM to select among diverse candidates \\citep{chen2024usc}. Confidence-weighted variants assign non-uniform weights to traces \\citep{taubenfeld2025cisc}, and DiVeRSe combines diverse prompts with a step-aware verifier \\citep{li2023diverse}. Reasoning-aware sampling refines SC further by using textual quality indicators \\citep{wan2024rasc} or evidence sufficiency \\citep{kim2026reasc} to filter traces without training a separate model. \\citet{loo2025reevaluating} show that SC gains plateau early and decline for strong models. Our Condorcet analysis explains this pattern: same-model traces yield Fleiss' $\\kappa$ of 0.21--0.82, compressing $K_{\\text{eff}}$ to 1.2--3.6 for $K = 12$ (\\S\\ref{sec:effective-k}). SICA shares SC's sampling setup but replaces majority voting with MAX-SAT aggregation over symbolic constraints. The substitution is regime-dependent: self-extracted constraints provide gains only when SC accuracy falls in a narrow band (${\\sim}$50--55\\%).\n\n\\paragraph{Neuro-Symbolic Reasoning.}\nLogic-LM \\citep{pan2023logiclm} translates natural language problems into first-order logic (FOL) and delegates solving to an external prover. LINC \\citep{olausson2023linc} follows a similar pipeline but documents ${\\sim}$40\\% translation errors on FOLIO. More recent systems extend this integration: DyLoS \\citep{xu2026dylos} adaptively selects solver types, Aristotle \\citep{li2025aristotle} applies logic-complete decomposition, FoVer \\citep{wang2025fover} trains dedicated FOL verifiers, and LogicAgent \\citep{luo2025logicagent} employs multi-perspective grounding. Each introduces capabilities beyond the reasoning model itself, whether through trained extractors, external provers, or multi-component pipelines. \\citet{amonkar2025realitycheck} show that LLM formalization quality degrades with problem complexity, consistent with our extraction-quality findings. SICA asks whether the \\emph{same} model can extract useful constraints from its own traces without additional machinery. Our oracle controls ($+14.22$\\,pp on FOLIO, $+11.50$\\,pp on ProofWriter; \\S\\ref{sec:oracle-design}) confirm the aggregation mechanism is sound when constraints are discriminative; the failure localizes to self-extraction quality, not the symbolic approach. This oracle-replacement methodology follows \\citet{press2023compositionality}, who use oracle sub-questions to isolate pipeline bottlenecks.\n\n\\paragraph{Test-Time Compute and Trace Diversity.}\nScaling test-time computation through additional reasoning traces offers an alternative to parameter scaling \\citep{snell2025scaling}. Reasoning-specialized models such as DeepSeek-R1 \\citep{guo2025deepseekr1} internalize extended chain-of-thought through reinforcement learning, and diversity-aware training explicitly optimizes for trace variety at test time \\citep{diverseaware2026}. These approaches share a common challenge: independent reasoning attempts from the same model collapse into correlated solutions. Our Condorcet/$K_{\\text{eff}}$ analysis (\\S\\ref{sec:condorcet}) provides a theoretical framework for this collapse. Same-model sampling creates correlated voters, and the effective ensemble size $K_{\\text{eff}}$ is bounded by inter-trace agreement regardless of how many traces $K$ are sampled. Reasoning models intensify this problem: QwQ-32B achieves a multi-candidate rate $C_0$ of only 2.6\\%, reducing any aggregation method to the unanimous output.\n\n\\paragraph{Verification and Reranking.}\nTrained verifiers offer a data-driven alternative to self-extraction. Outcome reward models (ORMs) score complete solutions \\citep{cobbe2021gsm8k}, process reward models (PRMs) assign step-level scores and outperform outcome-level verification \\citep{lightman2024prm}, and Math-Shepherd automates process supervision without human annotations \\citep{wang2024mathshepherd}. Multi-agent debate refines answers through iterative natural-language discussion \\citep{liang2023encouraging,du2023improving}, a paradigm distinct from SICA's one-shot symbolic aggregation. Self-correction methods attempt refinement without external feedback \\citep{huang2024selfcorrect,madaan2023selfrefine}, but \\citet{stechly2025selfverification} show that LLM self-verification degrades performance while sound external verification yields gains. Their finding parallels our capability trap in the high-accuracy regime. Both trained verifiers and SICA face extraction-quality challenges, but trained approaches may prove more robust because they learn discriminative patterns from data rather than relying on the same model's symbolic capabilities. The consistent pattern across this literature is that reliably improving on majority voting requires information beyond the reasoning model's own outputs (\\S\\ref{sec:remediation}).\n\n\\paragraph{Condorcet Jury Theorem and Ensemble Diversity.}\nThe Condorcet Jury Theorem (CJT) \\citep{condorcet1785} establishes that majority voting among independent voters, each correct with probability $p > 0.5$, converges to correctness as the number of voters grows. \\citet{austensmith1996} extend this result to information aggregation under strategic conditions. \\citet{ladha1992correlated} prove that correlated voters reduce the effective ensemble size, a result we operationalize as $K_{\\text{eff}} = K / (1 + (K{-}1) \\cdot \\kappa)$ in \\S\\ref{sec:condorcet}. \\citet{lefort2024condorcet_llm} apply the CJT framework to LLM ensemble sentiment classification and document independence violations when all ensemble members share the same architecture. We extend this line of work to reasoning-trace aggregation, measuring $\\kappa$ and $K_{\\text{eff}}$ across 10 model-dataset conditions (\\S\\ref{sec:effective-k}). Fleiss' $\\kappa$ \\citep{fleiss1971kappa} serves as our inter-rater agreement metric, connecting the voting-theory framework to a concrete diagnostic for when symbolic aggregation can improve over majority voting.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex",
    "content": "\\section{Related Work}\n\\label{sec:related-work}\n\n\\paragraph{Self-Consistency and Extensions.}\nSelf-Consistency (SC) selects the most frequent answer across multiple chain-of-thought traces \\citep{wang2023sc}. Universal SC extends this to free-form generation by using an LLM to select among diverse candidates \\citep{chen2024usc}. Confidence-weighted variants assign non-uniform weights to traces \\citep{taubenfeld2025cisc}, and DiVeRSe combines diverse prompts with a step-aware verifier \\citep{li2023diverse}. Reasoning-aware sampling refines SC further by using textual quality indicators \\citep{wan2024rasc} or evidence sufficiency \\citep{kim2026reasc} to filter traces without training a separate model. \\citet{loo2025reevaluating} show that SC gains plateau early and decline for strong models. Our Condorcet analysis explains this pattern: same-model traces yield Fleiss' $\\kappa$ of 0.21--0.82, compressing $K_{\\text{eff}}$ to 1.2--3.6 for $K = 12$ (\\S\\ref{sec:effective-k}). SICA shares SC's sampling setup but replaces majority voting with MAX-SAT aggregation over symbolic constraints. The substitution is regime-dependent: self-extracted constraints provide gains only when SC accuracy falls in a narrow band (${\\sim}$50--55\\%).\n\n\\paragraph{Neuro-Symbolic Reasoning.}\nLogic-LM \\citep{pan2023logiclm} translates natural language problems into first-order logic (FOL) and delegates solving to an external prover. LINC \\citep{olausson2023linc} follows a similar pipeline but documents ${\\sim}$40\\% translation errors on FOLIO. More recent systems extend this integration: DyLoS \\citep{xu2026dylos} adaptively selects solver types, Aristotle \\citep{li2025aristotle} applies logic-complete decomposition, FoVer \\citep{wang2025fover} trains dedicated FOL verifiers, and LogicAgent \\citep{luo2025logicagent} employs multi-perspective grounding. Each introduces capabilities beyond the reasoning model itself, whether through trained extractors, external provers, or multi-component pipelines. \\citet{amonkar2025realitycheck} show that LLM formalization quality degrades with problem complexity, consistent with our extraction-quality findings. SICA asks whether the \\emph{same} model can extract useful constraints from its own traces without additional machinery. Our oracle controls ($+14.22$\\,pp on FOLIO, $+11.50$\\,pp on ProofWriter; \\S\\ref{sec:oracle-design}) confirm the aggregation mechanism is sound when constraints are discriminative; the failure localizes to self-extraction quality, not the symbolic approach. This oracle-replacement methodology follows \\citet{press2023compositionality}, who use oracle sub-questions to isolate pipeline bottlenecks.\n\n\\paragraph{Test-Time Compute and Trace Diversity.}\nScaling test-time computation through additional reasoning traces offers an alternative to parameter scaling \\citep{snell2025scaling}. Reasoning-specialized models such as DeepSeek-R1 \\citep{guo2025deepseekr1} internalize extended chain-of-thought through reinforcement learning, and diversity-aware training explicitly optimizes for trace variety at test time \\citep{diverseaware2026}. These approaches share a common challenge: independent reasoning attempts from the same model collapse into correlated solutions. Our Condorcet/$K_{\\text{eff}}$ analysis (\\S\\ref{sec:condorcet}) provides a theoretical framework for this collapse. Same-model sampling creates correlated voters, and the effective ensemble size $K_{\\text{eff}}$ is bounded by inter-trace agreement regardless of how many traces $K$ are sampled. Reasoning models intensify this problem: QwQ-32B achieves a multi-candidate rate $C_0$ of only 2.6\\%, reducing any aggregation method to the unanimous output.\n\n\\paragraph{Verification and Reranking.}\nTrained verifiers offer a data-driven alternative to self-extraction. Outcome reward models (ORMs) score complete solutions \\citep{cobbe2021gsm8k}, process reward models (PRMs) assign step-level scores and outperform outcome-level verification \\citep{lightman2024prm}, and Math-Shepherd automates process supervision without human annotations \\citep{wang2024mathshepherd}. Multi-agent debate refines answers through iterative natural-language discussion \\citep{liang2023encouraging,du2023improving}, a paradigm distinct from SICA's one-shot symbolic aggregation. Self-correction methods attempt refinement without external feedback \\citep{huang2024selfcorrect,madaan2023selfrefine}, but \\citet{stechly2025selfverification} show that LLM self-verification degrades performance while sound external verification yields gains. Their finding parallels our capability trap in the high-accuracy regime. Both trained verifiers and SICA face extraction-quality challenges, but trained approaches may prove more robust because they learn discriminative patterns from data rather than relying on the same model's symbolic capabilities. The consistent pattern across this literature is that reliably improving on majority voting requires information beyond the reasoning model's own outputs (\\S\\ref{sec:remediation}).\n\n\\paragraph{Condorcet Jury Theorem and Ensemble Diversity.}\nThe Condorcet Jury Theorem (CJT) \\citep{condorcet1785} establishes that majority voting among independent voters, each correct with probability $p > 0.5$, converges to correctness as the number of voters grows. \\citet{austensmith1996} extend this result to information aggregation under strategic conditions. \\citet{ladha1992correlated} prove that correlated voters reduce the effective ensemble size, a result we operationalize as $K_{\\text{eff}} = K / (1 + (K{-}1) \\cdot \\kappa)$ in \\S\\ref{sec:condorcet}. \\citet{lefort2024condorcet_llm} apply the CJT framework to LLM ensemble sentiment classification and document independence violations when all ensemble members share the same architecture. We extend this line of work to reasoning-trace aggregation, measuring $\\kappa$ and $K_{\\text{eff}}$ across 10 model-dataset conditions (\\S\\ref{sec:effective-k}). Fleiss' $\\kappa$ \\citep{fleiss1971kappa} serves as our inter-rater agreement metric, connecting the voting-theory framework to a concrete diagnostic for when symbolic aggregation can improve over majority voting.\n"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-19T04:38:05.131771+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-19T04:38:05.132040+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "—",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Grep",
  "tool_args": {
    "pattern": "—",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-19T04:38:05.132247+00:00_

No matches found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-19T04:38:05.132444+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": " – ",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Grep",
  "tool_args": {
    "pattern": " – ",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-19T04:38:05.132635+00:00_

No matches found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-19T04:38:05.132818+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "ing[,.]",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Grep",
  "tool_args": {
    "pattern": "ing[,.]",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex",
    "output_mode": "content"
  }
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-19T04:38:05.133031+00:00_

7:\paragraph{Neuro-Symbolic Reasoning.}
8:[Omitted long matching line]
11:[Omitted long matching line]
13:\paragraph{Verification and Reranking.}
14:[Omitted long matching line]
17:[Omitted long matching line]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-19T04:38:05.133218+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "ing[,.]",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex",
  "output_mode": "content",
  "-n": "True"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Grep",
  "tool_args": {
    "pattern": "ing[,.]",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex",
    "output_mode": "content",
    "-n": "True"
  }
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-19T04:38:05.133411+00:00_

7:\paragraph{Neuro-Symbolic Reasoning.}
8:[Omitted long matching line]
11:[Omitted long matching line]
13:\paragraph{Verification and Reranking.}
14:[Omitted long matching line]
17:[Omitted long matching line]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-19T04:38:05.133621+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_3/projects/symb_invariant_consensus/docs/paper/related_work.tex"
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-19T04:38:05.133856+00:00_

1	\section{Related Work}
2	\label{sec:related-work}
3	
4	\paragraph{Self-Consistency and Extensions.}
5	Self-Consistency (SC) selects the most frequent answer across multiple chain-of-thought traces \citep{wang2023sc}. Universal SC extends this to free-form generation by using an LLM to select among diverse candidates \citep{chen2024usc}. Confidence-weighted variants assign non-uniform weights to traces \citep{taubenfeld2025cisc}, and DiVeRSe combines diverse prompts with a step-aware verifier \citep{li2023diverse}. Reasoning-aware sampling refines SC further by using textual quality indicators \citep{wan2024rasc} or evidence sufficiency \citep{kim2026reasc} to filter traces without training a separate model. \citet{loo2025reevaluating} show that SC gains plateau early and decline for strong models. Our Condorcet analysis explains this pattern: same-model traces yield Fleiss' $\kappa$ of 0.21--0.82, compressing $K_{\text{eff}}$ to 1.2--3.6 for $K = 12$ (\S\ref{sec:effective-k}). SICA shares SC's sampling setup but replaces majority voting with MAX-SAT aggregation over symbolic constraints. The substitution is regime-dependent: self-extracted constraints provide gains only when SC accuracy falls in a narrow band (${\sim}$50--55\%).
6	
7	\paragraph{Neuro-Symbolic Reasoning.}
8	Logic-LM \citep{pan2023logiclm} translates natural language problems into first-order logic (FOL) and delegates solving to an external prover. LINC \citep{olausson2023linc} follows a similar pipeline but documents ${\sim}$40\% translation errors on FOLIO. More recent systems extend this integration: DyLoS \citep{xu2026dylos} adaptively selects solver types, Aristotle \citep{li2025aristotle} applies logic-complete decomposition, FoVer \citep{wang2025fover} trains dedicated FOL verifiers, and LogicAgent \citep{luo2025logicagent} employs multi-perspective grounding. Each introduces capabilities beyond the reasoning model itself, whether through trained extractors, external provers, or multi-compone
…[truncated 4216 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_20260519T043455",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 29 · 2026-05-19T04:38:05.134150+00:00_

The `ing,`/`ing.` matches are all nouns in titles or noun phrases ("Reasoning.", "Reranking.", "grounding."), not participial clause endings. No style violations.

Written `related_work.tex` with 5 clusters (~630 words, well under 800 budget), 25 citations all verified against `references.bib`. Each paragraph ends with clear positioning against SICA. Cross-references to `\S\ref{sec:effective-k}`, `\S\ref{sec:oracle-design}`, `\S\ref{sec:condorcet}`, and `\S\ref{sec:remediation}` match the existing section labels.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_related_work_20260519T043455"
}
```

</details>

---
