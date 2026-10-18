# audit negative experiment framing

**When Debiasing Hurts: An Exact Bias Identity for LLM-Annotated Treatment Effects** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 57
- **Recorded user turns:** 0
- **Tool calls:** 21
- **Original source:** `logs/workers/worker_audit_negative-experiment-framing_20260524T075928.log`
- **Structured JSON:** [`fab7ffae411e0d4e8b7d.json`](../../sessions/fa/fab7ffae411e0d4e8b7d.json)

## Before a recorded user message

57 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
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
  "uuid": "c4638724-5fc0-4795-b49d-333a2013608d",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0520-projects-ec-hte-llm-annotation/memory/"
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
    "resetsAt": 1779621600,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "3e02a6bf-9745-41a1-b93c-19b6b7ef4416",
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524"
}
```

---

### Assistant

_source line 4_

我先读取所有相关论文文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "7c820b77-4111-4160-b4a4-6b166aa99c52",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011won9p5f9sA8Gcan4dngKR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12675,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12675
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

### Tool call

_source line 5_

<details open><summary>🔧 Tool call — Read · `toolu_01RiHrfJvSAh3T5VJU8XiyrU`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "55f39700-51d4-4e3f-a590-3ad39a7567cc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011won9p5f9sA8Gcan4dngKR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12675,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12675
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

_source line 6 · 2026-05-24T07:59:40.510Z_

<details><summary>↩ Tool result · `toolu_01RiHrfJvSAh3T5VJU8XiyrU`</summary>

```text
1	\section{Experiments}
2	
3	\subsection{Setup}
4	
5	We test on synthetic ($N{=}5{,}000$, $K \in \{2, 4\}$, controlled $\Delta\tau$ and $\Delta\pi$, 100 MC runs) and semi-synthetic (TweetEval sentiment~\cite{barbieri2020tweeteval}, $K{=}4$ unbalanced subgroups, $\pi \in \{0.05, 0.10, 0.15, 0.25\}$) DGPs; full specifications in Appendix~\ref{app:dgp}.
6	
7	We compare: (1) \textit{Naive} (no correction), (2) \textit{Global} (pooled confusion matrix, equivalent to PPI/DSL~\cite{angelopoulos2023ppi,egami2024dsl} with homogeneous error), (3) \textit{Stratified MLE} (per-subgroup DSL without shrinkage), (4) \textit{HB EC-HTE} (per-subgroup correction), (5) \textit{PPCI}~\cite{sui2026ppci}, and (6) \textit{EC-HTE+PPCI}.
8	For CausalForest~\cite{wager2018causal}, we compare naive, global, and EC-HTE variants.
9	Primary metrics are $|\text{bias}|$, RMSE, and 95\% CI coverage, averaged across subgroups and 100 MC runs.
10	Robustness validation covers hate speech, six OpenAI models, subgroup misspecification, asymmetric confusion matrices, confounded treatment, outcome-dependent misclassification (all $\geq$93.5\% coverage), stance detection (Appendix~\ref{app:stance}), and treatment-dependent misclassification ($\approx$90\% at $\gamma_T \leq 0.05$; Appendices~\ref{app:hatespeech}--\ref{app:treatment_dep}).
11	Semi-synthetic evaluation uses empirical LLM confusion matrices from 16 model--dataset--$K$ combinations (8 LLMs $\times$ 2 datasets $\times$ varying $K$; Appendix~\ref{app:semireal}); of these, 11 have sufficient subgroup variation for $R^2$ regression and 13 have $K{=}4$ for $\kappa$ analysis.
12	
13	\subsection{Empirical Validation of the Bias Identity}
14	\label{sec:bias_mechanism}
15	
16	We verify Theorem~\ref{thm:bias_identity} on a $K{=}2$ grid (520 configurations, $\Delta\pi \in [0, 0.25]$, $\Delta\tau \in (0, 0.50]$) and a $K{=}4$ grid (Appendix~\ref{app:dgp}).
17	Regressing observed subgroup bias on $\delta_s \cdot \Delta\tau / (1{-}2\bar{\pi})$ yields $R^2 = 0.994$ ($K{=}2$) and $0.97$ ($K{=}4$); residual variance reflects MC noise ($R^2 \geq 0.976$ even at $P(Z{=}1) = 0.1$; Appendix~\ref{app:classimbalance}).
18	Global correction worsens bias in 50\% of $K{=}2$ configurations (260/520, excluding $\Delta\pi{=}0$), with amplification reaching 2.86$\times$ ($K{=}2$) and 2.41$\times$ ($K{=}4$); Figure~\ref{fig:heatmap} visualizes the amplification surface.
19	Beyond amplification, global correction reverses the sign of estimated CATE---concluding a protective treatment is harmful---in 14.9\% of configurations at $\tau(0) = 0.03$ (31\% at $\tau(0) = 0.01$; critical threshold $\tau(0) < 0.089$, matching Theorem~\ref{thm:bias_identity}), with all eight real LLMs amplifying bias under global correction; EC-HTE eliminates sign reversal entirely (Figure~\ref{fig:sign_reversal}; Appendix~\ref{app:policy_reversal}).
20	
21	\subsection{Correction Evaluation}
22	\label{sec:ec_hte_eval}
23	
24	Table~\ref{tab:main_results} presents the main results across representative configurations.
25	In the $K{=}2$ extreme row, global correction \emph{increases} $|\text{bias}|$ relative to naive (0.059 vs.\ 0.058), confirming the over-correction mechanism of Theorem~\ref{thm:bias_identity}.
26	F-L scalar correction increases $|\text{bias}|$ to 0.122 (coverage 0.68); F-L per-subgroup to 0.168 as $(1{-}2\pi_s) \to 0$---both worse than naive (Table~\ref{tab:main_results}).
27	HB EC-HTE reduces $|\text{bias}|$ from 0.059 to 0.008 (7.4$\times$); relative to stratified MLE (0.012), the advantage is 1.5$\times$ with lower RMSE from partial pooling. At $K{=}4$, bias reduces from 0.056 to 0.012 (4.7$\times$), maintaining near-nominal coverage (0.94--0.96).
28	Under moderate heterogeneity and in TweetEval ($K{=}4$), methods converge ($p > 0.05$); EC-HTE incurs higher RMSE when $\Delta\pi$ is small (Table~\ref{tab:main_supp}).
29	At $K{=}8$ ($n_{\text{expert}}/K{=}31$), coverage remains $\geq$95.6\% but RMSE increases; we recommend $n_{\text{expert}}/K \geq 50$ (Appendix~\ref{app:k8_subgroups}).
30	
31	\paragraph{CausalForest.}
32	Theorem~\ref{thm:bias_identity} applies to any estimator whose inputs pass through a confusion matrix; CausalForest~\cite{wager2018causal} with a noisy effect modifier $\hat{Z}$ inherits the same $M_{\text{global}}^{-1} M_s$ structure.
33	With CausalForest ($K{=}4$, extreme, $n{=}500$), EC-HTE reduces $|\text{bias}|$ from 0.191 to 0.039 (4.9$\times$) with coverage 0.90; global amplifies bias up to 5.9$\times$ (Table~\ref{tab:main_results}; bootstrap SE in Appendix~\ref{app:bootstrap_se}).
34	The identity and correction are estimator-agnostic: R-learner yields comparable bias reduction (89\%, Appendix~\ref{app:rlearner}), confirming that the product-form bias arises from the confusion matrix structure, not the downstream estimator.
35	
36	\begin{table}[t]
37	\centering
38	\caption{Main results (extreme heterogeneity). Metrics averaged over subgroups, $z$-levels, 100 MC runs. Bold: lowest $|\text{bias}|$. $^\dagger$RMSE exceeds Global. F-L Scalar: $\hat{\tau}/(1{-}2\bar{\pi})$~\cite{frazis2003estimating}; F-L Per-sub.: per-subgroup variant (binary $Z$ only). Moderate/TweetEval in Table~\ref{tab:main_supp}; MC SEs $\leq 0.005$ for all entries (Appendix~\ref{app:mcse}).\protect\footnotemark}
39	\label{tab:main_results}
40	\resizebox{\columnwidth}{!}{%
41	\begin{tabular}{ll ccc}
42	\toprule
43	Configuration & Method & $|\text{Bias}|$ & RMSE & 95\% CI Cov. \\
44	\midrule
45	\multirow{6}{*}{\shortstack[l]{DIM\\$K{=}2$, $n{=}250$}}
46	 & Naive & 0.058 & 0.090 & 0.82 \\
47	 & Global & 0.059 & 0.099 & 0.87 \\
48	 & F-L Scalar & 0.122 & 0.159 & 0.68 \\
49	 & F-L Per-sub. & 0.168 & 0.220 & 0.65 \\
50	 & Strat.\ MLE & 0.012 & 0.094 & 0.95 \\
51	 & HB EC-HTE & \textbf{0.008} & 0.089 & 0.94 \\
52	\midrule
53	\multirow{4}{*}{\shortstack[l]{DIM\\$K{=}4$, $n{=}500$}}
54	 & Naive & 0.062 & 0.113 & 0.88 \\
55	 & Global & 0.056 & 0.125 & 0.91 \\
56	 & Strat.\ MLE & \textbf{0.010} & 0.127$^\dagger$ & 0.95 \\
57	 & HB EC-HTE & 0.012 & 0.120 & 0.96 \\
58	\midrule
59	\multirow{3}{*}{\shortstack[l]{CausalForest\\$K{=}4$, $n{=}500$}}
60	 & Naive & 0.208 & 0.231 & 0.44 \\
61	 & Global & 0.191 & 0.244 & 0.58 \\
62	 & EC-HTE Forest & \textbf{0.039} & 0.180 & 0.90 \\
63	\bottomrule
64	\end{tabular}}
65	\footnotetext{CausalForest plug-in SE achieves 93.8\% aggregate coverage; a bootstrap procedure ($B{=}100$) recovers $\geq$95\% coverage at all budgets tested (Appendix~\ref{app:bootstrap_se}).}
66	\end{table}
67	
68	\subsection{Actionable Diagnostic}
69	\label{sec:diagnostic}
70	
71	Proposition~\ref{prop:debiasing_hurts} provides a $\Delta\tau$-free diagnostic: global correction increases bias in subgroup $s$ iff $|\delta_s| / ((1-2\bar{\pi}) \cdot \pi_s) > 1$, computable from a pilot sample without estimating treatment effects.
72	The diagnostic achieves AUC $= 0.63$ across 16 semi-synthetic LLM--dataset combinations; restricting to subgroups with $\Delta\tau > 0$ recovers AUC $= 1.0$ ($0.86$ on synthetic grids; Figure~\ref{fig:roc} in Appendix~\ref{app:roc}; Appendix~\ref{app:screening}).
73	The lower AUC reflects inclusion of subgroups with $\Delta\tau \approx 0$, where misdiagnosis is inconsequential---global and stratified correction perform identically when effect heterogeneity is absent.
74	For $K{=}2$, $|\delta_0|{=}|\delta_1|$ limits discrimination (Appendix~\ref{app:screening}).
75	
76	The condition number $\kappa(\hat{C}_s)$ provides a practical guard: $\kappa > 100$ triggers fallback; all 13 tested LLM--dataset combinations fall in $\kappa \in (1.25, 3]$ with calibrated coverage $\geq$93\% (Appendix~\ref{app:kappa_analysis}).
77	Budget crossover, $K{=}8$ scalability, and multi-LLM validation ($R^2 = 0.975$; Appendix~\ref{app:realcm_bias}) appear in Appendices~\ref{sec:budget}--\ref{app:multilm}.
78	
79	On a real hate speech dataset ($\Delta\pi{=}0.117$; Appendix~\ref{app:hatespeech}), EC-HTE underperforms both naive and global correction, consistent with most real LLMs exhibiting $\Delta\pi \in [0.10, 0.20]$ (Appendices~\ref{app:multilm}--\ref{app:civilcomments}).
80	
81	\paragraph{Operating conditions.}
82	EC-HTE requires: (i)~$\Delta\pi > 0.15$, (ii)~$n_{\text{expert}} \geq 250$ for $K{=}2$, (iii)~$\text{FNR}_s < 0.50$, and (iv)~$K \leq 4$; when unmet, global correction is preferable (Appendix~\ref{app:k8_subgroups}).
83	EC-HTE is robust to noisy subgroup labels ($p_{\text{flip}} \leq 0.50$; Appendix~\ref{app:robustness}).
84	Under confounded treatment, pairing with IPW-DIM maintains $\geq$94.5\% coverage (Appendix~\ref{app:confounded_dgp}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "ce462333-54a0-4a38-a987-cdec0d9eee03",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/experiments.tex",
      "content": "\\section{Experiments}\n\n\\subsection{Setup}\n\nWe test on synthetic ($N{=}5{,}000$, $K \\in \\{2, 4\\}$, controlled $\\Delta\\tau$ and $\\Delta\\pi$, 100 MC runs) and semi-synthetic (TweetEval sentiment~\\cite{barbieri2020tweeteval}, $K{=}4$ unbalanced subgroups, $\\pi \\in \\{0.05, 0.10, 0.15, 0.25\\}$) DGPs; full specifications in Appendix~\\ref{app:dgp}.\n\nWe compare: (1) \\textit{Naive} (no correction), (2) \\textit{Global} (pooled confusion matrix, equivalent to PPI/DSL~\\cite{angelopoulos2023ppi,egami2024dsl} with homogeneous error), (3) \\textit{Stratified MLE} (per-subgroup DSL without shrinkage), (4) \\textit{HB EC-HTE} (per-subgroup correction), (5) \\textit{PPCI}~\\cite{sui2026ppci}, and (6) \\textit{EC-HTE+PPCI}.\nFor CausalForest~\\cite{wager2018causal}, we compare naive, global, and EC-HTE variants.\nPrimary metrics are $|\\text{bias}|$, RMSE, and 95\\% CI coverage, averaged across subgroups and 100 MC runs.\nRobustness validation covers hate speech, six OpenAI models, subgroup misspecification, asymmetric confusion matrices, confounded treatment, outcome-dependent misclassification (all $\\geq$93.5\\% coverage), stance detection (Appendix~\\ref{app:stance}), and treatment-dependent misclassification ($\\approx$90\\% at $\\gamma_T \\leq 0.05$; Appendices~\\ref{app:hatespeech}--\\ref{app:treatment_dep}).\nSemi-synthetic evaluation uses empirical LLM confusion matrices from 16 model--dataset--$K$ combinations (8 LLMs $\\times$ 2 datasets $\\times$ varying $K$; Appendix~\\ref{app:semireal}); of these, 11 have sufficient subgroup variation for $R^2$ regression and 13 have $K{=}4$ for $\\kappa$ analysis.\n\n\\subsection{Empirical Validation of the Bias Identity}\n\\label{sec:bias_mechanism}\n\nWe verify Theorem~\\ref{thm:bias_identity} on a $K{=}2$ grid (520 configurations, $\\Delta\\pi \\in [0, 0.25]$, $\\Delta\\tau \\in (0, 0.50]$) and a $K{=}4$ grid (Appendix~\\ref{app:dgp}).\nRegressing observed subgroup bias on $\\delta_s \\cdot \\Delta\\tau / (1{-}2\\bar{\\pi})$ yields $R^2 = 0.994$ ($K{=}2$) and $0.97$ ($K{=}4$); residual variance reflects MC noise ($R^2 \\geq 0.976$ even at $P(Z{=}1) = 0.1$; Appendix~\\ref{app:classimbalance}).\nGlobal correction worsens bias in 50\\% of $K{=}2$ configurations (260/520, excluding $\\Delta\\pi{=}0$), with amplification reaching 2.86$\\times$ ($K{=}2$) and 2.41$\\times$ ($K{=}4$); Figure~\\ref{fig:heatmap} visualizes the amplification surface.\nBeyond amplification, global correction reverses the sign of estimated CATE---concluding a protective treatment is harmful---in 14.9\\% of configurations at $\\tau(0) = 0.03$ (31\\% at $\\tau(0) = 0.01$; critical threshold $\\tau(0) < 0.089$, matching Theorem~\\ref{thm:bias_identity}), with all eight real LLMs amplifying bias under global correction; EC-HTE eliminates sign reversal entirely (Figure~\\ref{fig:sign_reversal}; Appendix~\\ref{app:policy_reversal}).\n\n\\subsection{Correction Evaluation}\n\\label{sec:ec_hte_eval}\n\nTable~\\ref{tab:main_results} presents the main results across representative configurations.\nIn the $K{=}2$ extreme row, global correction \\emph{increases} $|\\text{bias}|$ relative to naive (0.059 vs.\\ 0.058), confirming the over-correction mechanism of Theorem~\\ref{thm:bias_identity}.\nF-L scalar correction increases $|\\text{bias}|$ to 0.122 (coverage 0.68); F-L per-subgroup to 0.168 as $(1{-}2\\pi_s) \\to 0$---both worse than naive (Table~\\ref{tab:main_results}).\nHB EC-HTE reduces $|\\text{bias}|$ from 0.059 to 0.008 (7.4$\\times$); relative to stratified MLE (0.012), the advantage is 1.5$\\times$ with lower RMSE from partial pooling. At $K{=}4$, bias reduces from 0.056 to 0.012 (4.7$\\times$), maintaining near-nominal coverage (0.94--0.96).\nUnder moderate heterogeneity and in TweetEval ($K{=}4$), methods converge ($p > 0.05$); EC-HTE incurs higher RMSE when $\\Delta\\pi$ is small (Table~\\ref{tab:main_supp}).\nAt $K{=}8$ ($n_{\\text{expert}}/K{=}31$), coverage remains $\\geq$95.6\\% but RMSE increases; we recommend $n_{\\text{expert}}/K \\geq 50$ (Appendix~\\ref{app:k8_subgroups}).\n\n\\paragraph{CausalForest.}\nTheorem~\\ref{thm:bias_identity} applies to any estimator whose inputs pass through a confusion matrix; CausalForest~\\cite{wager2018causal} with a noisy effect modifier $\\hat{Z}$ inherits the same $M_{\\text{global}}^{-1} M_s$ structure.\nWith CausalForest ($K{=}4$, extreme, $n{=}500$), EC-HTE reduces $|\\text{bias}|$ from 0.191 to 0.039 (4.9$\\times$) with coverage 0.90; global amplifies bias up to 5.9$\\times$ (Table~\\ref{tab:main_results}; bootstrap SE in Appendix~\\ref{app:bootstrap_se}).\nThe identity and correction are estimator-agnostic: R-learner yields comparable bias reduction (89\\%, Appendix~\\ref{app:rlearner}), confirming that the product-form bias arises from the confusion matrix structure, not the downstream estimator.\n\n\\begin{table}[t]\n\\centering\n\\caption{Main results (extreme heterogeneity). Metrics averaged over subgroups, $z$-levels, 100 MC runs. Bold: lowest $|\\text{bias}|$. $^\\dagger$RMSE exceeds Global. F-L Scalar: $\\hat{\\tau}/(1{-}2\\bar{\\pi})$~\\cite{frazis2003estimating}; F-L Per-sub.: per-subgroup variant (binary $Z$ only). Moderate/TweetEval in Table~\\ref{tab:main_supp}; MC SEs $\\leq 0.005$ for all entries (Appendix~\\ref{app:mcse}).\\protect\\footnotemark}\n\\label{tab:main_results}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{ll ccc}\n\\toprule\nConfiguration & Method & $|\\text{Bias}|$ & RMSE & 95\\% CI Cov. \\\\\n\\midrule\n\\multirow{6}{*}{\\shortstack[l]{DIM\\\\$K{=}2$, $n{=}250$}}\n & Naive & 0.058 & 0.090 & 0.82 \\\\\n & Global & 0.059 & 0.099 & 0.87 \\\\\n & F-L Scalar & 0.122 & 0.159 & 0.68 \\\\\n & F-L Per-sub. & 0.168 & 0.220 & 0.65 \\\\\n & Strat.\\ MLE & 0.012 & 0.094 & 0.95 \\\\\n & HB EC-HTE & \\textbf{0.008} & 0.089 & 0.94 \\\\\n\\midrule\n\\multirow{4}{*}{\\shortstack[l]{DIM\\\\$K{=}4$, $n{=}500$}}\n & Naive & 0.062 & 0.113 & 0.88 \\\\\n & Global & 0.056 & 0.125 & 0.91 \\\\\n & Strat.\\ MLE & \\textbf{0.010} & 0.127$^\\dagger$ & 0.95 \\\\\n & HB EC-HTE & 0.012 & 0.120 & 0.96 \\\\\n\\midrule\n\\multirow{3}{*}{\\shortstack[l]{CausalForest\\\\$K{=}4$, $n{=}500$}}\n & Naive & 0.208 & 0.231 & 0.44 \\\\\n & Global & 0.191 & 0.244 & 0.58 \\\\\n & EC-HTE Forest & \\textbf{0.039} & 0.180 & 0.90 \\\\\n\\bottomrule\n\\end{tabular}}\n\\footnotetext{CausalForest plug-in SE achieves 93.8\\% aggregate coverage; a bootstrap procedure ($B{=}100$) recovers $\\geq$95\\% coverage at all budgets tested (Appendix~\\ref{app:bootstrap_se}).}\n\\end{table}\n\n\\subsection{Actionable Diagnostic}\n\\label{sec:diagnostic}\n\nProposition~\\ref{prop:debiasing_hurts} provides a $\\Delta\\tau$-free diagnostic: global correction increases bias in subgroup $s$ iff $|\\delta_s| / ((1-2\\bar{\\pi}) \\cdot \\pi_s) > 1$, computable from a pilot sample without estimating treatment effects.\nThe diagnostic achieves AUC $= 0.63$ across 16 semi-synthetic LLM--dataset combinations; restricting to subgroups with $\\Delta\\tau > 0$ recovers AUC $= 1.0$ ($0.86$ on synthetic grids; Figure~\\ref{fig:roc} in Appendix~\\ref{app:roc}; Appendix~\\ref{app:screening}).\nThe lower AUC reflects inclusion of subgroups with $\\Delta\\tau \\approx 0$, where misdiagnosis is inconsequential---global and stratified correction perform identically when effect heterogeneity is absent.\nFor $K{=}2$, $|\\delta_0|{=}|\\delta_1|$ limits discrimination (Appendix~\\ref{app:screening}).\n\nThe condition number $\\kappa(\\hat{C}_s)$ provides a practical guard: $\\kappa > 100$ triggers fallback; all 13 tested LLM--dataset combinations fall in $\\kappa \\in (1.25, 3]$ with calibrated coverage $\\geq$93\\% (Appendix~\\ref{app:kappa_analysis}).\nBudget crossover, $K{=}8$ scalability, and multi-LLM validation ($R^2 = 0.975$; Appendix~\\ref{app:realcm_bias}) appear in Appendices~\\ref{sec:budget}--\\ref{app:multilm}.\n\nOn a real hate speech dataset ($\\Delta\\pi{=}0.117$; Appendix~\\ref{app:hatespeech}), EC-HTE underperforms both naive and global correction, consistent with most real LLMs exhibiting $\\Delta\\pi \\in [0.10, 0.20]$ (Appendices~\\ref{app:multilm}--\\ref{app:civilcomments}).\n\n\\paragraph{Operating conditions.}\nEC-HTE requires: (i)~$\\Delta\\pi > 0.15$, (ii)~$n_{\\text{expert}} \\geq 250$ for $K{=}2$, (iii)~$\\text{FNR}_s < 0.50$, and (iv)~$K \\leq 4$; when unmet, global correction is preferable (Appendix~\\ref{app:k8_subgroups}).\nEC-HTE is robust to noisy subgroup labels ($p_{\\text{flip}} \\leq 0.50$; Appendix~\\ref{app:robustness}).\nUnder confounded treatment, pairing with IPW-DIM maintains $\\geq$94.5\\% coverage (Appendix~\\ref{app:confounded_dgp}).",
      "numLines": 84,
      "startLine": 1,
      "totalLines": 84
    }
  }
}
```

</details>

---

### Tool call

_source line 7_

<details open><summary>🔧 Tool call — Read · `toolu_01EG3kvJobe4UnztHw1fDYZK`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "673c46b2-e7f8-437d-bbca-8a73844950e9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011won9p5f9sA8Gcan4dngKR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12675,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12675
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

_source line 8 · 2026-05-24T07:59:40.970Z_

<details><summary>↩ Tool result · `toolu_01EG3kvJobe4UnztHw1fDYZK`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	Standard confusion-matrix correction---the default in PPI, DSL, and CSS practice---can reverse causal conclusions when misclassification rates vary across subgroups.
4	We derived an exact bias identity explaining when and why, verified across synthetic grids and semi-synthetic evaluations using 11 empirical LLM confusion matrices.
5	The identity yields a diagnostic that flags harmful correction from error rates alone, and prescribes per-subgroup correction that eliminates sign reversal given sufficient error heterogeneity; when these conditions are not met, practitioners should prefer global correction.
6	The framework applies wherever LLM annotations replace structured covariates and annotation error rates vary across subpopulations.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "ca7257b0-b7e9-46f3-b5ef-c44cca21bffd",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\\label{sec:conclusion}\n\nStandard confusion-matrix correction---the default in PPI, DSL, and CSS practice---can reverse causal conclusions when misclassification rates vary across subgroups.\nWe derived an exact bias identity explaining when and why, verified across synthetic grids and semi-synthetic evaluations using 11 empirical LLM confusion matrices.\nThe identity yields a diagnostic that flags harmful correction from error rates alone, and prescribes per-subgroup correction that eliminates sign reversal given sufficient error heterogeneity; when these conditions are not met, practitioners should prefer global correction.\nThe framework applies wherever LLM annotations replace structured covariates and annotation error rates vary across subpopulations.",
      "numLines": 6,
      "startLine": 1,
      "totalLines": 6
    }
  }
}
```

