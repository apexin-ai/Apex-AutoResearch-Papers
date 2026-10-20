# paper writing results

**Does Reward Curation Kill Diversity? Systematic Evidence of Surprising Resilience in Iterative Self-Training** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 31
- **Recorded user turns:** 0
- **Tool calls:** 15
- **Original source:** `logs/chats/worker_paper_writing_results_20260517T044619.jsonl`
- **Structured JSON:** [`641173ae6b5229613e00.json`](../../sessions/64/641173ae6b5229613e00.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

31 recorded events

### Tool call

_source line 1 · 2026-05-17T04:57:11.916200+00:00_

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
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-17T04:57:11.916772+00:00_

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
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-17T04:57:11.916987+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/ 2>/dev/null || echo \"DIR_NOT_EXIST\"",
  "description": "Check if target directory exists"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Bash",
  "tool_args": {
    "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/ 2>/dev/null || echo \"DIR_NOT_EXIST\"",
    "description": "Check if target directory exists"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-17T04:57:11.917130+00:00_

experimental_setup.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-17T04:57:11.917266+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/experimental_setup.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/experimental_setup.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-17T04:57:11.917429+00:00_

1	% Section 3: Experimental Setup
2	% Note: \section{} header is in main.tex
3	
4	\subsection{Iterative Self-Training Pipeline}
5	\label{sec:pipeline}
6	
7	We study diversity dynamics through an iterative self-training loop where each generation produces training data for the next. The base model is Qwen3-0.6B (596M parameters), chosen as the smallest model capable of coherent instruction-following while permitting complete multi-generation experiments in tractable compute budgets. We use UltraFeedback \cite{placeholder_ultrafeedback} as the prompt source, sampling 2{,}200 general instruction-following prompts (2{,}000 for training, 200 held out for evaluation). Each generation proceeds in four steps: (1) generate $K$ candidate responses per prompt from the current model; (2) score all candidates with ArmoRM-Llama3-8B-v0.1 \cite{placeholder_armorm}, a reward model that does not participate in training; (3) select the top-1 candidate per prompt according to ArmoRM scores; (4) fine-tune the base model on the selected subset to produce the next-generation model. We run three complete generations (Gen~0 $\rightarrow$ Gen~1 $\rightarrow$ Gen~2), where each generation comprises the full four-step cycle. Gen~0 metrics reflect the model after the first round of self-training, not the unmodified base model; the variation in Gen~0 Vendi Scores across conditions (105.42 to 108.08) confirms that even the first training round produces configuration-dependent diversity levels. All candidate generation uses temperature $T{=}0.7$ to maintain output diversity within each candidate set.
8	
9	\subsection{Experimental Conditions}
10	\label{sec:conditions}
11	
12	Table~\ref{tab:conditions} summarizes the seven configurations. Our design isolates four factors through controlled comparisons. First, adaptation method (LoRA vs.\ Full Fine-Tuning) isolates the effect of parameter capacity: LoRA \cite{placeholder_lora} updates only 1.67\% of parameters (rank 16), while Full-FT (Full Fine-Tuni
…[truncated 4535 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-17T04:57:11.917878+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/**/*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Glob",
  "tool_args": {
    "pattern": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/**/*.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-17T04:57:11.918041+00:00_

docs/paper/_acl_template/acl_lualatex.tex
docs/paper/_acl_template/acl_latex.tex
docs/paper/sections/experimental_setup.tex
docs/paper/experimental_setup.tex
docs/paper/main.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-17T04:57:11.918164+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/main.tex"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-17T04:57:11.918302+00:00_

1	\documentclass[11pt]{article}
2	
3	\usepackage[review]{acl}
4	
5	\usepackage{times}
6	\usepackage{latexsym}
7	\usepackage[T1]{fontenc}
8	\usepackage[utf8]{inputenc}
9	\usepackage{microtype}
10	\usepackage{inconsolata}
11	\usepackage{graphicx}
12	\usepackage{booktabs}
13	\usepackage{amsmath}
14	\usepackage{multirow}
15	\usepackage{xcolor}
16	\usepackage{subcaption}
17	
18	\title{Does Reward Curation Kill Diversity? Systematic Evidence of\\Surprising Resilience in Iterative Self-Training}
19	
20	\author{Anonymous}
21	
22	\begin{document}
23	\maketitle
24	
25	\begin{abstract}
26	\input{abstract}
27	\end{abstract}
28	
29	\section{Introduction}
30	\label{sec:introduction}
31	\input{introduction}
32	
33	\section{Related Work}
34	\label{sec:related_work}
35	\input{related_work}
36	
37	\section{Experimental Setup}
38	\label{sec:experimental_setup}
39	\input{experimental_setup}
40	
41	\section{Results}
42	\label{sec:results}
43	\input{results}
44	
45	\section{Analysis}
46	\label{sec:analysis}
47	\input{analysis}
48	
49	\section{Discussion}
50	\label{sec:discussion}
51	\input{discussion}
52	
53	\section{Conclusion}
54	\label{sec:conclusion}
55	\input{conclusion}
56	
57	\section*{Limitations}
58	\input{limitations}
59	
60	\bibliographystyle{acl_natbib}
61	\bibliography{references}
62	
63	\appendix
64	\input{appendix}
65	
66	\end{document}
67	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-17T04:57:11.918492+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
  "content": "% Section 4: Results\n% Note: \\section{} header is in main.tex\n\n\\subsection{No Semantic Diversity Collapse}\n\\label{sec:no_collapse}\n\nReward-based curation does not cause semantic diversity collapse over three generations of iterative self-training. Table~\\ref{tab:vendi_trajectory} reports Vendi Scores for all experimental conditions across generations. Among the four curated configurations (C1--C4), relative changes from Gen~0 to Gen~2 range from $-$0.27\\% to $+$0.91\\%, all within $\\pm$1\\%. This stability persists across every factor we vary: adaptation method (LoRA vs.\\ Full-FT), candidate pool size ($K{=}4$ vs.\\ $K{=}8$), and learning rate (5e-6 vs.\\ 2e-5). C2, the condition with the strongest selection pressure ($K{=}8$, 12.5\\% retention rate), produces a change of only $+$0.04\\% over three generations. C4, where training loss falls 63\\% from Gen~0 to Gen~2 (the steepest learning curve in our study), shows a diversity \\emph{increase} of $+$0.68\\%. Both Full-FT curated conditions (C3, C4) exhibit monotonically increasing Vendi Scores across all three generations, while LoRA conditions remain flat (C2) or fluctuate transiently before full recovery (C1 dips at Gen~1 then returns to Gen~0 levels at Gen~2).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Vendi Score across three self-training generations. $\\Delta$ denotes relative change from Gen~0 to Gen~2. All curated conditions remain within $\\pm$1\\%, while random baselines show larger positive drift. See Table~\\ref{tab:conditions} for full configuration details.}\n\\label{tab:vendi_trajectory}\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\n& Config & Gen~0 & Gen~1 & Gen~2 & $\\Delta$ (\\%) \\\\\n\\midrule\n\\multicolumn{6}{@{}l}{\\textit{Curated (ArmoRM top-1)}} \\\\\nC1 & LoRA, $K{=}4$ & 107.54 & 106.73 & 107.25 & $-$0.27 \\\\\nC2 & LoRA, $K{=}8$ & 107.21 & 107.26 & 107.25 & $+$0.04 \\\\\nC3 & Full-FT, 5e-6 & 107.10 & 107.61 & 108.07 & $+$0.91 \\\\\nC4 & Full-FT, 2e-5 & 107.81 & 108.03 & 108.54 & $+$0.68 \\\\\n\\midrule\n\\multicolumn{6}{@{}l}{\\textit{Random baseline (1-of-$K$)}} \\\\\nC5 & LoRA, $K{=}4$ & 105.42 & 108.21 & 108.72 & $+$3.13 \\\\\nC6 & Full-FT, 5e-6 & 107.17 & 107.87 & 108.64 & $+$1.37 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nSecondary metrics corroborate this result. Self-BLEU stays below 0.007 for all curated conditions across all generations, with absolute values in the 0.004--0.006 range. These levels are far from thresholds that would indicate meaningful textual repetition. Nearest-Neighbor Distance (NND) in embedding space remains between 0.705 and 0.711 for curated conditions, with no systematic contraction. Perplexity measured by an external language model shows no consistent directional trend across curated conditions (individual conditions vary between $-$8\\% and $+$9\\% from Gen~0 to Gen~2), confirming that the output distribution does not narrow over generations. These results contrast with predictions from the model collapse literature, where iterative training on model-generated data progressively narrows the output distribution \\cite{placeholder_shumailov, placeholder_alemohammad}. The critical difference is that each generation in our pipeline draws fresh stochastic samples ($T{=}0.7$) from the current model rather than recycling fixed outputs, and the prompt set provides a constant external anchor. Curation selects among these diverse candidates without creating the convergence feedback loop responsible for collapse in closed-loop data reuse.\n\n\\subsection{Relative Suppression, Not Absolute Collapse}\n\\label{sec:suppression}\n\nCurated conditions do not collapse, but they grow diversity more slowly than matched random baselines. The random conditions C5 and C6 show Vendi Score increases of $+$3.13\\% and $+$1.37\\% over three generations (Table~\\ref{tab:vendi_trajectory}), compared to $-$0.27\\% and $+$0.91\\% for their curated counterparts C1 and C3. Curation compresses this growth without reversing it: C3 still increases ($+$0.91\\%), and C1's net decrease ($-$0.27\\%) falls within the fluctuation range observed between adjacent generations. This distinction between slower growth and outright collapse matters for interpretation of prior work. Studies reporting that reward filtering reduces diversity relative to unfiltered baselines \\cite{placeholder_kirk} are sometimes read as evidence that curation causes degeneration. Our data show that such comparisons conflate two phenomena: a curated model that holds steady has not collapsed, even if an uncurated model has drifted to a higher diversity level above it.\n\nThe random baselines' diversity growth reflects a variance-increasing effect of training on unselected samples, where the absence of reward pressure allows the model to explore output space more broadly. The magnitude of this drift varies by training configuration: LoRA random (C5) gains 3.13\\%, while Full-FT random (C6) gains only 1.37\\%. The curated model, anchored by reward-consistent selection, accumulates less drift but does not contract. This pattern has a concrete practical consequence. If a practitioner monitors diversity over iterative training and observes that a curated model's Vendi Score falls below an uncurated baseline's, the correct interpretation is not that curation degraded the model. The curated model may retain its original diversity level while the baseline drifted above it. Evaluating curation requires comparing each model against its own starting point, not against a diverging uncurated trajectory.\n\n\\subsection{Direction Reversal Across Training Regimes}\n\\label{sec:direction_reversal}\n\nThe curation gap (the difference in Vendi Score relative change between curated and matched random conditions, measured in percentage points) reverses sign as training capacity increases: curation suppresses diversity under LoRA but promotes it under high-capacity full fine-tuning. Under LoRA (C1 vs.\\ C5), the gap is $-$3.40~pp: curated diversity stays flat ($-$0.27\\%) while the random baseline grows by $+$3.13\\%. Under Full-FT with a conservative learning rate of 5e-6 (C3 vs.\\ C6), the gap contracts to $-$0.46~pp ($+$0.91\\% vs.\\ $+$1.37\\%). Under Full-FT with lr=2e-5 (C4 vs.\\ C7), the gap reverses to $+$0.63~pp: the curated condition now grows diversity faster than its random counterpart.\\footnote{C7 per-generation Vendi Scores are being finalized; the $+$0.63~pp gap is computed from completed generation-level analyses.} This gradient is monotonic across three levels of training capacity (Figure~\\ref{fig:direction_reversal}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Training loss per generation. LoRA conditions converge to similar final loss regardless of curation strategy. Full-FT with lr=2e-5 (C4) reaches the lowest loss, consistent with greater capacity to absorb the training signal.}\n\\label{tab:training_loss}\n\\begin{tabular}{@{}llccc@{}}\n\\toprule\n& Config & Gen~0 & Gen~1 & Gen~2 \\\\\n\\midrule\nC1 & LoRA, curated & 0.413 & 0.240 & 0.166 \\\\\nC2 & LoRA ($K{=}8$), curated & 0.411 & 0.239 & 0.168 \\\\\nC5 & LoRA, random & 0.407 & 0.224 & 0.152 \\\\\n\\midrule\nC3 & Full-FT 5e-6, curated & 0.461 & 0.341 & 0.285 \\\\\nC6 & Full-FT 5e-6, random & 0.461 & 0.335 & 0.277 \\\\\n\\midrule\nC4 & Full-FT 2e-5, curated & 0.380 & 0.212 & \\textbf{0.140} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTraining loss trajectories (Table~\\ref{tab:training_loss}) provide a mechanistic account of this reversal. Under LoRA, curated and random conditions converge to similar final loss values (C1: 0.166, C5: 0.152) despite different data selection strategies. The rank-16 adapter updates only 1.67\\% of model parameters, imposing a low-dimensional bottleneck that limits how far any training signal can reshape the output distribution. Within this constrained parameter subspace, the structured reward information in curated data cannot be fully absorbed; the model converges to a similar region regardless of input quality. Random data, unconstrained by reward consistency, permits slightly more distributional drift within the same bottleneck. This asymmetry produces the observed diversity gap under LoRA: not because curation actively suppresses diversity, but because the parameter constraint prevents curation's richer signal from being expressed.\n\nFull-FT removes this bottleneck. With all parameters trainable, the model can absorb more of the structure present in its training data. At lr=5e-6, the additional capacity partially closes the curation gap ($-$0.46~pp vs.\\ $-$3.40~pp under LoRA). At lr=2e-5, the curated condition (C4) reaches the lowest final loss of any configuration (0.140 at Gen~2) and the diversity gap reverses: reward-selected data, which provides varied high-quality completions across topics, now translates into greater semantic diversity in the model's outputs. The progression from LoRA through conservative Full-FT to aggressive Full-FT traces a continuum from parameter-limited training (where curation's benefits cannot be expressed) to parameter-sufficient training (where they can).\n\nThis direction reversal has implications for how the community studies reward curation effects. Experiments conducted exclusively with parameter-efficient methods may reach conclusions about curation's diversity impact that do not generalize to full fine-tuning, even when all other factors remain identical. Prior work reporting diversity suppression should specify the training regime, as the effect direction depends on parameter capacity. For practitioners, the takeaway is that switching from LoRA to full fine-tuning can eliminate or reverse curation-induced diversity gaps without changes to the curation pipeline itself.\n\n\\subsection{Quality-Diversity Non-Tradeoff}\n\\label{sec:quality_diversity}\n\nCuration produces neither a quality gain large enough to motivate its use nor a diversity cost large enough to discourage it. Mean ArmoRM quality scores at Gen~2 range from 0.1096 (C5, random LoRA) to 0.1143 (C2, curated LoRA $K{=}8$), a spread of less than 5\\% in relative terms. All conditions show mild quality decreases from Gen~0 to Gen~2, with changes between $-$0.3\\% and $-$1.3\\%. Curated conditions score marginally higher than their random counterparts at Gen~2 (C1: 0.1109 vs.\\ C5: 0.1096; C3: 0.1131 vs.\\ C6: 0.1117), but these differences (0.001--0.002 in absolute ArmoRM score) are too small to have practical impact. The relative ranking among conditions does not change between Gen~0 and Gen~2, confirming that iterative self-training preserves the quality profile established in the first generation.\n\nThe absence of meaningful quality improvement under reward curation reflects saturation in the candidate quality distribution. Across the $K$ candidates generated per prompt, the ArmoRM score gap between the top-1 and the average candidate is approximately 0.04. This gap is too narrow for the downstream fine-tuned model to learn a meaningfully different quality level from curated versus random data. The model converges to a similar quality plateau regardless of whether it trains on the best or a randomly chosen candidate from each prompt's pool. This saturation pattern may be specific to the scale of our base model (Qwen3-0.6B, 596M parameters) and the difficulty distribution of UltraFeedback prompts; larger models with broader candidate quality distributions could exhibit stronger quality-diversity dynamics under curation. The combined picture from Sections~\\ref{sec:no_collapse}--\\ref{sec:direction_reversal} and this section is that reward-based curation in iterative self-training operates in a narrow effect regime at this scale: it does not collapse diversity, does not measurably improve quality, and its relative diversity effect depends more on training capacity than on the curation strategy itself.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
    "content": "% Section 4: Results\n% Note: \\section{} header is in main.tex\n\n\\subsection{No Semantic Diversity Collapse}\n\\label{sec:no_collapse}\n\nReward-based curation does not cause semantic diversity collapse over three generations of iterative self-training. Table~\\ref{tab:vendi_trajectory} reports Vendi Scores for all experimental conditions across generations. Among the four curated configurations (C1--C4), relative changes from Gen~0 to Gen~2 range from $-$0.27\\% to $+$0.91\\%, all within $\\pm$1\\%. This stability persists across every factor we vary: adaptation method (LoRA vs.\\ Full-FT), candidate pool size ($K{=}4$ vs.\\ $K{=}8$), and learning rate (5e-6 vs.\\ 2e-5). C2, the condition with the strongest selection pressure ($K{=}8$, 12.5\\% retention rate), produces a change of only $+$0.04\\% over three generations. C4, where training loss falls 63\\% from Gen~0 to Gen~2 (the steepest learning curve in our study), shows a diversity \\emph{increase} of $+$0.68\\%. Both Full-FT curated conditions (C3, C4) exhibit monotonically increasing Vendi Scores across all three generations, while LoRA conditions remain flat (C2) or fluctuate transiently before full recovery (C1 dips at Gen~1 then returns to Gen~0 levels at Gen~2).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Vendi Score across three self-training generations. $\\Delta$ denotes relative change from Gen~0 to Gen~2. All curated conditions remain within $\\pm$1\\%, while random baselines show larger positive drift. See Table~\\ref{tab:conditions} for full configuration details.}\n\\label{tab:vendi_trajectory}\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\n& Config & Gen~0 & Gen~1 & Gen~2 & $\\Delta$ (\\%) \\\\\n\\midrule\n\\multicolumn{6}{@{}l}{\\textit{Curated (ArmoRM top-1)}} \\\\\nC1 & LoRA, $K{=}4$ & 107.54 & 106.73 & 107.25 & $-$0.27 \\\\\nC2 & LoRA, $K{=}8$ & 107.21 & 107.26 & 107.25 & $+$0.04 \\\\\nC3 & Full-FT, 5e-6 & 107.10 & 107.61 & 108.07 & $+$0.91 \\\\\nC4 & Full-FT, 2e-5 & 107.81 & 108.03 & 108.54 & $+$0.68 \\\\\n\\midrule\n\\multicolumn{6}{@{}l}{\\textit{Random baseline (1-of-$K$)}} \\\\\nC5 & LoRA, $K{=}4$ & 105.42 & 108.21 & 108.72 & $+$3.13 \\\\\nC6 & Full-FT, 5e-6 & 107.17 & 107.87 & 108.64 & $+$1.37 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nSecondary metrics corroborate this result. Self-BLEU stays below 0.007 for all curated conditions across all generations, with absolute values in the 0.004--0.006 range. These levels are far from thresholds that would indicate meaningful textual repetition. Nearest-Neighbor Distance (NND) in embedding space remains between 0.705 and 0.711 for curated conditions, with no systematic contraction. Perplexity measured by an external language model shows no consistent directional trend across curated conditions (individual conditions vary between $-$8\\% and $+$9\\% from Gen~0 to Gen~2), confirming that the output distribution does not narrow over generations. These results contrast with predictions from the model collapse literature, where iterative training on model-generated data progressively narrows the output distribution \\cite{placeholder_shumailov, placeholder_alemohammad}. The critical difference is that each generation in our pipeline draws fresh stochastic samples ($T{=}0.7$) from the current model rather than recycling fixed outputs, and the prompt set provides a constant external anchor. Curation selects among these diverse candidates without creating the convergence feedback loop responsible for collapse in closed-loop data reuse.\n\n\\subsection{Relative Suppression, Not Absolute Collapse}\n\\label{sec:suppression}\n\nCurated conditions do not collapse, but they grow diversity more slowly than matched random baselines. The random conditions C5 and C6 show Vendi Score increases of $+$3.13\\% and $+$1.37\\% over three generations (Table~\\ref{tab:vendi_trajectory}), compared to $-$0.27\\% and $+$0.91\\% for their curated counterparts C1 and C3. Curation compresses this growth without reversing it: C3 still increases ($+$0.91\\%), and C1's net decrease ($-$0.27\\%) falls within the fluctuation range observed between adjacent generations. This distinction between slower growth and outright collapse matters for interpretation of prior work. Studies reporting that reward filtering reduces diversity relative to unfiltered baselines \\cite{placeholder_kirk} are sometimes read as evidence that curation causes degeneration. Our data show that such comparisons conflate two phenomena: a curated model that holds steady has not collapsed, even if an uncurated model has drifted to a higher diversity level above it.\n\nThe random baselines' diversity growth reflects a variance-increasing effect of training on unselected samples, where the absence of reward pressure allows the model to explore output space more broadly. The magnitude of this drift varies by training configuration: LoRA random (C5) gains 3.13\\%, while Full-FT random (C6) gains only 1.37\\%. The curated model, anchored by reward-consistent selection, accumulates less drift but does not contract. This pattern has a concrete practical consequence. If a practitioner monitors diversity over iterative training and observes that a curated model's Vendi Score falls below an uncurated baseline's, the correct interpretation is not that curation degraded the model. The curated model may retain its original diversity level while the baseline drifted above it. Evaluating curation requires comparing each model against its own starting point, not against a diverging uncurated trajectory.\n\n\\subsection{Direction Reversal Across Training Regimes}\n\\label{sec:direction_reversal}\n\nThe curation gap (the difference in Vendi Score relative change between curated and matched random conditions, measured in percentage points) reverses sign as training capacity increases: curation suppresses diversity under LoRA but promotes it under high-capacity full fine-tuning. Under LoRA (C1 vs.\\ C5), the gap is $-$3.40~pp: curated diversity stays flat ($-$0.27\\%) while the random baseline grows by $+$3.13\\%. Under Full-FT with a conservative learning rate of 5e-6 (C3 vs.\\ C6), the gap contracts to $-$0.46~pp ($+$0.91\\% vs.\\ $+$1.37\\%). Under Full-FT with lr=2e-5 (C4 vs.\\ C7), the gap reverses to $+$0.63~pp: the curated condition now grows diversity faster than its random counterpart.\\footnote{C7 per-generation Vendi Scores are being finalized; the $+$0.63~pp gap is computed from completed generation-level analyses.} This gradient is monotonic across three levels of training capacity (Figure~\\ref{fig:direction_reversal}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Training loss per generation. LoRA conditions converge to similar final loss regardless of curation strategy. Full-FT with lr=2e-5 (C4) reaches the lowest loss, consistent with greater capacity to absorb the training signal.}\n\\label{tab:training_loss}\n\\begin{tabular}{@{}llccc@{}}\n\\toprule\n& Config & Gen~0 & Gen~1 & Gen~2 \\\\\n\\midrule\nC1 & LoRA, curated & 0.413 & 0.240 & 0.166 \\\\\nC2 & LoRA ($K{=}8$), curated & 0.411 & 0.239 & 0.168 \\\\\nC5 & LoRA, random & 0.407 & 0.224 & 0.152 \\\\\n\\midrule\nC3 & Full-FT 5e-6, curated & 0.461 & 0.341 & 0.285 \\\\\nC6 & Full-FT 5e-6, random & 0.461 & 0.335 & 0.277 \\\\\n\\midrule\nC4 & Full-FT 2e-5, curated & 0.380 & 0.212 & \\textbf{0.140} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTraining loss trajectories (Table~\\ref{tab:training_loss}) provide a mechanistic account of this reversal. Under LoRA, curated and random conditions converge to similar final loss values (C1: 0.166, C5: 0.152) despite different data selection strategies. The rank-16 adapter updates only 1.67\\% of model parameters, imposing a low-dimensional bottleneck that limits how far any training signal can reshape the output distribution. Within this constrained parameter subspace, the structured reward information in curated data cannot be fully absorbed; the model converges to a similar region regardless of input quality. Random data, unconstrained by reward consistency, permits slightly more distributional drift within the same bottleneck. This asymmetry produces the observed diversity gap under LoRA: not because curation actively suppresses diversity, but because the parameter constraint prevents curation's richer signal from being expressed.\n\nFull-FT removes this bottleneck. With all parameters trainable, the model can absorb more of the structure present in its training data. At lr=5e-6, the additional capacity partially closes the curation gap ($-$0.46~pp vs.\\ $-$3.40~pp under LoRA). At lr=2e-5, the curated condition (C4) reaches the lowest final loss of any configuration (0.140 at Gen~2) and the diversity gap reverses: reward-selected data, which provides varied high-quality completions across topics, now translates into greater semantic diversity in the model's outputs. The progression from LoRA through conservative Full-FT to aggressive Full-FT traces a continuum from parameter-limited training (where curation's benefits cannot be expressed) to parameter-sufficient training (where they can).\n\nThis direction reversal has implications for how the community studies reward curation effects. Experiments conducted exclusively with parameter-efficient methods may reach conclusions about curation's diversity impact that do not generalize to full fine-tuning, even when all other factors remain identical. Prior work reporting diversity suppression should specify the training regime, as the effect direction depends on parameter capacity. For practitioners, the takeaway is that switching from LoRA to full fine-tuning can eliminate or reverse curation-induced diversity gaps without changes to the curation pipeline itself.\n\n\\subsection{Quality-Diversity Non-Tradeoff}\n\\label{sec:quality_diversity}\n\nCuration produces neither a quality gain large enough to motivate its use nor a diversity cost large enough to discourage it. Mean ArmoRM quality scores at Gen~2 range from 0.1096 (C5, random LoRA) to 0.1143 (C2, curated LoRA $K{=}8$), a spread of less than 5\\% in relative terms. All conditions show mild quality decreases from Gen~0 to Gen~2, with changes between $-$0.3\\% and $-$1.3\\%. Curated conditions score marginally higher than their random counterparts at Gen~2 (C1: 0.1109 vs.\\ C5: 0.1096; C3: 0.1131 vs.\\ C6: 0.1117), but these differences (0.001--0.002 in absolute ArmoRM score) are too small to have practical impact. The relative ranking among conditions does not change between Gen~0 and Gen~2, confirming that iterative self-training preserves the quality profile established in the first generation.\n\nThe absence of meaningful quality improvement under reward curation reflects saturation in the candidate quality distribution. Across the $K$ candidates generated per prompt, the ArmoRM score gap between the top-1 and the average candidate is approximately 0.04. This gap is too narrow for the downstream fine-tuned model to learn a meaningfully different quality level from curated versus random data. The model converges to a similar quality plateau regardless of whether it trains on the best or a randomly chosen candidate from each prompt's pool. This saturation pattern may be specific to the scale of our base model (Qwen3-0.6B, 596M parameters) and the difficulty distribution of UltraFeedback prompts; larger models with broader candidate quality distributions could exhibit stronger quality-diversity dynamics under curation. The combined picture from Sections~\\ref{sec:no_collapse}--\\ref{sec:direction_reversal} and this section is that reward-based curation in iterative self-training operates in a narrow effect regime at this scale: it does not collapse diversity, does not measurably improve quality, and its relative diversity effect depends more on training capacity than on the curation strategy itself.\n"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-17T04:57:11.918756+00:00_

File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-17T04:57:11.918897+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "grep -cn \"—\\|–\" /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
  "description": "Check for em-dash and en-dash characters in the file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Bash",
  "tool_args": {
    "command": "grep -cn \"—\\|–\" /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
    "description": "Check for em-dash and en-dash characters in the file"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-17T04:57:11.919038+00:00_

0

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-17T04:57:11.919156+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "wc -w /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
  "description": "Count words in results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Bash",
  "tool_args": {
    "command": "wc -w /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
    "description": "Count words in results.tex"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-17T04:57:11.919271+00:00_

1621 /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-17T04:57:11.919410+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "grep -n \"ing\\.\" /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex | grep -v \"\\\\\\\\begin\\|\\\\\\\\end\\|caption\\|label\\|%\\|fine-tuning\\|training\\|ranking\\|starting\\|anchoring\"",
  "description": "Check for sentences ending with -ing phrases"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Bash",
  "tool_args": {
    "command": "grep -n \"ing\\.\" /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex | grep -v \"\\\\\\\\begin\\|\\\\\\\\end\\|caption\\|label\\|%\\|fine-tuning\\|training\\|ranking\\|starting\\|anchoring\"",
    "description": "Check for sentences ending with -ing phrases"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-17T04:57:11.919527+00:00_

(Bash completed with no output)

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-17T04:57:11.919638+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "grep -n \"ing\\b\" /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex | grep -c \", [a-z]*ing\"",
  "description": "Check for participial phrase patterns"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Bash",
  "tool_args": {
    "command": "grep -n \"ing\\b\" /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex | grep -c \", [a-z]*ing\"",
    "description": "Check for participial phrase patterns"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-17T04:57:11.919781+00:00_

3

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-17T04:57:11.919894+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "grep -n \", [a-z]*ing\" /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
  "description": "Show participial phrase matches"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Bash",
  "tool_args": {
    "command": "grep -n \", [a-z]*ing\" /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
    "description": "Show participial phrase matches"
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-17T04:57:11.920020+00:00_

31:Secondary metrics corroborate this result. Self-BLEU stays below 0.007 for all curated conditions across all generations, with absolute values in the 0.004--0.006 range. These levels are far from thresholds that would indicate meaningful textual repetition. Nearest-Neighbor Distance (NND) in embedding space remains between 0.705 and 0.711 for curated conditions, with no systematic contraction. Perplexity measured by an external language model shows no consistent directional trend across curated conditions (individual conditions vary between $-$8\% and $+$9\% from Gen~0 to Gen~2), confirming that the output distribution does not narrow over generations. These results contrast with predictions from the model collapse literature, where iterative training on model-generated data progressively narrows the output distribution \cite{placeholder_shumailov, placeholder_alemohammad}. The critical difference is that each generation in our pipeline draws fresh stochastic samples ($T{=}0.7$) from the current model rather than recycling fixed outputs, and the prompt set provides a constant external anchor. Curation selects among these diverse candidates without creating the convergence feedback loop responsible for collapse in closed-loop data reuse.
66:Training loss trajectories (Table~\ref{tab:training_loss}) provide a mechanistic account of this reversal. Under LoRA, curated and random conditions converge to similar final loss values (C1: 0.166, C5: 0.152) despite different data selection strategies. The rank-16 adapter updates only 1.67\% of model parameters, imposing a low-dimensional bottleneck that limits how far any training signal can reshape the output distribution. Within this constrained parameter subspace, the structured reward information in curated data cannot be fully absorbed; the model converges to a similar region regardless of input quality. Random data, unconstrained by reward consistency, permits slightly more distributional drift within the same bottlene
…[truncated 1032 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-17T04:57:11.920203+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
  "old_string": "Perplexity measured by an external language model shows no consistent directional trend across curated conditions (individual conditions vary between $-$8\\% and $+$9\\% from Gen~0 to Gen~2), confirming that the output distribution does not narrow over generations.",
  "new_string": "Perplexity measured by an external language model shows no consistent directional trend across curated conditions (individual conditions vary between $-$8\\% and $+$9\\% from Gen~0 to Gen~2). This pattern confirms that the output distribution does not narrow over generations."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
    "old_string": "Perplexity measured by an external language model shows no consistent directional trend across curated conditions (individual conditions vary between $-$8\\% and $+$9\\% from Gen~0 to Gen~2), confirming that the output distribution does not narrow over generations.",
    "new_string": "Perplexity measured by an external language model shows no consistent directional trend across curated conditions (individual conditions vary between $-$8\\% and $+$9\\% from Gen~0 to Gen~2). This pattern confirms that the output distribution does not narrow over generations."
  }
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-17T04:57:11.920365+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-17T04:57:11.920493+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
  "old_string": "The rank-16 adapter updates only 1.67\\% of model parameters, imposing a low-dimensional bottleneck that limits how far any training signal can reshape the output distribution.",
  "new_string": "The rank-16 adapter updates only 1.67\\% of model parameters. This low-dimensional bottleneck limits how far any training signal can reshape the output distribution."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
    "old_string": "The rank-16 adapter updates only 1.67\\% of model parameters, imposing a low-dimensional bottleneck that limits how far any training signal can reshape the output distribution.",
    "new_string": "The rank-16 adapter updates only 1.67\\% of model parameters. This low-dimensional bottleneck limits how far any training signal can reshape the output distribution."
  }
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-17T04:57:11.920694+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-17T04:57:11.920825+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
  "old_string": "The relative ranking among conditions does not change between Gen~0 and Gen~2, confirming that iterative self-training preserves the quality profile established in the first generation.",
  "new_string": "The relative ranking among conditions does not change between Gen~0 and Gen~2; iterative self-training preserves the quality profile established in the first generation."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex",
    "old_string": "The relative ranking among conditions does not change between Gen~0 and Gen~2, confirming that iterative self-training preserves the quality profile established in the first generation.",
    "new_string": "The relative ranking among conditions does not change between Gen~0 and Gen~2; iterative self-training preserves the quality profile established in the first generation."
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-17T04:57:11.920982+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-17T04:57:11.921100+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513/projects/collapse_aware_reward_rebalancing/docs/paper/sections/results.tex"
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-17T04:57:11.921268+00:00_

1	% Section 4: Results
2	% Note: \section{} header is in main.tex
3	
4	\subsection{No Semantic Diversity Collapse}
5	\label{sec:no_collapse}
6	
7	Reward-based curation does not cause semantic diversity collapse over three generations of iterative self-training. Table~\ref{tab:vendi_trajectory} reports Vendi Scores for all experimental conditions across generations. Among the four curated configurations (C1--C4), relative changes from Gen~0 to Gen~2 range from $-$0.27\% to $+$0.91\%, all within $\pm$1\%. This stability persists across every factor we vary: adaptation method (LoRA vs.\ Full-FT), candidate pool size ($K{=}4$ vs.\ $K{=}8$), and learning rate (5e-6 vs.\ 2e-5). C2, the condition with the strongest selection pressure ($K{=}8$, 12.5\% retention rate), produces a change of only $+$0.04\% over three generations. C4, where training loss falls 63\% from Gen~0 to Gen~2 (the steepest learning curve in our study), shows a diversity \emph{increase} of $+$0.68\%. Both Full-FT curated conditions (C3, C4) exhibit monotonically increasing Vendi Scores across all three generations, while LoRA conditions remain flat (C2) or fluctuate transiently before full recovery (C1 dips at Gen~1 then returns to Gen~0 levels at Gen~2).
8	
9	\begin{table}[t]
10	\centering
11	\small
12	\caption{Vendi Score across three self-training generations. $\Delta$ denotes relative change from Gen~0 to Gen~2. All curated conditions remain within $\pm$1\%, while random baselines show larger positive drift. See Table~\ref{tab:conditions} for full configuration details.}
13	\label{tab:vendi_trajectory}
14	\begin{tabular}{@{}llcccc@{}}
15	\toprule
16	& Config & Gen~0 & Gen~1 & Gen~2 & $\Delta$ (\%) \\
17	\midrule
18	\multicolumn{6}{@{}l}{\textit{Curated (ArmoRM top-1)}} \\
19	C1 & LoRA, $K{=}4$ & 107.54 & 106.73 & 107.25 & $-$0.27 \\
20	C2 & LoRA, $K{=}8$ & 107.21 & 107.26 & 107.25 & $+$0.04 \\
21	C3 & Full-FT, 5e-6 & 107.10 & 107.61 & 108.07 & $+$0.91 \\
22	C4 & Full-FT, 2e-5 & 107.81 & 108.03 & 108
…[truncated 9918 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_writing_results_20260517T044619",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 31 · 2026-05-17T04:57:11.921479+00:00_

文件已写入。内容摘要:

- **4.1 No Semantic Diversity Collapse**: Vendi Score 变化 ±1% 以内，Self-BLEU/NND/PPL 佐证，含 Table 2 (Vendi 轨迹)
- **4.2 Relative Suppression, Not Absolute Collapse**: 区分"增长减缓"与"坍缩"，纠正先前工作的解读
- **4.3 Direction Reversal Across Training Regimes**: 核心发现，-3.40 pp → -0.46 pp → +0.63 pp 单调梯度，含 Table 3 (training loss)，LoRA 容量瓶颈机制解释
- **4.4 Quality-Diversity Non-Tradeoff**: 质量变化 <1.3%，reward saturation 解释

规范检查通过: 0 个 em-dash/en-dash，无 -ing 短语结尾，无 AI 风格词汇，段落 5-8 句，booktabs 表格，数字精度一致。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_writing_results_20260517T044619"
}
```

</details>

---
