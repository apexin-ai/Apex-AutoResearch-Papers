# analysis bce data source verify

**Output-Distribution Distillation for Contextual Sparsity Prediction in SwiGLU LLMs** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 52
- **Recorded user turns:** 0
- **Tool calls:** 17
- **Original source:** `logs/workers/worker_analysis_bce-data-source-verify_20260519T082212.log`
- **Structured JSON:** [`79266d0d5518032747ce.json`](../../sessions/79/79266d0d5518032747ce.json)

## Before a recorded user message

52 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu",
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
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
    "mcp__agent-ml-research__read_registry",
    "mcp__agent-ml-research__register_artifact",
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__update_registry"
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
  "uuid": "91be65d7-97f9-4683-a247-ec48f93b3d5e",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/memory/"
  },
  "fast_mode_state": "off"
}
```

---

### Assistant

_source line 3_

I'll verify the BCE data sources for Tables 2 and 4. Let me start by reading the paper tables and the experiment registry in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "b2ff4745-5587-4d64-9d98-f8a17183f865",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YAHbE5rzoLv63ihMYjjZqB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 14152,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14152
      },
      "output_tokens": 2,
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

### Runtime record

_source line 4_

```json
{
  "type": "rate_limit_event",
  "rate_limit_info": {
    "status": "allowed_warning",
    "resetsAt": 1779472800,
    "rateLimitType": "seven_day",
    "utilization": 0.76,
    "isUsingOverage": false,
    "surpassedThreshold": 0.75
  },
  "uuid": "1bbd276a-a7f0-4dc6-a926-925f46f9ca7b",
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c"
}
```

---

### Tool call

_source line 5_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01UNxgfDjz6jxuJNiNCfqNQA`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__register_artifact",
  "max_results": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "3ae88369-6391-4785-aaaf-1ee5b3ab0f2c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YAHbE5rzoLv63ihMYjjZqB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 14152,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14152
      },
      "output_tokens": 2,
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

_source line 6 · 2026-05-19T08:22:26.767Z_