</details>

---

### Tool call

_source line 9_

<details open><summary>🔧 Tool call — Read · `toolu_01NSM3VuMaD9tYCa7oqDi1F9`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "1515dea0-d9c5-4c50-8741-47e049e31d41",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011won9p5f9sA8Gcan4dngKR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12675,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12675
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

_source line 10 · 2026-05-24T07:59:41.434Z_

<details><summary>↩ Tool result · `toolu_01NSM3VuMaD9tYCa7oqDi1F9`</summary>

```text
1	\section*{Limitations}
2	\label{sec:limitations}
3	
4	Per-subgroup correction requires $n_{\text{expert}} \times P(Z_{\text{minority}}) / K \geq 25$ expert labels per subgroup and moderate classifier accuracy ($\text{FPR}_s, \text{FNR}_s < 0.5$); below these thresholds, stratification incurs more variance than the bias it removes.
5	At $K{=}8$ with $n_{\text{expert}}{=}250$ (${\approx}31$ labels/subgroup), coverage remains nominal ($\geq$95.6\%) but RMSE exceeds global correction, establishing a scalability boundary under fixed expert budget (Appendix~\ref{app:k8_subgroups}).
6	The diagnostic (Proposition~\ref{prop:debiasing_hurts}) achieves AUC $= 0.86$ on synthetic data but degrades to $0.63$ on real LLM confusion matrices (Appendix~\ref{app:screening}); it should be paired with $R^2$ validation of the bias identity rather than used as a standalone rule.
7	
8	Assumption~(A1)---conditional independence of misclassification and potential outcomes---is not empirically testable.
9	Sensitivity analysis shows robustness up to $\gamma = 0.2$ for outcome-dependent misclassification (coverage $\geq$93.5\%; Appendix~\ref{app:a1_sensitivity}) and $\gamma_T \leq 0.05$ for treatment-dependent misclassification (coverage $\geq$89.7\%; Appendix~\ref{app:treatment_dep}).
10	
11	The method requires discrete, pre-specified subgroups; continuous effect modifiers require discretization, and data-driven subgroup discovery risks overfitting.
12	Ground-truth subgroup CATEs are unavailable in public datasets---classic causal inference benchmarks lack the LLM annotation step that creates the measurement error we address---so we use synthetic CATE injection on real text features and real LLM annotations (Appendices~\ref{app:dgp},~\ref{app:multilm}).
13	Code and data generation scripts will be released upon acceptance.
14	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "a6561744-1d6e-4712-9b35-73888658254e",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/limitations.tex",
      "content": "\\section*{Limitations}\n\\label{sec:limitations}\n\nPer-subgroup correction requires $n_{\\text{expert}} \\times P(Z_{\\text{minority}}) / K \\geq 25$ expert labels per subgroup and moderate classifier accuracy ($\\text{FPR}_s, \\text{FNR}_s < 0.5$); below these thresholds, stratification incurs more variance than the bias it removes.\nAt $K{=}8$ with $n_{\\text{expert}}{=}250$ (${\\approx}31$ labels/subgroup), coverage remains nominal ($\\geq$95.6\\%) but RMSE exceeds global correction, establishing a scalability boundary under fixed expert budget (Appendix~\\ref{app:k8_subgroups}).\nThe diagnostic (Proposition~\\ref{prop:debiasing_hurts}) achieves AUC $= 0.86$ on synthetic data but degrades to $0.63$ on real LLM confusion matrices (Appendix~\\ref{app:screening}); it should be paired with $R^2$ validation of the bias identity rather than used as a standalone rule.\n\nAssumption~(A1)---conditional independence of misclassification and potential outcomes---is not empirically testable.\nSensitivity analysis shows robustness up to $\\gamma = 0.2$ for outcome-dependent misclassification (coverage $\\geq$93.5\\%; Appendix~\\ref{app:a1_sensitivity}) and $\\gamma_T \\leq 0.05$ for treatment-dependent misclassification (coverage $\\geq$89.7\\%; Appendix~\\ref{app:treatment_dep}).\n\nThe method requires discrete, pre-specified subgroups; continuous effect modifiers require discretization, and data-driven subgroup discovery risks overfitting.\nGround-truth subgroup CATEs are unavailable in public datasets---classic causal inference benchmarks lack the LLM annotation step that creates the measurement error we address---so we use synthetic CATE injection on real text features and real LLM annotations (Appendices~\\ref{app:dgp},~\\ref{app:multilm}).\nCode and data generation scripts will be released upon acceptance.\n",
      "numLines": 14,
      "startLine": 1,
      "totalLines": 14
    }
  }
}
```

</details>

---

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — Read · `toolu_012LUNiGTEe1b5o683QdyvhX`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "262624d7-a1e1-4385-9ed3-b641a14b84f8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011won9p5f9sA8Gcan4dngKR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12675,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12675
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

_source line 12 · 2026-05-24T07:59:42.337Z_

<details><summary>↩ Tool result · reported error · `toolu_012LUNiGTEe1b5o683QdyvhX`</summary>

```text
File content (40292 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "d5f84a69-2513-48ba-b5d4-90a1316c8d74",
  "tool_use_result": "Error: File content (40292 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file."
}
```

</details>

---

### Tool call

_source line 13_

<details open><summary>🔧 Tool call — Read · `toolu_01BdLXuaPdoUedrUig49pf9Z`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "6cf5695b-a02b-4131-8a9e-310d978f6260",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011won9p5f9sA8Gcan4dngKR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12675,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12675
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

_source line 14 · 2026-05-24T07:59:42.388Z_

<details><summary>↩ Tool result · `toolu_01BdLXuaPdoUedrUig49pf9Z`</summary>

```text
1	\section{Correction Prescribed by the Identity}
2	\label{sec:method}
3	
4	Theorem~\ref{thm:bias_identity} identifies per-subgroup misclassification deviation as the bias source; the natural correction is per-subgroup confusion matrix inversion.
5	This correction (EC-HTE) proceeds in three stages: estimate per-subgroup confusion matrices via hierarchical Bayes, invert them to correct observed outcome moments, and propagate correction uncertainty into downstream causal estimators.
6	The complete procedure is summarized in Algorithm~\ref{alg:echte} (Appendix~\ref{app:algorithm}).
7	
8	\subsection{Hierarchical Bayes Confusion Matrix Estimation}
9	
10	We place a Dirichlet-Multinomial hierarchical model over the confusion matrices $\{C_s\}_{s=1}^K$.
11	For each subgroup $s$, row $j$ of $C_s$ has a Dirichlet prior centered at the global pooled confusion matrix $\hat{C}_{\text{global}}$: $\text{Dir}(\alpha_0 \cdot \hat{C}_{\text{global},j})$, where $\hat{C}_{\text{global},j}$ is the $j$-th row of the pooled CM and $\alpha_0 > 0$ is a shared concentration parameter estimated via empirical Bayes (marginal likelihood maximization).
12	We place a $\mathrm{Gamma}(a_0, b_0)$ hyperprior on $\alpha_0$ with defaults $a_0 = 3$, $b_0 = 1$, robust to $2\times$ perturbation of $(a_0, b_0)$ (RMSE change $<$5\%; Table~\ref{tab:hyperprior_sweep}, Appendix~\ref{app:hyperprior}).
13	Large $\alpha_0$ pulls subgroup estimates toward $\hat{C}_{\text{global}}$ (global correction), while small $\alpha_0$ allows subgroup-specific rates to dominate (stratified correction).
14	This partial pooling---James-Stein shrinkage, a standard technique in small-area estimation applied here to per-subgroup confusion matrix estimation for causal inference---borrows strength across subgroups from limited expert labels, reducing variance for small subgroups while preserving heterogeneity where data support it.
15	
16	Posterior inference uses centered empirical Bayes optimization ($<$5ms for $K{=}4$, $N{=}5{,}000$); a full Gibbs MCMC alternative requires $\sim$5s (full MCMC specification in Appendix~\ref{app:mcmc}; algorithm in Appendix~\ref{app:algorithm}).
17	Bootstrap SE ($B{=}100$) adds $\sim$0.4s.
18	HB estimation outperforms stratified MLE in 87.5\% of configurations (21 of 24) across the experimental grid (Section~\ref{sec:ec_hte_eval}), with the largest gains when $n_{\text{expert}} / K < 100$.
19	The advantage requires $n_{\text{expert}} \times P(Z_{\text{minority}}) / K \geq 25$ per subgroup; below this threshold, stratified MLE is preferred because the hierarchical model lacks sufficient observations for stable shrinkage.
20	At $n_{\text{expert}} \geq 1000$, HB and stratified MLE converge to within 0.5\% on all metrics.
21	Sensitivity analysis shows $<$5\% RMSE variation under 2$\times$ hyperprior perturbation, confirming that results are not driven by prior specification.
22	
23	\subsection{Subgroup-Stratified Correction}
24	
25	Given posterior mean confusion matrices $\hat{C}_s$, we correct observed outcome moments per subgroup by matrix inversion:
26	\begin{equation}
27	\tilde{\boldsymbol{\mu}}_s = \hat{C}_s^{-1} \cdot \hat{\boldsymbol{\mu}}_s,
28	\end{equation}
29	where $\hat{\boldsymbol{\mu}}_s = [\hat{\tau}_{\text{obs}}(0, s),\, \hat{\tau}_{\text{obs}}(1, s)]^\top$ collects the observed conditional outcome moments in subgroup $s$.
30	This requires $\det(\hat{C}_s) \neq 0$ for all $s$, which holds under assumption~(A4) ($\pi_s \neq 0.5$) but may fail in finite samples when error rates approach degeneracy.
31	In practice, Laplace smoothing of the confusion matrix counts ensures finite-sample invertibility.
32	We impose a singularity guard: if the condition number $\kappa(\hat{C}_s) > 100$ (for a $2{\times}2$ symmetric confusion matrix, this corresponds to $\pi_s > 0.495$, i.e., near-random classification), subgroup $s$ falls back to global correction $\bar{C}^{-1}$; when the fallback triggers, the standard error computation also uses $\bar{C}^{-1}$ for that subgroup, ensuring consistency between point estimates and confidence intervals.
33	This hard guard prevents numerical catastrophe; $\kappa \leq 1.25$ is a sufficient condition for strongest bias reduction (Appendix~\ref{sec:budget}), though EC-HTE maintains calibrated coverage ($\geq$93\%) across the wider $\kappa \in [1.4, 3.0]$ range observed in practice (Appendix~\ref{app:kappa_analysis}).
34	
35	The contrast with global correction is direct.
36	Global correction applies $\bar{C}^{-1}$ uniformly to all subgroups, introducing the $\delta_s \cdot \Delta\tau$ bias identified in Theorem~\ref{thm:bias_identity}.
37	Subgroup-stratified correction eliminates this bias by matching each subgroup's correction to its own misclassification structure, at the cost of higher variance from estimating $K$ separate confusion matrices (Appendix~\ref{sec:budget}).
38	
39	\subsection{Variance-Adjusted CausalForest}
40	
41	For heterogeneous treatment effect estimation, we feed corrected covariates into CausalForestDML~\cite{wager2018causal} with honest splitting.
42	The forest produces per-observation standard error estimates $\text{se}_i$.
43	To account for confusion matrix correction, we propagate uncertainty through the inverse mapping:
44	\begin{equation}
45	\text{se}_{\text{corrected},i} = \sqrt{\text{diag}\!\left(\hat{C}_{S_i}^{-1}\, \text{diag}(\text{se}_i^2)\, \hat{C}_{S_i}^{-\top}\right)}.
46	\end{equation}
47	This plug-in SE conditions on $\hat{C}_s$, neglecting CM estimation uncertainty; at $n_{\text{expert}} \geq 100$ this is negligible, but below this threshold a full bootstrap ($B{=}100$; re-estimate CM and re-fit per replicate) maintains $\geq$95\% coverage across all budgets tested ($n_{\text{expert}} \in \{25, 50, 75, 100, 200\}$); even plug-in SE achieves $\geq$91\% at $n_{\text{expert}}{=}25$ (Appendix~\ref{app:bootstrap_se}).
48	When $n_{\text{expert}}/K < 50$, we recommend bootstrap SE; otherwise plug-in SE suffices.
49	
50	\paragraph{Diagnostic criterion.}
51	Proposition~\ref{prop:debiasing_hurts} provides a $\Delta\tau$-free diagnostic: global correction harms subgroup $s$ if and only if $|\delta_s| / ((1-2\bar{\pi}) \cdot \pi_s) > 1$, a condition depending only on per-subgroup misclassification rates estimable from a pilot sample.
52	This breaks the circular dependency that would arise if the diagnostic required CATE estimates.
53	A threshold classifier achieves AUC~=~0.86 at the subgroup level, reaching 1.0 when restricted to subgroups with $\tau_s > 0$ (Section~\ref{sec:diagnostic}).
54	
55	\paragraph{Composition with PPCI.}
56	EC-HTE corrects structured covariate misclassification through $\hat{C}_s^{-1}$ inversion but cannot address outcome-level measurement error.
57	PPCI~\cite{sui2026ppci} corrects residual outcome bias using a debiasing estimator but assumes correct covariate labels.
58	The two methods are complementary: apply EC-HTE first to correct covariate labels, then PPCI to correct outcome predictions.
59	Neither is redundant with the other: EC-HTE alone cannot fix outcome error, while PPCI alone incurs higher variance for covariate error.
60	Under both error types simultaneously, the composition reduces $|\text{bias}|$ from 0.179 to 0.007 (Appendix~\ref{sec:ppci}).
61	The two methods target different error sources and are not substitutes: under covariate-side error alone (DGP~A), EC-HTE provides a 38\% RMSE advantage over PPCI; under outcome-side error alone (DGP~B), PPCI achieves $|\text{bias}| = 0.015$--$0.020$ and EC-HTE's marginal contribution is negligible.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "6c292b3b-198c-4c18-b645-8f36c1c77cdd",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/method.tex",
      "content": "\\section{Correction Prescribed by the Identity}\n\\label{sec:method}\n\nTheorem~\\ref{thm:bias_identity} identifies per-subgroup misclassification deviation as the bias source; the natural correction is per-subgroup confusion matrix inversion.\nThis correction (EC-HTE) proceeds in three stages: estimate per-subgroup confusion matrices via hierarchical Bayes, invert them to correct observed outcome moments, and propagate correction uncertainty into downstream causal estimators.\nThe complete procedure is summarized in Algorithm~\\ref{alg:echte} (Appendix~\\ref{app:algorithm}).\n\n\\subsection{Hierarchical Bayes Confusion Matrix Estimation}\n\nWe place a Dirichlet-Multinomial hierarchical model over the confusion matrices $\\{C_s\\}_{s=1}^K$.\nFor each subgroup $s$, row $j$ of $C_s$ has a Dirichlet prior centered at the global pooled confusion matrix $\\hat{C}_{\\text{global}}$: $\\text{Dir}(\\alpha_0 \\cdot \\hat{C}_{\\text{global},j})$, where $\\hat{C}_{\\text{global},j}$ is the $j$-th row of the pooled CM and $\\alpha_0 > 0$ is a shared concentration parameter estimated via empirical Bayes (marginal likelihood maximization).\nWe place a $\\mathrm{Gamma}(a_0, b_0)$ hyperprior on $\\alpha_0$ with defaults $a_0 = 3$, $b_0 = 1$, robust to $2\\times$ perturbation of $(a_0, b_0)$ (RMSE change $<$5\\%; Table~\\ref{tab:hyperprior_sweep}, Appendix~\\ref{app:hyperprior}).\nLarge $\\alpha_0$ pulls subgroup estimates toward $\\hat{C}_{\\text{global}}$ (global correction), while small $\\alpha_0$ allows subgroup-specific rates to dominate (stratified correction).\nThis partial pooling---James-Stein shrinkage, a standard technique in small-area estimation applied here to per-subgroup confusion matrix estimation for causal inference---borrows strength across subgroups from limited expert labels, reducing variance for small subgroups while preserving heterogeneity where data support it.\n\nPosterior inference uses centered empirical Bayes optimization ($<$5ms for $K{=}4$, $N{=}5{,}000$); a full Gibbs MCMC alternative requires $\\sim$5s (full MCMC specification in Appendix~\\ref{app:mcmc}; algorithm in Appendix~\\ref{app:algorithm}).\nBootstrap SE ($B{=}100$) adds $\\sim$0.4s.\nHB estimation outperforms stratified MLE in 87.5\\% of configurations (21 of 24) across the experimental grid (Section~\\ref{sec:ec_hte_eval}), with the largest gains when $n_{\\text{expert}} / K < 100$.\nThe advantage requires $n_{\\text{expert}} \\times P(Z_{\\text{minority}}) / K \\geq 25$ per subgroup; below this threshold, stratified MLE is preferred because the hierarchical model lacks sufficient observations for stable shrinkage.\nAt $n_{\\text{expert}} \\geq 1000$, HB and stratified MLE converge to within 0.5\\% on all metrics.\nSensitivity analysis shows $<$5\\% RMSE variation under 2$\\times$ hyperprior perturbation, confirming that results are not driven by prior specification.\n\n\\subsection{Subgroup-Stratified Correction}\n\nGiven posterior mean confusion matrices $\\hat{C}_s$, we correct observed outcome moments per subgroup by matrix inversion:\n\\begin{equation}\n\\tilde{\\boldsymbol{\\mu}}_s = \\hat{C}_s^{-1} \\cdot \\hat{\\boldsymbol{\\mu}}_s,\n\\end{equation}\nwhere $\\hat{\\boldsymbol{\\mu}}_s = [\\hat{\\tau}_{\\text{obs}}(0, s),\\, \\hat{\\tau}_{\\text{obs}}(1, s)]^\\top$ collects the observed conditional outcome moments in subgroup $s$.\nThis requires $\\det(\\hat{C}_s) \\neq 0$ for all $s$, which holds under assumption~(A4) ($\\pi_s \\neq 0.5$) but may fail in finite samples when error rates approach degeneracy.\nIn practice, Laplace smoothing of the confusion matrix counts ensures finite-sample invertibility.\nWe impose a singularity guard: if the condition number $\\kappa(\\hat{C}_s) > 100$ (for a $2{\\times}2$ symmetric confusion matrix, this corresponds to $\\pi_s > 0.495$, i.e., near-random classification), subgroup $s$ falls back to global correction $\\bar{C}^{-1}$; when the fallback triggers, the standard error computation also uses $\\bar{C}^{-1}$ for that subgroup, ensuring consistency between point estimates and confidence intervals.\nThis hard guard prevents numerical catastrophe; $\\kappa \\leq 1.25$ is a sufficient condition for strongest bias reduction (Appendix~\\ref{sec:budget}), though EC-HTE maintains calibrated coverage ($\\geq$93\\%) across the wider $\\kappa \\in [1.4, 3.0]$ range observed in practice (Appendix~\\ref{app:kappa_analysis}).\n\nThe contrast with global correction is direct.\nGlobal correction applies $\\bar{C}^{-1}$ uniformly to all subgroups, introducing the $\\delta_s \\cdot \\Delta\\tau$ bias identified in Theorem~\\ref{thm:bias_identity}.\nSubgroup-stratified correction eliminates this bias by matching each subgroup's correction to its own misclassification structure, at the cost of higher variance from estimating $K$ separate confusion matrices (Appendix~\\ref{sec:budget}).\n\n\\subsection{Variance-Adjusted CausalForest}\n\nFor heterogeneous treatment effect estimation, we feed corrected covariates into CausalForestDML~\\cite{wager2018causal} with honest splitting.\nThe forest produces per-observation standard error estimates $\\text{se}_i$.\nTo account for confusion matrix correction, we propagate uncertainty through the inverse mapping:\n\\begin{equation}\n\\text{se}_{\\text{corrected},i} = \\sqrt{\\text{diag}\\!\\left(\\hat{C}_{S_i}^{-1}\\, \\text{diag}(\\text{se}_i^2)\\, \\hat{C}_{S_i}^{-\\top}\\right)}.\n\\end{equation}\nThis plug-in SE conditions on $\\hat{C}_s$, neglecting CM estimation uncertainty; at $n_{\\text{expert}} \\geq 100$ this is negligible, but below this threshold a full bootstrap ($B{=}100$; re-estimate CM and re-fit per replicate) maintains $\\geq$95\\% coverage across all budgets tested ($n_{\\text{expert}} \\in \\{25, 50, 75, 100, 200\\}$); even plug-in SE achieves $\\geq$91\\% at $n_{\\text{expert}}{=}25$ (Appendix~\\ref{app:bootstrap_se}).\nWhen $n_{\\text{expert}}/K < 50$, we recommend bootstrap SE; otherwise plug-in SE suffices.\n\n\\paragraph{Diagnostic criterion.}\nProposition~\\ref{prop:debiasing_hurts} provides a $\\Delta\\tau$-free diagnostic: global correction harms subgroup $s$ if and only if $|\\delta_s| / ((1-2\\bar{\\pi}) \\cdot \\pi_s) > 1$, a condition depending only on per-subgroup misclassification rates estimable from a pilot sample.\nThis breaks the circular dependency that would arise if the diagnostic required CATE estimates.\nA threshold classifier achieves AUC~=~0.86 at the subgroup level, reaching 1.0 when restricted to subgroups with $\\tau_s > 0$ (Section~\\ref{sec:diagnostic}).\n\n\\paragraph{Composition with PPCI.}\nEC-HTE corrects structured covariate misclassification through $\\hat{C}_s^{-1}$ inversion but cannot address outcome-level measurement error.\nPPCI~\\cite{sui2026ppci} corrects residual outcome bias using a debiasing estimator but assumes correct covariate labels.\nThe two methods are complementary: apply EC-HTE first to correct covariate labels, then PPCI to correct outcome predictions.\nNeither is redundant with the other: EC-HTE alone cannot fix outcome error, while PPCI alone incurs higher variance for covariate error.\nUnder both error types simultaneously, the composition reduces $|\\text{bias}|$ from 0.179 to 0.007 (Appendix~\\ref{sec:ppci}).\nThe two methods target different error sources and are not substitutes: under covariate-side error alone (DGP~A), EC-HTE provides a 38\\% RMSE advantage over PPCI; under outcome-side error alone (DGP~B), PPCI achieves $|\\text{bias}| = 0.015$--$0.020$ and EC-HTE's marginal contribution is negligible.",
      "numLines": 61,
      "startLine": 1,
      "totalLines": 61
    }
  }
}
```

