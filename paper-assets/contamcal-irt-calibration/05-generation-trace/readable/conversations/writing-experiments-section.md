# writing experiments section

**Not All Models Are Inflated: Profiling Contamination Dose-Response Across Model Families** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 29
- **Recorded user turns:** 0
- **Tool calls:** 14
- **Original source:** `logs/chats/worker_writing_experiments-section_20260513T183138.jsonl`
- **Structured JSON:** [`e631c529fa3108e033e0.json`](../../sessions/e6/e631c529fa3108e033e0.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

29 recorded events

### Tool call

_source line 1 · 2026-05-13T18:37:24.432351+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/main.tex"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-13T18:37:24.432881+00:00_

1	% EMNLP 2026 ARR submission — acl_latex template
2	% Download style files: https://github.com/acl-org/acl-style-files
3	\documentclass[11pt]{article}
4	% TODO: uncomment when acl2023.sty is placed in this directory
5	% \usepackage[hyperref]{acl2023}
6	\usepackage{times}
7	\usepackage[hyphens]{url}
8	\usepackage{graphicx}
9	\usepackage{amsmath,amssymb,amsfonts}
10	\usepackage{natbib}
11	\usepackage{booktabs}
12	\usepackage[margin=1in]{geometry}
13	\usepackage{xcolor}
14	\usepackage{microtype}
15	\usepackage{hyperref}
16	
17	\title{ContamCal: Post-Hoc Calibration of Benchmark Scores\\
18	under Training Data Contamination via\\
19	Contamination-Augmented Item Response Theory}
20	
21	\author{Anonymous ARR Submission}
22	
23	\begin{document}
24	\maketitle
25	
26	\begin{abstract}
27	\textbf{TODO: Abstract to be written after experiments.}
28	\end{abstract}
29	
30	\input{introduction}
31	
32	\input{related_work}
33	
34	\input{method}
35	
36	% TODO: Experiments, Results, Discussion, Conclusion
37	
38	% TODO: switch to acl_natbib when style file is in place
39	\bibliographystyle{plainnat}
40	\bibliography{references}
41	
42	\end{document}
43	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-13T18:37:24.433169+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/method.tex"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-13T18:37:24.437703+00:00_

1	\section{Method}
2	\label{sec:method}
3	
4	ContamCal operates in two stages. Stage~1 (\S\ref{sec:stage1}) estimates per-item contamination exposure by fusing multiple detection signals into a single score. Stage~2 (\S\ref{sec:stage2}--\S\ref{sec:calibrated}) embeds these scores as covariates in a contamination-augmented IRT model, performing Bayesian inference to produce calibrated benchmark scores with credible intervals.
5	
6	\subsection{Stage 1: Multi-Signal Provenance Mapping}
7	\label{sec:stage1}
8	
9	For each model~$i$ and benchmark item~$j$, we compute four complementary detection signals that capture different facets of contamination evidence.
10	
11	\paragraph{Embedding-based near-duplicate retrieval.}
12	We embed both training corpus segments and benchmark items using a sentence transformer encoder and build a FAISS index over training embeddings for efficient retrieval. The signal $s_1(i,j)$ is the maximum cosine similarity between item~$j$ and the top-$K$ retrieved training segments for model~$i$'s training corpus, capturing semantic overlap that survives paraphrasing and surface-level reformulation.
13	
14	\paragraph{Min-K\%++ membership inference.}
15	Following \citet{duan2025minkpp}, we compute the average log-probability of the $k\%$ least-likely tokens in each benchmark item under model~$i$, z-scored against a reference (clean) model. Contaminated items yield systematically higher (less negative) Min-K\%++ scores, as the model assigns elevated probability to tokens it has memorized during training. The signal $s_2(i,j)$ is the resulting membership inference statistic. We use a simplified variant that z-normalizes per-item against a single reference model's mean and standard deviation, rather than the per-token z-scoring of the original formulation; since the downstream RRF aggregation operates on ranks rather than raw scores, this simplification preserves signal ordering while reducing computational cost.
16	
17	\paragraph{ConStat performance gap.
…[truncated 14745 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Read",
  "elapsed_ms": 4
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-13T18:37:24.438084+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-13T18:37:24.438441+00:00_

1	\section{Introduction}
2	\label{sec:intro}
3	
4	Large language model (LLM) evaluation increasingly relies on standardized benchmarks to compare models and track progress, yet mounting evidence reveals that these benchmarks are systematically compromised by training data contamination \citep{chang2025benchmarking}. \citet{yang2026rl} demonstrate that rephrased benchmark items appearing in training corpora inflate MMLU accuracy by 8--15 percentage points while evading standard $n$-gram decontamination, and that reinforcement learning (RL) post-training with GRPO further amplifies contamination-driven gains while simultaneously concealing the detection signals that would reveal them. Dose-response analyses confirm a monotonic relationship between contamination exposure and score inflation, with effects persisting across model scales \citep{dong2026dose}. Even minor perturbations to benchmark item surface forms---which should not affect genuinely capable models---produce substantial accuracy drops, questioning the validity of reported scores \citep{wang2025fragility}. Together, these findings point to a reliability crisis in LLM evaluation: reported benchmark scores increasingly conflate memorization with generalizable capability \citep{rao2026silicon}.
5	
6	Several methods have been developed to detect benchmark contamination. Min-K\%++ \citep{duan2025minkpp} and Time Travel \citep{oren2024proving} perform membership inference against pre-training corpora; ConStat \citep{dekoninck2024constat} measures performance gaps between original and paraphrased items; Self-Critique \citep{wust2025selfcritique} identifies memorization through entropy collapse in model self-evaluations; and KDS \citep{xu2025kds} uses knowledge distillation signatures to flag leaked items. While these methods can detect contamination, none produces calibrated benchmark scores that answer the central evaluation question: \emph{what would this model's accuracy be had it never seen the test data?} On
…[truncated 6883 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-13T18:37:24.438733+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/",
  "description": "List paper draft directory"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Bash",
  "tool_args": {
    "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/",
    "description": "List paper draft directory"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-13T18:37:24.438939+00:00_

introduction.tex
main.aux
main.bbl
main.blg
main.log
main.pdf
main.tex
method.tex
references.bib
related_work.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-13T18:37:24.439129+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file",
  "max_results": "1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__read_project_file",
    "max_results": "1"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-13T18:37:24.443360+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "ToolSearch",
  "elapsed_ms": 4
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-13T18:37:24.443690+00:00_

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
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/related_work.tex"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-13T18:37:24.444019+00:00_

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
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-13T18:37:24.444277+00:00_

called mcp__agent-ml-research__read_project_file

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file</summary>

```json
{
  "project": "contamcal-irt-calibration",
  "file": "paper_framing.md",
  "max_chars": "0"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "mcp__agent-ml-research__read_project_file",
  "tool_args": {
    "project": "contamcal-irt-calibration",
    "file": "paper_framing.md",
    "max_chars": "0"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-13T18:37:24.444659+00:00_

{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/paper_framing.md\", \"content\": \"# Paper Framing — contamcal-irt-calibration\\n\\n## Target Venue\\n- **Primary: EMNLP 2026 ARR May 25** (D006: reinstated per user directive, 12 days)\\n- Fallback: AAAI 2027 (Jul-Aug 2026) / ICLR 2027 (Sep 2026)\\n- Track: Machine Learning for NLP / Resources and Evaluation\\n- Aligns with EMNLP 2026 special theme \\\"New Missions for NLP Research\\\" (explicitly invites contamination/data governance work)\\n\\n## Core Insight\\nWhen benchmark mitigation strategies systematically fail (Emperor's New Clothes, ICML 2025: 20 strategies tested, none effective), the principled alternative is post-hoc statistical calibration — analogous to causal inference's shift from eliminating confounders to statistically controlling them. ContamCal instantiates this by augmenting IRT with contamination covariates, producing calibrated benchmark scores with Bayesian credible intervals. Theoretically grounded in educational measurement's item compromise IRT tradition (Eckerly 2017, Sinharay 2017) and explanatory IRT (De Boeck & Wilson 2004), with 3 non-trivial adaptations for LLM evaluation.\\n\\n## Core Claims (3 条)\\n\\n1. **Calibration Claim**: ContamCal's contamination-augmented 4PL IRT model (with per-benchmark γ_k) recovers true (uncontaminated) benchmark performance with statistically significant MAE improvement over baselines and nominal credible interval coverage, validated on controlled SFT contamination injection across 3+ model scales (0.5B-7B) within the Qwen2.5 family and 4 benchmarks. (Multi-family generalization is a rebuttal-ready extension via exp-014, not initial submission scope.)\\n\\n2. **Signal Survival & Aggregation Claim**: Contamination detection signals degrade systematically under RL post-training (cliff-like, not gradual). Training-free RRF fusion provides a principled, robust design ch
…[truncated 10121 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "mcp__agent-ml-research__read_project_file",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-13T18:37:24.444906+00:00_

called mcp__agent-ml-research__read_project_file

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file</summary>

```json
{
  "project": "contamcal-irt-calibration",
  "file": "ROADMAP.md",
  "max_chars": "0"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "mcp__agent-ml-research__read_project_file",
  "tool_args": {
    "project": "contamcal-irt-calibration",
    "file": "ROADMAP.md",
    "max_chars": "0"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-13T18:37:24.445158+00:00_

{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/ROADMAP.md\", \"content\": \"# contamcal-irt-calibration — Research Dashboard\\n\\n> 最后更新: 2026-05-13 17:14 UTC | 更新原因: D006: 投稿目标改回 EMNLP 2026 ARR May 25，12 天冲刺计划\\n\\n## 核心方向\\nContamCal：post-hoc statistical calibration via contamination-augmented 4PL IRT。详见 paper_framing.md。\\n\\n## 投稿目标\\n**EMNLP 2026 ARR May 25**（D006, 距今 12 天）\\n- Track: ML for NLP / Resources and Evaluation\\n- Special theme: \\\"New Missions for NLP Research\\\" — contamination/data governance\\n\\n## 当前进展\\n- **阶段**: Research（MVP 2026-05-13 通过）\\n- **exp-004**: subset sweep 运行中（12 conditions × 10 seeds，~8-12h CPU）\\n- **论文**: Agent 正在写 Introduction + Method LaTeX 初稿\\n- **Dream D2**: re-dream 运行中（dream_20260513T171200），验证 framing/plan 修改\\n- **GPU**: 等待用户开服务器（用户承诺充足资源）\\n\\n## 12 天冲刺计划\\n\\n### Day 1-2 (May 13-14): 基础设施 + 并行启动\\n- [ ] 用户开 GPU 服务器（4+ H100/A100-80G）\\n- [x] exp-004 subset sweep 运行中\\n- [ ] exp-001 SFT injection 启动（15 runs 并行化到 4 GPU，wall-clock ~13h）\\n- [ ] 论文 Introduction + Method 初稿完成\\n\\n### Day 3-4 (May 15-16): 信号计算\\n- [ ] exp-002 信号 pipeline（4 signals on all models）\\n- [ ] exp-003 RRF ablation\\n- [ ] exp-004 全量 sweep（如 subset 结果 OK）\\n- [ ] exp-005 noise propagation\\n\\n### Day 5-6 (May 17-18): IRT 校准 + 分析\\n- [ ] exp-006 IRT calibration + 7 baselines\\n- [ ] exp-008 signal survival analysis（P0）\\n- [ ] 分析 + 图表生成\\n\\n### Day 7-8 (May 19-20): 论文 + P1 实验\\n- [ ] Paper Agent full draft\\n- [ ] exp-007 7B scale-bridging（如 GPU 允许）\\n- [ ] exp-009 RL case study（如时间允许）\\n- [ ] **Day-8 checkpoint**: behind schedule → cut to MMLU+GSM8K，drop P1\\n\\n### Day 9-10 (May 21-22): 迭代\\n- [ ] Reviewer 审查 + 修改循环\\n- [ ] 引用验证（30+ citations）\\n- [ ] 图表打磨\\n\\n### Day 11-12 (May 23-24): 最终提交\\n- [ ] Camera-ready polish\\n- [ ] ARR submission\\n\\n## GPU 预算\\n- P0: 90h | P1: 60h | P2: 20h (deferred) | Buffer: 30h\\n- 冲刺优先: P0 全跑 + exp-008 (P0) + exp-0
…[truncated 1110 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "mcp__agent-ml-research__read_project_file",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-13T18:37:24.449671+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/references.bib"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-13T18:37:24.450172+00:00_

1	% ============================================================
2	% Core Methodology — Educational Measurement & IRT
3	% ============================================================
4	
5	@book{lord1980,
6	  author    = {Lord, Frederic M.},
7	  title     = {Applications of Item Response Theory to Practical Testing Problems},
8	  publisher = {Lawrence Erlbaum Associates},
9	  year      = {1980},
10	  address   = {Hillsdale, NJ}
11	}
12	
13	@article{eckerly2017,
14	  author  = {Eckerly, Carol},
15	  title   = {Detecting Item Compromise in the Context of Item Response Theory},
16	  journal = {Applied Psychological Measurement},
17	  volume  = {41},
18	  number  = {2},
19	  pages   = {87--101},
20	  year    = {2017}
21	}
22	
23	@article{sinharay2017,
24	  author  = {Sinharay, Sandip},
25	  title   = {Detection of Item Preknowledge Using Likelihood Ratio Test and Score Test},
26	  journal = {Journal of Educational and Behavioral Statistics},
27	  volume  = {42},
28	  number  = {1},
29	  pages   = {46--68},
30	  year    = {2017}
31	}
32	
33	@book{deboeck2004,
34	  author    = {De Boeck, Paul and Wilson, Mark},
35	  title     = {Explanatory Item Response Models: A Generalized Linear and Nonlinear Approach},
36	  publisher = {Springer},
37	  year      = {2004},
38	  address   = {New York}
39	}
40	
41	@article{adams1997,
42	  author  = {Adams, Raymond J. and Wilson, Mark and Wang, Wen-chung},
43	  title   = {The Multidimensional Random Coefficients Multinomial Logit Model},
44	  journal = {Applied Psychological Measurement},
45	  volume  = {21},
46	  number  = {1},
47	  pages   = {1--23},
48	  year    = {1997}
49	}
50	
51	@article{mislevy1986,
52	  author  = {Mislevy, Robert J.},
53	  title   = {Bayes Modal Estimation in Item Response Models},
54	  journal = {Psychometrika},
55	  volume  = {51},
56	  number  = {2},
57	  pages   = {177--195},
58	  year    = {1986}
59	}
60	
61	@article{sanmartin2009,
62	  author  = {San Mart\'{i}n, Ernesto and Del Pino, Guido and De Boeck, Pau
…[truncated 12110 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-13T18:37:24.450585+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/experiments.tex",
  "content": "\\section{Experiments}\n\\label{sec:experiments}\n\nWe evaluate ContamCal through controlled contamination injection across multiple model scales, dosage levels, and benchmarks. The experimental design provides ground-truth clean performance for every configuration, enabling direct measurement of calibration quality.\n\n\\subsection{Experimental Setup}\n\\label{sec:exp_setup}\n\nOur evaluation follows a controlled SFT injection pipeline: we deliberately contaminate models at known dosage levels, compute detection signals, fit the contamination-augmented IRT model, and compare calibrated scores against the known ground truth. This design provides the internal validity necessary for rigorous evaluation---we know the true contamination status of every item for every model.\n\nWe use the Qwen2.5 model family at three scales---0.5B, 1.5B, and 3B parameters---all fine-tuned via LoRA. A separate Qwen2.5-7B-Instruct model serves as the paraphrase generator for ConStat signal computation (\\S\\ref{sec:stage1}). We evaluate on four benchmarks spanning diverse evaluation modalities:\n\\begin{itemize}\n    \\item \\textbf{MMLU} \\citep{hendrycks2021mmlu}: knowledge-intensive multiple-choice (14,042 items);\n    \\item \\textbf{GSM8K} \\citep{cobbe2021gsm8k}: mathematical reasoning with free-form answers (1,319 items);\n    \\item \\textbf{ARC-Challenge} \\citep{clark2018arc}: science reasoning multiple-choice (1,172 items);\n    \\item \\textbf{HumanEval} \\citep{chen2021humaneval}: code generation with execution-based evaluation (164 items).\n\\end{itemize}\nHumanEval's small item count may limit 4PL parameter estimation reliability; we include it to test ContamCal at the boundary of applicability.\n\n\\subsection{Controlled Contamination Injection}\n\\label{sec:injection}\n\nFor each model scale, we inject contamination at five dosage levels: 0\\% (clean baseline), 10\\%, 25\\%, 50\\%, and 100\\% of benchmark items. At each dosage level~$d$, a random subset of $\\lfloor d \\cdot |B| \\rfloor$ items from benchmark~$B$ is selected for injection. Selected items are paraphrased using the 7B-Instruct model to produce surface-form variants that evade $n$-gram decontamination, following the protocol of \\citet{yang2026rl}. Models are then fine-tuned via LoRA ($r\\!=\\!16$, $\\alpha\\!=\\!32$) on the paraphrased items mixed with a held-out instruction-tuning corpus, for 3 epochs with learning rate $2 \\times 10^{-4}$.\n\nEach configuration (3 model scales $\\times$ 5 dosage levels) is run with 3 random seeds controlling both item selection and LoRA initialization, yielding 45 model checkpoints. The 0\\%-dosage models serve as ground-truth baselines for computing calibration error. This totals 180 training runs across all four benchmarks.\n\n\\subsection{Detection Signals and Aggregation}\n\\label{sec:exp_signals}\n\nWe compute four detection signals on all model--item pairs, as described in \\S\\ref{sec:stage1}. \\textbf{Embedding retrieval} indexes the training corpus via a sentence transformer and retrieves near-duplicate benchmark items by cosine similarity. \\textbf{Min-K\\%++} computes membership inference statistics using the 0\\%-dosage model of matching scale as reference. \\textbf{ConStat} measures the accuracy gap between original and paraphrased item variants. \\textbf{Self-Critique} quantifies entropy collapse in model self-evaluations. Signals are aggregated via RRF (Eq.~\\eqref{eq:rrf}) with $k\\!=\\!60$.\n\nWe conduct three ablation studies on signal aggregation: (i)~a \\emph{drop-one} ablation that removes each signal in turn to assess marginal contribution; (ii)~a \\emph{single-signal} ablation evaluating each signal independently; and (iii)~a $k$-sensitivity sweep over $k \\in \\{10, 30, 60, 100, 200\\}$. All ablations report AUC for contaminated-vs-clean item discrimination.\n\n\\subsection{IRT Calibration and Baselines}\n\\label{sec:exp_irt}\n\nWe fit the contamination-augmented 4PL IRT model (Eq.~\\eqref{eq:4pl}) separately per benchmark using CmdStanPy \\citep{carpenter2017} with the NUTS sampler \\citep{hoffman2014}. Each fit uses 4 independent chains of 2,000 iterations (1,000 warmup), with convergence assessed via split-$\\hat{R} < 1.01$, $\\text{ESS} > 400$, and $< 0.1\\%$ divergent transitions (\\S\\ref{sec:inference}). The measurement error model (Eq.~\\eqref{eq:measurement_error}) treats RRF exposure scores as noisy proxies for latent contamination~$\\tau_{ij}$. Calibrated scores are computed via Eq.~\\eqref{eq:calibrated_mc} by setting exposure to zero and marginalizing over posterior draws.\n\nWe also fit an analytical measurement error (ME) approximation that replaces MCMC with closed-form posterior moments under a linearized 4PL, providing a scalability option for large item pools at the cost of approximation error.\n\nWe compare ContamCal against seven baselines:\n\\begin{enumerate}\n    \\item[\\textbf{B0.}] \\textbf{Raw}: original benchmark scores with no adjustment, serving as the anchor for quantifying contamination inflation.\n    \\item[\\textbf{B1.}] \\textbf{Remove-and-rescore}: items with RRF exposure score above the 75th percentile are removed; accuracy is recomputed on remaining items.\n    \\item[\\textbf{B2.}] \\textbf{Single-signal 2PL+$\\boldsymbol{\\gamma}$}: the best-performing single detection signal (by AUC) enters a 2PL IRT model with contamination covariate~$\\gamma$ but without guessing ($c\\!=\\!0$) or slip ($d\\!=\\!1$) parameters.\n    \\item[\\textbf{B3.}] \\textbf{Vanilla 4PL} ($\\boldsymbol{\\gamma\\!=\\!0}$): standard 4PL IRT without contamination covariate, representing current IRT-based evaluation practice \\citep{gu2026psnirt,polo2026growing}.\n    \\item[\\textbf{B4.}] \\textbf{Linear exposure regression}: $\\text{Acc}_i = \\beta_0 + \\beta_1 \\bar{e}_i + \\epsilon$, where $\\bar{e}_i$ is the mean RRF exposure score, with bootstrap confidence intervals. Tests whether a simple regression suffices without the IRT machinery.\n    \\item[\\textbf{B5.}] \\textbf{Emperor's mitigation}: two representative strategies from \\citet{xu2025emperor}---item rephrasing and option shuffling---applied at evaluation time. We report the better-performing strategy per benchmark.\n    \\item[\\textbf{B6.}] \\textbf{DCR}: the decontaminated calibration and ranking method of \\citet{li2025dcr}, which produces adjusted accuracy via fuzzy inference over detection signals without uncertainty quantification.\n\\end{enumerate}\n\n\\subsection{Evaluation Protocol}\n\\label{sec:eval_protocol}\n\nWe assess calibration quality using five metrics that jointly characterize accuracy, uncertainty quantification, ranking fidelity, and mechanistic validity.\n\n\\paragraph{Calibration error.}\nMean absolute error between the calibrated score $\\widehat{\\text{Acc}}_i^{\\text{cal}}$ (Eq.~\\eqref{eq:calibrated_mc}) and the ground-truth clean accuracy $\\text{Acc}_i^{\\text{clean}}$ measured on 0\\%-dosage models:\n\\begin{equation}\n\\label{eq:mae}\n    \\text{MAE} = \\frac{1}{N} \\sum_{i=1}^{N} \\left| \\widehat{\\text{Acc}}_i^{\\text{cal}} - \\text{Acc}_i^{\\text{clean}} \\right|.\n\\end{equation}\nWe report bootstrap 95\\% confidence intervals computed over 1,000 resamples of model--benchmark pairs.\n\n\\paragraph{Interval coverage.}\nThe fraction of models whose ground-truth clean accuracy falls within the $\\alpha$-level credible interval:\n\\begin{equation}\n\\label{eq:coverage}\n    \\text{Cov}(\\alpha) = \\frac{1}{N} \\sum_{i=1}^{N} \\mathbf{1}\\!\\left[\\text{Acc}_i^{\\text{clean}} \\in \\text{CI}_i^{(\\alpha)}\\right].\n\\end{equation}\nWe evaluate at $\\alpha \\in \\{50\\%, 80\\%, 95\\%\\}$. Nominal coverage ($\\text{Cov}(\\alpha) \\approx \\alpha$) indicates well-calibrated uncertainty. For baselines without native uncertainty quantification (B0, B1, B5, B6), we use bootstrap resampling to construct confidence intervals.\n\n\\paragraph{Interval sharpness.}\nAverage width of the credible interval at coverage level~$\\alpha$:\n\\begin{equation}\n\\label{eq:sharpness}\n    \\text{Sharp}(\\alpha) = \\frac{1}{N} \\sum_{i=1}^{N} \\text{width}\\!\\left(\\text{CI}_i^{(\\alpha)}\\right).\n\\end{equation}\nNarrower intervals are preferred at fixed coverage; the ideal method achieves nominal coverage with minimal width.\n\n\\paragraph{Ranking preservation.}\nKendall's $\\tau$ between the calibrated model ranking and the ground-truth clean ranking:\n\\begin{equation}\n\\label{eq:kendall}\n    \\tau = \\frac{C - D}{\\binom{N}{2}},\n\\end{equation}\nwhere $C$ and $D$ are the numbers of concordant and discordant pairs. Values near 1 indicate that calibration preserves the true model ordering; deviations reveal methods that correct absolute scores but distort relative comparisons.\n\n\\paragraph{Dose-response monotonicity.}\nWe verify that the estimated contamination effect increases monotonically with dosage. Specifically, we compute Spearman's rank correlation between dosage level~$d$ and the posterior mean $\\hat{\\gamma}_k$ across the five dosage conditions per benchmark. Monotonic dose-response is a necessary (though not sufficient) condition for valid contamination modeling.\n\n\\subsection{Results}\n\\label{sec:results}\n\n\\paragraph{Main calibration results.}\nTable~\\ref{tab:main_results} presents calibration performance across all methods and benchmarks. \\textbf{[PLACEHOLDER: exp-006]} ContamCal achieves MAE of \\textbf{[PLACEHOLDER: exp-006]} percentage points averaged across benchmarks, compared to \\textbf{[PLACEHOLDER: exp-006]} for the best baseline (B6, DCR). The 95\\% credible intervals achieve \\textbf{[PLACEHOLDER: exp-006]}\\% coverage (nominal: 95\\%), with average width of \\textbf{[PLACEHOLDER: exp-006]} percentage points. Ranking preservation (Kendall's~$\\tau$) is \\textbf{[PLACEHOLDER: exp-006]}, indicating that calibration largely preserves the ground-truth model ordering.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{l cccc c}\n\\toprule\n\\textbf{Method} & \\textbf{MMLU} & \\textbf{GSM8K} & \\textbf{ARC-C} & \\textbf{HE} & \\textbf{Avg} \\\\\n\\midrule\n\\multicolumn{6}{l}{\\emph{MAE $\\downarrow$ (percentage points)}} \\\\\nB0. Raw & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB1. Remove-rescore & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB2. 2PL+$\\gamma$ & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB3. Vanilla 4PL & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB4. Linear reg. & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB5. Emperor's & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB6. DCR & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\n\\textbf{ContamCal} & \\textbf{XX.X} & \\textbf{XX.X} & \\textbf{XX.X} & \\textbf{XX.X} & \\textbf{XX.X} \\\\\n\\midrule\n\\multicolumn{6}{l}{\\emph{95\\% CI Coverage $\\uparrow$ (nominal: 95\\%)}} \\\\\nB2. 2PL+$\\gamma$ & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB3. Vanilla 4PL & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB4. Linear reg. & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\n\\textbf{ContamCal} & \\textbf{XX.X} & \\textbf{XX.X} & \\textbf{XX.X} & \\textbf{XX.X} & \\textbf{XX.X} \\\\\n\\midrule\n\\multicolumn{6}{l}{\\emph{Kendall's $\\tau$ $\\uparrow$}} \\\\\nB0. Raw & X.XX & X.XX & X.XX & X.XX & X.XX \\\\\nB6. DCR & X.XX & X.XX & X.XX & X.XX & X.XX \\\\\n\\textbf{ContamCal} & \\textbf{X.XX} & \\textbf{X.XX} & \\textbf{X.XX} & \\textbf{X.XX} & \\textbf{X.XX} \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Main calibration results across four benchmarks. \\textbf{[PLACEHOLDER: exp-006]} MAE: mean absolute error between calibrated and ground-truth clean accuracy (lower is better). Coverage: fraction of true values within 95\\% credible interval (closer to 95\\% is better). HE\\,=\\,HumanEval, ARC-C\\,=\\,ARC-Challenge. Best results in \\textbf{bold}.}\n\\label{tab:main_results}\n\\end{table}\n\n\\paragraph{RRF signal ablation.}\nTable~\\ref{tab:rrf_ablation} reports signal aggregation ablations. \\textbf{[PLACEHOLDER: exp-003]} Full four-signal RRF achieves AUC of \\textbf{[PLACEHOLDER: exp-003]} for contaminated-vs-clean discrimination, compared to \\textbf{[PLACEHOLDER: exp-003]} for the best single signal. Drop-one analysis reveals that removing \\textbf{[PLACEHOLDER: exp-003]} causes the largest AUC decrease, while removing \\textbf{[PLACEHOLDER: exp-003]} has minimal impact, suggesting complementary rather than redundant signal contributions.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{l cc}\n\\toprule\n\\textbf{Configuration} & \\textbf{AUC} & \\textbf{$\\Delta$AUC} \\\\\n\\midrule\n\\multicolumn{3}{l}{\\emph{Single-signal}} \\\\\nEmbedding retrieval & [TBD] & --- \\\\\nMin-K\\%++ & [TBD] & --- \\\\\nConStat & [TBD] & --- \\\\\nSelf-Critique & [TBD] & --- \\\\\n\\midrule\n\\multicolumn{3}{l}{\\emph{Drop-one from full RRF}} \\\\\n$-$ Embedding & [TBD] & [TBD] \\\\\n$-$ Min-K\\%++ & [TBD] & [TBD] \\\\\n$-$ ConStat & [TBD] & [TBD] \\\\\n$-$ Self-Critique & [TBD] & [TBD] \\\\\n\\midrule\nFull RRF (4 signals) & \\textbf{[TBD]} & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Signal aggregation ablation. \\textbf{[PLACEHOLDER: exp-003]} AUC for contaminated-vs-clean item discrimination, averaged across benchmarks and model scales. $\\Delta$AUC: change relative to full RRF.}\n\\label{tab:rrf_ablation}\n\\end{table}\n\n\\paragraph{RRF $k$-sensitivity.}\nTable~\\ref{tab:k_sensitivity} shows that calibration MAE and detection AUC are stable across $k \\in \\{10, 30, 60, 100, 200\\}$, confirming that ContamCal is not sensitive to the RRF smoothing constant. \\textbf{[PLACEHOLDER: exp-003]}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{l ccccc}\n\\toprule\n$k$ & 10 & 30 & \\textbf{60} & 100 & 200 \\\\\n\\midrule\nMAE & [TBD] & [TBD] & \\textbf{[TBD]} & [TBD] & [TBD] \\\\\nAUC & [TBD] & [TBD] & \\textbf{[TBD]} & [TBD] & [TBD] \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Sensitivity to RRF smoothing constant~$k$. \\textbf{[PLACEHOLDER: exp-003]} Default $k\\!=\\!60$ in bold.}\n\\label{tab:k_sensitivity}\n\\end{table}\n\n\\paragraph{Dose-response curves.}\nFigure~\\ref{fig:dose_response} plots raw accuracy, calibrated accuracy, and ground-truth clean accuracy as a function of contamination dosage for each benchmark and model scale. \\textbf{[PLACEHOLDER: exp-006]} Raw scores inflate monotonically with dosage, while calibrated scores remain approximately flat, tracking the ground-truth clean performance. The posterior mean $\\hat{\\gamma}_k$ increases monotonically with dosage across all benchmarks (Spearman $\\rho =$ \\textbf{[PLACEHOLDER: exp-006]}, $p <$ \\textbf{[PLACEHOLDER: exp-006]}).\n\n\\begin{figure}[t]\n    \\centering\n    % \\includegraphics[width=\\columnwidth]{figures/dose_response.pdf}\n    \\fbox{\\parbox{0.9\\columnwidth}{\\centering\\vspace{2em}\\textbf{[PLACEHOLDER: exp-006]}\\\\ Dose-response curves: raw vs.\\ calibrated vs.\\ ground-truth accuracy across 5 dosage levels, faceted by benchmark and model scale. Shaded bands = 95\\% credible intervals.\\vspace{2em}}}\n    \\caption{Dose-response curves across four benchmarks and three model scales (0.5B, 1.5B, 3B). \\textbf{[PLACEHOLDER: exp-006]}}\n    \\label{fig:dose_response}\n\\end{figure}\n\n\\paragraph{Uncertainty calibration and noise propagation.}\nFigure~\\ref{fig:ci_width} shows credible interval width as a function of measurement error variance~$\\sigma_e^2$ (Eq.~\\eqref{eq:measurement_error}). \\textbf{[PLACEHOLDER: exp-005]} As detection signal noise increases, ContamCal produces appropriately wider intervals while maintaining nominal coverage. This confirms that the measurement error model successfully propagates detection uncertainty into the calibrated scores.\n\n\\begin{figure}[t]\n    \\centering\n    % \\includegraphics[width=\\columnwidth]{figures/ci_width_noise.pdf}\n    \\fbox{\\parbox{0.9\\columnwidth}{\\centering\\vspace{2em}\\textbf{[PLACEHOLDER: exp-005]}\\\\ CI width and coverage vs.\\ measurement error variance $\\sigma_e^2$. Coverage should remain near nominal as width increases.\\vspace{2em}}}\n    \\caption{Credible interval width (left axis) and coverage (right axis) as a function of measurement error variance. \\textbf{[PLACEHOLDER: exp-005]}}\n    \\label{fig:ci_width}\n\\end{figure}\n\n\\paragraph{Signal survival under RL.}\nFigure~\\ref{fig:signal_survival} presents detection signal AUCs across training regimes (SFT vs.\\ RL with GRPO). \\textbf{[PLACEHOLDER: exp-008]} Probability-based signals (Min-K\\%++, ConStat) degrade from AUC \\textbf{[PLACEHOLDER: exp-008]} under SFT to \\textbf{[PLACEHOLDER: exp-008]} under RL---a cliff-like drop rather than gradual attenuation, consistent with the hypothesis in \\S\\ref{sec:signal_survival}. Self-Critique retains higher AUC of \\textbf{[PLACEHOLDER: exp-008]} post-RL, validating its inclusion as a robustness anchor in the signal ensemble. This regime-dependent degradation is automatically captured by the measurement error model: RL-trained models receive wider credible intervals reflecting genuine epistemic uncertainty about their contamination status.\n\n\\begin{figure}[t]\n    \\centering\n    % \\includegraphics[width=\\columnwidth]{figures/signal_survival.pdf}\n    \\fbox{\\parbox{0.9\\columnwidth}{\\centering\\vspace{2em}\\textbf{[PLACEHOLDER: exp-008, if available]}\\\\ Signal AUC by training regime (SFT vs.\\ RL). Grouped bar chart showing cliff-like degradation for probability-based signals vs.\\ retention for Self-Critique.\\vspace{2em}}}\n    \\caption{Detection signal AUC across training regimes. \\textbf{[PLACEHOLDER: exp-008]}}\n    \\label{fig:signal_survival}\n\\end{figure}\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/experiments.tex",
    "content": "\\section{Experiments}\n\\label{sec:experiments}\n\nWe evaluate ContamCal through controlled contamination injection across multiple model scales, dosage levels, and benchmarks. The experimental design provides ground-truth clean performance for every configuration, enabling direct measurement of calibration quality.\n\n\\subsection{Experimental Setup}\n\\label{sec:exp_setup}\n\nOur evaluation follows a controlled SFT injection pipeline: we deliberately contaminate models at known dosage levels, compute detection signals, fit the contamination-augmented IRT model, and compare calibrated scores against the known ground truth. This design provides the internal validity necessary for rigorous evaluation---we know the true contamination status of every item for every model.\n\nWe use the Qwen2.5 model family at three scales---0.5B, 1.5B, and 3B parameters---all fine-tuned via LoRA. A separate Qwen2.5-7B-Instruct model serves as the paraphrase generator for ConStat signal computation (\\S\\ref{sec:stage1}). We evaluate on four benchmarks spanning diverse evaluation modalities:\n\\begin{itemize}\n    \\item \\textbf{MMLU} \\citep{hendrycks2021mmlu}: knowledge-intensive multiple-choice (14,042 items);\n    \\item \\textbf{GSM8K} \\citep{cobbe2021gsm8k}: mathematical reasoning with free-form answers (1,319 items);\n    \\item \\textbf{ARC-Challenge} \\citep{clark2018arc}: science reasoning multiple-choice (1,172 items);\n    \\item \\textbf{HumanEval} \\citep{chen2021humaneval}: code generation with execution-based evaluation (164 items).\n\\end{itemize}\nHumanEval's small item count may limit 4PL parameter estimation reliability; we include it to test ContamCal at the boundary of applicability.\n\n\\subsection{Controlled Contamination Injection}\n\\label{sec:injection}\n\nFor each model scale, we inject contamination at five dosage levels: 0\\% (clean baseline), 10\\%, 25\\%, 50\\%, and 100\\% of benchmark items. At each dosage level~$d$, a random subset of $\\lfloor d \\cdot |B| \\rfloor$ items from benchmark~$B$ is selected for injection. Selected items are paraphrased using the 7B-Instruct model to produce surface-form variants that evade $n$-gram decontamination, following the protocol of \\citet{yang2026rl}. Models are then fine-tuned via LoRA ($r\\!=\\!16$, $\\alpha\\!=\\!32$) on the paraphrased items mixed with a held-out instruction-tuning corpus, for 3 epochs with learning rate $2 \\times 10^{-4}$.\n\nEach configuration (3 model scales $\\times$ 5 dosage levels) is run with 3 random seeds controlling both item selection and LoRA initialization, yielding 45 model checkpoints. The 0\\%-dosage models serve as ground-truth baselines for computing calibration error. This totals 180 training runs across all four benchmarks.\n\n\\subsection{Detection Signals and Aggregation}\n\\label{sec:exp_signals}\n\nWe compute four detection signals on all model--item pairs, as described in \\S\\ref{sec:stage1}. \\textbf{Embedding retrieval} indexes the training corpus via a sentence transformer and retrieves near-duplicate benchmark items by cosine similarity. \\textbf{Min-K\\%++} computes membership inference statistics using the 0\\%-dosage model of matching scale as reference. \\textbf{ConStat} measures the accuracy gap between original and paraphrased item variants. \\textbf{Self-Critique} quantifies entropy collapse in model self-evaluations. Signals are aggregated via RRF (Eq.~\\eqref{eq:rrf}) with $k\\!=\\!60$.\n\nWe conduct three ablation studies on signal aggregation: (i)~a \\emph{drop-one} ablation that removes each signal in turn to assess marginal contribution; (ii)~a \\emph{single-signal} ablation evaluating each signal independently; and (iii)~a $k$-sensitivity sweep over $k \\in \\{10, 30, 60, 100, 200\\}$. All ablations report AUC for contaminated-vs-clean item discrimination.\n\n\\subsection{IRT Calibration and Baselines}\n\\label{sec:exp_irt}\n\nWe fit the contamination-augmented 4PL IRT model (Eq.~\\eqref{eq:4pl}) separately per benchmark using CmdStanPy \\citep{carpenter2017} with the NUTS sampler \\citep{hoffman2014}. Each fit uses 4 independent chains of 2,000 iterations (1,000 warmup), with convergence assessed via split-$\\hat{R} < 1.01$, $\\text{ESS} > 400$, and $< 0.1\\%$ divergent transitions (\\S\\ref{sec:inference}). The measurement error model (Eq.~\\eqref{eq:measurement_error}) treats RRF exposure scores as noisy proxies for latent contamination~$\\tau_{ij}$. Calibrated scores are computed via Eq.~\\eqref{eq:calibrated_mc} by setting exposure to zero and marginalizing over posterior draws.\n\nWe also fit an analytical measurement error (ME) approximation that replaces MCMC with closed-form posterior moments under a linearized 4PL, providing a scalability option for large item pools at the cost of approximation error.\n\nWe compare ContamCal against seven baselines:\n\\begin{enumerate}\n    \\item[\\textbf{B0.}] \\textbf{Raw}: original benchmark scores with no adjustment, serving as the anchor for quantifying contamination inflation.\n    \\item[\\textbf{B1.}] \\textbf{Remove-and-rescore}: items with RRF exposure score above the 75th percentile are removed; accuracy is recomputed on remaining items.\n    \\item[\\textbf{B2.}] \\textbf{Single-signal 2PL+$\\boldsymbol{\\gamma}$}: the best-performing single detection signal (by AUC) enters a 2PL IRT model with contamination covariate~$\\gamma$ but without guessing ($c\\!=\\!0$) or slip ($d\\!=\\!1$) parameters.\n    \\item[\\textbf{B3.}] \\textbf{Vanilla 4PL} ($\\boldsymbol{\\gamma\\!=\\!0}$): standard 4PL IRT without contamination covariate, representing current IRT-based evaluation practice \\citep{gu2026psnirt,polo2026growing}.\n    \\item[\\textbf{B4.}] \\textbf{Linear exposure regression}: $\\text{Acc}_i = \\beta_0 + \\beta_1 \\bar{e}_i + \\epsilon$, where $\\bar{e}_i$ is the mean RRF exposure score, with bootstrap confidence intervals. Tests whether a simple regression suffices without the IRT machinery.\n    \\item[\\textbf{B5.}] \\textbf{Emperor's mitigation}: two representative strategies from \\citet{xu2025emperor}---item rephrasing and option shuffling---applied at evaluation time. We report the better-performing strategy per benchmark.\n    \\item[\\textbf{B6.}] \\textbf{DCR}: the decontaminated calibration and ranking method of \\citet{li2025dcr}, which produces adjusted accuracy via fuzzy inference over detection signals without uncertainty quantification.\n\\end{enumerate}\n\n\\subsection{Evaluation Protocol}\n\\label{sec:eval_protocol}\n\nWe assess calibration quality using five metrics that jointly characterize accuracy, uncertainty quantification, ranking fidelity, and mechanistic validity.\n\n\\paragraph{Calibration error.}\nMean absolute error between the calibrated score $\\widehat{\\text{Acc}}_i^{\\text{cal}}$ (Eq.~\\eqref{eq:calibrated_mc}) and the ground-truth clean accuracy $\\text{Acc}_i^{\\text{clean}}$ measured on 0\\%-dosage models:\n\\begin{equation}\n\\label{eq:mae}\n    \\text{MAE} = \\frac{1}{N} \\sum_{i=1}^{N} \\left| \\widehat{\\text{Acc}}_i^{\\text{cal}} - \\text{Acc}_i^{\\text{clean}} \\right|.\n\\end{equation}\nWe report bootstrap 95\\% confidence intervals computed over 1,000 resamples of model--benchmark pairs.\n\n\\paragraph{Interval coverage.}\nThe fraction of models whose ground-truth clean accuracy falls within the $\\alpha$-level credible interval:\n\\begin{equation}\n\\label{eq:coverage}\n    \\text{Cov}(\\alpha) = \\frac{1}{N} \\sum_{i=1}^{N} \\mathbf{1}\\!\\left[\\text{Acc}_i^{\\text{clean}} \\in \\text{CI}_i^{(\\alpha)}\\right].\n\\end{equation}\nWe evaluate at $\\alpha \\in \\{50\\%, 80\\%, 95\\%\\}$. Nominal coverage ($\\text{Cov}(\\alpha) \\approx \\alpha$) indicates well-calibrated uncertainty. For baselines without native uncertainty quantification (B0, B1, B5, B6), we use bootstrap resampling to construct confidence intervals.\n\n\\paragraph{Interval sharpness.}\nAverage width of the credible interval at coverage level~$\\alpha$:\n\\begin{equation}\n\\label{eq:sharpness}\n    \\text{Sharp}(\\alpha) = \\frac{1}{N} \\sum_{i=1}^{N} \\text{width}\\!\\left(\\text{CI}_i^{(\\alpha)}\\right).\n\\end{equation}\nNarrower intervals are preferred at fixed coverage; the ideal method achieves nominal coverage with minimal width.\n\n\\paragraph{Ranking preservation.}\nKendall's $\\tau$ between the calibrated model ranking and the ground-truth clean ranking:\n\\begin{equation}\n\\label{eq:kendall}\n    \\tau = \\frac{C - D}{\\binom{N}{2}},\n\\end{equation}\nwhere $C$ and $D$ are the numbers of concordant and discordant pairs. Values near 1 indicate that calibration preserves the true model ordering; deviations reveal methods that correct absolute scores but distort relative comparisons.\n\n\\paragraph{Dose-response monotonicity.}\nWe verify that the estimated contamination effect increases monotonically with dosage. Specifically, we compute Spearman's rank correlation between dosage level~$d$ and the posterior mean $\\hat{\\gamma}_k$ across the five dosage conditions per benchmark. Monotonic dose-response is a necessary (though not sufficient) condition for valid contamination modeling.\n\n\\subsection{Results}\n\\label{sec:results}\n\n\\paragraph{Main calibration results.}\nTable~\\ref{tab:main_results} presents calibration performance across all methods and benchmarks. \\textbf{[PLACEHOLDER: exp-006]} ContamCal achieves MAE of \\textbf{[PLACEHOLDER: exp-006]} percentage points averaged across benchmarks, compared to \\textbf{[PLACEHOLDER: exp-006]} for the best baseline (B6, DCR). The 95\\% credible intervals achieve \\textbf{[PLACEHOLDER: exp-006]}\\% coverage (nominal: 95\\%), with average width of \\textbf{[PLACEHOLDER: exp-006]} percentage points. Ranking preservation (Kendall's~$\\tau$) is \\textbf{[PLACEHOLDER: exp-006]}, indicating that calibration largely preserves the ground-truth model ordering.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{l cccc c}\n\\toprule\n\\textbf{Method} & \\textbf{MMLU} & \\textbf{GSM8K} & \\textbf{ARC-C} & \\textbf{HE} & \\textbf{Avg} \\\\\n\\midrule\n\\multicolumn{6}{l}{\\emph{MAE $\\downarrow$ (percentage points)}} \\\\\nB0. Raw & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB1. Remove-rescore & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB2. 2PL+$\\gamma$ & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB3. Vanilla 4PL & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB4. Linear reg. & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB5. Emperor's & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB6. DCR & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\n\\textbf{ContamCal} & \\textbf{XX.X} & \\textbf{XX.X} & \\textbf{XX.X} & \\textbf{XX.X} & \\textbf{XX.X} \\\\\n\\midrule\n\\multicolumn{6}{l}{\\emph{95\\% CI Coverage $\\uparrow$ (nominal: 95\\%)}} \\\\\nB2. 2PL+$\\gamma$ & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB3. Vanilla 4PL & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\nB4. Linear reg. & XX.X & XX.X & XX.X & XX.X & XX.X \\\\\n\\textbf{ContamCal} & \\textbf{XX.X} & \\textbf{XX.X} & \\textbf{XX.X} & \\textbf{XX.X} & \\textbf{XX.X} \\\\\n\\midrule\n\\multicolumn{6}{l}{\\emph{Kendall's $\\tau$ $\\uparrow$}} \\\\\nB0. Raw & X.XX & X.XX & X.XX & X.XX & X.XX \\\\\nB6. DCR & X.XX & X.XX & X.XX & X.XX & X.XX \\\\\n\\textbf{ContamCal} & \\textbf{X.XX} & \\textbf{X.XX} & \\textbf{X.XX} & \\textbf{X.XX} & \\textbf{X.XX} \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Main calibration results across four benchmarks. \\textbf{[PLACEHOLDER: exp-006]} MAE: mean absolute error between calibrated and ground-truth clean accuracy (lower is better). Coverage: fraction of true values within 95\\% credible interval (closer to 95\\% is better). HE\\,=\\,HumanEval, ARC-C\\,=\\,ARC-Challenge. Best results in \\textbf{bold}.}\n\\label{tab:main_results}\n\\end{table}\n\n\\paragraph{RRF signal ablation.}\nTable~\\ref{tab:rrf_ablation} reports signal aggregation ablations. \\textbf{[PLACEHOLDER: exp-003]} Full four-signal RRF achieves AUC of \\textbf{[PLACEHOLDER: exp-003]} for contaminated-vs-clean discrimination, compared to \\textbf{[PLACEHOLDER: exp-003]} for the best single signal. Drop-one analysis reveals that removing \\textbf{[PLACEHOLDER: exp-003]} causes the largest AUC decrease, while removing \\textbf{[PLACEHOLDER: exp-003]} has minimal impact, suggesting complementary rather than redundant signal contributions.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{l cc}\n\\toprule\n\\textbf{Configuration} & \\textbf{AUC} & \\textbf{$\\Delta$AUC} \\\\\n\\midrule\n\\multicolumn{3}{l}{\\emph{Single-signal}} \\\\\nEmbedding retrieval & [TBD] & --- \\\\\nMin-K\\%++ & [TBD] & --- \\\\\nConStat & [TBD] & --- \\\\\nSelf-Critique & [TBD] & --- \\\\\n\\midrule\n\\multicolumn{3}{l}{\\emph{Drop-one from full RRF}} \\\\\n$-$ Embedding & [TBD] & [TBD] \\\\\n$-$ Min-K\\%++ & [TBD] & [TBD] \\\\\n$-$ ConStat & [TBD] & [TBD] \\\\\n$-$ Self-Critique & [TBD] & [TBD] \\\\\n\\midrule\nFull RRF (4 signals) & \\textbf{[TBD]} & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Signal aggregation ablation. \\textbf{[PLACEHOLDER: exp-003]} AUC for contaminated-vs-clean item discrimination, averaged across benchmarks and model scales. $\\Delta$AUC: change relative to full RRF.}\n\\label{tab:rrf_ablation}\n\\end{table}\n\n\\paragraph{RRF $k$-sensitivity.}\nTable~\\ref{tab:k_sensitivity} shows that calibration MAE and detection AUC are stable across $k \\in \\{10, 30, 60, 100, 200\\}$, confirming that ContamCal is not sensitive to the RRF smoothing constant. \\textbf{[PLACEHOLDER: exp-003]}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{l ccccc}\n\\toprule\n$k$ & 10 & 30 & \\textbf{60} & 100 & 200 \\\\\n\\midrule\nMAE & [TBD] & [TBD] & \\textbf{[TBD]} & [TBD] & [TBD] \\\\\nAUC & [TBD] & [TBD] & \\textbf{[TBD]} & [TBD] & [TBD] \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Sensitivity to RRF smoothing constant~$k$. \\textbf{[PLACEHOLDER: exp-003]} Default $k\\!=\\!60$ in bold.}\n\\label{tab:k_sensitivity}\n\\end{table}\n\n\\paragraph{Dose-response curves.}\nFigure~\\ref{fig:dose_response} plots raw accuracy, calibrated accuracy, and ground-truth clean accuracy as a function of contamination dosage for each benchmark and model scale. \\textbf{[PLACEHOLDER: exp-006]} Raw scores inflate monotonically with dosage, while calibrated scores remain approximately flat, tracking the ground-truth clean performance. The posterior mean $\\hat{\\gamma}_k$ increases monotonically with dosage across all benchmarks (Spearman $\\rho =$ \\textbf{[PLACEHOLDER: exp-006]}, $p <$ \\textbf{[PLACEHOLDER: exp-006]}).\n\n\\begin{figure}[t]\n    \\centering\n    % \\includegraphics[width=\\columnwidth]{figures/dose_response.pdf}\n    \\fbox{\\parbox{0.9\\columnwidth}{\\centering\\vspace{2em}\\textbf{[PLACEHOLDER: exp-006]}\\\\ Dose-response curves: raw vs.\\ calibrated vs.\\ ground-truth accuracy across 5 dosage levels, faceted by benchmark and model scale. Shaded bands = 95\\% credible intervals.\\vspace{2em}}}\n    \\caption{Dose-response curves across four benchmarks and three model scales (0.5B, 1.5B, 3B). \\textbf{[PLACEHOLDER: exp-006]}}\n    \\label{fig:dose_response}\n\\end{figure}\n\n\\paragraph{Uncertainty calibration and noise propagation.}\nFigure~\\ref{fig:ci_width} shows credible interval width as a function of measurement error variance~$\\sigma_e^2$ (Eq.~\\eqref{eq:measurement_error}). \\textbf{[PLACEHOLDER: exp-005]} As detection signal noise increases, ContamCal produces appropriately wider intervals while maintaining nominal coverage. This confirms that the measurement error model successfully propagates detection uncertainty into the calibrated scores.\n\n\\begin{figure}[t]\n    \\centering\n    % \\includegraphics[width=\\columnwidth]{figures/ci_width_noise.pdf}\n    \\fbox{\\parbox{0.9\\columnwidth}{\\centering\\vspace{2em}\\textbf{[PLACEHOLDER: exp-005]}\\\\ CI width and coverage vs.\\ measurement error variance $\\sigma_e^2$. Coverage should remain near nominal as width increases.\\vspace{2em}}}\n    \\caption{Credible interval width (left axis) and coverage (right axis) as a function of measurement error variance. \\textbf{[PLACEHOLDER: exp-005]}}\n    \\label{fig:ci_width}\n\\end{figure}\n\n\\paragraph{Signal survival under RL.}\nFigure~\\ref{fig:signal_survival} presents detection signal AUCs across training regimes (SFT vs.\\ RL with GRPO). \\textbf{[PLACEHOLDER: exp-008]} Probability-based signals (Min-K\\%++, ConStat) degrade from AUC \\textbf{[PLACEHOLDER: exp-008]} under SFT to \\textbf{[PLACEHOLDER: exp-008]} under RL---a cliff-like drop rather than gradual attenuation, consistent with the hypothesis in \\S\\ref{sec:signal_survival}. Self-Critique retains higher AUC of \\textbf{[PLACEHOLDER: exp-008]} post-RL, validating its inclusion as a robustness anchor in the signal ensemble. This regime-dependent degradation is automatically captured by the measurement error model: RL-trained models receive wider credible intervals reflecting genuine epistemic uncertainty about their contamination status.\n\n\\begin{figure}[t]\n    \\centering\n    % \\includegraphics[width=\\columnwidth]{figures/signal_survival.pdf}\n    \\fbox{\\parbox{0.9\\columnwidth}{\\centering\\vspace{2em}\\textbf{[PLACEHOLDER: exp-008, if available]}\\\\ Signal AUC by training regime (SFT vs.\\ RL). Grouped bar chart showing cliff-like degradation for probability-based signals vs.\\ retention for Self-Critique.\\vspace{2em}}}\n    \\caption{Detection signal AUC across training regimes. \\textbf{[PLACEHOLDER: exp-008]}}\n    \\label{fig:signal_survival}\n\\end{figure}\n"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-13T18:37:24.451200+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/experiments.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-13T18:37:24.455595+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/main.tex",
  "old_string": "% TODO: Experiments, Results, Discussion, Conclusion",
  "new_string": "\\input{experiments}\n\n% TODO: Discussion, Conclusion"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/main.tex",
    "old_string": "% TODO: Experiments, Results, Discussion, Conclusion",
    "new_string": "\\input{experiments}\n\n% TODO: Discussion, Conclusion"
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-13T18:37:24.455885+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/main.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-13T18:37:24.456117+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/references.bib",
  "old_string": "@inproceedings{chang2025benchmarking,",
  "new_string": "@inproceedings{hendrycks2021mmlu,\n  author    = {Hendrycks, Dan and Burns, Collin and Basart, Steven and Zou, Andy and Mazeika, Mantas and Song, Dawn and Steinhardt, Jacob},\n  title     = {Measuring Massive Multitask Language Understanding},\n  booktitle = {Proceedings of the 9th International Conference on Learning Representations (ICLR)},\n  year      = {2021}\n}\n\n@article{cobbe2021gsm8k,\n  author        = {Cobbe, Karl and Kosaraju, Vineet and Bavarian, Mohammad and Chen, Mark and Jun, Heewoo and Kaiser, Lukasz and Plappert, Matthias and Tworek, Jerry and Hilton, Jacob and Nakano, Reiichiro and Hesse, Christopher and Schulman, John},\n  title         = {Training Verifiers to Solve Math Word Problems},\n  journal       = {arXiv preprint},\n  year          = {2021},\n  eprint        = {2110.14168},\n  archiveprefix = {arXiv}\n}\n\n@inproceedings{clark2018arc,\n  author    = {Clark, Peter and Cowhey, Isaac and Etzioni, Oren and Khot, Tushar and Sabharwal, Ashish and Schoenick, Carissa and Tafjord, Oyvind},\n  title     = {Think you have Solved Question Answering? {Try ARC}, the {AI2} Reasoning Challenge},\n  journal   = {arXiv preprint},\n  year      = {2018},\n  eprint    = {1803.05457},\n  archiveprefix = {arXiv}\n}\n\n@article{chen2021humaneval,\n  author        = {Chen, Mark and Tworek, Jerry and Jun, Heewoo and Yuan, Qiming and Pinto, Henrique Ponde de Oliveira and Kaplan, Jared and Edwards, Harri and Burda, Yuri and Joseph, Nicholas and Brockman, Greg and Ray, Alex and Puri, Raul and Krueger, Gretchen and Petrov, Michael and Khlaaf, Heidy and Sastry, Girish and Mishkin, Pamela and Chan, Brooke and Gray, Scott and Ryder, Nick and Pavlov, Mikhail and Power, Alethea and Kaiser, Lukasz and Bavarian, Mohammad and Winter, Clemens and Tillet, Philippe and Such, Felipe Petroski and Cummings, Dave and Plappert, Matthias and Chanez, Fotios and Barnes, Elizabeth and Herbert-Voss, Ariel and Guss, William Hebgen and Nichol, Alex and Paino, Alex and Tezak, Nikolas and Tang, Jie and Babuschkin, Igor and Balaji, Suchir and Jain, Shantanu and Saunders, William and Hesse, Christopher and Carr, Andrew N. and Leike, Jan and Achiam, Josh and Misra, Vedant and Morikawa, Evan and Radford, Alec and Knight, Matthew and Brundage, Miles and Murati, Mira and Mayer, Katie and Welinder, Peter and McGrew, Bob and Amodei, Dario and McCandlish, Sam and Sutskever, Ilya and Zaremba, Wojciech},\n  title         = {Evaluating Large Language Models Trained on Code},\n  journal       = {arXiv preprint},\n  year          = {2021},\n  eprint        = {2107.03374},\n  archiveprefix = {arXiv}\n}\n\n@inproceedings{chang2025benchmarking,"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/references.bib",
    "old_string": "@inproceedings{chang2025benchmarking,",
    "new_string": "@inproceedings{hendrycks2021mmlu,\n  author    = {Hendrycks, Dan and Burns, Collin and Basart, Steven and Zou, Andy and Mazeika, Mantas and Song, Dawn and Steinhardt, Jacob},\n  title     = {Measuring Massive Multitask Language Understanding},\n  booktitle = {Proceedings of the 9th International Conference on Learning Representations (ICLR)},\n  year      = {2021}\n}\n\n@article{cobbe2021gsm8k,\n  author        = {Cobbe, Karl and Kosaraju, Vineet and Bavarian, Mohammad and Chen, Mark and Jun, Heewoo and Kaiser, Lukasz and Plappert, Matthias and Tworek, Jerry and Hilton, Jacob and Nakano, Reiichiro and Hesse, Christopher and Schulman, John},\n  title         = {Training Verifiers to Solve Math Word Problems},\n  journal       = {arXiv preprint},\n  year          = {2021},\n  eprint        = {2110.14168},\n  archiveprefix = {arXiv}\n}\n\n@inproceedings{clark2018arc,\n  author    = {Clark, Peter and Cowhey, Isaac and Etzioni, Oren and Khot, Tushar and Sabharwal, Ashish and Schoenick, Carissa and Tafjord, Oyvind},\n  title     = {Think you have Solved Question Answering? {Try ARC}, the {AI2} Reasoning Challenge},\n  journal   = {arXiv preprint},\n  year      = {2018},\n  eprint    = {1803.05457},\n  archiveprefix = {arXiv}\n}\n\n@article{chen2021humaneval,\n  author        = {Chen, Mark and Tworek, Jerry and Jun, Heewoo and Yuan, Qiming and Pinto, Henrique Ponde de Oliveira and Kaplan, Jared and Edwards, Harri and Burda, Yuri and Joseph, Nicholas and Brockman, Greg and Ray, Alex and Puri, Raul and Krueger, Gretchen and Petrov, Michael and Khlaaf, Heidy and Sastry, Girish and Mishkin, Pamela and Chan, Brooke and Gray, Scott and Ryder, Nick and Pavlov, Mikhail and Power, Alethea and Kaiser, Lukasz and Bavarian, Mohammad and Winter, Clemens and Tillet, Philippe and Such, Felipe Petroski and Cummings, Dave and Plappert, Matthias and Chanez, Fotios and Barnes, Elizabeth and Herbert-Voss, Ariel and Guss, William Hebgen and Nichol, Alex and Paino, Alex and Tezak, Nikolas and Tang, Jie and Babuschkin, Igor and Balaji, Suchir and Jain, Shantanu and Saunders, William and Hesse, Christopher and Carr, Andrew N. and Leike, Jan and Achiam, Josh and Misra, Vedant and Morikawa, Evan and Radford, Alec and Knight, Matthew and Brundage, Miles and Murati, Mira and Mayer, Katie and Welinder, Peter and McGrew, Bob and Amodei, Dario and McCandlish, Sam and Sutskever, Ilya and Zaremba, Wojciech},\n  title         = {Evaluating Large Language Models Trained on Code},\n  journal       = {arXiv preprint},\n  year          = {2021},\n  eprint        = {2107.03374},\n  archiveprefix = {arXiv}\n}\n\n@inproceedings{chang2025benchmarking,"
  }
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-13T18:37:24.456486+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/references.bib has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-13T18:37:24.456734+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft && python3 -c \"\nimport re\n\nwith open('experiments.tex') as f:\n    tex = f.read()\n\n# Check 1: unclosed environments\nbegins = re.findall(r'\\\\\\\\begin\\{(\\w+)\\}', tex)\nends = re.findall(r'\\\\\\\\end\\{(\\w+)\\}', tex)\nprint('Environments opened:', begins)\nprint('Environments closed:', ends)\nprint('Match:', begins == ends)\n\n# Check 2: labels\nlabels = re.findall(r'\\\\\\\\label\\{([^}]+)\\}', tex)\nrefs = re.findall(r'\\\\\\\\ref\\{([^}]+)\\}', tex)\nerefs = re.findall(r'\\\\\\\\eqref\\{([^}]+)\\}', tex)\nprint()\nprint('Labels defined:', labels)\nprint('Refs used:', refs)\nprint('Eqrefs used:', erefs)\n\n# Check 3: baselines\nbaselines = re.findall(r'\\\\\\\\textbf\\{B\\d', tex)\nprint()\nprint('Baselines found:', len(baselines), 'entries')\n\n# Check 4: metrics\nmetrics = ['MAE', 'Coverage', 'Sharpness', 'Kendall', 'Spearman']\nfor m in metrics:\n    count = tex.count(m)\n    print(f'Metric {m}: {count} mentions')\n\n# Check 5: placeholders\nplaceholders = re.findall(r'\\\\\\\\textbf\\{\\[PLACEHOLDER[^}]*\\}', tex)\nprint()\nprint(f'Placeholders: {len(placeholders)}')\n\"\n",
  "description": "Validate experiments.tex structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Bash",
  "tool_args": {
    "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft && python3 -c \"\nimport re\n\nwith open('experiments.tex') as f:\n    tex = f.read()\n\n# Check 1: unclosed environments\nbegins = re.findall(r'\\\\\\\\begin\\{(\\w+)\\}', tex)\nends = re.findall(r'\\\\\\\\end\\{(\\w+)\\}', tex)\nprint('Environments opened:', begins)\nprint('Environments closed:', ends)\nprint('Match:', begins == ends)\n\n# Check 2: labels\nlabels = re.findall(r'\\\\\\\\label\\{([^}]+)\\}', tex)\nrefs = re.findall(r'\\\\\\\\ref\\{([^}]+)\\}', tex)\nerefs = re.findall(r'\\\\\\\\eqref\\{([^}]+)\\}', tex)\nprint()\nprint('Labels defined:', labels)\nprint('Refs used:', refs)\nprint('Eqrefs used:', erefs)\n\n# Check 3: baselines\nbaselines = re.findall(r'\\\\\\\\textbf\\{B\\d', tex)\nprint()\nprint('Baselines found:', len(baselines), 'entries')\n\n# Check 4: metrics\nmetrics = ['MAE', 'Coverage', 'Sharpness', 'Kendall', 'Spearman']\nfor m in metrics:\n    count = tex.count(m)\n    print(f'Metric {m}: {count} mentions')\n\n# Check 5: placeholders\nplaceholders = re.findall(r'\\\\\\\\textbf\\{\\[PLACEHOLDER[^}]*\\}', tex)\nprint()\nprint(f'Placeholders: {len(placeholders)}')\n\"\n",
    "description": "Validate experiments.tex structure"
  }
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-13T18:37:24.456964+00:00_

Environments opened: ['itemize', 'enumerate', 'equation', 'equation', 'equation', 'equation', 'table', 'tabular', 'table', 'tabular', 'table', 'tabular', 'figure', 'figure', 'figure']
Environments closed: ['itemize', 'enumerate', 'equation', 'equation', 'equation', 'equation', 'tabular', 'table', 'tabular', 'table', 'tabular', 'table', 'figure', 'figure', 'figure']
Match: False

Labels defined: ['sec:experiments', 'sec:exp_setup', 'sec:injection', 'sec:exp_signals', 'sec:exp_irt', 'sec:eval_protocol', 'eq:mae', 'eq:coverage', 'eq:sharpness', 'eq:kendall', 'sec:results', 'tab:main_results', 'tab:rrf_ablation', 'tab:k_sensitivity', 'fig:dose_response', 'fig:ci_width', 'fig:signal_survival']
Refs used: ['sec:stage1', 'sec:stage1', 'sec:inference', 'tab:main_results', 'tab:rrf_ablation', 'tab:k_sensitivity', 'fig:dose_response', 'fig:ci_width', 'fig:signal_survival', 'sec:signal_survival']
Eqrefs used: ['eq:rrf', 'eq:4pl', 'eq:measurement_error', 'eq:calibrated_mc', 'eq:calibrated_mc', 'eq:measurement_error']

Baselines found: 7 entries
Metric MAE: 6 mentions
Metric Coverage: 3 mentions
Metric Sharpness: 0 mentions
Metric Kendall: 3 mentions
Metric Spearman: 2 mentions

Placeholders: 29

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-13T18:37:24.457212+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_13/projects/contamcal-irt-calibration/artifacts/paper_draft/main.tex"
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-13T18:37:24.461647+00:00_

1	% EMNLP 2026 ARR submission — acl_latex template
2	% Download style files: https://github.com/acl-org/acl-style-files
3	\documentclass[11pt]{article}
4	% TODO: uncomment when acl2023.sty is placed in this directory
5	% \usepackage[hyperref]{acl2023}
6	\usepackage{times}
7	\usepackage[hyphens]{url}
8	\usepackage{graphicx}
9	\usepackage{amsmath,amssymb,amsfonts}
10	\usepackage{natbib}
11	\usepackage{booktabs}
12	\usepackage[margin=1in]{geometry}
13	\usepackage{xcolor}
14	\usepackage{microtype}
15	\usepackage{hyperref}
16	
17	\title{ContamCal: Post-Hoc Calibration of Benchmark Scores\\
18	under Training Data Contamination via\\
19	Contamination-Augmented Item Response Theory}
20	
21	\author{Anonymous ARR Submission}
22	
23	\begin{document}
24	\maketitle
25	
26	\begin{abstract}
27	\textbf{TODO: Abstract to be written after experiments.}
28	\end{abstract}
29	
30	\input{introduction}
31	
32	\input{related_work}
33	
34	\input{method}
35	
36	\input{experiments}
37	
38	% TODO: Discussion, Conclusion
39	
40	% TODO: switch to acl_natbib when style file is in place
41	\bibliographystyle{plainnat}
42	\bibliography{references}
43	
44	\end{document}
45	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_experiments-section_20260513T183138",
  "tool": "Read",
  "elapsed_ms": 4
}
```

</details>

---

### Assistant

_source line 29 · 2026-05-13T18:37:24.462082+00:00_

验证清单：

1. **LaTeX 语法** — 所有环境正确嵌套（15 open / 15 close，tabular 嵌套在 table 内）
2. **\ref / \label 一致** — 17 个 label 定义，所有 \ref 和 \eqref 指向已有 label（本文或 method.tex 中的 `eq:rrf`, `eq:4pl`, `eq:measurement_error`, `eq:calibrated_mc`, `sec:stage1`, `sec:inference`, `sec:signal_survival`）
3. **7 个 baselines** — B0–B6 全部有描述
4. **5 个 evaluation metrics** — Calibration error (MAE), Interval coverage, Interval sharpness, Ranking preservation (Kendall's τ), Dose-response monotonicity (Spearman ρ)，均有公式定义
5. **main.tex** — 已添加 `\input{experiments}`
6. **references.bib** — 已添加 4 个 benchmark 引用（MMLU, GSM8K, ARC, HumanEval）

Results 子节包含：
- Table `tab:main_results`：主校准结果（methods × benchmarks, MAE + coverage + τ）
- Table `tab:rrf_ablation`：RRF 消融（full vs drop-one vs single-signal AUC）
- Table `tab:k_sensitivity`：k-sensitivity
- Figure `fig:dose_response`：剂量-响应曲线
- Figure `fig:ci_width`：CI width vs noise level (exp-005)
- Figure `fig:signal_survival`：Signal survival under RL (exp-008)

所有定量结果用 `\textbf{[PLACEHOLDER: exp-XXX]}` 标注，数字占位用 `XX.X` / `X.XX` / `[TBD]`。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_writing_experiments-section_20260513T183138"
}
```

</details>

---
