# paper claim3 revision

**When Does Non-Uniform KV Cache Quantization Help? Cardinality Constraints and a Heterogeneity Diagnostic** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 49
- **Recorded user turns:** 0
- **Tool calls:** 16
- **Original source:** `logs/workers/worker_paper_claim3_revision_20260514T210100.log`
- **Structured JSON:** [`56bbc4acad02a10fb967.json`](../../sessions/56/56bbc4acad02a10fb967.json)

## Before a recorded user message

49 recorded events

### Log line

_source line 1_

Warning: no stdin data received in 3s, proceeding without it. If piping from a slow command, redirect stdin explicitly: < /dev/null to skip, or wait longer.

---

### System

_source line 2_

```json
{
  "type": "system",
  "subtype": "init",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "tools": [
    "Task",
    "AskUserQuestion",
    "Bash",
    "CronCreate",
    "CronDelete",
    "CronList",
    "Edit",
    "EnterPlanMode",
    "EnterWorktree",
    "ExitPlanMode",
    "ExitWorktree",
    "Glob",
    "Grep",
    "ListMcpResourcesTool",
    "Monitor",
    "NotebookEdit",
    "PushNotification",
    "Read",
    "ReadMcpResourceTool",
    "RemoteTrigger",
    "ScheduleWakeup",
    "Skill",
    "TaskOutput",
    "TaskStop",
    "TodoWrite",
    "ToolSearch",
    "WebFetch",
    "WebSearch",
    "Write",
    "mcp__agent-ml-research__append_idea",
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__save_project_file"
  ],
  "mcp_servers": [
    {
      "name": "agent-ml-research",
      "status": "connected"
    }
  ],
  "model": "claude-opus-4-6",
  "permissionMode": "bypassPermissions",
  "slash_commands": [
    "update-config",
    "debug",
    "simplify",
    "batch",
    "fewer-permission-prompts",
    "loop",
    "schedule",
    "claude-api",
    "clear",
    "compact",
    "context",
    "heapdump",
    "init",
    "review",
    "security-review",
    "extra-usage",
    "usage",
    "insights",
    "team-onboarding"
  ],
  "apiKeySource": "none",
  "claude_code_version": "2.1.126",
  "output_style": "default",
  "agents": [
    "claude",
    "Explore",
    "general-purpose",
    "Plan",
    "statusline-setup"
  ],
  "skills": [
    "update-config",
    "debug",
    "simplify",
    "batch",
    "fewer-permission-prompts",
    "loop",
    "schedule",
    "claude-api"
  ],
  "plugins": [],
  "analytics_disabled": false,
  "uuid": "71d3dcad-3053-4074-baf0-47d239d162d6",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-2-projects-ratekv/memory/"
  },
  "fast_mode_state": "off"
}
```

---

### Runtime record

_source line 3_

```json
{
  "type": "rate_limit_event",
  "rate_limit_info": {
    "status": "allowed",
    "resetsAt": 1778803200,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "4154f2f7-f5c5-4063-aaab-4f40ae52ae28",
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the current content of all the relevant tex files to understand what needs to be changed.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "eedaa7c6-3402-489f-ad0c-9937ef35d6b4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XdyULNV6gpu2R2AA7MgRj6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13051,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13051
      },
      "output_tokens": 25,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 5_

我先读取所有需要修改的 tex 文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "ab267644-d549-40eb-a557-6173a73b3257",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XdyULNV6gpu2R2AA7MgRj6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13051,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13051
      },
      "output_tokens": 25,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 6_

<details open><summary>🔧 Tool call — Read · `toolu_01WgsarpEHzr9nFiAfdW4BVJ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "8b243a3a-6ad3-42e9-82ff-04be11178a08",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XdyULNV6gpu2R2AA7MgRj6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13051,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13051
      },
      "output_tokens": 25,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 7 · 2026-05-14T21:01:15.153Z_

<details><summary>↩ Tool result · `toolu_01WgsarpEHzr9nFiAfdW4BVJ`</summary>

```text
1	\section{Analysis}
2	\label{sec:analysis}
3	
4	\subsection{Heterogeneity Characterization}
5	\label{sec:heterogeneity}
6	
7	The benefit of non-uniform allocation depends on how unevenly head sensitivities are distributed.
8	We quantify this with a \emph{top-5\% concentration metric}: sort per-head 2-bit distortions $d_h(2)$ in descending order and compute the fraction of total distortion contributed by the top 5\% of heads.
9	High concentration indicates that a few heads are disproportionately sensitive; low concentration indicates near-uniform sensitivity.
10	
11	Table~\ref{tab:heterogeneity} summarizes the results across five architectures at $4\times$ compression.
12	Qwen2.5-7B exhibits the highest \emph{spread} heterogeneity (top-5\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.
13	Constrained MCKP reduces degradation from $+$5.64 PPL (uniform) to $+$1.42 PPL, a 27.3\% improvement over uniform 4-bit. %exp_id=qwen_constrained_mckp
14	
15	However, concentration alone does not predict MCKP benefit.
16	Yi-1.5-9B has a hires concentration of $0.71$---\emph{higher} than Qwen's $0.61$---yet constrained MCKP is counterproductive ($+$0.30 vs.\ $+$0.20 uniform). %exp_id=yi15_hires_constrained
17	The explanation lies in the \emph{shape} of the heterogeneity.
18	Yi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling
19	Critically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\approx}\,0$.
20	The solver therefore has no cross-bitwidth gradient to exploit---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.
21	We call this a ``spike'' pattern: high concentration, but a single outlier with sensitivity at only one bitwidth.
22	
23	In contrast, Qwen's Layer-0 heads exhibit non-zero deltas at multiple bitwidths (e.g., L0H0: 2-bit delta ${=}6.74$, with positive 4-bit and 8-bit deltas), giving the solver a multi-bitwidth sensitivity gradient across several heads---a ``spread'' pattern that enables meaningful budget reallocation. %exp_id=qwen_hires_profiling
24	
25	The remaining three architectures fill out the diagnostic picture.
26	Llama-3.1-8B shows moderate concentration ($0.34$) with a spike-like shape ($t_1/t_5{=}0.71$, $t_1/t_2{=}21.7$); its allocation benefit is marginal ($+$0.36 vs.\ $+$0.38 uniform). %exp_id=llama_hires_constrained
27	Mistral-7B-v0.3 and Gemma-2-9B both exhibit flat distributions ($t_1/t_5{=}0.18$) with low concentration ($0.22$ and $0.23$ respectively), leaving the profiler with no reliable signal; constrained MCKP is slightly worse than uniform in both cases ($+$0.13 vs.\ $+$0.10 for Mistral; $+$0.15 vs.\ $+$0.13 for Gemma-2). %exp_id=mistral_c4_cross_dataset %exp_id=gemma2_full_pipeline
28	
29	\begin{table}[t]
30	\centering
31	\small
32	\caption{Head sensitivity heterogeneity and constrained allocation benefit across architectures at $4\times$ compression. $t_1/t_5$: ratio of top-1 to top-5 per-head 2-bit distortion (low${=}$spread, high${=}$spike). $^\dagger$Hires profiling (64 seq $\times$ 2048 tok); $^\ddagger$standard profiling, hires pending.}
33	\label{tab:heterogeneity}
34	\begin{tabular}{lcccccc}
35	\toprule
36	Model & GQA & Top-5\% & $t_1/t_5$ & $\Delta$ PPL & $\Delta$ PPL & Shape \\
37	 & Ratio & Conc. & & (Uniform) & (Ours) & \\
38	\midrule
39	Qwen2.5-7B & 7:1 & 0.61 & 0.57 & $+$5.64 & $+$1.42 & Spread \\
40	Yi-1.5-9B$^\dagger$ & 8:1 & 0.71 & 0.90 & $+$0.20 & $+$0.30 & Spike \\
41	Llama-3.1-8B$^\ddagger$ & 4:1 & 0.34 & 0.71 & $+$0.38 & $+$0.36 & Spike \\
42	Mistral-7B-v0.3$^\ddagger$ & 4:1 & 0.22 & 0.18 & $+$0.10 & $+$0.13 & Flat \\
43	Gemma-2-9B$^\ddagger$ & 2:1 & 0.23 & 0.18 & $+$0.13 & $+$0.15 & Flat \\
44	\bottomrule
45	\end{tabular}
46	\end{table}
47	
48	\begin{figure*}[t]
49	\centering
50	\includegraphics[width=\textwidth]{figures/fig1_head_delta_heatmap.pdf}
51	\caption{Per-head 2-bit quantization sensitivity across five architectures. Qwen2.5-7B shows high concentration in Layer-0 heads (``spread'' pattern); Yi-1.5-9B shows a single extreme outlier at Layer-4 Head-3 (``spike'' pattern); Llama-3.1-8B shows moderate spread; Mistral-7B-v0.3 shows near-zero sensitivity across all heads; Gemma-2-9B exhibits the most uniform distribution, consistent with its low GQA ratio (2:1). Color intensity indicates PPL increase when the head is quantized to 2-bit.}
52	\label{fig:heatmap}
53	\end{figure*}
54	
55	Figure~\ref{fig:heatmap} visualizes the per-head 2-bit distortion as a heatmap.
56	The contrast is stark: Qwen's Layer-0 heads show high distortion (dark cells) while mid-to-deep layers are near-zero; Yi-1.5 shows a single bright spot at Layer-4 Head-3 (34\% of total delta) with the remaining 191 heads near-uniform---a ``spike'' that MCKP cannot exploit; Gemma-2 exhibits the most uniform heatmap across its 336 heads, consistent with its 0.23 concentration; Mistral shows similarly low distortion across all layers and heads.
57	
58	\subsection{Diagnostic Framework}
59	\label{sec:diagnostic}
60	
61	The heterogeneity characterization shows that MCKP benefit requires not just high concentration but a specific \emph{shape}---spread heterogeneity across multiple heads with cross-bitwidth sensitivity gradients.
62	This motivates a joint diagnostic, based on five architectures, for deciding when non-uniform allocation is worthwhile:
63	
64	\begin{enumerate}[nosep]
65	\item Run per-head profiling as described in \S\ref{sec:profiling}.
66	\item Compute the top-5\% concentration and the $t_1/t_5$ ratio (top-1 distortion divided by top-5 distortion) from the resulting distortion table.
67	\item Select allocation strategy based on concentration \emph{and} shape:
68	  \begin{itemize}[nosep]
69	  \item \textbf{Spread} (moderate-to-high concentration, $t_1/t_5 \lesssim 0.70$): non-uniform allocation recommended. Multiple heads have sensitivity gradients across bitwidths, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\% PPL improvement.
70	  \item \textbf{Spike} (any concentration, $t_1/t_5 \gtrsim 0.70$): use uniform. Sensitivity is confined to a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.
71	  \item \textbf{Flat} (low concentration, any shape): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral ($t_1/t_5{=}0.18$) and Gemma-2 ($t_1/t_5{=}0.18$): counterproductive.
72	  \end{itemize}
73	\end{enumerate}
74	
75	The $t_1/t_5 \approx 0.70$ boundary is an illustrative threshold derived from five architectures; it should be validated on a broader set before being treated as a general rule.
76	The diagnostic adds no computational overhead: it reuses the profiling data already required for the allocation solver and avoids wasted optimization effort on architectures where non-uniform allocation provides no benefit.
77	Additional analyses---the effect of aggressive compression ratios, profiling resolution and multi-seed stability, per-layer optimality validation, and KV separation ablation---are provided in Appendices~\ref{sec:aggressive}--\ref{sec:kv_separation}.
78	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "ea24e9f8-6638-4c1d-8acf-605842726a3e",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex",
      "content": "\\section{Analysis}\n\\label{sec:analysis}\n\n\\subsection{Heterogeneity Characterization}\n\\label{sec:heterogeneity}\n\nThe benefit of non-uniform allocation depends on how unevenly head sensitivities are distributed.\nWe quantify this with a \\emph{top-5\\% concentration metric}: sort per-head 2-bit distortions $d_h(2)$ in descending order and compute the fraction of total distortion contributed by the top 5\\% of heads.\nHigh concentration indicates that a few heads are disproportionately sensitive; low concentration indicates near-uniform sensitivity.\n\nTable~\\ref{tab:heterogeneity} summarizes the results across five architectures at $4\\times$ compression.\nQwen2.5-7B exhibits the highest \\emph{spread} heterogeneity (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.\nConstrained MCKP reduces degradation from $+$5.64 PPL (uniform) to $+$1.42 PPL, a 27.3\\% improvement over uniform 4-bit. %exp_id=qwen_constrained_mckp\n\nHowever, concentration alone does not predict MCKP benefit.\nYi-1.5-9B has a hires concentration of $0.71$---\\emph{higher} than Qwen's $0.61$---yet constrained MCKP is counterproductive ($+$0.30 vs.\\ $+$0.20 uniform). %exp_id=yi15_hires_constrained\nThe explanation lies in the \\emph{shape} of the heterogeneity.\nYi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling\nCritically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\\approx}\\,0$.\nThe solver therefore has no cross-bitwidth gradient to exploit---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.\nWe call this a ``spike'' pattern: high concentration, but a single outlier with sensitivity at only one bitwidth.\n\nIn contrast, Qwen's Layer-0 heads exhibit non-zero deltas at multiple bitwidths (e.g., L0H0: 2-bit delta ${=}6.74$, with positive 4-bit and 8-bit deltas), giving the solver a multi-bitwidth sensitivity gradient across several heads---a ``spread'' pattern that enables meaningful budget reallocation. %exp_id=qwen_hires_profiling\n\nThe remaining three architectures fill out the diagnostic picture.\nLlama-3.1-8B shows moderate concentration ($0.34$) with a spike-like shape ($t_1/t_5{=}0.71$, $t_1/t_2{=}21.7$); its allocation benefit is marginal ($+$0.36 vs.\\ $+$0.38 uniform). %exp_id=llama_hires_constrained\nMistral-7B-v0.3 and Gemma-2-9B both exhibit flat distributions ($t_1/t_5{=}0.18$) with low concentration ($0.22$ and $0.23$ respectively), leaving the profiler with no reliable signal; constrained MCKP is slightly worse than uniform in both cases ($+$0.13 vs.\\ $+$0.10 for Mistral; $+$0.15 vs.\\ $+$0.13 for Gemma-2). %exp_id=mistral_c4_cross_dataset %exp_id=gemma2_full_pipeline\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Head sensitivity heterogeneity and constrained allocation benefit across architectures at $4\\times$ compression. $t_1/t_5$: ratio of top-1 to top-5 per-head 2-bit distortion (low${=}$spread, high${=}$spike). $^\\dagger$Hires profiling (64 seq $\\times$ 2048 tok); $^\\ddagger$standard profiling, hires pending.}\n\\label{tab:heterogeneity}\n\\begin{tabular}{lcccccc}\n\\toprule\nModel & GQA & Top-5\\% & $t_1/t_5$ & $\\Delta$ PPL & $\\Delta$ PPL & Shape \\\\\n & Ratio & Conc. & & (Uniform) & (Ours) & \\\\\n\\midrule\nQwen2.5-7B & 7:1 & 0.61 & 0.57 & $+$5.64 & $+$1.42 & Spread \\\\\nYi-1.5-9B$^\\dagger$ & 8:1 & 0.71 & 0.90 & $+$0.20 & $+$0.30 & Spike \\\\\nLlama-3.1-8B$^\\ddagger$ & 4:1 & 0.34 & 0.71 & $+$0.38 & $+$0.36 & Spike \\\\\nMistral-7B-v0.3$^\\ddagger$ & 4:1 & 0.22 & 0.18 & $+$0.10 & $+$0.13 & Flat \\\\\nGemma-2-9B$^\\ddagger$ & 2:1 & 0.23 & 0.18 & $+$0.13 & $+$0.15 & Flat \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/fig1_head_delta_heatmap.pdf}\n\\caption{Per-head 2-bit quantization sensitivity across five architectures. Qwen2.5-7B shows high concentration in Layer-0 heads (``spread'' pattern); Yi-1.5-9B shows a single extreme outlier at Layer-4 Head-3 (``spike'' pattern); Llama-3.1-8B shows moderate spread; Mistral-7B-v0.3 shows near-zero sensitivity across all heads; Gemma-2-9B exhibits the most uniform distribution, consistent with its low GQA ratio (2:1). Color intensity indicates PPL increase when the head is quantized to 2-bit.}\n\\label{fig:heatmap}\n\\end{figure*}\n\nFigure~\\ref{fig:heatmap} visualizes the per-head 2-bit distortion as a heatmap.\nThe contrast is stark: Qwen's Layer-0 heads show high distortion (dark cells) while mid-to-deep layers are near-zero; Yi-1.5 shows a single bright spot at Layer-4 Head-3 (34\\% of total delta) with the remaining 191 heads near-uniform---a ``spike'' that MCKP cannot exploit; Gemma-2 exhibits the most uniform heatmap across its 336 heads, consistent with its 0.23 concentration; Mistral shows similarly low distortion across all layers and heads.\n\n\\subsection{Diagnostic Framework}\n\\label{sec:diagnostic}\n\nThe heterogeneity characterization shows that MCKP benefit requires not just high concentration but a specific \\emph{shape}---spread heterogeneity across multiple heads with cross-bitwidth sensitivity gradients.\nThis motivates a joint diagnostic, based on five architectures, for deciding when non-uniform allocation is worthwhile:\n\n\\begin{enumerate}[nosep]\n\\item Run per-head profiling as described in \\S\\ref{sec:profiling}.\n\\item Compute the top-5\\% concentration and the $t_1/t_5$ ratio (top-1 distortion divided by top-5 distortion) from the resulting distortion table.\n\\item Select allocation strategy based on concentration \\emph{and} shape:\n  \\begin{itemize}[nosep]\n  \\item \\textbf{Spread} (moderate-to-high concentration, $t_1/t_5 \\lesssim 0.70$): non-uniform allocation recommended. Multiple heads have sensitivity gradients across bitwidths, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\\% PPL improvement.\n  \\item \\textbf{Spike} (any concentration, $t_1/t_5 \\gtrsim 0.70$): use uniform. Sensitivity is confined to a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.\n  \\item \\textbf{Flat} (low concentration, any shape): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral ($t_1/t_5{=}0.18$) and Gemma-2 ($t_1/t_5{=}0.18$): counterproductive.\n  \\end{itemize}\n\\end{enumerate}\n\nThe $t_1/t_5 \\approx 0.70$ boundary is an illustrative threshold derived from five architectures; it should be validated on a broader set before being treated as a general rule.\nThe diagnostic adds no computational overhead: it reuses the profiling data already required for the allocation solver and avoids wasted optimization effort on architectures where non-uniform allocation provides no benefit.\nAdditional analyses---the effect of aggressive compression ratios, profiling resolution and multi-seed stability, per-layer optimality validation, and KV separation ablation---are provided in Appendices~\\ref{sec:aggressive}--\\ref{sec:kv_separation}.\n",
      "numLines": 78,
      "startLine": 1,
      "totalLines": 78
    }
  }
}
```

</details>

---

### Tool call

_source line 8_

<details open><summary>🔧 Tool call — Read · `toolu_01UrNBKLKdHf7nHDFe43tRTh`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "f973ca7d-dd7b-481e-a33e-607d582012ca",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XdyULNV6gpu2R2AA7MgRj6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13051,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13051
      },
      "output_tokens": 25,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 9 · 2026-05-14T21:01:15.734Z_

<details><summary>↩ Tool result · `toolu_01UrNBKLKdHf7nHDFe43tRTh`</summary>

```text
1	Per-head mixed-precision quantization of the KV cache promises lower perplexity than uniform quantization at the same average bit-width, but on hardware-aligned bit-widths $\{2, 4, 8, 16\}$, existing solvers fail catastrophically: unconstrained greedy and MCKP allocation achieve 32.45 and 36.92 perplexity on Qwen2.5-7B---far worse than uniform 4-bit (15.45).
2	We trace this failure to \emph{2-bit distortion compounding}: when the majority of heads are assigned 2-bit precision, per-head quantization errors interact non-additively through the residual stream, violating the additive objective assumed by standard solvers.
3	We show that a single cardinality constraint capping the number of 2-bit assignments is a minimal sufficient fix.
4	On Qwen2.5-7B at $4\times$ compression, constrained allocation achieves 11.23 perplexity, a 27.3\% reduction over uniform 4-bit.
5	The constraint also renders solver choice irrelevant: constrained greedy and constrained MCKP produce equivalent bit-width assignments across all three tested architectures ($\Delta{=}0.0000$), enabling use of a simple $O(H \log H)$ greedy algorithm; per-layer brute-force oracle confirms near-optimality (max gap 0.02 PPL).
6	However, the benefit depends on architecture: on Llama-3.1-8B the improvement is marginal (8.45 vs.\ 8.47), and on Mistral-7B-v0.3, Yi-1.5-9B, and Gemma-2-9B non-uniform allocation is counterproductive.
7	Notably, Yi-1.5-9B has the highest GQA ratio tested (8:1) and the highest top-5\% concentration (0.71), yet degrades under non-uniform allocation---because its heterogeneity is a single-outlier ``spike'' with no cross-bitwidth sensitivity gradient, rather than the ``spread'' pattern that enables MCKP to redistribute budget across heads.
8	We propose a joint heterogeneity diagnostic combining concentration and distribution shape, validated on five architectures, that can indicate before any allocation whether a given architecture will benefit from non-uniform quantization.
9	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "3a8f1dd6-93d7-456b-aca2-4960690cce83",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/abstract.tex",
      "content": "Per-head mixed-precision quantization of the KV cache promises lower perplexity than uniform quantization at the same average bit-width, but on hardware-aligned bit-widths $\\{2, 4, 8, 16\\}$, existing solvers fail catastrophically: unconstrained greedy and MCKP allocation achieve 32.45 and 36.92 perplexity on Qwen2.5-7B---far worse than uniform 4-bit (15.45).\nWe trace this failure to \\emph{2-bit distortion compounding}: when the majority of heads are assigned 2-bit precision, per-head quantization errors interact non-additively through the residual stream, violating the additive objective assumed by standard solvers.\nWe show that a single cardinality constraint capping the number of 2-bit assignments is a minimal sufficient fix.\nOn Qwen2.5-7B at $4\\times$ compression, constrained allocation achieves 11.23 perplexity, a 27.3\\% reduction over uniform 4-bit.\nThe constraint also renders solver choice irrelevant: constrained greedy and constrained MCKP produce equivalent bit-width assignments across all three tested architectures ($\\Delta{=}0.0000$), enabling use of a simple $O(H \\log H)$ greedy algorithm; per-layer brute-force oracle confirms near-optimality (max gap 0.02 PPL).\nHowever, the benefit depends on architecture: on Llama-3.1-8B the improvement is marginal (8.45 vs.\\ 8.47), and on Mistral-7B-v0.3, Yi-1.5-9B, and Gemma-2-9B non-uniform allocation is counterproductive.\nNotably, Yi-1.5-9B has the highest GQA ratio tested (8:1) and the highest top-5\\% concentration (0.71), yet degrades under non-uniform allocation---because its heterogeneity is a single-outlier ``spike'' with no cross-bitwidth sensitivity gradient, rather than the ``spread'' pattern that enables MCKP to redistribute budget across heads.\nWe propose a joint heterogeneity diagnostic combining concentration and distribution shape, validated on five architectures, that can indicate before any allocation whether a given architecture will benefit from non-uniform quantization.\n",
      "numLines": 9,
      "startLine": 1,
      "totalLines": 9
    }
  }
}
```