</details>

---

### Tool call

_source line 15_

<details open><summary>🔧 Tool call — Read · `toolu_01GjvkaBW7kFSBNYFKnoxXh3`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/theory.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "c2551456-e4c4-46fe-98a5-7fe43f6c95dc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011won9p5f9sA8Gcan4dngKR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12675,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12675
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

_source line 16 · 2026-05-24T07:59:42.897Z_

<details><summary>↩ Tool result · `toolu_01GjvkaBW7kFSBNYFKnoxXh3`</summary>

```text
1	% Requires preamble: \usepackage{amsthm,amsmath,amssymb}
2	% and: \newtheorem{theorem}{Theorem}
3	%      \newtheorem{corollary}[theorem]{Corollary}
4	%      \newtheorem{proposition}[theorem]{Proposition}
5	
6	\section{Bias Decomposition: When Debiasing Hurts}
7	\label{sec:theory}
8	
9	We formalize the bias that global misclassification correction introduces when subgroup error rates are heterogeneous.
10	Consider estimating the conditional average treatment effect (CATE) $\tau(z) = \mathbb{E}[Y(1) - Y(0) \mid Z = z]$, where $Z \in \{0, 1\}$ is a binary effect modifier observed only through a noisy annotation $\hat{Z}$.
11	The population consists of $K$ subgroups $S \in \{1, \ldots, K\}$ with weights $w_s = P(S{=}s)$, each characterized by a $2 \times 2$ confusion matrix $C_s$ with symmetric error rate $\pi_s = P(\hat{Z} \neq Z \mid S{=}s)$.
12	Standard practice estimates a single confusion matrix $\bar{C} = \sum_s w_s C_s$ from expert annotations and applies its inverse uniformly to all observations, with pooled error rate $\bar{\pi} = \sum_s w_s \pi_s$.
13	We show that when error rates vary across subgroups, this global procedure introduces a bias with an exact product form.
14	
15	We state five assumptions maintained throughout.
16	%
17	\begin{itemize}
18	\item[\textbf{(A1)}] \textit{Conditional independence:} misclassification depends only on the true label $Z$ and subgroup $S$, not on potential outcomes $Y(0), Y(1)$.
19	\item[\textbf{(A2)}] \textit{Symmetric misclassification:} $P(\hat{Z}{=}1 \mid Z{=}0, S{=}s) = P(\hat{Z}{=}0 \mid Z{=}1, S{=}s) = \pi_s$ for all $s$ (diagnostic only; see Remark~2).
20	\item[\textbf{(A3)}] \textit{Balanced effect modifier:} $P(Z{=}0) = P(Z{=}1) = 0.5$. This simplifies the exposition; we discuss relaxation below.
21	\item[\textbf{(A4)}] \textit{Non-degeneracy:} $\pi_s \neq 0.5$ for all $s$, ensuring each $C_s$ is invertible.
22	\item[\textbf{(A5)}] \textit{Homogeneous treatment effects across subgroups:} $\tau(z, s) = \tau(z)$ for all $s$, so $\Delta\tau = \tau(1) - \tau(0)$ is a scalar.
23	\end{itemize}
24	
25	Under (A2)--(A3), the Bayesian mixing matrix $M_s$ (entries $M_s[\hat{z}, z] = P(Z{=}z \mid \hat{Z}{=}\hat{z}, S{=}s)$) coincides with $C_s$.
26	The global mixing matrix is $M_{\text{global}} = \sum_s w_s M_s$.
27	
28	\begin{theorem}[Bias Decomposition Identity]
29	\label{thm:bias_identity}
30	Under \textnormal{(A1)--(A5)}, the bias of global correction in subgroup $s$ at effect-modifier level $z$ is
31	\begin{align}
32	\mathrm{bias}_{\mathrm{global}}(z{=}0, s) &= +\frac{\delta_s \cdot \Delta\tau}{1 - 2\bar{\pi}}, \label{eq:bias_z0} \\
33	\mathrm{bias}_{\mathrm{global}}(z{=}1, s) &= -\frac{\delta_s \cdot \Delta\tau}{1 - 2\bar{\pi}}, \label{eq:bias_z1}
34	\end{align}
35	where $\delta_s = \pi_s - \bar{\pi}$ is the subgroup deviation from the pooled error rate and $\Delta\tau = \tau(1) - \tau(0)$ is the CATE heterogeneity.
36	\end{theorem}
37	
38	Equations~\eqref{eq:bias_z0}--\eqref{eq:bias_z1} constitute an exact finite-population identity, not an asymptotic approximation or bound.
39	The bias factors into three interpretable components: $\delta_s$ captures how much subgroup $s$ deviates from the average misclassification rate, $\Delta\tau$ captures treatment effect heterogeneity across levels of $Z$, and $1/(1 - 2\bar{\pi})$ is an amplification factor from matrix inversion.
40	Bias vanishes when either source of variation is absent ($\delta_s = 0$ or $\Delta\tau = 0$), and arises only through their interaction.
41	Theorem~\ref{thm:bias_identity} implies that global correction trades one source of confounding for another: it removes attenuation from label noise but introduces a new bias from error-rate heterogeneity.
42	
43	\paragraph{Proof sketch.}
44	Global correction applies $M_{\text{global}}^{-1}$ to the subgroup-specific observed CATE $\tau_{\text{obs}}(\cdot, s) = M_s \cdot \tau_{\text{true}}$, yielding bias $(M_{\text{global}}^{-1} M_s - I) \cdot \tau_{\text{true}}$.
45	Direct computation shows $M_{\text{global}}^{-1} M_s - I = \frac{\delta_s}{1-2\bar{\pi}} \bigl[\begin{smallmatrix} -1 & 1 \\ 1 & -1 \end{smallmatrix}\bigr]$.
46	Applying this matrix to $[\tau(0),\, \tau(1)]^\top$ produces the product form.
47	The full derivation appears in Appendix~\ref{app:derivation}.
48	For comparison with classical scalar attenuation~\citep{frazis2003estimating}, see Section~\ref{sec:related}.
49	
50	\paragraph{Relationship to classical scalar attenuation.}
51	Classical scalar attenuation~\citep{frazis2003estimating} gives $\beta^* = \beta(1 - 2\pi)$; dividing by $(1 - 2\bar{\pi})$ removes this bias under homogeneous errors, but Theorem~\ref{thm:bias_identity} characterizes a structurally distinct quantity: \emph{correction-induced} bias from applying $M_{\mathrm{global}}^{-1}$ to heterogeneous $M_s$.
52	F-L scalar correction (dividing $\hat{\tau}(z)$ by $1 - 2\bar{\pi}$) over-corrects low-error and under-corrects high-error subgroups---the same mechanism as global CM correction but restricted to a scalar ignoring the mixing structure between $z$-levels.
53	When $\pi_s \to 0.5$, $(1 - 2\pi_s) \to 0$ and the F-L per-subgroup correction diverges; EC-HTE's $\kappa$-guard (Section~\ref{sec:method}) avoids this singularity.
54	Table~\ref{tab:main_results} confirms: under extreme heterogeneity ($K{=}2$), the classical F-L scalar correction \emph{increases} $|\text{bias}|$ from 0.058 to 0.122 ($2.1\times$ naive), and F-L per-subgroup to 0.168 ($2.9\times$)---the textbook attenuation correction systematically amplifies bias when subgroup error rates differ.
55	
56	\begin{remark}
57	Theorem~\ref{thm:bias_identity} does not require assumption~(A2).
58	For arbitrary asymmetric confusion matrices ($\mathrm{FPR}_s \neq \mathrm{FNR}_s$),
59	the product form $\mathrm{bias}(z, s) = \Delta\tau \cdot [B_s]_{z,1}$ holds exactly,
60	where $B_s = M_{\mathrm{global}}^{-1} M_s - I$, because $B_s \mathbf{1} = \mathbf{0}$
61	follows from stochasticity of $M_s$ and $M_{\mathrm{global}}$ alone.
62	Assumption~(A2) simplifies $[B_s]_{z,1}$ to the scalar
63	$\pm \delta_s / (1 - 2\bar{\pi})$ but is not necessary for the product structure.
64	Under asymmetric errors, the diagnostic (Proposition~\ref{prop:debiasing_hurts}) requires evaluating $[B_s]_{z,1}$ cell-by-cell rather than via a single scalar threshold; the AUC decreases from 0.86 to 0.66 (Appendix~\ref{app:asymmetric}), reflecting the additional complexity of cell-specific error rates.
65	For binary effect modifiers ($|\mathcal{Z}|{=}2$), the asymmetric score $|[B_s]_{z,1}|$ reduces to a monotone transform of the symmetric score $|\delta_s|/((1{-}2\bar{\pi})\pi_s)$, because column-stochastic $M$ forces $|B_s[0,1]|{=}|B_s[1,1]|$; practitioners may use the simpler symmetric formula without loss.
66	See Appendix~\ref{app:asymmetric} for the full derivation and empirical verification
67	($R^2 = 0.991$).
68	\end{remark}
69	
70	\begin{proposition}[Exact Identity under Heterogeneous Treatment Effects]
71	\label{prop:a5_relaxation}
72	When $\tau(z, s)$ varies across subgroups (relaxing A5), the bias identity remains exact:
73	\begin{equation}
74	\mathrm{bias}_{\mathrm{global}}(z{=}0, s) = +\frac{\delta_s \cdot \Delta\tau_s}{1 - 2\bar{\pi}}, \quad
75	\mathrm{bias}_{\mathrm{global}}(z{=}1, s) = -\frac{\delta_s \cdot \Delta\tau_s}{1 - 2\bar{\pi}},
76	\end{equation}
77	where $\Delta\tau_s = \tau_s(1) - \tau_s(0)$ is the subgroup-specific CATE heterogeneity.
78	\end{proposition}
79	
80	\begin{corollary}[Aggregate Bias]
81	\label{cor:aggregate_bias}
82	The population-weighted aggregate bias is $\mathrm{Cov}_w(\pi_s, \Delta\tau_s) / (1 - 2\bar{\pi})$.
83	\end{corollary}
84	
85	The proof is immediate: $B_s = M_{\mathrm{global}}^{-1} M_s - I$ depends only on confusion matrices, not on $\tau$.
86	The diagnostic (Proposition~\ref{prop:debiasing_hurts}) extends unchanged: $\Delta\tau_s$ cancels, so~\eqref{eq:hurts_condition} remains $\Delta\tau$-free.
87	EC-HTE maintains $\geq$93\% coverage under both positive and negative $\Delta\tau_s$--$\delta_s$ correlation (Appendix~\ref{app:a5_violation}).
88	
89	The identity extends to $K > 2$ subgroups with $J$ effect-modifier levels; the multi-class bias retains the same product structure with modified amplification terms (Corollary~\ref{cor:multiclass} in Appendix~\ref{app:multiclass}).
90	
91	Assumption~(A3) ensures $M_s = C_s$; when $P(Z{=}1) \neq 0.5$, the mixing matrices acquire asymmetric entries, but the product structure persists with modified coefficients (Appendix~\ref{app:derivation}).
92	Empirical verification under class imbalance (Appendix~\ref{app:classimbalance}) shows $R^2 \geq 0.976$ even at $P(Z{=}1) = 0.1$ for $K{=}2$, though EC-HTE's RMSE ratio relative to global correction increases to 1.06--1.68 as imbalance grows.
93	Empirical verification (Section~\ref{sec:bias_mechanism}) yields $R^2 = 0.994$ for $K{=}2$ and $R^2 = 0.97$ for $K{=}4$, closing the theory-practice gap to essentially zero; the residual variance reflects Monte Carlo noise, not model misspecification.
94	
95	\paragraph{Sensitivity to (A1).}
96	Assumption~(A1) is not empirically testable.
97	If misclassification correlates with potential outcomes ($\gamma = \mathrm{Corr}(\mathbb{1}[\hat{Z} {\neq} Z],\, Y(1){-}Y(0) \mid Z, S) \neq 0$), Theorem~\ref{thm:bias_identity} gains an $O(\gamma)$ perturbation; in NLP settings, this is plausible when LLM accuracy varies with outcome magnitude.
98	At $\gamma_T = 0.10$, EC-HTE coverage degrades to 75\% (full sensitivity in Table~\ref{tab:treatment_dep}, Appendix~\ref{app:treatment_dep}); sensitivity analysis frameworks~\cite{lash2009applying,dorn2022sharp,cinelli2020making} can bound the degradation (Section~\ref{sec:limitations}).
99	
100	\paragraph{Finite-sample remainder.}
101	Theorem~\ref{thm:bias_identity} is a population-level identity.
102	In practice, confusion matrices are estimated from $n_{\text{expert}}$ expert labels with $\hat{C}_s = C_s + E_s$, $\|E_s\| = O_p(n_{\text{expert}}^{-1/2})$; the resulting remainder is therefore $R_n = O_p(n_{\text{expert}}^{-1/2} \cdot \kappa(C_s))$, motivating the singularity guard ($\kappa > 100 \to$ fallback) in Section~\ref{sec:method}.
103	
104	\begin{proposition}[Debiasing Can Increase Bias]
105	\label{prop:debiasing_hurts}
106	Under \textnormal{(A1)--(A5)}, global correction produces larger absolute bias than the naive estimator ($|\mathrm{bias}_{\mathrm{global}}| > |\mathrm{bias}_{\mathrm{naive}}|$) in subgroup $s$ if and only if
107	\begin{equation}
108	\frac{|\delta_s|}{(1 - 2\bar{\pi}) \cdot \pi_s} > 1.
109	\label{eq:hurts_condition}
110	\end{equation}
111	\end{proposition}
112	
113	Equation~\eqref{eq:hurts_condition} partitions subgroups into two regimes:
114	\begin{itemize}
115	    \item \textit{High-error} ($\pi_s > \bar{\pi}$): the condition reduces to $\pi_s > 0.5$, excluded by~(A4); global correction always reduces bias.
116	    \item \textit{Low-error} ($\pi_s < \bar{\pi}$): the condition holds whenever $\pi_s < \bar{\pi} / (2(1 - \bar{\pi}))$---easily satisfied: when $\bar{\pi} = 0.15$, any subgroup with $\pi_s < 0.088$ is harmed by global correction.
117	\end{itemize}
118	The mechanism is over-correction: for subgroups with near-zero misclassification ($\pi_s \approx 0$), the naive estimator is nearly unbiased, yet global inversion calibrated for $\bar{\pi}$ creates substantial bias---debiasing is worse than doing nothing, and can reverse bias sign across subgroups.
119	
120	In our experiments (Section~\ref{sec:bias_mechanism}), global correction increases bias in 50\% of $K{=}2$ configurations (260/520), with amplification reaching $2.86\times$ ($K{=}2$) and $2.41\times$ ($K{=}4$); Figure~\ref{fig:heatmap} visualizes the full parameter grid.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "c57d45a6-0134-4b4d-b15f-752e81981eb0",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/theory.tex",
      "content": "% Requires preamble: \\usepackage{amsthm,amsmath,amssymb}\n% and: \\newtheorem{theorem}{Theorem}\n%      \\newtheorem{corollary}[theorem]{Corollary}\n%      \\newtheorem{proposition}[theorem]{Proposition}\n\n\\section{Bias Decomposition: When Debiasing Hurts}\n\\label{sec:theory}\n\nWe formalize the bias that global misclassification correction introduces when subgroup error rates are heterogeneous.\nConsider estimating the conditional average treatment effect (CATE) $\\tau(z) = \\mathbb{E}[Y(1) - Y(0) \\mid Z = z]$, where $Z \\in \\{0, 1\\}$ is a binary effect modifier observed only through a noisy annotation $\\hat{Z}$.\nThe population consists of $K$ subgroups $S \\in \\{1, \\ldots, K\\}$ with weights $w_s = P(S{=}s)$, each characterized by a $2 \\times 2$ confusion matrix $C_s$ with symmetric error rate $\\pi_s = P(\\hat{Z} \\neq Z \\mid S{=}s)$.\nStandard practice estimates a single confusion matrix $\\bar{C} = \\sum_s w_s C_s$ from expert annotations and applies its inverse uniformly to all observations, with pooled error rate $\\bar{\\pi} = \\sum_s w_s \\pi_s$.\nWe show that when error rates vary across subgroups, this global procedure introduces a bias with an exact product form.\n\nWe state five assumptions maintained throughout.\n%\n\\begin{itemize}\n\\item[\\textbf{(A1)}] \\textit{Conditional independence:} misclassification depends only on the true label $Z$ and subgroup $S$, not on potential outcomes $Y(0), Y(1)$.\n\\item[\\textbf{(A2)}] \\textit{Symmetric misclassification:} $P(\\hat{Z}{=}1 \\mid Z{=}0, S{=}s) = P(\\hat{Z}{=}0 \\mid Z{=}1, S{=}s) = \\pi_s$ for all $s$ (diagnostic only; see Remark~2).\n\\item[\\textbf{(A3)}] \\textit{Balanced effect modifier:} $P(Z{=}0) = P(Z{=}1) = 0.5$. This simplifies the exposition; we discuss relaxation below.\n\\item[\\textbf{(A4)}] \\textit{Non-degeneracy:} $\\pi_s \\neq 0.5$ for all $s$, ensuring each $C_s$ is invertible.\n\\item[\\textbf{(A5)}] \\textit{Homogeneous treatment effects across subgroups:} $\\tau(z, s) = \\tau(z)$ for all $s$, so $\\Delta\\tau = \\tau(1) - \\tau(0)$ is a scalar.\n\\end{itemize}\n\nUnder (A2)--(A3), the Bayesian mixing matrix $M_s$ (entries $M_s[\\hat{z}, z] = P(Z{=}z \\mid \\hat{Z}{=}\\hat{z}, S{=}s)$) coincides with $C_s$.\nThe global mixing matrix is $M_{\\text{global}} = \\sum_s w_s M_s$.\n\n\\begin{theorem}[Bias Decomposition Identity]\n\\label{thm:bias_identity}\nUnder \\textnormal{(A1)--(A5)}, the bias of global correction in subgroup $s$ at effect-modifier level $z$ is\n\\begin{align}\n\\mathrm{bias}_{\\mathrm{global}}(z{=}0, s) &= +\\frac{\\delta_s \\cdot \\Delta\\tau}{1 - 2\\bar{\\pi}}, \\label{eq:bias_z0} \\\\\n\\mathrm{bias}_{\\mathrm{global}}(z{=}1, s) &= -\\frac{\\delta_s \\cdot \\Delta\\tau}{1 - 2\\bar{\\pi}}, \\label{eq:bias_z1}\n\\end{align}\nwhere $\\delta_s = \\pi_s - \\bar{\\pi}$ is the subgroup deviation from the pooled error rate and $\\Delta\\tau = \\tau(1) - \\tau(0)$ is the CATE heterogeneity.\n\\end{theorem}\n\nEquations~\\eqref{eq:bias_z0}--\\eqref{eq:bias_z1} constitute an exact finite-population identity, not an asymptotic approximation or bound.\nThe bias factors into three interpretable components: $\\delta_s$ captures how much subgroup $s$ deviates from the average misclassification rate, $\\Delta\\tau$ captures treatment effect heterogeneity across levels of $Z$, and $1/(1 - 2\\bar{\\pi})$ is an amplification factor from matrix inversion.\nBias vanishes when either source of variation is absent ($\\delta_s = 0$ or $\\Delta\\tau = 0$), and arises only through their interaction.\nTheorem~\\ref{thm:bias_identity} implies that global correction trades one source of confounding for another: it removes attenuation from label noise but introduces a new bias from error-rate heterogeneity.\n\n\\paragraph{Proof sketch.}\nGlobal correction applies $M_{\\text{global}}^{-1}$ to the subgroup-specific observed CATE $\\tau_{\\text{obs}}(\\cdot, s) = M_s \\cdot \\tau_{\\text{true}}$, yielding bias $(M_{\\text{global}}^{-1} M_s - I) \\cdot \\tau_{\\text{true}}$.\nDirect computation shows $M_{\\text{global}}^{-1} M_s - I = \\frac{\\delta_s}{1-2\\bar{\\pi}} \\bigl[\\begin{smallmatrix} -1 & 1 \\\\ 1 & -1 \\end{smallmatrix}\\bigr]$.\nApplying this matrix to $[\\tau(0),\\, \\tau(1)]^\\top$ produces the product form.\nThe full derivation appears in Appendix~\\ref{app:derivation}.\nFor comparison with classical scalar attenuation~\\citep{frazis2003estimating}, see Section~\\ref{sec:related}.\n\n\\paragraph{Relationship to classical scalar attenuation.}\nClassical scalar attenuation~\\citep{frazis2003estimating} gives $\\beta^* = \\beta(1 - 2\\pi)$; dividing by $(1 - 2\\bar{\\pi})$ removes this bias under homogeneous errors, but Theorem~\\ref{thm:bias_identity} characterizes a structurally distinct quantity: \\emph{correction-induced} bias from applying $M_{\\mathrm{global}}^{-1}$ to heterogeneous $M_s$.\nF-L scalar correction (dividing $\\hat{\\tau}(z)$ by $1 - 2\\bar{\\pi}$) over-corrects low-error and under-corrects high-error subgroups---the same mechanism as global CM correction but restricted to a scalar ignoring the mixing structure between $z$-levels.\nWhen $\\pi_s \\to 0.5$, $(1 - 2\\pi_s) \\to 0$ and the F-L per-subgroup correction diverges; EC-HTE's $\\kappa$-guard (Section~\\ref{sec:method}) avoids this singularity.\nTable~\\ref{tab:main_results} confirms: under extreme heterogeneity ($K{=}2$), the classical F-L scalar correction \\emph{increases} $|\\text{bias}|$ from 0.058 to 0.122 ($2.1\\times$ naive), and F-L per-subgroup to 0.168 ($2.9\\times$)---the textbook attenuation correction systematically amplifies bias when subgroup error rates differ.\n\n\\begin{remark}\nTheorem~\\ref{thm:bias_identity} does not require assumption~(A2).\nFor arbitrary asymmetric confusion matrices ($\\mathrm{FPR}_s \\neq \\mathrm{FNR}_s$),\nthe product form $\\mathrm{bias}(z, s) = \\Delta\\tau \\cdot [B_s]_{z,1}$ holds exactly,\nwhere $B_s = M_{\\mathrm{global}}^{-1} M_s - I$, because $B_s \\mathbf{1} = \\mathbf{0}$\nfollows from stochasticity of $M_s$ and $M_{\\mathrm{global}}$ alone.\nAssumption~(A2) simplifies $[B_s]_{z,1}$ to the scalar\n$\\pm \\delta_s / (1 - 2\\bar{\\pi})$ but is not necessary for the product structure.\nUnder asymmetric errors, the diagnostic (Proposition~\\ref{prop:debiasing_hurts}) requires evaluating $[B_s]_{z,1}$ cell-by-cell rather than via a single scalar threshold; the AUC decreases from 0.86 to 0.66 (Appendix~\\ref{app:asymmetric}), reflecting the additional complexity of cell-specific error rates.\nFor binary effect modifiers ($|\\mathcal{Z}|{=}2$), the asymmetric score $|[B_s]_{z,1}|$ reduces to a monotone transform of the symmetric score $|\\delta_s|/((1{-}2\\bar{\\pi})\\pi_s)$, because column-stochastic $M$ forces $|B_s[0,1]|{=}|B_s[1,1]|$; practitioners may use the simpler symmetric formula without loss.\nSee Appendix~\\ref{app:asymmetric} for the full derivation and empirical verification\n($R^2 = 0.991$).\n\\end{remark}\n\n\\begin{proposition}[Exact Identity under Heterogeneous Treatment Effects]\n\\label{prop:a5_relaxation}\nWhen $\\tau(z, s)$ varies across subgroups (relaxing A5), the bias identity remains exact:\n\\begin{equation}\n\\mathrm{bias}_{\\mathrm{global}}(z{=}0, s) = +\\frac{\\delta_s \\cdot \\Delta\\tau_s}{1 - 2\\bar{\\pi}}, \\quad\n\\mathrm{bias}_{\\mathrm{global}}(z{=}1, s) = -\\frac{\\delta_s \\cdot \\Delta\\tau_s}{1 - 2\\bar{\\pi}},\n\\end{equation}\nwhere $\\Delta\\tau_s = \\tau_s(1) - \\tau_s(0)$ is the subgroup-specific CATE heterogeneity.\n\\end{proposition}\n\n\\begin{corollary}[Aggregate Bias]\n\\label{cor:aggregate_bias}\nThe population-weighted aggregate bias is $\\mathrm{Cov}_w(\\pi_s, \\Delta\\tau_s) / (1 - 2\\bar{\\pi})$.\n\\end{corollary}\n\nThe proof is immediate: $B_s = M_{\\mathrm{global}}^{-1} M_s - I$ depends only on confusion matrices, not on $\\tau$.\nThe diagnostic (Proposition~\\ref{prop:debiasing_hurts}) extends unchanged: $\\Delta\\tau_s$ cancels, so~\\eqref{eq:hurts_condition} remains $\\Delta\\tau$-free.\nEC-HTE maintains $\\geq$93\\% coverage under both positive and negative $\\Delta\\tau_s$--$\\delta_s$ correlation (Appendix~\\ref{app:a5_violation}).\n\nThe identity extends to $K > 2$ subgroups with $J$ effect-modifier levels; the multi-class bias retains the same product structure with modified amplification terms (Corollary~\\ref{cor:multiclass} in Appendix~\\ref{app:multiclass}).\n\nAssumption~(A3) ensures $M_s = C_s$; when $P(Z{=}1) \\neq 0.5$, the mixing matrices acquire asymmetric entries, but the product structure persists with modified coefficients (Appendix~\\ref{app:derivation}).\nEmpirical verification under class imbalance (Appendix~\\ref{app:classimbalance}) shows $R^2 \\geq 0.976$ even at $P(Z{=}1) = 0.1$ for $K{=}2$, though EC-HTE's RMSE ratio relative to global correction increases to 1.06--1.68 as imbalance grows.\nEmpirical verification (Section~\\ref{sec:bias_mechanism}) yields $R^2 = 0.994$ for $K{=}2$ and $R^2 = 0.97$ for $K{=}4$, closing the theory-practice gap to essentially zero; the residual variance reflects Monte Carlo noise, not model misspecification.\n\n\\paragraph{Sensitivity to (A1).}\nAssumption~(A1) is not empirically testable.\nIf misclassification correlates with potential outcomes ($\\gamma = \\mathrm{Corr}(\\mathbb{1}[\\hat{Z} {\\neq} Z],\\, Y(1){-}Y(0) \\mid Z, S) \\neq 0$), Theorem~\\ref{thm:bias_identity} gains an $O(\\gamma)$ perturbation; in NLP settings, this is plausible when LLM accuracy varies with outcome magnitude.\nAt $\\gamma_T = 0.10$, EC-HTE coverage degrades to 75\\% (full sensitivity in Table~\\ref{tab:treatment_dep}, Appendix~\\ref{app:treatment_dep}); sensitivity analysis frameworks~\\cite{lash2009applying,dorn2022sharp,cinelli2020making} can bound the degradation (Section~\\ref{sec:limitations}).\n\n\\paragraph{Finite-sample remainder.}\nTheorem~\\ref{thm:bias_identity} is a population-level identity.\nIn practice, confusion matrices are estimated from $n_{\\text{expert}}$ expert labels with $\\hat{C}_s = C_s + E_s$, $\\|E_s\\| = O_p(n_{\\text{expert}}^{-1/2})$; the resulting remainder is therefore $R_n = O_p(n_{\\text{expert}}^{-1/2} \\cdot \\kappa(C_s))$, motivating the singularity guard ($\\kappa > 100 \\to$ fallback) in Section~\\ref{sec:method}.\n\n\\begin{proposition}[Debiasing Can Increase Bias]\n\\label{prop:debiasing_hurts}\nUnder \\textnormal{(A1)--(A5)}, global correction produces larger absolute bias than the naive estimator ($|\\mathrm{bias}_{\\mathrm{global}}| > |\\mathrm{bias}_{\\mathrm{naive}}|$) in subgroup $s$ if and only if\n\\begin{equation}\n\\frac{|\\delta_s|}{(1 - 2\\bar{\\pi}) \\cdot \\pi_s} > 1.\n\\label{eq:hurts_condition}\n\\end{equation}\n\\end{proposition}\n\nEquation~\\eqref{eq:hurts_condition} partitions subgroups into two regimes:\n\\begin{itemize}\n    \\item \\textit{High-error} ($\\pi_s > \\bar{\\pi}$): the condition reduces to $\\pi_s > 0.5$, excluded by~(A4); global correction always reduces bias.\n    \\item \\textit{Low-error} ($\\pi_s < \\bar{\\pi}$): the condition holds whenever $\\pi_s < \\bar{\\pi} / (2(1 - \\bar{\\pi}))$---easily satisfied: when $\\bar{\\pi} = 0.15$, any subgroup with $\\pi_s < 0.088$ is harmed by global correction.\n\\end{itemize}\nThe mechanism is over-correction: for subgroups with near-zero misclassification ($\\pi_s \\approx 0$), the naive estimator is nearly unbiased, yet global inversion calibrated for $\\bar{\\pi}$ creates substantial bias---debiasing is worse than doing nothing, and can reverse bias sign across subgroups.\n\nIn our experiments (Section~\\ref{sec:bias_mechanism}), global correction increases bias in 50\\% of $K{=}2$ configurations (260/520), with amplification reaching $2.86\\times$ ($K{=}2$) and $2.41\\times$ ($K{=}4$); Figure~\\ref{fig:heatmap} visualizes the full parameter grid.",
      "numLines": 120,
      "startLine": 1,
      "totalLines": 120
    }
  }
}
```

