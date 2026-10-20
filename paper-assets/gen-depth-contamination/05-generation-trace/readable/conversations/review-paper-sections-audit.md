# review paper sections audit

**Generational Depth Estimation of Recursive Synthetic Text: Measuring the Discrimination Boundary** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 23
- **Recorded user turns:** 0
- **Tool calls:** 11
- **Original source:** `logs/chats/worker_review_paper_sections_audit_20260513T215258.jsonl`
- **Structured JSON:** [`377070ad659d11bb5f0b.json`](../../sessions/37/377070ad659d11bb5f0b.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

23 recorded events

### Tool call

_source line 1 · 2026-05-13T22:02:08.572180+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file",
  "max_results": "2"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file",
    "max_results": "2"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-13T22:02:08.572540+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-13T22:02:08.572976+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "find /home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper -type f -name \"*.tex\" 2>/dev/null | sort",
  "description": "Find all tex files in paper directory"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Bash",
  "tool_args": {
    "command": "find /home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper -type f -name \"*.tex\" 2>/dev/null | sort",
    "description": "Find all tex files in paper directory"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-13T22:02:08.573664+00:00_

/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/method.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/related_work.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-13T22:02:08.573874+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-13T22:02:08.574059+00:00_

1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Web-scale text corpora are increasingly contaminated by synthetic content that has itself been generated from earlier synthetic content.
5	Each pass through a language model constitutes a lossy channel: first-generation synthetic text retains much of the information structure of its human-written source, but by the fourth generation the output is qualitatively different---tail modes vanish, lexical diversity contracts, and surprisal distributions flatten~\cite{shumailov2024collapse, dohmatob2024model}.
6	This recursive degradation is not merely a theoretical concern; as synthetic text proliferates on the open web, training corpora inevitably ingest documents at varying generational depths, amplifying the risk of model collapse in downstream systems.
7	Yet the dominant paradigm in synthetic text detection treats all machine-generated text identically: a document is classified as human or synthetic, with no regard for how many rounds of recursive generation it has undergone.
8	This binary framing discards the generational depth dimension entirely.
9	
10	The gap cuts across three research communities.
11	Binary detection methods---including DivEye~\cite{basani2026diveye}, Min-K\%++~\cite{zhang2024minkpp}, and CoDeC~\cite{zawalski2026codec}---achieve strong human-versus-machine separation but produce no depth estimate.
12	The model collapse literature provides macro-level characterizations of recursive degradation: Shumailov et al.~\cite{shumailov2024collapse} demonstrated irreversible tail loss, Alemohammad et al.~\cite{alemohammad2024selfconsuming} proved convergence to a fixed point, and Schaeffer et al.~\cite{schaeffer2025position} organized the field into a taxonomy of eight definitions---yet none of these works provides a tool for estimating the generational depth of an individual text.
13	Data selection methods such as DSIR~\cite{xie2023dsir}, D4~\cite{tirumala2024d4}, and DoReMi~\cite{xie2024doremi} perfor
…[truncated 5334 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-13T22:02:08.574347+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/related_work.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-13T22:02:08.574538+00:00_

1	\section{Related Work}
2	\label{sec:related_work}
3	
4	\paragraph{Model Collapse and Recursive Generation.}
5	Training on model-generated data can cause progressive distribution shift known as \emph{model collapse}.
6	Shumailov et al.~\cite{shumailov2024collapse} showed that iteratively training language models on their own outputs leads to irreversible tail-distribution degradation, with minority modes vanishing across generations.
7	Alemohammad et al.~\cite{alemohammad2024selfconsuming} formalized this for self-consuming generative models, proving convergence to a fixed point under mild regularity conditions.
8	Dohmatob et al.~\cite{dohmatob2024model} derived scaling laws for collapse, demonstrating that tail probability mass is lost at rates predictable from model and data scale.
9	Schaeffer et al.~\cite{schaeffer2025position} organized the fragmented literature into a taxonomy of eight definitions across three families.
10	Our $\Kstar$ aligns with their Family~B (distributional deformation), specifically D4 (collapsing variance) and D6 (mode entanglement)---the features that degrade most rapidly in our experiments are precisely variance-based surprisal measures.
11	Kazdan et al.~\cite{kazdan2025collapse} distinguished \emph{replace} and \emph{accumulate} regimes: in the replace regime each generation completely supplants its predecessor, producing faster collapse.
12	Our prompt-chain protocol operates in the replace regime, so $\Kempirical = 2$ is a conservative lower bound; the accumulate regime would yield slower degradation and higher $\Kstar$.
13	Shi et al.~\cite{shi2025generalization} identified a generalization-to-memorization transition in recursively trained models, providing cross-modal evidence that information loss is progressive.
14	These works characterize the macro dynamics of collapse but do not provide tools for per-text generational depth estimation.
15	
16	\paragraph{Binary Synthetic Text Detection.}
17	Distinguishing machine-generated from h
…[truncated 4246 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-13T22:02:08.574687+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/method.tex"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-13T22:02:08.575046+00:00_

1	\section{Method}
2	\label{sec:method}
3	
4	% === Pipeline figure placeholder ===
5	% \begin{figure}[t]
6	% \centering
7	% \includegraphics[width=\columnwidth]{figures/pipeline.pdf}
8	% \caption{Overview of the generational depth estimation pipeline. Seed documents from C4 are recursively passed through a generation operator $G_\delta$ to produce a depth chain $X \to Y_1 \to \cdots \to Y_K$. Statistical features extracted by an external scorer model are fed to the OBD-LightGBM classifier for depth prediction.}
9	% \label{fig:pipeline}
10	% \end{figure}
11	
12	\subsection{Problem Formulation}
13	\label{sec:formulation}
14	
15	Recursive text generation naturally forms an iterated lossy channel.
16	Let $X$ denote an original human-written document drawn from a source distribution $\mathcal{D}$.
17	A generation operator $G_\delta = \text{LLM} + \delta$, parameterized by a decoding strategy $\delta$ (e.g., nucleus sampling with top-$p$ and temperature $T$), produces successive generations:
18	\begin{equation}
19	  X \to Y_1 \to Y_2 \to \cdots \to Y_K, \quad Y_k = G_\delta(Y_{k-1}),
20	  \label{eq:markov}
21	\end{equation}
22	where $Y_0 \triangleq X$.
23	The sequence $\{Y_k\}_{k=0}^K$ forms a Markov chain, since each generation depends only on its immediate predecessor.
24	
25	By the Data Processing Inequality (DPI), mutual information between the original document and successive generations is monotonically non-increasing:
26	\begin{equation}
27	  I(X; Y_1) \geq I(X; Y_2) \geq \cdots \geq 0.
28	  \label{eq:dpi}
29	\end{equation}
30	Since mutual information is bounded below by zero, this monotone sequence converges: the original signal degrades monotonically across generations.
31	Moreover, when the generation operator defines a finite-state Markov chain, the marginal distributions of adjacent generations converge to a shared stationary distribution, so that any classifier's ability to distinguish depth $k$ from depth $k{+}1$ must eventually degrade to chance.
32	Togethe
…[truncated 11402 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-13T22:02:08.575216+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/experiments_c1.tex"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-13T22:02:08.575447+00:00_

1	\section{Experiments}
2	\label{sec:experiments}
3	
4	We evaluate generational depth estimation on four model configurations:
5	Pythia-1.4B and OLMo-1B in continuation mode, and Qwen2.5-1.5B-Instruct in both rewrite and continuation modes.
6	All experiments use the OBD-LightGBM classifier with the 15-dimensional feature set described in Section~3.
7	Each configuration uses a balanced corpus of 5{,}000 texts per depth level (generations 0--5).
8	We organize results around four questions:
9	(1)~Does $\Kempirical = 2$ hold across configurations?
10	(2)~Do depth classifiers transfer across models?
11	(3)~Is the feature degradation ordering model-independent?
12	(4)~How does generation mode affect detectability?
13	
14	%% ====================================================================
15	\subsection{$\Kstar = 2$ Across All Configurations}
16	\label{sec:kstar_boundary}
17	
18	Table~\ref{tab:kstar_ci} reports pairwise $\auc$ for adjacent depth pairs
19	across all four configurations, with bootstrap 95\% confidence intervals
20	(1{,}000 resamples) and permutation-test $p$-values for the critical 1v2
21	and 2v3 boundaries.
22	
23	\begin{table}[t]
24	\centering
25	\small
26	\caption{Pairwise $\auc$ for adjacent depth pairs.  Bootstrap 95\% CIs
27	and permutation $p$-values shown for the $\Kstar$ boundary rows (1v2,
28	2v3).  $\Kempirical = 2$ requires 1v2 $\text{CI}_\text{low} > \theta$
29	and 2v3 $\text{CI}_\text{high} < \theta$ with $\theta = 0.60$.
30	All 0v1 permutation $p \leq 0.002$ (Qwen-cont 0v1 not computed due to $\auc > 0.997$; conservatively inferred).}
31	\label{tab:kstar_ci}
32	\begin{tabular}{lcccc}
33	\toprule
34	 & Qwen-rw & Pythia & OLMo & Qwen-cont \\
35	\midrule
36	0v1 & 0.9956 & 0.9932 & 0.9970 & 0.9972 \\[4pt]
37	1v2 & 0.6955 & 0.6539 & 0.6145 & 0.6112 \\
38	{\footnotesize CI}
39	  & {\footnotesize [.6859,\,.7041]}
40	  & {\footnotesize [.6454,\,.6630]}
41	  & {\footnotesize [.6045,\,.6247]}
42	  & {\footnotesize [.6015,\,.6213]} \\
43	{\footnotesi
…[truncated 13477 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-13T22:02:08.575599+00:00_

called mcp__agent-ml-research__read_registry

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry</summary>

```json
{
  "project": "gen-depth-contamination",
  "limit": "0",
  "fields": "['*']"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "mcp__agent-ml-research__read_registry",
  "tool_args": {
    "project": "gen-depth-contamination",
    "limit": "0",
    "fields": "['*']"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-13T22:02:08.576116+00:00_

{"result":"{\"success\": true, \"data\": {\"experiments\": {\"exp_006_graduated_filtering\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:25:52.364Z\", \"updated_at\": \"2026-05-13T21:19:21.632Z\", \"hypothesis\": \"K*-aware graduated filtering (exploiting human/gen-1/gen-2+ trichotomy) yields better downstream LM quality than binary filtering on MMLU and HellaSwag. 6 strategies × 5 seeds × α sweep.\", \"parent\": \"exp_003_decoding_ablation\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo 2>/dev/null && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && cd /root/autodl-tmp/gen-depth-contamination && bash scripts/run_exp006.sh\\\"\", \"server\": \"westc-26893\", \"gpu\": [\"cuda:0\"], \"pid\": \"46129\", \"log_path\": \"~/runs/gen-depth-contamination/exp_006_graduated_filtering.log\", \"submitted_at\": \"2026-05-13T21:02:48.327Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/gen-depth-contamination/data/\", \"data_count\": 30000, \"model_name\": \"Qwen/Qwen2.5-1.5B-Instruct\", \"seed\": \"42,123,456,789,1024\", \"checkpoint_source\": \"Qwen/Qwen2.5-1.5B-Instruct (base model, LoRA CPT per strategy)\", \"eval_data\": \"lm-eval-harness: MMLU (14042 test) + HellaSwag (10042 val)\"}}, \"exp_007_bootstrap_ci\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T03:45:50.948Z\", \"updated_at\": \"2026-05-13T21:15:42.372Z\", \"hypothesis\": \"K* 统计严谨性验证：bootstrap 95% CI 和 permutation test 确认 K*=2 在三个模型族上统计显著\", \"spec\": {\"command\": \"python scripts/bootstrap_ci.py --data_dirs results_exp001_pythia results_exp002_olmo data --labels Pythia-1.4B OLMo-1B Qwen-1.5B --output artifacts/bootstrap_ci_results.json\
…[truncated 25463 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "mcp__agent-ml-research__read_registry",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-13T22:02:08.576517+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "**/*.bib",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Glob",
  "tool_args": {
    "pattern": "**/*.bib",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-13T22:02:08.576667+00:00_

docs/paper/references.bib

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-13T22:02:08.576889+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "figures/*",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Glob",
  "tool_args": {
    "pattern": "figures/*",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-13T22:02:08.577044+00:00_

No files found

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-13T22:02:08.577162+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/main.tex"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-13T22:02:08.577303+00:00_

1	% EMNLP 2026 Main — ARR May 2026
2	% Generational Depth Contamination
3	% Template: standard article class (swap to acl.sty for final submission)
4	\documentclass[11pt,a4paper]{article}
5	\usepackage[margin=1in]{geometry}
6	\usepackage{times}
7	\usepackage{graphicx}
8	\usepackage{amsmath}
9	\usepackage{amssymb}
10	\usepackage{amsthm}
11	\usepackage{booktabs}
12	\usepackage{multirow}
13	\usepackage{xcolor}
14	\usepackage{hyperref}
15	\usepackage[numbers]{natbib}
16	\usepackage{enumitem}
17	\usepackage{subcaption}
18	
19	\newcommand{\Kstar}{K^*}
20	\newcommand{\Kempirical}{K^*_{\text{empirical}}}
21	\newcommand{\Ktheory}{K^*_{\text{theory}}}
22	\newcommand{\auc}{\text{AUC}}
23	\newcommand{\jsd}{\text{JSD}}
24	
25	\title{Generational Depth Estimation of Recursive Synthetic Text:\\Measuring the Discrimination Boundary}
26	
27	\author{Anonymous}
28	
29	\begin{document}
30	\maketitle
31	
32	% === Abstract (DEFERRED) ===
33	% \begin{abstract}
34	% [TODO: Write after C3 results available]
35	% \end{abstract}
36	
37	% === Section 1: Introduction ===
38	\input{introduction}
39	
40	% === Section 2: Related Work ===
41	\input{related_work}
42	
43	% === Section 3: Method ===
44	\input{method}
45	
46	% === Section 4: Experiments ===
47	\input{experiments_c1}
48	
49	% === Section 4.x: Graduated Filtering (DEFERRED) ===
50	% \input{experiments_c3}
51	
52	% === Section 5: Conclusion (DEFERRED) ===
53	% \input{conclusion}
54	
55	\bibliographystyle{plainnat}
56	\bibliography{references}
57	
58	\end{document}
59	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-13T22:02:08.577485+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_7/projects/gen-depth-contamination/docs/paper/references.bib"
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-13T22:02:08.577655+00:00_

1	% === References for gen-depth-contamination ===
2	% Source: literature_map.yaml — PENDING formal verification via verify_references
3	% NOTE: All entries require online verification before final submission
4	
5	% === Must-Cite ===
6	
7	@inproceedings{drayson2025,
8	  title={Machine-Generated Text Detection Prevents Language Model Collapse},
9	  author={Drayson, George and Yilmaz, Emine and Lampos, Vasileios},
10	  booktitle={Proceedings of EMNLP},
11	  year={2025},
12	  url={https://arxiv.org/abs/2502.15654}
13	}
14	
15	@inproceedings{schaeffer2025position,
16	  title={Position: Model Collapse Does Not Mean What You Think},
17	  author={Schaeffer, Rylan and Kazdan, Joshua and Arulandu, Anirudh and Koyejo, Sanmi},
18	  booktitle={Proceedings of ICML},
19	  year={2025},
20	  url={https://arxiv.org/abs/2503.03150}
21	}
22	
23	@inproceedings{kazdan2025collapse,
24	  title={Collapse or Thrive? Perils and Promises of Synthetic Data in a Self-Generating World},
25	  author={Kazdan, Joshua and Schaeffer, Rylan and Dey, Apratim and Gerstgrasser, Matthias and Rafailov, Rafael and Donoho, David and Koyejo, Sanmi},
26	  booktitle={Proceedings of ICML},
27	  year={2025},
28	  url={https://arxiv.org/abs/2410.16713}
29	}
30	
31	@inproceedings{shi2025generalization,
32	  title={A Closer Look at Model Collapse: From a Generalization-to-Memorization Perspective},
33	  author={Shi, Shiliang and Wu, Qiong and Zhang, Zhen and Zhang, Jing and Tao, Dacheng and Qu, Xiangyang},
34	  booktitle={Advances in NeurIPS},
35	  year={2025},
36	  note={Spotlight},
37	  url={https://arxiv.org/abs/2509.16499}
38	}
39	
40	@inproceedings{mitchell2023detectgpt,
41	  title={{DetectGPT}: Zero-Shot Machine-Generated Text Detection using Probability Curvature},
42	  author={Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher D. and Finn, Chelsea},
43	  booktitle={Proceedings of ICML},
44	  year={2023}
45	}
46	
47	% === Should-Cite ===
48	
49	@article{basani2026diveye,
50	  tit
…[truncated 4049 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_review_paper_sections_audit_20260513T215258",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 23 · 2026-05-13T22:02:08.577934+00:00_

All data collected. Here is the complete audit.

---

## 审查结果

### A. 数值引用一致性

所有 4 章 tex 文件统一使用 exp-007 bootstrap 值（非原始 pipeline 值），内部一致。以下是发现的问题：

```
[experiments_c1.tex:170] "Pythia→OLMo retains 91--92%" 计算不符 | 0.3531/0.3856=91.6%, 单方向无范围；若含反向 OLMo→Pythia (0.3450/0.3822=90.3%)，范围应为 90--92%
```

```
[experiments_c1.tex:175] "accuracy-based retention of 91--92%" 同上 | 91--92% → 应改为 90--92%
```

```
[introduction.tex:35] "Pythia↔OLMo: 91--92%" 同上 | 91--92% → 90--92%
```

```
[experiments_c1.tex:179] "Qwen-cont↔Pythia also transfers well (83--85% accuracy retention)" 计算不符 | Qwen_cont→Pythia=84.7%, Pythia→Qwen_cont=85.2%，范围 84--85%，不存在 83%
```

其余所有数值与 registry 一致（逐一核对了 tab:kstar_ci 全部 20 个 AUC 值、全部 8 个 CI bound、全部 p-value、tab:transfer_matrix 全部 16 个 cell、tab:top_features 排名、method.tex 的 MAE/mean_pw_auc 值、所有 Δpp 计算）。

### B. 已知修正同步状态

| 修正项 | 状态 |
|--------|------|
| "12 个条件" → "8 个条件" | **未发现** — 4 个 tex 文件中无 "12 conditions" 字样，已修正或在其他文件 |
| D016 universality (非 controllability) | **已正确** — 无 "controllability" 出现 |
| OBD 方向 P(depth ≤ k) vs P(depth > k) | **已正确** — method.tex:95-98 写的是 P(depth > k)（"exceedance probability"），与代码一致 |
| exp-003 config4_t12 数据 | **未引用** — 这些值未出现在当前 4 章中（仅在 intro 中以 rounded 形式引用：0.69→0.70） |
| exp-007 qwen_cont 0v1 CI | **未直接引用** — 表注说 "conservatively inferred"，见下方 C 节第 5 条 |

### C. 图表引用完整性

```
[experiments_c1.tex:75] \includegraphics{figures/fig2_auc_decay.pdf} — figures/ 目录不存在，编译会报错
```

```
[experiments_c1.tex:159] \includegraphics{figures/fig3_transfer_heatmap.pdf} — 同上，文件缺失
```

```
[experiments_c1.tex:157-167] \label{fig:transfer_heatmap} 已定义但全文无 \ref{fig:transfer_heatmap} 引用 — 浮动图无文本锚点
```

```
[introduction.tex:56] \ref{sec:conclusion} 悬空 — conclusion.tex 未写，main.tex 中 \input{conclusion} 被注释
```

```
[experiments_c1.tex:6] 硬编码 "Section~3" | → 应改为 Section~\ref{sec:method}
```

```
[experiments_c1.tex:301] 硬编码 "Section~3" | → 应改为 Section~\ref{sec:method} 或 \S\ref{sec:generation_mode}
```

```
[experiments_c1.tex:30] 表注 "Qwen-cont 0v1 not computed due to AUC > 0.997; conservatively inferred" — registry exp-007 实际有 perm_p=0（已计算，500 次 permutation 均未超过 observed AUC） | 建议修改为 "p < 0.002" 或删除此注
```

所有 `\cite{}` 均在 `references.bib` 中有对应条目，无悬空引用。

### D. 措辞一致性

- **$\Kstar$ vs $\Kempirical$**：experiments_c1.tex:15 节标题用 "$\Kstar = 2$"，而正文建立结论时用 "$\Kempirical = 2$"（line 90）。method.tex 明确区分 $\Kempirical$（经验值）和 $\Ktheory$（理论上界）。节标题用 $\Kstar$ 虽可接受（intro 中 $\Kstar$ 定义为通用 boundary），但可能与 method.tex 的精确区分产生混淆。**建议统一为 $\Kempirical$**。

- CI 格式统一（表内 `[.XXXX,\,.XXXX]`，正文 `$\text{CI}_\text{lower} = X.XXXX$`）✓
- p-value 格式统一（`$p = 0.002$`）✓
- "universality" 叙事一致，无 "controllability" 干扰 ✓

---

**共 10 条需修正项**（4 条数值、6 条格式/引用），无重大数据错误。核心发现 $K^*_{\text{empirical}}=2$ 的所有支撑数据与 registry 完全吻合。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_review_paper_sections_audit_20260513T215258"
}
```

</details>

---
