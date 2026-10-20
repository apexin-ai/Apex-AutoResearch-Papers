# paper writing

**Reproducibility Budgets for Open-Weight LLM Evaluation: A Generalizability Theory Study of 7–9B Instruction-Tuned Models** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 17
- **Recorded user turns:** 0
- **Tool calls:** 8
- **Original source:** `logs/chats/worker_paper_writing_20260521T205524.jsonl`
- **Structured JSON:** [`75602d187106d320f458.json`](../../sessions/75/75602d187106d320f458.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

17 recorded events

### Tool call

_source line 1 · 2026-05-21T20:57:25.241433+00:00_

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
  "session": "worker_paper_writing_20260521T205524",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-21T20:57:25.241932+00:00_

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
  "session": "worker_paper_writing_20260521T205524",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-21T20:57:25.242114+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519/skills/projects/nlp_variance_gtheory/distilled-writing.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519/skills/projects/nlp_variance_gtheory/distilled-writing.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-21T20:57:25.242420+00:00_

1	---
2	name: LLM Evaluation Variance — Writing Patterns
3	description: Narrative strategies, figure/table conventions from LLM evaluation variance papers (8 deep-read, 2024-2026)
4	type: writing
5	source_papers: 8
6	---
7	
8	## Story Types
9	
10	- **Breaking limitations** (3/8): Brittlebench, Yuan, ThinkingMachines. "Everyone assumed X, we show it fails." High.
11	- **Simplification** (2/8): Hua, GeneralizIT. "Complex problem, simpler real answer." Medium.
12	- **Unifying framework** (2/8): Kunievsky, Messina. "Scattered observations, one formalism." Medium.
13	- **Cross-domain transfer** (1/8): Mesting (psychometrics→ML). Our paper fits this type — study Mesting's structure. Low but critical.
14	
15	## Hook: Counter-Intuitive Claim Dominates (4/8, high)
16	
17	"Greedy≠deterministic" (Yuan), "80/1000 unique at T=0" (ThinkingMachines), "sensitivity is artifact" (Hua), "95% CIs→79% coverage" (Mesting). **Pattern**: open with a concrete number violating expectations. Avoid vague "X is important."
18	
19	## Tension: "Everyone's Doing It Wrong" (4/8, high)
20	
21	(1) Cite widespread practice, (2) quantified evidence it fails, (3) identify overlooked factor. ThinkingMachines adds a twist: debunk the accepted explanation before presenting the correct one.
22	
23	## Intro: 4 Paragraphs + 3 Contributions (mode)
24	
25	(1) Context, (2) existing approaches + limitation, (3) gap/surprise, (4) contributions. 3 contributions standard: framework + empirical finding + practical tool. **Support: 5/8, high.**
26	
27	## Figure Conventions
28	
29	**Figure 1**: problem_illustration (4/8) — show problem exists before solution. Concrete examples with before/after or divergence visualization. **High.**
30	
31	**Result figures**: bar charts primary (5/8); stacked bars for variance decomposition (2/8, Mesting/Brittlebench — expected idiom for our paper); line plots for trends (3/8); heatmaps for divergence (2/8). **High.**
32	
33	**Figure count**: 4-6 total. **Flow**: problem illustration →
…[truncated 1032 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-21T20:57:25.242587+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519/projects/nlp_variance_gtheory/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519/projects/nlp_variance_gtheory/docs/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-21T20:57:25.242740+00:00_

1	\section{Introduction}
2	\label{sec:introduction}
3	
4	On multiple-choice benchmarks, item selection drives 42--49\% of evaluation variance while prompt wording is negligible ($<$1\%). On the free-form reasoning task GSM8K, prompt wording alone accounts for 12\%, more than item selection. These numbers, drawn from our factorial analysis of 1.27 million evaluation records across four benchmarks, reveal that the variance structure of LLM evaluation is not a fixed property of the pipeline but shifts qualitatively with the response format. Current evaluation practice treats variance sources as independent nuisance factors and controls them one at a time: one study perturbs prompts, another varies precision, a third changes item subsets. This piecemeal approach cannot capture interactions between sources, nor can it predict how the relative importance of each source changes across evaluation settings. Leaderboard rankings built on single-condition evaluations are therefore sensitive to methodological choices that remain unreported and uncontrolled \citep{rodriguez2021leaderboards, dehghani2021benchmark}. No unified factorial framework exists to decompose these sources simultaneously, quantify their interactions, and compare the resulting variance structure across benchmarks.
5	
6	Existing studies have examined individual variance sources in isolation, each implicitly assuming separability. \citet{sclar2024formatting} documented up to 76\% accuracy swings from prompt formatting perturbations but held hardware and item selection fixed. BrittleBench \citep{brittlebench2026} found 50\% variance from prompt perturbation under the same constraint. \citet{yuan2025layercast} showed that numerical precision and GPU type cause up to 9\% accuracy variation but provided no factorial attribution to specific sources or their interactions. \citet{mesting2026hidden} applied Generalizability theory (G-theory) to LLM evaluation and decomposed variance across five methodology facets on a
…[truncated 4456 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-21T20:57:25.242884+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519/projects/nlp_variance_gtheory/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519/projects/nlp_variance_gtheory/docs/paper/method.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-21T20:57:25.243067+00:00_

1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Generalizability Theory}
5	\label{sec:gtheory}
6	
7	Generalizability theory (G-theory) treats each measurement as one observation from a universe of admissible conditions defined by the crossed facets of an evaluation design \cite{shavelson1991generalizability, brennan2001generalizability}. The \emph{object of measurement} is the entity whose consistency is of interest. In our setting, test items ($p$) serve as the object of measurement, and the goal is to determine how reliably item-level scores generalize across the methodological conditions under which they are collected.
8	
9	A \emph{G-study} decomposes total observed variance into components $\sigma^2_x$ for each facet $x$ and their interactions. Each component quantifies how much variability that source contributes to the overall measurement. Large interaction components (e.g., $\sigma^2_{pM}$ for item-by-model) indicate that facets do not affect items uniformly but instead create differential difficulty profiles. We estimate variance components via Henderson Method~I, an unbiased ANOVA-based estimator for balanced designs \cite[Ch.~3]{brennan2001generalizability}, with 1,000-resample bootstrap confidence intervals \cite{li2023bootstrap}.
10	
11	A \emph{D-study} projects the generalizability coefficient under hypothetical designs with different numbers of conditions per facet:
12	\begin{equation}
13	G_\text{item} = \frac{\sigma^2_p}{\sigma^2_p + \sigma^2_\text{rel}}
14	\label{eq:gcoeff}
15	\end{equation}
16	where $\sigma^2_\text{rel}$ aggregates all item-by-facet interaction variances, each divided by the number of conditions for the corresponding facets \cite[Ch.~4]{brennan2001generalizability}. This prospective capability distinguishes G-theory from classical ANOVA: rather than only attributing variance post hoc, a D-study enables optimization of evaluation designs \emph{before} data collection \cite{shavelson1989gtheory}. Throughout this paper, we use
…[truncated 8643 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-21T20:57:25.243206+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519/projects/nlp_variance_gtheory/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519/projects/nlp_variance_gtheory/docs/paper/experiments.tex"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-21T20:57:25.243462+00:00_

1	\section{Experiments}
2	
3	We apply the G-theory framework from Section~3 to a fully crossed evaluation design spanning multiple models, benchmarks, and methodological facets. All experiments use open-weight 7--9B parameter models evaluated with vLLM~0.9.2 on NVIDIA RTX PRO 6000 GPUs (96GB). Binary correctness (1/0) serves as the primary outcome measure throughout; generation-based scoring avoids the log-likelihood artifacts identified by \citet{hua2025flaw}.
4	
5	\subsection{Single-Model Baseline}
6	
7	We first establish the variance structure within a single model (Llama-3.1-8B-Instruct) on MMLU to isolate methodological facet contributions before introducing cross-model variation.
8	
9	\paragraph{Design.} The G-study crosses six facets: 200 items $\times$ 3 numerical precisions (BF16, FP16, FP32) $\times$ 6 prompt templates $\times$ 6 random seeds $\times$ 3 temperature levels (0.0, 0.3, 0.7) $\times$ 4 answer orderings, yielding 239,200 binary observations. Variance components are estimated via Henderson Method~I with bootstrap confidence intervals (1,000 resamples).
10	
11	\paragraph{Results.} Under binary scoring, item difficulty (\texttt{item\_id}) accounts for 61.1\% of total variance, with the residual term contributing 19.5\%. All main facet effects are negligible ($<$1\% each): prompt template 0.3\%, temperature 0.2\%, precision 0.1\%, seed $<$0.1\%, ordering $<$0.1\%. The interesting structure appears in item-conditional interactions: precision$\times$item contributes 7.2\%, temperature$\times$item 6.9\%, and prompt$\times$item 5.7\%. This pattern indicates that methodological choices do not shift performance uniformly across items; instead, specific items are differentially sensitive to specific facets.
12	
13	The resulting generalizability coefficient is $G_\text{item} = 0.918$, indicating that 200 items under multi-facet conditions produce highly reliable rankings. A D-study projection shows $G \geq 0.80$ is achievable with as few as 72 items in thi
…[truncated 12502 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-21T20:57:25.243713+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519/projects/nlp_variance_gtheory/docs/paper/related_work.tex",
  "content": "\\section{Related Work}\n\\label{sec:related}\n\n\\paragraph{Variance Decomposition in ML/NLP Evaluation.}\nFactorial decomposition of evaluation variance has roots in the ML reproducibility literature. \\citet{bouthillier2021accounting} introduced an ANOVA-based template that decomposes benchmark variance across implementation details, hyperparameters, and data splits, establishing that design choices account for a substantial share of reproducibility failures. Several subsequent studies applied similar decomposition logic to specific facets of model evaluation \\citep{dodge2020finetuning, henderson2018deep, magnusson2023reproducibility}. \\citet{mesting2026hidden} brought Generalizability theory into LLM evaluation, decomposing variance across five methodology facets on a single benchmark; judge identity dominated at 43.8\\%, with prompt$\\times$judge interaction at 12.4\\%. However, this study used a single benchmark, included no infrastructure facets such as numerical precision, and fixed the judge as an LLM evaluator rather than isolating other sources. \\citet{kunievsky2025intent} proposed an alternative decomposition that separates intent uncertainty, articulation variance, and model uncertainty, but this framework does not cross infrastructure and methodology facets in a factorial design. Our work extends these approaches by crossing seven facets across four benchmarks, enabling direct comparison of variance structures across evaluation formats.\n\n\\paragraph{Infrastructure and Prompt Variance.}\nA parallel line of work has examined individual variance sources in isolation. On the infrastructure side, \\citet{yuan2025layercast} documented up to 9\\% accuracy variation from numerical precision and GPU type but provided no factorial attribution. \\citet{messina2026background} formalized the concept of background temperature from floating-point non-associativity in GPU computation, and \\citet{thinkingmachines2025batch} proposed batch-invariant kernels to mitigate CUDA nondeterminism. On the methodology side, \\citet{sclar2024formatting} found up to 76\\% accuracy swings from prompt formatting changes on fixed hardware, and BrittleBench \\citep{brittlebench2026} reported 50\\% variance from prompt perturbation. \\citet{pezeshkpour2024ordering} showed that answer ordering in multiple-choice benchmarks introduces systematic bias, while \\citet{bui2025seeds} and \\citet{biderman2024lessons} documented sensitivity to random seeds and training configurations. Each of these studies isolates one factor while holding others fixed, which precludes estimating interactions between sources or comparing their relative magnitudes within a unified design.\n\n\\paragraph{IRT and Efficient Benchmarking.}\nItem Response Theory (IRT) offers a complementary perspective on evaluation design by modeling item difficulty and discrimination parameters. \\citet{lalor2019irt} introduced IRT-based item analysis for NLP benchmarks, and \\citet{rodriguez2021leaderboards} showed that IRT reveals hidden properties of evaluation items that raw accuracy scores obscure. Building on this foundation, \\citet{polo2024tinybenchmarks} developed tinyBenchmarks, using IRT-based subsampling to reduce evaluation cost while preserving ranking accuracy, and \\citet{zhou2026irt} recommended a 116-item subset via PSN-IRT for efficient MMLU evaluation. \\citet{perlitz2023efficient} explored related strategies for benchmark compression. These approaches optimize item selection for latent trait estimation but do not model variance from prompt, seed, or ordering facets. IRT-selected items evaluated under a single methodological condition can therefore systematically underestimate the number of items required for reliable measurement across diverse evaluation settings.\n\n\\paragraph{Binary Data and Psychometrics Foundations.}\nOur application of G-theory to binary correctness scores draws on established psychometric methodology. \\citet{shavelson1991generalizability} and \\citet{brennan2001generalizability} provide the canonical framework for multi-facet reliability analysis. \\citet{mushquash2006gtheory} extended G-theory to binary data, and \\citet{jiang2018bayesian} developed logistic-link generalized G-theory for binary outcomes. \\citet{tuerlinckx2006glmm} established the connection between generalized linear mixed models and G-theory variance components. These methods ground our use of Henderson Method~I for binary correctness scores (\\S\\ref{sec:binary}).\n\n\\paragraph{Positioning.}\nRelative to \\citet{mesting2026hidden}, we fix the judge (generation-based scoring) to isolate the remaining facets; their judge-dominated variance (43.8\\%) would otherwise mask all other sources. Our multi-benchmark design reveals format-conditional structure that single-benchmark studies cannot detect. Relative to IRT approaches \\citep{polo2024tinybenchmarks, zhou2026irt}, G-theory and IRT optimize orthogonal dimensions of evaluation design: IRT selects informative items, while G-theory determines the conditions needed for a target reliability. Our D-study quantifies this complementarity: multi-facet designs require $8.8\\times$ fewer items than single-condition protocols for equivalent reliability. Relative to isolated-factor studies \\citep{yuan2025layercast, sclar2024formatting, brittlebench2026}, our design crosses infrastructure and methodology facets within a single factorial framework, enabling interaction estimation that per-factor studies cannot provide.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519/projects/nlp_variance_gtheory/docs/paper/related_work.tex",
    "content": "\\section{Related Work}\n\\label{sec:related}\n\n\\paragraph{Variance Decomposition in ML/NLP Evaluation.}\nFactorial decomposition of evaluation variance has roots in the ML reproducibility literature. \\citet{bouthillier2021accounting} introduced an ANOVA-based template that decomposes benchmark variance across implementation details, hyperparameters, and data splits, establishing that design choices account for a substantial share of reproducibility failures. Several subsequent studies applied similar decomposition logic to specific facets of model evaluation \\citep{dodge2020finetuning, henderson2018deep, magnusson2023reproducibility}. \\citet{mesting2026hidden} brought Generalizability theory into LLM evaluation, decomposing variance across five methodology facets on a single benchmark; judge identity dominated at 43.8\\%, with prompt$\\times$judge interaction at 12.4\\%. However, this study used a single benchmark, included no infrastructure facets such as numerical precision, and fixed the judge as an LLM evaluator rather than isolating other sources. \\citet{kunievsky2025intent} proposed an alternative decomposition that separates intent uncertainty, articulation variance, and model uncertainty, but this framework does not cross infrastructure and methodology facets in a factorial design. Our work extends these approaches by crossing seven facets across four benchmarks, enabling direct comparison of variance structures across evaluation formats.\n\n\\paragraph{Infrastructure and Prompt Variance.}\nA parallel line of work has examined individual variance sources in isolation. On the infrastructure side, \\citet{yuan2025layercast} documented up to 9\\% accuracy variation from numerical precision and GPU type but provided no factorial attribution. \\citet{messina2026background} formalized the concept of background temperature from floating-point non-associativity in GPU computation, and \\citet{thinkingmachines2025batch} proposed batch-invariant kernels to mitigate CUDA nondeterminism. On the methodology side, \\citet{sclar2024formatting} found up to 76\\% accuracy swings from prompt formatting changes on fixed hardware, and BrittleBench \\citep{brittlebench2026} reported 50\\% variance from prompt perturbation. \\citet{pezeshkpour2024ordering} showed that answer ordering in multiple-choice benchmarks introduces systematic bias, while \\citet{bui2025seeds} and \\citet{biderman2024lessons} documented sensitivity to random seeds and training configurations. Each of these studies isolates one factor while holding others fixed, which precludes estimating interactions between sources or comparing their relative magnitudes within a unified design.\n\n\\paragraph{IRT and Efficient Benchmarking.}\nItem Response Theory (IRT) offers a complementary perspective on evaluation design by modeling item difficulty and discrimination parameters. \\citet{lalor2019irt} introduced IRT-based item analysis for NLP benchmarks, and \\citet{rodriguez2021leaderboards} showed that IRT reveals hidden properties of evaluation items that raw accuracy scores obscure. Building on this foundation, \\citet{polo2024tinybenchmarks} developed tinyBenchmarks, using IRT-based subsampling to reduce evaluation cost while preserving ranking accuracy, and \\citet{zhou2026irt} recommended a 116-item subset via PSN-IRT for efficient MMLU evaluation. \\citet{perlitz2023efficient} explored related strategies for benchmark compression. These approaches optimize item selection for latent trait estimation but do not model variance from prompt, seed, or ordering facets. IRT-selected items evaluated under a single methodological condition can therefore systematically underestimate the number of items required for reliable measurement across diverse evaluation settings.\n\n\\paragraph{Binary Data and Psychometrics Foundations.}\nOur application of G-theory to binary correctness scores draws on established psychometric methodology. \\citet{shavelson1991generalizability} and \\citet{brennan2001generalizability} provide the canonical framework for multi-facet reliability analysis. \\citet{mushquash2006gtheory} extended G-theory to binary data, and \\citet{jiang2018bayesian} developed logistic-link generalized G-theory for binary outcomes. \\citet{tuerlinckx2006glmm} established the connection between generalized linear mixed models and G-theory variance components. These methods ground our use of Henderson Method~I for binary correctness scores (\\S\\ref{sec:binary}).\n\n\\paragraph{Positioning.}\nRelative to \\citet{mesting2026hidden}, we fix the judge (generation-based scoring) to isolate the remaining facets; their judge-dominated variance (43.8\\%) would otherwise mask all other sources. Our multi-benchmark design reveals format-conditional structure that single-benchmark studies cannot detect. Relative to IRT approaches \\citep{polo2024tinybenchmarks, zhou2026irt}, G-theory and IRT optimize orthogonal dimensions of evaluation design: IRT selects informative items, while G-theory determines the conditions needed for a target reliability. Our D-study quantifies this complementarity: multi-facet designs require $8.8\\times$ fewer items than single-condition protocols for equivalent reliability. Relative to isolated-factor studies \\citep{yuan2025layercast, sclar2024formatting, brittlebench2026}, our design crosses infrastructure and methodology facets within a single factorial framework, enabling interaction estimation that per-factor studies cannot provide.\n"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-21T20:57:25.243898+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0519/projects/nlp_variance_gtheory/docs/paper/related_work.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-21T20:57:25.244021+00:00_

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
  "session": "worker_paper_writing_20260521T205524",
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

_source line 14 · 2026-05-21T20:57:25.244142+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-21T20:57:25.244258+00:00_

called mcp__agent-ml-research__register_artifact

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact</summary>

```json
{
  "name": "related_work.tex",
  "type": "paper",
  "description": "Related Work section (§2) for AAAI 2027 paper: 4 clusters (variance decomposition, infrastructure/prompt variance, IRT/efficient benchmarking, psychometrics foundations) + positioning paragraph. ~600 words, 24 citations.",
  "project": "nlp_variance_gtheory",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519/projects/nlp_variance_gtheory/docs/paper/related_work.tex",
  "tags": "['paper', 'related-work', 'aaai2027']"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "mcp__agent-ml-research__register_artifact",
  "tool_args": {
    "name": "related_work.tex",
    "type": "paper",
    "description": "Related Work section (§2) for AAAI 2027 paper: 4 clusters (variance decomposition, infrastructure/prompt variance, IRT/efficient benchmarking, psychometrics foundations) + positioning paragraph. ~600 words, 24 citations.",
    "project": "nlp_variance_gtheory",
    "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519/projects/nlp_variance_gtheory/docs/paper/related_work.tex",
    "tags": "['paper', 'related-work', 'aaai2027']"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-21T20:57:25.244414+00:00_

{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260521_767798\", \"name\": \"related_work.tex\", \"type\": \"paper\", \"description\": \"Related Work section (§2) for AAAI 2027 paper: 4 clusters (variance decomposition, infrastructure/prompt variance, IRT/efficient benchmarking, psychometrics foundations) + positioning paragraph. ~600 words, 24 citations.\", \"path\": \"projects/nlp_variance_gtheory/artifacts/_project/paper/related_work.tex\", \"url\": null, \"project\": \"nlp_variance_gtheory\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-21T20:57:18.845401+00:00\", \"tags\": [\"paper\", \"related-work\", \"aaai2027\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0519/projects/nlp_variance_gtheory/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_20260521T205524",
  "tool": "mcp__agent-ml-research__register_artifact",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 17 · 2026-05-21T20:57:25.244573+00:00_

已完成。文件写入 `docs/paper/related_work.tex`。

结构：4 个主题 cluster + positioning 段落，共 ~600 words，24 个 unique citations。各 cluster 做归纳比较而非论文堆砌，positioning 段落明确了相对 Mesting（fix judge）、IRT（orthogonal dimensions, 8.8× gap）、isolated-factor studies（unified factorial crossing）的增量。无破折号、无 -ing 尾句、无 AI 风格词汇。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_20260521T205524"
}
```

</details>

---
