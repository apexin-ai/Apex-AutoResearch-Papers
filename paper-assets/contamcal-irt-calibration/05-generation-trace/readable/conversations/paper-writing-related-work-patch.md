# paper writing related work patch

**Not All Models Are Inflated: Profiling Contamination Dose-Response Across Model Families** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 13
- **Recorded user turns:** 0
- **Tool calls:** 6
- **Original source:** `logs/chats/worker_paper_writing_related_work_patch_20260513T184852.jsonl`
- **Structured JSON:** [`a6145f47929a2138bea5.json`](../../sessions/a6/a6145f47929a2138bea5.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

13 recorded events

### Tool call

_source line 1 · 2026-05-13T18:50:14.377259+00:00_

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
  "session": "worker_paper_writing_related_work_patch_20260513T184852",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-13T18:50:14.378176+00:00_

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
  "session": "worker_paper_writing_related_work_patch_20260513T184852",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-13T18:50:14.382726+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_patch_20260513T184852",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-13T18:50:14.383143+00:00_

1	\section{Related Work}
2	\label{sec:related}
3	
4	\subsection{Benchmark Contamination Detection}
5	\label{sec:related:detection}
6	
7	Detecting training data contamination in LLMs has produced a diverse methodological landscape spanning at least eight paradigms. Time-based partitioning uses temporal cutoffs to identify potentially leaked items, while canary string insertion (e.g., BIG-Bench) provides direct memorization probes \citep{chang2025benchmarking}. Min-K\%++ \citep{duan2025minkpp} performs membership inference by examining token-level probability distributions, achieving strong detection on pre-training contamination. Time Travel \citep{oren2024proving} uses guided completion to detect black-box contamination without model weight access. ConStat \citep{dekoninck2024constat} measures performance gaps between original and paraphrased benchmark items, targeting surface-form memorization. Self-Critique \citep{wust2025selfcritique} identifies contamination through entropy collapse in model self-evaluations---a signal that, unlike probability-based methods, partially survives reinforcement learning post-training. Hierarchical semantic detection approaches match items at multiple granularity levels to training corpora. KDS \citep{xu2025kds} uses knowledge distillation signatures to achieve near-perfect detection (Spearman $\rho = 0.99$) but requires per-model LoRA fine-tuning, limiting scalability.
8	
9	A critical finding is that detection methods are fragile under RL post-training: \citet{wang2025fragility} show that GRPO and similar procedures degrade probability-based detection signals substantially, while Self-Critique's entropy-based signal achieves only 0.60--0.70 AUC on RL-trained models \citep{wust2025selfcritique}. Despite this rich detection toolkit, all existing methods produce binary or continuous \emph{flags}---they diagnose contamination without prescribing how to adjust the reported accuracy that end-users rely on.
10	
11	\subsection{Contamination
…[truncated 5687 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_patch_20260513T184852",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-13T18:50:14.383539+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex",
  "old_string": "\\paragraph{Positioning.} ContamCal bridges",
  "new_string": "\\paragraph{Differential item functioning.} The per-benchmark exposure parameter $\\gamma_k$ in ContamCal can be interpreted as measuring differential item functioning (DIF) between contaminated and clean model populations. DIF---the phenomenon whereby examinees of equal ability but different group membership respond differently to an item---was formalized by \\citep{holland1993dif}, with IRT-based detection procedures developed by \\citet{thissen1993dif} and logistic regression frameworks established by \\citet{zumbo1999dif}. In this view, $\\gamma_k$ functions as a uniform DIF parameter capturing systematic advantage conferred by exposure. However, ContamCal extends the classical DIF paradigm in two respects: group membership is determined by continuous exposure scores from Stage~1 rather than discrete demographic categories, and DIF is modeled jointly across all benchmarks within a hierarchical structure that shares information through the prior on $\\gamma_k$.\n\n\\paragraph{Positioning.} ContamCal bridges"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_patch_20260513T184852",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex",
    "old_string": "\\paragraph{Positioning.} ContamCal bridges",
    "new_string": "\\paragraph{Differential item functioning.} The per-benchmark exposure parameter $\\gamma_k$ in ContamCal can be interpreted as measuring differential item functioning (DIF) between contaminated and clean model populations. DIF---the phenomenon whereby examinees of equal ability but different group membership respond differently to an item---was formalized by \\citep{holland1993dif}, with IRT-based detection procedures developed by \\citet{thissen1993dif} and logistic regression frameworks established by \\citet{zumbo1999dif}. In this view, $\\gamma_k$ functions as a uniform DIF parameter capturing systematic advantage conferred by exposure. However, ContamCal extends the classical DIF paradigm in two respects: group membership is determined by continuous exposure scores from Stage~1 rather than discrete demographic categories, and DIF is modeled jointly across all benchmarks within a hierarchical structure that shares information through the prior on $\\gamma_k$.\n\n\\paragraph{Positioning.} ContamCal bridges"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-13T18:50:14.383803+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_patch_20260513T184852",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-13T18:50:14.383977+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex",
  "old_string": "Collectively, these findings motivate a paradigm shift: from contamination \\emph{prevention}---which demonstrably fails---to post-hoc statistical \\emph{adjustment} with proper uncertainty quantification.\n\n\\subsection{IRT for LLM Evaluation}",
  "new_string": "Collectively, these findings motivate a paradigm shift: from contamination \\emph{prevention}---which demonstrably fails---to post-hoc statistical \\emph{adjustment} with proper uncertainty quantification.\n\n\\paragraph{Terminological note.} Throughout this paper, ``calibration'' refers to the psychometric sense of score adjustment---recovering decontaminated ability estimates from potentially inflated benchmark scores. This should not be confused with probability calibration in machine learning, where the goal is to align predicted probabilities with empirical frequencies via methods such as Platt scaling or temperature scaling \\citep{guo2017calibration}. ContamCal performs the former: it adjusts reported accuracies for contamination bias rather than recalibrating model confidence scores.\n\n\\subsection{IRT for LLM Evaluation}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_patch_20260513T184852",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex",
    "old_string": "Collectively, these findings motivate a paradigm shift: from contamination \\emph{prevention}---which demonstrably fails---to post-hoc statistical \\emph{adjustment} with proper uncertainty quantification.\n\n\\subsection{IRT for LLM Evaluation}",
    "new_string": "Collectively, these findings motivate a paradigm shift: from contamination \\emph{prevention}---which demonstrably fails---to post-hoc statistical \\emph{adjustment} with proper uncertainty quantification.\n\n\\paragraph{Terminological note.} Throughout this paper, ``calibration'' refers to the psychometric sense of score adjustment---recovering decontaminated ability estimates from potentially inflated benchmark scores. This should not be confused with probability calibration in machine learning, where the goal is to align predicted probabilities with empirical frequencies via methods such as Platt scaling or temperature scaling \\citep{guo2017calibration}. ContamCal performs the former: it adjusts reported accuracies for contamination bias rather than recalibrating model confidence scores.\n\n\\subsection{IRT for LLM Evaluation}"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-13T18:50:14.384239+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_patch_20260513T184852",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-13T18:50:14.388655+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex",
  "old_string": "Across this body of work, contamination has not been modeled as a covariate within the IRT framework---a gap that ContamCal addresses by augmenting the item response function with exposure parameters.\n\n\\subsection{Item Compromise in Educational Measurement}",
  "new_string": "Across this body of work, contamination has not been modeled as a covariate within the IRT framework---a gap that ContamCal addresses by augmenting the item response function with exposure parameters.\n\n\\paragraph{Alternative uncertainty quantification.} Conformal prediction \\citep{angelopoulos2023conformal} offers distribution-free coverage guarantees and has been applied to various prediction tasks. We adopt Bayesian IRT over conformal alternatives for three reasons. First, contamination-specific parameters ($\\gamma_k$) yield directly interpretable causal quantities---``contamination inflates scores by $\\gamma_k$ units on benchmark $k$''---whereas conformal intervals lack such structural decomposition. Second, the posterior over all latent variables naturally propagates measurement error into credible intervals without requiring a separate calibration set. Third, conformal prediction assumes exchangeability of data points, which is violated in the contaminated setting: response distributions for contaminated items are systematically shifted relative to clean items. Conformal methods may nonetheless prove valuable in complementary LLM evaluation contexts where exchangeability holds.\n\n\\subsection{Item Compromise in Educational Measurement}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_patch_20260513T184852",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex",
    "old_string": "Across this body of work, contamination has not been modeled as a covariate within the IRT framework---a gap that ContamCal addresses by augmenting the item response function with exposure parameters.\n\n\\subsection{Item Compromise in Educational Measurement}",
    "new_string": "Across this body of work, contamination has not been modeled as a covariate within the IRT framework---a gap that ContamCal addresses by augmenting the item response function with exposure parameters.\n\n\\paragraph{Alternative uncertainty quantification.} Conformal prediction \\citep{angelopoulos2023conformal} offers distribution-free coverage guarantees and has been applied to various prediction tasks. We adopt Bayesian IRT over conformal alternatives for three reasons. First, contamination-specific parameters ($\\gamma_k$) yield directly interpretable causal quantities---``contamination inflates scores by $\\gamma_k$ units on benchmark $k$''---whereas conformal intervals lack such structural decomposition. Second, the posterior over all latent variables naturally propagates measurement error into credible intervals without requiring a separate calibration set. Third, conformal prediction assumes exchangeability of data points, which is violated in the contaminated setting: response distributions for contaminated items are systematically shifted relative to clean items. Conformal methods may nonetheless prove valuable in complementary LLM evaluation contexts where exchangeability holds.\n\n\\subsection{Item Compromise in Educational Measurement}"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-13T18:50:14.389030+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_patch_20260513T184852",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-13T18:50:14.389268+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_related_work_patch_20260513T184852",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-13T18:50:14.389590+00:00_

1	\section{Related Work}
2	\label{sec:related}
3	
4	\subsection{Benchmark Contamination Detection}
5	\label{sec:related:detection}
6	
7	Detecting training data contamination in LLMs has produced a diverse methodological landscape spanning at least eight paradigms. Time-based partitioning uses temporal cutoffs to identify potentially leaked items, while canary string insertion (e.g., BIG-Bench) provides direct memorization probes \citep{chang2025benchmarking}. Min-K\%++ \citep{duan2025minkpp} performs membership inference by examining token-level probability distributions, achieving strong detection on pre-training contamination. Time Travel \citep{oren2024proving} uses guided completion to detect black-box contamination without model weight access. ConStat \citep{dekoninck2024constat} measures performance gaps between original and paraphrased benchmark items, targeting surface-form memorization. Self-Critique \citep{wust2025selfcritique} identifies contamination through entropy collapse in model self-evaluations---a signal that, unlike probability-based methods, partially survives reinforcement learning post-training. Hierarchical semantic detection approaches match items at multiple granularity levels to training corpora. KDS \citep{xu2025kds} uses knowledge distillation signatures to achieve near-perfect detection (Spearman $\rho = 0.99$) but requires per-model LoRA fine-tuning, limiting scalability.
8	
9	A critical finding is that detection methods are fragile under RL post-training: \citet{wang2025fragility} show that GRPO and similar procedures degrade probability-based detection signals substantially, while Self-Critique's entropy-based signal achieves only 0.60--0.70 AUC on RL-trained models \citep{wust2025selfcritique}. Despite this rich detection toolkit, all existing methods produce binary or continuous \emph{flags}---they diagnose contamination without prescribing how to adjust the reported accuracy that end-users rely on.
10	
11	\subsection{Contamination
…[truncated 8272 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_related_work_patch_20260513T184852",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 13 · 2026-05-13T18:50:14.389871+00:00_

三处修改已完成：

1. **DIF 段落**（line 34）— 在 `\paragraph{Positioning.}` 前插入，连接 γ_k 与 DIF 文献（Holland, Thissen, Zumbo），说明从离散分组到连续 exposure gradient 的扩展。~118 词。

2. **Terminological note**（line 18）— 在 §2.2 末尾插入，区分 psychometric score adjustment 与 ML probability calibration（引用 Guo 2017）。~68 词。

3. **Conformal prediction 讨论**（line 25）— 在 §2.3 末尾插入，解释选择 Bayesian IRT 而非 conformal prediction 的三个理由（可解释性、uncertainty propagation、exchangeability violation）。~100 词。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_related_work_patch_20260513T184852"
}
```

</details>

---