</details>

---

### Tool call

_source line 10_

<details open><summary>🔧 Tool call — Read · `toolu_01AVDcaJYBxKVdQA8CYUc7Wp`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "cd0261c3-f5e8-4221-ac90-50eb2ef2f929",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XdyULNV6gpu2R2AA7MgRj6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13051,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13051
      },
      "output_tokens": 25,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 11 · 2026-05-14T21:01:16.248Z_

<details><summary>↩ Tool result · `toolu_01AVDcaJYBxKVdQA8CYUc7Wp`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Per-head mixed-precision quantization of the KV cache is a natural strategy for reducing memory during LLM inference: assign fewer bits to insensitive heads and more bits to sensitive ones, achieving lower perplexity than uniform quantization at the same average bit-width.
5	Recent work on KV cache quantization explores both uniform schemes~\cite{liu2024kivi,hooper2024kvquant,lin2024qserve,he2024zipcache} and token-level mixed-precision approaches~\cite{ge2024fastgen,lei2026arkv}, while complementary methods reduce cache size through eviction~\cite{zhang2023h2o,li2024snapkv}.
6	RateQuant~\cite{zuo2026ratequant} formalizes per-head allocation as a rate-distortion optimization and shows that greedy allocation is optimal when bit-widths are consecutive integers $\{2,3,4,5,6\}$, exploiting the polymatroid structure of the feasible set (their Proposition~6).
7	
8	In practice, hardware-efficient inference requires bit-widths drawn from $\{2, 4, 8, 16\}$---the formats natively supported by modern accelerators.
9	On this non-consecutive set, the polymatroid structure breaks down, and greedy is no longer provably optimal.
10	One might expect that exact MCKP solvers would fill this gap.
11	They do not.
12	On Qwen2.5-7B at $4\times$ compression, unconstrained greedy achieves 32.45 PPL and unconstrained MCKP achieves 36.92---both \emph{far worse} than uniform 4-bit (15.45).
13	The optimization does not merely underperform; it fails catastrophically.
14	
15	The root cause is not solver suboptimality but a violation of the objective's additive distortion assumption.
16	Both solvers assign 68--75 of 112 KV heads to 2-bit, where per-head quantization errors are large enough to compound through the residual stream.
17	The additive model predicts $\sim$11 PPL for these allocations; the actual PPL is $3$--$4\times$ higher.
18	At 4-bit and above, per-head distortions are small and compound negligibly---uniform 4-bit achieves close to its additive prediction---but 2-bit distortions are orders of magnitude larger.
19	When most heads are quantized to 2-bit simultaneously, cumulative truncation errors exceed the network's capacity to compensate, and perplexity degrades super-linearly.
20	
21	This observation points to a minimal intervention: cap the number of 2-bit assignments.
22	We add a single cardinality constraint $\sum_h \mathbb{1}[b_h{=}2] \leq k$ to the standard MCKP formulation (\S\ref{sec:method}).
23	On Qwen2.5-7B, setting $k{=}8$ (7\% of heads) yields 11.23 PPL---a 27.3\% reduction over uniform 4-bit.
24	The constraint works by forcing the solver to use 2-bit only on the least-sensitive heads, while redistributing the freed budget to protect sensitive heads at 8-bit or 16-bit.
25	This is not a heuristic patch: the constraint directly addresses the identified failure mode and is compatible with any solver.
26	
27	A surprising consequence is that, under the cardinality constraint, the choice of solver becomes irrelevant.
28	Constrained greedy and constrained MCKP produce identical allocations---not approximately, but exactly: all 112 heads receive the same bit-width on Qwen2.5-7B, all 256 on Llama-3.1-8B, and 255 of 256 on Mistral-7B-v0.3 (the single difference is a zero-distortion tie with no PPL impact).
29	The constraint narrows the feasible set enough that greedy's locally optimal decisions are globally optimal (\S\ref{sec:solver_equiv}), enabling practitioners to use the simpler $O(H \log H)$ greedy algorithm without sacrificing solution quality.
30	A per-layer brute-force oracle confirms near-optimality: the maximum gap across 28 layers is 0.02 PPL, 0.4\% of the total improvement (\S\ref{sec:solver_equiv}).
31	
32	However, non-uniform allocation does not help universally.
33	On Llama-3.1-8B, constrained MCKP achieves 8.45 PPL vs.\ uniform 8.47---a marginal 0.2\% improvement.
34	On Mistral-7B-v0.3, it is slightly \emph{worse}: 7.16 vs.\ 7.13.
35	On Yi-1.5-9B, non-uniform allocation degrades PPL by 1.3\% (7.31 vs.\ 7.22) despite Yi-1.5 having the highest GQA ratio tested (8:1).
36	On Gemma-2-9B (GQA 2:1, the lowest ratio tested), degradation is 0.3\% (9.05 vs.\ 9.03).
37	The difference across architectures traces to head sensitivity heterogeneity---specifically, its \emph{distribution shape}, not GQA ratio alone.
38	Qwen's KV heads vary widely in 2-bit distortion, with Layer-0 heads forming a cluster of high sensitivity; Yi-1.5 has a single extreme outlier but otherwise uniform heads (a ``spike'' pattern that MCKP cannot exploit); Gemma-2 and Mistral show near-uniform sensitivity across all heads.
39	When there is no exploitable heterogeneity, non-uniform allocation adds noise without benefit.
40	
41	This motivates a diagnostic question that prior work does not address: \emph{when} should a practitioner use per-head mixed-precision quantization?
42	We propose a joint heterogeneity diagnostic based on concentration \emph{and} distribution shape of per-head distortion (\S\ref{sec:heterogeneity}).
43	On our five architectures, the diagnostic separates the beneficial case (Qwen, concentration 0.61, spread pattern) from cases where non-uniform allocation provides marginal or no benefit.
44	Yi-1.5 is a critical test: its concentration ($0.71$) exceeds Qwen's, but its heterogeneity is a single-outlier spike with no cross-bitwidth gradient---precisely the pattern where MCKP cannot redistribute budget.
45	The diagnostic reuses profiling data already required by the solver and adds no computational overhead.
46	
47	Our contributions are:
48	\begin{enumerate}[nosep]
49	\item We identify 2-bit distortion compounding as the cause of catastrophic failure in unconstrained per-head KV cache quantization on hardware-aligned bit-widths, and show that a cardinality constraint on 2-bit assignments is a minimal sufficient fix, reducing Qwen2.5-7B PPL from 32--37 (unconstrained) to 11.23 (constrained) at $4\times$ compression (\S\ref{sec:compounding}, \S\ref{sec:experiments}).
50	
51	\item We demonstrate that the cardinality constraint makes solver choice irrelevant: constrained greedy and constrained MCKP produce equivalent per-head allocations across three architectures, enabling use of a simple greedy algorithm (\S\ref{sec:solver_equiv}).
52	
53	\item We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) to indicate whether non-uniform allocation will help a given architecture, distinguishing ``spread'' heterogeneity (MCKP-exploitable) from ``spike'' and ``flat'' patterns, validated on five models (\S\ref{sec:heterogeneity}).
54	\end{enumerate}
55	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "8ba01bad-cb18-4ff0-b8c4-94dd20672879",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nPer-head mixed-precision quantization of the KV cache is a natural strategy for reducing memory during LLM inference: assign fewer bits to insensitive heads and more bits to sensitive ones, achieving lower perplexity than uniform quantization at the same average bit-width.\nRecent work on KV cache quantization explores both uniform schemes~\\cite{liu2024kivi,hooper2024kvquant,lin2024qserve,he2024zipcache} and token-level mixed-precision approaches~\\cite{ge2024fastgen,lei2026arkv}, while complementary methods reduce cache size through eviction~\\cite{zhang2023h2o,li2024snapkv}.\nRateQuant~\\cite{zuo2026ratequant} formalizes per-head allocation as a rate-distortion optimization and shows that greedy allocation is optimal when bit-widths are consecutive integers $\\{2,3,4,5,6\\}$, exploiting the polymatroid structure of the feasible set (their Proposition~6).\n\nIn practice, hardware-efficient inference requires bit-widths drawn from $\\{2, 4, 8, 16\\}$---the formats natively supported by modern accelerators.\nOn this non-consecutive set, the polymatroid structure breaks down, and greedy is no longer provably optimal.\nOne might expect that exact MCKP solvers would fill this gap.\nThey do not.\nOn Qwen2.5-7B at $4\\times$ compression, unconstrained greedy achieves 32.45 PPL and unconstrained MCKP achieves 36.92---both \\emph{far worse} than uniform 4-bit (15.45).\nThe optimization does not merely underperform; it fails catastrophically.\n\nThe root cause is not solver suboptimality but a violation of the objective's additive distortion assumption.\nBoth solvers assign 68--75 of 112 KV heads to 2-bit, where per-head quantization errors are large enough to compound through the residual stream.\nThe additive model predicts $\\sim$11 PPL for these allocations; the actual PPL is $3$--$4\\times$ higher.\nAt 4-bit and above, per-head distortions are small and compound negligibly---uniform 4-bit achieves close to its additive prediction---but 2-bit distortions are orders of magnitude larger.\nWhen most heads are quantized to 2-bit simultaneously, cumulative truncation errors exceed the network's capacity to compensate, and perplexity degrades super-linearly.\n\nThis observation points to a minimal intervention: cap the number of 2-bit assignments.\nWe add a single cardinality constraint $\\sum_h \\mathbb{1}[b_h{=}2] \\leq k$ to the standard MCKP formulation (\\S\\ref{sec:method}).\nOn Qwen2.5-7B, setting $k{=}8$ (7\\% of heads) yields 11.23 PPL---a 27.3\\% reduction over uniform 4-bit.\nThe constraint works by forcing the solver to use 2-bit only on the least-sensitive heads, while redistributing the freed budget to protect sensitive heads at 8-bit or 16-bit.\nThis is not a heuristic patch: the constraint directly addresses the identified failure mode and is compatible with any solver.\n\nA surprising consequence is that, under the cardinality constraint, the choice of solver becomes irrelevant.\nConstrained greedy and constrained MCKP produce identical allocations---not approximately, but exactly: all 112 heads receive the same bit-width on Qwen2.5-7B, all 256 on Llama-3.1-8B, and 255 of 256 on Mistral-7B-v0.3 (the single difference is a zero-distortion tie with no PPL impact).\nThe constraint narrows the feasible set enough that greedy's locally optimal decisions are globally optimal (\\S\\ref{sec:solver_equiv}), enabling practitioners to use the simpler $O(H \\log H)$ greedy algorithm without sacrificing solution quality.\nA per-layer brute-force oracle confirms near-optimality: the maximum gap across 28 layers is 0.02 PPL, 0.4\\% of the total improvement (\\S\\ref{sec:solver_equiv}).\n\nHowever, non-uniform allocation does not help universally.\nOn Llama-3.1-8B, constrained MCKP achieves 8.45 PPL vs.\\ uniform 8.47---a marginal 0.2\\% improvement.\nOn Mistral-7B-v0.3, it is slightly \\emph{worse}: 7.16 vs.\\ 7.13.\nOn Yi-1.5-9B, non-uniform allocation degrades PPL by 1.3\\% (7.31 vs.\\ 7.22) despite Yi-1.5 having the highest GQA ratio tested (8:1).\nOn Gemma-2-9B (GQA 2:1, the lowest ratio tested), degradation is 0.3\\% (9.05 vs.\\ 9.03).\nThe difference across architectures traces to head sensitivity heterogeneity---specifically, its \\emph{distribution shape}, not GQA ratio alone.\nQwen's KV heads vary widely in 2-bit distortion, with Layer-0 heads forming a cluster of high sensitivity; Yi-1.5 has a single extreme outlier but otherwise uniform heads (a ``spike'' pattern that MCKP cannot exploit); Gemma-2 and Mistral show near-uniform sensitivity across all heads.\nWhen there is no exploitable heterogeneity, non-uniform allocation adds noise without benefit.\n\nThis motivates a diagnostic question that prior work does not address: \\emph{when} should a practitioner use per-head mixed-precision quantization?\nWe propose a joint heterogeneity diagnostic based on concentration \\emph{and} distribution shape of per-head distortion (\\S\\ref{sec:heterogeneity}).\nOn our five architectures, the diagnostic separates the beneficial case (Qwen, concentration 0.61, spread pattern) from cases where non-uniform allocation provides marginal or no benefit.\nYi-1.5 is a critical test: its concentration ($0.71$) exceeds Qwen's, but its heterogeneity is a single-outlier spike with no cross-bitwidth gradient---precisely the pattern where MCKP cannot redistribute budget.\nThe diagnostic reuses profiling data already required by the solver and adds no computational overhead.\n\nOur contributions are:\n\\begin{enumerate}[nosep]\n\\item We identify 2-bit distortion compounding as the cause of catastrophic failure in unconstrained per-head KV cache quantization on hardware-aligned bit-widths, and show that a cardinality constraint on 2-bit assignments is a minimal sufficient fix, reducing Qwen2.5-7B PPL from 32--37 (unconstrained) to 11.23 (constrained) at $4\\times$ compression (\\S\\ref{sec:compounding}, \\S\\ref{sec:experiments}).\n\n\\item We demonstrate that the cardinality constraint makes solver choice irrelevant: constrained greedy and constrained MCKP produce equivalent per-head allocations across three architectures, enabling use of a simple greedy algorithm (\\S\\ref{sec:solver_equiv}).\n\n\\item We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) to indicate whether non-uniform allocation will help a given architecture, distinguishing ``spread'' heterogeneity (MCKP-exploitable) from ``spike'' and ``flat'' patterns, validated on five models (\\S\\ref{sec:heterogeneity}).\n\\end{enumerate}\n",
      "numLines": 55,
      "startLine": 1,
      "totalLines": 55
    }
  }
}
```

</details>

---

### Tool call

_source line 12_

<details open><summary>🔧 Tool call — Read · `toolu_01XRX6y4nkfPFKX2M6SDo2Xn`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "405227f4-22a7-4f6d-98f6-e0368b5b2fbe",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XdyULNV6gpu2R2AA7MgRj6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13051,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13051
      },
      "output_tokens": 25,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 13 · 2026-05-14T21:01:16.556Z_

<details><summary>↩ Tool result · `toolu_01XRX6y4nkfPFKX2M6SDo2Xn`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	We showed that per-head mixed-precision KV cache quantization over hardware-aligned bit-widths \{2, 4, 8, 16\} requires a cardinality constraint on 2-bit assignments to prevent non-additive distortion compounding through the residual stream.
4	A single constraint---limiting simultaneously active 2-bit heads to $k \leq 8$ (7\% of heads)---reduces perplexity on Qwen2.5-7B from 15.45 (uniform 4-bit) to 11.23, a 27.3\% improvement at $4\times$ compression.
5	Under the constraint, solver choice becomes irrelevant: greedy and MCKP produce equivalent allocations across all three architectures ($\Delta = 0.0000$), so a simple $O(H \log H)$ greedy algorithm suffices.
6	The benefit of non-uniform allocation depends on both the concentration and \emph{shape} of head sensitivity heterogeneity.
7	Qwen2.5-7B (concentration 0.61, $t_1/t_5{=}0.57$, spread pattern) shows large gains; Llama-3.1-8B ($t_1/t_5{=}0.71$, spike) shows marginal improvement (8.45 vs.\ 8.47 PPL); Mistral-7B-v0.3, Yi-1.5-9B, and Gemma-2-9B are counterproductive.
8	Yi-1.5-9B is a critical test case: despite the highest concentration tested ($0.71$, exceeding Qwen), its heterogeneity is a single-outlier spike ($t_1/t_5{=}0.90$) with no cross-bitwidth sensitivity gradient, so MCKP cannot redistribute budget.
9	A joint diagnostic using concentration and $t_1/t_5$ ratio distinguishes spread, spike, and flat patterns across our five models, computable from the same profiling pass used for allocation, letting practitioners decide \emph{before deployment} whether non-uniform quantization is worthwhile.
10	
11	\paragraph{Limitations.}
12	Our study has several limitations that temper the generality of the findings.
13	First, we evaluate only five 7--9B-scale models---too few to establish a statistically robust correlation between heterogeneity and quantization benefit; the observed trend is directional evidence, not a predictive law.
14	Second, profiling relies on a single sensitivity metric (perplexity-based per-head distortion); alternative measures such as gradient-based or activation-norm diagnostics remain unexplored and could yield different allocation decisions.
15	Third, we report perplexity and downstream accuracy but no real-kernel latency benchmarks, leaving the practical inference speedup from mixed-precision allocation unquantified.
16	Fourth, we have not verified whether these findings transfer to larger scales (70B+), where head counts and attention patterns differ substantially.
17	Finally, although we validate on four downstream tasks, profiling and primary evaluation use a single dataset (WikiText-2).
18	
19	\paragraph{Future Work.}
20	Extending evaluation to 70B+ models would test whether the heterogeneity--benefit relationship holds at scale.
21	Integration with production inference engines (vLLM, TensorRT-LLM) would enable real-kernel latency measurement, and investigating per-side K/V cardinality constraints (Appendix~\ref{sec:kv_separation}) or dynamic per-request allocation could further improve the framework.
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "60e7a27d-fb0c-4ad1-a6ef-b74197a4419d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\\label{sec:conclusion}\n\nWe showed that per-head mixed-precision KV cache quantization over hardware-aligned bit-widths \\{2, 4, 8, 16\\} requires a cardinality constraint on 2-bit assignments to prevent non-additive distortion compounding through the residual stream.\nA single constraint---limiting simultaneously active 2-bit heads to $k \\leq 8$ (7\\% of heads)---reduces perplexity on Qwen2.5-7B from 15.45 (uniform 4-bit) to 11.23, a 27.3\\% improvement at $4\\times$ compression.\nUnder the constraint, solver choice becomes irrelevant: greedy and MCKP produce equivalent allocations across all three architectures ($\\Delta = 0.0000$), so a simple $O(H \\log H)$ greedy algorithm suffices.\nThe benefit of non-uniform allocation depends on both the concentration and \\emph{shape} of head sensitivity heterogeneity.\nQwen2.5-7B (concentration 0.61, $t_1/t_5{=}0.57$, spread pattern) shows large gains; Llama-3.1-8B ($t_1/t_5{=}0.71$, spike) shows marginal improvement (8.45 vs.\\ 8.47 PPL); Mistral-7B-v0.3, Yi-1.5-9B, and Gemma-2-9B are counterproductive.\nYi-1.5-9B is a critical test case: despite the highest concentration tested ($0.71$, exceeding Qwen), its heterogeneity is a single-outlier spike ($t_1/t_5{=}0.90$) with no cross-bitwidth sensitivity gradient, so MCKP cannot redistribute budget.\nA joint diagnostic using concentration and $t_1/t_5$ ratio distinguishes spread, spike, and flat patterns across our five models, computable from the same profiling pass used for allocation, letting practitioners decide \\emph{before deployment} whether non-uniform quantization is worthwhile.\n\n\\paragraph{Limitations.}\nOur study has several limitations that temper the generality of the findings.\nFirst, we evaluate only five 7--9B-scale models---too few to establish a statistically robust correlation between heterogeneity and quantization benefit; the observed trend is directional evidence, not a predictive law.\nSecond, profiling relies on a single sensitivity metric (perplexity-based per-head distortion); alternative measures such as gradient-based or activation-norm diagnostics remain unexplored and could yield different allocation decisions.\nThird, we report perplexity and downstream accuracy but no real-kernel latency benchmarks, leaving the practical inference speedup from mixed-precision allocation unquantified.\nFourth, we have not verified whether these findings transfer to larger scales (70B+), where head counts and attention patterns differ substantially.\nFinally, although we validate on four downstream tasks, profiling and primary evaluation use a single dataset (WikiText-2).\n\n\\paragraph{Future Work.}\nExtending evaluation to 70B+ models would test whether the heterogeneity--benefit relationship holds at scale.\nIntegration with production inference engines (vLLM, TensorRT-LLM) would enable real-kernel latency measurement, and investigating per-side K/V cardinality constraints (Appendix~\\ref{sec:kv_separation}) or dynamic per-request allocation could further improve the framework.\n",
      "numLines": 22,
      "startLine": 1,
      "totalLines": 22
    }
  }
}
```

</details>

---

### Tool call

_source line 14_

<details open><summary>🔧 Tool call — Read · `toolu_018Eph4RFSwexBvPYnFd2opf`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "4a206328-a1a2-4089-ae4f-d725688f0940",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XdyULNV6gpu2R2AA7MgRj6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13051,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13051
      },
      "output_tokens": 25,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 15 · 2026-05-14T21:01:17.024Z_

<details><summary>↩ Tool result · `toolu_018Eph4RFSwexBvPYnFd2opf`</summary>