</details>

---

### Assistant

_source line 17_

<details><summary>Logged reasoning block</summary>

```text
Now I need to read the appendix. It's too large to read at once. Let me search for specific sections related to the negative experiments.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "f8769915-00f5-42bd-8e3e-1de66bdc7ef0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TS1fdTysxNUTYpkxxrdCKU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11764,
      "cache_read_input_tokens": 24516,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11764
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

_source line 18_

Now let me search the appendix for the specific relevant sections.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "edcb06b1-29eb-4b97-a19d-d0406c0e7b9b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TS1fdTysxNUTYpkxxrdCKU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11764,
      "cache_read_input_tokens": 24516,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11764
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

_source line 19_

<details open><summary>🔧 Tool call — Grep · `toolu_016vftGDhN3x3oubSPeVV7yy`</summary>

```json
{
  "pattern": "k8|K=8|K{=}8|app:k8",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "568e54e4-cb9b-4608-9e58-79cec9b47b24",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TS1fdTysxNUTYpkxxrdCKU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11764,
      "cache_read_input_tokens": 24516,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11764
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

_source line 20 · 2026-05-24T07:59:58.909Z_

<details><summary>↩ Tool result · `toolu_016vftGDhN3x3oubSPeVV7yy`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "6eddb915-e156-460b-b03d-492cfb4cac74",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Tool call

_source line 21_

<details open><summary>🔧 Tool call — Grep · `toolu_01JvF7j8UWHkUD7VL81seR3a`</summary>

```json
{
  "pattern": "asymmetric|app:asymmetric|B_s",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "e8c87681-042c-41a0-a425-105fde6669a8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TS1fdTysxNUTYpkxxrdCKU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11764,
      "cache_read_input_tokens": 24516,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11764
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

_source line 22 · 2026-05-24T08:00:00.307Z_

<details><summary>↩ Tool result · `toolu_01JvF7j8UWHkUD7VL81seR3a`</summary>

```text
144:For non-uniform off-diagonal entries, the scalar amplification $g(\bar{\pi})$ generalizes to a cell-specific matrix; the product structure $B_s \cdot \Delta\tau$ persists but a closed-form amplification factor does not. \qed
168:\paragraph{Extension to asymmetric misclassification.}
170:Under asymmetric misclassification ($\mathrm{FPR}_s \neq \mathrm{FNR}_s$), the naive bias becomes $\mathrm{bias}_{\mathrm{naive}}(0,s) = \mathrm{FPR}_s \cdot \tau(1) + (1 - \mathrm{FPR}_s - 1)\tau(0)$ and the global correction bias depends on the full $2 \times 2$ structure of $B_s = M_{\mathrm{global}}^{-1} M_s - I$ (Remark~1 in Section~\ref{sec:theory}).
173:\|B_s\|_\infty > \max(\mathrm{FPR}_s, \mathrm{FNR}_s),
176:In the asymmetric experiments (Appendix~\ref{app:asymmetric}), the symmetric diagnostic still achieves AUC $= 0.66$ when applied with $\pi_s = (\mathrm{FPR}_s + \mathrm{FNR}_s)/2$, suggesting practical robustness.
177:A fully general asymmetric diagnostic that accounts for the separate roles of FPR and FNR in each entry of $B_s$ is left to future work.
315:\paragraph{Cost-asymmetric diagnostic thresholds.}
443:\label{app:asymmetric}
446:Real LLM annotators typically exhibit asymmetric confusion patterns; we show here that the product structure generalizes.
449:For asymmetric confusion matrices $C_s = \bigl(\begin{smallmatrix} 1{-}\text{FPR}_s & \text{FPR}_s \\ \text{FNR}_s & 1{-}\text{FNR}_s \end{smallmatrix}\bigr)$, define the mixing matrix $M_s$ via Bayesian inversion and the residual matrix $B_s = M_{\text{global}}^{-1} M_s - I$.
450:Since both $M_s$ and $M_{\text{global}}$ are row-stochastic, $B_s \mathbf{1} = \mathbf{0}$.
453:\text{bias}(z, s) = \Delta\tau \cdot [B_s]_{z,1},
455:where $[B_s]_{z,1}$ depends only on $\{\text{FPR}_k, \text{FNR}_k, w_k\}$, not on $\Delta\tau$.
459:We test three asymmetric configurations ($K{=}2$, $n_{\text{expert}}{=}250$, 100 MC runs each): \emph{Cross} (FPR/FNR = 0.10/0.20 vs.\ 0.25/0.10), \emph{Co-directional} (0.05/0.15 vs.\ 0.20/0.30), and \emph{Extreme} (0.03/0.25 vs.\ 0.30/0.05).
461:Table~\ref{tab:asymmetric} reports correction performance averaged over subgroups, $z$-levels, and $\Delta\tau \in \{0.1, \ldots, 0.5\}$.
467:\label{tab:asymmetric}
754:We test EC-HTE with empirical asymmetric confusion matrices from the GPT-4.1 TweetEval pilot.
973:Theorem~\ref{thm:bias_identity} is derived under symmetric misclassification (A2); real LLM confusion matrices are asymmetric (FPR $\neq$ FNR).
974:[Omitted long matching line]
976:Table~\ref{tab:realcm_r2} reports per-model $R^2$ from regressing observed subgroup bias on the predicted value $\Delta\tau \cdot [B_s]_{z,1}$.
978:The single outlier (GPT-4o-mini on Civil Comments, $R^2{=}0.76$) has near-homogeneous subgroup error rates ($\max|[B_s]_{z,1}| = 0.089$), so predicted biases are small and Monte Carlo noise dominates the regression.
979:$R^2$ correlates strongly with $\max|[B_s]_{z,1}|$: models with more heterogeneous per-subgroup error rates produce larger bias signals that are easier to verify empirically.
988:Model & Dataset & $R^2$ & $\max|[B_s]_{z,1}|$ \\
1446:\label{app:asymmetric_endtoend}
1448:We validate EC-HTE under strongly asymmetric confusion matrices ($\text{FPR}/\text{FNR}$ ratio up to $7{:}1$), simulating the error profile of GPT-4.1 on Civil Comments.
1450:We compare EC-HTE using the full $2{\times}2$ asymmetric CM (Remark~2) against the symmetric assumption ($\text{FPR}{=}\text{FNR}{=}\pi_s$).
1454:\caption{EC-HTE under asymmetric misclassification ($\text{FPR}/\text{FNR}$ up to $7{:}1$). The asymmetric formula improves coverage by $+1.5$pp and RMSE by $11.5\%$.}
1455:\label{tab:asymmetric_endtoend}
1462:EC-HTE (asymmetric) & 0.057 & 0.074 & \textbf{0.945} \\
1464:Global (asymmetric) & 0.061 & 0.076 & 0.915 \\
1471:EC-HTE with the asymmetric formula achieves 94.5\% coverage versus 93.0\% under the symmetric assumption ($+1.5$pp), with RMSE improved from 0.083 to 0.074 ($-11.5\%$).
1472:The improvement concentrates in the high-error subgroup ($s_1$): asymmetric coverage is 93.0\% vs.\ symmetric 91.0\%.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "55f0ba2c-07f6-4f1d-8336-b511f18f34bc",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "144:For non-uniform off-diagonal entries, the scalar amplification $g(\\bar{\\pi})$ generalizes to a cell-specific matrix; the product structure $B_s \\cdot \\Delta\\tau$ persists but a closed-form amplification factor does not. \\qed\n168:\\paragraph{Extension to asymmetric misclassification.}\n170:Under asymmetric misclassification ($\\mathrm{FPR}_s \\neq \\mathrm{FNR}_s$), the naive bias becomes $\\mathrm{bias}_{\\mathrm{naive}}(0,s) = \\mathrm{FPR}_s \\cdot \\tau(1) + (1 - \\mathrm{FPR}_s - 1)\\tau(0)$ and the global correction bias depends on the full $2 \\times 2$ structure of $B_s = M_{\\mathrm{global}}^{-1} M_s - I$ (Remark~1 in Section~\\ref{sec:theory}).\n173:\\|B_s\\|_\\infty > \\max(\\mathrm{FPR}_s, \\mathrm{FNR}_s),\n176:In the asymmetric experiments (Appendix~\\ref{app:asymmetric}), the symmetric diagnostic still achieves AUC $= 0.66$ when applied with $\\pi_s = (\\mathrm{FPR}_s + \\mathrm{FNR}_s)/2$, suggesting practical robustness.\n177:A fully general asymmetric diagnostic that accounts for the separate roles of FPR and FNR in each entry of $B_s$ is left to future work.\n315:\\paragraph{Cost-asymmetric diagnostic thresholds.}\n443:\\label{app:asymmetric}\n446:Real LLM annotators typically exhibit asymmetric confusion patterns; we show here that the product structure generalizes.\n449:For asymmetric confusion matrices $C_s = \\bigl(\\begin{smallmatrix} 1{-}\\text{FPR}_s & \\text{FPR}_s \\\\ \\text{FNR}_s & 1{-}\\text{FNR}_s \\end{smallmatrix}\\bigr)$, define the mixing matrix $M_s$ via Bayesian inversion and the residual matrix $B_s = M_{\\text{global}}^{-1} M_s - I$.\n450:Since both $M_s$ and $M_{\\text{global}}$ are row-stochastic, $B_s \\mathbf{1} = \\mathbf{0}$.\n453:\\text{bias}(z, s) = \\Delta\\tau \\cdot [B_s]_{z,1},\n455:where $[B_s]_{z,1}$ depends only on $\\{\\text{FPR}_k, \\text{FNR}_k, w_k\\}$, not on $\\Delta\\tau$.\n459:We test three asymmetric configurations ($K{=}2$, $n_{\\text{expert}}{=}250$, 100 MC runs each): \\emph{Cross} (FPR/FNR = 0.10/0.20 vs.\\ 0.25/0.10), \\emph{Co-directional} (0.05/0.15 vs.\\ 0.20/0.30), and \\emph{Extreme} (0.03/0.25 vs.\\ 0.30/0.05).\n461:Table~\\ref{tab:asymmetric} reports correction performance averaged over subgroups, $z$-levels, and $\\Delta\\tau \\in \\{0.1, \\ldots, 0.5\\}$.\n467:\\label{tab:asymmetric}\n754:We test EC-HTE with empirical asymmetric confusion matrices from the GPT-4.1 TweetEval pilot.\n973:Theorem~\\ref{thm:bias_identity} is derived under symmetric misclassification (A2); real LLM confusion matrices are asymmetric (FPR $\\neq$ FNR).\n974:[Omitted long matching line]\n976:Table~\\ref{tab:realcm_r2} reports per-model $R^2$ from regressing observed subgroup bias on the predicted value $\\Delta\\tau \\cdot [B_s]_{z,1}$.\n978:The single outlier (GPT-4o-mini on Civil Comments, $R^2{=}0.76$) has near-homogeneous subgroup error rates ($\\max|[B_s]_{z,1}| = 0.089$), so predicted biases are small and Monte Carlo noise dominates the regression.\n979:$R^2$ correlates strongly with $\\max|[B_s]_{z,1}|$: models with more heterogeneous per-subgroup error rates produce larger bias signals that are easier to verify empirically.\n988:Model & Dataset & $R^2$ & $\\max|[B_s]_{z,1}|$ \\\\\n1446:\\label{app:asymmetric_endtoend}\n1448:We validate EC-HTE under strongly asymmetric confusion matrices ($\\text{FPR}/\\text{FNR}$ ratio up to $7{:}1$), simulating the error profile of GPT-4.1 on Civil Comments.\n1450:We compare EC-HTE using the full $2{\\times}2$ asymmetric CM (Remark~2) against the symmetric assumption ($\\text{FPR}{=}\\text{FNR}{=}\\pi_s$).\n1454:\\caption{EC-HTE under asymmetric misclassification ($\\text{FPR}/\\text{FNR}$ up to $7{:}1$). The asymmetric formula improves coverage by $+1.5$pp and RMSE by $11.5\\%$.}\n1455:\\label{tab:asymmetric_endtoend}\n1462:EC-HTE (asymmetric) & 0.057 & 0.074 & \\textbf{0.945} \\\\\n1464:Global (asymmetric) & 0.061 & 0.076 & 0.915 \\\\\n1471:EC-HTE with the asymmetric formula achieves 94.5\\% coverage versus 93.0\\% under the symmetric assumption ($+1.5$pp), with RMSE improved from 0.083 to 0.074 ($-11.5\\%$).\n1472:The improvement concentrates in the high-error subgroup ($s_1$): asymmetric coverage is 93.0\\% vs.\\ symmetric 91.0\\%.",
    "numLines": 32
  }
}
```

</details>

---

### Tool call

_source line 23_

<details open><summary>🔧 Tool call — Grep · `toolu_01EyibwP71kmKSQfqr8HJRnc`</summary>

```json
{
  "pattern": "real.*CM|real.*confusion|semireal|realcm|GPT-4|gpt-3\\.5|FNR.*0\\.5|P\\(Z=1\\).*0\\.18|class.?imbalance",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true,
  "-i": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "d71e7801-97a7-4d5e-8d60-f36abc2bfb4f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TS1fdTysxNUTYpkxxrdCKU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11764,
      "cache_read_input_tokens": 24516,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11764
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

_source line 24 · 2026-05-24T08:00:05.569Z_

<details><summary>↩ Tool result · `toolu_01EyibwP71kmKSQfqr8HJRnc`</summary>

```text
11:\State \textbf{Preconditions:} verify $n_{\text{expert}} \times P(Z_{\text{minority}}) / K \geq 25$ and $\max_s(\text{FPR}_s, \text{FNR}_s) < 0.5$; if either fails, use global correction
446:Real LLM annotators typically exhibit asymmetric confusion patterns; we show here that the product structure generalizes.
560:We apply EC-HTE to the UC Berkeley Measuring Hate Speech corpus~\cite{kennedy2020constructing}, annotating 2{,}496 comments for dehumanization using GPT-4.1.
596:GPT-3.5-Turbo & 0.198 & \checkmark \\
597:GPT-4-Turbo & 0.149 & \checkmark \\
598:GPT-4o-mini & 0.136 & \checkmark \\
600:GPT-4.1 & 0.098 & \checkmark \\
601:GPT-4o & 0.080 & \checkmark \\
607:Newer models reduce absolute error rates but do not eliminate subgroup heterogeneity: GPT-5.4 achieves $\Delta\pi = 0.114$ compared to GPT-3.5-Turbo's $0.198$.
751:\section{Semi-Real Confusion Matrix Validation}
752:\label{app:semireal}
754:We test EC-HTE with empirical asymmetric confusion matrices from the GPT-4.1 TweetEval pilot.
755:Four text-feature subgroups ($K{=}4$) retain the real per-subgroup FPR and FNR from pilot annotations (Table~\ref{tab:semireal_cm}); CATE heterogeneity is injected synthetically ($\tau(z{=}0,s) = 0.3 + 0.1s$, $\tau(z{=}1,s) = 0.8 - 0.15s$).
760:\caption{Empirical confusion matrices from GPT-4.1 TweetEval pilot.
761:S0 exhibits FNR $= 0.526$, approaching chance-level classification.}
762:\label{tab:semireal_cm}
778:\caption{Semi-real confusion matrix results. RMSE and coverage averaged over subgroups and $z$-levels (100 MC runs). HB EC-HTE underperforms global at all budgets; S0's near-chance FNR drives the failure.}
779:\label{tab:semireal}
806:HB EC-HTE produces higher RMSE and lower coverage than global correction at all expert budgets (Table~\ref{tab:semireal}).
807:The root cause is S0's FNR $= 0.526$: when a confusion matrix row approaches a uniform distribution ($P(\hat{Z}{=}1 \mid Z{=}1) \approx 0.5$), inversion amplifies estimation noise regardless of the expert budget.
813:A second semi-real experiment using GPT-3.5-Turbo confusion matrices (worst-subgroup FPR $= 0.39$, FNR $= 0.21$) yields similar results: HB RMSE exceeds global by 1.3--3.5$\times$ at all budgets.
814:Here the failure stems from high false-positive rates compounded by class imbalance ($P(Z{=}1) = 0.18$), which leaves insufficient expert observations in the positive class for reliable per-subgroup confusion matrix estimation.
815:Together, these experiments identify three applicability conditions for EC-HTE: (1)~sufficient effective expert budget ($n_{\text{expert}} \times P(Z_{\text{minority}}) / K \geq 25$), (2)~no near-chance subgroup error rate ($\max(\text{FPR}_s, \text{FNR}_s) < 0.5$), and (3)~adequate class balance in the effect modifier.
818:A logistic regression over all 368 semi-real experiment--budget cells (dependent variable: HB EC-HTE $<$ Global RMSE) identifies two sufficient statistics: the worst-subgroup confusion matrix condition number $\kappa(\hat{M}_s) \leq 1.25$ and the effective minority-class expert count $n_{\text{expert}} \times P(Z_{\text{minority}}) / K \geq 25$.
821:Subgroup-average metrics can mask cell-level heterogeneity: in exp-015, HB EC-HTE substantially reduces bias for the three well-classified subgroups (S1--S3) but amplifies variance in the near-degenerate subgroup (S0, FNR $= 0.526$), and the S0 penalty dominates the aggregate RMSE.
826:\caption{Applicability frontier of EC-HTE. Green region: EC-HTE reduces bias vs.\ global correction. Yellow: comparable performance. Red: EC-HTE underperforms. Dashed lines mark the expert budget threshold ($n_{\text{expert}}/K = 25$) and classifier quality threshold (worst-subgroup error rate $= 0.5$). Red diamonds show semi-real experiments with actual GPT-4.1 and GPT-3.5-Turbo confusion matrices.}
884:\section{Robustness to Class Imbalance}
885:\label{app:classimbalance}
892:\caption{Robustness to class imbalance ($n_{\text{expert}}{=}250$, extreme heterogeneity). R$^2$: Theorem~\ref{thm:bias_identity} fit. Ratio: HB/Global RMSE ($<1$ = HB wins). Cov.: HB EC-HTE 95\% CI coverage.}
946:GPT-4o-mini and GPT-3.5-turbo show pronounced FPR/FNR asymmetry (e.g., GPT-4o-mini FPR $\in [0.42, 0.61]$ vs.\ FNR $\in [0.05, 0.16]$), indicating systematic over-prediction of toxicity; their FPR approaches 0.5, placing them in the ill-conditioned regime where confusion matrix inversion amplifies noise (consistent with the classifier quality threshold discussed in the Limitations section).
958:GPT-4o & FPR & 0.249 & 0.157 & 0.213 & 0.341 & 0.184 \\
961:GPT-4o-mini & FPR & 0.517 & 0.541 & 0.419 & 0.610 & 0.191 \\
964:GPT-3.5-turbo & FPR & 0.400 & 0.473 & 0.374 & 0.468 & 0.099 \\
970:\section{Bias Identity Validation with Real Confusion Matrices}
971:\label{app:realcm_bias}
973:Theorem~\ref{thm:bias_identity} is derived under symmetric misclassification (A2); real LLM confusion matrices are asymmetric (FPR $\neq$ FNR).
974:[Omitted long matching line]
976:Table~\ref{tab:realcm_r2} reports per-model $R^2$ from regressing observed subgroup bias on the predicted value $\Delta\tau \cdot [B_s]_{z,1}$.
978:The single outlier (GPT-4o-mini on Civil Comments, $R^2{=}0.76$) has near-homogeneous subgroup error rates ($\max|[B_s]_{z,1}| = 0.089$), so predicted biases are small and Monte Carlo noise dominates the regression.
983:\caption{Bias identity $R^2$ with real LLM confusion matrices ($K{=}4$, 100 MC runs).}
984:\label{tab:realcm_r2}
990:GPT-4-turbo  & TweetEval & 0.993 & 0.328 \\
994:GPT-4o       & Civil Comments & 0.979 & 0.198 \\
995:GPT-4o       & TweetEval & 0.975 & 0.240 \\
996:GPT-4.1      & TweetEval & 0.969 & 0.139 \\
997:GPT-3.5-turbo & TweetEval & 0.948 & 0.087 \\
998:GPT-3.5-turbo & Civil Comments & 0.935 & 0.170 \\
999:GPT-4o-mini  & TweetEval & 0.929 & 0.170 \\
1000:GPT-4o-mini  & Civil Comments & 0.756 & 0.089 \\
1007:\section{Applicability Screening with Real LLM Confusion Matrices}
1030:GPT-3.5-turbo & CivilComm. & 4 & {\small$\times$} & {\small$\checkmark$} & {\small$\checkmark$} & {\small$\times$} \\
1031:GPT-3.5-turbo & TweetEval & 4 & {\small$\times$} & {\small$\checkmark$} & {\small$\checkmark$} & {\small$\times$} \\
1032:GPT-4-turbo  & TweetEval & 4 & {\small$\times$} & {\small$\times$} & {\small$\checkmark$} & {\small$\times$} \\
1033:GPT-4.1      & TweetEval & 4 & {\small$\times$} & {\small$\times$} & {\small$\checkmark$} & {\small$\times$} \\
1034:GPT-4o       & CivilComm. & 4 & {\small$\times$} & {\small$\checkmark$} & {\small$\checkmark$} & {\small$\times$} \\
1035:GPT-4o       & TweetEval & 4 & {\small$\times$} & {\small$\times$} & {\small$\checkmark$} & {\small$\times$} \\
1036:GPT-4o-mini  & CivilComm. & 4 & {\small$\times$} & {\small$\times$} & {\small$\checkmark$} & {\small$\times$} \\
1037:GPT-4o-mini  & TweetEval & 4 & {\small$\times$} & {\small$\checkmark$} & {\small$\checkmark$} & {\small$\times$} \\
1045:Under a relaxed ``oracle screening'' that excludes near-degenerate subgroups ($\max(\mathrm{FPR}_s, \mathrm{FNR}_s) \geq 0.4$), we run semi-synthetic CATE estimation ($N{=}5{,}000$, $\Delta\tau{=}0.3$, 100 MC runs, $n_{\text{expert}} \in \{250, 500\}$) with each LLM's real per-subgroup confusion matrix.
1047:The four open-source LLMs on TweetEval show the strongest EC-HTE advantage (32/32 comparisons, RMSE reduction 0.001--0.008), while GPT-3.5-turbo/TweetEval (high FPR asymmetry, $\mathrm{FPR}_{\max}{=}0.39$) and GPT-4o/Civil Comments (low minority prevalence $P(Z{=}1){=}0.3$) show degradation.
1051:The diagnostic (Proposition~\ref{prop:debiasing_hurts}) degrades on real LLM confusion matrices (pooled AUC $= 0.63$) because the failure mode is systematic: subgroups where the true CATE heterogeneity $\tau_s \approx 0$ are hurt by global correction (since $\delta_s \neq 0$ still introduces bias), yet these subgroups produce low diagnostic scores---the diagnostic ranks them as safe precisely when they are most vulnerable to overcorrection.
1086:\paragraph{Real LLM confusion matrices.}
1448:We validate EC-HTE under strongly asymmetric confusion matrices ($\text{FPR}/\text{FNR}$ ratio up to $7{:}1$), simulating the error profile of GPT-4.1 on Civil Comments.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "e7c3b228-b408-4dfe-966e-c33e564dfbc3",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "11:\\State \\textbf{Preconditions:} verify $n_{\\text{expert}} \\times P(Z_{\\text{minority}}) / K \\geq 25$ and $\\max_s(\\text{FPR}_s, \\text{FNR}_s) < 0.5$; if either fails, use global correction\n446:Real LLM annotators typically exhibit asymmetric confusion patterns; we show here that the product structure generalizes.\n560:We apply EC-HTE to the UC Berkeley Measuring Hate Speech corpus~\\cite{kennedy2020constructing}, annotating 2{,}496 comments for dehumanization using GPT-4.1.\n596:GPT-3.5-Turbo & 0.198 & \\checkmark \\\\\n597:GPT-4-Turbo & 0.149 & \\checkmark \\\\\n598:GPT-4o-mini & 0.136 & \\checkmark \\\\\n600:GPT-4.1 & 0.098 & \\checkmark \\\\\n601:GPT-4o & 0.080 & \\checkmark \\\\\n607:Newer models reduce absolute error rates but do not eliminate subgroup heterogeneity: GPT-5.4 achieves $\\Delta\\pi = 0.114$ compared to GPT-3.5-Turbo's $0.198$.\n751:\\section{Semi-Real Confusion Matrix Validation}\n752:\\label{app:semireal}\n754:We test EC-HTE with empirical asymmetric confusion matrices from the GPT-4.1 TweetEval pilot.\n755:Four text-feature subgroups ($K{=}4$) retain the real per-subgroup FPR and FNR from pilot annotations (Table~\\ref{tab:semireal_cm}); CATE heterogeneity is injected synthetically ($\\tau(z{=}0,s) = 0.3 + 0.1s$, $\\tau(z{=}1,s) = 0.8 - 0.15s$).\n760:\\caption{Empirical confusion matrices from GPT-4.1 TweetEval pilot.\n761:S0 exhibits FNR $= 0.526$, approaching chance-level classification.}\n762:\\label{tab:semireal_cm}\n778:\\caption{Semi-real confusion matrix results. RMSE and coverage averaged over subgroups and $z$-levels (100 MC runs). HB EC-HTE underperforms global at all budgets; S0's near-chance FNR drives the failure.}\n779:\\label{tab:semireal}\n806:HB EC-HTE produces higher RMSE and lower coverage than global correction at all expert budgets (Table~\\ref{tab:semireal}).\n807:The root cause is S0's FNR $= 0.526$: when a confusion matrix row approaches a uniform distribution ($P(\\hat{Z}{=}1 \\mid Z{=}1) \\approx 0.5$), inversion amplifies estimation noise regardless of the expert budget.\n813:A second semi-real experiment using GPT-3.5-Turbo confusion matrices (worst-subgroup FPR $= 0.39$, FNR $= 0.21$) yields similar results: HB RMSE exceeds global by 1.3--3.5$\\times$ at all budgets.\n814:Here the failure stems from high false-positive rates compounded by class imbalance ($P(Z{=}1) = 0.18$), which leaves insufficient expert observations in the positive class for reliable per-subgroup confusion matrix estimation.\n815:Together, these experiments identify three applicability conditions for EC-HTE: (1)~sufficient effective expert budget ($n_{\\text{expert}} \\times P(Z_{\\text{minority}}) / K \\geq 25$), (2)~no near-chance subgroup error rate ($\\max(\\text{FPR}_s, \\text{FNR}_s) < 0.5$), and (3)~adequate class balance in the effect modifier.\n818:A logistic regression over all 368 semi-real experiment--budget cells (dependent variable: HB EC-HTE $<$ Global RMSE) identifies two sufficient statistics: the worst-subgroup confusion matrix condition number $\\kappa(\\hat{M}_s) \\leq 1.25$ and the effective minority-class expert count $n_{\\text{expert}} \\times P(Z_{\\text{minority}}) / K \\geq 25$.\n821:Subgroup-average metrics can mask cell-level heterogeneity: in exp-015, HB EC-HTE substantially reduces bias for the three well-classified subgroups (S1--S3) but amplifies variance in the near-degenerate subgroup (S0, FNR $= 0.526$), and the S0 penalty dominates the aggregate RMSE.\n826:\\caption{Applicability frontier of EC-HTE. Green region: EC-HTE reduces bias vs.\\ global correction. Yellow: comparable performance. Red: EC-HTE underperforms. Dashed lines mark the expert budget threshold ($n_{\\text{expert}}/K = 25$) and classifier quality threshold (worst-subgroup error rate $= 0.5$). Red diamonds show semi-real experiments with actual GPT-4.1 and GPT-3.5-Turbo confusion matrices.}\n884:\\section{Robustness to Class Imbalance}\n885:\\label{app:classimbalance}\n892:\\caption{Robustness to class imbalance ($n_{\\text{expert}}{=}250$, extreme heterogeneity). R$^2$: Theorem~\\ref{thm:bias_identity} fit. Ratio: HB/Global RMSE ($<1$ = HB wins). Cov.: HB EC-HTE 95\\% CI coverage.}\n946:GPT-4o-mini and GPT-3.5-turbo show pronounced FPR/FNR asymmetry (e.g., GPT-4o-mini FPR $\\in [0.42, 0.61]$ vs.\\ FNR $\\in [0.05, 0.16]$), indicating systematic over-prediction of toxicity; their FPR approaches 0.5, placing them in the ill-conditioned regime where confusion matrix inversion amplifies noise (consistent with the classifier quality threshold discussed in the Limitations section).\n958:GPT-4o & FPR & 0.249 & 0.157 & 0.213 & 0.341 & 0.184 \\\\\n961:GPT-4o-mini & FPR & 0.517 & 0.541 & 0.419 & 0.610 & 0.191 \\\\\n964:GPT-3.5-turbo & FPR & 0.400 & 0.473 & 0.374 & 0.468 & 0.099 \\\\\n970:\\section{Bias Identity Validation with Real Confusion Matrices}\n971:\\label{app:realcm_bias}\n973:Theorem~\\ref{thm:bias_identity} is derived under symmetric misclassification (A2); real LLM confusion matrices are asymmetric (FPR $\\neq$ FNR).\n974:[Omitted long matching line]\n976:Table~\\ref{tab:realcm_r2} reports per-model $R^2$ from regressing observed subgroup bias on the predicted value $\\Delta\\tau \\cdot [B_s]_{z,1}$.\n978:The single outlier (GPT-4o-mini on Civil Comments, $R^2{=}0.76$) has near-homogeneous subgroup error rates ($\\max|[B_s]_{z,1}| = 0.089$), so predicted biases are small and Monte Carlo noise dominates the regression.\n983:\\caption{Bias identity $R^2$ with real LLM confusion matrices ($K{=}4$, 100 MC runs).}\n984:\\label{tab:realcm_r2}\n990:GPT-4-turbo  & TweetEval & 0.993 & 0.328 \\\\\n994:GPT-4o       & Civil Comments & 0.979 & 0.198 \\\\\n995:GPT-4o       & TweetEval & 0.975 & 0.240 \\\\\n996:GPT-4.1      & TweetEval & 0.969 & 0.139 \\\\\n997:GPT-3.5-turbo & TweetEval & 0.948 & 0.087 \\\\\n998:GPT-3.5-turbo & Civil Comments & 0.935 & 0.170 \\\\\n999:GPT-4o-mini  & TweetEval & 0.929 & 0.170 \\\\\n1000:GPT-4o-mini  & Civil Comments & 0.756 & 0.089 \\\\\n1007:\\section{Applicability Screening with Real LLM Confusion Matrices}\n1030:GPT-3.5-turbo & CivilComm. & 4 & {\\small$\\times$} & {\\small$\\checkmark$} & {\\small$\\checkmark$} & {\\small$\\times$} \\\\\n1031:GPT-3.5-turbo & TweetEval & 4 & {\\small$\\times$} & {\\small$\\checkmark$} & {\\small$\\checkmark$} & {\\small$\\times$} \\\\\n1032:GPT-4-turbo  & TweetEval & 4 & {\\small$\\times$} & {\\small$\\times$} & {\\small$\\checkmark$} & {\\small$\\times$} \\\\\n1033:GPT-4.1      & TweetEval & 4 & {\\small$\\times$} & {\\small$\\times$} & {\\small$\\checkmark$} & {\\small$\\times$} \\\\\n1034:GPT-4o       & CivilComm. & 4 & {\\small$\\times$} & {\\small$\\checkmark$} & {\\small$\\checkmark$} & {\\small$\\times$} \\\\\n1035:GPT-4o       & TweetEval & 4 & {\\small$\\times$} & {\\small$\\times$} & {\\small$\\checkmark$} & {\\small$\\times$} \\\\\n1036:GPT-4o-mini  & CivilComm. & 4 & {\\small$\\times$} & {\\small$\\times$} & {\\small$\\checkmark$} & {\\small$\\times$} \\\\\n1037:GPT-4o-mini  & TweetEval & 4 & {\\small$\\times$} & {\\small$\\checkmark$} & {\\small$\\checkmark$} & {\\small$\\times$} \\\\\n1045:Under a relaxed ``oracle screening'' that excludes near-degenerate subgroups ($\\max(\\mathrm{FPR}_s, \\mathrm{FNR}_s) \\geq 0.4$), we run semi-synthetic CATE estimation ($N{=}5{,}000$, $\\Delta\\tau{=}0.3$, 100 MC runs, $n_{\\text{expert}} \\in \\{250, 500\\}$) with each LLM's real per-subgroup confusion matrix.\n1047:The four open-source LLMs on TweetEval show the strongest EC-HTE advantage (32/32 comparisons, RMSE reduction 0.001--0.008), while GPT-3.5-turbo/TweetEval (high FPR asymmetry, $\\mathrm{FPR}_{\\max}{=}0.39$) and GPT-4o/Civil Comments (low minority prevalence $P(Z{=}1){=}0.3$) show degradation.\n1051:The diagnostic (Proposition~\\ref{prop:debiasing_hurts}) degrades on real LLM confusion matrices (pooled AUC $= 0.63$) because the failure mode is systematic: subgroups where the true CATE heterogeneity $\\tau_s \\approx 0$ are hurt by global correction (since $\\delta_s \\neq 0$ still introduces bias), yet these subgroups produce low diagnostic scores---the diagnostic ranks them as safe precisely when they are most vulnerable to overcorrection.\n1086:\\paragraph{Real LLM confusion matrices.}\n1448:We validate EC-HTE under strongly asymmetric confusion matrices ($\\text{FPR}/\\text{FNR}$ ratio up to $7{:}1$), simulating the error profile of GPT-4.1 on Civil Comments.",
    "numLines": 63
  }
}
```

</details>

---

### Tool call

_source line 25_

<details open><summary>🔧 Tool call — Grep · `toolu_01LDAkuCiFqYK9NryNxMq34D`</summary>

```json
{
  "pattern": "shrinkage|adaptive|PPCI.*composition|HB.*backfill",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "c7bacbe9-86bc-427c-b979-920e2048d09a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TS1fdTysxNUTYpkxxrdCKU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11764,
      "cache_read_input_tokens": 24516,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11764
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

_source line 26 · 2026-05-24T08:00:05.806Z_

<details><summary>↩ Tool result · `toolu_01LDAkuCiFqYK9NryNxMq34D`</summary>

```text
42:The adaptive formula $\kappa_{\text{adapt}} = 10 \sqrt{n_{\text{expert}} / K}$ recovers $\kappa{=}100$ for this regime and scales naturally with the estimation precision.
235:\citet{zrnic2024cross} extend PPI via cross-prediction; their active inference framework~\citep{zrnic2024active} achieves $>$80\% expert budget savings through adaptive allocation, complementary to our fixed-budget analysis.
257:Appendix robustness experiments use a fixed Dirichlet prior ($\alpha{=}3$); since fixed-$\alpha$ partial pooling is weakly dominated by the adaptive variant, these results are conservative.
405:HB partial pooling achieves a 47\% RMSE reduction over stratified MLE (0.340 vs.\ 0.638), confirming that hierarchical shrinkage provides substantial regularization.
434:HB partial pooling reduces MLE RMSE by 24--54\% in the high-$\pi$ regime ($s_4$--$s_7$), confirming that hierarchical shrinkage provides meaningful regularization even when per-subgroup labels are scarce.
436:Adaptive shrinkage---increasing the prior strength for high-$\pi$ subgroups where CM estimation is least reliable---is a natural extension that may close the RMSE gap with global correction at larger $K$.
438:We explored adaptive shrinkage ($\alpha{=}10$ for high-$\pi$ subgroups vs.\ default $\alpha{=}3$), which reduces aggregate RMSE from 0.340 to 0.216 (35\% improvement) by attenuating estimation noise in high-$\pi$ subgroups.
439:However, RMSE remains 30\% above global correction (0.166), confirming that the bottleneck is per-subgroup sample size (${\sim}$31 expert labels) rather than the shrinkage method itself.
702:At $p_{\text{flip}} = 0.50$, subgroup structure is effectively destroyed; EC-HTE converges to global correction (coverage and RMSE within 0.1\%), confirming that hierarchical Bayesian shrinkage provides a built-in safety mechanism.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "4c386e50-499f-4ece-8228-15c3170ce775",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "42:The adaptive formula $\\kappa_{\\text{adapt}} = 10 \\sqrt{n_{\\text{expert}} / K}$ recovers $\\kappa{=}100$ for this regime and scales naturally with the estimation precision.\n235:\\citet{zrnic2024cross} extend PPI via cross-prediction; their active inference framework~\\citep{zrnic2024active} achieves $>$80\\% expert budget savings through adaptive allocation, complementary to our fixed-budget analysis.\n257:Appendix robustness experiments use a fixed Dirichlet prior ($\\alpha{=}3$); since fixed-$\\alpha$ partial pooling is weakly dominated by the adaptive variant, these results are conservative.\n405:HB partial pooling achieves a 47\\% RMSE reduction over stratified MLE (0.340 vs.\\ 0.638), confirming that hierarchical shrinkage provides substantial regularization.\n434:HB partial pooling reduces MLE RMSE by 24--54\\% in the high-$\\pi$ regime ($s_4$--$s_7$), confirming that hierarchical shrinkage provides meaningful regularization even when per-subgroup labels are scarce.\n436:Adaptive shrinkage---increasing the prior strength for high-$\\pi$ subgroups where CM estimation is least reliable---is a natural extension that may close the RMSE gap with global correction at larger $K$.\n438:We explored adaptive shrinkage ($\\alpha{=}10$ for high-$\\pi$ subgroups vs.\\ default $\\alpha{=}3$), which reduces aggregate RMSE from 0.340 to 0.216 (35\\% improvement) by attenuating estimation noise in high-$\\pi$ subgroups.\n439:However, RMSE remains 30\\% above global correction (0.166), confirming that the bottleneck is per-subgroup sample size (${\\sim}$31 expert labels) rather than the shrinkage method itself.\n702:At $p_{\\text{flip}} = 0.50$, subgroup structure is effectively destroyed; EC-HTE converges to global correction (coverage and RMSE within 0.1\\%), confirming that hierarchical Bayesian shrinkage provides a built-in safety mechanism.",
    "numLines": 9
  }
}
```

</details>

---

### Assistant

_source line 27_

<details><summary>Logged reasoning block</summary>

```text
Let me now read the specific appendix sections about K=8, semi-real CM, and the PPCI composition to get the exact line numbers.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "eb21ce70-89ca-43e3-9d87-b3c6d59dc5d1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ASqLn5zJExMCmvgrjsQmRq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6228,
      "cache_read_input_tokens": 36280,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6228
      },
      "output_tokens": 10,
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