<details><summary>↩ Tool result · `toolu_01UNxgfDjz6jxuJNiNCfqNQA`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_registry"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__register_artifact"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "60c4f6da-b3b0-443e-aa54-0c6f3bf706cb",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__register_artifact"
    ],
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__register_artifact",
    "total_deferred_tools": 25
  }
}
```

</details>

---

### Assistant

_source line 7_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the paper tables and query the registry in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "59d51484-746e-4dbe-8f93-f1f8bdb2eb6c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01G3zN7mkp9ru1hxY9dbMtqg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1093,
      "cache_read_input_tokens": 25993,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1093
      },
      "output_tokens": 38,
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

_source line 8_

<details open><summary>🔧 Tool call — Read · `toolu_01Hpw4dCeayvgCM6XHpF38i2`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "26024be0-d6cd-4457-8f5e-b3fe53aad24e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01G3zN7mkp9ru1hxY9dbMtqg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1093,
      "cache_read_input_tokens": 25993,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1093
      },
      "output_tokens": 38,
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

_source line 9 · 2026-05-19T08:22:30.473Z_

<details><summary>↩ Tool result · `toolu_01Hpw4dCeayvgCM6XHpF38i2`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\subsection{Experimental Setup}
5	
6	\paragraph{Model and Predictor.}
7	We evaluate on LLaMA-3.1-8B~\cite{grattafiori2024llama3}, which uses SwiGLU FFN blocks~\cite{shazeer2020glu} with $d_{\text{model}}=4096$ and $d_{\text{ff}}=14336$ across 32 layers.
8	The sparsity predictor is a two-layer MLP with 2.37M parameters per layer (75.9M total), implemented as Linear($4096 \to 128$) + GELU + Linear($128 \to 14336$), trained to produce per-neuron importance scores that minimize output-distribution divergence under sparsity.
9	
10	\paragraph{Training.}
11	All predictors are trained for 1000 steps on WikiText-103 with sequence length 2048 and batch size 4 on a single NVIDIA RTX PRO 6000 Blackwell Server Edition GPU (96\,GB), using AdamW~\cite{loshchilov2019adamw} with learning rate $1 \times 10^{-3}$, weight decay $5 \times 10^{-2}$, and cosine decay.
12	The KL predictor uses Gumbel-Sigmoid relaxation~\cite{jang2017gumbel} with temperature $\tau=1.0$ annealed to $0.1$ over training.
13	
14	\paragraph{Evaluation.}
15	We report perplexity on WikiText-2~\cite{merity2017pointer} (seq\_len=2048) and downstream accuracy on ARC-Challenge (25-shot), WinoGrande (5-shot), MMLU (5-shot), and GSM8K (8-shot).
16	
17	\paragraph{Inference Protocol.}
18	At inference, the predictor produces per-neuron scores that are passed to TEAL's global top-$k$ allocation mechanism~\cite{liu2025teal}, which distributes the sparsity budget across layers non-uniformly.
19	We term this \textit{predictor-TEAL}: the predictor replaces TEAL's magnitude-based scoring while retaining its allocation strategy.
20	
21	\paragraph{Baselines.}
22	We compare against: (1) \textbf{Vanilla TEAL}~\cite{liu2025teal}, which uses activation magnitudes directly; (2) \textbf{BCE predictor} (DejaVu-style~\cite{liu2023dejavu}), trained with per-neuron binary cross-entropy on magnitude-based oracle masks for 1000 and 2700 steps; (3) \textbf{Uniform allocation}, which distributes the sparsity budget equally across layers; and (4) \textbf{WINA}~\cite{liu2025teal}, an importance-weighted variant.
23	
24	
25	\subsection{Main Results}
26	
27	Table~\ref{tab:main} presents the primary comparison. Uniform allocation preserves downstream performance best; global allocation is analyzed to understand allocation-quality tradeoffs (\S\ref{sec:scaling}).
28	At 30\% sparsity, KL distillation with global TEAL allocation achieves PPL 8.96$\pm$0.02 (3-seed) and reduces TEAL's degradation from dense (10.97 $\to$ 8.96, an 18\% improvement). % exp_id: kl30_3seed_global
29	HellaSwag (86.0\% retention) and PIQA (92.5\% retention) confirm moderate degradation on non-reasoning tasks (Appendix~\ref{app:downstream}). % exp_id: hellaswag_piqa_kl30_uniform
30	Uniform allocation at 30\% achieves PPL 8.81$\pm$0.02 with stable downstream performance (MMLU 40.7$\pm$1.3\%, 3-seed), while global top-$k$ exhibits high seed variance (35.7$\pm$9.5\%) from late-layer starvation (L31 retention 28.4\%) interacting with predictor initialization (\S\ref{sec:scaling}). % exp_id: bench_kl30_uniform, kl30_s123_uniform, kl30_s456_uniform, kl30_3seed
31	
32	At 50\% sparsity, the PPL advantage widens: 11.79 vs.\ 23.31 (49\% reduction over TEAL). % exp_id: bench_kl50_global, bench_teal50
33	The predictor generalizes to C4 validation at both 30\% (PPL 16.03$\pm$0.01, 2-seed) and 50\% (52.5\% over TEAL; Appendix~\ref{app:ood}).
34	However, all methods exhibit downstream collapse on MMLU (28.1$\pm$0.2\% vs.\ 28.0$\pm$0.6\%, both $\approx$ random, 3-seed) and GSM8K ($<$2.2\%); this is a capacity-limited regime where no allocation strategy can recover. % exp_id: bench_kl50_global, d030_kl50_uniform, multi_seed_kl50_global
35	
36	\begin{table}[t]
37	\centering
38	\caption{Main results on LLaMA-3.1-8B (WikiText-2 PPL$\downarrow$; downstream accuracy$\uparrow$). \textbf{Bold}: best compensation-free per sparsity. $^\ast$BCE 50\%: DejaVu/FastForward pipeline with compensation (67.2M params). $^\dagger$BCE 30\%: TEAL global, no compensation (2700 steps). $\pm$: 3-seed mean$\pm$std ($s \in \{42, 123, 456\}$); unmarked: seed 42.}
39	\label{tab:main}
40	\resizebox{\columnwidth}{!}{
41	\begin{tabular}{llccccc}
42	\toprule
43	Sparsity & Method & PPL$\downarrow$ & ARC-c & WG & MMLU & GSM8K \\
44	\midrule
45	0\% & Dense & 6.12 & 58.28 & 78.06 & 65.27 & 48.75 \\
46	\midrule
47	\multirow{4}{*}{30\%}
48	& TEAL vanilla & 10.97 & 42.32 & 66.06 & 38.61 & 7.88 \\ % exp_id: bench_teal30
49	& KL global (Ours) & 8.96$\pm$0.02 & \textbf{43.8$\pm$3.6} & \textbf{70.2$\pm$0.9} & 35.7$\pm$9.5 & \textbf{8.0$\pm$0.7} \\ % exp_id: kl30_3seed_global
50	& KL uniform & \textbf{8.81$\pm$0.02} & 43.7$\pm$2.5 & 68.9$\pm$0.4 & \textbf{40.7$\pm$1.3} & 7.5$\pm$0.1 \\ % exp_id: bench_kl30_uniform, kl30_s123_uniform, kl30_s456_uniform
51	& BCE global$^\dagger$ & 11.25 & 41.2 & 66.0 & 36.3 & 6.0 \\ % exp_id: bce30_teal_global
52	\midrule
53	\multirow{4}{*}{50\%}
54	& TEAL vanilla & 23.31 & 28.41 & 53.04 & \textbf{28.32} & 1.97 \\ % exp_id: bench_teal50
55	& KL global (Ours) & \textbf{11.79} & 32.85 & \textbf{63.46} & 28.1 & 1.29 \\ % exp_id: bench_kl50_global
56	& KL uniform & 11.92$\pm$0.07 & \textbf{33.8$\pm$1.2} & 62.9$\pm$0.1 & 28.0$\pm$0.6 & \textbf{2.2$\pm$0.1} \\ % exp_id: bench_kl50_uniform, bench_kl50_uniform_s123, bench_kl50_uniform_s456
57	& BCE + comp.$^\ast$ & 28.13$\pm$0.20 & 27.6$\pm$0.6 & 51.8$\pm$0.6 & 26.1$\pm$0.5 & 2.1$\pm$0.2 \\ % exp_id: bce50_3seed
58	\bottomrule
59	\end{tabular}}
60	\end{table}
61	
62	
63	\subsection{Extended Training Analysis}
64	\label{sec:isocompute}
65	
66	To test whether BCE simply requires more compute, we train it for 2700 steps (2.71$\times$ the KL step budget, approximately equal wall-clock time: $\sim$46 min BCE vs.\ $\sim$45 min KL on RTX PRO 6000).
67	The BCE predictor achieves PPL 28.13$\pm$0.20 (3-seed), still 2.39$\times$ worse than KL at 1000 steps (PPL 11.79). % exp_id: bce50_3seed
68	The difference is systematic, not due to architectural or compute limitations: both predictors use identical architectures and TEAL allocation, yet BCE achieves +7pp oracle F1 (0.613 vs.\ 0.540) with 139\% worse PPL (28.13 vs.\ 11.79). KL's near-random precision (0.51) is consistent with a mask optimized for distributional fidelity rather than magnitude agreement. % exp_id: f1_oracle_analysis, bce_isocompute_s42
69	Coupled training correlates with better output preservation; the causal ablation in \S\ref{sec:mask_analysis} confirms that the discovered mask targets, not the coupling mechanism itself, are the proximate driver of inference-stage quality.
70	
71	
72	\subsection{Mask Pattern Analysis}
73	\label{sec:mask_analysis}
74	
75	To understand \emph{what} the KL predictor learns, we compare KL-derived masks against magnitude-based oracle masks (the BCE training targets) at 50\% sparsity on WikiText-2.
76	Per-layer Jaccard similarity averages 32\% at 50\% sparsity (64 samples, 131K tokens): the KL predictor discovers neuron importance patterns that diverge 68\% from activation magnitude, with divergence scaling from 46\% at 30\% to 68\% at 50\% (Figure~\ref{fig:mask_heatmap}).
77	At layer 16, 41\% of neurons fall in disagreement quadrants where KL and magnitude rankings diverge (Appendix~\ref{app:mask_viz}, Figures~\ref{fig:mask_heatmap}--\ref{fig:scatter}).
78	Despite this divergence, KL achieves PPL 11.79 vs.\ BCE's 28.13$\pm$0.20: output-distribution fidelity, not magnitude agreement, produces superior masks under global allocation. % exp_id: bench_kl50_global, bce50_3seed, c1_mask_overlap
79	
80	\paragraph{Per-Layer Divergence Structure.}
81	Per-layer Jaccard distance follows a U-shaped pattern (Figure~\ref{fig:mask_heatmap}): at 50\%, middle layers (L14--L17) show lowest divergence ($\sim$0.61), while late layers (L22--L28) peak at $\sim$0.70--0.75. The same structure holds at 30\% (range 0.361--0.600).
82	Late layers are closest to the KL-optimized output distribution, so their backward gradient carries stronger output-sensitivity signal and the predictor deviates most from magnitude ranking there. % exp_id: c1_mask_overlap
83	
84	\paragraph{Causal Ablation: Target Quality vs.\ Gradient Coupling.}
85	To disentangle whether KL's advantage stems from its coupled gradient pathway or from the mask patterns it discovers, we train a standard BCE predictor on KL-derived oracle masks instead of magnitude-based masks (C1 ablation).
86	Table~\ref{tab:c1} reports results under TEAL uniform allocation at matched sparsity.
87	
88	\begin{table}[t]
89	\centering
90	\caption{Causal ablation (C1): BCE on KL-derived masks vs.\ KL predictor (same seed), TEAL uniform. Retrained seeds (s123, s456) max $\Delta$$\leq$1.18pp at 30\%; max $\Delta$=0.59pp at 50\% (2-seed). $^\dagger$s42 uses an earlier oracle checkpoint.}
91	\label{tab:c1}
92	\resizebox{\columnwidth}{!}{
93	\begin{tabular}{lllccccc}
94	\toprule
95	Sparsity & Seed & Method & PPL$\downarrow$ & ARC-c & WG & MMLU & GSM8K \\
96	\midrule
97	\multirow{6}{*}{30\%}
98	& s42$^\dagger$ & C1 & 9.45 & \textbf{48.63} & \textbf{70.40} & \textbf{42.30} & \textbf{13.57} \\ % exp_id: c1_ablation_30pct_s42_eval_v2
99	& & KL & \textbf{8.80} & 40.78 & 68.59 & 40.6 & 7.35 \\ % exp_id: bench_kl30_uniform
100	& s123 & C1 & 8.84 & 44.71 & \textbf{69.77} & \textbf{39.92} & 6.82 \\ % exp_id: eval_c1_retrain_30pct_s123
101	& & KL & \textbf{8.83} & \textbf{45.31} & 69.38 & 39.4 & \textbf{7.51} \\ % exp_id: kl30_s123_eval
102	& s456 & C1 & 8.82 & 44.71 & \textbf{69.93} & 41.04 & 6.60 \\ % exp_id: eval_c1_retrain_30pct_s456
103	& & KL & \textbf{8.79} & \textbf{45.05} & 68.75 & \textbf{42.0} & \textbf{7.58} \\ % exp_id: kl30_s456_uniform_eval
104	\midrule
105	\multirow{2}{*}{50\%}
106	& s42 & C1 & 11.96 & 32.17 & \textbf{63.14} & 27.79 & \textbf{2.05} \\ % exp_id: c1_bce_kl_targets_teal50u
107	& & KL & 11.96 & \textbf{32.59} & 62.35 & \textbf{27.92} & 1.97 \\ % exp_id: c1_kl_teal50u
108	\bottomrule
109	\end{tabular}}
110	\end{table}
111	
112	At 50\%, C1 matches KL within statistical noise (max $\Delta$=0.59pp, 2-seed), while magnitude-trained BCE yields PPL 28.13$\pm$0.20 ($2.4\times$ worse; Table~\ref{tab:main}).
113	At 30\%, retrained C1 predictors (s123, s456) reproduce KL quality within $\pm$1.18pp across all downstream tasks (max $\Delta$=1.18pp WG, s456). The s42 pair uses an earlier oracle checkpoint and shows larger variation (max 7.85pp on ARC-c).
114	These results confirm that KL's coupled gradients discover superior mask targets that transfer to a simpler objective (BCE): mask quality is the proximate driver of inference-stage quality, while gradient coupling remains necessary at the discovery stage. % exp_id: bce50_3seed, c1_bce_kl_targets_30u, c1_s123
115	
116	\paragraph{Soft-vs-Hard Confound.}
117	C1 changes both gradient coupling and mask representation (hard binary vs.\ soft Gumbel-Sigmoid). However, BCE with Gumbel-Sigmoid relaxation (even without penalty) yields PPL 32.22 (Table~\ref{tab:ablation}), worse than standard hard-target BCE (27.97): softness alone does not explain KL's advantage. % exp_id: bce_gumbel_no_penalty_s42, eval_bce_v3_s42
118	Disentangling target quality from gradient representation remains for future work.
119	
120	\subsection{Ablation Studies}
121	
122	Table~\ref{tab:ablation} isolates the contribution of each design choice at 50\% sparsity.
123	
124	\begin{table}[t]
125	\centering
126	\caption{Ablation at 50\% sparsity on LLaMA-3.1-8B (WikiText-2 PPL$\downarrow$, unified benchmark protocol).}
127	\label{tab:ablation}
128	\small
129	\begin{tabular}{lcc}
130	\toprule
131	Configuration & PPL$\downarrow$ & $\Delta$ from Ours \\
132	\midrule
133	\multicolumn{3}{l}{\textit{KL-based variants}} \\
134	Forward KL + Gumbel (Ours) & \textbf{11.79} & --- \\ % exp_id: bench_kl50_global
135	JSD (symmetric) + Gumbel & 12.54 & +0.75 \\ % exp_id: jsd_ablation_s42
136	Reverse KL + Gumbel & 12.80 & +1.01 \\ % exp_id: reverse_kl_ablation_s42
137	Forward KL + STE & 15.77 & +3.98 \\ % exp_id: ste_baseline_s42
138	\midrule
139	\multicolumn{3}{l}{\textit{BCE-based variants}} \\
140	BCE + Compensation (hard mask) & 25.44 & +13.65 \\ % exp_id: bce_comp_staged_s42
141	BCE (no compensation) & 27.97 & +16.18 \\ % exp_id: eval_bce_v3_s42
142	BCE + Gumbel (no penalty) & 32.22 & +20.43 \\ % exp_id: bce_gumbel_no_penalty_s42
143	BCE + Gumbel + Penalty & 38.02 & +26.23 \\ % exp_id: bce_gumbel_lagrangian_isolation
144	\bottomrule
145	\end{tabular}
146	\end{table}
147	
148	\paragraph{Gumbel vs.\ STE.}
149	Replacing Gumbel-Sigmoid with STE~\cite{bengio2013ste} degrades PPL from 11.79 to 15.77 (+3.98). % exp_id: ste_baseline_s42
150	
151	\paragraph{Divergence Direction.}
152	Forward KL outperforms JSD (+6.4\%) and reverse KL (+8.6\%), consistent with the SNR analysis (\S\ref{sec:method:gradient}); mode-covering ensures no important neuron is omitted, contrasting with reverse-KL generation~\cite{gu2024minillm}. % exp_id: jsd_ablation_s42, reverse_kl_ablation_s42
153	
154	\paragraph{SPON Contribution.}
155	Adding SPON~\cite{xu2026spon} bias correction reduces PPL from 12.08 to 11.79 (2.4\% relative; Appendix~\ref{app:spon}). % exp_id: spon_2048_s42, mvp_kl_norm_v2_s42
156	
157	\paragraph{Loss Function Isolation.}
158	Removing the penalty from BCE+Gumbel improves PPL (32.22 vs.\ 38.02), partly due to a sparsity gap (38.3\% training vs.\ 50\% target), but remains $2.7\times$ worse than KL (11.79) and worse than vanilla BCE at matched 50\% sparsity (27.97): Gumbel relaxation does not benefit BCE regardless of sparsity control, and KL's advantage stems from the loss function itself. % exp_id: bce_gumbel_no_penalty_s42, bce_gumbel_lagrangian_isolation, eval_bce_v3_s42
159	The loss effect ($\Delta$PPL=20.43) is $5.1\times$ the relaxation effect ($\Delta$PPL=3.98).
160	
161	\paragraph{Compensation Redundancy.}
162	Adding compensation~\cite{gautam2026fastforward} (+67.2M params) to KL provides no benefit at either sparsity level (PPL 8.97 vs.\ 8.96 at 30\%, identical at 50\%; Appendix~\ref{app:comp_convergence}). BCE requires compensation (27.97$\to$25.44), yet remains $2.16\times$ worse than KL without it. % exp_id: kl_comp_30_s42, kl_comp_30_s456, kl_comp_50_s42, bce_comp_staged_s42
163	
164	\paragraph{Hyperparameter Robustness.}
165	Appendix~\ref{app:db_sensitivity} confirms robustness to predictor capacity ($d_b$, $<$3\%), temperature ($<$1.8\%), and training steps (saturated by 800). % exp_id: db_sensitivity_sweep, tau_schedule_sweep, training_steps_sweep
166	
167	
168	\subsection{Sparsity Scaling and Regime Analysis}
169	\label{sec:scaling}
170	
171	Figure~\ref{fig:sparsity_sweep} shows PPL as a function of sparsity for the KL predictor under global allocation.
172	
173	\begin{figure}[t]
174	\centering
175	\includegraphics[width=\columnwidth]{fig2_sparsity_sweep.pdf}
176	\caption{Perplexity scaling with sparsity. The KL predictor's advantage grows disproportionately as more neurons are pruned.}
177	\label{fig:sparsity_sweep}
178	\end{figure}
179	
180	The regime curve (Figure~\ref{fig:sparsity_sweep}) is strictly monotonic from PPL 8.17 at 25\% to 11.80 at 50\% (global, seed 42), with KL/Dense degradation ranging from $1.34\times$ to $1.93\times$.
181	At matched points, KL improves over TEAL by 18\% at 30\% and 49\% at 50\%; at 70\%, where TEAL collapses (PPL 100.11), the advantage reaches 82\%. % exp_id: regime_kl25_global, regime_kl50_global, kl_70_global_teal
182	
183	\paragraph{Allocation Behavior Across Sparsity Levels.}
184	Table~\ref{tab:phase} compares global vs.\ uniform allocation at representative sparsity levels, revealing qualitative shifts in preference.
185	
186	\begin{table}[t]
187	\centering
188	\caption{Allocation analysis at key sparsity levels (LLaMA-3.1-8B, PPL and MMLU; full 6-level data with all downstream metrics in Appendix~\ref{app:alloc_full}). $\pm$: 3-seed; others: seed 42. $^\ast$High seed variance (25.3--43.5\%).}
189	\label{tab:phase}
190	\footnotesize
191	\begin{tabular}{llcc}
192	\toprule
193	Sparsity & Allocation & PPL$\downarrow$ & MMLU \\
194	\midrule
195	\multirow{2}{*}{25\%}
196	& Global & \textbf{8.17} & \textbf{46.6} \\ % exp_id: regime_kl25_global
197	& Uniform & 8.23 & 44.0 \\ % exp_id: regime_kl25_uniform
198	\midrule
199	\multirow{2}{*}{30\%}
200	& Global & 8.96$\pm$0.02 & 35.7$\pm$9.5$^\ast$ \\ % exp_id: kl30_3seed_global
201	& Uniform & \textbf{8.81$\pm$0.02} & \textbf{40.7$\pm$1.3} \\ % exp_id: bench_kl30_uniform
202	\midrule
203	\multirow{2}{*}{35\%}
204	& Global & \textbf{9.31} & \textbf{40.4} \\ % exp_id: regime_kl35_global
205	& Uniform & 9.44 & 37.8 \\ % exp_id: regime_kl35_uniform
206	\midrule
207	\multirow{2}{*}{50\%}
208	& Global & \textbf{11.79} & \textbf{28.1$\pm$0.2} \\ % exp_id: multi_seed_kl50_global
209	& Uniform & 11.92$\pm$0.07 & 28.0$\pm$0.6 \\ % exp_id: multi_seed_kl50_uniform
210	\bottomrule
211	\end{tabular}
212	\end{table}
213	
214	The analysis reveals \emph{non-monotonic} allocation preference with three regimes, complementing OWL's~\cite{yin2024owl} finding that non-uniform layerwise budgets improve pruning quality (full 6-level data in Appendix~\ref{app:alloc_full}):
215	
216	\noindent\textbf{Budget-surplus ($\leq$30\%).}
217	At 25\%, PPL differs by only 0.06. At 30\%, uniform achieves PPL 8.81$\pm$0.02 (3-seed) with $7.5\times$ smaller cross-seed MMLU $\sigma$ (1.3pp vs.\ 9.5pp). % exp_id: regime_kl25_global, regime_kl25_uniform, kl30_3seed
218	
219	\noindent\textbf{Budget-constrained (35--40\%).}
220	Global becomes preferable: at 35\%, MMLU 40.4\% vs.\ 37.8\% (+2.6pp); at 40\%, MMLU 38.1\% (Appendix~\ref{app:alloc_full}). % exp_id: regime_kl35_global, regime_kl35_uniform, regime_kl40_global
221	
222	\noindent\textbf{Capacity-limited ($\geq$45\%).}
223	Gap vanishes for reasoning: at 50\%, MMLU collapses to near-random under both strategies (28.1 vs.\ 28.0\%), though global still helps non-reasoning tasks (HellaSwag +2.29pp; Appendix~\ref{app:downstream}). Late-layer starvation persists (Figure~\ref{fig:retention}; Appendix~\ref{app:retention}). % exp_id: multi_seed_kl50_global, multi_seed_kl50_uniform, hellaswag_piqa_kl50_global, hellaswag_piqa_kl50_uniform
224	
225	
226	\paragraph{Cross-Architecture and Scale.}
227	\label{sec:cross_arch}
228	On Mistral-7B-v0.3~\cite{jiang2023mistral}, KL outperforms TEAL on 5 of 6 downstream
229	tasks at 30\% (HellaSwag +8.8pp, ARC +9.0pp, WG +5.6pp, PIQA +3.1pp, MMLU +0.6pp),
230	with PPL 6.77 vs.\ 8.38; GSM8K is the sole reversal (11.1\% vs.\ 15.9\%,
231	Table~\ref{tab:mistral_downstream}); the 50\% capacity cliff also holds cross-architecture (MMLU 26.4\%$\approx$random; Appendix~\ref{app:cross_arch}). % exp_id: mistral_kl30_downstream, mistral_teal30_downstream, mistral_teal50_downstream
232	On Qwen-2.5-14B~\cite{qwen2024qwen25}, KL's PPL advantage generalizes at 30\% ($1.47\times$ dense) but MMLU falls to 63.7\% vs.\ TEAL's 71.8\% ($-$8.1pp; Appendix~\ref{app:14b}); this reversal is absent at 7B on both architectures.
233	Per-layer mask divergence identifies a structural difference consistent with this reversal: despite similar mean Jaccard ($\sim$0.40), 14B variance is $2.4\times$ that of 8B (std 0.076 vs.\ 0.031), with an early-layer convergence zone (L3--L6, min 0.063 at L4) absent in LLaMA-8B (min 0.353).
234	This suggests KL's PPL-optimal reallocation redirects resources from early knowledge-encoding layers toward mid-to-late layers, conflicting with factual recall.
235	Verification requires layer-wise probing beyond our current scope. % exp_id: qwen14b_kl30_s42, qwen14b_teal30_eval, qwen14b_bce30_s42_eval
236	\paragraph{Inference Efficiency.}
237	\label{sec:overhead}
238	The predictor adds 3.17\,ms (2.7\% overhead) using 75.96M params (0.9\% of base), eliminating BCE's 67.2M compensation network; actual speedup requires sparse kernel integration (Appendix~\ref{app:latency}). % exp_id: latency_profiling
239	
240	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "e02eac51-af45-461b-85f3-c2549f40cec0",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/paper/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\n\\subsection{Experimental Setup}\n\n\\paragraph{Model and Predictor.}\nWe evaluate on LLaMA-3.1-8B~\\cite{grattafiori2024llama3}, which uses SwiGLU FFN blocks~\\cite{shazeer2020glu} with $d_{\\text{model}}=4096$ and $d_{\\text{ff}}=14336$ across 32 layers.\nThe sparsity predictor is a two-layer MLP with 2.37M parameters per layer (75.9M total), implemented as Linear($4096 \\to 128$) + GELU + Linear($128 \\to 14336$), trained to produce per-neuron importance scores that minimize output-distribution divergence under sparsity.\n\n\\paragraph{Training.}\nAll predictors are trained for 1000 steps on WikiText-103 with sequence length 2048 and batch size 4 on a single NVIDIA RTX PRO 6000 Blackwell Server Edition GPU (96\\,GB), using AdamW~\\cite{loshchilov2019adamw} with learning rate $1 \\times 10^{-3}$, weight decay $5 \\times 10^{-2}$, and cosine decay.\nThe KL predictor uses Gumbel-Sigmoid relaxation~\\cite{jang2017gumbel} with temperature $\\tau=1.0$ annealed to $0.1$ over training.\n\n\\paragraph{Evaluation.}\nWe report perplexity on WikiText-2~\\cite{merity2017pointer} (seq\\_len=2048) and downstream accuracy on ARC-Challenge (25-shot), WinoGrande (5-shot), MMLU (5-shot), and GSM8K (8-shot).\n\n\\paragraph{Inference Protocol.}\nAt inference, the predictor produces per-neuron scores that are passed to TEAL's global top-$k$ allocation mechanism~\\cite{liu2025teal}, which distributes the sparsity budget across layers non-uniformly.\nWe term this \\textit{predictor-TEAL}: the predictor replaces TEAL's magnitude-based scoring while retaining its allocation strategy.\n\n\\paragraph{Baselines.}\nWe compare against: (1) \\textbf{Vanilla TEAL}~\\cite{liu2025teal}, which uses activation magnitudes directly; (2) \\textbf{BCE predictor} (DejaVu-style~\\cite{liu2023dejavu}), trained with per-neuron binary cross-entropy on magnitude-based oracle masks for 1000 and 2700 steps; (3) \\textbf{Uniform allocation}, which distributes the sparsity budget equally across layers; and (4) \\textbf{WINA}~\\cite{liu2025teal}, an importance-weighted variant.\n\n\n\\subsection{Main Results}\n\nTable~\\ref{tab:main} presents the primary comparison. Uniform allocation preserves downstream performance best; global allocation is analyzed to understand allocation-quality tradeoffs (\\S\\ref{sec:scaling}).\nAt 30\\% sparsity, KL distillation with global TEAL allocation achieves PPL 8.96$\\pm$0.02 (3-seed) and reduces TEAL's degradation from dense (10.97 $\\to$ 8.96, an 18\\% improvement). % exp_id: kl30_3seed_global\nHellaSwag (86.0\\% retention) and PIQA (92.5\\% retention) confirm moderate degradation on non-reasoning tasks (Appendix~\\ref{app:downstream}). % exp_id: hellaswag_piqa_kl30_uniform\nUniform allocation at 30\\% achieves PPL 8.81$\\pm$0.02 with stable downstream performance (MMLU 40.7$\\pm$1.3\\%, 3-seed), while global top-$k$ exhibits high seed variance (35.7$\\pm$9.5\\%) from late-layer starvation (L31 retention 28.4\\%) interacting with predictor initialization (\\S\\ref{sec:scaling}). % exp_id: bench_kl30_uniform, kl30_s123_uniform, kl30_s456_uniform, kl30_3seed\n\nAt 50\\% sparsity, the PPL advantage widens: 11.79 vs.\\ 23.31 (49\\% reduction over TEAL). % exp_id: bench_kl50_global, bench_teal50\nThe predictor generalizes to C4 validation at both 30\\% (PPL 16.03$\\pm$0.01, 2-seed) and 50\\% (52.5\\% over TEAL; Appendix~\\ref{app:ood}).\nHowever, all methods exhibit downstream collapse on MMLU (28.1$\\pm$0.2\\% vs.\\ 28.0$\\pm$0.6\\%, both $\\approx$ random, 3-seed) and GSM8K ($<$2.2\\%); this is a capacity-limited regime where no allocation strategy can recover. % exp_id: bench_kl50_global, d030_kl50_uniform, multi_seed_kl50_global\n\n\\begin{table}[t]\n\\centering\n\\caption{Main results on LLaMA-3.1-8B (WikiText-2 PPL$\\downarrow$; downstream accuracy$\\uparrow$). \\textbf{Bold}: best compensation-free per sparsity. $^\\ast$BCE 50\\%: DejaVu/FastForward pipeline with compensation (67.2M params). $^\\dagger$BCE 30\\%: TEAL global, no compensation (2700 steps). $\\pm$: 3-seed mean$\\pm$std ($s \\in \\{42, 123, 456\\}$); unmarked: seed 42.}\n\\label{tab:main}\n\\resizebox{\\columnwidth}{!}{\n\\begin{tabular}{llccccc}\n\\toprule\nSparsity & Method & PPL$\\downarrow$ & ARC-c & WG & MMLU & GSM8K \\\\\n\\midrule\n0\\% & Dense & 6.12 & 58.28 & 78.06 & 65.27 & 48.75 \\\\\n\\midrule\n\\multirow{4}{*}{30\\%}\n& TEAL vanilla & 10.97 & 42.32 & 66.06 & 38.61 & 7.88 \\\\ % exp_id: bench_teal30\n& KL global (Ours) & 8.96$\\pm$0.02 & \\textbf{43.8$\\pm$3.6} & \\textbf{70.2$\\pm$0.9} & 35.7$\\pm$9.5 & \\textbf{8.0$\\pm$0.7} \\\\ % exp_id: kl30_3seed_global\n& KL uniform & \\textbf{8.81$\\pm$0.02} & 43.7$\\pm$2.5 & 68.9$\\pm$0.4 & \\textbf{40.7$\\pm$1.3} & 7.5$\\pm$0.1 \\\\ % exp_id: bench_kl30_uniform, kl30_s123_uniform, kl30_s456_uniform\n& BCE global$^\\dagger$ & 11.25 & 41.2 & 66.0 & 36.3 & 6.0 \\\\ % exp_id: bce30_teal_global\n\\midrule\n\\multirow{4}{*}{50\\%}\n& TEAL vanilla & 23.31 & 28.41 & 53.04 & \\textbf{28.32} & 1.97 \\\\ % exp_id: bench_teal50\n& KL global (Ours) & \\textbf{11.79} & 32.85 & \\textbf{63.46} & 28.1 & 1.29 \\\\ % exp_id: bench_kl50_global\n& KL uniform & 11.92$\\pm$0.07 & \\textbf{33.8$\\pm$1.2} & 62.9$\\pm$0.1 & 28.0$\\pm$0.6 & \\textbf{2.2$\\pm$0.1} \\\\ % exp_id: bench_kl50_uniform, bench_kl50_uniform_s123, bench_kl50_uniform_s456\n& BCE + comp.$^\\ast$ & 28.13$\\pm$0.20 & 27.6$\\pm$0.6 & 51.8$\\pm$0.6 & 26.1$\\pm$0.5 & 2.1$\\pm$0.2 \\\\ % exp_id: bce50_3seed\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\n\\subsection{Extended Training Analysis}\n\\label{sec:isocompute}\n\nTo test whether BCE simply requires more compute, we train it for 2700 steps (2.71$\\times$ the KL step budget, approximately equal wall-clock time: $\\sim$46 min BCE vs.\\ $\\sim$45 min KL on RTX PRO 6000).\nThe BCE predictor achieves PPL 28.13$\\pm$0.20 (3-seed), still 2.39$\\times$ worse than KL at 1000 steps (PPL 11.79). % exp_id: bce50_3seed\nThe difference is systematic, not due to architectural or compute limitations: both predictors use identical architectures and TEAL allocation, yet BCE achieves +7pp oracle F1 (0.613 vs.\\ 0.540) with 139\\% worse PPL (28.13 vs.\\ 11.79). KL's near-random precision (0.51) is consistent with a mask optimized for distributional fidelity rather than magnitude agreement. % exp_id: f1_oracle_analysis, bce_isocompute_s42\nCoupled training correlates with better output preservation; the causal ablation in \\S\\ref{sec:mask_analysis} confirms that the discovered mask targets, not the coupling mechanism itself, are the proximate driver of inference-stage quality.\n\n\n\\subsection{Mask Pattern Analysis}\n\\label{sec:mask_analysis}\n\nTo understand \\emph{what} the KL predictor learns, we compare KL-derived masks against magnitude-based oracle masks (the BCE training targets) at 50\\% sparsity on WikiText-2.\nPer-layer Jaccard similarity averages 32\\% at 50\\% sparsity (64 samples, 131K tokens): the KL predictor discovers neuron importance patterns that diverge 68\\% from activation magnitude, with divergence scaling from 46\\% at 30\\% to 68\\% at 50\\% (Figure~\\ref{fig:mask_heatmap}).\nAt layer 16, 41\\% of neurons fall in disagreement quadrants where KL and magnitude rankings diverge (Appendix~\\ref{app:mask_viz}, Figures~\\ref{fig:mask_heatmap}--\\ref{fig:scatter}).\nDespite this divergence, KL achieves PPL 11.79 vs.\\ BCE's 28.13$\\pm$0.20: output-distribution fidelity, not magnitude agreement, produces superior masks under global allocation. % exp_id: bench_kl50_global, bce50_3seed, c1_mask_overlap\n\n\\paragraph{Per-Layer Divergence Structure.}\nPer-layer Jaccard distance follows a U-shaped pattern (Figure~\\ref{fig:mask_heatmap}): at 50\\%, middle layers (L14--L17) show lowest divergence ($\\sim$0.61), while late layers (L22--L28) peak at $\\sim$0.70--0.75. The same structure holds at 30\\% (range 0.361--0.600).\nLate layers are closest to the KL-optimized output distribution, so their backward gradient carries stronger output-sensitivity signal and the predictor deviates most from magnitude ranking there. % exp_id: c1_mask_overlap\n\n\\paragraph{Causal Ablation: Target Quality vs.\\ Gradient Coupling.}\nTo disentangle whether KL's advantage stems from its coupled gradient pathway or from the mask patterns it discovers, we train a standard BCE predictor on KL-derived oracle masks instead of magnitude-based masks (C1 ablation).\nTable~\\ref{tab:c1} reports results under TEAL uniform allocation at matched sparsity.\n\n\\begin{table}[t]\n\\centering\n\\caption{Causal ablation (C1): BCE on KL-derived masks vs.\\ KL predictor (same seed), TEAL uniform. Retrained seeds (s123, s456) max $\\Delta$$\\leq$1.18pp at 30\\%; max $\\Delta$=0.59pp at 50\\% (2-seed). $^\\dagger$s42 uses an earlier oracle checkpoint.}\n\\label{tab:c1}\n\\resizebox{\\columnwidth}{!}{\n\\begin{tabular}{lllccccc}\n\\toprule\nSparsity & Seed & Method & PPL$\\downarrow$ & ARC-c & WG & MMLU & GSM8K \\\\\n\\midrule\n\\multirow{6}{*}{30\\%}\n& s42$^\\dagger$ & C1 & 9.45 & \\textbf{48.63} & \\textbf{70.40} & \\textbf{42.30} & \\textbf{13.57} \\\\ % exp_id: c1_ablation_30pct_s42_eval_v2\n& & KL & \\textbf{8.80} & 40.78 & 68.59 & 40.6 & 7.35 \\\\ % exp_id: bench_kl30_uniform\n& s123 & C1 & 8.84 & 44.71 & \\textbf{69.77} & \\textbf{39.92} & 6.82 \\\\ % exp_id: eval_c1_retrain_30pct_s123\n& & KL & \\textbf{8.83} & \\textbf{45.31} & 69.38 & 39.4 & \\textbf{7.51} \\\\ % exp_id: kl30_s123_eval\n& s456 & C1 & 8.82 & 44.71 & \\textbf{69.93} & 41.04 & 6.60 \\\\ % exp_id: eval_c1_retrain_30pct_s456\n& & KL & \\textbf{8.79} & \\textbf{45.05} & 68.75 & \\textbf{42.0} & \\textbf{7.58} \\\\ % exp_id: kl30_s456_uniform_eval\n\\midrule\n\\multirow{2}{*}{50\\%}\n& s42 & C1 & 11.96 & 32.17 & \\textbf{63.14} & 27.79 & \\textbf{2.05} \\\\ % exp_id: c1_bce_kl_targets_teal50u\n& & KL & 11.96 & \\textbf{32.59} & 62.35 & \\textbf{27.92} & 1.97 \\\\ % exp_id: c1_kl_teal50u\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nAt 50\\%, C1 matches KL within statistical noise (max $\\Delta$=0.59pp, 2-seed), while magnitude-trained BCE yields PPL 28.13$\\pm$0.20 ($2.4\\times$ worse; Table~\\ref{tab:main}).\nAt 30\\%, retrained C1 predictors (s123, s456) reproduce KL quality within $\\pm$1.18pp across all downstream tasks (max $\\Delta$=1.18pp WG, s456). The s42 pair uses an earlier oracle checkpoint and shows larger variation (max 7.85pp on ARC-c).\nThese results confirm that KL's coupled gradients discover superior mask targets that transfer to a simpler objective (BCE): mask quality is the proximate driver of inference-stage quality, while gradient coupling remains necessary at the discovery stage. % exp_id: bce50_3seed, c1_bce_kl_targets_30u, c1_s123\n\n\\paragraph{Soft-vs-Hard Confound.}\nC1 changes both gradient coupling and mask representation (hard binary vs.\\ soft Gumbel-Sigmoid). However, BCE with Gumbel-Sigmoid relaxation (even without penalty) yields PPL 32.22 (Table~\\ref{tab:ablation}), worse than standard hard-target BCE (27.97): softness alone does not explain KL's advantage. % exp_id: bce_gumbel_no_penalty_s42, eval_bce_v3_s42\nDisentangling target quality from gradient representation remains for future work.\n\n\\subsection{Ablation Studies}\n\nTable~\\ref{tab:ablation} isolates the contribution of each design choice at 50\\% sparsity.\n\n\\begin{table}[t]\n\\centering\n\\caption{Ablation at 50\\% sparsity on LLaMA-3.1-8B (WikiText-2 PPL$\\downarrow$, unified benchmark protocol).}\n\\label{tab:ablation}\n\\small\n\\begin{tabular}{lcc}\n\\toprule\nConfiguration & PPL$\\downarrow$ & $\\Delta$ from Ours \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textit{KL-based variants}} \\\\\nForward KL + Gumbel (Ours) & \\textbf{11.79} & --- \\\\ % exp_id: bench_kl50_global\nJSD (symmetric) + Gumbel & 12.54 & +0.75 \\\\ % exp_id: jsd_ablation_s42\nReverse KL + Gumbel & 12.80 & +1.01 \\\\ % exp_id: reverse_kl_ablation_s42\nForward KL + STE & 15.77 & +3.98 \\\\ % exp_id: ste_baseline_s42\n\\midrule\n\\multicolumn{3}{l}{\\textit{BCE-based variants}} \\\\\nBCE + Compensation (hard mask) & 25.44 & +13.65 \\\\ % exp_id: bce_comp_staged_s42\nBCE (no compensation) & 27.97 & +16.18 \\\\ % exp_id: eval_bce_v3_s42\nBCE + Gumbel (no penalty) & 32.22 & +20.43 \\\\ % exp_id: bce_gumbel_no_penalty_s42\nBCE + Gumbel + Penalty & 38.02 & +26.23 \\\\ % exp_id: bce_gumbel_lagrangian_isolation\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Gumbel vs.\\ STE.}\nReplacing Gumbel-Sigmoid with STE~\\cite{bengio2013ste} degrades PPL from 11.79 to 15.77 (+3.98). % exp_id: ste_baseline_s42\n\n\\paragraph{Divergence Direction.}\nForward KL outperforms JSD (+6.4\\%) and reverse KL (+8.6\\%), consistent with the SNR analysis (\\S\\ref{sec:method:gradient}); mode-covering ensures no important neuron is omitted, contrasting with reverse-KL generation~\\cite{gu2024minillm}. % exp_id: jsd_ablation_s42, reverse_kl_ablation_s42\n\n\\paragraph{SPON Contribution.}\nAdding SPON~\\cite{xu2026spon} bias correction reduces PPL from 12.08 to 11.79 (2.4\\% relative; Appendix~\\ref{app:spon}). % exp_id: spon_2048_s42, mvp_kl_norm_v2_s42\n\n\\paragraph{Loss Function Isolation.}\nRemoving the penalty from BCE+Gumbel improves PPL (32.22 vs.\\ 38.02), partly due to a sparsity gap (38.3\\% training vs.\\ 50\\% target), but remains $2.7\\times$ worse than KL (11.79) and worse than vanilla BCE at matched 50\\% sparsity (27.97): Gumbel relaxation does not benefit BCE regardless of sparsity control, and KL's advantage stems from the loss function itself. % exp_id: bce_gumbel_no_penalty_s42, bce_gumbel_lagrangian_isolation, eval_bce_v3_s42\nThe loss effect ($\\Delta$PPL=20.43) is $5.1\\times$ the relaxation effect ($\\Delta$PPL=3.98).\n\n\\paragraph{Compensation Redundancy.}\nAdding compensation~\\cite{gautam2026fastforward} (+67.2M params) to KL provides no benefit at either sparsity level (PPL 8.97 vs.\\ 8.96 at 30\\%, identical at 50\\%; Appendix~\\ref{app:comp_convergence}). BCE requires compensation (27.97$\\to$25.44), yet remains $2.16\\times$ worse than KL without it. % exp_id: kl_comp_30_s42, kl_comp_30_s456, kl_comp_50_s42, bce_comp_staged_s42\n\n\\paragraph{Hyperparameter Robustness.}\nAppendix~\\ref{app:db_sensitivity} confirms robustness to predictor capacity ($d_b$, $<$3\\%), temperature ($<$1.8\\%), and training steps (saturated by 800). % exp_id: db_sensitivity_sweep, tau_schedule_sweep, training_steps_sweep\n\n\n\\subsection{Sparsity Scaling and Regime Analysis}\n\\label{sec:scaling}\n\nFigure~\\ref{fig:sparsity_sweep} shows PPL as a function of sparsity for the KL predictor under global allocation.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig2_sparsity_sweep.pdf}\n\\caption{Perplexity scaling with sparsity. The KL predictor's advantage grows disproportionately as more neurons are pruned.}\n\\label{fig:sparsity_sweep}\n\\end{figure}\n\nThe regime curve (Figure~\\ref{fig:sparsity_sweep}) is strictly monotonic from PPL 8.17 at 25\\% to 11.80 at 50\\% (global, seed 42), with KL/Dense degradation ranging from $1.34\\times$ to $1.93\\times$.\nAt matched points, KL improves over TEAL by 18\\% at 30\\% and 49\\% at 50\\%; at 70\\%, where TEAL collapses (PPL 100.11), the advantage reaches 82\\%. % exp_id: regime_kl25_global, regime_kl50_global, kl_70_global_teal\n\n\\paragraph{Allocation Behavior Across Sparsity Levels.}\nTable~\\ref{tab:phase} compares global vs.\\ uniform allocation at representative sparsity levels, revealing qualitative shifts in preference.\n\n\\begin{table}[t]\n\\centering\n\\caption{Allocation analysis at key sparsity levels (LLaMA-3.1-8B, PPL and MMLU; full 6-level data with all downstream metrics in Appendix~\\ref{app:alloc_full}). $\\pm$: 3-seed; others: seed 42. $^\\ast$High seed variance (25.3--43.5\\%).}\n\\label{tab:phase}\n\\footnotesize\n\\begin{tabular}{llcc}\n\\toprule\nSparsity & Allocation & PPL$\\downarrow$ & MMLU \\\\\n\\midrule\n\\multirow{2}{*}{25\\%}\n& Global & \\textbf{8.17} & \\textbf{46.6} \\\\ % exp_id: regime_kl25_global\n& Uniform & 8.23 & 44.0 \\\\ % exp_id: regime_kl25_uniform\n\\midrule\n\\multirow{2}{*}{30\\%}\n& Global & 8.96$\\pm$0.02 & 35.7$\\pm$9.5$^\\ast$ \\\\ % exp_id: kl30_3seed_global\n& Uniform & \\textbf{8.81$\\pm$0.02} & \\textbf{40.7$\\pm$1.3} \\\\ % exp_id: bench_kl30_uniform\n\\midrule\n\\multirow{2}{*}{35\\%}\n& Global & \\textbf{9.31} & \\textbf{40.4} \\\\ % exp_id: regime_kl35_global\n& Uniform & 9.44 & 37.8 \\\\ % exp_id: regime_kl35_uniform\n\\midrule\n\\multirow{2}{*}{50\\%}\n& Global & \\textbf{11.79} & \\textbf{28.1$\\pm$0.2} \\\\ % exp_id: multi_seed_kl50_global\n& Uniform & 11.92$\\pm$0.07 & 28.0$\\pm$0.6 \\\\ % exp_id: multi_seed_kl50_uniform\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe analysis reveals \\emph{non-monotonic} allocation preference with three regimes, complementing OWL's~\\cite{yin2024owl} finding that non-uniform layerwise budgets improve pruning quality (full 6-level data in Appendix~\\ref{app:alloc_full}):\n\n\\noindent\\textbf{Budget-surplus ($\\leq$30\\%).}\nAt 25\\%, PPL differs by only 0.06. At 30\\%, uniform achieves PPL 8.81$\\pm$0.02 (3-seed) with $7.5\\times$ smaller cross-seed MMLU $\\sigma$ (1.3pp vs.\\ 9.5pp). % exp_id: regime_kl25_global, regime_kl25_uniform, kl30_3seed\n\n\\noindent\\textbf{Budget-constrained (35--40\\%).}\nGlobal becomes preferable: at 35\\%, MMLU 40.4\\% vs.\\ 37.8\\% (+2.6pp); at 40\\%, MMLU 38.1\\% (Appendix~\\ref{app:alloc_full}). % exp_id: regime_kl35_global, regime_kl35_uniform, regime_kl40_global\n\n\\noindent\\textbf{Capacity-limited ($\\geq$45\\%).}\nGap vanishes for reasoning: at 50\\%, MMLU collapses to near-random under both strategies (28.1 vs.\\ 28.0\\%), though global still helps non-reasoning tasks (HellaSwag +2.29pp; Appendix~\\ref{app:downstream}). Late-layer starvation persists (Figure~\\ref{fig:retention}; Appendix~\\ref{app:retention}). % exp_id: multi_seed_kl50_global, multi_seed_kl50_uniform, hellaswag_piqa_kl50_global, hellaswag_piqa_kl50_uniform\n\n\n\\paragraph{Cross-Architecture and Scale.}\n\\label{sec:cross_arch}\nOn Mistral-7B-v0.3~\\cite{jiang2023mistral}, KL outperforms TEAL on 5 of 6 downstream\ntasks at 30\\% (HellaSwag +8.8pp, ARC +9.0pp, WG +5.6pp, PIQA +3.1pp, MMLU +0.6pp),\nwith PPL 6.77 vs.\\ 8.38; GSM8K is the sole reversal (11.1\\% vs.\\ 15.9\\%,\nTable~\\ref{tab:mistral_downstream}); the 50\\% capacity cliff also holds cross-architecture (MMLU 26.4\\%$\\approx$random; Appendix~\\ref{app:cross_arch}). % exp_id: mistral_kl30_downstream, mistral_teal30_downstream, mistral_teal50_downstream\nOn Qwen-2.5-14B~\\cite{qwen2024qwen25}, KL's PPL advantage generalizes at 30\\% ($1.47\\times$ dense) but MMLU falls to 63.7\\% vs.\\ TEAL's 71.8\\% ($-$8.1pp; Appendix~\\ref{app:14b}); this reversal is absent at 7B on both architectures.\nPer-layer mask divergence identifies a structural difference consistent with this reversal: despite similar mean Jaccard ($\\sim$0.40), 14B variance is $2.4\\times$ that of 8B (std 0.076 vs.\\ 0.031), with an early-layer convergence zone (L3--L6, min 0.063 at L4) absent in LLaMA-8B (min 0.353).\nThis suggests KL's PPL-optimal reallocation redirects resources from early knowledge-encoding layers toward mid-to-late layers, conflicting with factual recall.\nVerification requires layer-wise probing beyond our current scope. % exp_id: qwen14b_kl30_s42, qwen14b_teal30_eval, qwen14b_bce30_s42_eval\n\\paragraph{Inference Efficiency.}\n\\label{sec:overhead}\nThe predictor adds 3.17\\,ms (2.7\\% overhead) using 75.96M params (0.9\\% of base), eliminating BCE's 67.2M compensation network; actual speedup requires sparse kernel integration (Appendix~\\ref{app:latency}). % exp_id: latency_profiling\n\n",
      "numLines": 240,
      "startLine": 1,
      "totalLines": 240
    }
  }
}
```