```text
1	\appendix
2	
3	\section{Aggressive Compression}
4	\label{sec:aggressive}
5	
6	At $4\times$ compression, Llama and Mistral show minimal benefit from non-uniform allocation.
7	At more aggressive ratios, the picture changes: at $5.3\times$ (average 3 bits), constrained MCKP achieves $45\times$ lower PPL than uniform on Llama (57.60 vs.\ 2643.77) and $44\times$ on Mistral (11.91 vs.\ 519.11), because the constraint protects sensitive heads from 2-bit assignment.
8	At $8\times$, the budget is too constrained for any allocation to preserve quality (both methods degrade catastrophically).
9	The intermediate regime ($5.3\times$) provides the largest relative benefit.
10	
11	\section{Profiling Resolution and Stability}
12	\label{sec:profiling_resolution}
13	
14	We compare standard-resolution profiling (16 sequences $\times$ 512 tokens) against high-resolution profiling (64 sequences $\times$ 2048 tokens) on Qwen2.5-7B at $4\times$ compression.
15	
16	High-resolution profiling improves constrained MCKP from 11.23 to 10.91 PPL ($-$0.32 absolute).
17	Relative to the bf16 baseline (9.81), this reduces the degradation from 1.42 to 1.10, a 22.5\% reduction.
18	The improvement comes from finer-grained sensitivity estimates: standard profiling detects non-zero 2-bit distortion in 37 of 112 heads, while high-resolution profiling detects 100 of 112 (2.7$\times$ more).
19	
20	The additional signal changes 8 of 112 head assignments.
21	High-resolution profiling protects shallow layers (L1--L3) at higher bit-widths while compressing mid-layers (L5--L11) more aggressively---a redistribution that standard profiling misses because its distortion estimates for these heads fall below the noise floor.
22	
23	\paragraph{Multi-seed stability.}
24	The profiled allocation is stable across calibration subsets.
25	Under hires profiling on Qwen2.5-7B, constrained MCKP yields mean PPL $10.99 \pm 0.06$ across 3 random calibration seeds (individual runs: 11.02, 10.90, 11.05), with std/mean below 0.6\%.
26	The bit distribution is identical across all seeds ($\{$2-bit: 8, 4-bit: 100, 8-bit: 4$\}$), and 101 of 112 heads (90.2\%) receive the same assignment in all three runs.
27	This stability confirms that the per-head sensitivity ranking is robust to calibration sampling noise.
28	
29	\paragraph{Numerical precision.}
30	Float32 profiling (64 $\times$ 2048 tokens) yields an identical constrained allocation and PPL within seed variance (10.89 vs.\ 10.91, $\Delta = 0.02 < \sigma = 0.06$), confirming that bfloat16 precision is sufficient for the profiling step.
31	
32	\paragraph{Per-layer optimality.}
33	To validate the additive distortion assumption underlying the MCKP formulation, we compare constrained MCKP against a per-layer brute-force oracle that exhaustively enumerates all $4^4 = 256$ bit-width combinations within each 4-head group on Qwen2.5-7B (hires profiling).
34	Of the 8 layers admitting multiple feasible allocations, MCKP matches the oracle exactly in 5; the remaining 3 show gaps of 0.018 (Layer~1), 0.014 (Layer~11), and 0.005 (Layer~4) PPL.
35	All three gaps involve repositioning a 2-bit assignment among heads with near-identical sensitivity within the same layer bit budget.
36	The negligible total gap ($<0.04$ PPL) confirms that the per-head additive distortion model closely approximates the true layer-level interaction.
37	
38	\section{KV Separation Ablation}
39	\label{sec:kv_separation}
40	
41	We test whether treating K and V caches as independent items in the MCKP solver---allowing different bit-widths for K and V within the same head---improves over joint allocation where K and V share a bit-width.
42	
43	Joint allocation achieves 10.91 PPL; separated K/V allocation achieves 11.22 ($+$0.31 worse).
44	The degradation stems from K-side over-compression: the separated solver doubles the maximum number of 2-bit K items to 16 (vs.\ 8 in the joint formulation), since K and V are counted independently against the cardinality constraint.
45	Meanwhile, V-side distortion is near-zero for most heads, so the solver assigns all V items to 4-bit, concentrating compression entirely on K.
46	
47	Of the 112 heads, 21 show K$\neq$V asymmetry in the separated allocation, all with K receiving a lower bit-width than V.
48	This systematic asymmetry suggests that K caches are inherently more compressible than V caches, consistent with the observation that key vectors primarily encode positional information while value vectors carry content.
49	
50	Joint allocation is sufficient under the current constraint formulation.
51	Separated K/V allocation with per-side cardinality constraints---limiting 2-bit assignments independently for K and V---is a direction for future work.
52	
53	\section{Runtime Benchmark}
54	\label{sec:runtime}
55	
56	\begin{table}[h]
57	\centering
58	\caption{PyTorch-level latency on Qwen2.5-7B (single NVIDIA RTX PRO 6000 (96\,GB), prompt\_len=256, gen\_len=128, mean of 10 runs). All conditions store KV in bf16 with simulated per-head quantize/dequantize calls; peak GPU memory is identical across rows.}
59	\label{tab:runtime}
60	\begin{tabular}{lccc}
61	\toprule
62	Condition & Prefill (ms) & Decode (ms/tok) & Throughput (tok/s) \\
63	\midrule
64	Baseline bf16       & 45.86 & 33.78 & 29.6 \\
65	Uniform 4-bit       & 54.25 & 42.46 & 23.6 \\
66	Constrained MCKP    & 57.03 & 46.09 & 21.8 \\
67	\bottomrule
68	\end{tabular}
69	\end{table}
70	
71	Table~\ref{tab:runtime} reports end-to-end latency for three KV cache configurations.
72	Uniform 4-bit quantization adds 25.7\% decode overhead relative to the bf16 baseline (42.46 vs.\ 33.78~ms/tok), reflecting per-head quantize/dequantize calls at every attention step.
73	Constrained MCKP adds a further 8.5\% over uniform (46.09 vs.\ 42.46~ms/tok), because mixed-precision allocation dispatches different dequantization kernels for 2-bit, 4-bit, and 8-bit heads within the same layer.
74	The MCKP solver itself runs in ${\sim}5$~ms and is invoked once at initialization, contributing negligibly to end-to-end latency.
75	Both quantized conditions achieve the same $4\times$ KV cache compression (5.25~MB vs.\ 21~MB at bf16), so the latency difference between uniform and MCKP reflects only the mixed-precision dispatch overhead, not a memory trade-off.
76	
77	\paragraph{Caveat.}
78	These measurements use PyTorch-level per-head \texttt{quantize}/\texttt{dequantize} calls and do \emph{not} represent optimized CUDA kernel performance.
79	Production inference engines such as vLLM and TensorRT-LLM employ fused attention kernels that batch dequantization with the matrix multiply, amortizing the per-head dispatch cost that dominates the gap between uniform and MCKP in our simulation.
80	The 8.5\% overhead reported here should therefore be treated as an upper bound on the mixed-precision penalty; real-world deployment with fused kernels would likely narrow or eliminate this gap.
81	The limitation noted in Section~\ref{sec:conclusion}---that we report no real-kernel latency benchmarks---remains: the numbers above quantify simulation overhead, not production inference speedup.
82	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "7b54f2a0-699e-4cbd-a51b-5b0547f4e622",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/appendix.tex",
      "content": "\\appendix\n\n\\section{Aggressive Compression}\n\\label{sec:aggressive}\n\nAt $4\\times$ compression, Llama and Mistral show minimal benefit from non-uniform allocation.\nAt more aggressive ratios, the picture changes: at $5.3\\times$ (average 3 bits), constrained MCKP achieves $45\\times$ lower PPL than uniform on Llama (57.60 vs.\\ 2643.77) and $44\\times$ on Mistral (11.91 vs.\\ 519.11), because the constraint protects sensitive heads from 2-bit assignment.\nAt $8\\times$, the budget is too constrained for any allocation to preserve quality (both methods degrade catastrophically).\nThe intermediate regime ($5.3\\times$) provides the largest relative benefit.\n\n\\section{Profiling Resolution and Stability}\n\\label{sec:profiling_resolution}\n\nWe compare standard-resolution profiling (16 sequences $\\times$ 512 tokens) against high-resolution profiling (64 sequences $\\times$ 2048 tokens) on Qwen2.5-7B at $4\\times$ compression.\n\nHigh-resolution profiling improves constrained MCKP from 11.23 to 10.91 PPL ($-$0.32 absolute).\nRelative to the bf16 baseline (9.81), this reduces the degradation from 1.42 to 1.10, a 22.5\\% reduction.\nThe improvement comes from finer-grained sensitivity estimates: standard profiling detects non-zero 2-bit distortion in 37 of 112 heads, while high-resolution profiling detects 100 of 112 (2.7$\\times$ more).\n\nThe additional signal changes 8 of 112 head assignments.\nHigh-resolution profiling protects shallow layers (L1--L3) at higher bit-widths while compressing mid-layers (L5--L11) more aggressively---a redistribution that standard profiling misses because its distortion estimates for these heads fall below the noise floor.\n\n\\paragraph{Multi-seed stability.}\nThe profiled allocation is stable across calibration subsets.\nUnder hires profiling on Qwen2.5-7B, constrained MCKP yields mean PPL $10.99 \\pm 0.06$ across 3 random calibration seeds (individual runs: 11.02, 10.90, 11.05), with std/mean below 0.6\\%.\nThe bit distribution is identical across all seeds ($\\{$2-bit: 8, 4-bit: 100, 8-bit: 4$\\}$), and 101 of 112 heads (90.2\\%) receive the same assignment in all three runs.\nThis stability confirms that the per-head sensitivity ranking is robust to calibration sampling noise.\n\n\\paragraph{Numerical precision.}\nFloat32 profiling (64 $\\times$ 2048 tokens) yields an identical constrained allocation and PPL within seed variance (10.89 vs.\\ 10.91, $\\Delta = 0.02 < \\sigma = 0.06$), confirming that bfloat16 precision is sufficient for the profiling step.\n\n\\paragraph{Per-layer optimality.}\nTo validate the additive distortion assumption underlying the MCKP formulation, we compare constrained MCKP against a per-layer brute-force oracle that exhaustively enumerates all $4^4 = 256$ bit-width combinations within each 4-head group on Qwen2.5-7B (hires profiling).\nOf the 8 layers admitting multiple feasible allocations, MCKP matches the oracle exactly in 5; the remaining 3 show gaps of 0.018 (Layer~1), 0.014 (Layer~11), and 0.005 (Layer~4) PPL.\nAll three gaps involve repositioning a 2-bit assignment among heads with near-identical sensitivity within the same layer bit budget.\nThe negligible total gap ($<0.04$ PPL) confirms that the per-head additive distortion model closely approximates the true layer-level interaction.\n\n\\section{KV Separation Ablation}\n\\label{sec:kv_separation}\n\nWe test whether treating K and V caches as independent items in the MCKP solver---allowing different bit-widths for K and V within the same head---improves over joint allocation where K and V share a bit-width.\n\nJoint allocation achieves 10.91 PPL; separated K/V allocation achieves 11.22 ($+$0.31 worse).\nThe degradation stems from K-side over-compression: the separated solver doubles the maximum number of 2-bit K items to 16 (vs.\\ 8 in the joint formulation), since K and V are counted independently against the cardinality constraint.\nMeanwhile, V-side distortion is near-zero for most heads, so the solver assigns all V items to 4-bit, concentrating compression entirely on K.\n\nOf the 112 heads, 21 show K$\\neq$V asymmetry in the separated allocation, all with K receiving a lower bit-width than V.\nThis systematic asymmetry suggests that K caches are inherently more compressible than V caches, consistent with the observation that key vectors primarily encode positional information while value vectors carry content.\n\nJoint allocation is sufficient under the current constraint formulation.\nSeparated K/V allocation with per-side cardinality constraints---limiting 2-bit assignments independently for K and V---is a direction for future work.\n\n\\section{Runtime Benchmark}\n\\label{sec:runtime}\n\n\\begin{table}[h]\n\\centering\n\\caption{PyTorch-level latency on Qwen2.5-7B (single NVIDIA RTX PRO 6000 (96\\,GB), prompt\\_len=256, gen\\_len=128, mean of 10 runs). All conditions store KV in bf16 with simulated per-head quantize/dequantize calls; peak GPU memory is identical across rows.}\n\\label{tab:runtime}\n\\begin{tabular}{lccc}\n\\toprule\nCondition & Prefill (ms) & Decode (ms/tok) & Throughput (tok/s) \\\\\n\\midrule\nBaseline bf16       & 45.86 & 33.78 & 29.6 \\\\\nUniform 4-bit       & 54.25 & 42.46 & 23.6 \\\\\nConstrained MCKP    & 57.03 & 46.09 & 21.8 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTable~\\ref{tab:runtime} reports end-to-end latency for three KV cache configurations.\nUniform 4-bit quantization adds 25.7\\% decode overhead relative to the bf16 baseline (42.46 vs.\\ 33.78~ms/tok), reflecting per-head quantize/dequantize calls at every attention step.\nConstrained MCKP adds a further 8.5\\% over uniform (46.09 vs.\\ 42.46~ms/tok), because mixed-precision allocation dispatches different dequantization kernels for 2-bit, 4-bit, and 8-bit heads within the same layer.\nThe MCKP solver itself runs in ${\\sim}5$~ms and is invoked once at initialization, contributing negligibly to end-to-end latency.\nBoth quantized conditions achieve the same $4\\times$ KV cache compression (5.25~MB vs.\\ 21~MB at bf16), so the latency difference between uniform and MCKP reflects only the mixed-precision dispatch overhead, not a memory trade-off.\n\n\\paragraph{Caveat.}\nThese measurements use PyTorch-level per-head \\texttt{quantize}/\\texttt{dequantize} calls and do \\emph{not} represent optimized CUDA kernel performance.\nProduction inference engines such as vLLM and TensorRT-LLM employ fused attention kernels that batch dequantization with the matrix multiply, amortizing the per-head dispatch cost that dominates the gap between uniform and MCKP in our simulation.\nThe 8.5\\% overhead reported here should therefore be treated as an upper bound on the mixed-precision penalty; real-world deployment with fused kernels would likely narrow or eliminate this gap.\nThe limitation noted in Section~\\ref{sec:conclusion}---that we report no real-kernel latency benchmarks---remains: the numbers above quantify simulation overhead, not production inference speedup.\n",
      "numLines": 82,
      "startLine": 1,
      "totalLines": 82
    }
  }
}
```

</details>

---

### Assistant

_source line 16_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clear picture of all five files. Let me analyze what needs to change:

1. **analysis.tex** - The current content already looks quite good and aligned with the new Claim 3. Let me check carefully what needs updating:
   - The mechanism section already describes spread vs spike patterns well
   - The diagnostic framework section already has the joint diagnostic
   - Actually, reading more carefully, the current analysis.tex already has most of the desired content. Let me check what specific changes are needed.

Looking at the task requirements vs current content:

**analysis.tex**: The current content already has:
- Mechanism explanation with Qwen spread vs Yi spike


- t1/t5 ratio
- Joint diagnostic
- Illustrative threshold language
- Table with all the data

Now I'm checking the specific data values against the task requirements to make sure the table matches exactly what's needed. I'm checking the 24× notation against the actual ratio—23.7 is close enough that rounding to 24 makes sense. Looking back at the paper text, it already shows both values: the 24× gap alongside the specific ratios t₁/t₅=0.90 and t₁/t₂=23.7, so that's consistent. Now I need to carefully review what the task actually requires versus what's already in the analysis.tex file to identify what's genuinely missing or needs fixing. I need to verify whether the current analysis.tex actually implements the specific thresholds the task requires. The diagnostic framework mentions "moderate-to-high concentration" but doesn't explicitly state the "> 0.50" threshold, and I should check if the exact combined condition "concentration > 0.50 AND τ₁/τ₅ < 0.70" is clearly articulated in the current version or if it needs to be made more explicit. I'm checking the abstract against the task requirements—it already incorporates the joint diagnostic combining concentration and distribution shape, and mentions the five architectures. The spike versus spread distinction is present in the earlier section. It looks like the current version is closer to what's needed than the task description suggests, so I should verify whether the abstract properly emphasizes that the diagnostic correctly identifies all five cases rather than just indicating potential benefit. I'm checking what's already in place across the paper. The appendix already has the float32 validation note about bfloat16 precision being sufficient, so that's covered. Now I need to see what gaps remain—the analysis section could use more explicit language around the joint diagnostic condition and its perfect classification rate, and I should verify whether the introduction adequately emphasizes the Yi-1.5 counterexample as a key motivating case. I see the task is asking for explicit quantitative thresholds in the diagnostic section. The joint condition needs to be stated clearly: concentration > 0.50 AND τ₁/τ₅ < 0.70 results in correct 5/5 classification, with concrete examples like Qwen at 0.57 (spread strategy) and Yi-1.5 at 0.90 (spike strategy). I need to make these numerical criteria explicit rather than keeping them vague. Looking at the current structure of section 5.1, I see the numbers and mechanism are mixed together rather than organized with mechanism first. I need to restructure this so the explanation of why the concentration metric matters comes before diving into the specific results from Qwen and Yi-1.5. The key insight about cross-bitwidth gradients should frame the discussion before the numerical evidence appears. I'm working through the specific changes needed across multiple sections. The key insight is that mechanism should come before numbers—the current text in §5.1 actually does this reasonably well, but the opening paragraph leads with Qwen results instead. For §5.2, I need to add explicit thresholds and clarify that the diagnostic correctly classifies all five architectures. The abstract needs to highlight spike versus spread as a key contribution, the introduction could strengthen the Yi-1.5 counterexample, and the conclusion should frame shape analysis as practical guidance. Let me now draft these targeted revisions. I'm laying out the three diagnostic categories with their decision rules and empirical examples. The Spread pattern shows when non-uniform allocation helps—like Qwen's substantial PPL gains—while Spike indicates a single dominant head that resists redistribution, and Flat suggests the model lacks sufficient concentration to benefit from reallocation.

The 0.70 threshold on the ratio between top and fifth-ranked heads is a heuristic derived from these five architectures, so I should note it needs validation across a broader model set before generalizing it.

Looking at the abstract more carefully, I see the key insight about Yi-1.5-9B: it has the highest GQA ratio and concentration among the models tested, but still fails under non-uniform allocation because its heterogeneity is concentrated in a single outlier spike rather than distributed across heads in a way that lets the algorithm redistribute budget effectively.

The joint diagnostic combining concentration and distribution shape is what actually predicts whether an architecture will benefit from non-uniform quantization—it correctly identifies all five architectures in this study, which is the core contribution here. The diagnostic framework needs concrete thresholds—concentration around 0.50 or higher signals whether non-uniform quantization will actually help, and I should verify this correctly identifies all five architectures we tested. For the practitioner-facing summary, I want to emphasize that shape analysis gives a clear, actionable guideline: compute the concentration and $t_1/t_5$ ratio from a single profiling pass, then decide upfront whether the overhead of non-uniform quantization is justified before deployment.

Looking at §5.1, the current structure introduces Qwen's results first, then uses Yi-1.5 as a counterexample—but the task wants mechanism before numbers. I should reorganize so the spike-versus-spread mechanism explanation comes first, establishing why concentration matters, then show how this plays out in the actual results across architectures.

For the specific edits: I need to make the Spread condition threshold explicit (concentration > 0.50) in the diagnostic framework, strengthen the abstract's language from "can indicate" to "correctly identifies," add Yi-1.5 as a concrete counterexample in the introduction to demonstrate diagnostic value, and add "practical guideline" framing to the conclusion. The appendix already has what's needed.

Now I'm drafting the actual text changes, starting with the analysis section where I'll clarify the diagnostic conditions with explicit thresholds and the 5/5 classification statement. I'm noticing an inconsistency in my classification—Llama has low concentration (0.34) but I've grouped it under Spike, which should have high concentration. Let me reconsider: Llama's high $t_1/t_5$ ratio (0.71) suggests sensitivity is dominated by early bitwidths, but with such low overall concentration, the pattern doesn't fit the Spike category cleanly. I should verify whether Llama belongs in Flat instead, or if there's a separate pattern I'm missing here. Now I'm checking this joint condition across all the models—concentration above 0.50 combined with a t1/t5 ratio below 0.70 correctly identifies where MCKP provides benefits. Qwen passes both thresholds and shows the expected Spread pattern, while Yi-1.5, Llama, Mistral, and Gemma-2 all fail the concentration requirement, which aligns with MCKP not helping them. There's a mismatch here—Llama shows spike-like behavior in its t1/t5 ratio, but the concentration threshold alone would exclude it from the MCKP benefit category. The joint condition (concentration > 0.50 AND t1/t5 < 0.70) is what actually determines whether MCKP helps, and this correctly identifies all five cases, meaning any model failing either threshold shouldn't use MCKP regardless of its other characteristics. Writing the decision framework... I'm realizing the joint condition—concentration above 0.50 *and* a ratio below 0.70—is the cleaner way to frame this. It cleanly separates Qwen, which benefits from non-uniform allocation, from the other four architectures that don't, and it correctly classifies all five models we tested. Now I need to restructure the diagnostic section to present this joint condition upfront, then reorganize the categories to flow from the concentration check first, followed by the shape check, and add a statement confirming the classification accuracy. I'm laying out the decision rules for when to apply each allocation strategy—spread works best when there's moderate-to-high concentration with varied sensitivity across bitwidths, like Qwen's 27.3% improvement, while spike patterns with dominant outliers benefit from uniform allocation despite high concentration, and flat sensitivity profiles offer no advantage to non-uniform approaches regardless of the model. I'm noticing a discrepancy—Llama gets reclassified as Flat under the concentration threshold (< 0.50), but the table still marks it as Spike based on its shape characteristics like the high t1/t5 ratio. I think the solution is to keep the table's "Shape" column describing the actual observed pattern while using concentration thresholds separately for the allocation decision.

Actually, I'm overcomplicating this. The task references §5.3 but the current file has these sections renumbered as §5.1 and §5.2—the content is the same, just shifted. I should focus on making the minimal necessary changes to the diagnostic framework rather than getting caught up in the classification inconsistency.

The key moves are: make concentration thresholds explicit in the diagnostic, add the 5/5 classification statement, and handle Llama's reclassification cleanly. I can keep "Spike" in the table since it describes the shape, but in the diagnostic framework itself, I'll make concentration the primary filter—so low concentration models like Llama get classified as "Flat" in the recommendation, even if their shape is technically spiky. The table and diagnostic serve different purposes, so this distinction is acceptable. Now I'm checking each model against these thresholds. Qwen fits the Spread category cleanly, but Yi-1.5 and Llama both cross the spike threshold with their high t1/t5 ratios, which keeps them in the Spike category even though Llama's concentration is borderline. Mistral and Gemma-2 fall into Flat since their concentrations are too low.

The decision rule is straightforward: MCKP is recommended when concentration exceeds 0.50 AND the t1/t5 ratio stays below 0.70. This gives me the cleanest classification across all five models. I'll use this approach and write up the diagnostic descriptions for each pattern type.

Writing diagnostic definitions... The joint condition—concentration above roughly 0.50 and $t_1/t_5$ below 0.70—correctly pinpoints the single architecture that benefits from non-uniform allocation across all five models. These thresholds are illustrative boundaries derived from this limited set, so I should validate them against a broader range of architectures before treating them as universal principles.

Now I'm thinking through how to restructure section 5.1 to lead with mechanism rather than numbers. The current flow presents the concentration metric definition, then jumps into Qwen's specific results with their numerical spread characteristics. But the task emphasizes putting mechanism first—I should establish the key insight about spread versus spike patterns before diving into individual model examples.

The mechanism explanation is actually scattered across the Yi-1.5 counterexample discussion and Qwen details. I need to consolidate this insight upfront: concentration alone doesn't determine MCKP benefit because the underlying head behavior pattern matters more. Then I can use Qwen and Yi-1.5 as concrete illustrations of different mechanisms. 我引入 top-1/top-5 比率作为量化指标来区分 spike 和 spread 模式，Qwen 的比率较低表现为 spread，而 Yi-1.5 的比率接近 1 则呈现 spike 特征。结合浓度阈值，这个指标能有效分类两种模式，虽然这只是一个示意性的阈值而非通用规则。

现在我需要重新组织第 5.1 节，把机制洞察放在前面，而不是先堆砌数据。我会先阐述 MCKP 收益的核心要求——不仅需要高浓度，还需要跨比特宽度的梯度多样性分布在多个注意力头上，然后用 Qwen 作为正例展示 spread 机制如何实现这一点，再用 Yi-1.5 作为反例说明 spike 机制为何失效。 The spread pattern in Qwen2.5-7B demonstrates this principle—multiple heads show sensitivity across different bitwidths rather than concentrating in one, which gives the solver more flexibility. Even with moderate concentration at 0.61, constrained MCKP achieves a 27.3% improvement over uniform quantization by exploiting these distributed gradients.