_source line 28_

Let me read the specific appendix sections for K=8 and semi-real CM validation.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "6f53087e-628d-433e-b450-a9a3c08674c1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ASqLn5zJExMCmvgrjsQmRq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6228,
      "cache_read_input_tokens": 36280,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6228
      },
      "output_tokens": 10,
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

<details open><summary>🔧 Tool call — Grep · `toolu_01AC3KjHGFM6DDcsbjdgUoBL`</summary>

```json
{
  "pattern": "\\\\\\\\label\\{app:k8|\\\\\\\\section.*K.*8|\\\\\\\\subsection.*K.*8|subgroups.*scalability",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "801b1e44-eded-4ba6-974d-f59d0da36701",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ASqLn5zJExMCmvgrjsQmRq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6228,
      "cache_read_input_tokens": 36280,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6228
      },
      "output_tokens": 10,
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

_source line 30 · 2026-05-24T08:00:13.281Z_

<details><summary>↩ Tool result · `toolu_01AC3KjHGFM6DDcsbjdgUoBL`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "0cfe19c8-e938-4a5f-aa67-03d1e7001aa1",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Tool call

_source line 31_

<details open><summary>🔧 Tool call — Read · `toolu_01LrX1vewSbyrRVyQrcDhcxc`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "offset": 390,
  "limit": 60
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "217f7b08-a302-486b-b996-47154df432ef",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ASqLn5zJExMCmvgrjsQmRq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6228,
      "cache_read_input_tokens": 36280,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6228
      },
      "output_tokens": 10,
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

_source line 32 · 2026-05-24T08:00:14.233Z_

<details><summary>↩ Tool result · `toolu_01LrX1vewSbyrRVyQrcDhcxc`</summary>

```text
390	\small
391	\begin{tabular}{lccc}
392	\toprule
393	Method & Coverage & RMSE & $|\text{Bias}|$ \\
394	\midrule
395	Oracle       & 0.944 & 0.113 & 0.090 \\
396	Global       & 0.951 & 0.168 & 0.135 \\
397	HB EC-HTE    & 0.956 & 0.340 & 0.183 \\
398	Strat MLE    & 0.953 & 0.638 & 0.219 \\
399	Naive        & 0.913 & 0.133 & 0.107 \\
400	\bottomrule
401	\end{tabular}
402	\end{table}
403	
404	All CM-aware methods achieve nominal coverage at $K{=}8$: HB EC-HTE 95.6\%, Strat MLE 95.3\%, Global 95.1\%.
405	HB partial pooling achieves a 47\% RMSE reduction over stratified MLE (0.340 vs.\ 0.638), confirming that hierarchical shrinkage provides substantial regularization.
406	However, HB RMSE (0.340) exceeds global correction (0.168), indicating that ${\approx}31$ expert labels per subgroup are insufficient for per-subgroup CM estimation to outweigh variance inflation.
407	
408	\paragraph{Per-subgroup breakdown.}
409	Table~\ref{tab:k8_per_subgroup} decomposes RMSE by subgroup.
410	
411	\begin{table}[h]
412	\centering
413	\caption{Per-subgroup RMSE at $K{=}8$. HB improvement over MLE is largest in high-$\pi$ subgroups but does not close the gap with Global.}
414	\label{tab:k8_per_subgroup}
415	\small
416	\begin{tabular}{cccccc}
417	\toprule
418	Subgroup & $\pi_s$ & HB RMSE & MLE RMSE & Global RMSE & HB Cov \\
419	\midrule
420	$s_0$ & 0.050 & 0.136 & 0.134 & \textbf{0.181} & 0.950 \\
421	$s_1$ & 0.093 & 0.133 & 0.132 & \textbf{0.154} & 0.970 \\
422	$s_2$ & 0.136 & 0.154 & 0.154 & 0.161 & 0.975 \\
423	$s_3$ & 0.179 & 0.178 & 0.182 & \textbf{0.159} & 0.945 \\
424	$s_4$ & 0.221 & 0.263 & 0.343 & \textbf{0.163} & 0.940 \\
425	$s_5$ & 0.264 & 0.421 & 0.711 & \textbf{0.164} & 0.965 \\
426	$s_6$ & 0.307 & 0.634 & 1.375 & \textbf{0.177} & 0.940 \\
427	$s_7$ & 0.350 & 0.432 & 0.809 & \textbf{0.183} & 0.960 \\
428	\bottomrule
429	\end{tabular}
430	\end{table}
431	
432	RMSE degradation is concentrated in high-$\pi$ subgroups ($s_4$--$s_7$, $\pi \geq 0.22$), where confusion matrix inversion amplifies estimation noise ($r = 0.87$, $p = 0.005$ for correlation between $\pi_s$ and HB RMSE).
433	Low-error subgroups ($s_0$--$s_1$) benefit from stratification, with HB RMSE 14--25\% below global correction.
434	HB partial pooling reduces MLE RMSE by 24--54\% in the high-$\pi$ regime ($s_4$--$s_7$), confirming that hierarchical shrinkage provides meaningful regularization even when per-subgroup labels are scarce.
435	Coverage remains $\geq$0.94 across all subgroups for HB EC-HTE, indicating that variance inflation does not compromise inference validity.
436	Adaptive shrinkage---increasing the prior strength for high-$\pi$ subgroups where CM estimation is least reliable---is a natural extension that may close the RMSE gap with global correction at larger $K$.
437	
438	We explored adaptive shrinkage ($\alpha{=}10$ for high-$\pi$ subgroups vs.\ default $\alpha{=}3$), which reduces aggregate RMSE from 0.340 to 0.216 (35\% improvement) by attenuating estimation noise in high-$\pi$ subgroups.
439	However, RMSE remains 30\% above global correction (0.166), confirming that the bottleneck is per-subgroup sample size (${\sim}$31 expert labels) rather than the shrinkage method itself.
440	This establishes $K{=}8$ at $n_{\text{expert}}{=}250$ as a boundary condition: all correction methods provide valid inference (coverage $\geq$94\%), but per-subgroup stratification requires proportionally larger expert budgets---approximately $n_{\text{expert}} \geq 500$ (${\approx}60$ labels/subgroup)---to achieve RMSE parity with global correction.
441	
442	\section{Asymmetric Misclassification Extension}
443	\label{app:asymmetric}
444	
445	Assumption~(A2) imposes symmetric misclassification ($\text{FPR}_s = \text{FNR}_s = \pi_s$), which simplifies the bias decomposition but is not necessary for it.
446	Real LLM annotators typically exhibit asymmetric confusion patterns; we show here that the product structure generalizes.
447	
448	\paragraph{General bias formula.}
449	For asymmetric confusion matrices $C_s = \bigl(\begin{smallmatrix} 1{-}\text{FPR}_s & \text{FPR}_s \\ \text{FNR}_s & 1{-}\text{FNR}_s \end{smallmatrix}\bigr)$, define the mixing matrix $M_s$ via Bayesian inversion and the residual matrix $B_s = M_{\text{global}}^{-1} M_s - I$.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "3924dc5b-9364-439f-8495-f6006fc8fd68",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
      "content": "\\small\n\\begin{tabular}{lccc}\n\\toprule\nMethod & Coverage & RMSE & $|\\text{Bias}|$ \\\\\n\\midrule\nOracle       & 0.944 & 0.113 & 0.090 \\\\\nGlobal       & 0.951 & 0.168 & 0.135 \\\\\nHB EC-HTE    & 0.956 & 0.340 & 0.183 \\\\\nStrat MLE    & 0.953 & 0.638 & 0.219 \\\\\nNaive        & 0.913 & 0.133 & 0.107 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll CM-aware methods achieve nominal coverage at $K{=}8$: HB EC-HTE 95.6\\%, Strat MLE 95.3\\%, Global 95.1\\%.\nHB partial pooling achieves a 47\\% RMSE reduction over stratified MLE (0.340 vs.\\ 0.638), confirming that hierarchical shrinkage provides substantial regularization.\nHowever, HB RMSE (0.340) exceeds global correction (0.168), indicating that ${\\approx}31$ expert labels per subgroup are insufficient for per-subgroup CM estimation to outweigh variance inflation.\n\n\\paragraph{Per-subgroup breakdown.}\nTable~\\ref{tab:k8_per_subgroup} decomposes RMSE by subgroup.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-subgroup RMSE at $K{=}8$. HB improvement over MLE is largest in high-$\\pi$ subgroups but does not close the gap with Global.}\n\\label{tab:k8_per_subgroup}\n\\small\n\\begin{tabular}{cccccc}\n\\toprule\nSubgroup & $\\pi_s$ & HB RMSE & MLE RMSE & Global RMSE & HB Cov \\\\\n\\midrule\n$s_0$ & 0.050 & 0.136 & 0.134 & \\textbf{0.181} & 0.950 \\\\\n$s_1$ & 0.093 & 0.133 & 0.132 & \\textbf{0.154} & 0.970 \\\\\n$s_2$ & 0.136 & 0.154 & 0.154 & 0.161 & 0.975 \\\\\n$s_3$ & 0.179 & 0.178 & 0.182 & \\textbf{0.159} & 0.945 \\\\\n$s_4$ & 0.221 & 0.263 & 0.343 & \\textbf{0.163} & 0.940 \\\\\n$s_5$ & 0.264 & 0.421 & 0.711 & \\textbf{0.164} & 0.965 \\\\\n$s_6$ & 0.307 & 0.634 & 1.375 & \\textbf{0.177} & 0.940 \\\\\n$s_7$ & 0.350 & 0.432 & 0.809 & \\textbf{0.183} & 0.960 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nRMSE degradation is concentrated in high-$\\pi$ subgroups ($s_4$--$s_7$, $\\pi \\geq 0.22$), where confusion matrix inversion amplifies estimation noise ($r = 0.87$, $p = 0.005$ for correlation between $\\pi_s$ and HB RMSE).\nLow-error subgroups ($s_0$--$s_1$) benefit from stratification, with HB RMSE 14--25\\% below global correction.\nHB partial pooling reduces MLE RMSE by 24--54\\% in the high-$\\pi$ regime ($s_4$--$s_7$), confirming that hierarchical shrinkage provides meaningful regularization even when per-subgroup labels are scarce.\nCoverage remains $\\geq$0.94 across all subgroups for HB EC-HTE, indicating that variance inflation does not compromise inference validity.\nAdaptive shrinkage---increasing the prior strength for high-$\\pi$ subgroups where CM estimation is least reliable---is a natural extension that may close the RMSE gap with global correction at larger $K$.\n\nWe explored adaptive shrinkage ($\\alpha{=}10$ for high-$\\pi$ subgroups vs.\\ default $\\alpha{=}3$), which reduces aggregate RMSE from 0.340 to 0.216 (35\\% improvement) by attenuating estimation noise in high-$\\pi$ subgroups.\nHowever, RMSE remains 30\\% above global correction (0.166), confirming that the bottleneck is per-subgroup sample size (${\\sim}$31 expert labels) rather than the shrinkage method itself.\nThis establishes $K{=}8$ at $n_{\\text{expert}}{=}250$ as a boundary condition: all correction methods provide valid inference (coverage $\\geq$94\\%), but per-subgroup stratification requires proportionally larger expert budgets---approximately $n_{\\text{expert}} \\geq 500$ (${\\approx}60$ labels/subgroup)---to achieve RMSE parity with global correction.\n\n\\section{Asymmetric Misclassification Extension}\n\\label{app:asymmetric}\n\nAssumption~(A2) imposes symmetric misclassification ($\\text{FPR}_s = \\text{FNR}_s = \\pi_s$), which simplifies the bias decomposition but is not necessary for it.\nReal LLM annotators typically exhibit asymmetric confusion patterns; we show here that the product structure generalizes.\n\n\\paragraph{General bias formula.}\nFor asymmetric confusion matrices $C_s = \\bigl(\\begin{smallmatrix} 1{-}\\text{FPR}_s & \\text{FPR}_s \\\\ \\text{FNR}_s & 1{-}\\text{FNR}_s \\end{smallmatrix}\\bigr)$, define the mixing matrix $M_s$ via Bayesian inversion and the residual matrix $B_s = M_{\\text{global}}^{-1} M_s - I$.",
      "numLines": 60,
      "startLine": 390,
      "totalLines": 1561
    }
  }
}
```

</details>

---

### Tool call

_source line 33_

<details open><summary>🔧 Tool call — Read · `toolu_01URJ4H5QXd5pCsodNcbVzve`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "offset": 750,
  "limit": 80
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "2f564d5e-1c5d-4839-bbcd-b8c77ae9889b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ASqLn5zJExMCmvgrjsQmRq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6228,
      "cache_read_input_tokens": 36280,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6228
      },
      "output_tokens": 10,
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

_source line 34 · 2026-05-24T08:00:14.878Z_

<details><summary>↩ Tool result · `toolu_01URJ4H5QXd5pCsodNcbVzve`</summary>

```text
750	
751	\section{Semi-Real Confusion Matrix Validation}
752	\label{app:semireal}
753	
754	We test EC-HTE with empirical asymmetric confusion matrices from the GPT-4.1 TweetEval pilot.
755	Four text-feature subgroups ($K{=}4$) retain the real per-subgroup FPR and FNR from pilot annotations (Table~\ref{tab:semireal_cm}); CATE heterogeneity is injected synthetically ($\tau(z{=}0,s) = 0.3 + 0.1s$, $\tau(z{=}1,s) = 0.8 - 0.15s$).
756	$N{=}5{,}000$, $P(Z{=}1){=}0.18$, 100 MC seeds per $n_{\text{expert}}$ level.
757	
758	\begin{table}[t]
759	\centering
760	\caption{Empirical confusion matrices from GPT-4.1 TweetEval pilot.
761	S0 exhibits FNR $= 0.526$, approaching chance-level classification.}
762	\label{tab:semireal_cm}
763	\small
764	\begin{tabular}{lcccc}
765	\toprule
766	Subgroup & Weight & FPR & FNR & $\kappa(\hat{C}_s)$ \\
767	\midrule
768	S0 & 0.38 & 0.054 & 0.526 & high \\
769	S1 & 0.22 & 0.101 & 0.300 & moderate \\
770	S2 & 0.14 & 0.143 & 0.308 & moderate \\
771	S3 & 0.25 & 0.194 & 0.222 & low \\
772	\bottomrule
773	\end{tabular}
774	\end{table}
775	
776	\begin{table}[t]
777	\centering
778	\caption{Semi-real confusion matrix results. RMSE and coverage averaged over subgroups and $z$-levels (100 MC runs). HB EC-HTE underperforms global at all budgets; S0's near-chance FNR drives the failure.}
779	\label{tab:semireal}
780	\small
781	\begin{tabular}{llcc}
782	\toprule
783	$n_{\text{expert}}$ & Method & RMSE $\downarrow$ & Coverage $\uparrow$ \\
784	\midrule
785	\multirow{4}{*}{100}
786	 & Oracle & 0.101 & 0.957 \\
787	 & Naive & 0.123 & 0.879 \\
788	 & Global & 0.263 & 0.885 \\
789	 & HB EC-HTE & 0.784 & 0.744 \\
790	\midrule
791	\multirow{4}{*}{250}
792	 & Oracle & 0.101 & 0.957 \\
793	 & Naive & 0.123 & 0.879 \\
794	 & Global & 0.232 & 0.909 \\
795	 & HB EC-HTE & 0.411 & 0.834 \\
796	\midrule
797	\multirow{4}{*}{500}
798	 & Oracle & 0.101 & 0.957 \\
799	 & Naive & 0.123 & 0.879 \\
800	 & Global & 0.196 & 0.922 \\
801	 & HB EC-HTE & 0.260 & 0.890 \\
802	\bottomrule
803	\end{tabular}
804	\end{table}
805	
806	HB EC-HTE produces higher RMSE and lower coverage than global correction at all expert budgets (Table~\ref{tab:semireal}).
807	The root cause is S0's FNR $= 0.526$: when a confusion matrix row approaches a uniform distribution ($P(\hat{Z}{=}1 \mid Z{=}1) \approx 0.5$), inversion amplifies estimation noise regardless of the expert budget.
808	This converges with the hate speech case study (Appendix~\ref{app:hatespeech}, FNR $= 53.3$\%) and confirms that EC-HTE requires \emph{both} sufficient expert labels \emph{and} sufficient baseline classifier quality per subgroup.
809	The singularity guard ($\kappa > 100$, Section~\ref{sec:method}) mitigates catastrophic failure by falling back to global correction for near-degenerate subgroups, but does not recover the bias reduction that motivates stratification.
810	For a $2 \times 2$ symmetric confusion matrix, $\kappa = 1/|1-2\pi|$; $\kappa > 100$ corresponds to $\pi \in (0.495, 0.505)$, so the guard triggers only when the classifier performs within $0.5\%$ of random guessing.
811	At $n_{\text{expert}} = 500$, HB EC-HTE narrows the gap (RMSE 0.260 vs.\ 0.196) as confusion matrix estimates stabilize for the three well-classified subgroups, but the S0 bottleneck persists.
812	
813	A second semi-real experiment using GPT-3.5-Turbo confusion matrices (worst-subgroup FPR $= 0.39$, FNR $= 0.21$) yields similar results: HB RMSE exceeds global by 1.3--3.5$\times$ at all budgets.
814	Here the failure stems from high false-positive rates compounded by class imbalance ($P(Z{=}1) = 0.18$), which leaves insufficient expert observations in the positive class for reliable per-subgroup confusion matrix estimation.
815	Together, these experiments identify three applicability conditions for EC-HTE: (1)~sufficient effective expert budget ($n_{\text{expert}} \times P(Z_{\text{minority}}) / K \geq 25$), (2)~no near-chance subgroup error rate ($\max(\text{FPR}_s, \text{FNR}_s) < 0.5$), and (3)~adequate class balance in the effect modifier.
816	
817	\paragraph{Diagnostic rule.}
818	A logistic regression over all 368 semi-real experiment--budget cells (dependent variable: HB EC-HTE $<$ Global RMSE) identifies two sufficient statistics: the worst-subgroup confusion matrix condition number $\kappa(\hat{M}_s) \leq 1.25$ and the effective minority-class expert count $n_{\text{expert}} \times P(Z_{\text{minority}}) / K \geq 25$.
819	When both conditions hold, HB outperforms global in 93.3\% of cells; when either is violated, global is preferred in 94.7\% of cells.
820	Both exp-015 ($\kappa = 2.38$, effective $n = 2.5$) and exp-016 ($\kappa = 1.55$, effective $n = 2.5$) violate both conditions, and the diagnostic correctly predicts 100\% of their failure cells.
821	Subgroup-average metrics can mask cell-level heterogeneity: in exp-015, HB EC-HTE substantially reduces bias for the three well-classified subgroups (S1--S3) but amplifies variance in the near-degenerate subgroup (S0, FNR $= 0.526$), and the S0 penalty dominates the aggregate RMSE.
822	
823	\begin{figure}[t]
824	\centering
825	\includegraphics[width=\columnwidth]{figures/applicability_frontier.pdf}
826	\caption{Applicability frontier of EC-HTE. Green region: EC-HTE reduces bias vs.\ global correction. Yellow: comparable performance. Red: EC-HTE underperforms. Dashed lines mark the expert budget threshold ($n_{\text{expert}}/K = 25$) and classifier quality threshold (worst-subgroup error rate $= 0.5$). Red diamonds show semi-real experiments with actual GPT-4.1 and GPT-3.5-Turbo confusion matrices.}
827	\label{fig:applicability}
828	\end{figure}
829	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "7a68ebed-15b2-4528-9e05-20265aea4b92",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
      "content": "\n\\section{Semi-Real Confusion Matrix Validation}\n\\label{app:semireal}\n\nWe test EC-HTE with empirical asymmetric confusion matrices from the GPT-4.1 TweetEval pilot.\nFour text-feature subgroups ($K{=}4$) retain the real per-subgroup FPR and FNR from pilot annotations (Table~\\ref{tab:semireal_cm}); CATE heterogeneity is injected synthetically ($\\tau(z{=}0,s) = 0.3 + 0.1s$, $\\tau(z{=}1,s) = 0.8 - 0.15s$).\n$N{=}5{,}000$, $P(Z{=}1){=}0.18$, 100 MC seeds per $n_{\\text{expert}}$ level.\n\n\\begin{table}[t]\n\\centering\n\\caption{Empirical confusion matrices from GPT-4.1 TweetEval pilot.\nS0 exhibits FNR $= 0.526$, approaching chance-level classification.}\n\\label{tab:semireal_cm}\n\\small\n\\begin{tabular}{lcccc}\n\\toprule\nSubgroup & Weight & FPR & FNR & $\\kappa(\\hat{C}_s)$ \\\\\n\\midrule\nS0 & 0.38 & 0.054 & 0.526 & high \\\\\nS1 & 0.22 & 0.101 & 0.300 & moderate \\\\\nS2 & 0.14 & 0.143 & 0.308 & moderate \\\\\nS3 & 0.25 & 0.194 & 0.222 & low \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[t]\n\\centering\n\\caption{Semi-real confusion matrix results. RMSE and coverage averaged over subgroups and $z$-levels (100 MC runs). HB EC-HTE underperforms global at all budgets; S0's near-chance FNR drives the failure.}\n\\label{tab:semireal}\n\\small\n\\begin{tabular}{llcc}\n\\toprule\n$n_{\\text{expert}}$ & Method & RMSE $\\downarrow$ & Coverage $\\uparrow$ \\\\\n\\midrule\n\\multirow{4}{*}{100}\n & Oracle & 0.101 & 0.957 \\\\\n & Naive & 0.123 & 0.879 \\\\\n & Global & 0.263 & 0.885 \\\\\n & HB EC-HTE & 0.784 & 0.744 \\\\\n\\midrule\n\\multirow{4}{*}{250}\n & Oracle & 0.101 & 0.957 \\\\\n & Naive & 0.123 & 0.879 \\\\\n & Global & 0.232 & 0.909 \\\\\n & HB EC-HTE & 0.411 & 0.834 \\\\\n\\midrule\n\\multirow{4}{*}{500}\n & Oracle & 0.101 & 0.957 \\\\\n & Naive & 0.123 & 0.879 \\\\\n & Global & 0.196 & 0.922 \\\\\n & HB EC-HTE & 0.260 & 0.890 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nHB EC-HTE produces higher RMSE and lower coverage than global correction at all expert budgets (Table~\\ref{tab:semireal}).\nThe root cause is S0's FNR $= 0.526$: when a confusion matrix row approaches a uniform distribution ($P(\\hat{Z}{=}1 \\mid Z{=}1) \\approx 0.5$), inversion amplifies estimation noise regardless of the expert budget.\nThis converges with the hate speech case study (Appendix~\\ref{app:hatespeech}, FNR $= 53.3$\\%) and confirms that EC-HTE requires \\emph{both} sufficient expert labels \\emph{and} sufficient baseline classifier quality per subgroup.\nThe singularity guard ($\\kappa > 100$, Section~\\ref{sec:method}) mitigates catastrophic failure by falling back to global correction for near-degenerate subgroups, but does not recover the bias reduction that motivates stratification.\nFor a $2 \\times 2$ symmetric confusion matrix, $\\kappa = 1/|1-2\\pi|$; $\\kappa > 100$ corresponds to $\\pi \\in (0.495, 0.505)$, so the guard triggers only when the classifier performs within $0.5\\%$ of random guessing.\nAt $n_{\\text{expert}} = 500$, HB EC-HTE narrows the gap (RMSE 0.260 vs.\\ 0.196) as confusion matrix estimates stabilize for the three well-classified subgroups, but the S0 bottleneck persists.\n\nA second semi-real experiment using GPT-3.5-Turbo confusion matrices (worst-subgroup FPR $= 0.39$, FNR $= 0.21$) yields similar results: HB RMSE exceeds global by 1.3--3.5$\\times$ at all budgets.\nHere the failure stems from high false-positive rates compounded by class imbalance ($P(Z{=}1) = 0.18$), which leaves insufficient expert observations in the positive class for reliable per-subgroup confusion matrix estimation.\nTogether, these experiments identify three applicability conditions for EC-HTE: (1)~sufficient effective expert budget ($n_{\\text{expert}} \\times P(Z_{\\text{minority}}) / K \\geq 25$), (2)~no near-chance subgroup error rate ($\\max(\\text{FPR}_s, \\text{FNR}_s) < 0.5$), and (3)~adequate class balance in the effect modifier.\n\n\\paragraph{Diagnostic rule.}\nA logistic regression over all 368 semi-real experiment--budget cells (dependent variable: HB EC-HTE $<$ Global RMSE) identifies two sufficient statistics: the worst-subgroup confusion matrix condition number $\\kappa(\\hat{M}_s) \\leq 1.25$ and the effective minority-class expert count $n_{\\text{expert}} \\times P(Z_{\\text{minority}}) / K \\geq 25$.\nWhen both conditions hold, HB outperforms global in 93.3\\% of cells; when either is violated, global is preferred in 94.7\\% of cells.\nBoth exp-015 ($\\kappa = 2.38$, effective $n = 2.5$) and exp-016 ($\\kappa = 1.55$, effective $n = 2.5$) violate both conditions, and the diagnostic correctly predicts 100\\% of their failure cells.\nSubgroup-average metrics can mask cell-level heterogeneity: in exp-015, HB EC-HTE substantially reduces bias for the three well-classified subgroups (S1--S3) but amplifies variance in the near-degenerate subgroup (S0, FNR $= 0.526$), and the S0 penalty dominates the aggregate RMSE.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/applicability_frontier.pdf}\n\\caption{Applicability frontier of EC-HTE. Green region: EC-HTE reduces bias vs.\\ global correction. Yellow: comparable performance. Red: EC-HTE underperforms. Dashed lines mark the expert budget threshold ($n_{\\text{expert}}/K = 25$) and classifier quality threshold (worst-subgroup error rate $= 0.5$). Red diamonds show semi-real experiments with actual GPT-4.1 and GPT-3.5-Turbo confusion matrices.}\n\\label{fig:applicability}\n\\end{figure}\n",
      "numLines": 80,
      "startLine": 750,
      "totalLines": 1561
    }
  }
}
```

</details>

---

### Assistant

_source line 35_

<details><summary>Logged reasoning block</summary>

```text
Now let me also check for the PPCI composition section and its relationship to exp-007b.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "8dfae155-eb4a-4d71-a219-960423231f87",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0151iffbdCkBZTB9bA4zzRWV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4420,
      "cache_read_input_tokens": 42508,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4420
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