</details>

---

### Tool call

_source line 10_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01GFkcruPJhktwQ8nbGMiy8S`</summary>

```json
{
  "project": "distill_sparse_swiglu",
  "filters": {
    "status": "DONE"
  },
  "fields": [
    "exp_id",
    "status",
    "metrics",
    "conclusion",
    "config"
  ],
  "limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "db551d23-cf59-40a6-bdc0-313c3d0a13a2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01G3zN7mkp9ru1hxY9dbMtqg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1093,
      "cache_read_input_tokens": 25993,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1093
      },
      "output_tokens": 38,
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

_source line 11 · 2026-05-19T08:22:32.265Z_

<details><summary>↩ Tool result · `toolu_01GFkcruPJhktwQ8nbGMiy8S`</summary>

```text
Error: result (57,404 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "57be5d63-1fa2-471e-bb94-6ac2c135fd3b",
  "tool_use_result": {
    "content": "Error: result (57,404 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"teal_28.5pct_sanity\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 10.3}, \"conclusion\": \"success\"}, \"mistral_dense_hellaswag_piqa\": {\"status\": \"DONE\", \"metrics\": {\"hellaswag_acc_norm\": 0.832, \"piqa_acc_norm\": 0.8188}, \"conclusion\": \"success\"}, \"bce_gumbel_no_penalty_s42\": {\"status\": \"DONE\", \"metrics\": {\"training_bce_loss\": 0.6307, \"training_sparsity\": 0.383, \"wikitext2_ppl\": 32.22, \"training_time_seconds\": 977.6}, \"conclusion\": \"success\"}, \"qwen14b_mask_divergence_analysis\": {\"status\": \"DONE\", \"metrics\": {\"qwen14b_mean_jaccard\": 0.4016, \"qwen14b_std_jaccard\": 0.0756, \"qwen14b_max_jaccard\": 0.446, \"qwen14b_max_layer\": 11, \"qwen14b_min_jaccard\": 0.0627, \"qwen14b_min_layer\": 4, \"llama8b_mean_jaccard\": 0.3939, \"llama8b_std_jaccard\": 0.0314, \"llama8b_max_jaccard\": 0.4818, \"llama8b_max_layer\": 0, \"llama8b_min_jaccard\": 0.3528, \"llama8b_min_layer\": 14}, \"conclusion\": \"success\"}, \"mistral_kl30_hellaswag_piqa\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"hellaswag_acc_norm\": 0.6892, \"piqa_acc_norm\": 0.7519}}, \"eval_c1_retrain_30pct_s456\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.82, \"arc_challenge_acc_norm\": 0.4471, \"winogrande_acc\": 0.6993, \"mmlu_acc\": 0.4104, \"gsm8k_exact_match\": 0.066}, \"conclusion\": \"success\"}, \"eval_c1_retrain_30pct_s123\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.84, \"arc_challenge_acc_norm\": 0.4471, \"winogrande_acc\": 0.6977, \"mmlu_acc\": 0.3992, \"gsm8k_exact_match\": 0.0682}, \"conclusion\": \"success\"}, \"c1_retrain_30pct_s456\": {\"status\": \"DONE\", \"metrics\": {\"training_agreement\": 0.977, \"training_sparsity\": 0.312, \"wikitext2_ppl\": 7.38, \"actual_sparsity\": 0.346}, \"conclusion\": \"success\"}, \"c1_retrain_30pct_s123\": {\"status\": \"DONE\", \"metrics\": {\"training_agreement\": 0.977, \"training_sparsity\": 0.31, \"wikitext2_ppl\": 7.54, \"actual_sparsity\": 0.332}, \"conclusion\": \"success\"}, \"mistral_teal50_downstream\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 18.3061, \"arc_challenge_acc_norm\": 0.2457, \"winogrande_acc\": 0.5091, \"mmlu_acc\": 0.2635, \"gsm8k_exact_match\": 0.0341, \"hellaswag_acc_norm\": 0.3603, \"piqa_acc_norm\": 0.6045}, \"conclusion\": \"success\"}, \"mistral_teal30_downstream\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.3807, \"arc_challenge_acc_norm\": 0.4113, \"winogrande_acc\": 0.6354, \"mmlu_acc\": 0.4348, \"gsm8k_exact_match\": 0.1592, \"hellaswag_acc_norm\": 0.6011, \"piqa_acc_norm\": 0.7214}, \"conclusion\": \"success\"}, \"c1_ablation_30pct_s456\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.84, \"mmlu_acc\": 0.367, \"winogrande_acc\": 0.6938}, \"conclusion\": \"success\"}, \"c1_ablation_30pct_s123\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.83, \"mmlu_acc\": 0.3833, \"winogrande_acc\": 0.7119}, \"conclusion\": \"success\"}, \"mistral_kl30_downstream\": {\"status\": \"DONE\", \"metrics\": {\"arc_challenge_acc_norm\": 0.5017, \"winogrande_acc\": 0.6914, \"mmlu_acc\": 0.4404, \"gsm8k_exact_match\": 0.1114}, \"conclusion\": \"success\"}, \"bce_50pct_teal_global_unified\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 27.97, \"arc_challenge_acc_norm\": 0.2765, \"winogrande_acc\": 0.5162, \"mmlu_acc\": 0.2614, \"gsm8k_exact_match\": 0.019}, \"conclusion\": \"success\"}, \"bce_isocompute_hellaswag_piqa_v2\": {\"status\": \"DONE\", \"metrics\": {\"hellaswag_acc_norm\": 0.6281, \"piqa_acc_norm\": 0.7421}, \"conclusion\": \"success\"}, \"c1_ablation_30pct_eval_34887\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"kl30_uniform_hellaswag_piqa\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"hellaswag_acc_norm\": 0.7085, \"piqa_acc_norm\": 0.7481, \"note\": \"from v2 retry\"}}, \"kl50_global_hellaswag_piqa\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"hellaswag_acc_norm\": 0.5895, \"piqa_acc_norm\": 0.6948, \"note\": \"from v2 retry\"}}, \"kl50_uniform_hellaswag_piqa\": {\"status\": \"DONE\", \"metrics\": {\"hellaswag_acc_norm\": 0.5666, \"piqa_acc_norm\": 0.691}, \"conclusion\": \"success\"}, \"c1_ablation_30pct_s42_eval_v2\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 9.4463, \"arc_challenge_acc_norm\": 0.4027, \"winogrande_acc\": 0.674, \"mmlu_acc\": 0.4229, \"gsm8k_exact_match\": 0.0758}, \"conclusion\": \"success\"}, \"c1_ablation_30pct_s42_v2\": {\"status\": \"DONE\", \"metrics\": {\"agreement\": 0.975}, \"conclusion\": \"success\"}, \"dense_baseline_hellaswag_piqa\": {\"status\": \"DONE\", \"metrics\": {\"hellaswag_acc_norm\": 0.8235, \"piqa_acc_norm\": 0.809}, \"conclusion\": \"success\"}, \"bce_isocompute_hellaswag_piqa\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"c1_ablation_30pct_s42_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"kl50_global_hellaswag_piqa_v2\": {\"status\": \"DONE\", \"metrics\": {\"hellaswag_acc_norm\": 0.5895, \"piqa_acc_norm\": 0.6948}, \"conclusion\": \"success\"}, \"kl30_uniform_hellaswag_piqa_v2\": {\"status\": \"DONE\", \"metrics\": {\"hellaswag_acc_norm\": 0.7085, \"piqa_acc_norm\": 0.7481}, \"conclusion\": \"success\"}, \"kl30_s42_global_mmlu_recheck\": {\"status\": \"DONE\", \"metrics\": {\"mmlu_acc\": 0.2527, \"mmlu_stderr\": 0.00364}, \"conclusion\": \"success\"}, \"c1_ablation_30pct_s42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"kl30_s456_global_v3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.9332, \"arc_challenge_acc_norm\": 0.4633, \"winogrande_acc\": 0.7111, \"mmlu_acc\": 0.4382, \"gsm8k_exact_match\": 0.0758, \"actual_sparsity\": 0.3, \"allocation\": \"global_topk\"}}, \"kl30_s123_global_v3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.9748, \"arc_challenge_acc_norm\": 0.4531, \"winogrande_acc\": 0.693, \"mmlu_acc\": 0.3807, \"gsm8k_exact_match\": 0.0758, \"actual_sparsity\": 0.3, \"allocation\": \"global_topk\"}}, \"kl30_s456_uniform_v3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.7947, \"arc_challenge_acc_norm\": 0.4505, \"winogrande_acc\": 0.6875, \"mmlu_acc\": 0.4198, \"gsm8k_exact_match\": 0.0758, \"actual_sparsity\": 0.3, \"allocation\": \"uniform\", \"eval_wall_time_sec\": 2325.3}}, \"kl30_s123_uniform_v3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.8308, \"arc_challenge_acc_norm\": 0.4531, \"winogrande_acc\": 0.6938, \"mmlu_acc\": 0.3944, \"gsm8k_exact_match\": 0.0751, \"actual_sparsity\": 0.3, \"allocation\": \"uniform\", \"eval_wall_time_sec\": 2157.6}}, \"wallclock_speedup_30_50\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"dense_tok_s_bs1\": 17308.5, \"dense_tok_s_bs8\": 15636.6, \"kl30_tok_s_bs1\": 16089.2, \"kl30_tok_s_bs8\": 14697.4, \"kl50_tok_s_bs1\": 16056.8, \"kl50_tok_s_bs8\": 14756.8, \"overhead_bs1_30pct\": \"7%\", \"overhead_bs1_50pct\": \"7%\", \"overhead_bs8_30pct\": \"6%\", \"overhead_bs8_50pct\": \"6%\", \"predictor_latency_bs1_ms\": 3.2, \"predictor_latency_bs8_ms\": 14.4, \"note\": \"mask-and-multiply only, no sparse kernel. Memory identical across conditions.\"}}, \"kl_sparsity35_s42_eval_teal_uniform\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 9.4416, \"arc_challenge_acc_norm\": 0.3874, \"winogrande_acc\": 0.6654, \"mmlu_acc\": 0.3783, \"gsm8k_exact_match\": 0.0432, \"actual_sparsity\": 0.35, \"allocation\": \"uniform\"}}, \"kl_sparsity25_s42_eval_teal_uniform\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.2344, \"arc_challenge_acc_norm\": 0.465, \"winogrande_acc\": 0.7182, \"mmlu_acc\": 0.4395, \"gsm8k_exact_match\": 0.1099, \"actual_sparsity\": 0.25, \"allocation\": \"uniform\"}}, \"kl_sparsity25_s42_eval_teal\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.169, \"arc_challenge_acc_norm\": 0.4539, \"winogrande_acc\": 0.7056, \"mmlu_acc\": 0.466, \"gsm8k_exact_match\": 0.1145, \"actual_sparsity\": 0.23, \"allocation\": \"global_topk\"}}, \"c1_ablation_bce_kl_targets_s123_v2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.0537, \"ppl\": 9.32, \"sparsity\": 0.615, \"agreement\": 0.979, \"note\": \"Consistent with s42 (PPL=9.29, sparsity=0.609, agreement=0.978). Both seeds converge to ~61% eval sparsity. C1 confirmed multi-seed robust.\"}}, \"kl_sparsity45_s42_eval_teal_uniform\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 10.9488, \"arc_challenge_acc_norm\": 0.3763, \"winogrande_acc\": 0.6361, \"mmlu_acc\": 0.3063, \"gsm8k_exact_match\": 0.0273, \"actual_sparsity\": 0.45, \"allocation\": \"uniform\"}}, \"kl_sparsity45_s42_eval_teal\": {\"status\": \"DONE\", \"metrics\": {\"ppl_wikitext2\": 10.803, \"arc_challenge_acc\": 0.3498, \"arc_challenge_acc_norm\": 0.3916, \"winogrande_acc\": 0.6464, \"mmlu_acc\": 0.3037, \"gsm8k_exact_match\": 0.0296, \"actual_sparsity\": 0.449}, \"conclusion\": \"success\"}, \"kl_sparsity35_s42_eval_teal\": {\"status\": \"DONE\", \"metrics\": {\"ppl_wikitext2\": 9.3133, \"arc_challenge_acc\": 0.3643, \"arc_challenge_acc_norm\": 0.3891, \"winogrande_acc\": 0.6764, \"mmlu_acc\": 0.4041, \"gsm8k_exact_match\": 0.0773, \"actual_sparsity\": 0.336}, \"conclusion\": \"success\"}, \"bce_30pct_s42_eval\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 11.2445, \"arc_challenge_acc\": 0.3848, \"arc_challenge_acc_norm\": 0.4121, \"winogrande_acc\": 0.6598, \"mmlu_acc\": 0.3633, \"gsm8k_exact_match\": 0.0599, \"gsm8k_exact_match_strict\": 0.0538, \"sparsity_target\": 0.3, \"allocation\": \"global_topk\", \"training_sparsity_native\": 0.042, \"eval_wall_time_sec\": 2275.8}, \"conclusion\": \"negative\"}, \"c1_ablation_bce_kl_targets_s123\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"ppl\": 11.71, \"sparsity\": 0.5, \"agreement\": 0.834, \"bce_loss\": 0.448, \"note\": \"BCE+KL-targets PPL=11.71 ≈ KL PPL=11.79 at matched 50% sparsity, confirming target quality as primary driver\"}}, \"kl_sparsity25_s123\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.153, \"final_sparsity\": 0.23, \"steps\": 1000}}, \"kl_sparsity35_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.203, \"final_sparsity\": 0.336, \"steps\": 1000}}, \"kl_sparsity45_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.33, \"final_sparsity\": 0.449, \"steps\": 1000}}, \"c1_ablation_eval_uniform\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 11.9638, \"arc_challenge_acc_norm\": 0.3217, \"winogrande_acc\": 0.6314, \"mmlu_acc\": 0.2779, \"gsm8k_exact_match\": 0.0205, \"sparsity_target\": 0.5, \"allocation\": \"uniform\"}}, \"c1_ablation_bce_kl_targets_s42\": {\"status\": \"DONE\", \"metrics\": {\"wt2_ppl\": 9.29, \"eval_sparsity\": 0.609, \"oracle_agreement\": 0.978, \"final_bce_loss\": 0.0545, \"train_steps\": 1000, \"train_time_sec\": 877.1, \"reference_kl_ppl\": 11.79, \"reference_bce_ppl\": 22.51}, \"conclusion\": \"success\"}, \"kl_sparsity25_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss_final\": 0.1582, \"kl_normalized_final\": 0.1582, \"sparsity_actual\": 0.23, \"sparsity_target\": 0.25, \"lambda_final\": 5000, \"tau_final\": 0.1, \"steps\": 1000}}, \"bce_30pct_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"kl30_s456_uniform_v2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.8284, \"arc_challenge_acc_norm\": 0.4505, \"winogrande_acc\": 0.6953, \"mmlu_acc\": 0.3727, \"gsm8k_exact_match\": 0.0705}}, \"kl30_s123_uniform_v2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.8186, \"arc_challenge_acc_norm\": 0.471, \"winogrande_acc\": 0.6961, \"mmlu_acc\": 0.3763, \"gsm8k_exact_match\": 0.0705}}, \"kl50_s42_global_eval\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 11.8038, \"arc_challenge_acc_norm\": 0.3336, \"winogrande_acc\": 0.6338, \"mmlu_acc\": 0.2819, \"gsm8k_exact_match\": 0.0167}, \"conclusion\": \"success\"}, \"kl_comp_50pct_s42_eval\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 11.7933, \"arc_challenge_acc_norm\": 0.3285, \"winogrande_acc\": 0.6346, \"mmlu_acc\": 0.2789, \"gsm8k_exact_match\": 0.0129}, \"conclusion\": \"success\"}, \"kl_comp_30pct_s456_eval\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.9614, \"arc_challenge_acc_norm\": 0.4462, \"winogrande_acc\": 0.7143, \"mmlu_acc\": 0.2714, \"gsm8k_exact_match\": 0.0887}, \"conclusion\": \"success\"}, \"kl50_s456_uniform_eval\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 11.9538, \"arc_challenge_acc_norm\": 0.3831, \"winogrande_acc\": 0.6196, \"mmlu_acc\": 0.275, \"gsm8k_exact_match\": 0.0288}, \"conclusion\": \"success\"}, \"kl_comp_30pct_s123_eval\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.9788, \"arc_challenge_acc_norm\": 0.3993, \"winogrande_acc\": 0.6898, \"mmlu_acc\": 0.2531, \"gsm8k_exact_match\": 0.0842}, \"conclusion\": \"success\"}, \"kl_comp_50pct_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"kl_comp_30pct_s456\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"kl50_s42_uniform_eval\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 11.9638, \"arc_challenge_acc_norm\": 0.3259, \"winogrande_acc\": 0.6235, \"mmlu_acc\": 0.2792, \"gsm8k_exact_match\": 0.0197}, \"conclusion\": \"success\"}, \"kl_comp_30pct_s42_eval\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.9788, \"arc_challenge_acc_norm\": 0.3993, \"winogrande_acc\": 0.6898, \"mmlu_acc\": 0.2531, \"gsm8k_exact_match\": 0.0842}, \"conclusion\": \"success\"}, \"kl_comp_30pct_s123_ppl\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.9768, \"c4_ppl\": 16.0401, \"sparsity\": 0.3, \"allocation\": \"global_topk\", \"model\": \"llama-3.1-8b\", \"seed\": 123}, \"conclusion\": \"success\"}, \"kl_comp_30pct_s123\": {\"status\": \"DONE\", \"metrics\": {\"final_loss\": 0.7617, \"steps\": 1000, \"compensation_params\": 67248128, \"compensation_pct\": 0.837, \"mean_head_norm_final\": 9.2012, \"loss_trajectory\": [2.0469, 1.3828, 1.0703, 0.9609, 0.8711, 0.7305, 0.6875, 0.7773, 0.7969, 0.7617]}, \"conclusion\": \"success\"}, \"kl_comp_30pct_s42_ppl\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.9768, \"c4_ppl\": 16.0401, \"sparsity\": 0.3, \"allocation\": \"global_topk\", \"model\": \"llama-3.1-8b\", \"seed\": 42}, \"conclusion\": \"success\"}, \"kl_comp_30pct_s42\": {\"status\": \"DONE\", \"metrics\": {\"final_loss\": 0.6992, \"steps\": 1000, \"compensation_params\": 67248128, \"compensation_pct\": 0.837, \"mean_head_norm_final\": 9.2012, \"loss_trajectory\": [2.3594, 1.3516, 1.0859, 0.9219, 0.8789, 0.8281, 0.7461, 0.7344, 0.6953, 0.6992]}, \"conclusion\": \"success\"}, \"c4_ood_kl50_s456\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"c4_ppl\": 23.9867, \"sparsity\": 0.5, \"allocation\": \"global_topk\", \"seed\": 456}}, \"c4_ood_kl50_s42\": {\"status\": \"DONE\", \"metrics\": {\"c4_ppl\": 23.5297, \"sparsity\": 0.5, \"allocation\": \"global_topk\", \"seed\": 42}, \"conclusion\": \"success\"}, \"kl50_s456_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 11.8614, \"arc_challenge_acc_norm\": 0.3754, \"winogrande_acc\": 0.6417, \"mmlu_acc\": 0.2784, \"gsm8k_exact_match\": 0.0212}}, \"c4_ood_kl30_s456\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"c4_ood_kl30_s42_v2\": {\"status\": \"DONE\", \"metrics\": {\"c4_ppl\": 16.0401, \"allocation\": \"global_topk\", \"sparsity\": 0.3, \"model\": \"llama-3.1-8b\", \"seed\": 42}, \"conclusion\": \"success\"}, \"c4_ood_kl50_s123\": {\"status\": \"DONE\", \"metrics\": {\"c4_ppl\": 23.6064, \"allocation\": \"global_topk\", \"sparsity\": 0.5, \"model\": \"llama-3.1-8b\"}, \"conclusion\": \"success\"}, \"downstream_ext_kl50_uniform_s42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"downstream_ext_kl30_uniform_s123\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"c4_ood_dense_baseline_v2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"c4_ppl\": 9.2075, \"model\": \"llama-3.1-8b\", \"eval_sequences\": 132, \"seq_len\": 2048}}, \"c4_ood_kl30_s123_v2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"c4_ppl\": 16.0259, \"allocation\": \"global_topk\", \"sparsity\": 0.3, \"model\": \"llama-3.1-8b\", \"eval_sequences\": 132, \"seq_len\": 2048}}, \"kl50_s456_train\": {\"status\": \"DONE\", \"metrics\": {\"final_loss\": 0.397, \"final_kl_normalized\": 0.397, \"final_sparsity\": 0.492, \"final_lambda\": 5000, \"final_tau\": 0.1, \"steps_completed\": 1000}, \"conclusion\": \"success\"}, \"kl50_s123_uniform_eval\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 11.89, \"arc_challenge_acc_norm\": 37.88, \"winogrande_acc\": 62.19, \"mmlu_acc\": 27.75, \"gsm8k_exact_match\": 2.35, \"comparison_vs_global_topk\": {\"ppl_delta\": -0.94, \"arc_c_delta\": -5.55, \"wg_delta\": -6.71, \"mmlu_delta\": -8.2, \"gsm8k_delta\": -5}, \"note\": \"Uniform allocation: better PPL but catastrophic downstream degradation vs global_topk. Confirms global_topk allocation is critical for downstream quality.\"}, \"conclusion\": \"success\"}, \"c4_ood_kl30_s123\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"c4_ood_dense_baseline\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"kl50_s123_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 11.745, \"arc_challenge\": 0.3814, \"winogrande\": 0.6125, \"mmlu\": 0.2752, \"gsm8k\": 0.0281}}, \"snr_extended_r6w3\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"kl_snr_step300\": 0.0058773, \"bce_snr_step300\": 0.00114449, \"snr_ratio_step300\": 5.14, \"kl_train_time_s\": 641, \"bce_train_time_s\": 320, \"num_checkpoints\": 7, \"steps_range\": \"0-300\"}}, \"kl30_8b_s456_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.9614, \"arc_challenge_acc\": 0.436, \"arc_challenge_acc_norm\": 0.4462, \"winogrande_acc\": 0.7143, \"mmlu_acc\": 0.2714, \"gsm8k_exact_match\": 0.0887}}, \"kl30_8b_s123_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.9267, \"arc_challenge_acc\": 0.4462, \"arc_challenge_acc_norm\": 0.4744, \"winogrande_acc\": 0.7024, \"mmlu_acc\": 0.3836, \"gsm8k_exact_match\": 0.0917}}, \"bce_isocompute_v3_s42_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 27.9696, \"arc_challenge_acc\": 0.2346, \"arc_challenge_acc_norm\": 0.2765, \"winogrande_acc\": 0.5162, \"mmlu_acc\": 0.2614, \"gsm8k_exact_match\": 0.019}}, \"qwen14b_kl30_uniform_eval_4task\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 7.63, \"mmlu_acc\": 0.6449, \"arc_challenge_acc_norm\": 0.5444, \"winogrande_acc\": 0.7245}, \"conclusion\": \"negative\"}, \"qwen14b_teal30_uniform_eval_4task\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.01, \"mmlu_acc\": 0.6634, \"arc_challenge_acc_norm\": 0.5529, \"winogrande_acc\": 0.6985}, \"conclusion\": \"success\"}, \"kl30_8b_s456_train\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.9614, \"sparsity\": 0.3, \"training_loss\": 0.148}}, \"kl30_8b_s123_train\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.9267, \"sparsity\": 0.3, \"training_loss\": 0.147}}, \"qwen14b_teal30_uniform_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"qwen14b_kl30_uniform_eval\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"c4_ood_kl30_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"c4_ppl\": 16.0458, \"allocation\": \"global_topk\", \"sparsity\": 0.3, \"model\": \"llama-3.1-8b\", \"eval_sequences\": 132, \"seq_len\": 2048}}, \"qwen14b_teal30_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.7332, \"arc_challenge_acc_norm\": 0.5683, \"winogrande_acc\": 0.7269, \"mmlu_acc\": 0.7183, \"gsm8k_exact_match\": 0.4951}}, \"qwen14b_bce30_s42_eval\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.7634, \"arc_challenge_acc_norm\": 0.5759, \"winogrande_acc\": 0.7261, \"mmlu_acc\": 0.7167, \"gsm8k_exact_match\": 0.5307}, \"conclusion\": \"negative\"}, \"qwen14b_dense_baseline\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ppl\": 5.1854, \"arc_challenge\": 0.6758, \"winogrande\": 0.8106, \"mmlu\": 0.7977, \"gsm8k\": 0.8757}}, \"bce_isocompute_v3_s123_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 28.0627, \"arc_challenge_acc_norm\": 0.2696, \"winogrande_acc\": 0.513, \"mmlu_acc\": 0.2655, \"gsm8k_exact_match\": 0.022}}, \"bce_isocompute_v3_s123\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"bce_isocompute_v3_s456_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"teal_sparse_ppl\": 28.3503, \"model_level_sparsity\": 0.5, \"arc_challenge_acc\": 0.2312, \"arc_challenge_acc_stderr\": 0.01232, \"arc_challenge_acc_norm\": 0.2807, \"arc_challenge_acc_norm_stderr\": 0.01313, \"winogrande_acc\": 0.5241, \"winogrande_acc_stderr\": 0.01404, \"mmlu_acc\": 0.2567, \"mmlu_acc_stderr\": 0.00367, \"gsm8k_exact_match\": 0.022, \"gsm8k_exact_match_stderr\": 0.00404, \"gsm8k_exact_match_strict\": 0.00834, \"gsm8k_exact_match_strict_stderr\": 0.0025}}, \"bce_isocompute_v3_s456\": {\"status\": \"DONE\", \"metrics\": {\"final_loss\": 0.6368, \"final_sparsity\": 0.51, \"training_steps\": 2700}, \"conclusion\": \"success\"}, \"qwen14b_kl30_s42_eval\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 7.6232, \"arc_challenge_acc_norm\": 0.5717, \"winogrande_acc\": 0.7206, \"mmlu_acc\": 0.6372, \"gsm8k_exact_match\": 0.4882}, \"conclusion\": \"success\"}, \"kl50_global_s123_reeval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 11.7184, \"arc_challenge_acc_norm\": 0.3635, \"winogrande_acc\": 0.6109, \"mmlu_acc\": 0.2834, \"gsm8k_exact_match\": 0.0258}}, \"downstream_teal30_baseline\": {\"status\": \"DONE\", \"metrics\": {\"hellaswag_acc\": 0.4878, \"hellaswag_acc_norm\": 0.667, \"piqa_acc\": 0.7258, \"piqa_acc_norm\": 0.7361, \"boolq_acc\": 0.685}, \"conclusion\": \"success\"}, \"kl30_s456_uniform_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"mmlu\": 0.4198, \"ppl_uniform\": 8.7947, \"arc_challenge\": 0.4505, \"winogrande\": 0.6875, \"gsm8k\": 0.0758}}, \"downstream_dense_baseline\": {\"status\": \"DONE\", \"metrics\": {\"hellaswag_acc_norm\": 0.8233, \"hellaswag_acc_norm_stderr\": 0.0038, \"piqa_acc_norm\": 0.8074, \"piqa_acc_norm_stderr\": 0.0092, \"boolq_acc\": 0.8294, \"boolq_acc_stderr\": 0.0066}, \"conclusion\": \"success\"}, \"qwen14b_bce30_s42_v2\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"predictor_native_sparsity\": 0.064, \"lambda_max\": 50000, \"final_bce_loss\": 0.5324, \"steps\": 1000, \"constraint_satisfied\": false, \"sparsity_trajectory\": \"49%→5% collapse in 50 steps, no recovery over 950 steps\", \"note\": \"10x stronger Lagrangian produces identical sparsity as v1 (lambda=5000). Confirms BCE gradient insufficiency is fundamental, not constraint strength.\"}}, \"qwen14b_bce30_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"dense_ppl\": 5.18, \"predictor_hard_mask_ppl\": 5.57, \"teal_global_ppl\": 8.76, \"ppl_ratio_hard_mask\": 1.075, \"ppl_ratio_hard_mask_note\": \"at predictor native 6.4% sparsity, not comparable to KL's 28.1%\", \"ppl_ratio_teal\": 1.69, \"actual_sparsity_teal\": 0.3, \"predictor_native_sparsity\": 0.064, \"training_log_sparsity_note\": \"Training Lagrangian failed (predictor sparsity=6.4%). Inference via TEAL forces 30% externally. TEAL PPL 8.76 is valid for method comparison.\", \"final_loss\": 0.5561, \"final_bce_loss\": 0.5324, \"steps\": 1000, \"constraint_satisfied\": false}}, \"downstream_extended_kl30_s42\": {\"status\": \"DONE\", \"metrics\": {\"hellaswag_acc_norm\": 0.727, \"hellaswag_acc\": 0.527, \"piqa_acc_norm\": 0.7595, \"piqa_acc\": 0.747, \"boolq_acc\": 0.7685}, \"conclusion\": \"success\"}, \"kl30_s123_eval\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.8308, \"arc_challenge_acc_norm\": 0.4531, \"winogrande_acc\": 0.6938, \"mmlu_acc\": 0.3944, \"gsm8k_exact_match\": 0.0751, \"actual_sparsity\": 0.3, \"allocation\": \"uniform\"}}, \"kl30_s456_train\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.2021, \"actual_sparsity\": 0.289, \"constraint_satisfied\": true, \"training_steps\": 1000}}, \"qwen14b_kl30_s42\": {\"status\": \"DONE\", \"metrics\": {\"dense_ppl\": 5.18, \"predictor_hard_mask_ppl\": 6.8, \"teal_global_ppl\": 7.62, \"ppl_ratio_hard_mask\": 1.31, \"ppl_ratio_teal\": 1.47, \"final_loss\": 0.3398, \"training_sparsity\": 0.281, \"teal_sparsity\": 0.3, \"lambda\": 5000, \"steps\": 1000}, \"conclusion\": \"success\"}, \"kl50_s456_global_eval\": {\"status\": \"DONE\", \"metrics\": {\"ppl_wikitext2\": 11.8057, \"arc_challenge\": 0.3319, \"winogrande\": 0.6488, \"mmlu\": 0.2794, \"gsm8k\": 0.0212}, \"conclusion\": \"success\"}, \"kl30_s456_global_eval\": {\"status\": \"DONE\", \"metrics\": {\"ppl_wikitext2\": 8.9332, \"arc_challenge\": 0.4633, \"winogrande\": 0.7111, \"mmlu\": 0.4382, \"gsm8k\": 0.0758}, \"conclusion\": \"success\"}, \"kl_30pct_s123\": {\"status\": \"DONE\", \"metrics\": {\"ppl_wikitext2\": 8.9748, \"arc_challenge_acc_norm\": 0.4531, \"winogrande_acc\": 0.693, \"mmlu_acc\": 0.3807, \"gsm8k_exact_match\": 0.0758, \"sparsity\": 0.3, \"allocation\": \"global\"}, \"conclusion\": \"success\"}, \"mistral_teal70_baseline\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 61.716, \"model\": \"Mistral-7B-v0.3\", \"condition\": \"teal_vanilla_70pct\", \"sparsity\": 0.7, \"allocation\": \"uniform\", \"ppl_increase_vs_dense\": 56.1922}, \"conclusion\": \"success\"}, \"mistral_teal30_baseline\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.3807, \"model\": \"Mistral-7B-v0.3\", \"condition\": \"teal_vanilla_30pct\", \"sparsity\": 0.3, \"allocation\": \"uniform\", \"ppl_increase_vs_dense\": 2.8569}, \"conclusion\": \"success\"}, \"mistral_kl70_teal_global\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 13.3254, \"model\": \"Mistral-7B-v0.3\", \"condition\": \"kl_teal_global_70pct\", \"sparsity\": 0.7, \"allocation\": \"uniform\", \"ppl_increase_vs_dense\": 7.8016}, \"conclusion\": \"success\"}, \"mistral_kl50_teal_global\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.6489, \"model\": \"Mistral-7B-v0.3\", \"condition\": \"kl_teal_global_50pct\", \"sparsity\": 0.5, \"allocation\": \"uniform\", \"ppl_increase_vs_dense\": 3.1251}, \"conclusion\": \"success\"}, \"mistral_kl30_teal_global\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 6.7733, \"model\": \"Mistral-7B-v0.3\", \"condition\": \"kl_teal_global_30pct\", \"sparsity\": 0.3, \"allocation\": \"uniform\", \"ppl_increase_vs_dense\": 1.2495}, \"conclusion\": \"success\"}, \"mistral_kl70_pertoken\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 9.1086, \"model\": \"Mistral-7B-v0.3\", \"condition\": \"kl_pertoken_70pct\", \"sparsity\": 0.7, \"allocation\": \"uniform\", \"ppl_increase_vs_dense\": 3.5848}, \"conclusion\": \"success\"}, \"mistral_kl50_pertoken\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 7.2931, \"model\": \"Mistral-7B-v0.3\", \"condition\": \"kl_pertoken_50pct\", \"sparsity\": 0.5, \"allocation\": \"uniform\", \"ppl_increase_vs_dense\": 1.7693}, \"conclusion\": \"success\"}, \"mistral_kl30_pertoken\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 6.048, \"model\": \"Mistral-7B-v0.3\", \"condition\": \"kl_pertoken_30pct\", \"sparsity\": 0.3, \"allocation\": \"uniform\", \"ppl_increase_vs_dense\": 0.5242}, \"conclusion\": \"success\"}, \"mistral_dense_ppl\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 5.5238, \"model\": \"Mistral-7B-v0.3\", \"condition\": \"dense\", \"sparsity\": 0}, \"conclusion\": \"success\"}, \"kl_50pct_s123\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ppl_wikitext2\": 11.745, \"arc_challenge_acc_norm\": 0.3814, \"winogrande_acc\": 0.6125, \"mmlu_acc\": 0.2752, \"gsm8k_exact_match\": 0.0281, \"sparsity\": 0.5, \"allocation\": \"global\"}}, \"lm_eval_mistral_dense\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"arc_challenge_acc_norm\": 0.6024, \"winogrande_acc\": 0.7869, \"mmlu_acc\": 0.6244, \"gsm8k_exact_match\": 0.3654, \"model\": \"Mistral-7B-v0.3\", \"condition\": \"dense\", \"server\": \"westd-34887\"}}, \"lm_eval_mistral_kl_50pct\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"arc_challenge_acc\": 0.2927, \"arc_challenge_acc_norm\": 0.3183, \"arc_challenge_acc_norm_stderr\": 0.0136, \"winogrande_acc\": 0.629, \"winogrande_acc_stderr\": 0.0136, \"mmlu_acc\": 0.2295, \"mmlu_acc_stderr\": 0.0035, \"mmlu_stem_acc\": 0.2125, \"mmlu_humanities_acc\": 0.2421, \"mmlu_social_sciences_acc\": 0.2171, \"mmlu_other_acc\": 0.2398, \"gsm8k_exact_match_strict\": 0.0045, \"gsm8k_exact_match_flexible\": 0.0212, \"model\": \"Mistral-7B-v0.3\", \"condition\": \"kl_distill_50pct_sparsity_s42\", \"arc_challenge_retention_vs_dense\": 0.528, \"winogrande_retention_vs_dense\": 0.799, \"mmlu_retention_vs_dense\": 0.368, \"gsm8k_retention_vs_dense\": 0.012}}, \"mistral_teal50_baseline\": {\"status\": \"DONE\", \"metrics\": {\"teal_baseline_ppl\": 18.3061, \"dense_ppl\": 5.5238, \"teal_vs_dense_ratio\": 3.31}, \"conclusion\": \"success\"}, \"kl_bce_f1_oracle\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"bce_f1\": 0.6128, \"bce_precision\": 0.6132, \"bce_recall\": 0.6124, \"kl_f1\": 0.5397, \"kl_precision\": 0.5112, \"kl_recall\": 0.5715, \"random_f1\": 0.5, \"kl_ppl\": 11.79, \"bce_ppl\": 22.51}}, \"global_30pct_retention\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"early_retention\": 0.771, \"middle_retention\": 0.764, \"knowledge_L12_20_retention\": 0.797, \"late_L24_31_retention\": 0.501, \"L31_retention\": 0.284, \"L30_retention\": 0.366, \"starved_layers\": \"L27-L31\"}}, \"reverse_kl_50pct_s42\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"ppl_wikitext2\": 12.8, \"vs_forward_kl\": \"+1.01 (+8.6%)\", \"sparsity\": 0.5}}, \"jsd_50pct_s42\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"ppl_wikitext2\": 12.54, \"vs_forward_kl\": \"+0.75 (+6.4%)\", \"sparsity\": 0.5}}, \"teal_kl_overlap_corrected\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"z_score\": 7260.3, \"p_value\": 0, \"median_percentile_rank\": 78.6, \"iqr_q1\": 64.4, \"iqr_q3\": 89.1, \"layers_significant\": \"31/32\", \"exception_layer\": 31}}, \"sparsity_floor_extended\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"floor_30pct\": 0.0499, \"floor_50pct\": 0.0726, \"floor_70pct\": 0.1936, \"late_layer_max_30\": 0.4604, \"late_layer_max_50\": 1.2347, \"late_layer_max_70\": 4.3666, \"threshold\": 0.1, \"seq_len\": 2048, \"num_samples\": 50}}, \"gradient_snr_constrained_v2\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"kl_avg_snr\": 0.000545, \"bce_avg_snr\": 5.28e-06, \"snr_ratio\": 103.2, \"kl_final_sparsity\": 0.508, \"bce_final_sparsity\": 0.591, \"steps\": 200}}, \"teal_kl_overlap_analysis\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"overall_jaccard\": 0.396, \"divergence_ratio\": 0.433, \"kl_only_pruned_magnitude_ratio\": 1.48, \"teal_only_pruned_mean_gate_prob\": 0.614, \"min_jaccard_layer\": \"L17-L18 (0.19)\", \"max_jaccard_layer\": \"L26-L28 (0.55)\"}}, \"natural_sparsity_floor_30pct\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"always_pruned_ratio\": 0.0006, \"always_pruned_count\": 278, \"total_neurons\": 458752, \"late_layer_max_ratio\": 0.0051, \"threshold\": 0.1}}, \"gradient_snr_kl_vs_bce\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"kl_avg_snr\": 5.77e-05, \"bce_avg_snr\": 1e-05, \"snr_ratio\": 5.76, \"early_layer_ratio_range\": \"34-156x\", \"late_layer_ratio_range\": \"2-4x\"}}, \"training_free_wina_greedy\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"wina_greedy_ppl\": 2126.03, \"dense_ppl\": 6.12, \"model_level_sparsity\": 0.5, \"eval_dataset\": \"WikiText-2\", \"eval_seq_len\": 2048, \"greedy_allocation_summary\": \"layers 0-11: 0.90, layer 12: 0.85, layer 13: 0.80, layer 14: 0.70, layers 15-16: 0.50-0.55, layers 17-20: 0.30-0.35, layers 21-24: 0.05-0.15, layers 25-31: 0.00\"}}, \"bench_teal70\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 100.11, \"dense_ppl\": 6.12, \"actual_sparsity\": 0.7, \"source\": \"training_free_baselines experiment (vanilla teal global)\"}, \"conclusion\": \"success\"}, \"bench_kl70_global\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 17.91, \"dense_ppl\": 6.12, \"actual_sparsity\": 0.7, \"source\": \"kl_sparsity70_s42_v2 (teal_global_masks protocol)\", \"vanilla_teal_ppl\": 100.11}, \"conclusion\": \"success\"}, \"bench_kl50_global\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 11.7933, \"arc_challenge_acc_norm\": 0.3285, \"winogrande_acc\": 0.6346, \"mmlu_acc\": 0.2789, \"gsm8k_exact_match\": 0.0129, \"actual_sparsity\": 0.5}}, \"bench_kl30_uniform\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.8157, \"arc_challenge_acc_norm\": 0.4078, \"winogrande_acc\": 0.6859, \"mmlu_acc\": 0.4061, \"gsm8k_exact_match\": 0.0735, \"actual_sparsity\": 0.3}, \"conclusion\": \"success\"}, \"eval_kl30_teal_30pct\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"dense_ppl\": 6.12, \"predictor_hard_mask_ppl\": 7.3, \"teal_sparse_ppl\": 8.98, \"sparsity_target\": 0.3, \"actual_sparsity\": 0.3}}, \"bench_dense\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 6.1173, \"arc_challenge_acc\": 0.5478, \"arc_challenge_acc_norm\": 0.5828, \"winogrande_acc\": 0.7806, \"mmlu_acc\": 0.6527, \"gsm8k_exact_match\": 0.4875}, \"conclusion\": \"success\"}, \"kl_sparsity30_s42_v2\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"final_loss\": 0.1465, \"kl_normalized\": 0.1465, \"kl_raw\": 0.1465, \"model_level_sparsity\": 0.281, \"sparsity_target\": 0.3, \"lambda_sparse_final\": 1000, \"lambda_max_cap\": 1000, \"tau_final\": 0.1, \"constraint_loss_final\": 0, \"training_steps\": 1000, \"wall_clock_seconds\": 2662.6, \"gpu_hours\": 0.74, \"note\": \"No PPL evaluation in training script. Sparsity stuck at 0.281 (same as v1). Lambda hit cap=1000 by step 220 and could not push sparsity further. W&B run was offline (not synced).\"}}, \"bce_gumbel_lagrangian_isolation\": {\"status\": \"DONE\", \"metrics\": {\"lr_1e4_ppl\": 42.99, \"lr_1e3_ppl\": 48.4, \"lr_3e3_ppl\": 38.02, \"lr_1e4_bce_loss\": 0.7158, \"lr_1e3_bce_loss\": 0.6781, \"lr_3e3_bce_loss\": 0.6632, \"lr_1e4_sparsity\": 0.514, \"lr_1e3_sparsity\": 0.506, \"lr_3e3_sparsity\": 0.504, \"best_ppl\": 38.02, \"best_lr\": \"3e-3\", \"kl_baseline_ppl\": 11.79, \"gap_vs_kl\": 26.23}, \"conclusion\": \"success\"}, \"eval_c4_ood_kl50\": {\"status\": \"DONE\", \"metrics\": {\"dense_ppl\": 9.2075, \"kl_50_global_ppl\": 18.401, \"teal_50_ppl\": 38.7503, \"kl_vs_dense_ratio\": 2, \"teal_vs_dense_ratio\": 4.21}, \"conclusion\": \"success\"}, \"longbench_kl30_uniform_v6\": {\"status\": \"DONE\", \"metrics\": {\"longbench_narrativeqa\": 4.12, \"longbench_qasper\": 6.23, \"longbench_gov_report\": 16.97, \"longbench_multi_news\": 18.01, \"runtime_seconds\": 6156.6}, \"conclusion\": \"negative\"}, \"longbench_dense_v6\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"longbench_narrativeqa\": 7.3, \"longbench_qasper\": 13.4, \"longbench_gov_report\": 30.5, \"longbench_multi_news\": 2.5}}, \"bench_kl50_uniform_s456\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 11.9604, \"arc_challenge_acc_norm\": 0.3345, \"winogrande_acc\": 0.6275, \"mmlu_acc\": 0.2874, \"gsm8k_exact_match\": 0.0212, \"actual_sparsity\": 0.5}, \"conclusion\": \"success\"}, \"bench_kl50_uniform_s123\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 11.83, \"arc_challenge_acc_norm\": 0.3515, \"winogrande_acc\": 0.6298, \"mmlu_acc\": 0.2751, \"gsm8k_exact_match\": 0.0235, \"actual_sparsity\": 0.5}, \"conclusion\": \"success\"}, \"latency_benchmark\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"gpu_model\": \"NVIDIA RTX PRO 6000 Blackwell Server Edition\", \"dtype\": \"float16\", \"attn\": \"flash_attention_2\", \"batch\": 1, \"seq_len\": 2048, \"warmup\": 10, \"iters\": 100, \"dense_ms\": 119.11, \"dense_std\": 0.57, \"dense_tokens_per_s\": 17194.5, \"kl_30pct_ms\": 126.64, \"kl_30pct_std\": 0.7, \"kl_30pct_tokens_per_s\": 16171.8, \"kl_30pct_speedup\": 0.941, \"kl_50pct_ms\": 126.78, \"kl_50pct_std\": 0.31, \"kl_50pct_tokens_per_s\": 16154.2, \"kl_50pct_speedup\": 0.939, \"comp_30pct_ms\": 129.94, \"comp_30pct_std\": 0.75, \"comp_30pct_tokens_per_s\": 15761.4, \"comp_30pct_speedup\": 0.917, \"comp_50pct_ms\": 129.71, \"comp_50pct_std\": 0.53, \"comp_50pct_tokens_per_s\": 15788.8, \"comp_50pct_speedup\": 0.918, \"predictor_overhead_ms\": 3.17, \"predictor_overhead_pct\": 2.7, \"per_layer_predictor_ms\": 0.099, \"dense_ffn_per_layer_ms\": 2.427, \"sparse_ffn_pred_per_layer_ms\": 2.686, \"compensation_overhead_ms\": 3.3}}, \"bench_kl40_global\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 10.117, \"arc_challenge_acc_norm\": 0.4096, \"winogrande_acc\": 0.6535, \"mmlu_acc\": 0.3806, \"gsm8k_exact_match\": 0.05, \"actual_sparsity\": 0.4}}, \"bench_kl50_uniform\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 11.963, \"arc_challenge_acc_norm\": 0.3276, \"winogrande_acc\": 0.629, \"mmlu_acc\": 0.2777, \"gsm8k_exact_match\": 0.0212, \"actual_sparsity\": 0.5}}, \"bench_teal50\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 23.31, \"arc_challenge_acc_norm\": 0.2841, \"winogrande_acc\": 0.5304, \"mmlu_acc\": 0.2832, \"gsm8k_exact_match\": 0.0197, \"actual_sparsity\": 0.5}}, \"bench_teal30\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 10.97, \"arc_challenge_acc_norm\": 0.4232, \"winogrande_acc\": 0.6606, \"mmlu_acc\": 0.3861, \"gsm8k_exact_match\": 0.0788, \"actual_sparsity\": 0.3}}, \"bench_kl30_global\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 8.9768, \"arc_challenge_acc_norm\": 0.3968, \"winogrande_acc\": 0.7017, \"mmlu_acc\": 0.2527, \"gsm8k_exact_match\": 0.0879, \"actual_sparsity\": 0.3}}, \"lm_eval_dense\": {\"status\": \"DONE\", \"metrics\": {\"arc_challenge_acc_norm\": 0.5819, \"winogrande_acc\": 0.7814, \"mmlu_acc\": 0.6532, \"gsm8k_exact_match\": 0.5004, \"eval_tasks\": [\"arc_challenge\", \"winogrande\", \"mmlu\", \"gsm8k\"], \"model\": \"llama-3.1-8b\", \"condition\": \"dense\", \"server\": \"westd-34887\"}, \"conclusion\": \"success\"}, \"lm_eval_kl_s42\": {\"status\": \"DONE\", \"metrics\": {\"arc_challenge_acc_norm\": 0.3771, \"winogrande_acc\": 0.6156, \"mmlu_acc\": 0.2591, \"gsm8k_exact_match\": 0.0121, \"eval_tasks\": [\"arc_challenge\", \"winogrande\", \"mmlu\", \"gsm8k\"], \"model\": \"llama-3.1-8b\", \"condition\": \"kl_sparse_50pct\", \"server\": \"westd-34887\", \"exit_code\": 129, \"wall_time_sec\": 3010, \"flag\": \"SUSPECT — gsm8k 0.50→0.01 catastrophic drop; PID 179918 rerunning with lm_eval_sparse.py\"}, \"conclusion\": \"negative\"}, \"kl_sparsity70_s42_v2\": {\"status\": \"DONE\", \"metrics\": {\"true_dense_ppl\": 6.12, \"predictor_hard_mask_ppl\": 13.84, \"predictor_teal_sparse_ppl\": 17.91, \"vanilla_teal_sparse_ppl\": 100.11, \"teal_sparse_ppl\": 17.91, \"teal_sparse_ppl_static_baseline\": 17.91, \"model_level_sparsity\": 0.7, \"teal_sparse_note\": \"17.91 = predictor-based TEAL (teal_global_masks: predictor-gated magnitude scoring + global topk @70%). vanilla TEAL @70% = 100.11. 代码来源: quick_sp70.py L10 imports teal_global_masks, L60 调用. plan_007_all_ppl_fixed.json 的 mode=static_mask_70pct metadata 有误导性.\", \"eval_dataset\": \"wikitext-2\", \"eval_seq_len\": 2048, \"calibration_samples\": 32, \"per_layer_sparsity_range\": [0.508, 0.876]}, \"conclusion\": \"success\"}, \"training_free_baselines\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"dense_ppl\": 6.12, \"vanilla_teal_global_ppl_30pct\": 10.97, \"vanilla_teal_global_ppl_50pct\": 23.31, \"vanilla_teal_global_ppl_70pct\": 100.11, \"wina_global_ppl_30pct\": 11.45, \"wina_global_ppl_50pct\": 27.93, \"wina_global_ppl_70pct\": 137.24, \"uniform_50pct_ppl\": 23.9, \"teal_greedy_ppl\": 33.47, \"vanilla_teal_global_ppl\": 23.31, \"wina_global_ppl\": 27.93, \"rsparse_global_ppl\": 151.2}}, \"bce_comp_staged_s42\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"true_dense_ppl\": 6.12, \"predictor_hard_mask_ppl\": 25.44, \"predictor_hard_mask_ppl_no_comp\": 27.96, \"teal_sparse_ppl\": 44.54, \"model_level_sparsity\": 0.558, \"ppl_increase_vs_true_dense_pct\": 315.7, \"comp_loss_final\": 0.0033, \"bce_loss_final\": 0.6379, \"eval_seq_len\": 2048, \"calibration_samples\": 32}}, \"spon_training\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"true_dense_ppl\": 6.1193, \"predictor_hard_mask_ppl\": 9.2165, \"spon_sparse_ppl\": 9.0977, \"spon_recovery_pct\": 3.8, \"ppl_improvement_from_spon\": 0.1188, \"ppl_increase_vs_true_dense_pct\": 48.7, \"ppl_increase_no_spon_vs_true_dense_pct\": 50.6, \"mean_bias_norm\": 0.040596, \"max_bias_norm\": 0.054199, \"teal_sparse_ppl\": 12.08, \"teal_with_spon_ppl\": 11.93, \"spon_dense_ppl_degradation\": 6.19, \"model_level_sparsity\": 0.5, \"eval_seq_len\": 2048, \"eval_samples\": 141, \"trainable_params\": 458752, \"trainable_pct\": 0.0057}}, \"kl_only_s1\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"true_dense_ppl\": 6.12, \"predictor_hard_mask_ppl\": 9.15, \"teal_sparse_ppl\": 11.99, \"model_level_sparsity\": 0.498, \"ppl_increase_vs_true_dense_pct\": 96}}, \"kl_only_s0\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"true_dense_ppl\": 6.12, \"predictor_hard_mask_ppl\": 9.19, \"teal_sparse_ppl\": 12.03, \"model_level_sparsity\": 0.499, \"ppl_increase_vs_true_dense_pct\": 96.57, \"eval_seq_len\": 2048, \"calibration_samples\": 32}}, \"mvp_kl_norm_v2_s456\": {\"status\": \"DONE\", \"metrics\": {\"true_dense_ppl\": 6.1173, \"predictor_hard_mask_ppl\": 9.14, \"teal_sparse_ppl\": 13.58, \"model_level_sparsity\": 0.498, \"ppl_increase_vs_true_dense_pct\": 121.9, \"eval_md5\": \"f4086818bb55dc354ea4c6fe8ed8899a\", \"calibration_samples\": 32, \"vanilla_teal_sparse_ppl_INVALID\": 66036.4062}, \"conclusion\": \"success\"}, \"mvp_kl_norm_v2_s123\": {\"status\": \"DONE\", \"metrics\": {\"true_dense_ppl\": 6.1173, \"predictor_hard_mask_ppl\": 9.2474, \"teal_sparse_ppl\": 11.9128, \"model_level_sparsity\": 0.4979, \"ppl_increase_vs_true_dense_pct\": 94.7, \"eval_md5\": \"f4086818bb55dc354ea4c6fe8ed8899a\", \"calibration_samples\": 32, \"vanilla_teal_sparse_ppl_INVALID\": 66036.4062}, \"conclusion\": \"success\"}, \"mvp_kl_norm_v2_s42\": {\"status\": \"DONE\", \"metrics\": {\"true_dense_ppl\": 6.1173, \"predictor_hard_mask_ppl\": 9.2142, \"teal_sparse_ppl\": 12.0776, \"model_level_sparsity\": 0.4979, \"ppl_increase_vs_true_dense_pct\": 97.4, \"eval_md5\": \"f4086818bb55dc354ea4c6fe8ed8899a\", \"calibration_samples\": 32, \"vanilla_teal_sparse_ppl_INVALID\": 66036.4062}, \"conclusion\": \"success\"}, \"kl_lagrangian_quicktest\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"final_kl_loss\": 418, \"final_constraint_loss\": 1.211, \"final_sparsity\": 0.141, \"final_lambda\": 5.06, \"steps\": 200, \"sparsity_trajectory\": [0.406, 0.387, 0.289, 0.168, 0.141]}}, \"mvp_bce_s456\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"true_dense_ppl\": 6.1173, \"predictor_hard_mask_ppl\": 28.1437, \"teal_sparse_ppl\": 43.033, \"model_level_sparsity\": 0.4957, \"ppl_increase_vs_true_dense_pct\": 603.3, \"eval_md5\": \"f4086818bb55dc354ea4c6fe8ed8899a\", \"calibration_samples\": 32, \"vanilla_teal_sparse_ppl_INVALID\": 66036.4062}}, \"mvp_bce_s123\": {\"status\": \"DONE\", \"metrics\": {\"true_dense_ppl\": 6.1173, \"predictor_hard_mask_ppl\": 28.3817, \"teal_sparse_ppl\": 44.5864, \"model_level_sparsity\": 0.4957, \"ppl_increase_vs_true_dense_pct\": 629, \"eval_md5\": \"f4086818bb55dc354ea4c6fe8ed8899a\", \"calibration_samples\": 32, \"vanilla_teal_sparse_ppl_INVALID\": 66036.4062}, \"conclusion\": \"success\"}, \"mvp_bce_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"true_dense_ppl\": 6.1173, \"predictor_hard_mask_ppl\": 27.9603, \"teal_sparse_ppl\": 44.537, \"model_level_sparsity\": 0.4957, \"ppl_increase_vs_true_dense_pct\": 628, \"eval_md5\": \"f4086818bb55dc354ea4c6fe8ed8899a\", \"calibration_samples\": 32, \"vanilla_teal_sparse_ppl_INVALID\": 66036.4062}}, \"mvp_kl_s42\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"final_total_loss\": 3.3438, \"final_kl_loss\": 3.2969, \"final_reg_loss\": 0.05, \"final_sparsity\": 0, \"steps\": 1000, \"tau_final\": 0.1, \"wikitext2_ppl_dense\": 6.12, \"wikitext2_ppl_sparse\": 455.93, \"wikitext2_ppl_increase_pct\": 7349, \"model_level_sparsity\": 0.372, \"checkpoint_path\": \"/root/distill_sparse_swiglu/checkpoints/mvp_kl_s42/predictor_kl.pt\"}}, \"mistral_kl70_s42\": {\"status\": \"DONE\", \"metrics\": {\"kl_per_token_ppl\": 9.1086, \"kl_teal_global_ppl\": 13.3254, \"teal_baseline_ppl\": 61.716, \"dense_ppl\": 5.5238, \"kl_advantage_ratio\": 6.77, \"final_loss\": 0.3945, \"actual_sparsity\": 0.682}, \"conclusion\": \"success\"}, \"mistral_kl30_s42\": {\"status\": \"DONE\", \"metrics\": {\"kl_per_token_ppl\": 6.048, \"kl_teal_global_ppl\": 6.7733, \"teal_baseline_ppl\": 8.3807, \"dense_ppl\": 5.5238, \"kl_advantage_ratio\": 1.386, \"ppl_vs_dense_pct\": 9.5}, \"conclusion\": \"success\"}, \"plan_005_subsumption_s42\": {\"status\": \"DONE\", \"metrics\": {\"linearity_ratio\": 0.2644, \"linearity_ratio_std\": 0.0073, \"magnitude_ratio\": 0.1578, \"magnitude_ratio_std\": 0.0088, \"cosine_similarity\": 0.1962, \"cosine_similarity_std\": 0.0268, \"predictor_effect_norm\": 482.65, \"spon_correction_norm\": 76.2, \"interaction_norm\": 147.74, \"num_samples\": 50, \"seq_len\": 2048, \"conclusion_type\": \"weak_subsumption\"}, \"conclusion\": \"success\"}, \"eval_bce_v3_s42\": {\"status\": \"DONE\", \"metrics\": {\"dense_ppl\": 6.12, \"predictor_hard_mask_ppl\": 22.51, \"teal_sparse_ppl\": 27.97, \"model_level_sparsity\": 0.5, \"arc_challenge_acc\": 0.2048, \"arc_challenge_acc_norm\": 0.2398, \"arc_challenge_acc_norm_stderr\": 0.0125, \"winogrande_acc\": 0.5059, \"winogrande_acc_stderr\": 0.0141, \"mmlu_acc\": 0.3002, \"mmlu_acc_stderr\": 0.0038, \"gsm8k_exact_match\": 0.0485, \"gsm8k_exact_match_strict\": 0.0425, \"gsm8k_exact_match_stderr\": 0.0059}, \"conclusion\": \"success\"}, \"lm_eval_teal_30pct\": {\"status\": \"DONE\", \"metrics\": {\"arc_challenge\": {\"acc\": 0.3933, \"acc_norm\": 0.4155, \"acc_stderr\": 0.0143, \"acc_norm_stderr\": 0.0144}, \"winogrande\": {\"acc\": 0.6559, \"acc_stderr\": 0.0134}, \"mmlu\": {\"acc\": 0.3598, \"acc_stderr\": 0.004}, \"mmlu_stem\": {\"acc\": 0.313}, \"mmlu_humanities\": {\"acc\": 0.3305}, \"mmlu_social_sciences\": {\"acc\": 0.4108}, \"mmlu_other\": {\"acc\": 0.401}, \"gsm8k\": {\"exact_match_strict\": 0.0849, \"exact_match_flexible\": 0.0925, \"strict_stderr\": 0.0077, \"flexible_stderr\": 0.008}, \"actual_sparsity\": 0.3}, \"conclusion\": \"negative\"}, \"lm_eval_kl_30pct_s42\": {\"status\": \"DONE\", \"metrics\": {\"arc_challenge_acc\": 0.3575, \"arc_challenge_acc_norm\": 0.3737, \"winogrande_acc\": 0.6756, \"mmlu_acc\": 0.2874, \"gsm8k_exact_match_strict\": 0.0743, \"gsm8k_exact_match_flexible\": 0.0781, \"actual_sparsity\": 0.3, \"model\": \"llama-3.1-8b\", \"condition\": \"kl_distill_30pct_sparsity_s42\", \"mmlu_stem_acc\": 0.2499, \"mmlu_social_sciences_acc\": 0.2896, \"mmlu_humanities_acc\": 0.2786, \"mmlu_other_acc\": 0.3363}, \"conclusion\": \"negative\"}, \"gsm8k_gen_compare\": {\"status\": \"DONE\", \"conclusion\": \"negative\"}, \"d030_kl40_uniform\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.3627, \"arc_challenge_acc_norm\": 0.4181, \"winogrande_acc\": 0.6717, \"mmlu_acc\": 0.3068, \"gsm8k_exact_match\": 0.0394, \"actual_sparsity\": 0.398}, \"conclusion\": \"success\"}, \"d030_kl50_uniform\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"wikitext2_ppl\": 11.96, \"arc_challenge_acc_norm\": 0.3276, \"winogrande_acc\": 0.629, \"mmlu_acc\": 0.2777, \"gsm8k_exact_match\": 0.0212, \"actual_sparsity\": 0.5, \"allocation\": \"uniform\", \"per_layer_sparsity\": \"uniform 0.500 across all 32 layers\", \"mmlu_change_vs_global\": \"+1.86pp (0.2591 → 0.2777, not significant)\", \"gsm8k_change_vs_global\": \"+0.91pp (0.0121 → 0.0212, not significant)\", \"conclusion_note\": \"50% uniform 未能修复 MMLU/GSM8K collapse. Uniform allocation 的修复效应在 50% sparsity 下消失。\"}}, \"bce_isocompute_v3_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"steps\": 2700, \"loss\": 0.6382, \"bce_loss\": 0.6371, \"reg_loss\": 0.001, \"sparsity\": 0.51, \"training_time_seconds\": 2828, \"note\": \"BCE saturation confirmed: step 500→2700 only 0.006 improvement\"}}, \"spon_2048_s42\": {\"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"true_dense_ppl\": 6.1173, \"predictor_hard_mask_ppl\": 9.2165, \"spon_sparse_ppl\": 8.991, \"spon_recovery_pct\": 7.3, \"ppl_improvement_from_spon\": 0.2255, \"mean_bias_norm\": 0.05312, \"max_bias_norm\": 0.065918, \"model_level_sparsity\": 0.498, \"eval_seq_len\": 2048, \"training_seq_len\": 2048, \"eval_samples\": 141, \"trainable_params\": 458752, \"trainable_pct\": 0.0057, \"training_steps\": 1000, \"final_loss\": 0.377, \"dense_with_spon_ppl\": 6.1823, \"dense_ppl_degradation\": 0.0651, \"teal_sparse_no_spon_ppl\": 12.0776, \"teal_sparse_with_spon_ppl\": 11.7907, \"spon_recovery_teal_pct\": 4.8, \"teal_sparsity\": 0.4979}}, \"kl_sparsity30_s42_v3\": {\"status\": \"DONE\", \"metrics\": {\"loss\": 0.165, \"kl_normalized\": 0.165, \"kl_raw\": 0.165, \"sparsity\": 0.285, \"lambda_sparse\": 5000, \"tau\": 0.1, \"constraint_loss\": 0, \"steps\": 1000, \"true_dense_ppl\": 6.12, \"predictor_hard_mask_ppl\": 7.3, \"teal_sparse_ppl\": 8.98, \"teal_sparse_ppl_note\": \"已通过 eval_kl30_teal_30pct 独立验证 (sparsity_target=0.3, D034)\", \"model_level_sparsity\": 0.3, \"eval_dataset\": \"wikitext-2\", \"eval_seq_len\": 2048}, \"conclusion\": \"success\"}, \"steps_curve_v2\": {\"status\": \"DONE\", \"metrics\": {\"step200_ppl\": 15.158, \"step400_ppl\": 12.538, \"step600_ppl\": 12.046, \"step800_ppl\": 11.907, \"step1000_ppl\": 11.906, \"convergence_step\": 800, \"ppl_800_vs_1000_delta\": 0.001}, \"conclusion\": \"success\"}, \"tau_schedule_ablation\": {\"status\": \"DONE\", \"metrics\": {\"tau_linear_baseline_ppl\": 11.963, \"tau_fixed05_ppl\": 11.861, \"tau_fixed01_ppl\": 12.072, \"tau_fixed05_loss\": 0.248, \"tau_fixed01_loss\": 0.43, \"best_tau\": \"fixed_0.5\", \"ppl_range\": 0.211}, \"conclusion\": \"success\"}, \"steps_curve_s42_v3\": {\"status\": \"DONE\", \"conclusion\": \"success\"}, \"steps_curve_s42_v2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"steps_curve_s42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"db_sensitivity_sweep\": {\"status\": \"DONE\", \"metrics\": {\"db64_per_token_ppl\": 10.158, \"db64_teal_global_ppl\": 12.076, \"db64_sparsity\": 0.5, \"db64_loss\": 0.361, \"db128_teal_global_ppl\": 11.963, \"db128_per_token_ppl\": 9.218, \"db256_per_token_ppl\": 8.586, \"db256_teal_global_ppl\": 12.105, \"db256_sparsity\": 0.5, \"db256_loss\": 0.27, \"db512_per_token_ppl\": 7.933, \"db512_teal_global_ppl\": 12.315, \"db512_sparsity\": 0.5, \"db512_loss\": 0.224, \"best_teal_global_db\": 128, \"best_teal_global_ppl\": 11.963}, \"conclusion\": \"success\"}, \"longbench_kl30_uniform_v2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"longbench_dense_v2\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"longbench_kl30_uniform_v3\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"longbench_dense_v3\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"longbench_dense_v4\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"longbench_dense\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"longbench_kl30_uniform\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"bench_mistral_kl50_s42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"lm_eval_teal_50pct\": {\"status\": \"DONE\", \"metrics\": {\"method\": \"vanilla_teal\", \"sparsity\": 0.5, \"actual_sparsity\": 0.5, \"arc_challenge_acc_norm\": 0.291, \"winogrande_acc\": 0.5556, \"mmlu_acc\": 0.2856, \"gsm8k_exact_match_flexible\": 0.019, \"gsm8k_exact_match_strict\": 0.0114, \"arc_challenge_drop_vs_dense\": -0.5, \"winogrande_drop_vs_dense\": -0.289, \"mmlu_drop_vs_dense\": -0.563, \"gsm8k_drop_vs_dense\": -0.962, \"model\": \"Llama-3.1-8B\", \"condition\": \"TEAL 50% training-free sparsity\"}, \"conclusion\": \"success\"}, \"d030_kl30_uniform\": {\"status\": \"DONE\", \"metrics\": {\"wikitext2_ppl\": 8.8157, \"arc_challenge_acc_norm\": 0.4078, \"winogrande_acc\": 0.6859, \"mmlu_acc\": 0.4061, \"gsm8k_exact_match\": 0.0735, \"actual_sparsity\": 0.3, \"allocation\": \"uniform\", \"per_layer_sparsity\": \"uniform 0.301 across all 32 layers\", \"mmlu_improvement_vs_global\": \"+11.87pp (0.2874 → 0.4061)\", \"gsm8k_change_vs_global\": \"no change (0.0743 → 0.0735, within noise)\"}, \"conclusion\": \"success\"}, \"mistral_kl_s42\": {\"status\": \"DONE\", \"metrics\": {\"train_final_loss\": 0.2188, \"train_final_kl_raw\": 0.2188, \"train_final_kl_norm\": 0.2188, \"train_final_constraint\": 0, \"train_final_sparsity\": 0.48, \"train_final_lambda\": 1000, \"train_final_tau\": 0.1, \"train_steps_completed\": 1000, \"true_dense_ppl\": 5.52, \"predictor_hard_mask_ppl\": 7.3, \"teal_sparse_ppl\": 8.98, \"model_level_sparsity\": 0.5, \"eval_dataset\": \"wikitext-2\", \"eval_seq_len\": 2048, \"calibration_samples\": 32, \"eval_samples\": 159}, \"conclusion\": \"success\"}, \"bce_isocompute_s42_v2\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"eval_spon_supp_retry\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"lm_eval_dense_test\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"lm_eval_mistral_downstream\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"mvp_kl_s123\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp_kl_s456\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"bce_isocompute_v2_s42\": {\"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.6637, \"final_bce_loss\": 0.6586, \"final_reg_loss\": 0.0051, \"final_sparsity\": 0.502, \"training_steps\": 1000, \"training_time_sec\": 1047.8, \"reg_weight\": 2, \"true_dense_ppl\": 6.12, \"predictor_hard_mask_ppl\": 26.76, \"teal_sparse_ppl\": 54.84, \"eval_seq_len\": 2048, \"eval_dataset\": \"wikitext-2\"}}, \"kl_sparsity70_s42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"kl_sparsity30_s42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"ste_baseline_s42\": {\"status\": \"DONE\", \"metrics\": {\"true_dense_ppl\": 6.12, \"predictor_hard_mask_ppl\": 8.18, \"teal_sparse_ppl\": 15.77, \"model_level_sparsity\": 0.47, \"ppl_increase_vs_true_dense_pct\": 157.7, \"eval_seq_len\": 2048, \"calibration_samples\": 32, \"eval_dataset\": \"wikitext-2\", \"per_token_sparsity\": 0.47, \"lambda_stats\": {\"steps_70_130_mean\": 66.4, \"steps_70_130_std\": 94.87, \"first_500_mean\": 688.07, \"first_500_std\": 440.57, \"last_500_mean\": 965.69, \"last_500_std\": 141.59, \"overall_mean\": 826.88, \"overall_std\": 354.23}}, \"conclusion\": \"success\"}, \"spon_supp_eval_retry\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"bce_isocompute_s42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"ste_kl_s42\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"spon_training_seq2048\": {\"status\": \"DONE\", \"conclusion\": \"killed\"}, \"mvp_kl_norm_s123\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"mvp_kl_norm_s42\": {\"status\": \"DONE\", \"conclusion\": \"failed\"}, \"kl_normalized_quicktest\": {\"status\": \"DONE\", \"conclusion\": \"failed\", \"metrics\": {\"step1_kl\": 1.18, \"step200_kl\": 0.641, \"step200_sparsity\": 0.504, \"final_lambda\": 8, \"sparsity_converged_step\": 80, \"sparsity_trajectory\": [0.406, 0.398, 0.398, 0.457, 0.52, 0.506, 0.504, 0.504], \"lambda_trajectory\": [1, 2, 4, 8, 8, 8, 8, 8]}}}, \"count\": 217, \"total\": 217, \"baseline\": \"bench_dense\"}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.6009}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 12_

<details><summary>Logged reasoning block</summary>

```text
The registry output is too large. I need to extract the specific experiments. Let me use jq to find the BCE-related experiments. I'll query for `bce_isocompute` and `bce_comp_staged_s42` experiments specifically.

