# paper writing related work reframe

**Characterizing the Detectability Landscape of Iterative Model Collapse** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 17
- **Recorded user turns:** 0
- **Tool calls:** 8
- **Original source:** `logs/chats/worker_paper_writing_related_work_reframe_20260520T121501.jsonl`
- **Structured JSON:** [`967a3c46d47c9702298a.json`](../../sessions/96/967a3c46d47c9702298a.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

17 recorded events

### Tool call

_source line 1 · 2026-05-20T12:17:35.630709+00:00_

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
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-20T12:17:35.631767+00:00_

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
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Read",
  "elapsed_ms": 1
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-20T12:17:35.632160+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work.tex"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-20T12:17:35.632617+00:00_

1	\section{Related Work}
2	\label{sec:related_work}
3	
4	\paragraph{Model collapse in iterative training.}
5	
6	The phenomenon of iterative training collapse was formalized by \citet{shumailov2024curse}, who showed that recursively replacing real data with model-generated text causes progressive tail erosion across VAEs, GMMs, and language models, and by \citet{alemohammad2024mad}, who demonstrated quality--diversity tradeoffs in self-consuming generative loops for image models.
7	Theoretical analyses have since sharpened these results: \citet{dohmatob2024tale} recast collapse as a change in scaling-law exponents, showing that even small fractions of synthetic data alter effective scaling behavior, while \citet{dohmatob2025strong} proved that collapse can occur even when synthetic data constitutes a vanishingly small fraction of the training set.
8	\citet{hataya2023will} provided early empirical evidence that large-scale generative models degrade future datasets through web-scale contamination, showing that even state-of-the-art models produce training-data artifacts detectable in downstream models, a finding that motivates our focus on contamination-level-dependent analysis.
9	\citet{seddik2024bad} formalized the statistical analysis of training on synthetic data, deriving excess risk bounds that quantify how synthetic fraction and model misspecification jointly govern degradation; their framework predicts regime-dependent behavior consistent with the onset boundary we observe empirically at $\alpha{\approx}0.45$--$0.50$.
10	The role of data accumulation has been a central theme.
11	\citet{dey2024breaking} proved that accumulating data across generations (rather than replacing it) prevents divergence of population risk in GMMs, HMMs, and language models.
12	\citet{kazdan2025collapse} systematically compared replace and accumulate regimes, finding that synthetic data value depends on the absolute quantity of co-present real data.
13	\citet{fu2025selfconsuming} provi
…[truncated 13191 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-20T12:17:35.632930+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-20T12:17:35.633286+00:00_

1	\section{Introduction}
2	\label{sec:introduction}
3	
4	When language models train iteratively on their own output, the training distribution progressively loses its tail modes, a phenomenon termed model collapse~\cite{shumailov2024curse,alemohammad2024mad}.
5	Lexical diversity narrows, calibration deteriorates, and each generation inherits the systematic biases of its predecessors.
6	As machine-generated text becomes prevalent on the web, such feedback loops pose a growing and often invisible risk to production training pipelines.
7	By the time standard quality metrics register degradation, the underlying distribution may have already shifted irreversibly.
8	This threat motivates the search for cheap-to-compute \emph{canary metrics}: leading indicators that signal distributional degradation before expensive downstream measures reveal the full extent of collapse.
9	The concept parallels early-warning signals for critical transitions in ecological systems~\cite{scheffer2009early,scheffer2012anticipating}, where proxy indicators allow intervention before a tipping point.
10	
11	Yet a fundamental question remains unanswered: \emph{at what contamination level does causal detection of collapse become possible?}
12	Whether a candidate canary genuinely \emph{precedes} downstream degradation or merely correlates with it under shared non-stationary trends depends on contamination regime and statistical method in ways that existing analyses leave unresolved.
13	Iterative training produces short, noisy time series (often fewer than 15 points per generation sequence), where detection power drops sharply and false positive rates can be high~\cite{boettiger2012limits}.
14	
15	We identify four deficiencies in existing lead-lag analyses of iterative training collapse.
16	(1)~No differencing tests rule out spurious regression from shared non-stationary trends~\cite{granger1974spurious}.
17	(2)~Conclusions rest on a single statistical method whose assumptions about stationarity and 
…[truncated 3691 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-20T12:17:35.633612+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/method.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-20T12:17:35.633961+00:00_

1	\section{Method}
2	\label{sec:method}
3	
4	\paragraph{Methodological pitfalls.}
5	\label{sec:pitfalls}
6	Lead-lag analysis in iterative model collapse is fragile along three axes, each documented with data from \S\ref{sec:regime}--\ref{sec:dose_response}.
7	\emph{Method sensitivity}: five detection methods applied to identical data ($\alpha{=}1.0$, 8 validated canary$\to$downstream pairs, direction-checked) yield forward significance rates spanning 0\% to 75\%, with inter-method agreement at $\kappa{=}0.185$ and naive cross-correlation reaching 75\% null-control FPR.
8	\emph{Spurious regression}: first-differencing to remove shared trends~\cite{granger1974spurious} eliminates canary$\to$perplexity associations ($F{\approx}0$, $p{=}0.99$) while preserving canary$\to$diversity (24/24$\to$24/24), exposing an entire analysis channel as trend-driven rather than temporally precedent.
9	\emph{Regime dependence}: the same Granger test finds 0/8 pairs significant through $\alpha{=}0.45$ but 6/8 at $\alpha{=}0.50$, a categorical shift at a 5-percentage-point boundary that a single-$\alpha$ study would miss entirely.
10	These pitfalls motivate systematic method comparison rather than reliance on any single detection approach.
11	
12	\paragraph{Multi-Method Consensus Test (MMCT).}
13	\label{sec:mmct}
14	We apply the Multi-Method Consensus Test, a weighted consensus framework in the specification curve~\cite{simonsohn2020specification} and multi-method early-warning~\cite{scheffer2009early,bell2022modeling} traditions, adapted to the constraints of iterative training analysis: short series ($T{=}5$--$20$), non-stationarity by design, and heterogeneous method sensitivities.
15	MMCT is a consensus testing protocol, not a novel statistical method.
16	It compares five lead-lag detection methods through FPR-inverse weighted consensus, calibrated against null-control ($\alpha{=}0.0$) data where any detection is a false positive.
17	Each method $m_k$ receives weight $w_k = 1/\max(\ha
…[truncated 5406 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-20T12:17:35.634507+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work_reframe.tex",
  "content": "\\section{Related Work}\n\\label{sec:related_work}\n\n\\paragraph{Model collapse and canary metrics.}\n\nIterative training collapse was formalized by \\citet{shumailov2024curse} for language models and by \\citet{alemohammad2024mad} for image generation, establishing that recursive self-training erodes tail modes and reduces output diversity.\nTheoretical analyses have since shown that even small synthetic fractions alter effective scaling-law exponents \\cite{dohmatob2024tale}.\nSeveral metrics have been proposed as early collapse indicators: calibration error \\cite{du2026geometric,du2025scales}, surplexity \\cite{gambetta2024surplexity}, spectral divergence \\cite{sigma2026spectral}, topological persistence \\cite{kalinowski2026topology}, and center-edge dynamics \\cite{dces2026counter}.\nYet none of these analyses apply differencing tests to rule out spurious co-trending, cross-validate across multiple statistical methods, or apply false discovery rate correction when testing multiple metric pairs.\n\n\\paragraph{Early-warning signals and lead-lag methodology.}\n\nThe concept of early-warning indicators originates in ecology, where \\citet{scheffer2009early} showed that systems approaching tipping points exhibit rising autocorrelation and variance independent of system-specific mechanisms.\n\\citet{boettiger2012limits} quantified the detection limits of such signals in short time series, a constraint directly relevant to iterative training where generation counts rarely exceed 20.\nGranger causality \\cite{granger1969investigating} provides the standard test for temporal precedence but produces spurious rejections on non-stationary series \\cite{granger1974spurious}; the Toda--Yamamoto procedure \\cite{toda1995statistical} restores valid inference at the cost of degrees of freedom \\cite{shojaie2022granger}, a severe trade-off when $T{\\leq}20$.\nYet these ecological and econometric tools have not been combined for model collapse; existing canary studies rely on visual inspection or naive correlation that cannot distinguish temporal precedence from shared trends.\n\n\\paragraph{Analytical robustness.}\n\nResearcher degrees of freedom in ML have received increasing attention through multiverse analysis \\cite{bell2022modeling}, many-analysts designs showing that independent teams reach divergent conclusions on identical data \\cite{coretta2023multidimensional}, and the REFORMS checklist \\cite{kapoor2024reforms}.\nOur work applies this perspective to collapse monitoring.\nWe differ from the closest predecessor \\cite{du2026geometric} in four respects: we compare an entire family of canary metrics rather than a single pair, cross-validate each relationship across five statistical methods, apply FDR correction across all tested pairs, and map detectability as a function of contamination regime.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work_reframe.tex",
    "content": "\\section{Related Work}\n\\label{sec:related_work}\n\n\\paragraph{Model collapse and canary metrics.}\n\nIterative training collapse was formalized by \\citet{shumailov2024curse} for language models and by \\citet{alemohammad2024mad} for image generation, establishing that recursive self-training erodes tail modes and reduces output diversity.\nTheoretical analyses have since shown that even small synthetic fractions alter effective scaling-law exponents \\cite{dohmatob2024tale}.\nSeveral metrics have been proposed as early collapse indicators: calibration error \\cite{du2026geometric,du2025scales}, surplexity \\cite{gambetta2024surplexity}, spectral divergence \\cite{sigma2026spectral}, topological persistence \\cite{kalinowski2026topology}, and center-edge dynamics \\cite{dces2026counter}.\nYet none of these analyses apply differencing tests to rule out spurious co-trending, cross-validate across multiple statistical methods, or apply false discovery rate correction when testing multiple metric pairs.\n\n\\paragraph{Early-warning signals and lead-lag methodology.}\n\nThe concept of early-warning indicators originates in ecology, where \\citet{scheffer2009early} showed that systems approaching tipping points exhibit rising autocorrelation and variance independent of system-specific mechanisms.\n\\citet{boettiger2012limits} quantified the detection limits of such signals in short time series, a constraint directly relevant to iterative training where generation counts rarely exceed 20.\nGranger causality \\cite{granger1969investigating} provides the standard test for temporal precedence but produces spurious rejections on non-stationary series \\cite{granger1974spurious}; the Toda--Yamamoto procedure \\cite{toda1995statistical} restores valid inference at the cost of degrees of freedom \\cite{shojaie2022granger}, a severe trade-off when $T{\\leq}20$.\nYet these ecological and econometric tools have not been combined for model collapse; existing canary studies rely on visual inspection or naive correlation that cannot distinguish temporal precedence from shared trends.\n\n\\paragraph{Analytical robustness.}\n\nResearcher degrees of freedom in ML have received increasing attention through multiverse analysis \\cite{bell2022modeling}, many-analysts designs showing that independent teams reach divergent conclusions on identical data \\cite{coretta2023multidimensional}, and the REFORMS checklist \\cite{kapoor2024reforms}.\nOur work applies this perspective to collapse monitoring.\nWe differ from the closest predecessor \\cite{du2026geometric} in four respects: we compare an entire family of canary metrics rather than a single pair, cross-validate each relationship across five statistical methods, apply FDR correction across all tested pairs, and map detectability as a function of contamination regime.\n"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-20T12:17:35.634823+00:00_

&lt;tool_use_error>File has not been read yet. Read it first before writing to it.&lt;/tool_use_error>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-20T12:17:35.635074+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work_reframe.tex 2>/dev/null; echo \"EXIT:$?\"",
  "description": "Check if staging file exists"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Bash",
  "tool_args": {
    "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work_reframe.tex 2>/dev/null; echo \"EXIT:$?\"",
    "description": "Check if staging file exists"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-20T12:17:35.635341+00:00_

/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work_reframe.tex
EXIT:0

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-20T12:17:35.635603+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work_reframe.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work_reframe.tex"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-20T12:17:35.635895+00:00_

1	\section{Related Work}
2	\label{sec:related_work}
3	
4	\paragraph{Model collapse and canary metrics.}
5	Iterative training collapse was formalized by \citet{shumailov2024curse} and \citet{alemohammad2024mad}, who showed that recursively replacing real data with model-generated text causes progressive tail erosion.
6	Theoretical analyses have sharpened these results: \citet{dohmatob2024tale} recast collapse as a change in scaling-law exponents, and \citet{dohmatob2025strong} proved that collapse can occur even when synthetic data constitutes a vanishingly small fraction of the training set.
7	Several works have since proposed monitoring metrics that precede or accompany degradation: \citet{du2026geometric} observe that calibration error rises before accuracy degrades; \citet{du2025scales} report ECE increases of 75\% at 30\% synthetic contamination before accuracy drops; and \citet{gambetta2024surplexity} introduces surplexity as a simultaneous collapse detector and data filter.
8	Other approaches track spectral divergence~\cite{sigma2026spectral}, topological features~\cite{kalinowski2026topology}, or center-edge sampling dynamics~\cite{dces2026counter}.
9	Yet none of these canary studies apply differencing tests to distinguish genuine temporal precedence from spurious co-trending, cross-validate across multiple statistical methods, or correct for false discovery rate when testing multiple metric pairs.
10	
11	\paragraph{Early-warning signals and lead-lag methodology.}
12	The theoretical foundation for canary-based prediction originates in ecology: \citet{scheffer2009early} established that systems approaching tipping points exhibit generic early-warning signals, while \citet{boettiger2012limits} quantified detection limits in short time series---a constraint directly relevant to iterative training, where generation counts ($T{=}5$--$20$) are far smaller than typical ecological datasets.
13	The standard econometric framework for testing temporal precedence is Gran
…[truncated 1464 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-20T12:17:35.636442+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work_reframe.tex",
  "content": "\\section{Related Work}\n\\label{sec:related_work}\n\n\\paragraph{Model collapse and canary metrics.}\n\nIterative training collapse was formalized by \\citet{shumailov2024curse} for language models and by \\citet{alemohammad2024mad} for image generation, establishing that recursive self-training erodes tail modes and reduces output diversity.\nTheoretical analyses have since shown that even small synthetic fractions alter effective scaling-law exponents \\cite{dohmatob2024tale}.\nSeveral metrics have been proposed as early collapse indicators: calibration error \\cite{du2026geometric,du2025scales}, surplexity \\cite{gambetta2024surplexity}, spectral divergence \\cite{sigma2026spectral}, topological persistence \\cite{kalinowski2026topology}, and center-edge dynamics \\cite{dces2026counter}.\nYet none of these analyses apply differencing tests to rule out spurious co-trending, cross-validate across multiple statistical methods, or apply false discovery rate correction when testing multiple metric pairs.\n\n\\paragraph{Early-warning signals and lead-lag methodology.}\n\nThe concept of early-warning indicators originates in ecology, where \\citet{scheffer2009early} showed that systems approaching tipping points exhibit rising autocorrelation and variance independent of system-specific mechanisms.\n\\citet{boettiger2012limits} quantified the detection limits of such signals in short time series, a constraint directly relevant to iterative training where generation counts rarely exceed 20.\nGranger causality \\cite{granger1969investigating} provides the standard test for temporal precedence but produces spurious rejections on non-stationary series \\cite{granger1974spurious}; the Toda--Yamamoto procedure \\cite{toda1995statistical} restores valid inference at the cost of degrees of freedom \\cite{shojaie2022granger}, a severe trade-off when $T{\\leq}20$.\nYet these ecological and econometric tools have not been combined for model collapse; existing canary studies rely on visual inspection or naive correlation that cannot distinguish temporal precedence from shared trends.\n\n\\paragraph{Analytical robustness.}\n\nResearcher degrees of freedom in ML have received increasing attention through multiverse analysis \\cite{bell2022modeling}, many-analysts designs showing that independent teams reach divergent conclusions on identical data \\cite{coretta2023multidimensional}, and the REFORMS checklist \\cite{kapoor2024reforms}.\nOur work applies this perspective to collapse monitoring.\nWe differ from the closest predecessor \\cite{du2026geometric} in four respects: we compare an entire family of canary metrics rather than a single pair, cross-validate each relationship across five statistical methods, apply FDR correction across all tested pairs, and map detectability as a function of contamination regime.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work_reframe.tex",
    "content": "\\section{Related Work}\n\\label{sec:related_work}\n\n\\paragraph{Model collapse and canary metrics.}\n\nIterative training collapse was formalized by \\citet{shumailov2024curse} for language models and by \\citet{alemohammad2024mad} for image generation, establishing that recursive self-training erodes tail modes and reduces output diversity.\nTheoretical analyses have since shown that even small synthetic fractions alter effective scaling-law exponents \\cite{dohmatob2024tale}.\nSeveral metrics have been proposed as early collapse indicators: calibration error \\cite{du2026geometric,du2025scales}, surplexity \\cite{gambetta2024surplexity}, spectral divergence \\cite{sigma2026spectral}, topological persistence \\cite{kalinowski2026topology}, and center-edge dynamics \\cite{dces2026counter}.\nYet none of these analyses apply differencing tests to rule out spurious co-trending, cross-validate across multiple statistical methods, or apply false discovery rate correction when testing multiple metric pairs.\n\n\\paragraph{Early-warning signals and lead-lag methodology.}\n\nThe concept of early-warning indicators originates in ecology, where \\citet{scheffer2009early} showed that systems approaching tipping points exhibit rising autocorrelation and variance independent of system-specific mechanisms.\n\\citet{boettiger2012limits} quantified the detection limits of such signals in short time series, a constraint directly relevant to iterative training where generation counts rarely exceed 20.\nGranger causality \\cite{granger1969investigating} provides the standard test for temporal precedence but produces spurious rejections on non-stationary series \\cite{granger1974spurious}; the Toda--Yamamoto procedure \\cite{toda1995statistical} restores valid inference at the cost of degrees of freedom \\cite{shojaie2022granger}, a severe trade-off when $T{\\leq}20$.\nYet these ecological and econometric tools have not been combined for model collapse; existing canary studies rely on visual inspection or naive correlation that cannot distinguish temporal precedence from shared trends.\n\n\\paragraph{Analytical robustness.}\n\nResearcher degrees of freedom in ML have received increasing attention through multiverse analysis \\cite{bell2022modeling}, many-analysts designs showing that independent teams reach divergent conclusions on identical data \\cite{coretta2023multidimensional}, and the REFORMS checklist \\cite{kapoor2024reforms}.\nOur work applies this perspective to collapse monitoring.\nWe differ from the closest predecessor \\cite{du2026geometric} in four respects: we compare an entire family of canary metrics rather than a single pair, cross-validate each relationship across five statistical methods, apply FDR correction across all tested pairs, and map detectability as a function of contamination regime.\n"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-20T12:17:35.636837+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0514_4/projects/distrib_canary_collapse/docs/paper/related_work_reframe.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 17 · 2026-05-20T12:17:35.637174+00:00_

Written to `docs/paper/related_work_reframe.tex`. Summary of changes:

- **102 lines → 22 content lines** (3 paragraphs + section header)
- **Table 3 removed** entirely
- **Citations kept**: 15 essential refs (shumailov, alemohammad, dohmatob, du×2, gambetta, sigma, kalinowski, dces, scheffer, boettiger, granger×2, toda, shojaie, bell, coretta, kapoor)
- **Citations dropped**: 13 tangential refs (hataya, seddik, dey, kazdan, fu, he, guo, schaeffer-position, dohmatob2025strong, truong, gu×2, marcinkevics, ruiz, yi, sahoo, falahati, scheffer2012)
- **"Training dynamics monitoring" paragraph** dropped entirely
- **Positioning** preserved in final paragraph: 4 explicit differences (multi-metric family, multi-method cross-validation, FDR correction, regime-dependent mapping)
- No em-dashes, no -ing phrase endings, no AI filler

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_related_work_reframe_20260520T121501"
}
```

</details>

---