Yi-1.5-9B presents the opposite case: despite higher concentration (0.71), the optimization actually hurts performance because the sensitivity is dominated by a single extreme outlier—Layer-4 Head-3 with a 2-bit delta of 13.12, creating a 24× gap to the second-ranked head. This extreme concentration means the solver has little flexibility to optimize across the bitwidth space. I'm realizing the key insight should come first—that MCKP benefits from spread heterogeneity across multiple heads rather than isolated spikes at single bitwidths. Adding this framing sentence right after the table reference would let the Qwen and Yi-1.5 examples serve as concrete evidence of this principle, making the mechanism clear before diving into the numbers. I'm mapping out the specific edits needed across multiple sections of the paper. The key changes involve making the spread versus spike mechanism more explicit upfront in section 5.1, clarifying the concentration thresholds in the diagnostics, strengthening the language around what the method "correctly identifies" in the abstract, adding a counterexample to the introduction, and framing the diagnostic guidance as a practical guideline in the conclusion. I'm finishing the thought about Yi-1.5-9B's heterogeneity pattern—even though it has higher concentration than Qwen, the distribution of sensitivity across bitwidths is fundamentally different, which explains why constrained MCKP actually hurts performance compared to uniform quantization. L4H3's sensitivity is locked to the 2-bit operating point with essentially zero deltas at 4-bit and 8-bit, creating a "spike" pattern where the model gains nothing from upgrading beyond 4-bit even though that's where the outlier's distortion lives. This means any budget freed from downgrading other heads can't be productively allocated elsewhere, which is why the constrained approach fails despite the high concentration of sensitivity. I'm distinguishing between two allocation strategies based on the concentration metric and gradient shape. When concentration is moderate-to-high but the ratio stays below 0.70, I call this the "Spread" pattern—multiple heads show sensitivity across different bitwidths, so the solver has flexibility to redistribute. Qwen exemplifies this with a 0.57 ratio and achieves strong improvements. Conversely, the "Spike" pattern occurs when the ratio exceeds 0.70, meaning sensitivity clusters on a single outlier with flat gradients elsewhere, leaving the solver no meaningful levers to pull. Yi-1.5 demonstrates this constraint. Qwen demonstrates the effectiveness of non-uniform allocation with a 27.3% perplexity improvement, while spike-dominated models like Yi-1.5 and Llama show minimal gains since their sensitivity is concentrated in a single outlier that the solver can't meaningfully exploit. For flat sensitivity profiles with low concentration, uniform allocation is again the right choice since there's no meaningful gradient to guide differentiated budget distribution. I'm looking at how to refine the abstract and introduction to emphasize that the joint diagnostic combining concentration and distribution shape can distinguish which architectures will actually benefit from non-uniform quantization, separating the cases where MCKP helps from those where it doesn't. I'm finalizing the edits across all the files—checking that the diagnostic sentence in conclusion.tex captures both the concentration and ratio thresholds, and verifying the appendix note on float32 validation is already in place. Now I'm executing all the changes. I'm seeing that Yi-1.5-9B's heterogeneity is driven by a single extreme outlier in Layer-4 Head-3, which has a massive 2-bit sensitivity but essentially zero impact at higher bitwidths. This creates a fundamental problem for the solver: upgrading that head from 2-bit to 4-bit eliminates its distortion, but there's no gradient to exploit across bitwidths, so any budget freed elsewhere can't be productively reallocated.

This is what I'm calling a "spike" pattern—high concentration in one head, but sensitivity locked to a single bitwidth. The next part is distinguishing this from other heterogeneity shapes to guide allocation strategy: spread patterns like Qwen's have multiple heads with cross-bitwidth gradients, giving the solver flexibility to redistribute, whereas spike patterns need a different approach. I'm checking the indentation in the file more carefully—the Read tool shows line numbers with tabs, so I need to verify that lines 69-73 use two spaces before `\item` to match the formatting. Looking at line 75, I should also note that the $t_1/t_5 \approx 0.70$ threshold is just an illustrative boundary from these five architectures and would need validation across a broader set before being considered a general principle.

For the abstract edits, I'm focusing on lines 7-8, where I only need to modify line 8 about the joint heterogeneity diagnostic. And in the intro section at line 53, I'm starting to describe the diagnostic that combines concentration and distribution shape using the $t_1/t_5$ ratio.

Now looking at the continuation about distinguishing spread, spike, and flat patterns across the five models—this validates the diagnostic approach and shows it's computable from the same profiling pass, so practitioners can decide upfront whether non-uniform quantization makes sense for their architecture.

For the conclusion, I'm summarizing how this joint diagnostic using concentration and the $t_1/t_5$ ratio works across the models, emphasizing that it's practical because it comes from the same profiling step used for allocation.

For the analysis section on Qwen, I'm noting that unlike other models, Qwen's Layer-0 heads show sensitivity across multiple bitwidths rather than just at one point, which suggests a different heterogeneity pattern. I'm realizing that after moving the Qwen mechanism discussion earlier with my edits, line 23's detailed breakdown of the Layer-0 heads becomes somewhat redundant since I've already introduced the spread pattern concept. The current structure has me going from a high-level Qwen summary into the Yi-1.5 counterexample, then back to Qwen specifics—which creates an awkward flow. I should reconsider whether that detailed mechanism explanation at line 23 still serves a purpose or if it's now just repeating what I've already established about the spread pattern. of "However, concentration alone does not predict MCKP benefit." The "concentration alone" phrasing is crucial for setting up the counterexample, but since the new key insight sentence already establishes that spread matters more than concentration, I can open the Yi paragraph directly with "Yi-1.5-9B is a critical counterexample" and it flows naturally from the preceding discussion.

So the revised structure for §5.1 works like this: I introduce the central finding about spread heterogeneity, show how Qwen exemplifies that pattern with its distributed sensitivity across multiple bitwidths, then pivot to Yi-1.5 as the case that breaks the concentration-only hypothesis. The "In contrast" transition still lands well because the reader now understands what they're contrasting against.

I need to apply these edits sequentially since each change affects the file state for the next one. I'm realizing all four analysis.tex edits target completely separate sections of the file, so I can execute them all at once without any conflicts. Let me verify the line ranges don't overlap—Edit 1 hits lines 11-12, Edit 2 covers 15-21, Edit 3 is at 69-73, and Edit 4 is just line 75. Since they're all distinct, I can batch all seven edits together and run them in parallel. I'm working through the edits to restructure this section. I need to insert the key insight about MCKP as its own paragraph between the table summary and the Qwen example, which means adding proper spacing and ensuring the new paragraph flows naturally into the existing content. The key insight is that MCKP's effectiveness hinges on spread heterogeneity—multiple heads exhibiting sensitivity across different bitwidths—rather than sensitivity concentrated in a single outlier. Qwen2.5-7B demonstrates this pattern well, with its top-5% concentration at 0.61 and ratio of 0.57, where Layer-0 heads drive most of the 2-bit distortion across the board.

Yi-1.5-9B presents the contrasting case: despite having the highest GQA ratio (8:1) and top-5% concentration (0.71), it fails under non-uniform allocation because its heterogeneity manifests as an isolated spike lacking cross-bitwidth sensitivity gradients—the opposite of the spread pattern that lets MCKP reallocate budget effectively.