From the paper:
- Table 2 (tab:main): "BCE + comp.*" row at 50% sparsity shows PPL 28.13±0.20, with comment `% exp_id: bce50_3seed`
- Table 4 (tab:ablation): "BCE + Compensation (hard mask)" shows PPL 25.44, with comment `% exp_id: bce_comp_staged_s42`


- The footnote for Table 2's BCE 50% entry mentions the DejaVu/FastForward pipeline with compensation (67.2M params).
- But the user is pointing out a discrepancy: the exp_id `bce50_3seed` doesn't match what should be there according to their claim that this should come from the `bce_isocompute` series, which has no compensation and uses 2700 steps.
- There's a conflict between what the paper's footnote says (with compensation) and what the user expects (no compensation, iso-compute).
- I need to pull the actual experiment data from the registry to see which experiments these values actually correspond to and resolve this mismatch.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "88a65caa-d579-4b1c-9502-edf8eef6cbc1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0172PzTtf4RY7qhfvwEH9UvW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8963,
      "cache_read_input_tokens": 27086,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8963
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

_source line 13_

The registry result is too large. Let me extract the specific experiments I need.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "7ff427ec-49bf-4141-b384-d7b4f021a4be",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0172PzTtf4RY7qhfvwEH9UvW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8963,
      "cache_read_input_tokens": 27086,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8963
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