_source line 36_

Let me also check the PPCI section and the diagnostic screening appendix.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "3bee1ff6-3511-482a-a260-db89c4a4c5da",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0151iffbdCkBZTB9bA4zzRWV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4420,
      "cache_read_input_tokens": 42508,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4420
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

_source line 37_

<details open><summary>🔧 Tool call — Grep · `toolu_011FZPpBdRSJTcqHDV11fyLC`</summary>

```json
{
  "pattern": "\\\\\\\\label\\{sec:ppci|\\\\\\\\section.*PPCI|\\\\\\\\label\\{app:screening",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "bb7548b4-5b6e-4c0c-9659-b910e77892d4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0151iffbdCkBZTB9bA4zzRWV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4420,
      "cache_read_input_tokens": 42508,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4420
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

_source line 38 · 2026-05-24T08:00:28.001Z_

<details><summary>↩ Tool result · `toolu_011FZPpBdRSJTcqHDV11fyLC`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "62a1632e-8afa-4499-af97-f48359b9db72",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Tool call

_source line 39_

<details open><summary>🔧 Tool call — Grep · `toolu_01QF4gUzk9LSG4bRKhkG3gWf`</summary>

```json
{
  "pattern": "column.stochastic|monotone transform|symmetric formula",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "7e97b3fd-9f9f-4c48-ab07-18acc2c17e77",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0151iffbdCkBZTB9bA4zzRWV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4420,
      "cache_read_input_tokens": 42508,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4420
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

_source line 40 · 2026-05-24T08:00:29.396Z_

<details><summary>↩ Tool result · `toolu_01QF4gUzk9LSG4bRKhkG3gWf`</summary>

```text
docs/paper/theory.tex:65:For binary effect modifiers ($|\mathcal{Z}|{=}2$), the asymmetric score $|[B_s]_{z,1}|$ reduces to a monotone transform of the symmetric score $|\delta_s|/((1{-}2\bar{\pi})\pi_s)$, because column-stochastic $M$ forces $|B_s[0,1]|{=}|B_s[1,1]|$; practitioners may use the simpler symmetric formula without loss.
docs/paper/appendix.tex:1454:\caption{EC-HTE under asymmetric misclassification ($\text{FPR}/\text{FNR}$ up to $7{:}1$). The asymmetric formula improves coverage by $+1.5$pp and RMSE by $11.5\%$.}
docs/paper/appendix.tex:1471:EC-HTE with the asymmetric formula achieves 94.5\% coverage versus 93.0\% under the symmetric assumption ($+1.5$pp), with RMSE improved from 0.083 to 0.074 ($-11.5\%$).
docs/paper/main.aux:2660:\@writefile{lot}{\contentsline {table}{\numberline {34}{\ignorespaces EC-HTE under asymmetric misclassification ($\text  {FPR}/\text  {FNR}$ up to $7{:}1$). The asymmetric formula improves coverage by $+1.5$pp and RMSE by $11.5\%$.}}{30}{table.caption.90}\protected@file@percent }
docs/paper/main.aux:2661:\newlabel{tab:asymmetric_endtoend}{{34}{30}{EC-HTE under asymmetric misclassification ($\text {FPR}/\text {FNR}$ up to $7{:}1$). The asymmetric formula improves coverage by $+1.5$pp and RMSE by $11.5\%$}{table.caption.90}{}}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "b28a60c8-8948-48cf-9abb-40b190217cba",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/theory.tex:65:For binary effect modifiers ($|\\mathcal{Z}|{=}2$), the asymmetric score $|[B_s]_{z,1}|$ reduces to a monotone transform of the symmetric score $|\\delta_s|/((1{-}2\\bar{\\pi})\\pi_s)$, because column-stochastic $M$ forces $|B_s[0,1]|{=}|B_s[1,1]|$; practitioners may use the simpler symmetric formula without loss.\ndocs/paper/appendix.tex:1454:\\caption{EC-HTE under asymmetric misclassification ($\\text{FPR}/\\text{FNR}$ up to $7{:}1$). The asymmetric formula improves coverage by $+1.5$pp and RMSE by $11.5\\%$.}\ndocs/paper/appendix.tex:1471:EC-HTE with the asymmetric formula achieves 94.5\\% coverage versus 93.0\\% under the symmetric assumption ($+1.5$pp), with RMSE improved from 0.083 to 0.074 ($-11.5\\%$).\ndocs/paper/main.aux:2660:\\@writefile{lot}{\\contentsline {table}{\\numberline {34}{\\ignorespaces EC-HTE under asymmetric misclassification ($\\text  {FPR}/\\text  {FNR}$ up to $7{:}1$). The asymmetric formula improves coverage by $+1.5$pp and RMSE by $11.5\\%$.}}{30}{table.caption.90}\\protected@file@percent }\ndocs/paper/main.aux:2661:\\newlabel{tab:asymmetric_endtoend}{{34}{30}{EC-HTE under asymmetric misclassification ($\\text {FPR}/\\text {FNR}$ up to $7{:}1$). The asymmetric formula improves coverage by $+1.5$pp and RMSE by $11.5\\%$}{table.caption.90}{}}",
    "numLines": 5
  }
}
```

</details>

---

### Tool call

_source line 41_

<details open><summary>🔧 Tool call — Grep · `toolu_01MGueRjdzzhoLVhbYRtEKKp`</summary>

```json
{
  "pattern": "\\\\\\\\section.*PPCI|\\\\\\\\label.*ppci|Composition",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "6849147d-15e7-4073-8652-3957796cc897",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012cqTrBkBGXdfGTKfzHs6Xa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 931,
      "cache_read_input_tokens": 46928,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 931
      },
      "output_tokens": 44,
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

_source line 42 · 2026-05-24T08:00:33.054Z_

<details><summary>↩ Tool result · `toolu_01MGueRjdzzhoLVhbYRtEKKp`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "1fa9f52d-f15f-4054-82ff-53de661f573a",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Tool call

_source line 43_

<details open><summary>🔧 Tool call — Grep · `toolu_01KyXuhRpVgDtyGXtBqMeB9D`</summary>

```json
{
  "pattern": "\\\\\\\\section.*Screening|\\\\\\\\label.*screening",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "d95d5ce9-7efb-4d52-8d3a-2549cc2b0b99",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012cqTrBkBGXdfGTKfzHs6Xa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 931,
      "cache_read_input_tokens": 46928,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 931
      },
      "output_tokens": 44,
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

_source line 44 · 2026-05-24T08:00:33.922Z_

<details><summary>↩ Tool result · `toolu_01KyXuhRpVgDtyGXtBqMeB9D`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "a6338fff-5544-4939-9223-331b607649a5",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Tool call

_source line 45_

<details open><summary>🔧 Tool call — Grep · `toolu_01XEgatWMNu3HmfDanbsUphT`</summary>

```json
{
  "pattern": "ppci|PPCI|screening|Screening",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "e8ffbae6-f9f8-421c-8b87-38e6f09b7783",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RU2E35ZcCv6FZYm3PNC9Wj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 363,
      "cache_read_input_tokens": 47859,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 363
      },
      "output_tokens": 46,
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

_source line 46 · 2026-05-24T08:00:37.568Z_

<details><summary>↩ Tool result · `toolu_01XEgatWMNu3HmfDanbsUphT`</summary>

```text
207:\paragraph{PPCI DGPs (Appendix~\ref{sec:ppci}).}
507:\section{PPCI Complementarity Results}
508:\label{app:ppci}
509:\label{sec:ppci}
511:EC-HTE composes with PPCI~\cite{sui2026ppci} for settings where both covariate misclassification and outcome model error are present: EC-HTE+PPCI reduces $|\text{bias}|$ from 0.179 to 0.007 ($z{=}0$, DGP~C), and the corrected pseudo-outcomes are compatible with other CATE estimators (R-learner bias reduction: 89\%; Appendix~\ref{app:rlearner}).
515:\caption{PPCI complementarity experiment ($K{=}2$, extreme, $n_{\text{expert}}{=}250$). DGP~A: covariate error only; B: outcome error only ($\sigma{=}0.5$); C: both errors; D: no error. Values are $|\text{bias}|$ and RMSE averaged over two subgroups. $^\star$EC-HTE+PPCI achieves near-zero bias when both error types are present.}
516:\label{tab:ppci}
526: & PPCI & \textbf{0.015} & 0.020 & 0.162 & 0.168 \\
527: & EC-HTE+PPCI & 0.017 & \textbf{0.013} & 0.097 & 0.108 \\
533: & PPCI & 0.015 & \textbf{0.020} & 0.171 & 0.176 \\
534: & EC-HTE+PPCI & \textbf{0.012} & 0.023 & 0.171 & 0.186 \\
540: & PPCI & 0.017 & 0.007 & 0.241 & 0.232 \\
541: & EC-HTE+PPCI$^\star$ & \textbf{0.007} & \textbf{0.008} & 0.209 & 0.223 \\
547: & PPCI & \textbf{0.007} & \textbf{0.003} & 0.060 & 0.065 \\
548: & EC-HTE+PPCI & 0.013 & 0.007 & 0.062 & 0.079 \\
553:The complementarity of EC-HTE and PPCI follows from the distinct error sources they correct: EC-HTE addresses misclassification in the effect modifier $Z$ (covariate space), while PPCI corrects specification error in the outcome model $f(X)$ (prediction space).
554:Since covariate misclassification and outcome model error are algebraically independent in the potential outcomes framework, their corrections compose without interference---confirmed by the 4-DGP orthogonal design (Table~\ref{tab:ppci}), where DGP~C (both errors present) yields the largest bias reduction from the combined approach.
555:Under covariate error only, PPCI adds nothing; under no error, all methods perform equivalently.
1007:\section{Applicability Screening with Real LLM Confusion Matrices}
1008:\label{app:screening}
1011:Table~\ref{tab:screening} summarizes which conditions each combination satisfies.
1015:\caption{Diagnostic screening of 16 LLM--dataset--$K$ combinations. Columns report whether all subgroups satisfy each condition. Budget assumes $n_{\text{expert}}{=}500$.}
1016:\label{tab:screening}
1045:Under a relaxed ``oracle screening'' that excludes near-degenerate subgroups ($\max(\mathrm{FPR}_s, \mathrm{FNR}_s) \geq 0.4$), we run semi-synthetic CATE estimation ($N{=}5{,}000$, $\Delta\tau{=}0.3$, 100 MC runs, $n_{\text{expert}} \in \{250, 500\}$) with each LLM's real per-subgroup confusion matrix.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "08a2f624-da97-4f35-9c91-21756bd2c085",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "207:\\paragraph{PPCI DGPs (Appendix~\\ref{sec:ppci}).}\n507:\\section{PPCI Complementarity Results}\n508:\\label{app:ppci}\n509:\\label{sec:ppci}\n511:EC-HTE composes with PPCI~\\cite{sui2026ppci} for settings where both covariate misclassification and outcome model error are present: EC-HTE+PPCI reduces $|\\text{bias}|$ from 0.179 to 0.007 ($z{=}0$, DGP~C), and the corrected pseudo-outcomes are compatible with other CATE estimators (R-learner bias reduction: 89\\%; Appendix~\\ref{app:rlearner}).\n515:\\caption{PPCI complementarity experiment ($K{=}2$, extreme, $n_{\\text{expert}}{=}250$). DGP~A: covariate error only; B: outcome error only ($\\sigma{=}0.5$); C: both errors; D: no error. Values are $|\\text{bias}|$ and RMSE averaged over two subgroups. $^\\star$EC-HTE+PPCI achieves near-zero bias when both error types are present.}\n516:\\label{tab:ppci}\n526: & PPCI & \\textbf{0.015} & 0.020 & 0.162 & 0.168 \\\\\n527: & EC-HTE+PPCI & 0.017 & \\textbf{0.013} & 0.097 & 0.108 \\\\\n533: & PPCI & 0.015 & \\textbf{0.020} & 0.171 & 0.176 \\\\\n534: & EC-HTE+PPCI & \\textbf{0.012} & 0.023 & 0.171 & 0.186 \\\\\n540: & PPCI & 0.017 & 0.007 & 0.241 & 0.232 \\\\\n541: & EC-HTE+PPCI$^\\star$ & \\textbf{0.007} & \\textbf{0.008} & 0.209 & 0.223 \\\\\n547: & PPCI & \\textbf{0.007} & \\textbf{0.003} & 0.060 & 0.065 \\\\\n548: & EC-HTE+PPCI & 0.013 & 0.007 & 0.062 & 0.079 \\\\\n553:The complementarity of EC-HTE and PPCI follows from the distinct error sources they correct: EC-HTE addresses misclassification in the effect modifier $Z$ (covariate space), while PPCI corrects specification error in the outcome model $f(X)$ (prediction space).\n554:Since covariate misclassification and outcome model error are algebraically independent in the potential outcomes framework, their corrections compose without interference---confirmed by the 4-DGP orthogonal design (Table~\\ref{tab:ppci}), where DGP~C (both errors present) yields the largest bias reduction from the combined approach.\n555:Under covariate error only, PPCI adds nothing; under no error, all methods perform equivalently.\n1007:\\section{Applicability Screening with Real LLM Confusion Matrices}\n1008:\\label{app:screening}\n1011:Table~\\ref{tab:screening} summarizes which conditions each combination satisfies.\n1015:\\caption{Diagnostic screening of 16 LLM--dataset--$K$ combinations. Columns report whether all subgroups satisfy each condition. Budget assumes $n_{\\text{expert}}{=}500$.}\n1016:\\label{tab:screening}\n1045:Under a relaxed ``oracle screening'' that excludes near-degenerate subgroups ($\\max(\\mathrm{FPR}_s, \\mathrm{FNR}_s) \\geq 0.4$), we run semi-synthetic CATE estimation ($N{=}5{,}000$, $\\Delta\\tau{=}0.3$, 100 MC runs, $n_{\\text{expert}} \\in \\{250, 500\\}$) with each LLM's real per-subgroup confusion matrix.",
    "numLines": 24
  }
}
```

</details>

---

### Assistant

_source line 47_

<details><summary>Logged reasoning block</summary>

```text
Now let me also check the appendix for the K=8 section label specifically.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "f5b70ff5-e95a-47de-8848-81875fc4dafc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NPWSUiqNijoM24ttr5RtoL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1317,
      "cache_read_input_tokens": 48222,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1317
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