I'm proposing a joint diagnostic that combines concentration metrics with distribution shape, specifically the t₁/t₅ ratio, to predict which architectures will actually benefit from non-uniform quantization. Testing this across five models shows it reliably distinguishes between spread heterogeneity that MCKP can exploit and spike or flat patterns where non-uniform allocation offers no advantage. I'm finalizing the wording for the diagnostic description—it needs to emphasize that the joint measure correctly identifies all five architectures and highlights the distinction between spread heterogeneity (which MCKP can exploit) versus spike and flat patterns (where non-uniform quantization doesn't help). Now I'm ready to execute all seven edits across the different files, checking that each old_string is unique to avoid conflicts. I'm torn between doing all the edits in parallel versus playing it safe with sequential execution on the same file. The instructions favor parallel calls when there are no dependencies, but file writes could create race conditions. Let me split this strategically—run the independent files in parallel first, then tackle the analysis.tex edits together since they're in non-overlapping regions. Actually, I'll just attempt all of them at once and fall back to sequential if needed. Now I'm finalizing the old and new text pairs for each edit. Yi-1.5-9B demonstrates that high concentration alone doesn't guarantee MCKP benefits---despite having even higher concentration than Qwen (0.71 vs 0.61), constrained MCKP actually hurts performance. The difference is that Yi-1.5's heterogeneity stems from a single extreme outlier: Layer-4 Head-3 dominates with a 2-bit delta of 13.12, while the next head drops to 0.55, creating a 24× gap that concentrates sensitivity in one place rather than spreading it across multiple heads.

The real constraint is that this outlier's sensitivity exists only at the 2-bit operating point---upgrading it to 4-bit or 8-bit provides no additional benefit, so the solver can't exploit cross-bitwidth tradeoffs. This "spike" pattern means the budget freed by downgrading other heads has nowhere productive to go, making constrained allocation counterproductive compared to uniform quantization. cross-bitwidth gradient structure.

Yi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55—a 24× gap. Critically, L4H3's sensitivity is confined to the 2-bit operating point; its 4-bit and 8-bit deltas are essentially zero. This means the solver has only one lever: upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrades provide no benefit, so freed budget from downgrading other heads has nowhere useful to go. This is the "spike" pattern—high concentration driven by a single outlier with sensitivity at only one bitwidth.

Now I'm looking at the diagnostic framework in the analysis document. The key distinction is between "Spread" patterns, where multiple heads have sensitivity gradients across different bitwidths, allowing the solver to redistribute budget effectively, versus "Spike" patterns, where sensitivity is confined to a single outlier with no cross-bitwidth gradient, making uniform allocation the better choice. Qwen exemplifies the Spread case with significant PPL improvement through non-uniform allocation, while Yi-1.5 and Llama demonstrate the Spike pattern where uniform allocation is more appropriate. I'm continuing to work through the categorization of model sensitivity patterns. For spike-dominated distributions where one head overwhelms the others, uniform allocation is the right call since the solver can't meaningfully redistribute across bitwidths—Yi-1.5 and Llama both show this pattern and don't benefit from non-uniform strategies. For flat distributions with minimal concentration, uniform allocation again makes sense because there's no meaningful signal to guide differentiated allocation, as we see with Mistral and Gemma-2.

Now I'm refining the threshold discussion. The $t_1/t_5 \approx 0.70$ boundary isn't meant to be a hard rule—it's an illustrative threshold derived from these five architectures that needs validation on a broader set. The key insight is that the joint condition of concentration above 0.50 and $t_1/t_5$ below 0.70 correctly separates the beneficial cases from the non-beneficial ones across all five models we studied, but both thresholds should be treated as preliminary until tested more widely. The Yi-1.5-9B model presents an interesting edge case—its concentration rivals Qwen's, but the single dominant spike in its distribution makes MCKP allocation actually harmful rather than beneficial. This reinforces that concentration alone isn't sufficient; the $t_1/t_5$ ratio captures whether that concentration manifests as exploitable spread versus a pathological spike pattern. The diagnostic thresholds (concentration $\gtrsim 0.50$ and $t_1/t_5$ ratio $\lesssim 0.70$) emerge as practical markers practitioners can compute during standard profiling to decide upfront whether non-uniform quantization will pay off. I'm thinking through whether I can apply all four edits to analysis.tex in parallel. Since the Edit tool uses string matching rather than line numbers, edits to non-overlapping sections should work even if applied simultaneously—Edit 2 will still find its target text even after Edit 1 adds lines elsewhere. To be safe though, I'll batch the three independent files first, then handle the analysis.tex edits together.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "dddfc25c-bd48-4ea3-80e4-9603acd2ea04",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015Vc172h4d7mfQD64rsHZhA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8917,
      "cache_read_input_tokens": 24892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8917
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 17_

开始修改 5 个文件。先并行修改 abstract、introduction、conclusion，然后顺序修改 analysis.tex（4 处）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "5d37b8cf-a742-4bbb-89c7-c63581827e3e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015Vc172h4d7mfQD64rsHZhA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8917,
      "cache_read_input_tokens": 24892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8917
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 18_

<details open><summary>🔧 Tool call — Edit · `toolu_012WwxhQjCGG5bncRHM7VGoe`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/abstract.tex",
  "old_string": "We propose a joint heterogeneity diagnostic combining concentration and distribution shape, validated on five architectures, that can indicate before any allocation whether a given architecture will benefit from non-uniform quantization.",
  "new_string": "We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) that correctly identifies all five architectures studied---distinguishing spread heterogeneity (MCKP-exploitable) from spike and flat patterns where non-uniform allocation provides no benefit."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "9054f848-658b-4141-9a81-e71db6893420",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015Vc172h4d7mfQD64rsHZhA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8917,
      "cache_read_input_tokens": 24892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8917
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 19 · 2026-05-14T21:07:46.883Z_

<details><summary>↩ Tool result · `toolu_012WwxhQjCGG5bncRHM7VGoe`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/abstract.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "3438e588-5e24-4ace-807e-4f761cb66e67",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/abstract.tex",
    "oldString": "We propose a joint heterogeneity diagnostic combining concentration and distribution shape, validated on five architectures, that can indicate before any allocation whether a given architecture will benefit from non-uniform quantization.",
    "newString": "We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) that correctly identifies all five architectures studied---distinguishing spread heterogeneity (MCKP-exploitable) from spike and flat patterns where non-uniform allocation provides no benefit.",
    "originalFile": "Per-head mixed-precision quantization of the KV cache promises lower perplexity than uniform quantization at the same average bit-width, but on hardware-aligned bit-widths $\\{2, 4, 8, 16\\}$, existing solvers fail catastrophically: unconstrained greedy and MCKP allocation achieve 32.45 and 36.92 perplexity on Qwen2.5-7B---far worse than uniform 4-bit (15.45).\nWe trace this failure to \\emph{2-bit distortion compounding}: when the majority of heads are assigned 2-bit precision, per-head quantization errors interact non-additively through the residual stream, violating the additive objective assumed by standard solvers.\nWe show that a single cardinality constraint capping the number of 2-bit assignments is a minimal sufficient fix.\nOn Qwen2.5-7B at $4\\times$ compression, constrained allocation achieves 11.23 perplexity, a 27.3\\% reduction over uniform 4-bit.\nThe constraint also renders solver choice irrelevant: constrained greedy and constrained MCKP produce equivalent bit-width assignments across all three tested architectures ($\\Delta{=}0.0000$), enabling use of a simple $O(H \\log H)$ greedy algorithm; per-layer brute-force oracle confirms near-optimality (max gap 0.02 PPL).\nHowever, the benefit depends on architecture: on Llama-3.1-8B the improvement is marginal (8.45 vs.\\ 8.47), and on Mistral-7B-v0.3, Yi-1.5-9B, and Gemma-2-9B non-uniform allocation is counterproductive.\nNotably, Yi-1.5-9B has the highest GQA ratio tested (8:1) and the highest top-5\\% concentration (0.71), yet degrades under non-uniform allocation---because its heterogeneity is a single-outlier ``spike'' with no cross-bitwidth sensitivity gradient, rather than the ``spread'' pattern that enables MCKP to redistribute budget across heads.\nWe propose a joint heterogeneity diagnostic combining concentration and distribution shape, validated on five architectures, that can indicate before any allocation whether a given architecture will benefit from non-uniform quantization.\n",
    "structuredPatch": [
      {
        "oldStart": 5,
        "oldLines": 4,
        "newStart": 5,
        "newLines": 4,
        "lines": [
          " The constraint also renders solver choice irrelevant: constrained greedy and constrained MCKP produce equivalent bit-width assignments across all three tested architectures ($\\Delta{=}0.0000$), enabling use of a simple $O(H \\log H)$ greedy algorithm; per-layer brute-force oracle confirms near-optimality (max gap 0.02 PPL).",
          " However, the benefit depends on architecture: on Llama-3.1-8B the improvement is marginal (8.45 vs.\\ 8.47), and on Mistral-7B-v0.3, Yi-1.5-9B, and Gemma-2-9B non-uniform allocation is counterproductive.",
          " Notably, Yi-1.5-9B has the highest GQA ratio tested (8:1) and the highest top-5\\% concentration (0.71), yet degrades under non-uniform allocation---because its heterogeneity is a single-outlier ``spike'' with no cross-bitwidth sensitivity gradient, rather than the ``spread'' pattern that enables MCKP to redistribute budget across heads.",
          "-We propose a joint heterogeneity diagnostic combining concentration and distribution shape, validated on five architectures, that can indicate before any allocation whether a given architecture will benefit from non-uniform quantization.",
          "+We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) that correctly identifies all five architectures studied---distinguishing spread heterogeneity (MCKP-exploitable) from spike and flat patterns where non-uniform allocation provides no benefit."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 20_

<details open><summary>🔧 Tool call — Edit · `toolu_01QFVJMVcZmXo55rS4L32BkU`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/introduction.tex",
  "old_string": "\\item We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) to indicate whether non-uniform allocation will help a given architecture, distinguishing ``spread'' heterogeneity (MCKP-exploitable) from ``spike'' and ``flat'' patterns, validated on five models (\\S\\ref{sec:heterogeneity}).",
  "new_string": "\\item We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) that correctly separates architectures where non-uniform allocation helps from those where it does not, across all five models tested. Yi-1.5-9B serves as a critical test: its concentration exceeds Qwen's, yet its single-outlier spike pattern makes MCKP counterproductive (\\S\\ref{sec:heterogeneity})."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "780d82a9-fe81-4cd0-a897-3ae322e5ba5c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015Vc172h4d7mfQD64rsHZhA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8917,
      "cache_read_input_tokens": 24892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8917
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 21 · 2026-05-14T21:07:49.227Z_

<details><summary>↩ Tool result · `toolu_01QFVJMVcZmXo55rS4L32BkU`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/introduction.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "a1def66e-a7c9-4c75-a335-05f1e5d49a34",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/introduction.tex",
    "oldString": "\\item We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) to indicate whether non-uniform allocation will help a given architecture, distinguishing ``spread'' heterogeneity (MCKP-exploitable) from ``spike'' and ``flat'' patterns, validated on five models (\\S\\ref{sec:heterogeneity}).",
    "newString": "\\item We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) that correctly separates architectures where non-uniform allocation helps from those where it does not, across all five models tested. Yi-1.5-9B serves as a critical test: its concentration exceeds Qwen's, yet its single-outlier spike pattern makes MCKP counterproductive (\\S\\ref{sec:heterogeneity}).",
    "originalFile": "\\section{Introduction}\n\\label{sec:introduction}\n\nPer-head mixed-precision quantization of the KV cache is a natural strategy for reducing memory during LLM inference: assign fewer bits to insensitive heads and more bits to sensitive ones, achieving lower perplexity than uniform quantization at the same average bit-width.\nRecent work on KV cache quantization explores both uniform schemes~\\cite{liu2024kivi,hooper2024kvquant,lin2024qserve,he2024zipcache} and token-level mixed-precision approaches~\\cite{ge2024fastgen,lei2026arkv}, while complementary methods reduce cache size through eviction~\\cite{zhang2023h2o,li2024snapkv}.\nRateQuant~\\cite{zuo2026ratequant} formalizes per-head allocation as a rate-distortion optimization and shows that greedy allocation is optimal when bit-widths are consecutive integers $\\{2,3,4,5,6\\}$, exploiting the polymatroid structure of the feasible set (their Proposition~6).\n\nIn practice, hardware-efficient inference requires bit-widths drawn from $\\{2, 4, 8, 16\\}$---the formats natively supported by modern accelerators.\nOn this non-consecutive set, the polymatroid structure breaks down, and greedy is no longer provably optimal.\nOne might expect that exact MCKP solvers would fill this gap.\nThey do not.\nOn Qwen2.5-7B at $4\\times$ compression, unconstrained greedy achieves 32.45 PPL and unconstrained MCKP achieves 36.92---both \\emph{far worse} than uniform 4-bit (15.45).\nThe optimization does not merely underperform; it fails catastrophically.\n\nThe root cause is not solver suboptimality but a violation of the objective's additive distortion assumption.\nBoth solvers assign 68--75 of 112 KV heads to 2-bit, where per-head quantization errors are large enough to compound through the residual stream.\nThe additive model predicts $\\sim$11 PPL for these allocations; the actual PPL is $3$--$4\\times$ higher.\nAt 4-bit and above, per-head distortions are small and compound negligibly---uniform 4-bit achieves close to its additive prediction---but 2-bit distortions are orders of magnitude larger.\nWhen most heads are quantized to 2-bit simultaneously, cumulative truncation errors exceed the network's capacity to compensate, and perplexity degrades super-linearly.\n\nThis observation points to a minimal intervention: cap the number of 2-bit assignments.\nWe add a single cardinality constraint $\\sum_h \\mathbb{1}[b_h{=}2] \\leq k$ to the standard MCKP formulation (\\S\\ref{sec:method}).\nOn Qwen2.5-7B, setting $k{=}8$ (7\\% of heads) yields 11.23 PPL---a 27.3\\% reduction over uniform 4-bit.\nThe constraint works by forcing the solver to use 2-bit only on the least-sensitive heads, while redistributing the freed budget to protect sensitive heads at 8-bit or 16-bit.\nThis is not a heuristic patch: the constraint directly addresses the identified failure mode and is compatible with any solver.\n\nA surprising consequence is that, under the cardinality constraint, the choice of solver becomes irrelevant.\nConstrained greedy and constrained MCKP produce identical allocations---not approximately, but exactly: all 112 heads receive the same bit-width on Qwen2.5-7B, all 256 on Llama-3.1-8B, and 255 of 256 on Mistral-7B-v0.3 (the single difference is a zero-distortion tie with no PPL impact).\nThe constraint narrows the feasible set enough that greedy's locally optimal decisions are globally optimal (\\S\\ref{sec:solver_equiv}), enabling practitioners to use the simpler $O(H \\log H)$ greedy algorithm without sacrificing solution quality.\nA per-layer brute-force oracle confirms near-optimality: the maximum gap across 28 layers is 0.02 PPL, 0.4\\% of the total improvement (\\S\\ref{sec:solver_equiv}).\n\nHowever, non-uniform allocation does not help universally.\nOn Llama-3.1-8B, constrained MCKP achieves 8.45 PPL vs.\\ uniform 8.47---a marginal 0.2\\% improvement.\nOn Mistral-7B-v0.3, it is slightly \\emph{worse}: 7.16 vs.\\ 7.13.\nOn Yi-1.5-9B, non-uniform allocation degrades PPL by 1.3\\% (7.31 vs.\\ 7.22) despite Yi-1.5 having the highest GQA ratio tested (8:1).\nOn Gemma-2-9B (GQA 2:1, the lowest ratio tested), degradation is 0.3\\% (9.05 vs.\\ 9.03).\nThe difference across architectures traces to head sensitivity heterogeneity---specifically, its \\emph{distribution shape}, not GQA ratio alone.\nQwen's KV heads vary widely in 2-bit distortion, with Layer-0 heads forming a cluster of high sensitivity; Yi-1.5 has a single extreme outlier but otherwise uniform heads (a ``spike'' pattern that MCKP cannot exploit); Gemma-2 and Mistral show near-uniform sensitivity across all heads.\nWhen there is no exploitable heterogeneity, non-uniform allocation adds noise without benefit.\n\nThis motivates a diagnostic question that prior work does not address: \\emph{when} should a practitioner use per-head mixed-precision quantization?\nWe propose a joint heterogeneity diagnostic based on concentration \\emph{and} distribution shape of per-head distortion (\\S\\ref{sec:heterogeneity}).\nOn our five architectures, the diagnostic separates the beneficial case (Qwen, concentration 0.61, spread pattern) from cases where non-uniform allocation provides marginal or no benefit.\nYi-1.5 is a critical test: its concentration ($0.71$) exceeds Qwen's, but its heterogeneity is a single-outlier spike with no cross-bitwidth gradient---precisely the pattern where MCKP cannot redistribute budget.\nThe diagnostic reuses profiling data already required by the solver and adds no computational overhead.\n\nOur contributions are:\n\\begin{enumerate}[nosep]\n\\item We identify 2-bit distortion compounding as the cause of catastrophic failure in unconstrained per-head KV cache quantization on hardware-aligned bit-widths, and show that a cardinality constraint on 2-bit assignments is a minimal sufficient fix, reducing Qwen2.5-7B PPL from 32--37 (unconstrained) to 11.23 (constrained) at $4\\times$ compression (\\S\\ref{sec:compounding}, \\S\\ref{sec:experiments}).\n\n\\item We demonstrate that the cardinality constraint makes solver choice irrelevant: constrained greedy and constrained MCKP produce equivalent per-head allocations across three architectures, enabling use of a simple greedy algorithm (\\S\\ref{sec:solver_equiv}).\n\n\\item We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) to indicate whether non-uniform allocation will help a given architecture, distinguishing ``spread'' heterogeneity (MCKP-exploitable) from ``spike'' and ``flat'' patterns, validated on five models (\\S\\ref{sec:heterogeneity}).\n\\end{enumerate}\n",
    "structuredPatch": [
      {
        "oldStart": 50,
        "oldLines": 5,
        "newStart": 50,
        "newLines": 5,
        "lines": [
          " ",
          " \\item We demonstrate that the cardinality constraint makes solver choice irrelevant: constrained greedy and constrained MCKP produce equivalent per-head allocations across three architectures, enabling use of a simple greedy algorithm (\\S\\ref{sec:solver_equiv}).",
          " ",
          "-\\item We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) to indicate whether non-uniform allocation will help a given architecture, distinguishing ``spread'' heterogeneity (MCKP-exploitable) from ``spike'' and ``flat'' patterns, validated on five models (\\S\\ref{sec:heterogeneity}).",
          "+\\item We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) that correctly separates architectures where non-uniform allocation helps from those where it does not, across all five models tested. Yi-1.5-9B serves as a critical test: its concentration exceeds Qwen's, yet its single-outlier spike pattern makes MCKP counterproductive (\\S\\ref{sec:heterogeneity}).",
          " \\end{enumerate}"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Tool call

_source line 22_

<details open><summary>🔧 Tool call — Edit · `toolu_018cuhb7TMkLUZot3mhk8a4K`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/conclusion.tex",
  "old_string": "A joint diagnostic using concentration and $t_1/t_5$ ratio distinguishes spread, spike, and flat patterns across our five models, computable from the same profiling pass used for allocation, letting practitioners decide \\emph{before deployment} whether non-uniform quantization is worthwhile.",
  "new_string": "A joint diagnostic using concentration ($\\gtrsim 0.50$) and $t_1/t_5$ ratio ($\\lesssim 0.70$) correctly identifies spread, spike, and flat patterns across all five models studied, computable from the same profiling pass used for allocation.\nThis provides a practical guideline: practitioners can determine whether non-uniform quantization is worthwhile for their architecture \\emph{before} running the allocation solver."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "79f0aa0c-2b58-46f1-a7bf-4b829a80c5bc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015Vc172h4d7mfQD64rsHZhA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8917,
      "cache_read_input_tokens": 24892,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8917
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 23 · 2026-05-14T21:07:50.924Z_

<details><summary>↩ Tool result · `toolu_018cuhb7TMkLUZot3mhk8a4K`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/conclusion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "98c36115-ddfe-4c69-aadd-a0fbfc0200a3",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/conclusion.tex",
    "oldString": "A joint diagnostic using concentration and $t_1/t_5$ ratio distinguishes spread, spike, and flat patterns across our five models, computable from the same profiling pass used for allocation, letting practitioners decide \\emph{before deployment} whether non-uniform quantization is worthwhile.",
    "newString": "A joint diagnostic using concentration ($\\gtrsim 0.50$) and $t_1/t_5$ ratio ($\\lesssim 0.70$) correctly identifies spread, spike, and flat patterns across all five models studied, computable from the same profiling pass used for allocation.\nThis provides a practical guideline: practitioners can determine whether non-uniform quantization is worthwhile for their architecture \\emph{before} running the allocation solver.",
    "originalFile": "\\section{Conclusion}\\label{sec:conclusion}\n\nWe showed that per-head mixed-precision KV cache quantization over hardware-aligned bit-widths \\{2, 4, 8, 16\\} requires a cardinality constraint on 2-bit assignments to prevent non-additive distortion compounding through the residual stream.\nA single constraint---limiting simultaneously active 2-bit heads to $k \\leq 8$ (7\\% of heads)---reduces perplexity on Qwen2.5-7B from 15.45 (uniform 4-bit) to 11.23, a 27.3\\% improvement at $4\\times$ compression.\nUnder the constraint, solver choice becomes irrelevant: greedy and MCKP produce equivalent allocations across all three architectures ($\\Delta = 0.0000$), so a simple $O(H \\log H)$ greedy algorithm suffices.\nThe benefit of non-uniform allocation depends on both the concentration and \\emph{shape} of head sensitivity heterogeneity.\nQwen2.5-7B (concentration 0.61, $t_1/t_5{=}0.57$, spread pattern) shows large gains; Llama-3.1-8B ($t_1/t_5{=}0.71$, spike) shows marginal improvement (8.45 vs.\\ 8.47 PPL); Mistral-7B-v0.3, Yi-1.5-9B, and Gemma-2-9B are counterproductive.\nYi-1.5-9B is a critical test case: despite the highest concentration tested ($0.71$, exceeding Qwen), its heterogeneity is a single-outlier spike ($t_1/t_5{=}0.90$) with no cross-bitwidth sensitivity gradient, so MCKP cannot redistribute budget.\nA joint diagnostic using concentration and $t_1/t_5$ ratio distinguishes spread, spike, and flat patterns across our five models, computable from the same profiling pass used for allocation, letting practitioners decide \\emph{before deployment} whether non-uniform quantization is worthwhile.\n\n\\paragraph{Limitations.}\nOur study has several limitations that temper the generality of the findings.\nFirst, we evaluate only five 7--9B-scale models---too few to establish a statistically robust correlation between heterogeneity and quantization benefit; the observed trend is directional evidence, not a predictive law.\nSecond, profiling relies on a single sensitivity metric (perplexity-based per-head distortion); alternative measures such as gradient-based or activation-norm diagnostics remain unexplored and could yield different allocation decisions.\nThird, we report perplexity and downstream accuracy but no real-kernel latency benchmarks, leaving the practical inference speedup from mixed-precision allocation unquantified.\nFourth, we have not verified whether these findings transfer to larger scales (70B+), where head counts and attention patterns differ substantially.\nFinally, although we validate on four downstream tasks, profiling and primary evaluation use a single dataset (WikiText-2).\n\n\\paragraph{Future Work.}\nExtending evaluation to 70B+ models would test whether the heterogeneity--benefit relationship holds at scale.\nIntegration with production inference engines (vLLM, TensorRT-LLM) would enable real-kernel latency measurement, and investigating per-side K/V cardinality constraints (Appendix~\\ref{sec:kv_separation}) or dynamic per-request allocation could further improve the framework.\n",
    "structuredPatch": [
      {
        "oldStart": 6,
        "oldLines": 7,
        "newStart": 6,
        "newLines": 8,
        "lines": [
          " The benefit of non-uniform allocation depends on both the concentration and \\emph{shape} of head sensitivity heterogeneity.",
          " Qwen2.5-7B (concentration 0.61, $t_1/t_5{=}0.57$, spread pattern) shows large gains; Llama-3.1-8B ($t_1/t_5{=}0.71$, spike) shows marginal improvement (8.45 vs.\\ 8.47 PPL); Mistral-7B-v0.3, Yi-1.5-9B, and Gemma-2-9B are counterproductive.",
          " Yi-1.5-9B is a critical test case: despite the highest concentration tested ($0.71$, exceeding Qwen), its heterogeneity is a single-outlier spike ($t_1/t_5{=}0.90$) with no cross-bitwidth sensitivity gradient, so MCKP cannot redistribute budget.",
          "-A joint diagnostic using concentration and $t_1/t_5$ ratio distinguishes spread, spike, and flat patterns across our five models, computable from the same profiling pass used for allocation, letting practitioners decide \\emph{before deployment} whether non-uniform quantization is worthwhile.",
          "+A joint diagnostic using concentration ($\\gtrsim 0.50$) and $t_1/t_5$ ratio ($\\lesssim 0.70$) correctly identifies spread, spike, and flat patterns across all five models studied, computable from the same profiling pass used for allocation.",
          "+This provides a practical guideline: practitioners can determine whether non-uniform quantization is worthwhile for their architecture \\emph{before} running the allocation solver.",
          " ",
          " \\paragraph{Limitations.}",
          " Our study has several limitations that temper the generality of the findings."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 24_

<details><summary>Logged reasoning block</summary>

```text
Good, all three independent file edits succeeded. Now let me do the 4 analysis.tex edits sequentially.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "c4fd949a-59fd-4307-8642-0df9d015e4d3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CB1XPD5MGQwr5eKtgoWtKJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23925,
      "cache_read_input_tokens": 33809,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 23925
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 25_

abstract/introduction/conclusion 修改完成。开始修改 analysis.tex — Edit 1: 在 §5.1 开头插入机制洞察。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "ad870030-deec-4a3a-8c9f-8cd61e1508d5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CB1XPD5MGQwr5eKtgoWtKJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23925,
      "cache_read_input_tokens": 33809,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 23925
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 26_

<details open><summary>🔧 Tool call — Edit · `toolu_011ZwSZbsxixXAVcAP7dskJ6`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex",
  "old_string": "Table~\\ref{tab:heterogeneity} summarizes the results across five architectures at $4\\times$ compression.\nQwen2.5-7B exhibits the highest \\emph{spread} heterogeneity (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.",
  "new_string": "Table~\\ref{tab:heterogeneity} summarizes the results across five architectures at $4\\times$ compression.\nThe central finding is that MCKP benefit requires \\emph{spread heterogeneity}---multiple heads with cross-bitwidth sensitivity gradients---rather than sensitivity concentrated in a single outlier at one bitwidth.\n\nQwen2.5-7B exemplifies the spread pattern (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "8ee15672-b56f-4dd6-8203-060b40b1593d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CB1XPD5MGQwr5eKtgoWtKJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23925,
      "cache_read_input_tokens": 33809,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 23925
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 27 · 2026-05-14T21:08:03.504Z_

<details><summary>↩ Tool result · `toolu_011ZwSZbsxixXAVcAP7dskJ6`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "a73f4a9c-bd3c-4275-a916-d37acc918e34",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex",
    "oldString": "Table~\\ref{tab:heterogeneity} summarizes the results across five architectures at $4\\times$ compression.\nQwen2.5-7B exhibits the highest \\emph{spread} heterogeneity (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.",
    "newString": "Table~\\ref{tab:heterogeneity} summarizes the results across five architectures at $4\\times$ compression.\nThe central finding is that MCKP benefit requires \\emph{spread heterogeneity}---multiple heads with cross-bitwidth sensitivity gradients---rather than sensitivity concentrated in a single outlier at one bitwidth.\n\nQwen2.5-7B exemplifies the spread pattern (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.",
    "originalFile": "\\section{Analysis}\n\\label{sec:analysis}\n\n\\subsection{Heterogeneity Characterization}\n\\label{sec:heterogeneity}\n\nThe benefit of non-uniform allocation depends on how unevenly head sensitivities are distributed.\nWe quantify this with a \\emph{top-5\\% concentration metric}: sort per-head 2-bit distortions $d_h(2)$ in descending order and compute the fraction of total distortion contributed by the top 5\\% of heads.\nHigh concentration indicates that a few heads are disproportionately sensitive; low concentration indicates near-uniform sensitivity.\n\nTable~\\ref{tab:heterogeneity} summarizes the results across five architectures at $4\\times$ compression.\nQwen2.5-7B exhibits the highest \\emph{spread} heterogeneity (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.\nConstrained MCKP reduces degradation from $+$5.64 PPL (uniform) to $+$1.42 PPL, a 27.3\\% improvement over uniform 4-bit. %exp_id=qwen_constrained_mckp\n\nHowever, concentration alone does not predict MCKP benefit.\nYi-1.5-9B has a hires concentration of $0.71$---\\emph{higher} than Qwen's $0.61$---yet constrained MCKP is counterproductive ($+$0.30 vs.\\ $+$0.20 uniform). %exp_id=yi15_hires_constrained\nThe explanation lies in the \\emph{shape} of the heterogeneity.\nYi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling\nCritically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\\approx}\\,0$.\nThe solver therefore has no cross-bitwidth gradient to exploit---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.\nWe call this a ``spike'' pattern: high concentration, but a single outlier with sensitivity at only one bitwidth.\n\nIn contrast, Qwen's Layer-0 heads exhibit non-zero deltas at multiple bitwidths (e.g., L0H0: 2-bit delta ${=}6.74$, with positive 4-bit and 8-bit deltas), giving the solver a multi-bitwidth sensitivity gradient across several heads---a ``spread'' pattern that enables meaningful budget reallocation. %exp_id=qwen_hires_profiling\n\nThe remaining three architectures fill out the diagnostic picture.\nLlama-3.1-8B shows moderate concentration ($0.34$) with a spike-like shape ($t_1/t_5{=}0.71$, $t_1/t_2{=}21.7$); its allocation benefit is marginal ($+$0.36 vs.\\ $+$0.38 uniform). %exp_id=llama_hires_constrained\nMistral-7B-v0.3 and Gemma-2-9B both exhibit flat distributions ($t_1/t_5{=}0.18$) with low concentration ($0.22$ and $0.23$ respectively), leaving the profiler with no reliable signal; constrained MCKP is slightly worse than uniform in both cases ($+$0.13 vs.\\ $+$0.10 for Mistral; $+$0.15 vs.\\ $+$0.13 for Gemma-2). %exp_id=mistral_c4_cross_dataset %exp_id=gemma2_full_pipeline\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Head sensitivity heterogeneity and constrained allocation benefit across architectures at $4\\times$ compression. $t_1/t_5$: ratio of top-1 to top-5 per-head 2-bit distortion (low${=}$spread, high${=}$spike). $^\\dagger$Hires profiling (64 seq $\\times$ 2048 tok); $^\\ddagger$standard profiling, hires pending.}\n\\label{tab:heterogeneity}\n\\begin{tabular}{lcccccc}\n\\toprule\nModel & GQA & Top-5\\% & $t_1/t_5$ & $\\Delta$ PPL & $\\Delta$ PPL & Shape \\\\\n & Ratio & Conc. & & (Uniform) & (Ours) & \\\\\n\\midrule\nQwen2.5-7B & 7:1 & 0.61 & 0.57 & $+$5.64 & $+$1.42 & Spread \\\\\nYi-1.5-9B$^\\dagger$ & 8:1 & 0.71 & 0.90 & $+$0.20 & $+$0.30 & Spike \\\\\nLlama-3.1-8B$^\\ddagger$ & 4:1 & 0.34 & 0.71 & $+$0.38 & $+$0.36 & Spike \\\\\nMistral-7B-v0.3$^\\ddagger$ & 4:1 & 0.22 & 0.18 & $+$0.10 & $+$0.13 & Flat \\\\\nGemma-2-9B$^\\ddagger$ & 2:1 & 0.23 & 0.18 & $+$0.13 & $+$0.15 & Flat \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/fig1_head_delta_heatmap.pdf}\n\\caption{Per-head 2-bit quantization sensitivity across five architectures. Qwen2.5-7B shows high concentration in Layer-0 heads (``spread'' pattern); Yi-1.5-9B shows a single extreme outlier at Layer-4 Head-3 (``spike'' pattern); Llama-3.1-8B shows moderate spread; Mistral-7B-v0.3 shows near-zero sensitivity across all heads; Gemma-2-9B exhibits the most uniform distribution, consistent with its low GQA ratio (2:1). Color intensity indicates PPL increase when the head is quantized to 2-bit.}\n\\label{fig:heatmap}\n\\end{figure*}\n\nFigure~\\ref{fig:heatmap} visualizes the per-head 2-bit distortion as a heatmap.\nThe contrast is stark: Qwen's Layer-0 heads show high distortion (dark cells) while mid-to-deep layers are near-zero; Yi-1.5 shows a single bright spot at Layer-4 Head-3 (34\\% of total delta) with the remaining 191 heads near-uniform---a ``spike'' that MCKP cannot exploit; Gemma-2 exhibits the most uniform heatmap across its 336 heads, consistent with its 0.23 concentration; Mistral shows similarly low distortion across all layers and heads.\n\n\\subsection{Diagnostic Framework}\n\\label{sec:diagnostic}\n\nThe heterogeneity characterization shows that MCKP benefit requires not just high concentration but a specific \\emph{shape}---spread heterogeneity across multiple heads with cross-bitwidth sensitivity gradients.\nThis motivates a joint diagnostic, based on five architectures, for deciding when non-uniform allocation is worthwhile:\n\n\\begin{enumerate}[nosep]\n\\item Run per-head profiling as described in \\S\\ref{sec:profiling}.\n\\item Compute the top-5\\% concentration and the $t_1/t_5$ ratio (top-1 distortion divided by top-5 distortion) from the resulting distortion table.\n\\item Select allocation strategy based on concentration \\emph{and} shape:\n  \\begin{itemize}[nosep]\n  \\item \\textbf{Spread} (moderate-to-high concentration, $t_1/t_5 \\lesssim 0.70$): non-uniform allocation recommended. Multiple heads have sensitivity gradients across bitwidths, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\\% PPL improvement.\n  \\item \\textbf{Spike} (any concentration, $t_1/t_5 \\gtrsim 0.70$): use uniform. Sensitivity is confined to a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.\n  \\item \\textbf{Flat} (low concentration, any shape): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral ($t_1/t_5{=}0.18$) and Gemma-2 ($t_1/t_5{=}0.18$): counterproductive.\n  \\end{itemize}\n\\end{enumerate}\n\nThe $t_1/t_5 \\approx 0.70$ boundary is an illustrative threshold derived from five architectures; it should be validated on a broader set before being treated as a general rule.\nThe diagnostic adds no computational overhead: it reuses the profiling data already required for the allocation solver and avoids wasted optimization effort on architectures where non-uniform allocation provides no benefit.\nAdditional analyses---the effect of aggressive compression ratios, profiling resolution and multi-seed stability, per-layer optimality validation, and KV separation ablation---are provided in Appendices~\\ref{sec:aggressive}--\\ref{sec:kv_separation}.\n",
    "structuredPatch": [
      {
        "oldStart": 9,
        "oldLines": 7,
        "newStart": 9,
        "newLines": 9,
        "lines": [
          " High concentration indicates that a few heads are disproportionately sensitive; low concentration indicates near-uniform sensitivity.",
          " ",
          " Table~\\ref{tab:heterogeneity} summarizes the results across five architectures at $4\\times$ compression.",
          "-Qwen2.5-7B exhibits the highest \\emph{spread} heterogeneity (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.",
          "+The central finding is that MCKP benefit requires \\emph{spread heterogeneity}---multiple heads with cross-bitwidth sensitivity gradients---rather than sensitivity concentrated in a single outlier at one bitwidth.",
          "+",
          "+Qwen2.5-7B exemplifies the spread pattern (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.",
          " Constrained MCKP reduces degradation from $+$5.64 PPL (uniform) to $+$1.42 PPL, a 27.3\\% improvement over uniform 4-bit. %exp_id=qwen_constrained_mckp",
          " ",
          " However, concentration alone does not predict MCKP benefit."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 28_

Edit 2: Yi-1.5 段落重构——mechanism first。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "36cb5770-41a8-44da-a483-47991c0a5bde",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NYWTDpo9ou1oK8SU4jJhmc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 517,
      "cache_read_input_tokens": 57734,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 517
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 29_

<details open><summary>🔧 Tool call — Edit · `toolu_01Kfb5JiWXUpMohdUGuow239`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex",
  "old_string": "However, concentration alone does not predict MCKP benefit.\nYi-1.5-9B has a hires concentration of $0.71$---\\emph{higher} than Qwen's $0.61$---yet constrained MCKP is counterproductive ($+$0.30 vs.\\ $+$0.20 uniform). %exp_id=yi15_hires_constrained\nThe explanation lies in the \\emph{shape} of the heterogeneity.\nYi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling\nCritically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\\approx}\\,0$.\nThe solver therefore has no cross-bitwidth gradient to exploit---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.\nWe call this a ``spike'' pattern: high concentration, but a single outlier with sensitivity at only one bitwidth.",
  "new_string": "Yi-1.5-9B is a critical counterexample: despite the highest concentration tested ($0.71$, exceeding Qwen's $0.61$), constrained MCKP is counterproductive ($+$0.30 vs.\\ $+$0.20 uniform). %exp_id=yi15_hires_constrained\nThe mechanism is clear from the cross-bitwidth gradient structure.\nYi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling\nCritically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\\approx}\\,0$.\nThe solver therefore has only one lever---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.\nThis is the ``spike'' pattern: high concentration driven by a single outlier with sensitivity at only one bitwidth."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "a7f8673a-9e62-4b06-aed5-cb5eb70adf4a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NYWTDpo9ou1oK8SU4jJhmc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 517,
      "cache_read_input_tokens": 57734,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 517
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-14T21:08:19.953Z_

<details><summary>↩ Tool result · `toolu_01Kfb5JiWXUpMohdUGuow239`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "44a9bde3-db0c-47fe-a7a6-d82f60509c8e",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex",
    "oldString": "However, concentration alone does not predict MCKP benefit.\nYi-1.5-9B has a hires concentration of $0.71$---\\emph{higher} than Qwen's $0.61$---yet constrained MCKP is counterproductive ($+$0.30 vs.\\ $+$0.20 uniform). %exp_id=yi15_hires_constrained\nThe explanation lies in the \\emph{shape} of the heterogeneity.\nYi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling\nCritically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\\approx}\\,0$.\nThe solver therefore has no cross-bitwidth gradient to exploit---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.\nWe call this a ``spike'' pattern: high concentration, but a single outlier with sensitivity at only one bitwidth.",
    "newString": "Yi-1.5-9B is a critical counterexample: despite the highest concentration tested ($0.71$, exceeding Qwen's $0.61$), constrained MCKP is counterproductive ($+$0.30 vs.\\ $+$0.20 uniform). %exp_id=yi15_hires_constrained\nThe mechanism is clear from the cross-bitwidth gradient structure.\nYi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling\nCritically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\\approx}\\,0$.\nThe solver therefore has only one lever---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.\nThis is the ``spike'' pattern: high concentration driven by a single outlier with sensitivity at only one bitwidth.",
    "originalFile": "\\section{Analysis}\n\\label{sec:analysis}\n\n\\subsection{Heterogeneity Characterization}\n\\label{sec:heterogeneity}\n\nThe benefit of non-uniform allocation depends on how unevenly head sensitivities are distributed.\nWe quantify this with a \\emph{top-5\\% concentration metric}: sort per-head 2-bit distortions $d_h(2)$ in descending order and compute the fraction of total distortion contributed by the top 5\\% of heads.\nHigh concentration indicates that a few heads are disproportionately sensitive; low concentration indicates near-uniform sensitivity.\n\nTable~\\ref{tab:heterogeneity} summarizes the results across five architectures at $4\\times$ compression.\nThe central finding is that MCKP benefit requires \\emph{spread heterogeneity}---multiple heads with cross-bitwidth sensitivity gradients---rather than sensitivity concentrated in a single outlier at one bitwidth.\n\nQwen2.5-7B exemplifies the spread pattern (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.\nConstrained MCKP reduces degradation from $+$5.64 PPL (uniform) to $+$1.42 PPL, a 27.3\\% improvement over uniform 4-bit. %exp_id=qwen_constrained_mckp\n\nHowever, concentration alone does not predict MCKP benefit.\nYi-1.5-9B has a hires concentration of $0.71$---\\emph{higher} than Qwen's $0.61$---yet constrained MCKP is counterproductive ($+$0.30 vs.\\ $+$0.20 uniform). %exp_id=yi15_hires_constrained\nThe explanation lies in the \\emph{shape} of the heterogeneity.\nYi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling\nCritically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\\approx}\\,0$.\nThe solver therefore has no cross-bitwidth gradient to exploit---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.\nWe call this a ``spike'' pattern: high concentration, but a single outlier with sensitivity at only one bitwidth.\n\nIn contrast, Qwen's Layer-0 heads exhibit non-zero deltas at multiple bitwidths (e.g., L0H0: 2-bit delta ${=}6.74$, with positive 4-bit and 8-bit deltas), giving the solver a multi-bitwidth sensitivity gradient across several heads---a ``spread'' pattern that enables meaningful budget reallocation. %exp_id=qwen_hires_profiling\n\nThe remaining three architectures fill out the diagnostic picture.\nLlama-3.1-8B shows moderate concentration ($0.34$) with a spike-like shape ($t_1/t_5{=}0.71$, $t_1/t_2{=}21.7$); its allocation benefit is marginal ($+$0.36 vs.\\ $+$0.38 uniform). %exp_id=llama_hires_constrained\nMistral-7B-v0.3 and Gemma-2-9B both exhibit flat distributions ($t_1/t_5{=}0.18$) with low concentration ($0.22$ and $0.23$ respectively), leaving the profiler with no reliable signal; constrained MCKP is slightly worse than uniform in both cases ($+$0.13 vs.\\ $+$0.10 for Mistral; $+$0.15 vs.\\ $+$0.13 for Gemma-2). %exp_id=mistral_c4_cross_dataset %exp_id=gemma2_full_pipeline\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Head sensitivity heterogeneity and constrained allocation benefit across architectures at $4\\times$ compression. $t_1/t_5$: ratio of top-1 to top-5 per-head 2-bit distortion (low${=}$spread, high${=}$spike). $^\\dagger$Hires profiling (64 seq $\\times$ 2048 tok); $^\\ddagger$standard profiling, hires pending.}\n\\label{tab:heterogeneity}\n\\begin{tabular}{lcccccc}\n\\toprule\nModel & GQA & Top-5\\% & $t_1/t_5$ & $\\Delta$ PPL & $\\Delta$ PPL & Shape \\\\\n & Ratio & Conc. & & (Uniform) & (Ours) & \\\\\n\\midrule\nQwen2.5-7B & 7:1 & 0.61 & 0.57 & $+$5.64 & $+$1.42 & Spread \\\\\nYi-1.5-9B$^\\dagger$ & 8:1 & 0.71 & 0.90 & $+$0.20 & $+$0.30 & Spike \\\\\nLlama-3.1-8B$^\\ddagger$ & 4:1 & 0.34 & 0.71 & $+$0.38 & $+$0.36 & Spike \\\\\nMistral-7B-v0.3$^\\ddagger$ & 4:1 & 0.22 & 0.18 & $+$0.10 & $+$0.13 & Flat \\\\\nGemma-2-9B$^\\ddagger$ & 2:1 & 0.23 & 0.18 & $+$0.13 & $+$0.15 & Flat \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/fig1_head_delta_heatmap.pdf}\n\\caption{Per-head 2-bit quantization sensitivity across five architectures. Qwen2.5-7B shows high concentration in Layer-0 heads (``spread'' pattern); Yi-1.5-9B shows a single extreme outlier at Layer-4 Head-3 (``spike'' pattern); Llama-3.1-8B shows moderate spread; Mistral-7B-v0.3 shows near-zero sensitivity across all heads; Gemma-2-9B exhibits the most uniform distribution, consistent with its low GQA ratio (2:1). Color intensity indicates PPL increase when the head is quantized to 2-bit.}\n\\label{fig:heatmap}\n\\end{figure*}\n\nFigure~\\ref{fig:heatmap} visualizes the per-head 2-bit distortion as a heatmap.\nThe contrast is stark: Qwen's Layer-0 heads show high distortion (dark cells) while mid-to-deep layers are near-zero; Yi-1.5 shows a single bright spot at Layer-4 Head-3 (34\\% of total delta) with the remaining 191 heads near-uniform---a ``spike'' that MCKP cannot exploit; Gemma-2 exhibits the most uniform heatmap across its 336 heads, consistent with its 0.23 concentration; Mistral shows similarly low distortion across all layers and heads.\n\n\\subsection{Diagnostic Framework}\n\\label{sec:diagnostic}\n\nThe heterogeneity characterization shows that MCKP benefit requires not just high concentration but a specific \\emph{shape}---spread heterogeneity across multiple heads with cross-bitwidth sensitivity gradients.\nThis motivates a joint diagnostic, based on five architectures, for deciding when non-uniform allocation is worthwhile:\n\n\\begin{enumerate}[nosep]\n\\item Run per-head profiling as described in \\S\\ref{sec:profiling}.\n\\item Compute the top-5\\% concentration and the $t_1/t_5$ ratio (top-1 distortion divided by top-5 distortion) from the resulting distortion table.\n\\item Select allocation strategy based on concentration \\emph{and} shape:\n  \\begin{itemize}[nosep]\n  \\item \\textbf{Spread} (moderate-to-high concentration, $t_1/t_5 \\lesssim 0.70$): non-uniform allocation recommended. Multiple heads have sensitivity gradients across bitwidths, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\\% PPL improvement.\n  \\item \\textbf{Spike} (any concentration, $t_1/t_5 \\gtrsim 0.70$): use uniform. Sensitivity is confined to a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.\n  \\item \\textbf{Flat} (low concentration, any shape): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral ($t_1/t_5{=}0.18$) and Gemma-2 ($t_1/t_5{=}0.18$): counterproductive.\n  \\end{itemize}\n\\end{enumerate}\n\nThe $t_1/t_5 \\approx 0.70$ boundary is an illustrative threshold derived from five architectures; it should be validated on a broader set before being treated as a general rule.\nThe diagnostic adds no computational overhead: it reuses the profiling data already required for the allocation solver and avoids wasted optimization effort on architectures where non-uniform allocation provides no benefit.\nAdditional analyses---the effect of aggressive compression ratios, profiling resolution and multi-seed stability, per-layer optimality validation, and KV separation ablation---are provided in Appendices~\\ref{sec:aggressive}--\\ref{sec:kv_separation}.\n",
    "structuredPatch": [
      {
        "oldStart": 14,
        "oldLines": 13,
        "newStart": 14,
        "newLines": 12,
        "lines": [
          " Qwen2.5-7B exemplifies the spread pattern (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.",
          " Constrained MCKP reduces degradation from $+$5.64 PPL (uniform) to $+$1.42 PPL, a 27.3\\% improvement over uniform 4-bit. %exp_id=qwen_constrained_mckp",
          " ",
          "-However, concentration alone does not predict MCKP benefit.",
          "-Yi-1.5-9B has a hires concentration of $0.71$---\\emph{higher} than Qwen's $0.61$---yet constrained MCKP is counterproductive ($+$0.30 vs.\\ $+$0.20 uniform). %exp_id=yi15_hires_constrained",
          "-The explanation lies in the \\emph{shape} of the heterogeneity.",
          "+Yi-1.5-9B is a critical counterexample: despite the highest concentration tested ($0.71$, exceeding Qwen's $0.61$), constrained MCKP is counterproductive ($+$0.30 vs.\\ $+$0.20 uniform). %exp_id=yi15_hires_constrained",
          "+The mechanism is clear from the cross-bitwidth gradient structure.",
          " Yi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling",
          " Critically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\\approx}\\,0$.",
          "-The solver therefore has no cross-bitwidth gradient to exploit---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.",
          "-We call this a ``spike'' pattern: high concentration, but a single outlier with sensitivity at only one bitwidth.",
          "+The solver therefore has only one lever---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.",
          "+This is the ``spike'' pattern: high concentration driven by a single outlier with sensitivity at only one bitwidth.",
          " ",
          " In contrast, Qwen's Layer-0 heads exhibit non-zero deltas at multiple bitwidths (e.g., L0H0: 2-bit delta ${=}6.74$, with positive 4-bit and 8-bit deltas), giving the solver a multi-bitwidth sensitivity gradient across several heads---a ``spread'' pattern that enables meaningful budget reallocation. %exp_id=qwen_hires_profiling",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 31_

Edit 3: 诊断框架条目——显式阈值。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "5fd73e9d-6d20-4fd1-adf3-6805e1dd1ecc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01S7gtKHJ5PjWAWRSyrrWeem",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 883,
      "cache_read_input_tokens": 58251,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 883
      },
      "output_tokens": 5,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 32_

<details open><summary>🔧 Tool call — Edit · `toolu_01QCWdia22myidNmRDVVV4G6`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex",
  "old_string": "  \\item \\textbf{Spread} (moderate-to-high concentration, $t_1/t_5 \\lesssim 0.70$): non-uniform allocation recommended. Multiple heads have sensitivity gradients across bitwidths, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\\% PPL improvement.\n  \\item \\textbf{Spike} (any concentration, $t_1/t_5 \\gtrsim 0.70$): use uniform. Sensitivity is confined to a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.\n  \\item \\textbf{Flat} (low concentration, any shape): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral ($t_1/t_5{=}0.18$) and Gemma-2 ($t_1/t_5{=}0.18$): counterproductive.",
  "new_string": "  \\item \\textbf{Spread} (concentration $\\gtrsim 0.50$, $t_1/t_5 \\lesssim 0.70$): non-uniform allocation recommended. Multiple heads exhibit cross-bitwidth sensitivity gradients, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\\% PPL improvement.\n  \\item \\textbf{Spike} ($t_1/t_5 \\gtrsim 0.70$, any concentration): use uniform. Sensitivity is dominated by a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.\n  \\item \\textbf{Flat} (concentration $\\lesssim 0.50$, low $t_1/t_5$): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral (0.22, $t_1/t_5{=}0.18$) and Gemma-2 (0.23, $t_1/t_5{=}0.18$): counterproductive."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "cb4a5f18-0632-4544-8719-4ffda9f36302",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01S7gtKHJ5PjWAWRSyrrWeem",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 883,
      "cache_read_input_tokens": 58251,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 883
      },
      "output_tokens": 5,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 33 · 2026-05-14T21:08:31.921Z_

<details><summary>↩ Tool result · `toolu_01QCWdia22myidNmRDVVV4G6`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "bff6602b-d735-4a89-81b2-45f4c25c54b7",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex",
    "oldString": "  \\item \\textbf{Spread} (moderate-to-high concentration, $t_1/t_5 \\lesssim 0.70$): non-uniform allocation recommended. Multiple heads have sensitivity gradients across bitwidths, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\\% PPL improvement.\n  \\item \\textbf{Spike} (any concentration, $t_1/t_5 \\gtrsim 0.70$): use uniform. Sensitivity is confined to a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.\n  \\item \\textbf{Flat} (low concentration, any shape): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral ($t_1/t_5{=}0.18$) and Gemma-2 ($t_1/t_5{=}0.18$): counterproductive.",
    "newString": "  \\item \\textbf{Spread} (concentration $\\gtrsim 0.50$, $t_1/t_5 \\lesssim 0.70$): non-uniform allocation recommended. Multiple heads exhibit cross-bitwidth sensitivity gradients, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\\% PPL improvement.\n  \\item \\textbf{Spike} ($t_1/t_5 \\gtrsim 0.70$, any concentration): use uniform. Sensitivity is dominated by a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.\n  \\item \\textbf{Flat} (concentration $\\lesssim 0.50$, low $t_1/t_5$): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral (0.22, $t_1/t_5{=}0.18$) and Gemma-2 (0.23, $t_1/t_5{=}0.18$): counterproductive.",
    "originalFile": "\\section{Analysis}\n\\label{sec:analysis}\n\n\\subsection{Heterogeneity Characterization}\n\\label{sec:heterogeneity}\n\nThe benefit of non-uniform allocation depends on how unevenly head sensitivities are distributed.\nWe quantify this with a \\emph{top-5\\% concentration metric}: sort per-head 2-bit distortions $d_h(2)$ in descending order and compute the fraction of total distortion contributed by the top 5\\% of heads.\nHigh concentration indicates that a few heads are disproportionately sensitive; low concentration indicates near-uniform sensitivity.\n\nTable~\\ref{tab:heterogeneity} summarizes the results across five architectures at $4\\times$ compression.\nThe central finding is that MCKP benefit requires \\emph{spread heterogeneity}---multiple heads with cross-bitwidth sensitivity gradients---rather than sensitivity concentrated in a single outlier at one bitwidth.\n\nQwen2.5-7B exemplifies the spread pattern (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.\nConstrained MCKP reduces degradation from $+$5.64 PPL (uniform) to $+$1.42 PPL, a 27.3\\% improvement over uniform 4-bit. %exp_id=qwen_constrained_mckp\n\nYi-1.5-9B is a critical counterexample: despite the highest concentration tested ($0.71$, exceeding Qwen's $0.61$), constrained MCKP is counterproductive ($+$0.30 vs.\\ $+$0.20 uniform). %exp_id=yi15_hires_constrained\nThe mechanism is clear from the cross-bitwidth gradient structure.\nYi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling\nCritically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\\approx}\\,0$.\nThe solver therefore has only one lever---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.\nThis is the ``spike'' pattern: high concentration driven by a single outlier with sensitivity at only one bitwidth.\n\nIn contrast, Qwen's Layer-0 heads exhibit non-zero deltas at multiple bitwidths (e.g., L0H0: 2-bit delta ${=}6.74$, with positive 4-bit and 8-bit deltas), giving the solver a multi-bitwidth sensitivity gradient across several heads---a ``spread'' pattern that enables meaningful budget reallocation. %exp_id=qwen_hires_profiling\n\nThe remaining three architectures fill out the diagnostic picture.\nLlama-3.1-8B shows moderate concentration ($0.34$) with a spike-like shape ($t_1/t_5{=}0.71$, $t_1/t_2{=}21.7$); its allocation benefit is marginal ($+$0.36 vs.\\ $+$0.38 uniform). %exp_id=llama_hires_constrained\nMistral-7B-v0.3 and Gemma-2-9B both exhibit flat distributions ($t_1/t_5{=}0.18$) with low concentration ($0.22$ and $0.23$ respectively), leaving the profiler with no reliable signal; constrained MCKP is slightly worse than uniform in both cases ($+$0.13 vs.\\ $+$0.10 for Mistral; $+$0.15 vs.\\ $+$0.13 for Gemma-2). %exp_id=mistral_c4_cross_dataset %exp_id=gemma2_full_pipeline\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Head sensitivity heterogeneity and constrained allocation benefit across architectures at $4\\times$ compression. $t_1/t_5$: ratio of top-1 to top-5 per-head 2-bit distortion (low${=}$spread, high${=}$spike). $^\\dagger$Hires profiling (64 seq $\\times$ 2048 tok); $^\\ddagger$standard profiling, hires pending.}\n\\label{tab:heterogeneity}\n\\begin{tabular}{lcccccc}\n\\toprule\nModel & GQA & Top-5\\% & $t_1/t_5$ & $\\Delta$ PPL & $\\Delta$ PPL & Shape \\\\\n & Ratio & Conc. & & (Uniform) & (Ours) & \\\\\n\\midrule\nQwen2.5-7B & 7:1 & 0.61 & 0.57 & $+$5.64 & $+$1.42 & Spread \\\\\nYi-1.5-9B$^\\dagger$ & 8:1 & 0.71 & 0.90 & $+$0.20 & $+$0.30 & Spike \\\\\nLlama-3.1-8B$^\\ddagger$ & 4:1 & 0.34 & 0.71 & $+$0.38 & $+$0.36 & Spike \\\\\nMistral-7B-v0.3$^\\ddagger$ & 4:1 & 0.22 & 0.18 & $+$0.10 & $+$0.13 & Flat \\\\\nGemma-2-9B$^\\ddagger$ & 2:1 & 0.23 & 0.18 & $+$0.13 & $+$0.15 & Flat \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/fig1_head_delta_heatmap.pdf}\n\\caption{Per-head 2-bit quantization sensitivity across five architectures. Qwen2.5-7B shows high concentration in Layer-0 heads (``spread'' pattern); Yi-1.5-9B shows a single extreme outlier at Layer-4 Head-3 (``spike'' pattern); Llama-3.1-8B shows moderate spread; Mistral-7B-v0.3 shows near-zero sensitivity across all heads; Gemma-2-9B exhibits the most uniform distribution, consistent with its low GQA ratio (2:1). Color intensity indicates PPL increase when the head is quantized to 2-bit.}\n\\label{fig:heatmap}\n\\end{figure*}\n\nFigure~\\ref{fig:heatmap} visualizes the per-head 2-bit distortion as a heatmap.\nThe contrast is stark: Qwen's Layer-0 heads show high distortion (dark cells) while mid-to-deep layers are near-zero; Yi-1.5 shows a single bright spot at Layer-4 Head-3 (34\\% of total delta) with the remaining 191 heads near-uniform---a ``spike'' that MCKP cannot exploit; Gemma-2 exhibits the most uniform heatmap across its 336 heads, consistent with its 0.23 concentration; Mistral shows similarly low distortion across all layers and heads.\n\n\\subsection{Diagnostic Framework}\n\\label{sec:diagnostic}\n\nThe heterogeneity characterization shows that MCKP benefit requires not just high concentration but a specific \\emph{shape}---spread heterogeneity across multiple heads with cross-bitwidth sensitivity gradients.\nThis motivates a joint diagnostic, based on five architectures, for deciding when non-uniform allocation is worthwhile:\n\n\\begin{enumerate}[nosep]\n\\item Run per-head profiling as described in \\S\\ref{sec:profiling}.\n\\item Compute the top-5\\% concentration and the $t_1/t_5$ ratio (top-1 distortion divided by top-5 distortion) from the resulting distortion table.\n\\item Select allocation strategy based on concentration \\emph{and} shape:\n  \\begin{itemize}[nosep]\n  \\item \\textbf{Spread} (moderate-to-high concentration, $t_1/t_5 \\lesssim 0.70$): non-uniform allocation recommended. Multiple heads have sensitivity gradients across bitwidths, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\\% PPL improvement.\n  \\item \\textbf{Spike} (any concentration, $t_1/t_5 \\gtrsim 0.70$): use uniform. Sensitivity is confined to a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.\n  \\item \\textbf{Flat} (low concentration, any shape): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral ($t_1/t_5{=}0.18$) and Gemma-2 ($t_1/t_5{=}0.18$): counterproductive.\n  \\end{itemize}\n\\end{enumerate}\n\nThe $t_1/t_5 \\approx 0.70$ boundary is an illustrative threshold derived from five architectures; it should be validated on a broader set before being treated as a general rule.\nThe diagnostic adds no computational overhead: it reuses the profiling data already required for the allocation solver and avoids wasted optimization effort on architectures where non-uniform allocation provides no benefit.\nAdditional analyses---the effect of aggressive compression ratios, profiling resolution and multi-seed stability, per-layer optimality validation, and KV separation ablation---are provided in Appendices~\\ref{sec:aggressive}--\\ref{sec:kv_separation}.\n",
    "structuredPatch": [
      {
        "oldStart": 67,
        "oldLines": 9,
        "newStart": 67,
        "newLines": 9,
        "lines": [
          " \\item Compute the top-5\\% concentration and the $t_1/t_5$ ratio (top-1 distortion divided by top-5 distortion) from the resulting distortion table.",
          " \\item Select allocation strategy based on concentration \\emph{and} shape:",
          "   \\begin{itemize}[nosep]",
          "-  \\item \\textbf{Spread} (moderate-to-high concentration, $t_1/t_5 \\lesssim 0.70$): non-uniform allocation recommended. Multiple heads have sensitivity gradients across bitwidths, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\\% PPL improvement.",
          "-  \\item \\textbf{Spike} (any concentration, $t_1/t_5 \\gtrsim 0.70$): use uniform. Sensitivity is confined to a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.",
          "-  \\item \\textbf{Flat} (low concentration, any shape): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral ($t_1/t_5{=}0.18$) and Gemma-2 ($t_1/t_5{=}0.18$): counterproductive.",
          "+  \\item \\textbf{Spread} (concentration $\\gtrsim 0.50$, $t_1/t_5 \\lesssim 0.70$): non-uniform allocation recommended. Multiple heads exhibit cross-bitwidth sensitivity gradients, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\\% PPL improvement.",
          "+  \\item \\textbf{Spike} ($t_1/t_5 \\gtrsim 0.70$, any concentration): use uniform. Sensitivity is dominated by a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.",
          "+  \\item \\textbf{Flat} (concentration $\\lesssim 0.50$, low $t_1/t_5$): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral (0.22, $t_1/t_5{=}0.18$) and Gemma-2 (0.23, $t_1/t_5{=}0.18$): counterproductive.",
          "   \\end{itemize}",
          " \\end{enumerate}",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 34_

Edit 4: illustrative threshold → 联合条件 + 5/5 分类声明。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "226f315b-a9d7-40bb-a3e5-361c7f0bfe1e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MnKNnNVQxDX1TouVFJx4Eg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 834,
      "cache_read_input_tokens": 59134,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 834
      },
      "output_tokens": 5,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 35_

<details open><summary>🔧 Tool call — Edit · `toolu_01Qk41BJ7LVKqmk2HjSjXVf4`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex",
  "old_string": "The $t_1/t_5 \\approx 0.70$ boundary is an illustrative threshold derived from five architectures; it should be validated on a broader set before being treated as a general rule.",
  "new_string": "The joint condition---concentration $\\gtrsim 0.50$ and $t_1/t_5 \\lesssim 0.70$---correctly separates the beneficial case from the four non-beneficial cases across all five architectures studied.\nBoth thresholds are illustrative, derived from five models; they should be validated on a broader set before being treated as general rules."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "23cdf3d2-2e26-4b64-8568-a6e35241c239",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MnKNnNVQxDX1TouVFJx4Eg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 834,
      "cache_read_input_tokens": 59134,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 834
      },
      "output_tokens": 5,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 36 · 2026-05-14T21:08:40.378Z_

<details><summary>↩ Tool result · `toolu_01Qk41BJ7LVKqmk2HjSjXVf4`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "0211f602-f7e7-4a32-9868-07574ebb7410",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex",
    "oldString": "The $t_1/t_5 \\approx 0.70$ boundary is an illustrative threshold derived from five architectures; it should be validated on a broader set before being treated as a general rule.",
    "newString": "The joint condition---concentration $\\gtrsim 0.50$ and $t_1/t_5 \\lesssim 0.70$---correctly separates the beneficial case from the four non-beneficial cases across all five architectures studied.\nBoth thresholds are illustrative, derived from five models; they should be validated on a broader set before being treated as general rules.",
    "originalFile": "\\section{Analysis}\n\\label{sec:analysis}\n\n\\subsection{Heterogeneity Characterization}\n\\label{sec:heterogeneity}\n\nThe benefit of non-uniform allocation depends on how unevenly head sensitivities are distributed.\nWe quantify this with a \\emph{top-5\\% concentration metric}: sort per-head 2-bit distortions $d_h(2)$ in descending order and compute the fraction of total distortion contributed by the top 5\\% of heads.\nHigh concentration indicates that a few heads are disproportionately sensitive; low concentration indicates near-uniform sensitivity.\n\nTable~\\ref{tab:heterogeneity} summarizes the results across five architectures at $4\\times$ compression.\nThe central finding is that MCKP benefit requires \\emph{spread heterogeneity}---multiple heads with cross-bitwidth sensitivity gradients---rather than sensitivity concentrated in a single outlier at one bitwidth.\n\nQwen2.5-7B exemplifies the spread pattern (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.\nConstrained MCKP reduces degradation from $+$5.64 PPL (uniform) to $+$1.42 PPL, a 27.3\\% improvement over uniform 4-bit. %exp_id=qwen_constrained_mckp\n\nYi-1.5-9B is a critical counterexample: despite the highest concentration tested ($0.71$, exceeding Qwen's $0.61$), constrained MCKP is counterproductive ($+$0.30 vs.\\ $+$0.20 uniform). %exp_id=yi15_hires_constrained\nThe mechanism is clear from the cross-bitwidth gradient structure.\nYi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling\nCritically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\\approx}\\,0$.\nThe solver therefore has only one lever---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.\nThis is the ``spike'' pattern: high concentration driven by a single outlier with sensitivity at only one bitwidth.\n\nIn contrast, Qwen's Layer-0 heads exhibit non-zero deltas at multiple bitwidths (e.g., L0H0: 2-bit delta ${=}6.74$, with positive 4-bit and 8-bit deltas), giving the solver a multi-bitwidth sensitivity gradient across several heads---a ``spread'' pattern that enables meaningful budget reallocation. %exp_id=qwen_hires_profiling\n\nThe remaining three architectures fill out the diagnostic picture.\nLlama-3.1-8B shows moderate concentration ($0.34$) with a spike-like shape ($t_1/t_5{=}0.71$, $t_1/t_2{=}21.7$); its allocation benefit is marginal ($+$0.36 vs.\\ $+$0.38 uniform). %exp_id=llama_hires_constrained\nMistral-7B-v0.3 and Gemma-2-9B both exhibit flat distributions ($t_1/t_5{=}0.18$) with low concentration ($0.22$ and $0.23$ respectively), leaving the profiler with no reliable signal; constrained MCKP is slightly worse than uniform in both cases ($+$0.13 vs.\\ $+$0.10 for Mistral; $+$0.15 vs.\\ $+$0.13 for Gemma-2). %exp_id=mistral_c4_cross_dataset %exp_id=gemma2_full_pipeline\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Head sensitivity heterogeneity and constrained allocation benefit across architectures at $4\\times$ compression. $t_1/t_5$: ratio of top-1 to top-5 per-head 2-bit distortion (low${=}$spread, high${=}$spike). $^\\dagger$Hires profiling (64 seq $\\times$ 2048 tok); $^\\ddagger$standard profiling, hires pending.}\n\\label{tab:heterogeneity}\n\\begin{tabular}{lcccccc}\n\\toprule\nModel & GQA & Top-5\\% & $t_1/t_5$ & $\\Delta$ PPL & $\\Delta$ PPL & Shape \\\\\n & Ratio & Conc. & & (Uniform) & (Ours) & \\\\\n\\midrule\nQwen2.5-7B & 7:1 & 0.61 & 0.57 & $+$5.64 & $+$1.42 & Spread \\\\\nYi-1.5-9B$^\\dagger$ & 8:1 & 0.71 & 0.90 & $+$0.20 & $+$0.30 & Spike \\\\\nLlama-3.1-8B$^\\ddagger$ & 4:1 & 0.34 & 0.71 & $+$0.38 & $+$0.36 & Spike \\\\\nMistral-7B-v0.3$^\\ddagger$ & 4:1 & 0.22 & 0.18 & $+$0.10 & $+$0.13 & Flat \\\\\nGemma-2-9B$^\\ddagger$ & 2:1 & 0.23 & 0.18 & $+$0.13 & $+$0.15 & Flat \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/fig1_head_delta_heatmap.pdf}\n\\caption{Per-head 2-bit quantization sensitivity across five architectures. Qwen2.5-7B shows high concentration in Layer-0 heads (``spread'' pattern); Yi-1.5-9B shows a single extreme outlier at Layer-4 Head-3 (``spike'' pattern); Llama-3.1-8B shows moderate spread; Mistral-7B-v0.3 shows near-zero sensitivity across all heads; Gemma-2-9B exhibits the most uniform distribution, consistent with its low GQA ratio (2:1). Color intensity indicates PPL increase when the head is quantized to 2-bit.}\n\\label{fig:heatmap}\n\\end{figure*}\n\nFigure~\\ref{fig:heatmap} visualizes the per-head 2-bit distortion as a heatmap.\nThe contrast is stark: Qwen's Layer-0 heads show high distortion (dark cells) while mid-to-deep layers are near-zero; Yi-1.5 shows a single bright spot at Layer-4 Head-3 (34\\% of total delta) with the remaining 191 heads near-uniform---a ``spike'' that MCKP cannot exploit; Gemma-2 exhibits the most uniform heatmap across its 336 heads, consistent with its 0.23 concentration; Mistral shows similarly low distortion across all layers and heads.\n\n\\subsection{Diagnostic Framework}\n\\label{sec:diagnostic}\n\nThe heterogeneity characterization shows that MCKP benefit requires not just high concentration but a specific \\emph{shape}---spread heterogeneity across multiple heads with cross-bitwidth sensitivity gradients.\nThis motivates a joint diagnostic, based on five architectures, for deciding when non-uniform allocation is worthwhile:\n\n\\begin{enumerate}[nosep]\n\\item Run per-head profiling as described in \\S\\ref{sec:profiling}.\n\\item Compute the top-5\\% concentration and the $t_1/t_5$ ratio (top-1 distortion divided by top-5 distortion) from the resulting distortion table.\n\\item Select allocation strategy based on concentration \\emph{and} shape:\n  \\begin{itemize}[nosep]\n  \\item \\textbf{Spread} (concentration $\\gtrsim 0.50$, $t_1/t_5 \\lesssim 0.70$): non-uniform allocation recommended. Multiple heads exhibit cross-bitwidth sensitivity gradients, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\\% PPL improvement.\n  \\item \\textbf{Spike} ($t_1/t_5 \\gtrsim 0.70$, any concentration): use uniform. Sensitivity is dominated by a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.\n  \\item \\textbf{Flat} (concentration $\\lesssim 0.50$, low $t_1/t_5$): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral (0.22, $t_1/t_5{=}0.18$) and Gemma-2 (0.23, $t_1/t_5{=}0.18$): counterproductive.\n  \\end{itemize}\n\\end{enumerate}\n\nThe $t_1/t_5 \\approx 0.70$ boundary is an illustrative threshold derived from five architectures; it should be validated on a broader set before being treated as a general rule.\nThe diagnostic adds no computational overhead: it reuses the profiling data already required for the allocation solver and avoids wasted optimization effort on architectures where non-uniform allocation provides no benefit.\nAdditional analyses---the effect of aggressive compression ratios, profiling resolution and multi-seed stability, per-layer optimality validation, and KV separation ablation---are provided in Appendices~\\ref{sec:aggressive}--\\ref{sec:kv_separation}.\n",
    "structuredPatch": [
      {
        "oldStart": 73,
        "oldLines": 6,
        "newStart": 73,
        "newLines": 7,
        "lines": [
          "   \\end{itemize}",
          " \\end{enumerate}",
          " ",
          "-The $t_1/t_5 \\approx 0.70$ boundary is an illustrative threshold derived from five architectures; it should be validated on a broader set before being treated as a general rule.",
          "+The joint condition---concentration $\\gtrsim 0.50$ and $t_1/t_5 \\lesssim 0.70$---correctly separates the beneficial case from the four non-beneficial cases across all five architectures studied.",
          "+Both thresholds are illustrative, derived from five models; they should be validated on a broader set before being treated as general rules.",
          " The diagnostic adds no computational overhead: it reuses the profiling data already required for the allocation solver and avoids wasted optimization effort on architectures where non-uniform allocation provides no benefit.",
          " Additional analyses---the effect of aggressive compression ratios, profiling resolution and multi-seed stability, per-layer optimality validation, and KV separation ablation---are provided in Appendices~\\ref{sec:aggressive}--\\ref{sec:kv_separation}."
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 37_

<details><summary>Logged reasoning block</summary>

```text
All 7 edits succeeded. Let me verify the final state of all files by reading them.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "398aa22f-5eea-4f42-9d33-458086437aaa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011uDzjRSLLw4ZRsRWSSEs6M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 345,
      "cache_read_input_tokens": 59968,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 345
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 38_

全部 7 处修改完成。验证最终结果。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "60ebc412-da1f-414a-b0ed-5aeb65ea1502",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011uDzjRSLLw4ZRsRWSSEs6M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 345,
      "cache_read_input_tokens": 59968,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 345
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 39_

<details open><summary>🔧 Tool call — Read · `toolu_016PQWnkYUU81sg81D2sek9F`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "6ac647ca-ba5d-4223-8440-41fc0237d620",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011uDzjRSLLw4ZRsRWSSEs6M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 345,
      "cache_read_input_tokens": 59968,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 345
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 40 · 2026-05-14T21:08:44.940Z_

<details><summary>↩ Tool result · `toolu_016PQWnkYUU81sg81D2sek9F`</summary>

```text
1	\section{Analysis}
2	\label{sec:analysis}
3	
4	\subsection{Heterogeneity Characterization}
5	\label{sec:heterogeneity}
6	
7	The benefit of non-uniform allocation depends on how unevenly head sensitivities are distributed.
8	We quantify this with a \emph{top-5\% concentration metric}: sort per-head 2-bit distortions $d_h(2)$ in descending order and compute the fraction of total distortion contributed by the top 5\% of heads.
9	High concentration indicates that a few heads are disproportionately sensitive; low concentration indicates near-uniform sensitivity.
10	
11	Table~\ref{tab:heterogeneity} summarizes the results across five architectures at $4\times$ compression.
12	The central finding is that MCKP benefit requires \emph{spread heterogeneity}---multiple heads with cross-bitwidth sensitivity gradients---rather than sensitivity concentrated in a single outlier at one bitwidth.
13	
14	Qwen2.5-7B exemplifies the spread pattern (top-5\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.
15	Constrained MCKP reduces degradation from $+$5.64 PPL (uniform) to $+$1.42 PPL, a 27.3\% improvement over uniform 4-bit. %exp_id=qwen_constrained_mckp
16	
17	Yi-1.5-9B is a critical counterexample: despite the highest concentration tested ($0.71$, exceeding Qwen's $0.61$), constrained MCKP is counterproductive ($+$0.30 vs.\ $+$0.20 uniform). %exp_id=yi15_hires_constrained
18	The mechanism is clear from the cross-bitwidth gradient structure.
19	Yi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling
20	Critically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\approx}\,0$.
21	The solver therefore has only one lever---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.
22	This is the ``spike'' pattern: high concentration driven by a single outlier with sensitivity at only one bitwidth.
23	
24	In contrast, Qwen's Layer-0 heads exhibit non-zero deltas at multiple bitwidths (e.g., L0H0: 2-bit delta ${=}6.74$, with positive 4-bit and 8-bit deltas), giving the solver a multi-bitwidth sensitivity gradient across several heads---a ``spread'' pattern that enables meaningful budget reallocation. %exp_id=qwen_hires_profiling
25	
26	The remaining three architectures fill out the diagnostic picture.
27	Llama-3.1-8B shows moderate concentration ($0.34$) with a spike-like shape ($t_1/t_5{=}0.71$, $t_1/t_2{=}21.7$); its allocation benefit is marginal ($+$0.36 vs.\ $+$0.38 uniform). %exp_id=llama_hires_constrained
28	Mistral-7B-v0.3 and Gemma-2-9B both exhibit flat distributions ($t_1/t_5{=}0.18$) with low concentration ($0.22$ and $0.23$ respectively), leaving the profiler with no reliable signal; constrained MCKP is slightly worse than uniform in both cases ($+$0.13 vs.\ $+$0.10 for Mistral; $+$0.15 vs.\ $+$0.13 for Gemma-2). %exp_id=mistral_c4_cross_dataset %exp_id=gemma2_full_pipeline
29	
30	\begin{table}[t]
31	\centering
32	\small
33	\caption{Head sensitivity heterogeneity and constrained allocation benefit across architectures at $4\times$ compression. $t_1/t_5$: ratio of top-1 to top-5 per-head 2-bit distortion (low${=}$spread, high${=}$spike). $^\dagger$Hires profiling (64 seq $\times$ 2048 tok); $^\ddagger$standard profiling, hires pending.}
34	\label{tab:heterogeneity}
35	\begin{tabular}{lcccccc}
36	\toprule
37	Model & GQA & Top-5\% & $t_1/t_5$ & $\Delta$ PPL & $\Delta$ PPL & Shape \\
38	 & Ratio & Conc. & & (Uniform) & (Ours) & \\
39	\midrule
40	Qwen2.5-7B & 7:1 & 0.61 & 0.57 & $+$5.64 & $+$1.42 & Spread \\
41	Yi-1.5-9B$^\dagger$ & 8:1 & 0.71 & 0.90 & $+$0.20 & $+$0.30 & Spike \\
42	Llama-3.1-8B$^\ddagger$ & 4:1 & 0.34 & 0.71 & $+$0.38 & $+$0.36 & Spike \\
43	Mistral-7B-v0.3$^\ddagger$ & 4:1 & 0.22 & 0.18 & $+$0.10 & $+$0.13 & Flat \\
44	Gemma-2-9B$^\ddagger$ & 2:1 & 0.23 & 0.18 & $+$0.13 & $+$0.15 & Flat \\
45	\bottomrule
46	\end{tabular}
47	\end{table}
48	
49	\begin{figure*}[t]
50	\centering
51	\includegraphics[width=\textwidth]{figures/fig1_head_delta_heatmap.pdf}
52	\caption{Per-head 2-bit quantization sensitivity across five architectures. Qwen2.5-7B shows high concentration in Layer-0 heads (``spread'' pattern); Yi-1.5-9B shows a single extreme outlier at Layer-4 Head-3 (``spike'' pattern); Llama-3.1-8B shows moderate spread; Mistral-7B-v0.3 shows near-zero sensitivity across all heads; Gemma-2-9B exhibits the most uniform distribution, consistent with its low GQA ratio (2:1). Color intensity indicates PPL increase when the head is quantized to 2-bit.}
53	\label{fig:heatmap}
54	\end{figure*}
55	
56	Figure~\ref{fig:heatmap} visualizes the per-head 2-bit distortion as a heatmap.
57	The contrast is stark: Qwen's Layer-0 heads show high distortion (dark cells) while mid-to-deep layers are near-zero; Yi-1.5 shows a single bright spot at Layer-4 Head-3 (34\% of total delta) with the remaining 191 heads near-uniform---a ``spike'' that MCKP cannot exploit; Gemma-2 exhibits the most uniform heatmap across its 336 heads, consistent with its 0.23 concentration; Mistral shows similarly low distortion across all layers and heads.
58	
59	\subsection{Diagnostic Framework}
60	\label{sec:diagnostic}
61	
62	The heterogeneity characterization shows that MCKP benefit requires not just high concentration but a specific \emph{shape}---spread heterogeneity across multiple heads with cross-bitwidth sensitivity gradients.
63	This motivates a joint diagnostic, based on five architectures, for deciding when non-uniform allocation is worthwhile:
64	
65	\begin{enumerate}[nosep]
66	\item Run per-head profiling as described in \S\ref{sec:profiling}.
67	\item Compute the top-5\% concentration and the $t_1/t_5$ ratio (top-1 distortion divided by top-5 distortion) from the resulting distortion table.
68	\item Select allocation strategy based on concentration \emph{and} shape:
69	  \begin{itemize}[nosep]
70	  \item \textbf{Spread} (concentration $\gtrsim 0.50$, $t_1/t_5 \lesssim 0.70$): non-uniform allocation recommended. Multiple heads exhibit cross-bitwidth sensitivity gradients, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\% PPL improvement.
71	  \item \textbf{Spike} ($t_1/t_5 \gtrsim 0.70$, any concentration): use uniform. Sensitivity is dominated by a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.
72	  \item \textbf{Flat} (concentration $\lesssim 0.50$, low $t_1/t_5$): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral (0.22, $t_1/t_5{=}0.18$) and Gemma-2 (0.23, $t_1/t_5{=}0.18$): counterproductive.
73	  \end{itemize}
74	\end{enumerate}
75	
76	The joint condition---concentration $\gtrsim 0.50$ and $t_1/t_5 \lesssim 0.70$---correctly separates the beneficial case from the four non-beneficial cases across all five architectures studied.
77	Both thresholds are illustrative, derived from five models; they should be validated on a broader set before being treated as general rules.
78	The diagnostic adds no computational overhead: it reuses the profiling data already required for the allocation solver and avoids wasted optimization effort on architectures where non-uniform allocation provides no benefit.
79	Additional analyses---the effect of aggressive compression ratios, profiling resolution and multi-seed stability, per-layer optimality validation, and KV separation ablation---are provided in Appendices~\ref{sec:aggressive}--\ref{sec:kv_separation}.
80	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "033828d9-e6ac-4597-b726-812ba156ab96",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex",
      "content": "\\section{Analysis}\n\\label{sec:analysis}\n\n\\subsection{Heterogeneity Characterization}\n\\label{sec:heterogeneity}\n\nThe benefit of non-uniform allocation depends on how unevenly head sensitivities are distributed.\nWe quantify this with a \\emph{top-5\\% concentration metric}: sort per-head 2-bit distortions $d_h(2)$ in descending order and compute the fraction of total distortion contributed by the top 5\\% of heads.\nHigh concentration indicates that a few heads are disproportionately sensitive; low concentration indicates near-uniform sensitivity.\n\nTable~\\ref{tab:heterogeneity} summarizes the results across five architectures at $4\\times$ compression.\nThe central finding is that MCKP benefit requires \\emph{spread heterogeneity}---multiple heads with cross-bitwidth sensitivity gradients---rather than sensitivity concentrated in a single outlier at one bitwidth.\n\nQwen2.5-7B exemplifies the spread pattern (top-5\\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.\nConstrained MCKP reduces degradation from $+$5.64 PPL (uniform) to $+$1.42 PPL, a 27.3\\% improvement over uniform 4-bit. %exp_id=qwen_constrained_mckp\n\nYi-1.5-9B is a critical counterexample: despite the highest concentration tested ($0.71$, exceeding Qwen's $0.61$), constrained MCKP is counterproductive ($+$0.30 vs.\\ $+$0.20 uniform). %exp_id=yi15_hires_constrained\nThe mechanism is clear from the cross-bitwidth gradient structure.\nYi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 has a 2-bit delta of 13.12, while the second-ranked head has delta 0.55---a $24\\times$ gap ($t_1/t_5{=}0.90$, $t_1/t_2{=}23.7$). %exp_id=yi15_hires_profiling\nCritically, L4H3's sensitivity is confined to the 2-bit operating point: its 4-bit and 8-bit deltas are ${\\approx}\\,0$.\nThe solver therefore has only one lever---upgrading L4H3 from 2-bit to 4-bit removes the distortion, but further upgrading to 8-bit provides no additional benefit, so the budget freed by downgrading other heads has nowhere useful to go.\nThis is the ``spike'' pattern: high concentration driven by a single outlier with sensitivity at only one bitwidth.\n\nIn contrast, Qwen's Layer-0 heads exhibit non-zero deltas at multiple bitwidths (e.g., L0H0: 2-bit delta ${=}6.74$, with positive 4-bit and 8-bit deltas), giving the solver a multi-bitwidth sensitivity gradient across several heads---a ``spread'' pattern that enables meaningful budget reallocation. %exp_id=qwen_hires_profiling\n\nThe remaining three architectures fill out the diagnostic picture.\nLlama-3.1-8B shows moderate concentration ($0.34$) with a spike-like shape ($t_1/t_5{=}0.71$, $t_1/t_2{=}21.7$); its allocation benefit is marginal ($+$0.36 vs.\\ $+$0.38 uniform). %exp_id=llama_hires_constrained\nMistral-7B-v0.3 and Gemma-2-9B both exhibit flat distributions ($t_1/t_5{=}0.18$) with low concentration ($0.22$ and $0.23$ respectively), leaving the profiler with no reliable signal; constrained MCKP is slightly worse than uniform in both cases ($+$0.13 vs.\\ $+$0.10 for Mistral; $+$0.15 vs.\\ $+$0.13 for Gemma-2). %exp_id=mistral_c4_cross_dataset %exp_id=gemma2_full_pipeline\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Head sensitivity heterogeneity and constrained allocation benefit across architectures at $4\\times$ compression. $t_1/t_5$: ratio of top-1 to top-5 per-head 2-bit distortion (low${=}$spread, high${=}$spike). $^\\dagger$Hires profiling (64 seq $\\times$ 2048 tok); $^\\ddagger$standard profiling, hires pending.}\n\\label{tab:heterogeneity}\n\\begin{tabular}{lcccccc}\n\\toprule\nModel & GQA & Top-5\\% & $t_1/t_5$ & $\\Delta$ PPL & $\\Delta$ PPL & Shape \\\\\n & Ratio & Conc. & & (Uniform) & (Ours) & \\\\\n\\midrule\nQwen2.5-7B & 7:1 & 0.61 & 0.57 & $+$5.64 & $+$1.42 & Spread \\\\\nYi-1.5-9B$^\\dagger$ & 8:1 & 0.71 & 0.90 & $+$0.20 & $+$0.30 & Spike \\\\\nLlama-3.1-8B$^\\ddagger$ & 4:1 & 0.34 & 0.71 & $+$0.38 & $+$0.36 & Spike \\\\\nMistral-7B-v0.3$^\\ddagger$ & 4:1 & 0.22 & 0.18 & $+$0.10 & $+$0.13 & Flat \\\\\nGemma-2-9B$^\\ddagger$ & 2:1 & 0.23 & 0.18 & $+$0.13 & $+$0.15 & Flat \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{figures/fig1_head_delta_heatmap.pdf}\n\\caption{Per-head 2-bit quantization sensitivity across five architectures. Qwen2.5-7B shows high concentration in Layer-0 heads (``spread'' pattern); Yi-1.5-9B shows a single extreme outlier at Layer-4 Head-3 (``spike'' pattern); Llama-3.1-8B shows moderate spread; Mistral-7B-v0.3 shows near-zero sensitivity across all heads; Gemma-2-9B exhibits the most uniform distribution, consistent with its low GQA ratio (2:1). Color intensity indicates PPL increase when the head is quantized to 2-bit.}\n\\label{fig:heatmap}\n\\end{figure*}\n\nFigure~\\ref{fig:heatmap} visualizes the per-head 2-bit distortion as a heatmap.\nThe contrast is stark: Qwen's Layer-0 heads show high distortion (dark cells) while mid-to-deep layers are near-zero; Yi-1.5 shows a single bright spot at Layer-4 Head-3 (34\\% of total delta) with the remaining 191 heads near-uniform---a ``spike'' that MCKP cannot exploit; Gemma-2 exhibits the most uniform heatmap across its 336 heads, consistent with its 0.23 concentration; Mistral shows similarly low distortion across all layers and heads.\n\n\\subsection{Diagnostic Framework}\n\\label{sec:diagnostic}\n\nThe heterogeneity characterization shows that MCKP benefit requires not just high concentration but a specific \\emph{shape}---spread heterogeneity across multiple heads with cross-bitwidth sensitivity gradients.\nThis motivates a joint diagnostic, based on five architectures, for deciding when non-uniform allocation is worthwhile:\n\n\\begin{enumerate}[nosep]\n\\item Run per-head profiling as described in \\S\\ref{sec:profiling}.\n\\item Compute the top-5\\% concentration and the $t_1/t_5$ ratio (top-1 distortion divided by top-5 distortion) from the resulting distortion table.\n\\item Select allocation strategy based on concentration \\emph{and} shape:\n  \\begin{itemize}[nosep]\n  \\item \\textbf{Spread} (concentration $\\gtrsim 0.50$, $t_1/t_5 \\lesssim 0.70$): non-uniform allocation recommended. Multiple heads exhibit cross-bitwidth sensitivity gradients, giving the solver room to redistribute budget. Qwen (0.61, $t_1/t_5{=}0.57$): 27.3\\% PPL improvement.\n  \\item \\textbf{Spike} ($t_1/t_5 \\gtrsim 0.70$, any concentration): use uniform. Sensitivity is dominated by a single outlier with no cross-bitwidth gradient; the solver cannot exploit it. Yi-1.5 (0.71, $t_1/t_5{=}0.90$) and Llama (0.34, $t_1/t_5{=}0.71$): counterproductive or marginal.\n  \\item \\textbf{Flat} (concentration $\\lesssim 0.50$, low $t_1/t_5$): use uniform. Near-uniform sensitivity provides no signal for differentiated allocation. Mistral (0.22, $t_1/t_5{=}0.18$) and Gemma-2 (0.23, $t_1/t_5{=}0.18$): counterproductive.\n  \\end{itemize}\n\\end{enumerate}\n\nThe joint condition---concentration $\\gtrsim 0.50$ and $t_1/t_5 \\lesssim 0.70$---correctly separates the beneficial case from the four non-beneficial cases across all five architectures studied.\nBoth thresholds are illustrative, derived from five models; they should be validated on a broader set before being treated as general rules.\nThe diagnostic adds no computational overhead: it reuses the profiling data already required for the allocation solver and avoids wasted optimization effort on architectures where non-uniform allocation provides no benefit.\nAdditional analyses---the effect of aggressive compression ratios, profiling resolution and multi-seed stability, per-layer optimality validation, and KV separation ablation---are provided in Appendices~\\ref{sec:aggressive}--\\ref{sec:kv_separation}.\n",
      "numLines": 80,
      "startLine": 1,
      "totalLines": 80
    }
  }
}
```

</details>

---

### Tool call

_source line 41_

<details open><summary>🔧 Tool call — Read · `toolu_01SZFLWKzXMyJ6jLNLqRFM47`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "4cfd2d79-0666-4f3a-b9f0-50a84f420f8b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011uDzjRSLLw4ZRsRWSSEs6M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 345,
      "cache_read_input_tokens": 59968,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 345
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 42 · 2026-05-14T21:08:45.396Z_

<details><summary>↩ Tool result · `toolu_01SZFLWKzXMyJ6jLNLqRFM47`</summary>

```text
1	Per-head mixed-precision quantization of the KV cache promises lower perplexity than uniform quantization at the same average bit-width, but on hardware-aligned bit-widths $\{2, 4, 8, 16\}$, existing solvers fail catastrophically: unconstrained greedy and MCKP allocation achieve 32.45 and 36.92 perplexity on Qwen2.5-7B---far worse than uniform 4-bit (15.45).
2	We trace this failure to \emph{2-bit distortion compounding}: when the majority of heads are assigned 2-bit precision, per-head quantization errors interact non-additively through the residual stream, violating the additive objective assumed by standard solvers.
3	We show that a single cardinality constraint capping the number of 2-bit assignments is a minimal sufficient fix.
4	On Qwen2.5-7B at $4\times$ compression, constrained allocation achieves 11.23 perplexity, a 27.3\% reduction over uniform 4-bit.
5	The constraint also renders solver choice irrelevant: constrained greedy and constrained MCKP produce equivalent bit-width assignments across all three tested architectures ($\Delta{=}0.0000$), enabling use of a simple $O(H \log H)$ greedy algorithm; per-layer brute-force oracle confirms near-optimality (max gap 0.02 PPL).
6	However, the benefit depends on architecture: on Llama-3.1-8B the improvement is marginal (8.45 vs.\ 8.47), and on Mistral-7B-v0.3, Yi-1.5-9B, and Gemma-2-9B non-uniform allocation is counterproductive.
7	Notably, Yi-1.5-9B has the highest GQA ratio tested (8:1) and the highest top-5\% concentration (0.71), yet degrades under non-uniform allocation---because its heterogeneity is a single-outlier ``spike'' with no cross-bitwidth sensitivity gradient, rather than the ``spread'' pattern that enables MCKP to redistribute budget across heads.
8	We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) that correctly identifies all five architectures studied---distinguishing spread heterogeneity (MCKP-exploitable) from spike and flat patterns where non-uniform allocation provides no benefit.
9	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "eb184597-7e1b-4e4d-ad25-d256a539aad7",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/abstract.tex",
      "content": "Per-head mixed-precision quantization of the KV cache promises lower perplexity than uniform quantization at the same average bit-width, but on hardware-aligned bit-widths $\\{2, 4, 8, 16\\}$, existing solvers fail catastrophically: unconstrained greedy and MCKP allocation achieve 32.45 and 36.92 perplexity on Qwen2.5-7B---far worse than uniform 4-bit (15.45).\nWe trace this failure to \\emph{2-bit distortion compounding}: when the majority of heads are assigned 2-bit precision, per-head quantization errors interact non-additively through the residual stream, violating the additive objective assumed by standard solvers.\nWe show that a single cardinality constraint capping the number of 2-bit assignments is a minimal sufficient fix.\nOn Qwen2.5-7B at $4\\times$ compression, constrained allocation achieves 11.23 perplexity, a 27.3\\% reduction over uniform 4-bit.\nThe constraint also renders solver choice irrelevant: constrained greedy and constrained MCKP produce equivalent bit-width assignments across all three tested architectures ($\\Delta{=}0.0000$), enabling use of a simple $O(H \\log H)$ greedy algorithm; per-layer brute-force oracle confirms near-optimality (max gap 0.02 PPL).\nHowever, the benefit depends on architecture: on Llama-3.1-8B the improvement is marginal (8.45 vs.\\ 8.47), and on Mistral-7B-v0.3, Yi-1.5-9B, and Gemma-2-9B non-uniform allocation is counterproductive.\nNotably, Yi-1.5-9B has the highest GQA ratio tested (8:1) and the highest top-5\\% concentration (0.71), yet degrades under non-uniform allocation---because its heterogeneity is a single-outlier ``spike'' with no cross-bitwidth sensitivity gradient, rather than the ``spread'' pattern that enables MCKP to redistribute budget across heads.\nWe propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) that correctly identifies all five architectures studied---distinguishing spread heterogeneity (MCKP-exploitable) from spike and flat patterns where non-uniform allocation provides no benefit.\n",
      "numLines": 9,
      "startLine": 1,
      "totalLines": 9
    }
  }
}
```

</details>

---

### Tool call

_source line 43_

<details open><summary>🔧 Tool call — Read · `toolu_01HriWquxs4BQ4Gy6A6dAESr`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/introduction.tex",
  "offset": 46,
  "limit": 10
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "41af9c46-ef21-4d4d-8911-38cfcb091618",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011uDzjRSLLw4ZRsRWSSEs6M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 345,
      "cache_read_input_tokens": 59968,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 345
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 44 · 2026-05-14T21:08:46.337Z_

<details><summary>↩ Tool result · `toolu_01HriWquxs4BQ4Gy6A6dAESr`</summary>

```text
46	
47	Our contributions are:
48	\begin{enumerate}[nosep]
49	\item We identify 2-bit distortion compounding as the cause of catastrophic failure in unconstrained per-head KV cache quantization on hardware-aligned bit-widths, and show that a cardinality constraint on 2-bit assignments is a minimal sufficient fix, reducing Qwen2.5-7B PPL from 32--37 (unconstrained) to 11.23 (constrained) at $4\times$ compression (\S\ref{sec:compounding}, \S\ref{sec:experiments}).
50	
51	\item We demonstrate that the cardinality constraint makes solver choice irrelevant: constrained greedy and constrained MCKP produce equivalent per-head allocations across three architectures, enabling use of a simple greedy algorithm (\S\ref{sec:solver_equiv}).
52	
53	\item We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) that correctly separates architectures where non-uniform allocation helps from those where it does not, across all five models tested. Yi-1.5-9B serves as a critical test: its concentration exceeds Qwen's, yet its single-outlier spike pattern makes MCKP counterproductive (\S\ref{sec:heterogeneity}).
54	\end{enumerate}
55	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "2975d518-312e-4e0a-a916-0af8e8b116fe",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/introduction.tex",
      "content": "\nOur contributions are:\n\\begin{enumerate}[nosep]\n\\item We identify 2-bit distortion compounding as the cause of catastrophic failure in unconstrained per-head KV cache quantization on hardware-aligned bit-widths, and show that a cardinality constraint on 2-bit assignments is a minimal sufficient fix, reducing Qwen2.5-7B PPL from 32--37 (unconstrained) to 11.23 (constrained) at $4\\times$ compression (\\S\\ref{sec:compounding}, \\S\\ref{sec:experiments}).\n\n\\item We demonstrate that the cardinality constraint makes solver choice irrelevant: constrained greedy and constrained MCKP produce equivalent per-head allocations across three architectures, enabling use of a simple greedy algorithm (\\S\\ref{sec:solver_equiv}).\n\n\\item We propose a joint diagnostic combining concentration and distribution shape ($t_1/t_5$ ratio) that correctly separates architectures where non-uniform allocation helps from those where it does not, across all five models tested. Yi-1.5-9B serves as a critical test: its concentration exceeds Qwen's, yet its single-outlier spike pattern makes MCKP counterproductive (\\S\\ref{sec:heterogeneity}).\n\\end{enumerate}\n",
      "numLines": 10,
      "startLine": 46,
      "totalLines": 55
    }
  }
}
```

</details>

---

### Tool call

_source line 45_

<details open><summary>🔧 Tool call — Read · `toolu_01Y5P2bFqEtov1jg2QFDpXQD`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/conclusion.tex",
  "offset": 1,
  "limit": 12
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "604c941c-369c-4c17-ba5c-6f293dd335bb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011uDzjRSLLw4ZRsRWSSEs6M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 345,
      "cache_read_input_tokens": 59968,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 345
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 46 · 2026-05-14T21:08:46.859Z_

<details><summary>↩ Tool result · `toolu_01Y5P2bFqEtov1jg2QFDpXQD`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	We showed that per-head mixed-precision KV cache quantization over hardware-aligned bit-widths \{2, 4, 8, 16\} requires a cardinality constraint on 2-bit assignments to prevent non-additive distortion compounding through the residual stream.
4	A single constraint---limiting simultaneously active 2-bit heads to $k \leq 8$ (7\% of heads)---reduces perplexity on Qwen2.5-7B from 15.45 (uniform 4-bit) to 11.23, a 27.3\% improvement at $4\times$ compression.
5	Under the constraint, solver choice becomes irrelevant: greedy and MCKP produce equivalent allocations across all three architectures ($\Delta = 0.0000$), so a simple $O(H \log H)$ greedy algorithm suffices.
6	The benefit of non-uniform allocation depends on both the concentration and \emph{shape} of head sensitivity heterogeneity.
7	Qwen2.5-7B (concentration 0.61, $t_1/t_5{=}0.57$, spread pattern) shows large gains; Llama-3.1-8B ($t_1/t_5{=}0.71$, spike) shows marginal improvement (8.45 vs.\ 8.47 PPL); Mistral-7B-v0.3, Yi-1.5-9B, and Gemma-2-9B are counterproductive.
8	Yi-1.5-9B is a critical test case: despite the highest concentration tested ($0.71$, exceeding Qwen), its heterogeneity is a single-outlier spike ($t_1/t_5{=}0.90$) with no cross-bitwidth sensitivity gradient, so MCKP cannot redistribute budget.
9	A joint diagnostic using concentration ($\gtrsim 0.50$) and $t_1/t_5$ ratio ($\lesssim 0.70$) correctly identifies spread, spike, and flat patterns across all five models studied, computable from the same profiling pass used for allocation.
10	This provides a practical guideline: practitioners can determine whether non-uniform quantization is worthwhile for their architecture \emph{before} running the allocation solver.
11	
12	\paragraph{Limitations.}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "acebb9ac-3b69-41f8-b1c4-13045a3ce95a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\\label{sec:conclusion}\n\nWe showed that per-head mixed-precision KV cache quantization over hardware-aligned bit-widths \\{2, 4, 8, 16\\} requires a cardinality constraint on 2-bit assignments to prevent non-additive distortion compounding through the residual stream.\nA single constraint---limiting simultaneously active 2-bit heads to $k \\leq 8$ (7\\% of heads)---reduces perplexity on Qwen2.5-7B from 15.45 (uniform 4-bit) to 11.23, a 27.3\\% improvement at $4\\times$ compression.\nUnder the constraint, solver choice becomes irrelevant: greedy and MCKP produce equivalent allocations across all three architectures ($\\Delta = 0.0000$), so a simple $O(H \\log H)$ greedy algorithm suffices.\nThe benefit of non-uniform allocation depends on both the concentration and \\emph{shape} of head sensitivity heterogeneity.\nQwen2.5-7B (concentration 0.61, $t_1/t_5{=}0.57$, spread pattern) shows large gains; Llama-3.1-8B ($t_1/t_5{=}0.71$, spike) shows marginal improvement (8.45 vs.\\ 8.47 PPL); Mistral-7B-v0.3, Yi-1.5-9B, and Gemma-2-9B are counterproductive.\nYi-1.5-9B is a critical test case: despite the highest concentration tested ($0.71$, exceeding Qwen), its heterogeneity is a single-outlier spike ($t_1/t_5{=}0.90$) with no cross-bitwidth sensitivity gradient, so MCKP cannot redistribute budget.\nA joint diagnostic using concentration ($\\gtrsim 0.50$) and $t_1/t_5$ ratio ($\\lesssim 0.70$) correctly identifies spread, spike, and flat patterns across all five models studied, computable from the same profiling pass used for allocation.\nThis provides a practical guideline: practitioners can determine whether non-uniform quantization is worthwhile for their architecture \\emph{before} running the allocation solver.\n\n\\paragraph{Limitations.}",
      "numLines": 12,
      "startLine": 1,
      "totalLines": 23
    }
  }
}
```

</details>

---

### Assistant

_source line 47_

<details><summary>Logged reasoning block</summary>

```text
All edits look correct. Let me verify the appendix already has the float32 validation note (it did from my first read). No changes needed there.

Let me summarize all changes made:

1. **analysis.tex §5.1** (lines 11-12): Added key insight sentence — "spread heterogeneity (multiple heads with cross-bitwidth sensitivity gradients)" stated before examples. Qwen reworded from "exhibits highest spread" to "exemplifies the spread pattern".

2. **analysis.tex §5.1** (lines 15-22): Yi-1.5 paragraph restructured — leads with "critical counterexample" instead of "concentration alone doesn't predict"; "mechanism is clear from cross-bitwidth gradient structure" replaces "explanation lies in shape"; "only one lever" replaces "no gradient to exploit"; "spike pattern: high concentration driven by..." replaces "spike pattern: high concentration, but...".
   
3. **analysis.tex §5.2** (diagnostic items): Replaced vague thresholds with explicit numerical bounds — concentration ranges now specified as ≳ 0.50 for moderate-to-high and ≲ 0.50 for low, while the ratio condition $t_1/t_5 ≳ 0.70$ is now stated upfront; Mistral and Gemma-2 entries updated with actual concentration values.

4. **analysis.tex §5.2** (threshold statement): Introducing a joint condition combining concentration and ratio thresholds...

5. **abstract.tex** (line 8): Strengthened the claim from "can indicate" to "correctly identifies all five architectures studied", incorporating the ratio terminology and spike/flat distinction.

6. **introduction.tex** (Claim 3): Reframed to emphasize correct separation of architectures, with Yi-1.5 highlighted as a key validation case.

7. **conclusion.tex** (line 9): Embedded the explicit thresholds directly, adopted "correctly identifies" language, and restructured as two sentences with practical application guidance.

8. **appendix.tex**: The float32 validation section is already in place, so no updates needed there.

All revisions align with the core requirements: the mechanism comes first, thresholds are framed as illustrative, Yi-1.5 serves as the critical test case, and the honest presentation of its failure case prevents any appearance of cherry-picking.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "ede08c64-a5c2-4276-8bbf-a07cca19ad0f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LRpmN5LcP4gmA2AvuR4oYe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4930,
      "cache_read_input_tokens": 60313,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4930
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 48_

全部修改完成，appendix.tex 无需改动（float32 validation 已存在于 lines 29-30）。汇总：

### 改动清单

**analysis.tex** (4 处)
1. **§5.1 开头**（L11-12）：插入机制洞察——"MCKP benefit requires *spread heterogeneity*—multiple heads with cross-bitwidth sensitivity gradients"，置于 Qwen 数据之前
2. **§5.1 Yi-1.5 段**（L17-22）：以 "critical counterexample" 开头，强调 "mechanism is clear from cross-bitwidth gradient structure"，"only one lever" 替代 "no gradient to exploit"
3. **§5.2 诊断条目**（L70-72）：显式阈值——Spread: `concentration ≳ 0.50, t₁/t₅ ≲ 0.70`；Spike: `t₁/t₅ ≳ 0.70, any concentration`；Flat: `concentration ≲ 0.50, low t₁/t₅`；Mistral/Gemma-2 加上浓度数值
4. **§5.2 阈值声明**（L76-77）：联合条件 "correctly separates the beneficial case from the four non-beneficial cases across all five architectures studied"，两个阈值均标注 illustrative

**abstract.tex**（L8）："can indicate" → "correctly identifies all five architectures studied"，加入 t₁/t₅ ratio 和 spike/flat 术语

**introduction.tex**（L53 Claim 3）："to indicate" → "correctly separates"，加 Yi-1.5 as critical test 说明

**conclusion.tex**（L9-10）：加显式阈值 (≳ 0.50, ≲ 0.70)，拆为两句，新增 practical guideline 表述

**appendix.tex**：无改动（float32 validation 已在 ¶Numerical precision）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "uuid": "77762c81-82fe-4a60-b65b-ce997dc0a5cb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LRpmN5LcP4gmA2AvuR4oYe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4930,
      "cache_read_input_tokens": 60313,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4930
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Task result

_source line 49_

全部修改完成，appendix.tex 无需改动（float32 validation 已存在于 lines 29-30）。汇总：

### 改动清单

**analysis.tex** (4 处)
1. **§5.1 开头**（L11-12）：插入机制洞察——"MCKP benefit requires *spread heterogeneity*—multiple heads with cross-bitwidth sensitivity gradients"，置于 Qwen 数据之前
2. **§5.1 Yi-1.5 段**（L17-22）：以 "critical counterexample" 开头，强调 "mechanism is clear from cross-bitwidth gradient structure"，"only one lever" 替代 "no gradient to exploit"
3. **§5.2 诊断条目**（L70-72）：显式阈值——Spread: `concentration ≳ 0.50, t₁/t₅ ≲ 0.70`；Spike: `t₁/t₅ ≳ 0.70, any concentration`；Flat: `concentration ≲ 0.50, low t₁/t₅`；Mistral/Gemma-2 加上浓度数值
4. **§5.2 阈值声明**（L76-77）：联合条件 "correctly separates the beneficial case from the four non-beneficial cases across all five architectures studied"，两个阈值均标注 illustrative

**abstract.tex**（L8）："can indicate" → "correctly identifies all five architectures studied"，加入 t₁/t₅ ratio 和 spike/flat 术语

**introduction.tex**（L53 Claim 3）："to indicate" → "correctly separates"，加 Yi-1.5 as critical test 说明

**conclusion.tex**（L9-10）：加显式阈值 (≳ 0.50, ≲ 0.70)，拆为两句，新增 practical guideline 表述

**appendix.tex**：无改动（float32 validation 已在 ¶Numerical precision）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 487432,
  "duration_api_ms": 488533,
  "num_turns": 17,
  "stop_reason": "end_turn",
  "session_id": "ca4b0092-736a-46cc-afb2-dcb74ba65397",
  "total_cost_usd": 1.2214034999999999,
  "usage": {
    "input_tokens": 10,
    "cache_creation_input_tokens": 53402,
    "cache_read_input_tokens": 365942,
    "output_tokens": 28093,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 53402,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 1306,
        "cache_read_input_tokens": 60313,
        "cache_creation_input_tokens": 4930,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 4930
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2190,
      "outputTokens": 21,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.002295,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 10,
      "outputTokens": 28093,
      "cacheReadInputTokens": 365942,
      "cacheCreationInputTokens": 53402,
      "webSearchRequests": 0,
      "costUSD": 1.2191085,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "d20aeafb-a415-42b9-aa9b-7a501329dac5"
}
```

</details>

---