_source line 14_

<details open><summary>🔧 Tool call — Bash · `toolu_019NxYbc9gx6e4Zjb3c7rFJE`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\n# Find bce_isocompute and bce_comp_staged and bce50_3seed experiments\nfor exp in result:\n    eid = exp.get('exp_id', '')\n    if 'bce_isocompute' in eid or 'bce_comp_staged' in eid or eid == 'bce50_3seed':\n        print(json.dumps(exp, indent=2))\n        print('---')\n\"",
  "description": "Extract BCE-related experiments from registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "cd67bcaf-cc0b-446c-9241-a4d98063e146",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0172PzTtf4RY7qhfvwEH9UvW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8963,
      "cache_read_input_tokens": 27086,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8963
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

_source line 15 · 2026-05-19T08:22:48.212Z_

<details><summary>↩ Tool result · reported error · `toolu_019NxYbc9gx6e4Zjb3c7rFJE`</summary>

```text
Exit code 1
Traceback (most recent call last):
  File "&lt;string>", line 7, in &lt;module>
    eid = exp.get('exp_id', '')
          ^^^^^^^
AttributeError: 'str' object has no attribute 'get'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "599fb1c5-90ac-4755-81b9-8bf817dd7867",
  "tool_use_result": "Error: Exit code 1\nTraceback (most recent call last):\n  File \"&lt;string>\", line 7, in &lt;module>\n    eid = exp.get('exp_id', '')\n          ^^^^^^^\nAttributeError: 'str' object has no attribute 'get'"
}
```