Let me find the exact K=8 section location in the appendix.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "d9365049-5a2f-4744-ae35-331707b995eb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NPWSUiqNijoM24ttr5RtoL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1317,
      "cache_read_input_tokens": 48222,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1317
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

_source line 49_

<details open><summary>🔧 Tool call — Read · `toolu_01FQYc2wCVCAzjoJb2JbDP3H`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "offset": 370,
  "limit": 25
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "3c782572-0d44-4a57-9cd4-c6171089445a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NPWSUiqNijoM24ttr5RtoL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1317,
      "cache_read_input_tokens": 48222,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1317
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

_source line 50 · 2026-05-24T08:00:43.133Z_

<details><summary>↩ Tool result · `toolu_01FQYc2wCVCAzjoJb2JbDP3H`</summary>

```text
370	At very low budgets ($n_{\text{expert}} < 50$ for $K{=}2$, $< 75$ for $K{=}4$), per-subgroup counts are insufficient for reliable confusion matrix estimation; global pooling dominates because the variance cost of stratification overwhelms any bias reduction.
371	HB degrades substantially in this regime because the Gibbs posterior, while better regularized than MLE, still cannot overcome the fundamental sample-size constraint with $\sim$6--12 labels per subgroup.
372	At moderate budgets ($n_{\text{expert}} = 50$--$250$ for $K{=}2$, $75$--$250$ for $K{=}4$), HB partial pooling provides consistent RMSE improvement over stratified MLE ($-0.4\%$ to $-16.1\%$), with the largest gains near the crossover point.
373	At high budgets ($n_{\text{expert}} \geq 250$), both estimators converge as subgroup-level data becomes sufficient for reliable MLE; the HB advantage diminishes to $< 1\%$.
374	Coverage remains $\geq 0.88$ for both methods across all budget levels.
375	
376	\subsection{Scalability to $K{=}8$ Subgroups}
377	\label{app:k8_subgroups}
378	
379	We test EC-HTE at $K{=}8$ to identify the scalability boundary of hierarchical Bayesian partial pooling under fixed expert budget.
380	
381	\paragraph{Setup.}
382	$N{=}5{,}000$, $K{=}8$ (equal-weight subgroups), $n_{\text{expert}}{=}250$ (${\approx}31$ labels per subgroup), 100 MC replications.
383	Misclassification rates are uniformly spread: $\pi_s \in \{0.05, 0.09, 0.13, 0.18, 0.22, 0.26, 0.30, 0.35\}$.
384	Treatment effects depend on $Z$ (not subgroup): $\tau(Z{=}0){=}0$, $\tau(Z{=}1){=}0.3$.
385	
386	\begin{table}[h]
387	\centering
388	\caption{EC-HTE at $K{=}8$ ($n_{\text{expert}}{=}250$, ${\approx}31$ labels/subgroup, 100 MC).}
389	\label{tab:k8_subgroups}
390	\small
391	\begin{tabular}{lccc}
392	\toprule
393	Method & Coverage & RMSE & $|\text{Bias}|$ \\
394	\midrule
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "8fb89e2d-23d5-411b-970b-024ff5dcaa4e",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
      "content": "At very low budgets ($n_{\\text{expert}} < 50$ for $K{=}2$, $< 75$ for $K{=}4$), per-subgroup counts are insufficient for reliable confusion matrix estimation; global pooling dominates because the variance cost of stratification overwhelms any bias reduction.\nHB degrades substantially in this regime because the Gibbs posterior, while better regularized than MLE, still cannot overcome the fundamental sample-size constraint with $\\sim$6--12 labels per subgroup.\nAt moderate budgets ($n_{\\text{expert}} = 50$--$250$ for $K{=}2$, $75$--$250$ for $K{=}4$), HB partial pooling provides consistent RMSE improvement over stratified MLE ($-0.4\\%$ to $-16.1\\%$), with the largest gains near the crossover point.\nAt high budgets ($n_{\\text{expert}} \\geq 250$), both estimators converge as subgroup-level data becomes sufficient for reliable MLE; the HB advantage diminishes to $< 1\\%$.\nCoverage remains $\\geq 0.88$ for both methods across all budget levels.\n\n\\subsection{Scalability to $K{=}8$ Subgroups}\n\\label{app:k8_subgroups}\n\nWe test EC-HTE at $K{=}8$ to identify the scalability boundary of hierarchical Bayesian partial pooling under fixed expert budget.\n\n\\paragraph{Setup.}\n$N{=}5{,}000$, $K{=}8$ (equal-weight subgroups), $n_{\\text{expert}}{=}250$ (${\\approx}31$ labels per subgroup), 100 MC replications.\nMisclassification rates are uniformly spread: $\\pi_s \\in \\{0.05, 0.09, 0.13, 0.18, 0.22, 0.26, 0.30, 0.35\\}$.\nTreatment effects depend on $Z$ (not subgroup): $\\tau(Z{=}0){=}0$, $\\tau(Z{=}1){=}0.3$.\n\n\\begin{table}[h]\n\\centering\n\\caption{EC-HTE at $K{=}8$ ($n_{\\text{expert}}{=}250$, ${\\approx}31$ labels/subgroup, 100 MC).}\n\\label{tab:k8_subgroups}\n\\small\n\\begin{tabular}{lccc}\n\\toprule\nMethod & Coverage & RMSE & $|\\text{Bias}|$ \\\\\n\\midrule",
      "numLines": 25,
      "startLine": 370,
      "totalLines": 1561
    }
  }
}
```

