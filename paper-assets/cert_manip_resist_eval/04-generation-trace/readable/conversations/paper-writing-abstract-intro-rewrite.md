# paper writing abstract intro rewrite

**The Weakest Link Across Panel Sizes: Predictor Relevance Patterns in Multi-Judge LLM Evaluation under Adversarial Manipulation** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 25
- **Recorded user turns:** 0
- **Tool calls:** 12
- **Original source:** `logs/chats/worker_paper_writing_abstract_intro_rewrite_20260524T181332.jsonl`
- **Structured JSON:** [`3a9e5033f22b1ed3541f.json`](../../sessions/3a/3a9e5033f22b1ed3541f.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

25 recorded events

### Tool call

_source line 1 · 2026-05-24T18:19:05.563363+00:00_

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
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-24T18:19:05.564029+00:00_

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
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-24T18:19:05.564214+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/skills/projects/cert_manip_resist_eval/distilled-writing.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/skills/projects/cert_manip_resist_eval/distilled-writing.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-24T18:19:05.564490+00:00_

1	# Distilled Writing — Certifiable Manipulation Resistance for Multi-Judge LLM Eval
2	
3	> 8 篇深度精读论文的叙事结构、图表设计、论证策略归纳。
4	
5	## 1. 主流故事类型："化繁为简型" (3/8)
6	Yang2026, Feng2026, Turkmen2026: 复杂现象→单一信息论量→简洁解释。Turkmen 用 4 递进定理（独立→分解→饱和→算法）。**中置信度**。
7	→ 找一个统一量 (K_eff) 归纳不同现象。用递进定理链构建理论。
8	
9	## 2. Intro: 5 段 + 末段贡献列表 (7/8)
10	**高置信度**。模板: (1) 领域背景, (2) 现有局限, (3) 核心 insight, (4) 结果预览, (5) 编号贡献。贡献 3 个最常见 (5/8)，措辞 "framework + theory + empirical"。
11	
12	## 3. Hook: 悖论式最强
13	分布: 悖论/反直觉 3/8, 问题式 2/8, 能力缺口 1/8, 统一 1/8。**中置信度**。
14	Turkmen "Don't Always Pick the Highest-Performing Model" 挑战直觉; Robertson "Instead of 'which is better?' ask 'do they share information?'" 概念替换。
15	→ 可用 "Adding more judges doesn't make evaluation safer"。
16	
17	## 4. 张力: 假设失效 + 数字冲击
18	**6/8 篇**。**高置信度**。揭示被忽视假设→展示失效证据。Kim2025 "60% agreement when both err (vs 33% baseline)" 一个数字摧毁多样性假设。
19	→ 找同样冲击力的反直觉数字。
20	
21	## 5. Figure 1: 无主导模式，按论文类型选
22	method_overview 2/8, motivation 2/8, teaser_result 2/8, problem_illustration 2/8。**中置信度**。
23	理论导向偏 motivation（Yang 的 diminishing returns, Kim 的 heatmap）; 方法导向偏 teaser。
24	→ 本项目建议 motivation 类: homo vs hetero ASR scaling 对比。
25	
26	## 6. 主结果: Scaling→Line plot, 对比→Table
27	**7/8**。**高置信度**。
28	Scaling 行为: line plot (Turkmen error-vs-k, Yang accuracy-vs-N, Kaneko log-log)。
29	方法对比: table (PEG Table 1, TVD-MI Table 2)。
30	高亮: bold best 5/8; 理论验证用 regression slopes+p-values (Kaneko)。
31	统计: 趋势为 mean±std across seeds，但 3/8 仍 single run。
32	
33	## 7. 消融: Full numbers 主导 (5/8)
34	**高置信度**。无 checkmark grid。关键消融放 main（PEG K-scaling），其余 appendix。
35	
36	## 8. 图表叙事流 (6/8 共识)
37	**高置信度**。Motivation/Problem → Method/Theory → Main Results → Ablation。
38	数量: 4-6 figures (中位 5), 3-5 tables (中位 4)。
39	分工: scaling/correlation→图; 方法对比/消融→表; 扩展→appendix。
40	
41	## 9. 理论验证的视觉模式
42	**3/8**。**中置信度**。
43	Kaneko: log-log plot, slope-1 参考线; Turkmen: empirical vs copula scatter; Yang: K* 单调性。
44	→ K_eff 验证需 "theoretical prediction vs empirical" 对齐图。
45	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-24T18:19:05.564660+00:00_

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
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/main.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-24T18:19:05.564829+00:00_

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
14	\usepackage{tikz}
15	\usetikzlibrary{shapes.geometric,arrows.meta,positioning,fit,shadows.blur,calc}
16	
17	\newtheorem{theorem}{Theorem}
18	\newtheorem{definition}{Definition}
19	\newtheorem{proposition}{Proposition}
20	
21	\title{The Shifting Predictor: Panel-Size-Dependent Vulnerability\\Patterns in LLM Judge Panels}
22	
23	\author{Anonymous}
24	
25	\begin{document}
26	\maketitle
27	
28	\begin{abstract}
29	Multi-judge LLM evaluation panels are assumed to benefit from diversity, yet diversity's relationship to adversarial vulnerability is poorly understood. We decompose panel attack success into individual judge weakness ($\eta_{\max}$) and structural diversity ($K_{\mathrm{eff}}$) across 15 models, six attack types, two benchmarks, and panel sizes $K \in \{3, 5, 7\}$ (up to 6,435 panels). Consistent with adversarial ensemble theory but newly characterized in the LLM judge setting, $K_{\mathrm{eff}}$'s coefficient direction is positive in all 12 conditions (12/12 under OLS), though significance is method-sensitive (0--12/12 across inference methods) and the diversity--capability confound ($r{=}0.70$--$0.81$) limits causal interpretation. The predictors' relative importance shifts with panel size: at $K{=}3$, both contribute; at $K{\geq}5$, $K_{\mathrm{eff}}$ becomes the dominant predictor while $\eta_{\max}$ sharply attenuates. Cinelli--Hazlett sensitivity analysis reveals that $K_{\mathrm{eff}}$'s robustness value does not exceed the known confound in 69\% of conditions (25/36), but fractional logit with clustered standard errors confirms the positive association in most conditions ($K{=}3$: 9/12; $K{=}5$: 11/12; $K{=}
…[truncated 3315 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-24T18:19:05.564994+00:00_

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
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-24T18:19:05.565144+00:00_

1	\section{Introduction}
2	
3	\input{figures/fig_framework}
4	
5	Multi-judge panels have emerged as the dominant defense against bias and manipulation in LLM-based evaluation. After \citet{zheng2023judging} demonstrated that individual LLM judges can rival human annotators, subsequent work exposed systematic vulnerabilities: position bias, verbosity preferences, and sycophancy compromise the reliability of any single judge \citep{wang2023fair}. The natural response has been to aggregate decisions across diverse models, drawing inspiration from Byzantine fault tolerance (BFT), where majority voting among independent nodes tolerates faulty responses \citep{lamport1982byzantine,castro1999practical}. A recent systematization of LLM-judge security reports that 7-model committees reduce attack success rates from 50--68\% to 10--19\% \citep{almasoud2026security}. Diversity, by this logic, is the key ingredient for secure evaluation.
6	
7	Yet the evidence for diversity as a causal defense is weaker than it appears. The observed ASR reduction conflates panel diversity (judge independence) with individual robustness (strongest members). No existing work disentangles these across panel sizes. BFT adversaries control faulty nodes internally, whereas evaluation adversaries manipulate inputs externally; the independence-based intuition that joint failure scales with $K_{\mathrm{eff}} \cdot \eta_{\max}$ assumes non-adaptive faults \citep{schneier2000secrets}.
8	
9	In our experiments, we observe a panel-size-dependent predictor shift. The positive direction of $K_{\mathrm{eff}}$'s coefficient across all 12 conditions (direction 12/12 under ordinary least-squares (OLS), though significance is method-sensitive: 0--12/12 across inference methods; generalized additive model (GAM) bootstrap confirms 88.9--100\% positive rate) is directionally consistent with adversarial ensemble theory \citep{goodfellow2015adversarial,papernot2016transferability}, but the $K$-dependent transition in pre
…[truncated 2374 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-24T18:19:05.565291+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/abstract.tex"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-24T18:19:05.565424+00:00_

1	% Mirror of abstract in main.tex — do not edit here.
2	
3	Multi-judge LLM evaluation panels are assumed to benefit from diversity, yet diversity's relationship to adversarial vulnerability is poorly understood. We decompose panel attack success into individual judge weakness ($\eta_{\max}$) and structural diversity ($K_{\mathrm{eff}}$) across 15 models, six attack types, two benchmarks, and panel sizes $K \in \{3, 5, 7\}$ (up to 6,435 panels). Consistent with adversarial ensemble theory but newly characterized in the LLM judge setting, $K_{\mathrm{eff}}$'s coefficient direction is positive in all 12 conditions (12/12 under OLS), though significance is method-sensitive (0--12/12 across inference methods) and the diversity--capability confound ($r{=}0.70$--$0.81$) limits causal interpretation. The predictors' relative importance shifts with panel size: at $K{=}3$, both contribute; at $K{\geq}5$, $K_{\mathrm{eff}}$ becomes the dominant predictor while $\eta_{\max}$ sharply attenuates. Cinelli--Hazlett sensitivity analysis reveals that $K_{\mathrm{eff}}$'s robustness value does not exceed the known confound in 69\% of conditions (25/36), but fractional logit with clustered standard errors confirms the positive association in most conditions ($K{=}3$: 9/12; $K{=}5$: 11/12; $K{=}7$: 12/12). Aggregation rules influence predictability ($R^2$: threshold 0.83, Bayesian 0.09). The defense strategy should be informed by panel size: small panels benefit from screening for individual robustness; larger panels benefit from monitoring judge independence.
4	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-24T18:19:05.565753+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/main.tex",
  "old_string": "Multi-judge LLM evaluation panels are assumed to benefit from diversity, yet diversity's relationship to adversarial vulnerability is poorly understood. We decompose panel attack success into individual judge weakness ($\\eta_{\\max}$) and structural diversity ($K_{\\mathrm{eff}}$) across 15 models, six attack types, two benchmarks, and panel sizes $K \\in \\{3, 5, 7\\}$ (up to 6,435 panels). Consistent with adversarial ensemble theory but newly characterized in the LLM judge setting, $K_{\\mathrm{eff}}$'s coefficient direction is positive in all 12 conditions (12/12 under OLS), though significance is method-sensitive (0--12/12 across inference methods) and the diversity--capability confound ($r{=}0.70$--$0.81$) limits causal interpretation. The predictors' relative importance shifts with panel size: at $K{=}3$, both contribute; at $K{\\geq}5$, $K_{\\mathrm{eff}}$ becomes the dominant predictor while $\\eta_{\\max}$ sharply attenuates. Cinelli--Hazlett sensitivity analysis reveals that $K_{\\mathrm{eff}}$'s robustness value does not exceed the known confound in 69\\% of conditions (25/36), but fractional logit with clustered standard errors confirms the positive association in most conditions ($K{=}3$: 9/12; $K{=}5$: 11/12; $K{=}7$: 12/12). Aggregation rules influence predictability ($R^2$: threshold 0.83, Bayesian 0.09). The defense strategy should be informed by panel size: small panels benefit from screening for individual robustness; larger panels benefit from monitoring judge independence.",
  "new_string": "Multi-judge panels are widely deployed for robust Large Language Model (LLM) evaluation, yet adding judges can shift, not reduce, the dominant vulnerability pathway. Existing defenses conflate panel diversity with individual judge robustness, and it remains unclear which factor drives attack success rate (ASR) reduction. We decompose panel ASR into weakest-link susceptibility ($\\eta_{\\max}$) and effective independent channels ($K_{\\mathrm{eff}}$) across 15 models, six attack types, two benchmarks, and panel sizes $K \\in \\{3, 5, 7\\}$ (up to 6,435 panels). $K_{\\mathrm{eff}}$'s coefficient is positive in all 12 conditions under ordinary least squares, but significance varies across inference methods (0 to 12 of 12), and the diversity--capability confound ($r{=}0.70$--$0.81$) limits causal claims. The dominant predictor shifts with panel size: at $K{=}3$, both $\\eta_{\\max}$ and $K_{\\mathrm{eff}}$ contribute; at $K{\\geq}5$, $K_{\\mathrm{eff}}$ dominates while $\\eta_{\\max}$ attenuates. Aggregation rules modulate predictability ($R^2$: threshold 0.83, Bayesian 0.09). Small panels benefit most from individual robustness screening; larger panels require attention to judge independence."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/main.tex",
    "old_string": "Multi-judge LLM evaluation panels are assumed to benefit from diversity, yet diversity's relationship to adversarial vulnerability is poorly understood. We decompose panel attack success into individual judge weakness ($\\eta_{\\max}$) and structural diversity ($K_{\\mathrm{eff}}$) across 15 models, six attack types, two benchmarks, and panel sizes $K \\in \\{3, 5, 7\\}$ (up to 6,435 panels). Consistent with adversarial ensemble theory but newly characterized in the LLM judge setting, $K_{\\mathrm{eff}}$'s coefficient direction is positive in all 12 conditions (12/12 under OLS), though significance is method-sensitive (0--12/12 across inference methods) and the diversity--capability confound ($r{=}0.70$--$0.81$) limits causal interpretation. The predictors' relative importance shifts with panel size: at $K{=}3$, both contribute; at $K{\\geq}5$, $K_{\\mathrm{eff}}$ becomes the dominant predictor while $\\eta_{\\max}$ sharply attenuates. Cinelli--Hazlett sensitivity analysis reveals that $K_{\\mathrm{eff}}$'s robustness value does not exceed the known confound in 69\\% of conditions (25/36), but fractional logit with clustered standard errors confirms the positive association in most conditions ($K{=}3$: 9/12; $K{=}5$: 11/12; $K{=}7$: 12/12). Aggregation rules influence predictability ($R^2$: threshold 0.83, Bayesian 0.09). The defense strategy should be informed by panel size: small panels benefit from screening for individual robustness; larger panels benefit from monitoring judge independence.",
    "new_string": "Multi-judge panels are widely deployed for robust Large Language Model (LLM) evaluation, yet adding judges can shift, not reduce, the dominant vulnerability pathway. Existing defenses conflate panel diversity with individual judge robustness, and it remains unclear which factor drives attack success rate (ASR) reduction. We decompose panel ASR into weakest-link susceptibility ($\\eta_{\\max}$) and effective independent channels ($K_{\\mathrm{eff}}$) across 15 models, six attack types, two benchmarks, and panel sizes $K \\in \\{3, 5, 7\\}$ (up to 6,435 panels). $K_{\\mathrm{eff}}$'s coefficient is positive in all 12 conditions under ordinary least squares, but significance varies across inference methods (0 to 12 of 12), and the diversity--capability confound ($r{=}0.70$--$0.81$) limits causal claims. The dominant predictor shifts with panel size: at $K{=}3$, both $\\eta_{\\max}$ and $K_{\\mathrm{eff}}$ contribute; at $K{\\geq}5$, $K_{\\mathrm{eff}}$ dominates while $\\eta_{\\max}$ attenuates. Aggregation rules modulate predictability ($R^2$: threshold 0.83, Bayesian 0.09). Small panels benefit most from individual robustness screening; larger panels require attention to judge independence."
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-24T18:19:05.565988+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/main.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-24T18:19:05.566146+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/abstract.tex",
  "content": "% Mirror of abstract in main.tex — do not edit here.\n\nMulti-judge panels are widely deployed for robust Large Language Model (LLM) evaluation, yet adding judges can shift, not reduce, the dominant vulnerability pathway. Existing defenses conflate panel diversity with individual judge robustness, and it remains unclear which factor drives attack success rate (ASR) reduction. We decompose panel ASR into weakest-link susceptibility ($\\eta_{\\max}$) and effective independent channels ($K_{\\mathrm{eff}}$) across 15 models, six attack types, two benchmarks, and panel sizes $K \\in \\{3, 5, 7\\}$ (up to 6,435 panels). $K_{\\mathrm{eff}}$'s coefficient is positive in all 12 conditions under ordinary least squares, but significance varies across inference methods (0 to 12 of 12), and the diversity--capability confound ($r{=}0.70$--$0.81$) limits causal claims. The dominant predictor shifts with panel size: at $K{=}3$, both $\\eta_{\\max}$ and $K_{\\mathrm{eff}}$ contribute; at $K{\\geq}5$, $K_{\\mathrm{eff}}$ dominates while $\\eta_{\\max}$ attenuates. Aggregation rules modulate predictability ($R^2$: threshold 0.83, Bayesian 0.09). Small panels benefit most from individual robustness screening; larger panels require attention to judge independence.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/abstract.tex",
    "content": "% Mirror of abstract in main.tex — do not edit here.\n\nMulti-judge panels are widely deployed for robust Large Language Model (LLM) evaluation, yet adding judges can shift, not reduce, the dominant vulnerability pathway. Existing defenses conflate panel diversity with individual judge robustness, and it remains unclear which factor drives attack success rate (ASR) reduction. We decompose panel ASR into weakest-link susceptibility ($\\eta_{\\max}$) and effective independent channels ($K_{\\mathrm{eff}}$) across 15 models, six attack types, two benchmarks, and panel sizes $K \\in \\{3, 5, 7\\}$ (up to 6,435 panels). $K_{\\mathrm{eff}}$'s coefficient is positive in all 12 conditions under ordinary least squares, but significance varies across inference methods (0 to 12 of 12), and the diversity--capability confound ($r{=}0.70$--$0.81$) limits causal claims. The dominant predictor shifts with panel size: at $K{=}3$, both $\\eta_{\\max}$ and $K_{\\mathrm{eff}}$ contribute; at $K{\\geq}5$, $K_{\\mathrm{eff}}$ dominates while $\\eta_{\\max}$ attenuates. Aggregation rules modulate predictability ($R^2$: threshold 0.83, Bayesian 0.09). Small panels benefit most from individual robustness screening; larger panels require attention to judge independence.\n"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-24T18:19:05.566311+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/abstract.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-24T18:19:05.566448+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/introduction.tex",
  "content": "\\section{Introduction}\n\n\\input{figures/fig_framework}\n\nMulti-judge panels have become the dominant defense against bias and manipulation in Large Language Model (LLM) evaluation. After \\citet{zheng2023judging} demonstrated that individual LLM judges can rival human annotators, subsequent work exposed systematic vulnerabilities: position bias, verbosity preferences, and sycophancy compromise the reliability of any single judge \\citep{wang2023fair}. The natural response has been to aggregate decisions across diverse models, an approach inspired by Byzantine fault tolerance (BFT), where majority voting among independent nodes tolerates faulty responses \\citep{lamport1982byzantine,castro1999practical}. A recent systematization reports that 7-model committees reduce attack success rates (ASR) from 50--68\\% to 10--19\\% \\citep{almasoud2026security}. Diversity, by this logic, is the key ingredient for secure evaluation, yet this framing conflates two distinct sources of robustness: the quality of individual judges and the independence among them.\n\nThe conflation matters because the BFT analogy breaks down in the LLM judge setting. BFT adversaries control faulty nodes from within; evaluation adversaries manipulate inputs from without, and shared pretraining corpora create correlated failure modes that violate the independence assumption underlying majority-vote guarantees \\citep{schneier2000secrets}. No existing work disentangles diversity from individual robustness across panel sizes, so the mechanism behind observed ASR reductions remains unclear.\n\nWe address this gap by decomposing panel vulnerability into two predictors: weakest-link susceptibility ($\\eta_{\\max}$, the maximum individual attack success rate in a panel) and effective independent channels ($K_{\\mathrm{eff}}$, a spectral measure of judge independence). Across all 12 conditions (two benchmarks $\\times$ six attacks), $K_{\\mathrm{eff}}$'s ordinary least-squares (OLS) coefficient is positive (12/12), directionally consistent with adversarial ensemble theory \\citep{goodfellow2015adversarial,papernot2016transferability}. However, the significance of this association is method-sensitive (0 to 12 of 12 across inference approaches), and a previously uncharacterized transition emerges: at $K{=}3$, both predictors contribute (bootstrap significance: $\\eta_{\\max}$ 3/12, $K_{\\mathrm{eff}}$ 4/12); at $K{\\geq}5$, $K_{\\mathrm{eff}}$ becomes the dominant predictor (7/12 at $K{=}5$, 8/12 at $K{=}7$) while $\\eta_{\\max}$ sharply attenuates (2/12, then 1/12).\n\nControlled experiments across 15 models (9 API, 6 local AWQ-quantized), $K \\in \\{3,5,7\\}$, six attack types, and two benchmarks (MMLU, ARC) confirm this predictor shift. Under random faults, panel composition is highly predictive ($R^2 = 0.73$--$0.81$); adaptive attack reduces predictability to $R^2 = 0.275$ (Figure~\\ref{fig:framework}).\n\nThese findings yield three contributions:\n\\begin{enumerate}\n\\item \\textbf{Diversity--vulnerability association.} $K_{\\mathrm{eff}}$'s coefficient direction is positive in all 12 conditions (12/12 under OLS and generalized additive model (GAM) bootstrap), but the diversity--capability confound ($r{=}0.70$--$0.81$) limits causal interpretation: Cinelli--Hazlett robustness values do not exceed the confound in 69\\% of conditions (25/36), though fractional logit confirms the positive association in most conditions ($K{=}3$: 9/12; $K{=}5$: 11/12; $K{=}7$: 12/12) (\\S\\ref{sec:dominance}, \\S\\ref{sec:gam_taxonomy}).\n\\item \\textbf{Panel-size-dependent predictor shift.} At $K{=}3$, both $\\eta_{\\max}$ (3/12) and $K_{\\mathrm{eff}}$ (4/12) contribute under bootstrap (co-determination); at $K{\\geq}5$, $K_{\\mathrm{eff}}$ becomes the dominant predictor (7/12 at $K{=}5$, 8/12 at $K{=}7$) while $\\eta_{\\max}$ sharply attenuates (2/12, then 1/12) (\\S\\ref{sec:cross_k}, \\S\\ref{sec:rf_contrast}).\n\\item \\textbf{Aggregation as predictability control.} Aggregation rules modulate how much variance panel composition explains ($R^2$: threshold 0.83, Bayesian 0.09). Bayesian calibration attenuates $K_{\\mathrm{eff}}$ (5+/1$-$) but $\\eta_{\\max}$ persists (9/12), so the defense is partial rather than complete (\\S\\ref{sec:aggregation}, \\S\\ref{sec:analysis}).\n\\end{enumerate}\n\nOur findings are descriptive; the diversity--capability confound ($r{=}0.70$--$0.81$; \\S\\ref{sec:analysis}) limits causal claims.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/introduction.tex",
    "content": "\\section{Introduction}\n\n\\input{figures/fig_framework}\n\nMulti-judge panels have become the dominant defense against bias and manipulation in Large Language Model (LLM) evaluation. After \\citet{zheng2023judging} demonstrated that individual LLM judges can rival human annotators, subsequent work exposed systematic vulnerabilities: position bias, verbosity preferences, and sycophancy compromise the reliability of any single judge \\citep{wang2023fair}. The natural response has been to aggregate decisions across diverse models, an approach inspired by Byzantine fault tolerance (BFT), where majority voting among independent nodes tolerates faulty responses \\citep{lamport1982byzantine,castro1999practical}. A recent systematization reports that 7-model committees reduce attack success rates (ASR) from 50--68\\% to 10--19\\% \\citep{almasoud2026security}. Diversity, by this logic, is the key ingredient for secure evaluation, yet this framing conflates two distinct sources of robustness: the quality of individual judges and the independence among them.\n\nThe conflation matters because the BFT analogy breaks down in the LLM judge setting. BFT adversaries control faulty nodes from within; evaluation adversaries manipulate inputs from without, and shared pretraining corpora create correlated failure modes that violate the independence assumption underlying majority-vote guarantees \\citep{schneier2000secrets}. No existing work disentangles diversity from individual robustness across panel sizes, so the mechanism behind observed ASR reductions remains unclear.\n\nWe address this gap by decomposing panel vulnerability into two predictors: weakest-link susceptibility ($\\eta_{\\max}$, the maximum individual attack success rate in a panel) and effective independent channels ($K_{\\mathrm{eff}}$, a spectral measure of judge independence). Across all 12 conditions (two benchmarks $\\times$ six attacks), $K_{\\mathrm{eff}}$'s ordinary least-squares (OLS) coefficient is positive (12/12), directionally consistent with adversarial ensemble theory \\citep{goodfellow2015adversarial,papernot2016transferability}. However, the significance of this association is method-sensitive (0 to 12 of 12 across inference approaches), and a previously uncharacterized transition emerges: at $K{=}3$, both predictors contribute (bootstrap significance: $\\eta_{\\max}$ 3/12, $K_{\\mathrm{eff}}$ 4/12); at $K{\\geq}5$, $K_{\\mathrm{eff}}$ becomes the dominant predictor (7/12 at $K{=}5$, 8/12 at $K{=}7$) while $\\eta_{\\max}$ sharply attenuates (2/12, then 1/12).\n\nControlled experiments across 15 models (9 API, 6 local AWQ-quantized), $K \\in \\{3,5,7\\}$, six attack types, and two benchmarks (MMLU, ARC) confirm this predictor shift. Under random faults, panel composition is highly predictive ($R^2 = 0.73$--$0.81$); adaptive attack reduces predictability to $R^2 = 0.275$ (Figure~\\ref{fig:framework}).\n\nThese findings yield three contributions:\n\\begin{enumerate}\n\\item \\textbf{Diversity--vulnerability association.} $K_{\\mathrm{eff}}$'s coefficient direction is positive in all 12 conditions (12/12 under OLS and generalized additive model (GAM) bootstrap), but the diversity--capability confound ($r{=}0.70$--$0.81$) limits causal interpretation: Cinelli--Hazlett robustness values do not exceed the confound in 69\\% of conditions (25/36), though fractional logit confirms the positive association in most conditions ($K{=}3$: 9/12; $K{=}5$: 11/12; $K{=}7$: 12/12) (\\S\\ref{sec:dominance}, \\S\\ref{sec:gam_taxonomy}).\n\\item \\textbf{Panel-size-dependent predictor shift.} At $K{=}3$, both $\\eta_{\\max}$ (3/12) and $K_{\\mathrm{eff}}$ (4/12) contribute under bootstrap (co-determination); at $K{\\geq}5$, $K_{\\mathrm{eff}}$ becomes the dominant predictor (7/12 at $K{=}5$, 8/12 at $K{=}7$) while $\\eta_{\\max}$ sharply attenuates (2/12, then 1/12) (\\S\\ref{sec:cross_k}, \\S\\ref{sec:rf_contrast}).\n\\item \\textbf{Aggregation as predictability control.} Aggregation rules modulate how much variance panel composition explains ($R^2$: threshold 0.83, Bayesian 0.09). Bayesian calibration attenuates $K_{\\mathrm{eff}}$ (5+/1$-$) but $\\eta_{\\max}$ persists (9/12), so the defense is partial rather than complete (\\S\\ref{sec:aggregation}, \\S\\ref{sec:analysis}).\n\\end{enumerate}\n\nOur findings are descriptive; the diversity--capability confound ($r{=}0.70$--$0.81$; \\S\\ref{sec:analysis}) limits causal claims.\n"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-24T18:19:05.566686+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/introduction.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-24T18:19:05.566858+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper && sed -n '/\\\\begin{abstract}/,/\\\\end{abstract}/p' main.tex | grep -v '\\\\begin\\|\\\\end' | sed 's/\\\\[a-zA-Z]*{[^}]*}//g; s/\\$[^$]*\\$//g; s/[{}()~]//g; s/\\\\%/%/g; s/--/-/g; s/\\\\//g' | wc -w",
  "description": "Count abstract words (approximate, stripping LaTeX commands)"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Bash",
  "tool_args": {
    "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper && sed -n '/\\\\begin{abstract}/,/\\\\end{abstract}/p' main.tex | grep -v '\\\\begin\\|\\\\end' | sed 's/\\\\[a-zA-Z]*{[^}]*}//g; s/\\$[^$]*\\$//g; s/[{}()~]//g; s/\\\\%/%/g; s/--/-/g; s/\\\\//g' | wc -w",
    "description": "Count abstract words (approximate, stripping LaTeX commands)"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-24T18:19:05.566985+00:00_

142

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-24T18:19:05.567110+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "echo \"=== em-dash check ===\" && grep -n \"—\" introduction.tex main.tex abstract.tex 2>/dev/null || echo \"No em-dashes found\" && echo \"=== -ing ending check ===\" && grep -n \"ing\\.\" introduction.tex | head -20 && echo \"=== en-dash explanatory check ===\" && grep -n \" – \" introduction.tex abstract.tex 2>/dev/null || echo \"No explanatory en-dashes\"",
  "description": "Check for style violations (em-dash, -ing endings, explanatory en-dash)"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Bash",
  "tool_args": {
    "command": "echo \"=== em-dash check ===\" && grep -n \"—\" introduction.tex main.tex abstract.tex 2>/dev/null || echo \"No em-dashes found\" && echo \"=== -ing ending check ===\" && grep -n \"ing\\.\" introduction.tex | head -20 && echo \"=== en-dash explanatory check ===\" && grep -n \" – \" introduction.tex abstract.tex 2>/dev/null || echo \"No explanatory en-dashes\"",
    "description": "Check for style violations (em-dash, -ing endings, explanatory en-dash)"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-24T18:19:05.567243+00:00_

=== em-dash check ===
abstract.tex:1:% Mirror of abstract in main.tex — do not edit here.
=== -ing ending check ===
7:The conflation matters because the BFT analogy breaks down in the LLM judge setting. BFT adversaries control faulty nodes from within; evaluation adversaries manipulate inputs from without, and shared pretraining corpora create correlated failure modes that violate the independence assumption underlying majority-vote guarantees \citep{schneier2000secrets}. No existing work disentangles diversity from individual robustness across panel sizes, so the mechanism behind observed ASR reductions remains unclear.
=== en-dash explanatory check ===
No explanatory en-dashes

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-24T18:19:05.567403+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/main.tex",
  "offset": "27",
  "limit": "5"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/main.tex",
    "offset": "27",
    "limit": "5"
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-24T18:19:05.567534+00:00_

27	
28	\begin{abstract}
29	Multi-judge panels are widely deployed for robust Large Language Model (LLM) evaluation, yet adding judges can shift, not reduce, the dominant vulnerability pathway. Existing defenses conflate panel diversity with individual judge robustness, and it remains unclear which factor drives attack success rate (ASR) reduction. We decompose panel ASR into weakest-link susceptibility ($\eta_{\max}$) and effective independent channels ($K_{\mathrm{eff}}$) across 15 models, six attack types, two benchmarks, and panel sizes $K \in \{3, 5, 7\}$ (up to 6,435 panels). $K_{\mathrm{eff}}$'s coefficient is positive in all 12 conditions under ordinary least squares, but significance varies across inference methods (0 to 12 of 12), and the diversity--capability confound ($r{=}0.70$--$0.81$) limits causal claims. The dominant predictor shifts with panel size: at $K{=}3$, both $\eta_{\max}$ and $K_{\mathrm{eff}}$ contribute; at $K{\geq}5$, $K_{\mathrm{eff}}$ dominates while $\eta_{\max}$ attenuates. Aggregation rules modulate predictability ($R^2$: threshold 0.83, Bayesian 0.09). Small panels benefit most from individual robustness screening; larger panels require attention to judge independence.
30	\end{abstract}
31	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-24T18:19:05.567714+00:00_

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
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0519_2/projects/cert_manip_resist_eval/docs/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-24T18:19:05.567869+00:00_

1	\section{Introduction}
2	
3	\input{figures/fig_framework}
4	
5	Multi-judge panels have become the dominant defense against bias and manipulation in Large Language Model (LLM) evaluation. After \citet{zheng2023judging} demonstrated that individual LLM judges can rival human annotators, subsequent work exposed systematic vulnerabilities: position bias, verbosity preferences, and sycophancy compromise the reliability of any single judge \citep{wang2023fair}. The natural response has been to aggregate decisions across diverse models, an approach inspired by Byzantine fault tolerance (BFT), where majority voting among independent nodes tolerates faulty responses \citep{lamport1982byzantine,castro1999practical}. A recent systematization reports that 7-model committees reduce attack success rates (ASR) from 50--68\% to 10--19\% \citep{almasoud2026security}. Diversity, by this logic, is the key ingredient for secure evaluation, yet this framing conflates two distinct sources of robustness: the quality of individual judges and the independence among them.
6	
7	The conflation matters because the BFT analogy breaks down in the LLM judge setting. BFT adversaries control faulty nodes from within; evaluation adversaries manipulate inputs from without, and shared pretraining corpora create correlated failure modes that violate the independence assumption underlying majority-vote guarantees \citep{schneier2000secrets}. No existing work disentangles diversity from individual robustness across panel sizes, so the mechanism behind observed ASR reductions remains unclear.
8	
9	We address this gap by decomposing panel vulnerability into two predictors: weakest-link susceptibility ($\eta_{\max}$, the maximum individual attack success rate in a panel) and effective independent channels ($K_{\mathrm{eff}}$, a spectral measure of judge independence). Across all 12 conditions (two benchmarks $\times$ six attacks), $K_{\mathrm{eff}}$'s ordinary least-squares (OLS) coefficient is positive (1
…[truncated 2430 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 25 · 2026-05-24T18:19:05.568049+00:00_

三个文件均已更新完成。

**Abstract** (~142 words, 远低于 200 上限):
- 悖论式 hook 开场 ("shift, not reduce")
- 问题 → 方法 → 核心发现 → 实践建议结构完整
- 所有缩写首次出现已展开 (LLM, ASR, K_eff, η_max)

**Introduction** (5 段 + 3 条贡献):
1. Hook: multi-judge panels 主流化 → 7-model committees ASR 50-68%→10-19% → 悖论引出
2. 假设失效: BFT 内部 vs 外部对手 → independence 不成立 → 无已有工作 disentangle
3. 核心 insight: η_max + K_eff 分解 → predictor shift 预览 → K-dependent transition
4. 实验预览: 15 models, K∈{3,5,7}, R²=0.73-0.81, adaptive→0.275
5. 3 条贡献 + 末句 descriptive caveat

**风格检查通过**: 无 em-dash, 无 -ing 短语结尾, 无 AI 废话开场, 段间有逻辑连接, 所有 \cite/\ref 保留。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_abstract_intro_rewrite_20260524T181332"
}
```

</details>

---