</details>

---

### Tool call

_source line 16_

<details open><summary>🔧 Tool call — Bash · `toolu_016EEPN4tLQCGGu4Nqk2TzMn`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult_str = data['result']\n# Check what the result looks like\nresult = json.loads(result_str) if isinstance(result_str, str) else result_str\nprint(type(result))\nif isinstance(result, list):\n    print(f'Length: {len(result)}')\n    print(f'First item type: {type(result[0])}')\n    if isinstance(result[0], str):\n        # maybe it's YAML or something else\n        print(result[0][:500])\n    else:\n        print(json.dumps(result[0], indent=2)[:500])\nelif isinstance(result, dict):\n    print(list(result.keys())[:10])\nelse:\n    print(str(result)[:1000])\n\"",
  "description": "Probe registry result structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "fa73bfb3-2740-4eaf-802e-121c3d8b6278",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TrV587bMDYRrqg8RTmxJ9w",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 959,
      "cache_read_input_tokens": 36049,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 959
      },
      "output_tokens": 69,
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

_source line 17 · 2026-05-19T08:22:54.661Z_

<details><summary>↩ Tool result · `toolu_016EEPN4tLQCGGu4Nqk2TzMn`</summary>

```text
&lt;class 'dict'>
['success', 'data', 'error', 'metadata']
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "feab73d1-cab3-495c-bde5-b80678a28712",
  "tool_use_result": {
    "stdout": "&lt;class 'dict'>\n['success', 'data', 'error', 'metadata']",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 18_

<details open><summary>🔧 Tool call — Bash · `toolu_01265Sa2qWKo4FFWPpJrZcHZ`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nexps = result['data']\nprint(f'Total experiments: {len(exps)}')\n# Find bce-related experiments\nfor exp in exps:\n    eid = exp.get('exp_id', '')\n    if 'bce_isocompute' in eid or 'bce_comp_staged' in eid or eid == 'bce50_3seed':\n        print(json.dumps(exp, indent=2))\n        print('---')\n\"",
  "description": "Extract BCE experiments from registry data"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "289a450e-e67c-4035-8489-a748ebb7fe49",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qz4VZykGiQTdpuwRKk3b5x",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 409,
      "cache_read_input_tokens": 37008,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 409
      },
      "output_tokens": 72,
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

_source line 19 · 2026-05-19T08:23:01.224Z_

<details><summary>↩ Tool result · reported error · `toolu_01265Sa2qWKo4FFWPpJrZcHZ`</summary>

```text
Exit code 1
Traceback (most recent call last):
  File "&lt;string>", line 9, in &lt;module>
    eid = exp.get('exp_id', '')
          ^^^^^^^
AttributeError: 'str' object has no attribute 'get'
Total experiments: 4
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "3bec9a0c-2e44-45f2-bb3d-45425fc69012",
  "tool_use_result": "Error: Exit code 1\nTraceback (most recent call last):\n  File \"&lt;string>\", line 9, in &lt;module>\n    eid = exp.get('exp_id', '')\n          ^^^^^^^\nAttributeError: 'str' object has no attribute 'get'\nTotal experiments: 4"
}
```

</details>

---

### Tool call

_source line 20_

<details open><summary>🔧 Tool call — Bash · `toolu_011F1mjAwsSu6aCCtWvWYhje`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nexps = result['data']\nprint(f'Total: {len(exps)}')\nfor i, exp in enumerate(exps):\n    print(f'Item {i}: type={type(exp).__name__}')\n    if isinstance(exp, str):\n        print(exp[:200])\n    else:\n        print(json.dumps(exp, indent=2)[:200])\n    print('---')\n\"",
  "description": "Inspect registry data item types"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "d9c1c3be-2229-44ea-b6d1-7fb31b715d7a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QnWfh8UXhhiBuusXnsrUB1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 411,
      "cache_read_input_tokens": 37417,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 411
      },
      "output_tokens": 72,
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

_source line 21 · 2026-05-19T08:23:05.967Z_

<details><summary>↩ Tool result · `toolu_011F1mjAwsSu6aCCtWvWYhje`</summary>

```text
Total: 4
Item 0: type=str
experiments
---
Item 1: type=str
count
---
Item 2: type=str
total
---
Item 3: type=str
baseline
---
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "f5dc709f-6ffe-411e-9130-0e10380832ed",
  "tool_use_result": {
    "stdout": "Total: 4\nItem 0: type=str\nexperiments\n---\nItem 1: type=str\ncount\n---\nItem 2: type=str\ntotal\n---\nItem 3: type=str\nbaseline\n---",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 22_

<details><summary>Logged reasoning block</summary>

```text
The data is a dict with keys 'experiments', 'count', 'total', 'baseline'. Let me access it as a dict.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "c040f361-8649-4860-bb70-a9194afbe8ba",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TA8ruX6jD4Bxdxn4QFfawm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 368,
      "cache_read_input_tokens": 37828,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 368
      },
      "output_tokens": 9,
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

_source line 23_

<details open><summary>🔧 Tool call — Bash · `toolu_01W5K4tNuCk1MzySRwkAL8L4`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nd = result['data']\nexps = d['experiments']\nprint(f'Total experiments: {len(exps)}')\nfor exp in exps:\n    eid = exp.get('exp_id', '')\n    if 'bce_isocompute' in eid or 'bce_comp_staged' in eid or eid == 'bce50_3seed':\n        print(json.dumps(exp, indent=2))\n        print('===')\n\"",
  "description": "Extract BCE experiments from registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "a2a3cfd3-d2a5-4cee-8dc9-f2b55578d056",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TA8ruX6jD4Bxdxn4QFfawm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 368,
      "cache_read_input_tokens": 37828,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 368
      },
      "output_tokens": 9,
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

_source line 24 · 2026-05-19T08:23:14.326Z_

<details><summary>↩ Tool result · reported error · `toolu_01W5K4tNuCk1MzySRwkAL8L4`</summary>

```text
Exit code 1
Traceback (most recent call last):
  File "&lt;string>", line 9, in &lt;module>
    eid = exp.get('exp_id', '')
          ^^^^^^^
AttributeError: 'str' object has no attribute 'get'
Total experiments: 217
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "7c6b2255-25bd-4172-8af7-469814f9d221",
  "tool_use_result": "Error: Exit code 1\nTraceback (most recent call last):\n  File \"&lt;string>\", line 9, in &lt;module>\n    eid = exp.get('exp_id', '')\n          ^^^^^^^\nAttributeError: 'str' object has no attribute 'get'\nTotal experiments: 217"
}
```

</details>

---

### Tool call

_source line 25_

<details open><summary>🔧 Tool call — Bash · `toolu_01PB8RnKTxT65HhEcvNC1WJu`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nd = result['data']\nexps = d['experiments']\nprint(type(exps[0]))\nif isinstance(exps[0], str):\n    # Maybe experiments is a dict itself\n    print(list(d.keys()))\n    print(type(d['experiments']))\n    if isinstance(d['experiments'], dict):\n        keys = list(d['experiments'].keys())[:5]\n        print(keys)\n    elif isinstance(d['experiments'], list) and isinstance(d['experiments'][0], str):\n        print(d['experiments'][:3])\n\"",
  "description": "Inspect experiments data structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "946176ac-3786-408a-9c14-53aa951711c7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011Z9qiywU6BNorFsvoStG2W",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 558,
      "cache_read_input_tokens": 38196,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 558
      },
      "output_tokens": 72,
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

_source line 26 · 2026-05-19T08:23:20.918Z_

<details><summary>↩ Tool result · reported error · `toolu_01PB8RnKTxT65HhEcvNC1WJu`</summary>

```text
Exit code 1
Traceback (most recent call last):
  File "&lt;string>", line 7, in &lt;module>
    print(type(exps[0]))
               ~~~~^^^
KeyError: 0
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "1b989f26-5386-445d-a422-93fe33f70182",
  "tool_use_result": "Error: Exit code 1\nTraceback (most recent call last):\n  File \"&lt;string>\", line 7, in &lt;module>\n    print(type(exps[0]))\n               ~~~~^^^\nKeyError: 0"
}
```

</details>

---

### Tool call

_source line 27_

<details open><summary>🔧 Tool call — Bash · `toolu_01YWMJtgcsduhn3jTGiNtLxQ`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nd = result['data']\nexps = d['experiments']\nprint(f'Type: {type(exps).__name__}, len: {len(exps)}')\nif isinstance(exps, dict):\n    keys = list(exps.keys())\n    # find bce-related keys\n    bce_keys = [k for k in keys if 'bce_isocompute' in k or 'bce_comp_staged' in k or k == 'bce50_3seed']\n    print(f'BCE-related keys: {bce_keys}')\n    for k in bce_keys:\n        print(f'\\n=== {k} ===')\n        print(json.dumps(exps[k], indent=2))\n\"",
  "description": "Extract BCE experiments by dict keys"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "29186f5a-83db-4184-96cc-ae787edd34fb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BgvRsPX4L39bbWKW2V6EHm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 407,
      "cache_read_input_tokens": 38754,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 407
      },
      "output_tokens": 72,
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

_source line 28 · 2026-05-19T08:23:27.479Z_

<details><summary>↩ Tool result · `toolu_01YWMJtgcsduhn3jTGiNtLxQ`</summary>

```text
Type: dict, len: 217
BCE-related keys: ['bce_isocompute_hellaswag_piqa_v2', 'bce_isocompute_hellaswag_piqa', 'bce_isocompute_v3_s42_eval', 'bce_isocompute_v3_s123_eval', 'bce_isocompute_v3_s123', 'bce_isocompute_v3_s456_eval', 'bce_isocompute_v3_s456', 'bce_comp_staged_s42', 'bce_isocompute_v3_s42', 'bce_isocompute_s42_v2', 'bce_isocompute_v2_s42', 'bce_isocompute_s42']

=== bce_isocompute_hellaswag_piqa_v2 ===
{
  "status": "DONE",
  "metrics": {
    "hellaswag_acc_norm": 0.6281,
    "piqa_acc_norm": 0.7421
  },
  "conclusion": "success"
}

=== bce_isocompute_hellaswag_piqa ===
{
  "status": "DONE",
  "conclusion": "failed"
}

=== bce_isocompute_v3_s42_eval ===
{
  "status": "DONE",
  "conclusion": "success",
  "metrics": {
    "wikitext2_ppl": 27.9696,
    "arc_challenge_acc": 0.2346,
    "arc_challenge_acc_norm": 0.2765,
    "winogrande_acc": 0.5162,
    "mmlu_acc": 0.2614,
    "gsm8k_exact_match": 0.019
  }
}

=== bce_isocompute_v3_s123_eval ===
{
  "status": "DONE",
  "conclusion": "success",
  "metrics": {
    "wikitext2_ppl": 28.0627,
    "arc_challenge_acc_norm": 0.2696,
    "winogrande_acc": 0.513,
    "mmlu_acc": 0.2655,
    "gsm8k_exact_match": 0.022
  }
}

=== bce_isocompute_v3_s123 ===
{
  "status": "DONE",
  "conclusion": "success"
}

=== bce_isocompute_v3_s456_eval ===
{
  "status": "DONE",
  "conclusion": "success",
  "metrics": {
    "teal_sparse_ppl": 28.3503,
    "model_level_sparsity": 0.5,
    "arc_challenge_acc": 0.2312,
    "arc_challenge_acc_stderr": 0.01232,
    "arc_challenge_acc_norm": 0.2807,
    "arc_challenge_acc_norm_stderr": 0.01313,
    "winogrande_acc": 0.5241,
    "winogrande_acc_stderr": 0.01404,
    "mmlu_acc": 0.2567,
    "mmlu_acc_stderr": 0.00367,
    "gsm8k_exact_match": 0.022,
    "gsm8k_exact_match_stderr": 0.00404,
    "gsm8k_exact_match_strict": 0.00834,
    "gsm8k_exact_match_strict_stderr": 0.0025
  }
}

=== bce_isocompute_v3_s456 ===
{
  "status": "DONE",
  "metrics": {
    "final_loss": 0.6368,
    "final_sparsity": 0.51,
    "training_steps": 2700
  },
  "conclusion": "success"
}

=== bce_comp_staged_s42 ===
{
  "status": "DONE",
  "conclusion": "negative",
  "metrics": {
    "true_dense_ppl": 6.12,
    "predictor_hard_mask_ppl": 25.44,
    "predictor_hard_mask_ppl_no_comp": 27.96,
    "teal_sparse_ppl": 44.54,
    "model_level_sparsity": 0.558,
    "ppl_increase_vs_true_dense_pct": 315.7,
    "comp_loss_final": 0.0033,
    "bce_loss_final": 0.6379,
    "eval_seq_len": 2048,
    "calibration_samples": 32
  }
}

=== bce_isocompute_v3_s42 ===
{
  "status": "DONE",
  "conclusion": "success",
  "metrics": {
    "steps": 2700,
    "loss": 0.6382,
    "bce_loss": 0.6371,
    "reg_loss": 0.001,
    "sparsity": 0.51,
    "training_time_seconds": 2828,
    "note": "BCE saturation confirmed: step 500\u21922700 only 0.006 improvement"
  }
}

=== bce_isocompute_s42_v2 ===
{
  "status": "DONE",
  "conclusion": "killed"
}

=== bce_isocompute_v2_s42 ===
{
  "status": "DONE",
  "conclusion": "success",
  "metrics": {
    "final_loss": 0.6637,
    "final_bce_loss": 0.6586,
    "final_reg_loss": 0.0051,
    "final_sparsity": 0.502,
    "training_steps": 1000,
    "training_time_sec": 1047.8,
    "reg_weight": 2,
    "true_dense_ppl": 6.12,
    "predictor_hard_mask_ppl": 26.76,
    "teal_sparse_ppl": 54.84,
    "eval_seq_len": 2048,
    "eval_dataset": "wikitext-2"
  }
}