</details>

---

### Tool call

_source line 51_

<details open><summary>🔧 Tool call — Grep · `toolu_01MYUQpAnubTYCpkqC6wSV2h`</summary>

```json
{
  "pattern": "k8_subgroups|Scalability.*K|K.*Subgroup|label.*k8",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "70a138d4-4b82-4c6d-a870-2c9edbffffb8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NPWSUiqNijoM24ttr5RtoL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1317,
      "cache_read_input_tokens": 48222,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1317
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

_source line 52 · 2026-05-24T08:00:44.817Z_

<details><summary>↩ Tool result · `toolu_01MYUQpAnubTYCpkqC6wSV2h`</summary>

```text
376:\subsection{Scalability to $K{=}8$ Subgroups}
377:\label{app:k8_subgroups}
389:\label{tab:k8_subgroups}
414:\label{tab:k8_per_subgroup}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "e0e88953-485a-4b06-92a4-30d6f8390ff1",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "376:\\subsection{Scalability to $K{=}8$ Subgroups}\n377:\\label{app:k8_subgroups}\n389:\\label{tab:k8_subgroups}\n414:\\label{tab:k8_per_subgroup}",
    "numLines": 4
  }
}
```

</details>

---

### Assistant

_source line 53_

Now I have all the information needed. Let me write the audit report.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "3bd8d164-aaac-49f9-b98a-3ecbc948afd7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QygSnfiFRr73W5oQdvcWvJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1138,
      "cache_read_input_tokens": 49539,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1138
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

### Tool call

_source line 54_

<details open><summary>🔧 Tool call — Write · `toolu_01TzdxYVEWLTZJeCcWaN2BQq`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/artifacts/negative_experiment_framing_audit.md",
  "content": "# 阴性实验 Framing 审计\n\n## exp-007b (killed): PPCI 表 HB backfill\n\n- **论文中是否讨论**：不需要（内部决策，非阴性结果）\n- **PPCI composition 讨论完整性**：充分\n- **位置**：`method.tex:55-61`（PPCI composition 段落）、`appendix.tex:507-555`（Appendix PPCI 完整实验）\n- **具体情况**：论文在 method.tex 中清楚说明 EC-HTE 和 PPCI 的互补性（\"Neither is redundant with the other\"），并给出了 4-DGP 正交设计的完整结果（Table PPCI）。DGP-A（仅 covariate error）下 PPCI 无增益，DGP-B（仅 outcome error）下 EC-HTE 贡献可忽略——这些就是 exp-007b 放弃 HB backfill 的理由的间接体现。\n- **建议**：无需补充\n\n---\n\n## exp-015 (negative): GPT-4.1 real CM 上 EC-HTE 失败\n\n- **论文中是否讨论**：是，详细\n- **讨论位置**：\n  - `appendix.tex:751-828`（§Semi-Real CM Validation，完整 section）\n  - `appendix.tex:806-811`（root cause 分析：S0 FNR=0.526）\n  - `appendix.tex:818-821`（diagnostic rule，明确引用 exp-015）\n  - `experiments.tex:82`（operating conditions 汇总，FNR<0.50 条件）\n  - `limitations.tex:1`（FPR/FNR<0.5 条件）\n  - `experiments.tex:79`（hate speech 实测 underperformance）\n- **充分性**：**充分**\n  - Root cause 完整：S0 FNR=0.526 → CM 行近均匀 → inversion 放大噪声（appendix.tex:807）\n  - P(Z=1)=0.18 的 class imbalance 影响在 appendix.tex:756 和 814 中明确提及\n  - 三个 applicability conditions 在 appendix.tex:815 归纳，并上升到 experiments.tex:82 的 operating conditions\n  - 提供了 applicability frontier 图（Figure applicability_frontier.pdf）\n  - 明确指出 exp-015 同时违反 κ 和 effective n 两个条件（appendix.tex:820）\n  - 提到 subgroup-average metrics 可能 mask cell-level heterogeneity（appendix.tex:821）\n- **建议**：无需补充\n\n---\n\n## exp-016 (negative): GPT-3.5-Turbo real CM 上 EC-HTE 失败\n\n- **论文中是否讨论**：是\n- **讨论位置**：\n  - `appendix.tex:813-814`（第二个 semi-real 实验，明确 GPT-3.5-Turbo）\n  - `appendix.tex:820`（diagnostic 正确预测 exp-016 失败）\n  - `appendix.tex:946`（Civil Comments multi-LLM 表中 GPT-3.5-turbo FPR 数据）\n- **充分性**：**充分**\n  - Root cause 明确：high FPR variance (worst-subgroup FPR=0.39) + class imbalance P(Z=1)=0.18（appendix.tex:814）\n  - 与 exp-015 root cause 的一致性被明确指出（\"yields similar results\"）\n  - Diagnostic rule 在 appendix.tex:820 验证了对 exp-016 的 100% 预测准确率\n- **建议**：无需补充\n\n---\n\n## exp-028 (negative): 非对称 diagnostic AUC ≈ 对称版\n\n- **论文中是否讨论**：是\n- **讨论位置**：\n  - `theory.tex:56-67`（Remark 2，核心理论结果）\n  - `theory.tex:64-65`（关键推导：column-stochastic M → |B_s[0,1]|=|B_s[1,1]|，非对称退化为对称）\n  - `appendix.tex:168-177`（asymmetric extension 讨论，AUC 0.86→0.66）\n  - `appendix.tex:443-466`（完整 asymmetric 实验 section）\n- **充分性**：**充分**\n  - 退化机制在 theory.tex:65 清楚解释：\"because column-stochastic M forces |B_s[0,1]|=|B_s[1,1]|; practitioners may use the simpler symmetric formula without loss\"\n  - 这是 positive framing：论文将\"非对称退化为对称\"呈现为一个便利的理论结果（practitioners 可以用更简单的公式），而非实验失败\n  - AUC 降低（0.86→0.66）在 appendix.tex:176 中有报告\n- **具体问题**：无。这个实验的 framing 是诚实的——退化结论本身是有用的理论洞见。\n- **建议**：无需补充\n\n---\n\n## exp-030 (negative): K=8 HB RMSE >> Global\n\n- **论文中是否讨论**：是，详细\n- **讨论位置**：\n  - `appendix.tex:376-440`（完整 K=8 subsection，含 per-subgroup breakdown）\n  - `appendix.tex:397`（HB RMSE=0.340 vs Global RMSE=0.168）\n  - `appendix.tex:406`（明确指出 ~31 labels/subgroup 不足）\n  - `experiments.tex:29`（主文提及 K=8 RMSE 增加，推荐 n_expert/K≥50）\n  - `experiments.tex:82`（operating conditions：K≤4）\n  - `limitations.tex:2`（K=8 boundary 明确讨论）\n- **充分性**：**充分**\n  - 主文 experiments.tex:29 直接承认 RMSE 增加\n  - 主文 experiments.tex:82 将 K≤4 列为 operating condition\n  - limitations.tex:2 明确 K=8 boundary：\"coverage remains nominal (≥95.6%) but RMSE exceeds global correction, establishing a scalability boundary\"\n  - Appendix 提供完整 per-subgroup 分析（Table k8_per_subgroup）\n  - 解释了 RMSE degradation 集中在 high-π subgroups（appendix.tex:432）\n- **建议**：无需补充\n\n---\n\n## exp-033 (negative): K=8 adaptive shrinkage 仍不够\n\n- **论文中是否讨论**：是\n- **讨论位置**：\n  - `appendix.tex:436-440`（adaptive shrinkage 结果）\n  - `appendix.tex:438`（RMSE 0.340→0.216，但仍超 Global 0.166）\n  - `appendix.tex:439`（关键结论：\"the bottleneck is per-subgroup sample size (~31 expert labels) rather than the shrinkage method itself\"）\n  - `appendix.tex:440`（给出 n_expert≥500 的推荐）\n- **充分性**：**充分**\n  - Root cause 诊断精准：瓶颈是 per-subgroup sample size 而非 shrinkage 方法（appendix.tex:439）\n  - 给出实际建议：n_expert≥500（~60 labels/subgroup）才能达到 RMSE parity（appendix.tex:440）\n  - 与 exp-030 的讨论形成完整 narrative：K=8 是真实边界，adaptive shrinkage 只能缩小但无法消除差距\n- **建议**：无需补充\n\n---\n\n## 总结\n\n### 需要补充的地方\n\n**无。** 所有 6 个阴性/killed 实验在论文中都有诚实且充分的讨论：\n\n| 实验 | 主文提及 | Appendix 详细分析 | Limitations 提及 | Operating Conditions |\n|------|---------|-------------------|------------------|---------------------|\n| exp-007b | N/A（内部决策） | PPCI section | N/A | N/A |\n| exp-015 | ✓ (experiments.tex:79,82) | ✓ (appendix.tex:751-828) | ✓ (limitations.tex:1) | ✓ (FNR<0.5) |\n| exp-016 | ✓ (via operating conditions) | ✓ (appendix.tex:813-814) | ✓ (via exp-015) | ✓ (FPR<0.5) |\n| exp-028 | ✓ (theory.tex:56-67) | ✓ (appendix.tex:443-466) | ✓ (limitations.tex:6) | N/A |\n| exp-030 | ✓ (experiments.tex:29,82) | ✓ (appendix.tex:376-440) | ✓ (limitations.tex:2) | ✓ (K≤4) |\n| exp-033 | via exp-030 | ✓ (appendix.tex:438-440) | via exp-030 | via exp-030 |\n\n### 风险评估\n\n**低风险。** Reviewer 可能追问的点及论文已有应对：\n\n1. **\"Why does EC-HTE fail on real LLMs?\"** — 论文在 appendix.tex:815 归纳了三个 applicability conditions，在 experiments.tex:82 给出操作指南，在 Figure applicability_frontier 提供可视化决策工具。\n2. **\"K=8 is a limitation — does the method scale?\"** — limitations.tex:2 直接承认 scalability boundary，appendix.tex:440 给出量化建议（n_expert≥500），framing 为 fixed-budget 下的 trade-off 而非方法缺陷。\n3. **\"Asymmetric diagnostic 没有提升？\"** — theory.tex:65 将其 reframe 为理论便利性（practitioners 无需区分 symmetric/asymmetric），而非 negative result。\n4. **\"Why not test on more real data?\"** — limitations.tex:12 诚实承认缺乏 ground-truth subgroup CATEs 的公共数据集，解释了使用 synthetic CATE injection 的原因。\n\n唯一潜在弱点：exp-015/016 的失败在**主文**中的措辞比较间接（experiments.tex:79 说 \"underperforms\"，experiments.tex:82 列 operating conditions），完整 root cause 分析只在 Appendix。但这符合顶会惯例——主文给结论和条件，Appendix 给机制，不构成 framing 问题。\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "8007bb47-6612-4110-81f3-ab95bfb5e7af",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QygSnfiFRr73W5oQdvcWvJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1138,
      "cache_read_input_tokens": 49539,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1138
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

_source line 55 · 2026-05-24T08:01:53.896Z_

<details><summary>↩ Tool result · `toolu_01TzdxYVEWLTZJeCcWaN2BQq`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/artifacts/negative_experiment_framing_audit.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "b1996106-7bcf-4566-928c-66a8e64e491f",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/artifacts/negative_experiment_framing_audit.md",
    "content": "# 阴性实验 Framing 审计\n\n## exp-007b (killed): PPCI 表 HB backfill\n\n- **论文中是否讨论**：不需要（内部决策，非阴性结果）\n- **PPCI composition 讨论完整性**：充分\n- **位置**：`method.tex:55-61`（PPCI composition 段落）、`appendix.tex:507-555`（Appendix PPCI 完整实验）\n- **具体情况**：论文在 method.tex 中清楚说明 EC-HTE 和 PPCI 的互补性（\"Neither is redundant with the other\"），并给出了 4-DGP 正交设计的完整结果（Table PPCI）。DGP-A（仅 covariate error）下 PPCI 无增益，DGP-B（仅 outcome error）下 EC-HTE 贡献可忽略——这些就是 exp-007b 放弃 HB backfill 的理由的间接体现。\n- **建议**：无需补充\n\n---\n\n## exp-015 (negative): GPT-4.1 real CM 上 EC-HTE 失败\n\n- **论文中是否讨论**：是，详细\n- **讨论位置**：\n  - `appendix.tex:751-828`（§Semi-Real CM Validation，完整 section）\n  - `appendix.tex:806-811`（root cause 分析：S0 FNR=0.526）\n  - `appendix.tex:818-821`（diagnostic rule，明确引用 exp-015）\n  - `experiments.tex:82`（operating conditions 汇总，FNR<0.50 条件）\n  - `limitations.tex:1`（FPR/FNR<0.5 条件）\n  - `experiments.tex:79`（hate speech 实测 underperformance）\n- **充分性**：**充分**\n  - Root cause 完整：S0 FNR=0.526 → CM 行近均匀 → inversion 放大噪声（appendix.tex:807）\n  - P(Z=1)=0.18 的 class imbalance 影响在 appendix.tex:756 和 814 中明确提及\n  - 三个 applicability conditions 在 appendix.tex:815 归纳，并上升到 experiments.tex:82 的 operating conditions\n  - 提供了 applicability frontier 图（Figure applicability_frontier.pdf）\n  - 明确指出 exp-015 同时违反 κ 和 effective n 两个条件（appendix.tex:820）\n  - 提到 subgroup-average metrics 可能 mask cell-level heterogeneity（appendix.tex:821）\n- **建议**：无需补充\n\n---\n\n## exp-016 (negative): GPT-3.5-Turbo real CM 上 EC-HTE 失败\n\n- **论文中是否讨论**：是\n- **讨论位置**：\n  - `appendix.tex:813-814`（第二个 semi-real 实验，明确 GPT-3.5-Turbo）\n  - `appendix.tex:820`（diagnostic 正确预测 exp-016 失败）\n  - `appendix.tex:946`（Civil Comments multi-LLM 表中 GPT-3.5-turbo FPR 数据）\n- **充分性**：**充分**\n  - Root cause 明确：high FPR variance (worst-subgroup FPR=0.39) + class imbalance P(Z=1)=0.18（appendix.tex:814）\n  - 与 exp-015 root cause 的一致性被明确指出（\"yields similar results\"）\n  - Diagnostic rule 在 appendix.tex:820 验证了对 exp-016 的 100% 预测准确率\n- **建议**：无需补充\n\n---\n\n## exp-028 (negative): 非对称 diagnostic AUC ≈ 对称版\n\n- **论文中是否讨论**：是\n- **讨论位置**：\n  - `theory.tex:56-67`（Remark 2，核心理论结果）\n  - `theory.tex:64-65`（关键推导：column-stochastic M → |B_s[0,1]|=|B_s[1,1]|，非对称退化为对称）\n  - `appendix.tex:168-177`（asymmetric extension 讨论，AUC 0.86→0.66）\n  - `appendix.tex:443-466`（完整 asymmetric 实验 section）\n- **充分性**：**充分**\n  - 退化机制在 theory.tex:65 清楚解释：\"because column-stochastic M forces |B_s[0,1]|=|B_s[1,1]|; practitioners may use the simpler symmetric formula without loss\"\n  - 这是 positive framing：论文将\"非对称退化为对称\"呈现为一个便利的理论结果（practitioners 可以用更简单的公式），而非实验失败\n  - AUC 降低（0.86→0.66）在 appendix.tex:176 中有报告\n- **具体问题**：无。这个实验的 framing 是诚实的——退化结论本身是有用的理论洞见。\n- **建议**：无需补充\n\n---\n\n## exp-030 (negative): K=8 HB RMSE >> Global\n\n- **论文中是否讨论**：是，详细\n- **讨论位置**：\n  - `appendix.tex:376-440`（完整 K=8 subsection，含 per-subgroup breakdown）\n  - `appendix.tex:397`（HB RMSE=0.340 vs Global RMSE=0.168）\n  - `appendix.tex:406`（明确指出 ~31 labels/subgroup 不足）\n  - `experiments.tex:29`（主文提及 K=8 RMSE 增加，推荐 n_expert/K≥50）\n  - `experiments.tex:82`（operating conditions：K≤4）\n  - `limitations.tex:2`（K=8 boundary 明确讨论）\n- **充分性**：**充分**\n  - 主文 experiments.tex:29 直接承认 RMSE 增加\n  - 主文 experiments.tex:82 将 K≤4 列为 operating condition\n  - limitations.tex:2 明确 K=8 boundary：\"coverage remains nominal (≥95.6%) but RMSE exceeds global correction, establishing a scalability boundary\"\n  - Appendix 提供完整 per-subgroup 分析（Table k8_per_subgroup）\n  - 解释了 RMSE degradation 集中在 high-π subgroups（appendix.tex:432）\n- **建议**：无需补充\n\n---\n\n## exp-033 (negative): K=8 adaptive shrinkage 仍不够\n\n- **论文中是否讨论**：是\n- **讨论位置**：\n  - `appendix.tex:436-440`（adaptive shrinkage 结果）\n  - `appendix.tex:438`（RMSE 0.340→0.216，但仍超 Global 0.166）\n  - `appendix.tex:439`（关键结论：\"the bottleneck is per-subgroup sample size (~31 expert labels) rather than the shrinkage method itself\"）\n  - `appendix.tex:440`（给出 n_expert≥500 的推荐）\n- **充分性**：**充分**\n  - Root cause 诊断精准：瓶颈是 per-subgroup sample size 而非 shrinkage 方法（appendix.tex:439）\n  - 给出实际建议：n_expert≥500（~60 labels/subgroup）才能达到 RMSE parity（appendix.tex:440）\n  - 与 exp-030 的讨论形成完整 narrative：K=8 是真实边界，adaptive shrinkage 只能缩小但无法消除差距\n- **建议**：无需补充\n\n---\n\n## 总结\n\n### 需要补充的地方\n\n**无。** 所有 6 个阴性/killed 实验在论文中都有诚实且充分的讨论：\n\n| 实验 | 主文提及 | Appendix 详细分析 | Limitations 提及 | Operating Conditions |\n|------|---------|-------------------|------------------|---------------------|\n| exp-007b | N/A（内部决策） | PPCI section | N/A | N/A |\n| exp-015 | ✓ (experiments.tex:79,82) | ✓ (appendix.tex:751-828) | ✓ (limitations.tex:1) | ✓ (FNR<0.5) |\n| exp-016 | ✓ (via operating conditions) | ✓ (appendix.tex:813-814) | ✓ (via exp-015) | ✓ (FPR<0.5) |\n| exp-028 | ✓ (theory.tex:56-67) | ✓ (appendix.tex:443-466) | ✓ (limitations.tex:6) | N/A |\n| exp-030 | ✓ (experiments.tex:29,82) | ✓ (appendix.tex:376-440) | ✓ (limitations.tex:2) | ✓ (K≤4) |\n| exp-033 | via exp-030 | ✓ (appendix.tex:438-440) | via exp-030 | via exp-030 |\n\n### 风险评估\n\n**低风险。** Reviewer 可能追问的点及论文已有应对：\n\n1. **\"Why does EC-HTE fail on real LLMs?\"** — 论文在 appendix.tex:815 归纳了三个 applicability conditions，在 experiments.tex:82 给出操作指南，在 Figure applicability_frontier 提供可视化决策工具。\n2. **\"K=8 is a limitation — does the method scale?\"** — limitations.tex:2 直接承认 scalability boundary，appendix.tex:440 给出量化建议（n_expert≥500），framing 为 fixed-budget 下的 trade-off 而非方法缺陷。\n3. **\"Asymmetric diagnostic 没有提升？\"** — theory.tex:65 将其 reframe 为理论便利性（practitioners 无需区分 symmetric/asymmetric），而非 negative result。\n4. **\"Why not test on more real data?\"** — limitations.tex:12 诚实承认缺乏 ground-truth subgroup CATEs 的公共数据集，解释了使用 synthetic CATE injection 的原因。\n\n唯一潜在弱点：exp-015/016 的失败在**主文**中的措辞比较间接（experiments.tex:79 说 \"underperforms\"，experiments.tex:82 列 operating conditions），完整 root cause 分析只在 Appendix。但这符合顶会惯例——主文给结论和条件，Appendix 给机制，不构成 framing 问题。\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
```

</details>

---

### Assistant

_source line 56_

审计完成。所有 6 个阴性/killed 实验在论文中都有诚实充分的讨论，无需补充。

关键发现：
- **exp-015/016**（real CM 失败）：主文给出 operating conditions（FNR<0.5, K≤4），Appendix 有完整 root cause 分析和 applicability frontier 图
- **exp-030/033**（K=8 boundary）：主文、limitations、Appendix 三处覆盖，明确承认 scalability boundary
- **exp-028**（非对称 diagnostic 退化）：theory.tex Remark 2 中 reframe 为理论便利性，framing 合理
- **exp-007b**（killed）：无需提及，PPCI composition 讨论完整

唯一潜在弱点是 exp-015/016 完整 root cause 只在 Appendix，主文措辞较间接，但符合顶会惯例。

产出已写入 `artifacts/negative_experiment_framing_audit.md`。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "uuid": "9817b7d3-0028-4af0-a137-a640028fb8a9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0186ufg5cUHtBsYYPSHcUeVD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3207,
      "cache_read_input_tokens": 50677,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3207
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

_source line 57_

审计完成。所有 6 个阴性/killed 实验在论文中都有诚实充分的讨论，无需补充。

关键发现：
- **exp-015/016**（real CM 失败）：主文给出 operating conditions（FNR<0.5, K≤4），Appendix 有完整 root cause 分析和 applicability frontier 图
- **exp-030/033**（K=8 boundary）：主文、limitations、Appendix 三处覆盖，明确承认 scalability boundary
- **exp-028**（非对称 diagnostic 退化）：theory.tex Remark 2 中 reframe 为理论便利性，framing 合理
- **exp-007b**（killed）：无需提及，PPCI composition 讨论完整

唯一潜在弱点是 exp-015/016 完整 root cause 只在 Appendix，主文措辞较间接，但符合顶会惯例。

产出已写入 `artifacts/negative_experiment_framing_audit.md`。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 144200,
  "duration_api_ms": 145334,
  "num_turns": 22,
  "stop_reason": "end_turn",
  "session_id": "3bd0af4a-496c-4c25-9b63-48839d4f0524",
  "total_cost_usd": 0.59835875,
  "usage": {
    "input_tokens": 11,
    "cache_creation_input_tokens": 42043,
    "cache_read_input_tokens": 358370,
    "output_tokens": 6183,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 42043,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 291,
        "cache_read_input_tokens": 50677,
        "cache_creation_input_tokens": 3207,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 3207
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1695,
      "outputTokens": 16,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.0017749999999999999,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 11,
      "outputTokens": 6183,
      "cacheReadInputTokens": 358370,
      "cacheCreationInputTokens": 42043,
      "webSearchRequests": 0,
      "costUSD": 0.5965837500000001,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "175a226c-cb84-420b-9c31-6570a027d13e"
}
```

</details>

---
