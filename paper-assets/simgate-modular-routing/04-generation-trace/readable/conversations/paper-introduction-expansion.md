# paper introduction expansion

**Death Avoidance as the Dominant Routing Signal: A Counterfactual Analysis on ScienceWorld** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 17
- **Recorded user turns:** 0
- **Tool calls:** 8
- **Original source:** `logs/chats/worker_paper_introduction-expansion_20260515T101918.jsonl`
- **Structured JSON:** [`31b0215d0f0da5e3aae5.json`](../../sessions/31/31b0215d0f0da5e3aae5.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

17 recorded events

### Tool call

_source line 1 · 2026-05-15T10:20:41.465817+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-15T10:20:41.466270+00:00_

1	\section{Introduction}
2	
3	When a Qwen2.5-7B-Instruct agent attempts to boil water in ScienceWorld \cite{scienceworld-2022}, it must track temperature thresholds and container states across dozens of steps. Internal reasoning hallucinates these transitions---predicting water has boiled when the stove was never activated---triggering agent death with a $-100$ penalty. Deterministic external computation (environment simulators, code interpreters) eliminates such hallucinations via exact state transitions. The natural question: when should an agent route computation externally versus reasoning internally?
4	
5	Existing routing approaches \cite{toolformer-2024,art-2023,chameleon-2024} frame tool selection as a capability or efficiency decision---matching subtasks to tools that can solve them. This framing ignores a potentially dominant signal: routing to \emph{avoid catastrophic failure}. Understanding what routing actually learns requires counterfactual analysis, but the standard per-step oracle approach degenerates under sparse rewards. On ScienceWorld, where non-zero reward arrives only at episode termination, 97.4\% of steps (across 11 prescreened task types) produce identical scores regardless of modality---no step-level signal exists to train a router (\S\ref{sec:collection}). Keyword-based heuristics also fail structurally, as ScienceWorld actions lack science-specific terminology (\S\ref{sec:baselines}).
6	
7	We propose \emph{episode-level counterfactual analysis}: run complete episodes under pure-internal (ReAct~\cite{react-2023}) and pure-deterministic strategies, then compare episode outcomes to generate routing labels (\S\ref{sec:collection}). Across 11 ScienceWorld task types (245 episodes), the full deterministic advantage is $\Delta_{\text{full}} = +29.60$ points. Excluding death episodes, the gap collapses to $\Delta_{\text{nd}} = +2.84$; 75 of 95 non-tie labels (78.9\%) are driven by death asymmetry---a penalty-independent measure. The penalty-sensit
…[truncated 1092 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-15T10:20:41.466478+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "**/*.bib",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Glob",
  "tool_args": {
    "pattern": "**/*.bib",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-15T10:20:41.466618+00:00_

docs/paper/references.bib

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-15T10:20:41.466748+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/references.bib"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-15T10:20:41.466916+00:00_

1	@inproceedings{scienceworld-2022,
2	  title={ScienceWorld: Is Your Agent Smarter Than a 5th Grader?},
3	  author={Wang, Ruoyao and Jansen, Peter and C\^{o}t\'{e}, Marc-Alexandre and Ammanabrolu, Prithviraj},
4	  booktitle={Proceedings of the 2022 Conference on Empirical Methods in Natural Language Processing (EMNLP)},
5	  year={2022}
6	}
7	
8	@inproceedings{react-2023,
9	  title={ReAct: Synergizing Reasoning and Acting in Language Models},
10	  author={Yao, Shunyu and Zhao, Jeffrey and Yu, Dian and Du, Nan and Shafran, Izhak and Narasimhan, Karthik and Cao, Yuan},
11	  booktitle={International Conference on Learning Representations (ICLR)},
12	  year={2023}
13	}
14	
15	@inproceedings{toolformer-2024,
16	  title={Toolformer: Language Models Can Teach Themselves to Use Tools},
17	  author={Schick, Timo and Dwivedi-Yu, Jane and Dess\`{i}, Roberto and Raileanu, Roberta and Lomeli, Maria and Hambro, Eric and Zettlemoyer, Luke and Cancedda, Nicola and Scialom, Thomas},
18	  booktitle={Advances in Neural Information Processing Systems (NeurIPS)},
19	  year={2023}
20	}
21	
22	@article{art-2023,
23	  title={ART: Automatic Multi-step Reasoning and Tool-use for Large Language Models},
24	  author={Paranjape, Bhargavi and Lundberg, Scott and Singh, Sameer and Hajishirzi, Hannaneh and Zettlemoyer, Luke and Ribeiro, Marco Tulio},
25	  journal={arXiv preprint arXiv:2303.09014},
26	  year={2023}
27	}
28	
29	@inproceedings{chameleon-2024,
30	  title={Chameleon: Plug-and-Play Compositional Reasoning with Large Language Models},
31	  author={Lu, Pan and Peng, Baolin and Cheng, Hao and Galley, Michel and Chang, Kai-Wei and Wu, Ying Nian and Zhu, Song-Chun and Gao, Jianfeng},
32	  booktitle={Advances in Neural Information Processing Systems (NeurIPS)},
33	  year={2023}
34	}
35	
36	@article{retool-2026,
37	  title={ReTool: Reinforcement Learning for Strategic Tool Use in LLMs},
38	  author={Feng, Jiazhan and others},
39	  journal={arXiv preprint arXiv:2504.11536},
40	  year={2025}
41	}
…[truncated 5559 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-15T10:20:41.467161+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Glob",
  "tool_args": {
    "pattern": "**/*.tex",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-15T10:20:41.467298+00:00_

docs/paper/abstract.tex
docs/paper/introduction.tex
docs/paper/conclusion.tex
docs/paper/related_work.tex
docs/paper/discussion.tex
docs/paper/experiments.tex
docs/paper/method.tex
docs/paper/main.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-15T10:20:41.467415+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/main.tex"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-15T10:20:41.467603+00:00_

1	\documentclass[11pt]{article}
2	
3	\usepackage[review]{acl}
4	
5	\usepackage{times}
6	\usepackage{latexsym}
7	\usepackage[T1]{fontenc}
8	\usepackage[utf8]{inputenc}
9	\usepackage{microtype}
10	\usepackage{graphicx}
11	\usepackage{booktabs}
12	\usepackage{amsmath}
13	\usepackage{algorithm}
14	\usepackage{algorithmic}
15	
16	\title{Death Avoidance as the Dominant Routing Signal:\\A Counterfactual Analysis on ScienceWorld}
17	
18	\author{Anonymous}
19	
20	\begin{document}
21	\maketitle
22	
23	\input{abstract}
24	\input{introduction}
25	\input{method}
26	\input{experiments}
27	\input{related_work}
28	\input{conclusion}
29	
30	\section*{Limitations}
31	
32	Our analysis uses a single benchmark (ScienceWorld) with a single LLM backbone (Qwen2.5-7B-Instruct), and generalization to other interactive environments and model scales remains to be established. A preliminary cross-model pilot with Llama-3.1-8B-Instruct ($N{=}10$ episode pairs, 2 task types) shows directionally consistent death patterns (\S\ref{sec:cross-model}), but full-scale multi-model validation remains future work. The $-100$ death penalty may amplify DAF; environments with less catastrophic penalties could exhibit lower DAF, though the qualitative finding may still hold. On the 135 episodes (55.1\%) where neither strategy leads to catastrophic failure, deterministic computation retains a small advantage ($\Delta_{\text{nd}} = +2.84$), indicating non-zero routing signal beyond death avoidance. Our analysis covers 11 of 30 ScienceWorld task types; the remaining 19 (63\%) were excluded during prescreening because both strategies timed out on all seed variations within the 30-step budget, providing no counterfactual signal. These tasks likely require longer-horizon planning; increasing the step budget could surface additional routing signal whose composition may differ from the death-dominated pattern observed here. Stronger models (e.g., 70B-scale or reasoning-specialized) likely exhibit lower internal-strate
…[truncated 10608 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-15T10:20:41.467755+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex",
  "limit": "30"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/related_work.tex",
    "limit": "30"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-15T10:20:41.467900+00:00_

1	\section{Related Work}
2	
3	\paragraph{Tool Use and External Computation in LLMs.}
4	A growing body of work augments language models with external tools.
5	Toolformer \cite{toolformer-2024} teaches LLMs to insert API calls via self-supervised loss filtering, while ToolkenGPT \cite{toolkengpt-2023} represents tools as special tokens in the embedding space, enabling frozen models to invoke massive tool libraries.
6	ART \cite{art-2023} decomposes tasks into multi-step programs that interleave reasoning with tool calls, and Chameleon \cite{chameleon-2024} composes heterogeneous modules (search, code, vision) via LLM-generated programs.
7	ReTool \cite{retool-2026} applies reinforcement learning to let models discover when code execution is preferable to chain-of-thought.
8	These approaches focus on \emph{learning to use tools}; our work instead asks a prior question: \emph{what signal drives the decision to route to an external modality at all?}
9	
10	Recent concurrent studies sharpen this question from multiple angles.
11	\citet{tool-overuse-illusion-2026} identify a cognitive-illusion effect in which LLMs default to external tools even when internal knowledge suffices.
12	\citet{when2tool-2026} show that tool-call decisions are already encoded in hidden states before explicit reasoning occurs.
13	\citet{tool-use-tax-2026} quantify a ``tool-use tax''---cases where invoking a tool degrades rather than improves performance.
14	\citet{to-call-or-not-2026} propose a necessity--utility--affordability framework for deciding whether to call a tool.
15	Our counterfactual decomposition provides complementary, environment-grounded evidence: in ScienceWorld, ${\sim}90\%$ of the routing signal at $P{=}100$ traces to catastrophic-failure prevention rather than general utility, offering a concrete quantification that these frameworks currently lack.
16	
17	\paragraph{Adaptive Computation and Routing.}
18	Rather than adding new tools, a parallel line of research routes inputs to dif
…[truncated 1767 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-15T10:20:41.468140+00:00_

called Grep

<details open><summary>🔧 Tool call — Grep</summary>

```json
{
  "pattern": "\\\\(sub)?section|\\\\label\\{sec:",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
  "output_mode": "content",
  "glob": "*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Grep",
  "tool_args": {
    "pattern": "\\\\(sub)?section|\\\\label\\{sec:",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper",
    "output_mode": "content",
    "glob": "*.tex"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-15T10:20:41.468307+00:00_

docs/paper/related_work.tex:1:\section{Related Work}
docs/paper/experiments.tex:1:\section{Experiments}
docs/paper/experiments.tex:3:\subsection{Death Avoidance Decomposition}
docs/paper/experiments.tex:4:\label{sec:death-decomp}
docs/paper/experiments.tex:23:\subsection{Baselines}
docs/paper/experiments.tex:24:\label{sec:baselines}
docs/paper/experiments.tex:49:\subsection{Router Training as Diagnostic}
docs/paper/experiments.tex:50:\label{sec:router-diagnostic}
docs/paper/experiments.tex:64:\subsection{Cross-Model Verification}
docs/paper/experiments.tex:65:\label{sec:cross-model}
docs/paper/main.tex:30:\section*{Limitations}
docs/paper/main.tex:42:\section*{Ethics Statement}
docs/paper/main.tex:50:\section{Labeling Quality Audit}
docs/paper/main.tex:55:\section{Per-Task Decomposition}
docs/paper/main.tex:87:\section{Correlation Robustness}
docs/paper/main.tex:116:\section{Router Training Details}
docs/paper/main.tex:150:\section{Penalty Sensitivity Analysis}
docs/paper/conclusion.tex:1:\section{Conclusion}
docs/paper/discussion.tex:1:\section{Discussion}
docs/paper/discussion.tex:2:\label{sec:discussion}
docs/paper/method.tex:1:\section{Method}
docs/paper/method.tex:2:\label{sec:method}
docs/paper/method.tex:4:\subsection{Problem Setup}
docs/paper/method.tex:5:\label{sec:problem-setup}
docs/paper/method.tex:17:\subsection{Counterfactual Episode Collection}
docs/paper/method.tex:18:\label{sec:collection}
docs/paper/method.tex:36:\subsection{Episode-Level Labeling}
docs/paper/method.tex:37:\label{sec:labeling}
docs/paper/method.tex:83:\subsection{Death Avoidance Factor}
docs/paper/method.tex:84:\label{sec:daf}
docs/paper/introduction.tex:1:\section{Introduction}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Grep",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-15T10:20:41.468474+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex",
  "content": "\\section{Introduction}\n\nLarge language models deployed as interactive agents must repeatedly decide \\emph{how} to compute: reason internally, or delegate to an external tool.\nA Qwen2.5-7B-Instruct agent navigating ScienceWorld \\cite{scienceworld-2022}---a text-based science simulation with 30 task types---faces this choice at every step. Tracking temperature thresholds, container states, and multi-step procedures via internal reasoning is error-prone: the model may hallucinate that water has boiled when the stove was never activated, or that an object has been moved when the action was invalid. Deterministic external computation (environment simulators, code interpreters) eliminates such hallucinations via exact state transitions. The practical question for agent design is therefore: \\emph{when should an agent route computation externally versus reasoning internally?}\n\nExisting routing approaches frame this as a capability or efficiency decision.\nToolformer \\cite{toolformer-2024} teaches models to insert API calls when doing so reduces perplexity; ART \\cite{art-2023} decomposes tasks into tool-augmented programs; Chameleon \\cite{chameleon-2024} selects among heterogeneous modules (search, code, vision) per subtask.\nMore recent adaptive-computation methods route to different reasoning depths \\cite{cogrouter-2026,ares-2026} or model tiers \\cite{mtrouter-2026}.\nThe shared assumption is that routing signal stems from diverse sources---accuracy, latency, capability matching---and that a learned router can exploit this signal to improve over any fixed strategy.\nBut this assumption has never been systematically verified: \\emph{what actually drives the value of routing decisions in interactive environments?}\n\nWe find a surprisingly concentrated answer: \\textbf{death avoidance accounts for approximately 90\\% of the routing signal} in ScienceWorld.\nThe internal strategy's hallucination-induced failures trigger catastrophic agent death (a $-100$ penalty), while the deterministic strategy survives the same episodes.\nOnce death episodes are removed, the performance gap between strategies nearly vanishes.\n\nReaching this conclusion requires a methodological contribution.\nThe standard approach to generating routing labels---per-step oracle comparison---degenerates under sparse rewards.\nIn ScienceWorld, non-zero reward arrives only at episode termination; 97.4\\% of steps (across 11 prescreened task types) produce identical scores regardless of modality, leaving no step-level signal to learn from (\\S\\ref{sec:collection}).\nKeyword-based heuristics also fail structurally, as ScienceWorld actions lack science-specific terminology (\\S\\ref{sec:baselines}).\nWe instead propose \\emph{episode-level counterfactual analysis}: run complete episodes under pure-internal (ReAct \\cite{react-2023}) and pure-deterministic strategies, then compare episode outcomes to generate routing labels (\\S\\ref{sec:collection}).\n\nAcross 11 ScienceWorld task types (245 episode pairs), the full deterministic advantage is $\\Delta_{\\text{full}} = +29.60$ points.\nExcluding death episodes, the gap collapses to $\\Delta_{\\text{nd}} = +2.84$; 75 of 95 non-tie labels (78.9\\%) arise from death asymmetry---a penalty-independent measure.\nThe penalty-sensitive Death Avoidance Factor (DAF; \\S\\ref{sec:daf}) is 90.41\\% at the default penalty $P{=}100$, ranging from 46\\% ($P{=}10$) to 95\\% ($P{=}200$).\nThe per-task correlation between death-rate differential and performance gap is $r = 0.97$ ($p < 10^{-6}$, $n = 11$), confirming that death avoidance is the dominant mechanism across task types (\\S\\ref{sec:death-decomp}).\n\nTwo cross-context checks probe the specificity of this finding.\nFirst, a MATH Level~4--5 evaluation (300 problems), using a code interpreter as the deterministic modality, shows a directional reversal: internal reasoning outperforms code interpreter by $+4.3$ percentage points---the opposite direction from ScienceWorld.\nIn the absence of death risk, the deterministic advantage vanishes.\nSecond, a preliminary cross-model pilot with Llama-3.1-8B-Instruct ($N{=}10$ episode pairs, 2 task types) shows directionally consistent death patterns within ScienceWorld (\\S\\ref{sec:cross-model}), suggesting the phenomenon is not specific to a single model, though full-scale multi-model validation remains future work.\nA trained router (Qwen3-1.7B with LoRA) achieves balanced accuracy of only 57.6\\%, barely above chance, consistent with a signal so dominated by death avoidance that the residual learnable structure is thin (\\S\\ref{sec:router-diagnostic}).\n\nOur contributions are:\n\\begin{enumerate}\n    \\item \\textbf{Routing signal decomposition.}\n    We identify step-level oracle degeneracy in sparse-reward environments and introduce episode-level counterfactual analysis with the DAF metric, a methodology for quantifying what fraction of routing signal derives from catastrophic-failure avoidance (\\S\\ref{sec:collection}--\\ref{sec:daf}).\n\n    \\item \\textbf{Death avoidance dominance.}\n    On ScienceWorld, death asymmetry drives 78.9\\% of non-tie routing labels independent of penalty magnitude (DAF = 90.41\\% at $P{=}100$; $r = 0.97$ across task types), and a trained router does not significantly outperform always-deterministic (\\S\\ref{sec:death-decomp}--\\ref{sec:router-diagnostic}).\n\n    \\item \\textbf{Cross-environment negative contrast.}\n    On MATH ($N{=}300$), where death risk is absent, the routing signal reverses direction, providing evidence that the ScienceWorld pattern is driven by its failure structure rather than a universal property of routing (\\S\\ref{sec:discussion}).\n\n    \\item \\textbf{Cross-model directional evidence.}\n    A Llama-3.1-8B pilot shows consistent death-pattern direction, providing preliminary evidence that the finding is not model-specific (\\S\\ref{sec:cross-model}).\n\n    \\item \\textbf{Router training as diagnostic probe.}\n    Near-random balanced accuracy (57.6\\%) of a trained router confirms that the learnable signal beyond death avoidance is structurally thin (\\S\\ref{sec:router-diagnostic}).\n\\end{enumerate}\n\nThe remainder of the paper is organized as follows.\n\\S\\ref{sec:method} describes the counterfactual collection procedure, episode-level labeling, and the DAF metric.\n\\S\\ref{sec:death-decomp} presents the death avoidance decomposition and correlation analysis.\n\\S\\ref{sec:baselines}--\\ref{sec:cross-model} report baselines, router diagnostics, and cross-model verification.\n\\S\\ref{sec:discussion} discusses cross-environment evidence and implications.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex",
    "content": "\\section{Introduction}\n\nLarge language models deployed as interactive agents must repeatedly decide \\emph{how} to compute: reason internally, or delegate to an external tool.\nA Qwen2.5-7B-Instruct agent navigating ScienceWorld \\cite{scienceworld-2022}---a text-based science simulation with 30 task types---faces this choice at every step. Tracking temperature thresholds, container states, and multi-step procedures via internal reasoning is error-prone: the model may hallucinate that water has boiled when the stove was never activated, or that an object has been moved when the action was invalid. Deterministic external computation (environment simulators, code interpreters) eliminates such hallucinations via exact state transitions. The practical question for agent design is therefore: \\emph{when should an agent route computation externally versus reasoning internally?}\n\nExisting routing approaches frame this as a capability or efficiency decision.\nToolformer \\cite{toolformer-2024} teaches models to insert API calls when doing so reduces perplexity; ART \\cite{art-2023} decomposes tasks into tool-augmented programs; Chameleon \\cite{chameleon-2024} selects among heterogeneous modules (search, code, vision) per subtask.\nMore recent adaptive-computation methods route to different reasoning depths \\cite{cogrouter-2026,ares-2026} or model tiers \\cite{mtrouter-2026}.\nThe shared assumption is that routing signal stems from diverse sources---accuracy, latency, capability matching---and that a learned router can exploit this signal to improve over any fixed strategy.\nBut this assumption has never been systematically verified: \\emph{what actually drives the value of routing decisions in interactive environments?}\n\nWe find a surprisingly concentrated answer: \\textbf{death avoidance accounts for approximately 90\\% of the routing signal} in ScienceWorld.\nThe internal strategy's hallucination-induced failures trigger catastrophic agent death (a $-100$ penalty), while the deterministic strategy survives the same episodes.\nOnce death episodes are removed, the performance gap between strategies nearly vanishes.\n\nReaching this conclusion requires a methodological contribution.\nThe standard approach to generating routing labels---per-step oracle comparison---degenerates under sparse rewards.\nIn ScienceWorld, non-zero reward arrives only at episode termination; 97.4\\% of steps (across 11 prescreened task types) produce identical scores regardless of modality, leaving no step-level signal to learn from (\\S\\ref{sec:collection}).\nKeyword-based heuristics also fail structurally, as ScienceWorld actions lack science-specific terminology (\\S\\ref{sec:baselines}).\nWe instead propose \\emph{episode-level counterfactual analysis}: run complete episodes under pure-internal (ReAct \\cite{react-2023}) and pure-deterministic strategies, then compare episode outcomes to generate routing labels (\\S\\ref{sec:collection}).\n\nAcross 11 ScienceWorld task types (245 episode pairs), the full deterministic advantage is $\\Delta_{\\text{full}} = +29.60$ points.\nExcluding death episodes, the gap collapses to $\\Delta_{\\text{nd}} = +2.84$; 75 of 95 non-tie labels (78.9\\%) arise from death asymmetry---a penalty-independent measure.\nThe penalty-sensitive Death Avoidance Factor (DAF; \\S\\ref{sec:daf}) is 90.41\\% at the default penalty $P{=}100$, ranging from 46\\% ($P{=}10$) to 95\\% ($P{=}200$).\nThe per-task correlation between death-rate differential and performance gap is $r = 0.97$ ($p < 10^{-6}$, $n = 11$), confirming that death avoidance is the dominant mechanism across task types (\\S\\ref{sec:death-decomp}).\n\nTwo cross-context checks probe the specificity of this finding.\nFirst, a MATH Level~4--5 evaluation (300 problems), using a code interpreter as the deterministic modality, shows a directional reversal: internal reasoning outperforms code interpreter by $+4.3$ percentage points---the opposite direction from ScienceWorld.\nIn the absence of death risk, the deterministic advantage vanishes.\nSecond, a preliminary cross-model pilot with Llama-3.1-8B-Instruct ($N{=}10$ episode pairs, 2 task types) shows directionally consistent death patterns within ScienceWorld (\\S\\ref{sec:cross-model}), suggesting the phenomenon is not specific to a single model, though full-scale multi-model validation remains future work.\nA trained router (Qwen3-1.7B with LoRA) achieves balanced accuracy of only 57.6\\%, barely above chance, consistent with a signal so dominated by death avoidance that the residual learnable structure is thin (\\S\\ref{sec:router-diagnostic}).\n\nOur contributions are:\n\\begin{enumerate}\n    \\item \\textbf{Routing signal decomposition.}\n    We identify step-level oracle degeneracy in sparse-reward environments and introduce episode-level counterfactual analysis with the DAF metric, a methodology for quantifying what fraction of routing signal derives from catastrophic-failure avoidance (\\S\\ref{sec:collection}--\\ref{sec:daf}).\n\n    \\item \\textbf{Death avoidance dominance.}\n    On ScienceWorld, death asymmetry drives 78.9\\% of non-tie routing labels independent of penalty magnitude (DAF = 90.41\\% at $P{=}100$; $r = 0.97$ across task types), and a trained router does not significantly outperform always-deterministic (\\S\\ref{sec:death-decomp}--\\ref{sec:router-diagnostic}).\n\n    \\item \\textbf{Cross-environment negative contrast.}\n    On MATH ($N{=}300$), where death risk is absent, the routing signal reverses direction, providing evidence that the ScienceWorld pattern is driven by its failure structure rather than a universal property of routing (\\S\\ref{sec:discussion}).\n\n    \\item \\textbf{Cross-model directional evidence.}\n    A Llama-3.1-8B pilot shows consistent death-pattern direction, providing preliminary evidence that the finding is not model-specific (\\S\\ref{sec:cross-model}).\n\n    \\item \\textbf{Router training as diagnostic probe.}\n    Near-random balanced accuracy (57.6\\%) of a trained router confirms that the learnable signal beyond death avoidance is structurally thin (\\S\\ref{sec:router-diagnostic}).\n\\end{enumerate}\n\nThe remainder of the paper is organized as follows.\n\\S\\ref{sec:method} describes the counterfactual collection procedure, episode-level labeling, and the DAF metric.\n\\S\\ref{sec:death-decomp} presents the death avoidance decomposition and correlation analysis.\n\\S\\ref{sec:baselines}--\\ref{sec:cross-model} report baselines, router diagnostics, and cross-model verification.\n\\S\\ref{sec:discussion} discusses cross-environment evidence and implications.\n"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-15T10:20:41.468711+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_introduction-expansion_20260515T101918",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 17 · 2026-05-15T10:20:41.468886+00:00_

Introduction 已扩写完成。主要变更：

- **Motivation**: 展开了 LLM agent routing 问题的背景，明确指出现有方法假设 routing signal 来源多样但从未系统验证
- **Research question**: 显式提出 "what actually drives the value of routing decisions?"，并预告 ~90% death avoidance 的结论
- **Approach**: 解释了 step-level oracle 退化的问题，引出 episode-level counterfactual 方法论
- **Key findings**: 保留了所有关键数字（245 episodes, DAF=90.41%, 78.9%, r=0.97, MATH +4.3pp）
- **Contributions**: 从 2 条扩展为 5 条（C1-C5），覆盖 routing signal decomposition、death dominance、cross-environment contrast、cross-model pilot、router diagnostic
- **Paper structure**: 末尾添加了 section 导读
- MATH 和 Llama pilot 的 claim 强度控制为 "directional" / "preliminary"

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_introduction-expansion_20260515T101918"
}
```

</details>

---