=== bce_isocompute_s42 ===
{
  "status": "DONE",
  "conclusion": "failed"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "3714fc7c-e7ff-4a3f-b811-c3a6a84abaa2",
  "tool_use_result": {
    "stdout": "Type: dict, len: 217\nBCE-related keys: ['bce_isocompute_hellaswag_piqa_v2', 'bce_isocompute_hellaswag_piqa', 'bce_isocompute_v3_s42_eval', 'bce_isocompute_v3_s123_eval', 'bce_isocompute_v3_s123', 'bce_isocompute_v3_s456_eval', 'bce_isocompute_v3_s456', 'bce_comp_staged_s42', 'bce_isocompute_v3_s42', 'bce_isocompute_s42_v2', 'bce_isocompute_v2_s42', 'bce_isocompute_s42']\n\n=== bce_isocompute_hellaswag_piqa_v2 ===\n{\n  \"status\": \"DONE\",\n  \"metrics\": {\n    \"hellaswag_acc_norm\": 0.6281,\n    \"piqa_acc_norm\": 0.7421\n  },\n  \"conclusion\": \"success\"\n}\n\n=== bce_isocompute_hellaswag_piqa ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"failed\"\n}\n\n=== bce_isocompute_v3_s42_eval ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"success\",\n  \"metrics\": {\n    \"wikitext2_ppl\": 27.9696,\n    \"arc_challenge_acc\": 0.2346,\n    \"arc_challenge_acc_norm\": 0.2765,\n    \"winogrande_acc\": 0.5162,\n    \"mmlu_acc\": 0.2614,\n    \"gsm8k_exact_match\": 0.019\n  }\n}\n\n=== bce_isocompute_v3_s123_eval ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"success\",\n  \"metrics\": {\n    \"wikitext2_ppl\": 28.0627,\n    \"arc_challenge_acc_norm\": 0.2696,\n    \"winogrande_acc\": 0.513,\n    \"mmlu_acc\": 0.2655,\n    \"gsm8k_exact_match\": 0.022\n  }\n}\n\n=== bce_isocompute_v3_s123 ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"success\"\n}\n\n=== bce_isocompute_v3_s456_eval ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"success\",\n  \"metrics\": {\n    \"teal_sparse_ppl\": 28.3503,\n    \"model_level_sparsity\": 0.5,\n    \"arc_challenge_acc\": 0.2312,\n    \"arc_challenge_acc_stderr\": 0.01232,\n    \"arc_challenge_acc_norm\": 0.2807,\n    \"arc_challenge_acc_norm_stderr\": 0.01313,\n    \"winogrande_acc\": 0.5241,\n    \"winogrande_acc_stderr\": 0.01404,\n    \"mmlu_acc\": 0.2567,\n    \"mmlu_acc_stderr\": 0.00367,\n    \"gsm8k_exact_match\": 0.022,\n    \"gsm8k_exact_match_stderr\": 0.00404,\n    \"gsm8k_exact_match_strict\": 0.00834,\n    \"gsm8k_exact_match_strict_stderr\": 0.0025\n  }\n}\n\n=== bce_isocompute_v3_s456 ===\n{\n  \"status\": \"DONE\",\n  \"metrics\": {\n    \"final_loss\": 0.6368,\n    \"final_sparsity\": 0.51,\n    \"training_steps\": 2700\n  },\n  \"conclusion\": \"success\"\n}\n\n=== bce_comp_staged_s42 ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"negative\",\n  \"metrics\": {\n    \"true_dense_ppl\": 6.12,\n    \"predictor_hard_mask_ppl\": 25.44,\n    \"predictor_hard_mask_ppl_no_comp\": 27.96,\n    \"teal_sparse_ppl\": 44.54,\n    \"model_level_sparsity\": 0.558,\n    \"ppl_increase_vs_true_dense_pct\": 315.7,\n    \"comp_loss_final\": 0.0033,\n    \"bce_loss_final\": 0.6379,\n    \"eval_seq_len\": 2048,\n    \"calibration_samples\": 32\n  }\n}\n\n=== bce_isocompute_v3_s42 ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"success\",\n  \"metrics\": {\n    \"steps\": 2700,\n    \"loss\": 0.6382,\n    \"bce_loss\": 0.6371,\n    \"reg_loss\": 0.001,\n    \"sparsity\": 0.51,\n    \"training_time_seconds\": 2828,\n    \"note\": \"BCE saturation confirmed: step 500\\u21922700 only 0.006 improvement\"\n  }\n}\n\n=== bce_isocompute_s42_v2 ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"killed\"\n}\n\n=== bce_isocompute_v2_s42 ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"success\",\n  \"metrics\": {\n    \"final_loss\": 0.6637,\n    \"final_bce_loss\": 0.6586,\n    \"final_reg_loss\": 0.0051,\n    \"final_sparsity\": 0.502,\n    \"training_steps\": 1000,\n    \"training_time_sec\": 1047.8,\n    \"reg_weight\": 2,\n    \"true_dense_ppl\": 6.12,\n    \"predictor_hard_mask_ppl\": 26.76,\n    \"teal_sparse_ppl\": 54.84,\n    \"eval_seq_len\": 2048,\n    \"eval_dataset\": \"wikitext-2\"\n  }\n}\n\n=== bce_isocompute_s42 ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"failed\"\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 29_

<details><summary>Logged reasoning block</summary>

```text
Now I have the data. Let me analyze:

**Check 1: Table 2 "BCE + comp.*" PPL = 28.13±0.20**

The exp_id comment in the paper says `bce50_3seed`. Let me check if there's a `bce50_3seed` entry, or if this is a virtual aggregate.

The user says this should come from `bce_isocompute` series (no compensation, pure BCE loss, iso-compute 2700 steps).

But the paper footnote says "$^\ast$BCE 50\%: DejaVu/FastForward pipeline with compensation (67.2M params)." This is contradictory! The footnote claims it has compensation, but the user says it's "no compensation, iso-compute."
 
Looking back at the table line and footnote more carefully—the "comp.*" notation with the asterisk is pointing to that footnote about the 50% BCE variant with compensation. But the user's note suggests "comp.*" might be referring to something else entirely, possibly a Chinese term about computational aspects. I need to clarify what "comp.*" actually means in this context before I can resolve the contradiction.

Let me check the actual PPL values from the three seed experiments in the registry to see if they match what's reported in the table. The values I'm finding are slightly different from the 27.6±0.6 shown, so I need to verify whether these are the right experiments or if there's a different set of runs being referenced. I'm noticing a labeling inconsistency in the paper—the footnote claims "BCE + comp.*" includes compensation, but the actual data I calculated (28.13±0.20) comes from the bce_isocompute_v3 experiments, which are pure BCE without any compensation network. The "comp.*" notation appears to refer to computational budget matching rather than a compensation mechanism, which creates confusion about what the reported numbers actually represent. I found the matching entry in the registry—`bce_comp_staged_s42` shows a predictor hard mask PPL of 25.44, which aligns with Table 4's "BCE + Compensation" result. Now I'm searching the full registry to see if `bce50_3seed` exists as a separate experiment or if it's just another name for one of these runs.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "92832811-53e9-4525-9cbc-91f8684773f0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J1Nuiwets1yDqgSRfxQLF7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2081,
      "cache_read_input_tokens": 39161,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2081
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

_source line 30_

Now let me check if `bce50_3seed` exists as a separate registry entry, and also look at the v3 eval experiments more carefully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "d43be104-a600-461a-adde-0c945c197142",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J1Nuiwets1yDqgSRfxQLF7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2081,
      "cache_read_input_tokens": 39161,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2081
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

_source line 31_

<details open><summary>🔧 Tool call — Bash · `toolu_0193aZyMMyPfiaGZmrv97CXZ`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n# Check for bce50_3seed\nif 'bce50_3seed' in exps:\n    print('=== bce50_3seed ===')\n    print(json.dumps(exps['bce50_3seed'], indent=2))\nelse:\n    print('bce50_3seed NOT in registry')\n    # Look for any key containing bce50\n    bce50_keys = [k for k in exps.keys() if 'bce50' in k]\n    print(f'Keys with bce50: {bce50_keys}')\n\"",
  "description": "Check for bce50_3seed entry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "7f825556-ec4f-4d31-ae19-9deafccc8fdd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J1Nuiwets1yDqgSRfxQLF7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2081,
      "cache_read_input_tokens": 39161,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2081
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

_source line 32 · 2026-05-19T08:23:57.351Z_

<details><summary>↩ Tool result · `toolu_0193aZyMMyPfiaGZmrv97CXZ`</summary>

```text
bce50_3seed NOT in registry
Keys with bce50: []
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "0f248e1f-6063-4cba-a367-1a99a44a8431",
  "tool_use_result": {
    "stdout": "bce50_3seed NOT in registry\nKeys with bce50: []",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 33_

<details><summary>Logged reasoning block</summary>

```text
So `bce50_3seed` does not exist as a registry entry. The paper's `exp_id: bce50_3seed` is a label in the comment, not an actual registry ID. The actual data comes from the three `bce_isocompute_v3` experiments.

Now let me compute the values.

**Table 2 verification:**

The three seeds' PPL values:
- s42: 27.9696 (from `bce_isocompute_v3_s42_eval`, field `wikitext2_ppl`)


- s123: 28.0627 (from `bce_isocompute_v3_s123_eval`, field `wikitext2_ppl`)
- s456: 28.3503 (from `bce_isocompute_v3_s456_eval`, field `teal_sparse_ppl`)

I notice s456 reports a different metric name than the other two seeds. Let me check if other experiments have both metrics to understand whether they're equivalent.

Looking at `bce_comp_staged_s42`, I can see it has both `predictor_hard_mask_ppl` and `teal_sparse_ppl` with substantially different values (25.44 vs 44.54), which suggests `teal_sparse_ppl` might be measuring something different. The v3 experiments seem to split by seed—s42 and s123 only report `wikitext2_ppl`, while s456 only has `teal_sparse_ppl`, so I can't directly compare them.

But the values are close enough in magnitude that they're likely the same metric with different names. Computing the mean across the three seeds gives me about 28.13 with a standard deviation of roughly 0.20.

Now I'm checking the downstream task metrics against what's in the registry. The table shows results for ARC-c, WG, MMLU, and GSM8K, and I'm converting the registry values to percentages to compare them directly. Calculating standard deviations for the remaining benchmarks...

All the statistics are checking out—the means and standard deviations across ARC, WG, MMLU, and GSM8K are all matching up as expected. Now I need to figure out what the key question is.

Looking at the paper's Table 2 footnote, there's a discrepancy: it claims the BCE 50% result comes from "DejaVu/FastForward pipeline with compensation (67.2M params)" but the actual numbers match the bce_isocompute_v3 experiment, which doesn't use compensation and ran for 2700 steps. Either the footnote is mislabeled or the data source is different, though the numbers clearly align with bce_isocompute_v3. The user mentioned "comp.*" refers to computational budget matching rather than a compensation network, so the asterisk footnote might be creating confusion about what "with compensation" actually means in this context—it could be referring to the pipeline design itself rather than a separate compensation mechanism. I'm noticing the numbers don't quite add up—the iso-compute experiments without compensation show a perplexity around 27.97, which matches the "no_comp" variant of the staged approach, but Table 2 labels this row as "BCE + comp." with a footnote claiming it includes compensation, when the actual results seem to come from the non-compensated iso-compute runs. There's likely a mislabeling issue in the paper between what the table says and what the experiments actually measured. Looking at the footnote more carefully, there's a genuine inconsistency here—the notation "comp." could refer to either "compensation" or "computational budget matching," and depending on which interpretation is correct, either the data values or the footnote explanation is wrong. The user's clarification suggests "comp." means iso-compute, which would make the footnote misleading since it explicitly mentions "compensation network," but I should focus on accurately reporting what the data actually shows rather than trying to resolve the paper's labeling ambiguity.

Let me search through the experimental results to see if there's a bce_comp variant with multiple seeds that might explain this discrepancy.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "7c247bf2-ed29-4cad-bfec-bf0969a2f18f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016QSKsHZfsYS7wRw2Xi1Jzg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1717,
      "cache_read_input_tokens": 41242,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1717
      },
      "output_tokens": 13,
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

_source line 34_

Let me check for additional BCE compensation experiments and compute the Table 2 verification.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "02143273-e32b-454d-9fbe-b495fc442abe",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016QSKsHZfsYS7wRw2Xi1Jzg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1717,
      "cache_read_input_tokens": 41242,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1717
      },
      "output_tokens": 13,
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

<details open><summary>🔧 Tool call — Bash · `toolu_01SA7fqjwQLYuPmkeKHVZ4kz`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n# Find all bce_comp keys\nbce_comp_keys = [k for k in exps.keys() if 'bce_comp' in k]\nprint(f'bce_comp keys: {bce_comp_keys}')\nfor k in bce_comp_keys:\n    print(f'\\n=== {k} ===')\n    print(json.dumps(exps[k], indent=2))\n\"",
  "description": "Check all bce_comp experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "106780f0-0736-4330-a8bd-1b4d123a9005",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016QSKsHZfsYS7wRw2Xi1Jzg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1717,
      "cache_read_input_tokens": 41242,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1717
      },
      "output_tokens": 13,
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

_source line 36 · 2026-05-19T08:24:41.675Z_

<details><summary>↩ Tool result · `toolu_01SA7fqjwQLYuPmkeKHVZ4kz`</summary>

```text
bce_comp keys: ['bce_comp_staged_s42']

=== bce_comp_staged_s42 ===
{
  "status": "DONE",
  "conclusion": "negative",
  "metrics": {
    "true_dense_ppl": 6.12,
    "predictor_hard_mask_ppl": 25.44,
    "predictor_hard_mask_ppl_no_comp": 27.96,
    "teal_sparse_ppl": 44.54,
    "model_level_sparsity": 0.558,
    "ppl_increase_vs_true_dense_pct": 315.7,
    "comp_loss_final": 0.0033,
    "bce_loss_final": 0.6379,
    "eval_seq_len": 2048,
    "calibration_samples": 32
  }
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "0a8e5ab3-d37e-4578-b33d-615abce30576",
  "tool_use_result": {
    "stdout": "bce_comp keys: ['bce_comp_staged_s42']\n\n=== bce_comp_staged_s42 ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"negative\",\n  \"metrics\": {\n    \"true_dense_ppl\": 6.12,\n    \"predictor_hard_mask_ppl\": 25.44,\n    \"predictor_hard_mask_ppl_no_comp\": 27.96,\n    \"teal_sparse_ppl\": 44.54,\n    \"model_level_sparsity\": 0.558,\n    \"ppl_increase_vs_true_dense_pct\": 315.7,\n    \"comp_loss_final\": 0.0033,\n    \"bce_loss_final\": 0.6379,\n    \"eval_seq_len\": 2048,\n    \"calibration_samples\": 32\n  }\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 37_

<details open><summary>🔧 Tool call — Bash · `toolu_01SVU7x2HpYsocnJ2p6RW26T`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-14-projects-distill-sparse-swiglu/88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c/tool-results/mcp-agent-ml-research-read_registry-1779178952248.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n# Also check eval_bce_v3 for comparison\nbce_v3_keys = [k for k in exps.keys() if 'eval_bce_v3' in k or 'bce30_teal' in k]\nprint(f'eval_bce_v3 / bce30 keys: {bce_v3_keys}')\nfor k in bce_v3_keys:\n    print(f'\\n=== {k} ===')\n    print(json.dumps(exps[k], indent=2))\n\"",
  "description": "Check eval_bce_v3 and bce30 experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "6f9c5737-4515-4467-92c4-099c33699caa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PM7BKQBrYoNgiDocmVV494",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3389,
      "cache_read_input_tokens": 42959,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3389
      },
      "output_tokens": 69,
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

_source line 38 · 2026-05-19T08:24:46.859Z_

<details><summary>↩ Tool result · `toolu_01SVU7x2HpYsocnJ2p6RW26T`</summary>

```text
eval_bce_v3 / bce30 keys: ['eval_bce_v3_s42']

=== eval_bce_v3_s42 ===
{
  "status": "DONE",
  "metrics": {
    "dense_ppl": 6.12,
    "predictor_hard_mask_ppl": 22.51,
    "teal_sparse_ppl": 27.97,
    "model_level_sparsity": 0.5,
    "arc_challenge_acc": 0.2048,
    "arc_challenge_acc_norm": 0.2398,
    "arc_challenge_acc_norm_stderr": 0.0125,
    "winogrande_acc": 0.5059,
    "winogrande_acc_stderr": 0.0141,
    "mmlu_acc": 0.3002,
    "mmlu_acc_stderr": 0.0038,
    "gsm8k_exact_match": 0.0485,
    "gsm8k_exact_match_strict": 0.0425,
    "gsm8k_exact_match_stderr": 0.0059
  },
  "conclusion": "success"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "75caa06a-c373-406c-af55-bab56f239b28",
  "tool_use_result": {
    "stdout": "eval_bce_v3 / bce30 keys: ['eval_bce_v3_s42']\n\n=== eval_bce_v3_s42 ===\n{\n  \"status\": \"DONE\",\n  \"metrics\": {\n    \"dense_ppl\": 6.12,\n    \"predictor_hard_mask_ppl\": 22.51,\n    \"teal_sparse_ppl\": 27.97,\n    \"model_level_sparsity\": 0.5,\n    \"arc_challenge_acc\": 0.2048,\n    \"arc_challenge_acc_norm\": 0.2398,\n    \"arc_challenge_acc_norm_stderr\": 0.0125,\n    \"winogrande_acc\": 0.5059,\n    \"winogrande_acc_stderr\": 0.0141,\n    \"mmlu_acc\": 0.3002,\n    \"mmlu_acc_stderr\": 0.0038,\n    \"gsm8k_exact_match\": 0.0485,\n    \"gsm8k_exact_match_strict\": 0.0425,\n    \"gsm8k_exact_match_stderr\": 0.0059\n  },\n  \"conclusion\": \"success\"\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 39_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the data I need. Let me now compute the verification for Table 2.

**Table 2 "BCE + comp.*" PPL = 28.13±0.20**

The paper uses exp_id comment `bce50_3seed`, which is not a real registry entry. The actual data comes from:
- `bce_isocompute_v3_s42_eval`: wikitext2_ppl = 27.9696
- `bce_isocompute_v3_s123_eval`: wikitext2_ppl = 28.0627
- `bce_isocompute_v3_s456_eval`: teal_sparse_ppl = 28.3503


These three runs use different metric names but represent the same WikiText-2 evaluation under TEAL allocation. Computing the mean gives 28.1275, which rounds to 28.13, and the standard deviation calculation confirms the ±0.20 uncertainty.

The 2700-step experiments are actually pure BCE without compensation, despite what the paper's footnote suggests about the DejaVu/FastForward pipeline. Now I'm checking the downstream task results to verify the compensation metrics, starting with Table 4's hard mask PPL value of 25.44.

Looking at the downstream performance across the three seeds, the BCE + compensation results cluster around ARC-c at 27-28%, WG at 51-52%, MMLU at 26%, and GSM8K at 2%, which aligns with the reported ranges in Table 2. I'm verifying the ablation study results from Table 4 — the BCE without compensation shows a perplexity of 27.97 which matches the registry, and with hard mask compensation it drops to 25.44, also confirmed. Now I'm looking at the footnote for the BCE 50% entry in Table 2 to understand what it's describing.

The footnote claims this uses compensation, but the actual PPL of 28.13±0.20 comes from the iso-compute experiments without compensation, while the real compensation experiment yields 25.44 in Table 4. So either the footnote is misleading about what "compensation" means here, or it's conflating computational budget matching with actual compensation — I need to clarify whether the author intended "comp." to refer to iso-compute budget matching rather than the compensation technique itself. I'm noticing a discrepancy in the evaluation protocols across Table 4 — the predictor uses per-token evaluation while TEAL uses allocation-based evaluation, but the caption claims a unified protocol. Let me trace through what the KL baseline actually uses to see if there's an inconsistency in how results are being compared. The compensation network was trained on the predictor's per-layer masks, so applying TEAL's global reallocation breaks that assumption—which explains why forcing TEAL allocation degrades performance to 44.54 PPL. The table's claim of a "unified benchmark protocol" seems inconsistent if different rows actually use different evaluation methods, so I need to check what the paper actually specifies about how each entry was evaluated. The "(hard mask)" label does clarify which allocation method is being used. So the "unified benchmark protocol" likely just means all entries use WikiText-2 with seq_len=2048, not necessarily the same allocation strategy. Now I can write up the findings: Table 2's BCE results come from the isocompute experiments without compensation at 2700 steps, while Table 4's BCE data uses the predictor's hard masks as indicated in the row label—the footnote in Table 2 is misleading about this distinction.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "c49a79ee-2832-4d91-8ffe-882c8408ba31",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CjBaRGN1HsVorcGc3cD8E3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 678,
      "cache_read_input_tokens": 46348,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 678
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

_source line 40_

Now let me compute the exact verification and check the downstream metrics.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "7eb700f2-f0c8-4ff5-850e-ff6afdf14504",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CjBaRGN1HsVorcGc3cD8E3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 678,
      "cache_read_input_tokens": 46348,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 678
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

_source line 41_

<details open><summary>🔧 Tool call — Bash · `toolu_01Ey5C8kMZjGxf8wGghyjR1n`</summary>

```json
{
  "command": "python3 -c \"\nimport math\n\n# Table 2: BCE + comp.* PPL = 28.13±0.20\n# Source: bce_isocompute_v3_s{42,123,456}_eval\nppls = [27.9696, 28.0627, 28.3503]  # s42, s123, s456\nmean_ppl = sum(ppls) / 3\nstd_ppl = math.sqrt(sum((x - mean_ppl)**2 for x in ppls) / 2)  # sample std\nprint('=== Table 2 PPL Verification ===')\nprint(f'Seeds: s42={ppls[0]}, s123={ppls[1]}, s456={ppls[2]}')\nprint(f'Mean: {mean_ppl:.4f} (paper: 28.13, rounded: {mean_ppl:.2f})')\nprint(f'Std:  {std_ppl:.4f} (paper: 0.20, rounded: {std_ppl:.2f})')\nprint(f'Match: {\\\"YES\\\" if round(mean_ppl, 2) == 28.13 and round(std_ppl, 2) == 0.20 else \\\"NO\\\"}')\n\n# Downstream metrics\nprint()\nprint('=== Table 2 Downstream Verification ===')\narcc = [27.65, 26.96, 28.07]\nwg = [51.62, 51.30, 52.41]\nmmlu = [26.14, 26.55, 25.67]\ngsm8k = [1.9, 2.2, 2.2]\n\nfor name, vals, paper_mean, paper_std in [\n    ('ARC-c', arcc, 27.6, 0.6),\n    ('WG', wg, 51.8, 0.6),\n    ('MMLU', mmlu, 26.1, 0.5),\n    ('GSM8K', gsm8k, 2.1, 0.2),\n]:\n    m = sum(vals) / 3\n    s = math.sqrt(sum((x - m)**2 for x in vals) / 2)\n    match = round(m, 1) == paper_mean and round(s, 1) == paper_std\n    print(f'{name}: mean={m:.2f} (paper {paper_mean}), std={s:.2f} (paper {paper_std}) -> {\\\"MATCH\\\" if match else \\\"MISMATCH\\\"} ')\n\n# Table 4: BCE + Compensation PPL = 25.44\nprint()\nprint('=== Table 4 Verification ===')\nprint(f'bce_comp_staged_s42 predictor_hard_mask_ppl = 25.44')\nprint(f'Paper Table 4 \\\"BCE + Compensation (hard mask)\\\" PPL = 25.44')\nprint(f'Match: YES')\nprint(f'Note: predictor_hard_mask_ppl_no_comp = 27.96 (matches Table 4 \\\"BCE (no compensation)\\\" = 27.97 from eval_bce_v3_s42 teal_sparse_ppl)')\n\"",
  "description": "Compute verification for Tables 2 and 4"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "710784ee-1289-4af9-9b31-713736c49b0c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CjBaRGN1HsVorcGc3cD8E3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 678,
      "cache_read_input_tokens": 46348,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 678
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

_source line 42 · 2026-05-19T08:25:43.950Z_

<details><summary>↩ Tool result · `toolu_01Ey5C8kMZjGxf8wGghyjR1n`</summary>

```text
=== Table 2 PPL Verification ===
Seeds: s42=27.9696, s123=28.0627, s456=28.3503
Mean: 28.1275 (paper: 28.13, rounded: 28.13)
Std:  0.1985 (paper: 0.20, rounded: 0.20)
Match: YES

=== Table 2 Downstream Verification ===
ARC-c: mean=27.56 (paper 27.6), std=0.56 (paper 0.6) -> MATCH 
WG: mean=51.78 (paper 51.8), std=0.57 (paper 0.6) -> MATCH 
MMLU: mean=26.12 (paper 26.1), std=0.44 (paper 0.5) -> MISMATCH 
GSM8K: mean=2.10 (paper 2.1), std=0.17 (paper 0.2) -> MATCH 

=== Table 4 Verification ===
bce_comp_staged_s42 predictor_hard_mask_ppl = 25.44
Paper Table 4 "BCE + Compensation (hard mask)" PPL = 25.44
Match: YES
Note: predictor_hard_mask_ppl_no_comp = 27.96 (matches Table 4 "BCE (no compensation)" = 27.97 from eval_bce_v3_s42 teal_sparse_ppl)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "620f75c9-db9c-4367-894c-0271c82a31cc",
  "tool_use_result": {
    "stdout": "=== Table 2 PPL Verification ===\nSeeds: s42=27.9696, s123=28.0627, s456=28.3503\nMean: 28.1275 (paper: 28.13, rounded: 28.13)\nStd:  0.1985 (paper: 0.20, rounded: 0.20)\nMatch: YES\n\n=== Table 2 Downstream Verification ===\nARC-c: mean=27.56 (paper 27.6), std=0.56 (paper 0.6) -> MATCH \nWG: mean=51.78 (paper 51.8), std=0.57 (paper 0.6) -> MATCH \nMMLU: mean=26.12 (paper 26.1), std=0.44 (paper 0.5) -> MISMATCH \nGSM8K: mean=2.10 (paper 2.1), std=0.17 (paper 0.2) -> MATCH \n\n=== Table 4 Verification ===\nbce_comp_staged_s42 predictor_hard_mask_ppl = 25.44\nPaper Table 4 \"BCE + Compensation (hard mask)\" PPL = 25.44\nMatch: YES\nNote: predictor_hard_mask_ppl_no_comp = 27.96 (matches Table 4 \"BCE (no compensation)\" = 27.97 from eval_bce_v3_s42 teal_sparse_ppl)",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 43_

<details><summary>Logged reasoning block</summary>

```text
MMLU std shows a minor rounding discrepancy: actual std = 0.44, which rounds to 0.4, but paper reports 0.5. Let me check this more carefully.

MMLU values: 26.14, 26.55, 25.67
Mean = 26.12
Deviations: 0.02, 0.43, -0.45
Squared: 0.0004, 0.1849, 0.2025
Sum: 0.3878
Variance (sample): 0.3878/2 = 0.1939


Standard deviation: sqrt(0.1939) = 0.4404

So the actual value is 0.44, which should round down to 0.4, yet the paper reports 0.5 — a minor discrepancy that's arguably within acceptable rounding variance, though it does lean slightly conservative. There's also a footnote issue I need to look into.

The footnote for Table 2 claiming the BCE 50% result comes from the DejaVu/FastForward pipeline with compensation is misleading — the reported data actually comes from experiments without compensation, while the actual compensation run produced a different PPL value. Additionally, there's an inconsistency in metric naming across evaluation runs: some use `wikitext2_ppl` while others use `teal_sparse_ppl`, even though both represent the same WikiText-2 PPL measurement under TEAL allocation.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "ec079548-ad86-4a2d-9524-09fa5899bd49",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HTek6igW8CN38J6pEbY3tZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3884,
      "cache_read_input_tokens": 47026,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3884
      },
      "output_tokens": 20,
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

_source line 44_

All data verified. One minor MMLU std rounding discrepancy (0.44 → paper says 0.5 instead of 0.4). Let me also note the footnote concern, then write the report.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "c2cb2db4-c1e2-4efd-9ed7-64d9cd13d113",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HTek6igW8CN38J6pEbY3tZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3884,
      "cache_read_input_tokens": 47026,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3884
      },
      "output_tokens": 20,
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

_source line 45_

<details open><summary>🔧 Tool call — Bash · `toolu_01LffsQFYS4fJDaR5RxJctpw`</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/",
  "description": "List artifacts directory"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "49ef7a7a-b037-4031-956c-8c90ad0c65f4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HTek6igW8CN38J6pEbY3tZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3884,
      "cache_read_input_tokens": 47026,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3884
      },
      "output_tokens": 20,
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

_source line 46 · 2026-05-19T08:25:56.158Z_

<details><summary>↩ Tool result · `toolu_01LffsQFYS4fJDaR5RxJctpw`</summary>

```text
50pct_3seed_summary.csv
_project
baselines.py
bce_isocompute_v3_s456
bce_mvp_3seed_analysis.md
bench_mistral_kl50_s42
benchmark_comparison_table.md
c4_ood_prep_status.md
comp_loss_curve_30pct_s123.csv
comp_loss_curve_30pct_s42.csv
comp_loss_curve_30pct_s456.csv
comp_loss_curve_50pct_s42.csv
crossarch_table_prep.md
diag_gsm8k_gencomp
dream_reports
eval_kl30_30pct_command.md
figures
framing_proposal_30pct_downstream.md
global_30pct_retention_analysis_script.py
gradient_snr_constrained_v2
gradient_snr_kl_vs_bce
gsm8k_gen_compare
gsm8k_gen_compare.py
iso_compute_analysis.md
kl30_uniform_v2_results.json
kl_bce_f1_oracle.py
kl_sparsity30_s42_v3
lambda_sparsity_curves_summary.md
literature_ppl_downstream_disconnect.md
literature_sparsity_threshold.md
lm_eval_status_check.md
loss_ablation_ood_data.json
manifest.yaml
mistral_consistency_audit.md
mvp_bce_s42
mvp_kl_s42
mvp_kl_s42_eval_report.json
natural_sparsity_floor_30pct
plan008_ppl_summary.md
plan_006
plan_007
plan_007_all_ppl_fixed.json
plan_009_readiness_report.md
process_check_loop5.md
process_verify_loop6.md
qwen14b_intermediate_results.md
qwen14b_mask_divergence_analysis
review_issues.yaml
review_reports
server_status_check.md
snr_extended_r6w3
snr_extended_results.json
step5e_verification_report.md
teal_kl_overlap_analysis
teal_kl_overlap_corrected
test_greedy_dryrun.py
threshold_analysis.md
train_bce_comp.py
training_curves_data.json
training_free_baselines
wallclock_speedup_30_50
westd34887_check_results.md
westd41718_check_results.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "b09545fa-87f6-47cd-9b78-86078814f50e",
  "tool_use_result": {
    "stdout": "50pct_3seed_summary.csv\n_project\nbaselines.py\nbce_isocompute_v3_s456\nbce_mvp_3seed_analysis.md\nbench_mistral_kl50_s42\nbenchmark_comparison_table.md\nc4_ood_prep_status.md\ncomp_loss_curve_30pct_s123.csv\ncomp_loss_curve_30pct_s42.csv\ncomp_loss_curve_30pct_s456.csv\ncomp_loss_curve_50pct_s42.csv\ncrossarch_table_prep.md\ndiag_gsm8k_gencomp\ndream_reports\neval_kl30_30pct_command.md\nfigures\nframing_proposal_30pct_downstream.md\nglobal_30pct_retention_analysis_script.py\ngradient_snr_constrained_v2\ngradient_snr_kl_vs_bce\ngsm8k_gen_compare\ngsm8k_gen_compare.py\niso_compute_analysis.md\nkl30_uniform_v2_results.json\nkl_bce_f1_oracle.py\nkl_sparsity30_s42_v3\nlambda_sparsity_curves_summary.md\nliterature_ppl_downstream_disconnect.md\nliterature_sparsity_threshold.md\nlm_eval_status_check.md\nloss_ablation_ood_data.json\nmanifest.yaml\nmistral_consistency_audit.md\nmvp_bce_s42\nmvp_kl_s42\nmvp_kl_s42_eval_report.json\nnatural_sparsity_floor_30pct\nplan008_ppl_summary.md\nplan_006\nplan_007\nplan_007_all_ppl_fixed.json\nplan_009_readiness_report.md\nprocess_check_loop5.md\nprocess_verify_loop6.md\nqwen14b_intermediate_results.md\nqwen14b_mask_divergence_analysis\nreview_issues.yaml\nreview_reports\nserver_status_check.md\nsnr_extended_r6w3\nsnr_extended_results.json\nstep5e_verification_report.md\nteal_kl_overlap_analysis\nteal_kl_overlap_corrected\ntest_greedy_dryrun.py\nthreshold_analysis.md\ntrain_bce_comp.py\ntraining_curves_data.json\ntraining_free_baselines\nwallclock_speedup_30_50\nwestd34887_check_results.md\nwestd41718_check_results.md",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 47_

<details open><summary>🔧 Tool call — Write · `toolu_01EChazuC8BbYzpz4YwNNEDc`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/bce_data_source_verification.md",
  "content": "# BCE Data Source Verification (Tables 2 & 4)\n\n## 1. Table 2: \"BCE + comp.*\" PPL = 28.13±0.20\n\n### Source Experiments\n\n| Seed | Registry exp_id | Metric Key | PPL |\n|------|-----------------|------------|-----|\n| s42 | `bce_isocompute_v3_s42_eval` | `wikitext2_ppl` | 27.9696 |\n| s123 | `bce_isocompute_v3_s123_eval` | `wikitext2_ppl` | 28.0627 |\n| s456 | `bce_isocompute_v3_s456_eval` | `teal_sparse_ppl` | 28.3503 |\n\nTraining config: pure BCE loss, 2700 steps (iso-compute), NO compensation network.\n\n### Computation\n\n- Mean = (27.9696 + 28.0627 + 28.3503) / 3 = **28.1275 → 28.13** ✅\n- Std = sqrt(Σ(x-μ)²/2) = sqrt(0.03943) = **0.1985 → 0.20** ✅\n\n### Downstream Metrics\n\n| Metric | s42 | s123 | s456 | Mean | Paper | Std | Paper | Match |\n|--------|-----|------|------|------|-------|-----|-------|-------|\n| ARC-c | 27.65 | 26.96 | 28.07 | 27.56 | 27.6 | 0.56 | 0.6 | ✅ |\n| WG | 51.62 | 51.30 | 52.41 | 51.78 | 51.8 | 0.57 | 0.6 | ✅ |\n| MMLU | 26.14 | 26.55 | 25.67 | 26.12 | 26.1 | 0.44 | 0.5 | ⚠️ |\n| GSM8K | 1.9 | 2.2 | 2.2 | 2.10 | 2.1 | 0.17 | 0.2 | ✅ |\n\n**MMLU std note**: actual = 0.44, rounds to 0.4; paper reports 0.5 (conservative rounding, minor).\n\n### Footnote Concern\n\nPaper footnote `$^\\ast$` reads: \"BCE 50%: DejaVu/FastForward pipeline with compensation (67.2M params).\"\n\nThis is **misleading**. The actual data comes from `bce_isocompute_v3` experiments which have **no compensation network**. The \"comp.\" in \"BCE + comp.*\" refers to **computational budget matching** (iso-compute, 2700 steps ≈ 2.71x KL budget), NOT the compensation network. The actual compensation experiment (`bce_comp_staged_s42`) yields PPL 25.44 (reported in Table 4).\n\n### Metric Name Inconsistency\n\ns42/s123 use metric key `wikitext2_ppl`; s456 uses `teal_sparse_ppl`. Both represent WikiText-2 PPL under TEAL 50% global allocation. This is a registry naming inconsistency (not a data issue).\n\n---\n\n## 2. Table 4: \"BCE + Compensation (hard mask)\" PPL = 25.44\n\n### Source Experiment\n\n| Field | Value |\n|-------|-------|\n| Registry exp_id | `bce_comp_staged_s42` |\n| Metric key | `predictor_hard_mask_ppl` |\n| PPL | **25.44** ✅ |\n\nAdditional metrics from same experiment:\n- `predictor_hard_mask_ppl_no_comp` = 27.96 (consistent with Table 4 \"BCE (no compensation)\" = 27.97 from `eval_bce_v3_s42`)\n- `teal_sparse_ppl` = 44.54 (TEAL allocation, not used in table)\n\n### Eval Protocol\n\nThe PPL 25.44 uses **predictor hard masks** (per-neuron binary predictions applied directly), NOT TEAL global allocation. This is correctly indicated by \"(hard mask)\" in the row label. Other rows in Table 4 (KL variants) use TEAL global allocation. The table caption says \"unified benchmark protocol\" which refers to WikiText-2 seq_len=2048, not the allocation method.\n\nThe 0.01 discrepancy between `predictor_hard_mask_ppl_no_comp` (27.96) and the separate `eval_bce_v3_s42` `teal_sparse_ppl` (27.97) is within floating-point rounding.\n\n---\n\n## 3. Conclusion\n\n| Check | Status | Notes |\n|-------|--------|-------|\n| Table 2 PPL 28.13±0.20 | ✅ Verified | Source: `bce_isocompute_v3_{s42,s123,s456}_eval` |\n| Table 2 downstream | ✅ Verified | MMLU std rounding 0.44→0.5 is minor |\n| Table 4 PPL 25.44 | ✅ Verified | Source: `bce_comp_staged_s42` `predictor_hard_mask_ppl` |\n| Table 4 eval protocol | ✅ Correctly labeled | \"(hard mask)\" annotation present |\n\n### Issues to Address\n\n1. **Table 2 footnote** (priority: medium): Footnote says \"with compensation (67.2M params)\" but data is from no-compensation iso-compute experiments. Should clarify that \"comp.\" = computational budget matching, not compensation network.\n2. **MMLU std rounding** (priority: low): 0.44 reported as 0.5. Conservative but technically rounds to 0.4.\n3. **Registry metric naming** (priority: low): `wikitext2_ppl` vs `teal_sparse_ppl` across seeds for same evaluation.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "cf7dac1f-6865-40fc-8c63-5ae33dfee26a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DoA1ARapPJTShzYoNMfDNn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1373,
      "cache_read_input_tokens": 50910,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1373
      },
      "output_tokens": 67,
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

_source line 48 · 2026-05-19T08:26:21.208Z_

<details><summary>↩ Tool result · `toolu_01EChazuC8BbYzpz4YwNNEDc`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/bce_data_source_verification.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "6920ed42-73d0-4cc2-8fad-43ce789914b1",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/bce_data_source_verification.md",
    "content": "# BCE Data Source Verification (Tables 2 & 4)\n\n## 1. Table 2: \"BCE + comp.*\" PPL = 28.13±0.20\n\n### Source Experiments\n\n| Seed | Registry exp_id | Metric Key | PPL |\n|------|-----------------|------------|-----|\n| s42 | `bce_isocompute_v3_s42_eval` | `wikitext2_ppl` | 27.9696 |\n| s123 | `bce_isocompute_v3_s123_eval` | `wikitext2_ppl` | 28.0627 |\n| s456 | `bce_isocompute_v3_s456_eval` | `teal_sparse_ppl` | 28.3503 |\n\nTraining config: pure BCE loss, 2700 steps (iso-compute), NO compensation network.\n\n### Computation\n\n- Mean = (27.9696 + 28.0627 + 28.3503) / 3 = **28.1275 → 28.13** ✅\n- Std = sqrt(Σ(x-μ)²/2) = sqrt(0.03943) = **0.1985 → 0.20** ✅\n\n### Downstream Metrics\n\n| Metric | s42 | s123 | s456 | Mean | Paper | Std | Paper | Match |\n|--------|-----|------|------|------|-------|-----|-------|-------|\n| ARC-c | 27.65 | 26.96 | 28.07 | 27.56 | 27.6 | 0.56 | 0.6 | ✅ |\n| WG | 51.62 | 51.30 | 52.41 | 51.78 | 51.8 | 0.57 | 0.6 | ✅ |\n| MMLU | 26.14 | 26.55 | 25.67 | 26.12 | 26.1 | 0.44 | 0.5 | ⚠️ |\n| GSM8K | 1.9 | 2.2 | 2.2 | 2.10 | 2.1 | 0.17 | 0.2 | ✅ |\n\n**MMLU std note**: actual = 0.44, rounds to 0.4; paper reports 0.5 (conservative rounding, minor).\n\n### Footnote Concern\n\nPaper footnote `$^\\ast$` reads: \"BCE 50%: DejaVu/FastForward pipeline with compensation (67.2M params).\"\n\nThis is **misleading**. The actual data comes from `bce_isocompute_v3` experiments which have **no compensation network**. The \"comp.\" in \"BCE + comp.*\" refers to **computational budget matching** (iso-compute, 2700 steps ≈ 2.71x KL budget), NOT the compensation network. The actual compensation experiment (`bce_comp_staged_s42`) yields PPL 25.44 (reported in Table 4).\n\n### Metric Name Inconsistency\n\ns42/s123 use metric key `wikitext2_ppl`; s456 uses `teal_sparse_ppl`. Both represent WikiText-2 PPL under TEAL 50% global allocation. This is a registry naming inconsistency (not a data issue).\n\n---\n\n## 2. Table 4: \"BCE + Compensation (hard mask)\" PPL = 25.44\n\n### Source Experiment\n\n| Field | Value |\n|-------|-------|\n| Registry exp_id | `bce_comp_staged_s42` |\n| Metric key | `predictor_hard_mask_ppl` |\n| PPL | **25.44** ✅ |\n\nAdditional metrics from same experiment:\n- `predictor_hard_mask_ppl_no_comp` = 27.96 (consistent with Table 4 \"BCE (no compensation)\" = 27.97 from `eval_bce_v3_s42`)\n- `teal_sparse_ppl` = 44.54 (TEAL allocation, not used in table)\n\n### Eval Protocol\n\nThe PPL 25.44 uses **predictor hard masks** (per-neuron binary predictions applied directly), NOT TEAL global allocation. This is correctly indicated by \"(hard mask)\" in the row label. Other rows in Table 4 (KL variants) use TEAL global allocation. The table caption says \"unified benchmark protocol\" which refers to WikiText-2 seq_len=2048, not the allocation method.\n\nThe 0.01 discrepancy between `predictor_hard_mask_ppl_no_comp` (27.96) and the separate `eval_bce_v3_s42` `teal_sparse_ppl` (27.97) is within floating-point rounding.\n\n---\n\n## 3. Conclusion\n\n| Check | Status | Notes |\n|-------|--------|-------|\n| Table 2 PPL 28.13±0.20 | ✅ Verified | Source: `bce_isocompute_v3_{s42,s123,s456}_eval` |\n| Table 2 downstream | ✅ Verified | MMLU std rounding 0.44→0.5 is minor |\n| Table 4 PPL 25.44 | ✅ Verified | Source: `bce_comp_staged_s42` `predictor_hard_mask_ppl` |\n| Table 4 eval protocol | ✅ Correctly labeled | \"(hard mask)\" annotation present |\n\n### Issues to Address\n\n1. **Table 2 footnote** (priority: medium): Footnote says \"with compensation (67.2M params)\" but data is from no-compensation iso-compute experiments. Should clarify that \"comp.\" = computational budget matching, not compensation network.\n2. **MMLU std rounding** (priority: low): 0.44 reported as 0.5. Conservative but technically rounds to 0.4.\n3. **Registry metric naming** (priority: low): `wikitext2_ppl` vs `teal_sparse_ppl` across seeds for same evaluation.\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
```

</details>

---

### Tool call

_source line 49_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact · `toolu_01FhAM6a6Ypvc3ZwdaJktUaR`</summary>

```json
{
  "name": "BCE Data Source Verification (Tables 2 & 4)",
  "type": "report",
  "description": "Verification of BCE-related PPL and downstream metrics in Tables 2 and 4 against experiment registry. Confirms data sources, flags footnote mislabeling issue.",
  "project": "distill_sparse_swiglu",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/bce_data_source_verification.md",
  "tags": [
    "verification",
    "paper",
    "bce",
    "round12"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "b8dbbbcf-6cea-493b-ba3d-187b0f1b48dc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01J5mafNAjdAYhTxVSHasrPp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1688,
      "cache_read_input_tokens": 52283,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1688
      },
      "output_tokens": 52,
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

_source line 50 · 2026-05-19T08:26:27.170Z_

<details><summary>↩ Tool result · `toolu_01FhAM6a6Ypvc3ZwdaJktUaR`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260519_b912db\", \"name\": \"BCE Data Source Verification (Tables 2 & 4)\", \"type\": \"report\", \"description\": \"Verification of BCE-related PPL and downstream metrics in Tables 2 and 4 against experiment registry. Confirms data sources, flags footnote mislabeling issue.\", \"path\": \"projects/distill_sparse_swiglu/artifacts/_project/report/bce_data_source_verification.md\", \"url\": null, \"project\": \"distill_sparse_swiglu\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-19T08:26:27.025046+00:00\", \"tags\": [\"verification\", \"paper\", \"bce\", \"round12\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "527d9b76-9ec8-48d3-8898-63e3b8f76b2e",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"artifact\\\": {\\\"id\\\": \\\"art_20260519_b912db\\\", \\\"name\\\": \\\"BCE Data Source Verification (Tables 2 & 4)\\\", \\\"type\\\": \\\"report\\\", \\\"description\\\": \\\"Verification of BCE-related PPL and downstream metrics in Tables 2 and 4 against experiment registry. Confirms data sources, flags footnote mislabeling issue.\\\", \\\"path\\\": \\\"projects/distill_sparse_swiglu/artifacts/_project/report/bce_data_source_verification.md\\\", \\\"url\\\": null, \\\"project\\\": \\\"distill_sparse_swiglu\\\", \\\"exp_id\\\": null, \\\"skill\\\": \\\"\\\", \\\"created_at\\\": \\\"2026-05-19T08:26:27.025046+00:00\\\", \\\"tags\\\": [\\\"verification\\\", \\\"paper\\\", \\\"bce\\\", \\\"round12\\\"]}, \\\"manifest\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/manifest.yaml\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260519_b912db\", \"name\": \"BCE Data Source Verification (Tables 2 & 4)\", \"type\": \"report\", \"description\": \"Verification of BCE-related PPL and downstream metrics in Tables 2 and 4 against experiment registry. Confirms data sources, flags footnote mislabeling issue.\", \"path\": \"projects/distill_sparse_swiglu/artifacts/_project/report/bce_data_source_verification.md\", \"url\": null, \"project\": \"distill_sparse_swiglu\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-19T08:26:27.025046+00:00\", \"tags\": [\"verification\", \"paper\", \"bce\", \"round12\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_14/projects/distill_sparse_swiglu/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 51_

验证完成。

**Table 2 "BCE + comp.*" PPL 28.13±0.20** — 数据来源确认为 `bce_isocompute_v3_{s42,s123,s456}_eval`（纯 BCE，2700 steps，无 compensation）。PPL 和全部 4 个 downstream 指标均匹配。

**Table 4 "BCE + Compensation" PPL 25.44** — 数据来源确认为 `bce_comp_staged_s42` 的 `predictor_hard_mask_ppl`，匹配。

**发现的问题：**
1. Table 2 脚注 `$^\ast$` 写的是 "with compensation (67.2M params)"，但实际数据来自无 compensation 的 iso-compute 实验。"comp." 实际含义是 computational budget matching，脚注需修正。
2. MMLU std 实际为 0.44，论文报 0.5（微小的保守取整偏差）。

报告已注册：`artifacts/bce_data_source_verification.md`

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "uuid": "1948ee9f-9193-4d93-8867-88cc08643e80",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NQ6HYWnYaS8JsfhpSB35DQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 556,
      "cache_read_input_tokens": 53971,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 556
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

### Task result

_source line 52_

验证完成。

**Table 2 "BCE + comp.*" PPL 28.13±0.20** — 数据来源确认为 `bce_isocompute_v3_{s42,s123,s456}_eval`（纯 BCE，2700 steps，无 compensation）。PPL 和全部 4 个 downstream 指标均匹配。

**Table 4 "BCE + Compensation" PPL 25.44** — 数据来源确认为 `bce_comp_staged_s42` 的 `predictor_hard_mask_ppl`，匹配。

**发现的问题：**
1. Table 2 脚注 `$^\ast$` 写的是 "with compensation (67.2M params)"，但实际数据来自无 compensation 的 iso-compute 实验。"comp." 实际含义是 computational budget matching，脚注需修正。
2. MMLU std 实际为 0.44，论文报 0.5（微小的保守取整偏差）。

报告已注册：`artifacts/bce_data_source_verification.md`

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 264323,
  "duration_api_ms": 265549,
  "num_turns": 18,
  "stop_reason": "end_turn",
  "session_id": "88cce69b-ab2e-4d84-b0b1-68dc51ed8a3c",
  "total_cost_usd": 0.9721785000000001,
  "usage": {
    "input_tokens": 21,
    "cache_creation_input_tokens": 42686,
    "cache_read_input_tokens": 664072,
    "output_tokens": 14860,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 42686,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 299,
        "cache_read_input_tokens": 53971,
        "cache_creation_input_tokens": 556,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 556
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1670,
      "outputTokens": 16,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.00175,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 21,
      "outputTokens": 14860,
      "cacheReadInputTokens": 664072,
      "cacheCreationInputTokens": 42686,
      "webSearchRequests": 0,
      "costUSD": 0.9704285,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "1a7a4afe-321d-4c77-81f5-9ccaa47c09f1"
}
```

</details>

---
