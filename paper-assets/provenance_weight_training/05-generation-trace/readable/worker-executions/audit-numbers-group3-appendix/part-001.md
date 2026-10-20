# audit numbers group3 appendix — Part 1 of 2

**When Does Detect-and-Reweight Work for Synthetic Contamination?** · Worker execution logs

[Transcript overview](../audit-numbers-group3-appendix.md) · [Part 2 →](part-002.md) · [Structured JSON](../../../sessions/7e/7eb11a7da3fbe1204f2f.json)

## Before a recorded user message

## Before a recorded user message

83 recorded events


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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
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
  "uuid": "d13fa3c9-4454-437b-912a-415da4a3080c",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/memory/"
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
    "resetsAt": 1779754200,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "49e218bb-99ab-4892-9008-2fa5c1fcd564",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
The user wants me to audit all numbers in the appendix.tex file for accuracy, traceability, and consistency with the main text. Let me start by reading the appendix file and the registry, then cross-reference with the main text sections.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "5d2caa7a-efc2-47a9-8624-d6c1df153bda",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Axc8ZKTov5FbVFTMh4x2Me",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12807,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12807
      },
      "output_tokens": 32,
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

开始审计 appendix.tex 中的所有数字。先读取文件和 registry。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "192a0caa-ee80-4aef-8334-7a70f122cca4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Axc8ZKTov5FbVFTMh4x2Me",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12807,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12807
      },
      "output_tokens": 32,
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

<details open><summary>🔧 Tool call — Read · `toolu_01YRsteYE1KFoWCv1bhkBWFt`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "0237bb63-5db3-44ae-bdb2-71bbc0a487e8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Axc8ZKTov5FbVFTMh4x2Me",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12807,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12807
      },
      "output_tokens": 32,
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

_source line 7 · 2026-05-25T20:02:36.982Z_

<details><summary>↩ Tool result · `toolu_01YRsteYE1KFoWCv1bhkBWFt`</summary>

```text
1	\section{Proofs}
2	\label{app:proofs}
3	
4	\begin{proposition}[$\alpha_{\mathrm{eff}}$ monotonicity]
5	\label{prop:monotone}
6	$\alpha_{\mathrm{eff}}(b)$ is non-decreasing in $b$, and strictly increasing whenever the batch contains at least two samples with distinct $q$-values.
7	\end{proposition}
8	
9	\begin{proof}[Proof of Proposition~\ref{prop:monotone}]
10	Let $w_i(b) = (1 - q_i)^b$, $W(b) = \sum_{j=1}^B w_j(b)$, and $\pi_i(b) = w_i(b) / W(b)$.
11	Then
12	\begin{equation*}
13	  \alpha_{\mathrm{eff}}(b) = \sum_{i=1}^{B} \pi_i(b)\, (1 - q_i).
14	\end{equation*}
15	Taking the derivative with respect to $b$:
16	\begin{align*}
17	  \frac{d\pi_i}{db}
18	  &= \pi_i \!\left(\frac{d \ln w_i}{db} - \frac{d \ln W}{db}\right) \\
19	  &= \pi_i \!\left(\ln(1{-}q_i) - \textstyle\sum_j \pi_j \ln(1{-}q_j)\right).
20	\end{align*}
21	Substituting,
22	\begin{align*}
23	  \frac{d\alpha_{\mathrm{eff}}}{db}
24	  &= \sum_i (1{-}q_i)\, \pi_i \!\left(\ln(1{-}q_i) - \mathbb{E}_{\pi}[\ln(1{-}q)]\right) \\
25	  &= \mathrm{Cov}_{\pi}\!\bigl(1{-}q_i,\, \ln(1{-}q_i)\bigr).
26	\end{align*}
27	Since $(1{-}q_i)$ and $\ln(1{-}q_i)$ are both increasing functions of $(1{-}q_i)$, they are positively associated, so the covariance is non-negative.
28	\end{proof}
29	
30	\begin{proposition}[ESS monotonicity]
31	\label{prop:ess_mono}
32	$\mathrm{ESS}(b)$ is non-increasing in $b$, and strictly decreasing whenever the batch contains at least two samples with distinct $q$-values.
33	\end{proposition}
34	
35	\begin{proof}
36	Write $\mathrm{ESS}(b) = 1 / \sum_i \pi_i(b)^2$, where $\pi_i(b) = w_i(b) / W(b)$.
37	The denominator $\sum_i \pi_i^2$ is the Herfindahl index $H$.
38	Differentiating $H$ with respect to $b$:
39	\begin{equation*}
40	  \frac{dH}{db} = 2 \sum_i \pi_i^2 \bigl(\ln(1{-}q_i) - \mathbb{E}_{\pi}[\ln(1{-}q)]\bigr).
41	\end{equation*}
42	Since $\pi_i \propto (1{-}q_i)^b$, larger $\pi_i$ implies larger $\ln(1{-}q_i)$; the $\pi^2$-weighted sum assigns greater mass to terms where $\ln(1{-}q_i) > \mathbb{E}_\pi[\ln(1{-}q)]$, so $dH/db \geq 0$, with strict inequality when at least two $q$-values differ.
43	Thus $H$ is non-decreasing and $\mathrm{ESS} = 1/H$ is non-increasing.
44	This is a standard property of exponential tilting~\citep{kish1965survey,owen2013mc}.
45	\end{proof}
46	
47	\section{Algorithm Details}
48	\label{app:algorithm}
49	
50	\begin{algorithm}[h]
51	\caption{Per-batch adaptive $b^{*}$ selection}
52	\label{alg:bstar}
53	\begin{algorithmic}[1]
54	\REQUIRE Batch scores $\{q_i\}_{i=1}^{B}$, threshold~$\tau$, ESS floor~$n_{\min}$, bound~$b_{\max}$, tol.~$\varepsilon$
55	\ENSURE Optimal sharpening exponent $b^{*}$
56	\IF{$\alpha_{\mathrm{eff}}(0) \geq \tau$}
57	  \STATE \textbf{return} $0$ \COMMENT{clean batch}
58	\ENDIF
59	\STATE $b_\tau \gets \textsc{Bisect}(\alpha_{\mathrm{eff}}(\cdot){=}\tau,\; [0, b_{\max}],\; \varepsilon)$
60	\IF{$\mathrm{ESS}(b_\tau) \geq n_{\min}$}
61	  \STATE \textbf{return} $b_\tau$ \COMMENT{$\alpha_{\mathrm{eff}}$-binding}
62	\ELSE
63	  \STATE $b_{\mathrm{ESS}} \gets \textsc{Bisect}(\mathrm{ESS}(\cdot){=}n_{\min},\; [0, b_{\max}],\; \varepsilon)$
64	  \STATE \textbf{return} $b_{\mathrm{ESS}}$ \COMMENT{ESS-binding}
65	\ENDIF
66	\end{algorithmic}
67	\end{algorithm}
68	
69	\begin{figure}[h]
70	\centering
71	\includegraphics[width=\columnwidth]{bstar_trajectory_adaptive_fix}
72	\caption{Adaptive $\bstar$ trajectory over 6{,}103 training steps (seed\,42, $\rho{=}0.4$).
73	The exponent alternates between clean ($\bstar{=}0$), $\aeff$-binding, and ESS-binding regimes with no systematic drift, reflecting per-batch adaptation to local $q$-score composition.}
74	\label{fig:bstar_traj}
75	\end{figure}
76	We compute $\bstar$ at the micro-batch level ($B{=}4$) rather than the effective batch ($B{=}16$ after gradient accumulation) because $q$-score statistics exhibit sufficient variance within micro-batches: Spearman $r{=}0.699$ with the true real fraction, and at $B{=}16$ the adaptive advantage amplifies $3.0{\times}$ ($\Delta{=}{-}0.068{\pm}0.005$; \S\ref{sec:sensitivity}).
77	
78	\section{Grid Search Details}
79	\label{app:grid}
80	
81	Table~\ref{tab:grid_full} reports held-out PPL for all grid-$b$ values at $\rho = 0.4$ (seed\,42).
82	
83	\begin{table}[h]
84	\centering
85	\small
86	\begin{tabular}{@{}cc@{}}
87	\toprule
88	$b$ & PPL $\downarrow$ \\
89	\midrule
90	0.1 & 17.657 \\
91	0.2 & 17.640 \\
92	0.3 & \textbf{17.640} \\
93	0.5 & 17.651 \\
94	1.0 & 17.692 \\
95	1.5 & 17.718 \\
96	2.0 & 17.741 \\
97	3.0 & 17.774 \\
98	5.0 & 17.818 \\
99	\bottomrule
100	\end{tabular}
101	\caption{Full grid search results ($\rho{=}0.4$, seed\,42).
102	$b \in [0.1, 0.5]$ forms a broad plateau (three-seed mean for $b{=}0.1$: $17.655 \pm 0.009$); $b{=}0.3$ is the post-hoc best.}
103	\label{tab:grid_full}
104	\end{table}
105	
106	\section{Quality Threshold Sweep}
107	\label{app:tau_sweep}
108	
109	\begin{table}[h]
110	\centering
111	\small
112	\resizebox{\columnwidth}{!}{%
113	\begin{tabular}{@{}ccccccc@{}}
114	\toprule
115	$\tau$ & Holdout $\downarrow$ & $\Delta_{\text{H}}$ & OWT $\downarrow$ & $\Delta_{\text{O}}$ & Wiki $\downarrow$ & $\Delta_{\text{W}}$ \\
116	\midrule
117	0.50 & 17.688 & $-$0.006 & -- & -- & -- & -- \\
118	0.60 & 17.681 & $-$0.013 & -- & -- & -- & -- \\
119	0.70$^\star$ & \textbf{17.674{\tiny$\pm$.006}} & $\boldsymbol{-}$\textbf{0.020} & \textbf{18.347{\tiny$\pm$.003}} & $\boldsymbol{-}$\textbf{0.028} & \textbf{15.330{\tiny$\pm$.015}} & $\boldsymbol{-}$\textbf{0.029} \\
120	0.80$^\star$ & 17.683{\tiny$\pm$.006} & $-$0.011 & 18.370{\tiny$\pm$.005} & $-$0.005 & 15.350 & $-$0.009 \\
121	0.90 & 17.712 & $+$0.018 & -- & -- & -- & -- \\
122	0.95 & 17.723 & $+$0.029 & -- & -- & -- & -- \\
123	\bottomrule
124	\end{tabular}}
125	\caption{Quality threshold sweep ($\nmin{=}2$, $\rho{=}0.4$).
126	$\Delta$ relative to 3-seed uniform baseline (Holdout 17.694, OWT 18.375, Wiki 15.359).
127	$^\star$\,$\tau{=}0.7$: 5-seed mean (SD from 5 seeds); $\tau{=}0.8$: 3 from-scratch seeds (Appendix~\ref{app:resume_artifact}). The 5-seed comparison in Table~\ref{tab:main} yields $\Delta{=}{-}0.023$.
128	Other values from single-seed exploratory sweep (seed\,42, holdout only).
129	$\tau{=}0.7$ achieves the lowest holdout and largest OOD gains ($|\Delta| \geq 0.028$); $\tau{=}0.8$'s OOD effect is smaller ($|\Delta| \leq 0.009$).}
130	\label{tab:tau}
131	\end{table}
132	
133	\section{Batch-Adaptive $\tau$}
134	\label{app:batch_adaptive}
135	
136	We tested a per-batch adaptive variant that clamps $\tau$ between 0.5 and the fixed threshold based on local $\aeff(0)$, allowing the quality floor to relax in batches with low estimated real fraction.
137	At both contamination levels ($\rho \in \{0.4, 0.6\}$), the adaptive variant did not outperform the fixed threshold (single-seed exploratory at each level), suggesting the quality constraint does not require adaptation to local contamination density.
138	This supports the ``two hyperparameters with good defaults'' characterization: neither $\tau$ nor $\nmin$ benefits from per-batch tuning.
139	
140	\section{\texorpdfstring{$\tau$--$\rho$}{tau-rho} Rank Preservation}
141	\label{app:tau_rho}
142	
143	Figure~\ref{fig:tau_rho_rank} shows the $\tau$--PPL relationship at two contamination levels.
144	
145	\begin{figure}[h]
146	\centering
147	\includegraphics[width=\columnwidth]{tau_rho_rank_preservation}
148	\caption{(a) Held-out PPL as a function of quality threshold $\tau$ at $\rho \in \{0.4, 0.6\}$.
149	$\tau{=}0.7$ and $\tau{=}0.8$ yield comparable holdout PPL at $\rho{=}0.4$; at $\rho{=}0.6$, $\tau{=}0.7$ is statistically better (paired $t{=}{-}4.70$, $p{<}0.05$, 3 seeds, $\Delta{=}{-}0.005$). $\tau{=}0.7$ also achieves lower OOD perplexity at both levels ($\rho{=}0.6$: $\Delta_{\text{OWT}}{=}{-}0.014$, $\Delta_{\text{Wiki}}{=}{-}0.013$, 2 seeds).
150	(b) Normalized PPL gap relative to uniform at shared $\tau$ values.}
151	\label{fig:tau_rho_rank}
152	\end{figure}
153	
154	\section{Hybrid and Threshold Comparison}
155	\label{app:hybrid}
156	
157	Table~\ref{tab:hybrid} compares method families across contamination levels.
158	Table~\ref{tab:dr_threshold} shows D\&R sensitivity to the detection threshold at both full training length and epoch-matched settings.
159	Raw PPL traces a U-shaped curve with a minimum at $q{>}0.3$ (17.250, 3 seeds), but this curve conflates filtering quality with multi-epoch exposure: aggressive thresholds retain less data and repeat it more often.
160	Epoch-matched comparisons (rightmost column of Table~\ref{tab:dr_threshold}) remove the multi-epoch confound: the U-shape vanishes and PPL decreases monotonically, saturating near the adaptive $\bstar$ level at $q{\geq}0.5$.
161	Figure~\ref{fig:dr_dual_curve} visualizes the two curves.
162	
163	\begin{table}[h]
164	\centering
165	\small
166	\begin{tabular}{@{}lcc@{}}
167	\toprule
168	\textbf{Method} & $\rho{=}0.4$ & $\rho{=}0.6$ \\
169	\midrule
170	Uniform & 17.694 & 17.766 \\
171	Adaptive $\bstar$ & 17.689 & 17.740 \\
172	Hybrid ($q{>}0.95$ + adaptive) & 17.514 & 17.530$^*$ \\
173	Detect \& Remove ($q{>}0.5$) & 17.285 & -- \\
174	Detect \& Remove ($q{>}0.3$) & 17.250 & -- \\
175	\bottomrule
176	\end{tabular}
177	\caption{Method comparison across contamination levels (seed\,42, $\tau{=}0.8$).
178	$^*$Hybrid at $\rho{=}0.6$ filters high-confidence synthetic ($q{>}0.95$), reducing effective $\rho$ to ${\approx}0.4$; PPL is not directly comparable to $\rho{=}0.6$ baselines.}
179	\label{tab:hybrid}
180	\end{table}
181	
182	\begin{table}[h]
183	\centering
184	\small
185	\setlength{\tabcolsep}{3pt}
186	\begin{tabular}{@{}ccccc@{}}
187	\toprule
188	\textbf{Thresh.} & \textbf{Ret.\ \%} & \textbf{Epochs} & \textbf{Raw PPL} $\downarrow$ & \textbf{Ep.-matched} $\downarrow$ \\
189	\midrule
190	$q > 0.1$ & 15.0\% & ${\sim}$10.0 & 17.40 & 18.04 \\
191	$q > 0.2$ & ${\sim}$23\% & ${\sim}$5.0 & 17.27 & -- \\
192	$q > 0.3$ & 31.5\% & ${\sim}$3.2 & \textbf{17.250}$^\dagger$ & 17.74 \\
193	$q > 0.4$ & ${\sim}$38\% & ${\sim}$2.8 & 17.26 & -- \\
194	$q > 0.5$ & 41.4\% & ${\sim}$2.4 & 17.28 & 17.65 \\
195	$q > 0.6$ & ${\sim}$46\% & ${\sim}$1.7 & 17.30 & -- \\
196	$q > 0.7$ & 49.8\% & ${\sim}$2.0 & 17.32 & 17.62 \\
197	$q > 0.8$ & ${\sim}$56\% & ${\sim}$1.3 & 17.34 & -- \\
198	$q > 0.9$ & 61.6\% & ${\sim}$1.1 & 17.42 & 17.628 \\
199	\bottomrule
200	\end{tabular}
201	\caption{D\&R threshold sensitivity ($\rho{=}0.4$, seed\,42 unless noted).
202	Raw PPL traces a U-shaped curve (minimum at $q{>}0.3$); epoch-matched PPL (single content epoch) decreases monotonically and saturates near the adaptive $\bstar$ level (${\approx}$17.65) at $q{\geq}0.5$; the U-shape is thus a multi-epoch artifact.
203	$^\dagger$\,3-seed mean $17.250 \pm 0.001$.}
204	\label{tab:dr_threshold}
205	\end{table}
206	
207	See Figure~\ref{fig:dr_dual_curve} (\S\ref{sec:main-results}) for the dual-curve visualization.
208	
209	\section{Downstream Task Evaluation}
210	\label{app:downstream}
211	
212	Table~\ref{tab:downstream} reports downstream benchmark accuracy for adaptive vs.\ uniform training at $\rho{=}0.4$ (seed\,42, Qwen3-0.6B).
213	Across multiple seeds, downstream differences are mixed in direction and uniformly within standard error, indicating that adaptive reweighting has no meaningful downstream impact.
214	
215	\begin{table}[h]
216	\centering
217	\small
218	\resizebox{\columnwidth}{!}{%
219	\begin{tabular}{@{}llccc@{}}
220	\toprule
221	\textbf{Benchmark} & \textbf{Metric} & \textbf{Adaptive} & \textbf{Uniform} & $\boldsymbol{\Delta}$ \\
222	\midrule
223	\multicolumn{5}{@{}l}{\textit{Seed 42 (checkpoint resume)}} \\
224	ARC-Challenge & acc\_norm & 0.343 & 0.348 & $-$0.005 \\
225	ARC-Easy & acc & 0.650 & 0.657 & $-$0.007 \\
226	HellaSwag & acc\_norm & 0.479 & 0.484 & $-$0.005 \\
227	PIQA & acc & 0.687 & 0.686 & $+$0.001 \\
228	WinoGrande & acc & 0.578 & 0.586 & $-$0.008 \\
229	\midrule
230	\multicolumn{5}{@{}l}{\textit{From-scratch 2-seed mean (seeds 123, 456)}} \\
231	\multicolumn{3}{@{}l}{Mean $\Delta$ across 5 tasks} & & $+$0.001 \\
232	\multicolumn{3}{@{}l}{Direction} & \multicolumn{2}{c}{mixed (seed 123: 3/5$-$; seed 456: 3/5$+$)} \\
233	\bottomrule
234	\end{tabular}}
235	\caption{Downstream benchmarks (Qwen3-0.6B, $\rho{=}0.4$).
236	Seed\,42 used a checkpoint-resumed adaptive model; from-scratch seeds (123, 456) show mixed direction with mean $|\Delta| \leq 0.01$.
237	All differences within standard error ($\pm 0.01$).
238	Models use $\tau{=}0.8$; $\tau{=}0.7$ yields identical 3-seed means (0.5414).}
239	\label{tab:downstream}
240	\end{table}
241	
242	\section{Higher Contamination Details}
243	\label{app:rho06}
244	
245	Table~\ref{tab:rho06} reports results at $\rho{=}0.6$.
246	The full five-method ablation preserves the hierarchy from $\rho{=}0.4$ across all three seeds: Grid ${<}$ Adaptive ${<}$ Uniform ${\approx}$ ESS-only ${<}$ Random.
247	
248	\begin{table}[h]
249	\centering
250	\small
251	\resizebox{\columnwidth}{!}{%
252	\begin{tabular}{@{}lcccc@{}}
253	\toprule
254	\textbf{Method} & \textbf{Seed 42} & \textbf{Seed 123} & \textbf{Seed 456} & \textbf{Mean} \\
255	\midrule
256	Grid ($b{=}0.3$)$^\ddagger$ & \textbf{17.634} & -- & -- & -- \\
257	Adaptive $\bstar$ & 17.735 & 17.727 & 17.732 & 17.731 $\pm$ .004 \\
258	Uniform           & 17.766 & 17.754 & 17.770 & 17.763 $\pm$ .008 \\
259	ESS-only          & 17.770 & 17.760 & 17.760 & 17.763 $\pm$ .006 \\
260	Random $\mathcal{U}(0,2)$ & 17.832 & 17.870 & 17.880 & 17.861 $\pm$ .025 \\
261	\bottomrule
262	\end{tabular}}
263	\caption{Results at $\rho{=}0.6$ (Qwen3-0.6B, $\nmin{=}2$).
264	Adaptive uses $\tau{=}0.7$ (consistent with main results); other methods are $\tau$-independent.
265	$^\ddagger$Post-hoc oracle; seed\,42 only.
266	Adaptive vs.\ Uniform: $\Delta{=}{-}0.032$, paired $t{=}{-}15.4$, $p{=}0.004$ (full precision; 3dp rounding yields $t{=}{-}9.95$, $p{=}0.010$).
267	ESS-only collapses onto Uniform (both $17.763$); Random ($17.861$) confirms detector signal is load-bearing.}
268	\label{tab:rho06}
269	\end{table}
270	
271	The ESS-only/Uniform gap collapses from 0.043 at $\rho{=}0.4$ to 0.000 at $\rho{=}0.6$ (three-seed means: both $17.763$); ESS binding rises to ${\sim}$49\% of batches (from ${\sim}$43\% at $\rho{=}0.4$), and the constraints become nearly balanced rather than $\aeff$-dominant.
272	The adaptive method maintains its advantage ($\Delta{=}{-}0.032$, consistent across seeds) through the $\aeff$ quality constraint, which operates independently of the ESS ceiling.
273	Random reweighting ($17.861 \pm 0.025$) is substantially worse than Uniform, with the highest cross-seed variance; uninformed weights add noise without corrective signal.
274	The Adaptive-vs-Grid gap is 0.054 at $\rho{=}0.4$ (mean-to-mean, consistent with Table~\ref{tab:aux}) and 0.097 at $\rho{=}0.6$ (adaptive 3-seed mean vs.\ grid seed\,42; the $\rho{=}0.6$ grid result is preliminary and may not generalize across seeds).
275	
276	\section{\texorpdfstring{$\alpha_{\mathrm{eff}}$}{alpha-eff} Proxy Validation}
277	\label{app:alpha_validation}
278	
279	Table~\ref{tab:alpha_corr} reports the correlation between $\aeff(0)$ (the detector-based proxy at $b{=}0$) and the true batch-level real fraction $\alpha_{\mathrm{true}}$, computed over all training batches at $\rho{=}0.4$ (seed\,42).
280	
281	\begin{table}[h]
282	\centering
283	\small
284	\begin{tabular}{@{}ccccc@{}}
285	\toprule
286	$B$ & Pearson $r$ & Spearman $r$ & MAE$\downarrow$ & Bias \\
287	\midrule
288	4  & 0.706 & 0.699 & 0.114 & $-$0.029 \\
289	8  & 0.697 & 0.683 & 0.097 & $-$0.027 \\
290	16 & 0.707 & 0.691 & 0.075 & $-$0.031 \\
291	\bottomrule
292	\end{tabular}
293	\caption{Correlation between $\aeff(0)$ and true batch-level real fraction across batch sizes ($\rho{=}0.4$, seed\,42).
294	Values use a binarized proxy $\hat{r}_i = \mathbf{1}[q_i \leq 0.5]$ for discrete comparison; the continuous formulation used during training (\S\ref{sec:method}) achieves $r \approx 0.77$--$0.79$ depending on batch size.
295	The consistent negative bias (${\approx}{-}0.03$) indicates that $\aeff$ slightly underestimates the true real fraction, biasing the method toward conservative intervention.}
296	\label{tab:alpha_corr}
297	\end{table}
298	
299	Mean absolute error (MAE) decreases with batch size (0.114 $\to$ 0.075) as expected from averaging, but the rank-order information that drives $\bstar$ selection is already well-captured at $B{=}4$.
300	
301	\paragraph{Cross-seed stability.}
302	Table~\ref{tab:alpha_corr_perseed} reports the correlation between $\aeff$ and the batch mean $q$-score ($\bar{q}$, computed from known labels) across all three seeds.
303	
304	\begin{table}[h]
305	\centering
306	\small
307	\begin{tabular}{@{}cccc@{}}
308	\toprule
309	\textbf{Seed} & Pearson $r(\aeff, \bar{q})$ & Spearman $\rho_s$ & $\bstar{=}0$ (\%) \\
310	\midrule
311	42  & 0.8019 & 0.8761 & 5.8 \\
312	123 & 0.7994 & 0.8692 & 5.7 \\
313	456 & 0.8006 & 0.8749 & 5.9 \\
314	\midrule
315	\textbf{Spread} & 0.0025 & 0.0069 & 0.2 \\
316	\bottomrule
317	\end{tabular}
318	\caption{Per-seed $\aeff$--$\bar{q}$ correlation ($\rho{=}0.4$, $B{=}4$).
319	Cross-seed spread is $<$0.003 for Pearson $r$ and $<$0.007 for Spearman $\rho_s$, indicating stable proxy fidelity across random seeds.
320	$r(\aeff, \bar{q}) = 0.80$ measures the proxy's fidelity to batch composition; the ground-truth correlation $r(\aeff, \text{true real fraction}) \approx 0.79$ (\S\ref{sec:discussion}) is slightly lower due to detector noise.
321	The per-seed table demonstrates cross-seed stability rather than superseding the ground-truth estimate.}
322	\label{tab:alpha_corr_perseed}
323	\end{table}
324	
325	\section{Detector Comparison}
326	\label{app:detector}
327	
328	See Figure~\ref{fig:overview}b (\S\ref{sec:robustness}) for the detector requirements visualization.
329	
330	Table~\ref{tab:detector} compares three detector families for adaptive reweighting.
331	The discriminative TF-IDF+LR detector (ECE\,=\,0.048) produces the only improvement over uniform.
332	The TF-IDF vs.\ GPT-2 contrast (comparable AUC: 0.94 vs.\ 0.91, but $2.7{\times}$ ECE gap: 0.048 vs.\ 0.131) isolates calibration as an empirically observed requirement; however, N-gram's better ECE (0.069) does not compensate for its low AUC (0.73); both sufficient discrimination and good calibration are jointly necessary in our setting.
333	TF-IDF+LR's $q$-scores have reliable probabilistic semantics, so the $\aeff$ proxy accurately tracks batch quality.
334	Generative detectors assign high $q$-scores to fluent, predictable human text (false positives concentrated among high-quality samples), systematically inflating $\aeff$ for clean batches and deflating it for contaminated ones, which inverts the minimum-intervention logic.
335	
336	\begin{table}[h]
337	\centering
338	\small
339	\resizebox{\columnwidth}{!}{%
340	\begin{tabular}{@{}llccccc@{}}
341	\toprule
342	\textbf{Detector} & \textbf{Type} & \textbf{AUC} & \textbf{ECE} & \textbf{Mean PPL} & $\boldsymbol{\Delta}$ \\
343	\midrule
344	TF-IDF+LR & Discriminative & 0.94 & 0.048 & 17.650{\tiny$\pm$.010} & $-$0.044 \\
345	GPT-2 PPL & Generative & 0.91 & 0.131 & 17.792{\tiny$\pm$.005} & $+$0.098 \\
346	N-gram PPL & Generative & 0.73 & 0.069 & 17.823{\tiny$\pm$.003} & $+$0.129 \\
347	\bottomrule
348	\end{tabular}}
349	\caption{Detector comparison for adaptive reweighting ($\rho{=}0.4$, $\tau{=}0.8$, 3 seeds).
350	Uniform baseline PPL\,=\,17.694.
351	$\Delta$ = Adaptive $-$ Uniform (negative is better).
352	TF-IDF+LR calibrated via temperature scaling.
353	The $\tau$ confound is conservative: TF-IDF+LR at $\tau{=}0.7$ achieves 17.674 (Table~\ref{tab:main}).}
354	\label{tab:detector}
355	\end{table}
356	
357	\section{Detector and Synthetic Data Details}
358	\label{app:detector_details}
359	
360	\paragraph{TF-IDF+LR detector.}
361	TF-IDF features (unigrams + bigrams, max 50{,}000 features, sublinear TF) fed to Logistic Regression (C\,=\,1.0, L2 penalty, solver\,=\,lbfgs, max\_iter\,=\,100).
362	Trained on a held-out labeled split (10K documents per class).
363	Post-hoc temperature scaling applied when uncalibrated ECE exceeds 0.05: a scalar $T$ is searched via \texttt{scipy.optimize.minimize\_scalar} over $[0.1, 10.0]$ on a 20\% stratified validation split, yielding $T{=}0.204$ (ECE reduced from 0.12 to 0.05).
364	The detector is selected automatically from six configurations as the first satisfying AUC $\in [0.85, 0.98]$ and mid-range score ratio $\geq 5\%$.
365	
366	\paragraph{Synthetic data generation.}
367	Continuations generated with Qwen3-0.6B (self-generation) using nucleus sampling ($p{=}0.95$, $T{=}0.8$), producing up to 384 tokens per continuation from a 128-token prefix prompt (512 total), targeting ${\sim}$100M synthetic tokens.
368	Source prompts are the first 128 tokens of randomly sampled FineWeb documents, used as prefix continuations.
369	Injected at token-level ratio $\rho$ via uniform random mixing across the training corpus.
370	
371	\section{Low Contamination Analysis}
372	\label{app:rho02}
373	
374	At $\rho{=}0.2$, the adaptive method degrades by $+$0.046 PPL relative to uniform (0.26\% relative, seed\,42).
375	The detector's mean $q$-score at this contamination level is 0.393 (vs.\ 0.487 at $\rho{=}0.4$), indicating that many clean samples receive moderate $q$-scores, blurring the provenance signal.
376	The regime decomposition reveals 13.7\% clean batches ($\bstar{=}0$), 60.1\% $\aeff$-binding, and 26.3\% ESS-binding, with mean $\bstar{=}1.735$ in reweighted batches.
377	The high $\aeff$-binding rate (60.1\% vs.\ ${\sim}$50\% at $\rho{=}0.4$) means the method actively intervenes rather than defaulting to $\bstar{=}0$, but the unreliable signal causes it to suppress useful training data.
378	This is consistent with the generative detector failures: when $q$-scores do not reliably separate provenance, the minimum intervention framework amplifies the error rather than correcting it.
379	The effective range of the method is $\rho \geq 0.4$ with $\tau \in [0.7, 0.8]$ (\S\ref{sec:sensitivity}); lower $\tau$ values may extend the range but have not been tested at $\rho{=}0.2$.
380	
381	\section{Cross-Model Transfer}
382	\label{app:cross_model}
383	
384	Table~\ref{tab:cross_model} reports a single exploratory run with Llama-3.2-3B as a cross-generator (synthetic data generated by Llama, training on Qwen3-0.6B); this does not establish generality.
385	Results are mixed: MMLU improves while HellaSwag slightly degrades, consistent with the pattern observed in Qwen3-1.7B downstream evaluation (\S\ref{sec:robustness}).
386	Perplexity comparison omitted due to inconsistent evaluation configurations; checkpoints were not retained for re-evaluation.
387	
388	\begin{table}[h]
389	\centering
390	\small
391	\resizebox{\columnwidth}{!}{%
392	\begin{tabular}{@{}lccc@{}}
393	\toprule
394	\textbf{Metric} & \textbf{Uniform} & \textbf{Adaptive} & $\boldsymbol{\Delta}$ \\
395	\midrule
396	MMLU (5-shot) & 51.85\% $\pm$ .41 & 53.42\% $\pm$ .41 & $+$1.57pp \\
397	HellaSwag (10-shot, acc\_norm) & 73.08\% $\pm$ .44 & 72.49\% $\pm$ .45 & $-$0.60pp \\
398	\bottomrule
399	\end{tabular}}
400	\caption{Cross-model transfer: Llama-3.2-3B generator, Qwen3-0.6B trainer ($\rho{=}0.4$, single seed).
401	Mixed results reflect evaluation-set distribution sensitivity rather than consistent quality differences.}
402	\label{tab:cross_model}
403	\end{table}
404	
405	\section{Checkpoint Resume Artifact}
406	\label{app:resume_artifact}
407	
408	The checkpoint-resume artifact described here affected early $\tau{=}0.8$ experiments only.
409	All results in Tables~\ref{tab:main}--\ref{tab:epoch_match} use independent from-scratch training ($\tau{=}0.7$; Table~\ref{tab:main} Adaptive/Uniform: five seeds, others: three seeds).
410	
411	The adaptive model for seed\,42 in early $\tau{=}0.8$ runs was trained with a checkpoint-resumed run whose first ${\sim}$1{,}000 steps used different hyperparameters (learning rate warmup, gradient accumulation configuration) than seeds 123 and 456, which were trained from scratch.
412	The resume artifact inflates the in-distribution effect ($\Delta{=}{-}0.041$ resume vs.\ $\Delta{=}{-}0.005$ from-scratch at $\tau{=}0.8$) and reverses the out-of-distribution direction:
413	
414	\begin{center}
415	\small
416	\begin{tabular}{@{}lccc@{}}
417	\toprule
418	\textbf{Domain} & \textbf{Resume} & \textbf{From-scratch} & \textbf{Dir.} \\
419	\midrule
420	FineWeb (in-dist) & $-$0.041 & $-$0.005 & same \\
421	OpenWebText (OOD) & $+$0.058 & $-$0.005 & reversed \\
422	Wikipedia (OOD)   & $+$0.137 & $-$0.009 & reversed \\
423	\bottomrule
424	\end{tabular}\\[2pt]
425	{\scriptsize $\Delta$ relative to from-scratch uniform (Table~\ref{tab:tau}). Resume: seed\,42 original checkpoint. From-scratch: clean replication run.}
426	\end{center}
427	
428	The resume model showed apparent distribution matching (OOD degradation), which was the basis for the ``distribution matching'' finding in earlier analyses.
429	From-scratch retraining eliminates this pattern: all three evaluation domains show small, directionally consistent improvements, providing no evidence of distribution matching.
430	This underscores the importance of controlling for training artifacts when interpreting small effect sizes across evaluation domains.
431	
432	\section{Additional Contamination Rate}
433	\label{app:rho03}
434	
435	To probe the boundary between the degradation regime ($\rho{=}0.2$, $\Delta{=}{+}0.046$) and the improvement regime ($\rho{=}0.4$, $\Delta{=}{-}0.023$), we run adaptive $\bstar$ and uniform baselines at $\rho{=}0.3$ using the same experimental setup as the main experiments (Qwen3-0.6B, 132M FineWeb tokens, $\tau{=}0.7$, $\nmin{=}2$).
436	
437	\begin{table}[h]
438	\centering
439	\small
440	\begin{tabular}{@{}lcccc@{}}
441	\toprule
442	\textbf{Method} & \textbf{Seed} & \textbf{FineWeb} $\downarrow$ & \textbf{OWT} $\downarrow$ & \textbf{Wiki} $\downarrow$ \\
443	\midrule
444	Uniform          & 42  & 17.422 & 18.113 & 15.204 \\
445	Adaptive $\bstar$ & 42  & 17.422 & 18.123 & 15.172 \\
446	\midrule
447	Uniform          & 123 & 17.433 & 18.126 & 15.204 \\
448	Adaptive $\bstar$ & 123 & 17.435 & 18.148 & 15.165 \\
449	\midrule
450	Uniform          & 456 & 17.419 & -- & -- \\
451	Adaptive $\bstar$ & 456 & 17.424 & -- & -- \\
452	\midrule
453	$\Delta$ (3-seed mean) & --  & $+$0.002 & -- & -- \\
454	\bottomrule
455	\end{tabular}
456	\caption{Results at $\rho{=}0.3$ (Qwen3-0.6B, 3 seeds).
457	Holdout $\Delta{=}{+}0.002$ ($t(2){=}1.60$, $p{=}0.25$, non-significant); OOD available for seeds 42 and 123 only, mixed in direction.}
458	\label{tab:rho03}
459	\end{table}
460	
461	The holdout difference is effectively zero ($\Delta{=}{+}0.002$, $t(2){=}1.60$, $p{=}0.25$, non-significant), placing the transition boundary between the degradation regime ($\rho{=}0.2$, $\Delta{=}{+}0.046$) and the improvement regime ($\rho{=}0.4$, $\Delta{=}{-}0.023$) within $[0.3, 0.4]$ (Figure~\ref{fig:delta_vs_rho}).
462	
463	At $\rho{=}0.3$, 28\% of micro-batches have $\bstar{=}0$ (clean, no intervention), compared to ${\sim}$6\% at $\rho{=}0.4$; the low intervention frequency explains why the method neither helps nor harms.
464	The progression across contamination levels ($\rho{=}0.2$ harmful, $+$0.046; $\rho{=}0.3$ neutral, $+$0.002; $\rho{=}0.4$ beneficial, $-$0.023) shows a graceful transition rather than abrupt failure, consistent with the detector's signal-to-noise ratio gradually crossing the threshold needed for reliable $\aeff$ estimation.
465	
466	\section{Statistical Power Analysis}
467	\label{app:power}
468	
469	The adaptive-vs-uniform comparison at $\rho{=}0.4$ has Cohen's $d = \bar{\Delta}/\mathrm{SD}_{\Delta} = 0.023/0.006 = 3.83$ (5 seeds, paired).
470	A one-sided paired $t$-test at $\alpha{=}0.05$ with $d{=}3.83$ and $N{=}5$ achieves statistical power ${>}0.99$ (noncentrality $\lambda = d\sqrt{N} = 8.56$, $t_{0.05,4} = 2.13$), indicating that $N{=}5$ is more than adequate to detect an effect of this magnitude.
471	
472	The low cross-seed variance ($\sigma{=}0.006$) reflects the experimental design: seeds affect only parameter initialization, not data order (the dataloader is deterministic), so the primary stochastic axis is initialization noise at 0.6B scale.
473	The uniform baseline exhibits comparable variance ($\sigma{=}0.008$); the low dispersion is a property of the experimental setting rather than a method artifact.
474	
475	We apply Bonferroni--Holm correction for $k{=}9$ family-wise comparisons (six reweighting methods $\times$ one contamination level, plus three additional $\rho$ levels).
476	After correction, $p_{\mathrm{BH}}{=}0.011$ at $\rho{=}0.4$, reaching conventional significance at $\alpha{=}0.05$.
477	At $\rho{=}0.6$ (3 seeds), $p_{\mathrm{BH}}{=}0.064$; the family includes structurally heterogeneous tests (different methods, different $\rho$), which makes Bonferroni--Holm conservative.
478	The uncorrected $p$-values ($0.0012$ and $0.010$ respectively), directional consistency across all seeds, and the dose-response pattern across $\rho$ levels collectively support a real effect.
479	
480	\section{Supplementary Analyses Summary}
481	\label{app:summary}
482	
483	\begin{table}[h]
484	\centering
485	\small
486	\setlength{\tabcolsep}{3pt}
487	\resizebox{\columnwidth}{!}{%
488	\begin{tabular}{@{}lll@{}}
489	\toprule
490	\textbf{Analysis} & \textbf{Key result} & \textbf{App.} \\
491	\midrule
492	Downstream tasks & No gain (5 benchmarks, $|\Delta|\leq 0.01$) & \ref{app:downstream} \\
493	Cross-model (Llama) & Mixed (MMLU $+$1.6, HellaSwag $-$0.6) & \ref{app:cross_model} \\
494	$\tau$ sweep & $[0.5,0.8]$ all improve; $\tau{>}0.8$ degrades & \ref{app:tau_sweep} \\
495	$\rho{=}0.3$ boundary & $\Delta{=}{+}0.002$ (neutral, 3 seeds) & \ref{app:rho03} \\
496	Statistical power & Cohen's $d{=}3.83$, power ${>}0.99$ at $N{=}5$ & \ref{app:power} \\
497	\bottomrule
498	\end{tabular}}
499	\caption{Summary of supplementary analyses.}
500	\label{tab:appendix_summary}
501	\end{table}
502	
503	\section{Use of AI Assistants}
504	\label{app:ai-assistants}
505	
506	We used Claude (Anthropic) as an AI coding and writing assistant
507	throughout this work. Specifically:
508	\begin{itemize}
509	    \item \textbf{Code:} drafting experiment scripts, data-processing
510	    pipelines, and analysis utilities; debugging and refactoring.
511	    \item \textbf{Writing:} drafting and revising paper sections,
512	    polishing prose, and reformatting \LaTeX{}.
513	    \item \textbf{Literature:} summarizing related papers to inform
514	    the related-work section.
515	\end{itemize}
516	
517	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "9cce039c-2b82-4968-ba37-89c3ce0bcdf1",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/appendix.tex",
      "content": "\\section{Proofs}\n\\label{app:proofs}\n\n\\begin{proposition}[$\\alpha_{\\mathrm{eff}}$ monotonicity]\n\\label{prop:monotone}\n$\\alpha_{\\mathrm{eff}}(b)$ is non-decreasing in $b$, and strictly increasing whenever the batch contains at least two samples with distinct $q$-values.\n\\end{proposition}\n\n\\begin{proof}[Proof of Proposition~\\ref{prop:monotone}]\nLet $w_i(b) = (1 - q_i)^b$, $W(b) = \\sum_{j=1}^B w_j(b)$, and $\\pi_i(b) = w_i(b) / W(b)$.\nThen\n\\begin{equation*}\n  \\alpha_{\\mathrm{eff}}(b) = \\sum_{i=1}^{B} \\pi_i(b)\\, (1 - q_i).\n\\end{equation*}\nTaking the derivative with respect to $b$:\n\\begin{align*}\n  \\frac{d\\pi_i}{db}\n  &= \\pi_i \\!\\left(\\frac{d \\ln w_i}{db} - \\frac{d \\ln W}{db}\\right) \\\\\n  &= \\pi_i \\!\\left(\\ln(1{-}q_i) - \\textstyle\\sum_j \\pi_j \\ln(1{-}q_j)\\right).\n\\end{align*}\nSubstituting,\n\\begin{align*}\n  \\frac{d\\alpha_{\\mathrm{eff}}}{db}\n  &= \\sum_i (1{-}q_i)\\, \\pi_i \\!\\left(\\ln(1{-}q_i) - \\mathbb{E}_{\\pi}[\\ln(1{-}q)]\\right) \\\\\n  &= \\mathrm{Cov}_{\\pi}\\!\\bigl(1{-}q_i,\\, \\ln(1{-}q_i)\\bigr).\n\\end{align*}\nSince $(1{-}q_i)$ and $\\ln(1{-}q_i)$ are both increasing functions of $(1{-}q_i)$, they are positively associated, so the covariance is non-negative.\n\\end{proof}\n\n\\begin{proposition}[ESS monotonicity]\n\\label{prop:ess_mono}\n$\\mathrm{ESS}(b)$ is non-increasing in $b$, and strictly decreasing whenever the batch contains at least two samples with distinct $q$-values.\n\\end{proposition}\n\n\\begin{proof}\nWrite $\\mathrm{ESS}(b) = 1 / \\sum_i \\pi_i(b)^2$, where $\\pi_i(b) = w_i(b) / W(b)$.\nThe denominator $\\sum_i \\pi_i^2$ is the Herfindahl index $H$.\nDifferentiating $H$ with respect to $b$:\n\\begin{equation*}\n  \\frac{dH}{db} = 2 \\sum_i \\pi_i^2 \\bigl(\\ln(1{-}q_i) - \\mathbb{E}_{\\pi}[\\ln(1{-}q)]\\bigr).\n\\end{equation*}\nSince $\\pi_i \\propto (1{-}q_i)^b$, larger $\\pi_i$ implies larger $\\ln(1{-}q_i)$; the $\\pi^2$-weighted sum assigns greater mass to terms where $\\ln(1{-}q_i) > \\mathbb{E}_\\pi[\\ln(1{-}q)]$, so $dH/db \\geq 0$, with strict inequality when at least two $q$-values differ.\nThus $H$ is non-decreasing and $\\mathrm{ESS} = 1/H$ is non-increasing.\nThis is a standard property of exponential tilting~\\citep{kish1965survey,owen2013mc}.\n\\end{proof}\n\n\\section{Algorithm Details}\n\\label{app:algorithm}\n\n\\begin{algorithm}[h]\n\\caption{Per-batch adaptive $b^{*}$ selection}\n\\label{alg:bstar}\n\\begin{algorithmic}[1]\n\\REQUIRE Batch scores $\\{q_i\\}_{i=1}^{B}$, threshold~$\\tau$, ESS floor~$n_{\\min}$, bound~$b_{\\max}$, tol.~$\\varepsilon$\n\\ENSURE Optimal sharpening exponent $b^{*}$\n\\IF{$\\alpha_{\\mathrm{eff}}(0) \\geq \\tau$}\n  \\STATE \\textbf{return} $0$ \\COMMENT{clean batch}\n\\ENDIF\n\\STATE $b_\\tau \\gets \\textsc{Bisect}(\\alpha_{\\mathrm{eff}}(\\cdot){=}\\tau,\\; [0, b_{\\max}],\\; \\varepsilon)$\n\\IF{$\\mathrm{ESS}(b_\\tau) \\geq n_{\\min}$}\n  \\STATE \\textbf{return} $b_\\tau$ \\COMMENT{$\\alpha_{\\mathrm{eff}}$-binding}\n\\ELSE\n  \\STATE $b_{\\mathrm{ESS}} \\gets \\textsc{Bisect}(\\mathrm{ESS}(\\cdot){=}n_{\\min},\\; [0, b_{\\max}],\\; \\varepsilon)$\n  \\STATE \\textbf{return} $b_{\\mathrm{ESS}}$ \\COMMENT{ESS-binding}\n\\ENDIF\n\\end{algorithmic}\n\\end{algorithm}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{bstar_trajectory_adaptive_fix}\n\\caption{Adaptive $\\bstar$ trajectory over 6{,}103 training steps (seed\\,42, $\\rho{=}0.4$).\nThe exponent alternates between clean ($\\bstar{=}0$), $\\aeff$-binding, and ESS-binding regimes with no systematic drift, reflecting per-batch adaptation to local $q$-score composition.}\n\\label{fig:bstar_traj}\n\\end{figure}\nWe compute $\\bstar$ at the micro-batch level ($B{=}4$) rather than the effective batch ($B{=}16$ after gradient accumulation) because $q$-score statistics exhibit sufficient variance within micro-batches: Spearman $r{=}0.699$ with the true real fraction, and at $B{=}16$ the adaptive advantage amplifies $3.0{\\times}$ ($\\Delta{=}{-}0.068{\\pm}0.005$; \\S\\ref{sec:sensitivity}).\n\n\\section{Grid Search Details}\n\\label{app:grid}\n\nTable~\\ref{tab:grid_full} reports held-out PPL for all grid-$b$ values at $\\rho = 0.4$ (seed\\,42).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}cc@{}}\n\\toprule\n$b$ & PPL $\\downarrow$ \\\\\n\\midrule\n0.1 & 17.657 \\\\\n0.2 & 17.640 \\\\\n0.3 & \\textbf{17.640} \\\\\n0.5 & 17.651 \\\\\n1.0 & 17.692 \\\\\n1.5 & 17.718 \\\\\n2.0 & 17.741 \\\\\n3.0 & 17.774 \\\\\n5.0 & 17.818 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Full grid search results ($\\rho{=}0.4$, seed\\,42).\n$b \\in [0.1, 0.5]$ forms a broad plateau (three-seed mean for $b{=}0.1$: $17.655 \\pm 0.009$); $b{=}0.3$ is the post-hoc best.}\n\\label{tab:grid_full}\n\\end{table}\n\n\\section{Quality Threshold Sweep}\n\\label{app:tau_sweep}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}ccccccc@{}}\n\\toprule\n$\\tau$ & Holdout $\\downarrow$ & $\\Delta_{\\text{H}}$ & OWT $\\downarrow$ & $\\Delta_{\\text{O}}$ & Wiki $\\downarrow$ & $\\Delta_{\\text{W}}$ \\\\\n\\midrule\n0.50 & 17.688 & $-$0.006 & -- & -- & -- & -- \\\\\n0.60 & 17.681 & $-$0.013 & -- & -- & -- & -- \\\\\n0.70$^\\star$ & \\textbf{17.674{\\tiny$\\pm$.006}} & $\\boldsymbol{-}$\\textbf{0.020} & \\textbf{18.347{\\tiny$\\pm$.003}} & $\\boldsymbol{-}$\\textbf{0.028} & \\textbf{15.330{\\tiny$\\pm$.015}} & $\\boldsymbol{-}$\\textbf{0.029} \\\\\n0.80$^\\star$ & 17.683{\\tiny$\\pm$.006} & $-$0.011 & 18.370{\\tiny$\\pm$.005} & $-$0.005 & 15.350 & $-$0.009 \\\\\n0.90 & 17.712 & $+$0.018 & -- & -- & -- & -- \\\\\n0.95 & 17.723 & $+$0.029 & -- & -- & -- & -- \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Quality threshold sweep ($\\nmin{=}2$, $\\rho{=}0.4$).\n$\\Delta$ relative to 3-seed uniform baseline (Holdout 17.694, OWT 18.375, Wiki 15.359).\n$^\\star$\\,$\\tau{=}0.7$: 5-seed mean (SD from 5 seeds); $\\tau{=}0.8$: 3 from-scratch seeds (Appendix~\\ref{app:resume_artifact}). The 5-seed comparison in Table~\\ref{tab:main} yields $\\Delta{=}{-}0.023$.\nOther values from single-seed exploratory sweep (seed\\,42, holdout only).\n$\\tau{=}0.7$ achieves the lowest holdout and largest OOD gains ($|\\Delta| \\geq 0.028$); $\\tau{=}0.8$'s OOD effect is smaller ($|\\Delta| \\leq 0.009$).}\n\\label{tab:tau}\n\\end{table}\n\n\\section{Batch-Adaptive $\\tau$}\n\\label{app:batch_adaptive}\n\nWe tested a per-batch adaptive variant that clamps $\\tau$ between 0.5 and the fixed threshold based on local $\\aeff(0)$, allowing the quality floor to relax in batches with low estimated real fraction.\nAt both contamination levels ($\\rho \\in \\{0.4, 0.6\\}$), the adaptive variant did not outperform the fixed threshold (single-seed exploratory at each level), suggesting the quality constraint does not require adaptation to local contamination density.\nThis supports the ``two hyperparameters with good defaults'' characterization: neither $\\tau$ nor $\\nmin$ benefits from per-batch tuning.\n\n\\section{\\texorpdfstring{$\\tau$--$\\rho$}{tau-rho} Rank Preservation}\n\\label{app:tau_rho}\n\nFigure~\\ref{fig:tau_rho_rank} shows the $\\tau$--PPL relationship at two contamination levels.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{tau_rho_rank_preservation}\n\\caption{(a) Held-out PPL as a function of quality threshold $\\tau$ at $\\rho \\in \\{0.4, 0.6\\}$.\n$\\tau{=}0.7$ and $\\tau{=}0.8$ yield comparable holdout PPL at $\\rho{=}0.4$; at $\\rho{=}0.6$, $\\tau{=}0.7$ is statistically better (paired $t{=}{-}4.70$, $p{<}0.05$, 3 seeds, $\\Delta{=}{-}0.005$). $\\tau{=}0.7$ also achieves lower OOD perplexity at both levels ($\\rho{=}0.6$: $\\Delta_{\\text{OWT}}{=}{-}0.014$, $\\Delta_{\\text{Wiki}}{=}{-}0.013$, 2 seeds).\n(b) Normalized PPL gap relative to uniform at shared $\\tau$ values.}\n\\label{fig:tau_rho_rank}\n\\end{figure}\n\n\\section{Hybrid and Threshold Comparison}\n\\label{app:hybrid}\n\nTable~\\ref{tab:hybrid} compares method families across contamination levels.\nTable~\\ref{tab:dr_threshold} shows D\\&R sensitivity to the detection threshold at both full training length and epoch-matched settings.\nRaw PPL traces a U-shaped curve with a minimum at $q{>}0.3$ (17.250, 3 seeds), but this curve conflates filtering quality with multi-epoch exposure: aggressive thresholds retain less data and repeat it more often.\nEpoch-matched comparisons (rightmost column of Table~\\ref{tab:dr_threshold}) remove the multi-epoch confound: the U-shape vanishes and PPL decreases monotonically, saturating near the adaptive $\\bstar$ level at $q{\\geq}0.5$.\nFigure~\\ref{fig:dr_dual_curve} visualizes the two curves.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\n\\textbf{Method} & $\\rho{=}0.4$ & $\\rho{=}0.6$ \\\\\n\\midrule\nUniform & 17.694 & 17.766 \\\\\nAdaptive $\\bstar$ & 17.689 & 17.740 \\\\\nHybrid ($q{>}0.95$ + adaptive) & 17.514 & 17.530$^*$ \\\\\nDetect \\& Remove ($q{>}0.5$) & 17.285 & -- \\\\\nDetect \\& Remove ($q{>}0.3$) & 17.250 & -- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Method comparison across contamination levels (seed\\,42, $\\tau{=}0.8$).\n$^*$Hybrid at $\\rho{=}0.6$ filters high-confidence synthetic ($q{>}0.95$), reducing effective $\\rho$ to ${\\approx}0.4$; PPL is not directly comparable to $\\rho{=}0.6$ baselines.}\n\\label{tab:hybrid}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{@{}ccccc@{}}\n\\toprule\n\\textbf{Thresh.} & \\textbf{Ret.\\ \\%} & \\textbf{Epochs} & \\textbf{Raw PPL} $\\downarrow$ & \\textbf{Ep.-matched} $\\downarrow$ \\\\\n\\midrule\n$q > 0.1$ & 15.0\\% & ${\\sim}$10.0 & 17.40 & 18.04 \\\\\n$q > 0.2$ & ${\\sim}$23\\% & ${\\sim}$5.0 & 17.27 & -- \\\\\n$q > 0.3$ & 31.5\\% & ${\\sim}$3.2 & \\textbf{17.250}$^\\dagger$ & 17.74 \\\\\n$q > 0.4$ & ${\\sim}$38\\% & ${\\sim}$2.8 & 17.26 & -- \\\\\n$q > 0.5$ & 41.4\\% & ${\\sim}$2.4 & 17.28 & 17.65 \\\\\n$q > 0.6$ & ${\\sim}$46\\% & ${\\sim}$1.7 & 17.30 & -- \\\\\n$q > 0.7$ & 49.8\\% & ${\\sim}$2.0 & 17.32 & 17.62 \\\\\n$q > 0.8$ & ${\\sim}$56\\% & ${\\sim}$1.3 & 17.34 & -- \\\\\n$q > 0.9$ & 61.6\\% & ${\\sim}$1.1 & 17.42 & 17.628 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{D\\&R threshold sensitivity ($\\rho{=}0.4$, seed\\,42 unless noted).\nRaw PPL traces a U-shaped curve (minimum at $q{>}0.3$); epoch-matched PPL (single content epoch) decreases monotonically and saturates near the adaptive $\\bstar$ level (${\\approx}$17.65) at $q{\\geq}0.5$; the U-shape is thus a multi-epoch artifact.\n$^\\dagger$\\,3-seed mean $17.250 \\pm 0.001$.}\n\\label{tab:dr_threshold}\n\\end{table}\n\nSee Figure~\\ref{fig:dr_dual_curve} (\\S\\ref{sec:main-results}) for the dual-curve visualization.\n\n\\section{Downstream Task Evaluation}\n\\label{app:downstream}\n\nTable~\\ref{tab:downstream} reports downstream benchmark accuracy for adaptive vs.\\ uniform training at $\\rho{=}0.4$ (seed\\,42, Qwen3-0.6B).\nAcross multiple seeds, downstream differences are mixed in direction and uniformly within standard error, indicating that adaptive reweighting has no meaningful downstream impact.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llccc@{}}\n\\toprule\n\\textbf{Benchmark} & \\textbf{Metric} & \\textbf{Adaptive} & \\textbf{Uniform} & $\\boldsymbol{\\Delta}$ \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{Seed 42 (checkpoint resume)}} \\\\\nARC-Challenge & acc\\_norm & 0.343 & 0.348 & $-$0.005 \\\\\nARC-Easy & acc & 0.650 & 0.657 & $-$0.007 \\\\\nHellaSwag & acc\\_norm & 0.479 & 0.484 & $-$0.005 \\\\\nPIQA & acc & 0.687 & 0.686 & $+$0.001 \\\\\nWinoGrande & acc & 0.578 & 0.586 & $-$0.008 \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{From-scratch 2-seed mean (seeds 123, 456)}} \\\\\n\\multicolumn{3}{@{}l}{Mean $\\Delta$ across 5 tasks} & & $+$0.001 \\\\\n\\multicolumn{3}{@{}l}{Direction} & \\multicolumn{2}{c}{mixed (seed 123: 3/5$-$; seed 456: 3/5$+$)} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Downstream benchmarks (Qwen3-0.6B, $\\rho{=}0.4$).\nSeed\\,42 used a checkpoint-resumed adaptive model; from-scratch seeds (123, 456) show mixed direction with mean $|\\Delta| \\leq 0.01$.\nAll differences within standard error ($\\pm 0.01$).\nModels use $\\tau{=}0.8$; $\\tau{=}0.7$ yields identical 3-seed means (0.5414).}\n\\label{tab:downstream}\n\\end{table}\n\n\\section{Higher Contamination Details}\n\\label{app:rho06}\n\nTable~\\ref{tab:rho06} reports results at $\\rho{=}0.6$.\nThe full five-method ablation preserves the hierarchy from $\\rho{=}0.4$ across all three seeds: Grid ${<}$ Adaptive ${<}$ Uniform ${\\approx}$ ESS-only ${<}$ Random.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n\\textbf{Method} & \\textbf{Seed 42} & \\textbf{Seed 123} & \\textbf{Seed 456} & \\textbf{Mean} \\\\\n\\midrule\nGrid ($b{=}0.3$)$^\\ddagger$ & \\textbf{17.634} & -- & -- & -- \\\\\nAdaptive $\\bstar$ & 17.735 & 17.727 & 17.732 & 17.731 $\\pm$ .004 \\\\\nUniform           & 17.766 & 17.754 & 17.770 & 17.763 $\\pm$ .008 \\\\\nESS-only          & 17.770 & 17.760 & 17.760 & 17.763 $\\pm$ .006 \\\\\nRandom $\\mathcal{U}(0,2)$ & 17.832 & 17.870 & 17.880 & 17.861 $\\pm$ .025 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Results at $\\rho{=}0.6$ (Qwen3-0.6B, $\\nmin{=}2$).\nAdaptive uses $\\tau{=}0.7$ (consistent with main results); other methods are $\\tau$-independent.\n$^\\ddagger$Post-hoc oracle; seed\\,42 only.\nAdaptive vs.\\ Uniform: $\\Delta{=}{-}0.032$, paired $t{=}{-}15.4$, $p{=}0.004$ (full precision; 3dp rounding yields $t{=}{-}9.95$, $p{=}0.010$).\nESS-only collapses onto Uniform (both $17.763$); Random ($17.861$) confirms detector signal is load-bearing.}\n\\label{tab:rho06}\n\\end{table}\n\nThe ESS-only/Uniform gap collapses from 0.043 at $\\rho{=}0.4$ to 0.000 at $\\rho{=}0.6$ (three-seed means: both $17.763$); ESS binding rises to ${\\sim}$49\\% of batches (from ${\\sim}$43\\% at $\\rho{=}0.4$), and the constraints become nearly balanced rather than $\\aeff$-dominant.\nThe adaptive method maintains its advantage ($\\Delta{=}{-}0.032$, consistent across seeds) through the $\\aeff$ quality constraint, which operates independently of the ESS ceiling.\nRandom reweighting ($17.861 \\pm 0.025$) is substantially worse than Uniform, with the highest cross-seed variance; uninformed weights add noise without corrective signal.\nThe Adaptive-vs-Grid gap is 0.054 at $\\rho{=}0.4$ (mean-to-mean, consistent with Table~\\ref{tab:aux}) and 0.097 at $\\rho{=}0.6$ (adaptive 3-seed mean vs.\\ grid seed\\,42; the $\\rho{=}0.6$ grid result is preliminary and may not generalize across seeds).\n\n\\section{\\texorpdfstring{$\\alpha_{\\mathrm{eff}}$}{alpha-eff} Proxy Validation}\n\\label{app:alpha_validation}\n\nTable~\\ref{tab:alpha_corr} reports the correlation between $\\aeff(0)$ (the detector-based proxy at $b{=}0$) and the true batch-level real fraction $\\alpha_{\\mathrm{true}}$, computed over all training batches at $\\rho{=}0.4$ (seed\\,42).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}ccccc@{}}\n\\toprule\n$B$ & Pearson $r$ & Spearman $r$ & MAE$\\downarrow$ & Bias \\\\\n\\midrule\n4  & 0.706 & 0.699 & 0.114 & $-$0.029 \\\\\n8  & 0.697 & 0.683 & 0.097 & $-$0.027 \\\\\n16 & 0.707 & 0.691 & 0.075 & $-$0.031 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Correlation between $\\aeff(0)$ and true batch-level real fraction across batch sizes ($\\rho{=}0.4$, seed\\,42).\nValues use a binarized proxy $\\hat{r}_i = \\mathbf{1}[q_i \\leq 0.5]$ for discrete comparison; the continuous formulation used during training (\\S\\ref{sec:method}) achieves $r \\approx 0.77$--$0.79$ depending on batch size.\nThe consistent negative bias (${\\approx}{-}0.03$) indicates that $\\aeff$ slightly underestimates the true real fraction, biasing the method toward conservative intervention.}\n\\label{tab:alpha_corr}\n\\end{table}\n\nMean absolute error (MAE) decreases with batch size (0.114 $\\to$ 0.075) as expected from averaging, but the rank-order information that drives $\\bstar$ selection is already well-captured at $B{=}4$.\n\n\\paragraph{Cross-seed stability.}\nTable~\\ref{tab:alpha_corr_perseed} reports the correlation between $\\aeff$ and the batch mean $q$-score ($\\bar{q}$, computed from known labels) across all three seeds.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}cccc@{}}\n\\toprule\n\\textbf{Seed} & Pearson $r(\\aeff, \\bar{q})$ & Spearman $\\rho_s$ & $\\bstar{=}0$ (\\%) \\\\\n\\midrule\n42  & 0.8019 & 0.8761 & 5.8 \\\\\n123 & 0.7994 & 0.8692 & 5.7 \\\\\n456 & 0.8006 & 0.8749 & 5.9 \\\\\n\\midrule\n\\textbf{Spread} & 0.0025 & 0.0069 & 0.2 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Per-seed $\\aeff$--$\\bar{q}$ correlation ($\\rho{=}0.4$, $B{=}4$).\nCross-seed spread is $<$0.003 for Pearson $r$ and $<$0.007 for Spearman $\\rho_s$, indicating stable proxy fidelity across random seeds.\n$r(\\aeff, \\bar{q}) = 0.80$ measures the proxy's fidelity to batch composition; the ground-truth correlation $r(\\aeff, \\text{true real fraction}) \\approx 0.79$ (\\S\\ref{sec:discussion}) is slightly lower due to detector noise.\nThe per-seed table demonstrates cross-seed stability rather than superseding the ground-truth estimate.}\n\\label{tab:alpha_corr_perseed}\n\\end{table}\n\n\\section{Detector Comparison}\n\\label{app:detector}\n\nSee Figure~\\ref{fig:overview}b (\\S\\ref{sec:robustness}) for the detector requirements visualization.\n\nTable~\\ref{tab:detector} compares three detector families for adaptive reweighting.\nThe discriminative TF-IDF+LR detector (ECE\\,=\\,0.048) produces the only improvement over uniform.\nThe TF-IDF vs.\\ GPT-2 contrast (comparable AUC: 0.94 vs.\\ 0.91, but $2.7{\\times}$ ECE gap: 0.048 vs.\\ 0.131) isolates calibration as an empirically observed requirement; however, N-gram's better ECE (0.069) does not compensate for its low AUC (0.73); both sufficient discrimination and good calibration are jointly necessary in our setting.\nTF-IDF+LR's $q$-scores have reliable probabilistic semantics, so the $\\aeff$ proxy accurately tracks batch quality.\nGenerative detectors assign high $q$-scores to fluent, predictable human text (false positives concentrated among high-quality samples), systematically inflating $\\aeff$ for clean batches and deflating it for contaminated ones, which inverts the minimum-intervention logic.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llccccc@{}}\n\\toprule\n\\textbf{Detector} & \\textbf{Type} & \\textbf{AUC} & \\textbf{ECE} & \\textbf{Mean PPL} & $\\boldsymbol{\\Delta}$ \\\\\n\\midrule\nTF-IDF+LR & Discriminative & 0.94 & 0.048 & 17.650{\\tiny$\\pm$.010} & $-$0.044 \\\\\nGPT-2 PPL & Generative & 0.91 & 0.131 & 17.792{\\tiny$\\pm$.005} & $+$0.098 \\\\\nN-gram PPL & Generative & 0.73 & 0.069 & 17.823{\\tiny$\\pm$.003} & $+$0.129 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Detector comparison for adaptive reweighting ($\\rho{=}0.4$, $\\tau{=}0.8$, 3 seeds).\nUniform baseline PPL\\,=\\,17.694.\n$\\Delta$ = Adaptive $-$ Uniform (negative is better).\nTF-IDF+LR calibrated via temperature scaling.\nThe $\\tau$ confound is conservative: TF-IDF+LR at $\\tau{=}0.7$ achieves 17.674 (Table~\\ref{tab:main}).}\n\\label{tab:detector}\n\\end{table}\n\n\\section{Detector and Synthetic Data Details}\n\\label{app:detector_details}\n\n\\paragraph{TF-IDF+LR detector.}\nTF-IDF features (unigrams + bigrams, max 50{,}000 features, sublinear TF) fed to Logistic Regression (C\\,=\\,1.0, L2 penalty, solver\\,=\\,lbfgs, max\\_iter\\,=\\,100).\nTrained on a held-out labeled split (10K documents per class).\nPost-hoc temperature scaling applied when uncalibrated ECE exceeds 0.05: a scalar $T$ is searched via \\texttt{scipy.optimize.minimize\\_scalar} over $[0.1, 10.0]$ on a 20\\% stratified validation split, yielding $T{=}0.204$ (ECE reduced from 0.12 to 0.05).\nThe detector is selected automatically from six configurations as the first satisfying AUC $\\in [0.85, 0.98]$ and mid-range score ratio $\\geq 5\\%$.\n\n\\paragraph{Synthetic data generation.}\nContinuations generated with Qwen3-0.6B (self-generation) using nucleus sampling ($p{=}0.95$, $T{=}0.8$), producing up to 384 tokens per continuation from a 128-token prefix prompt (512 total), targeting ${\\sim}$100M synthetic tokens.\nSource prompts are the first 128 tokens of randomly sampled FineWeb documents, used as prefix continuations.\nInjected at token-level ratio $\\rho$ via uniform random mixing across the training corpus.\n\n\\section{Low Contamination Analysis}\n\\label{app:rho02}\n\nAt $\\rho{=}0.2$, the adaptive method degrades by $+$0.046 PPL relative to uniform (0.26\\% relative, seed\\,42).\nThe detector's mean $q$-score at this contamination level is 0.393 (vs.\\ 0.487 at $\\rho{=}0.4$), indicating that many clean samples receive moderate $q$-scores, blurring the provenance signal.\nThe regime decomposition reveals 13.7\\% clean batches ($\\bstar{=}0$), 60.1\\% $\\aeff$-binding, and 26.3\\% ESS-binding, with mean $\\bstar{=}1.735$ in reweighted batches.\nThe high $\\aeff$-binding rate (60.1\\% vs.\\ ${\\sim}$50\\% at $\\rho{=}0.4$) means the method actively intervenes rather than defaulting to $\\bstar{=}0$, but the unreliable signal causes it to suppress useful training data.\nThis is consistent with the generative detector failures: when $q$-scores do not reliably separate provenance, the minimum intervention framework amplifies the error rather than correcting it.\nThe effective range of the method is $\\rho \\geq 0.4$ with $\\tau \\in [0.7, 0.8]$ (\\S\\ref{sec:sensitivity}); lower $\\tau$ values may extend the range but have not been tested at $\\rho{=}0.2$.\n\n\\section{Cross-Model Transfer}\n\\label{app:cross_model}\n\nTable~\\ref{tab:cross_model} reports a single exploratory run with Llama-3.2-3B as a cross-generator (synthetic data generated by Llama, training on Qwen3-0.6B); this does not establish generality.\nResults are mixed: MMLU improves while HellaSwag slightly degrades, consistent with the pattern observed in Qwen3-1.7B downstream evaluation (\\S\\ref{sec:robustness}).\nPerplexity comparison omitted due to inconsistent evaluation configurations; checkpoints were not retained for re-evaluation.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n\\textbf{Metric} & \\textbf{Uniform} & \\textbf{Adaptive} & $\\boldsymbol{\\Delta}$ \\\\\n\\midrule\nMMLU (5-shot) & 51.85\\% $\\pm$ .41 & 53.42\\% $\\pm$ .41 & $+$1.57pp \\\\\nHellaSwag (10-shot, acc\\_norm) & 73.08\\% $\\pm$ .44 & 72.49\\% $\\pm$ .45 & $-$0.60pp \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Cross-model transfer: Llama-3.2-3B generator, Qwen3-0.6B trainer ($\\rho{=}0.4$, single seed).\nMixed results reflect evaluation-set distribution sensitivity rather than consistent quality differences.}\n\\label{tab:cross_model}\n\\end{table}\n\n\\section{Checkpoint Resume Artifact}\n\\label{app:resume_artifact}\n\nThe checkpoint-resume artifact described here affected early $\\tau{=}0.8$ experiments only.\nAll results in Tables~\\ref{tab:main}--\\ref{tab:epoch_match} use independent from-scratch training ($\\tau{=}0.7$; Table~\\ref{tab:main} Adaptive/Uniform: five seeds, others: three seeds).\n\nThe adaptive model for seed\\,42 in early $\\tau{=}0.8$ runs was trained with a checkpoint-resumed run whose first ${\\sim}$1{,}000 steps used different hyperparameters (learning rate warmup, gradient accumulation configuration) than seeds 123 and 456, which were trained from scratch.\nThe resume artifact inflates the in-distribution effect ($\\Delta{=}{-}0.041$ resume vs.\\ $\\Delta{=}{-}0.005$ from-scratch at $\\tau{=}0.8$) and reverses the out-of-distribution direction:\n\n\\begin{center}\n\\small\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n\\textbf{Domain} & \\textbf{Resume} & \\textbf{From-scratch} & \\textbf{Dir.} \\\\\n\\midrule\nFineWeb (in-dist) & $-$0.041 & $-$0.005 & same \\\\\nOpenWebText (OOD) & $+$0.058 & $-$0.005 & reversed \\\\\nWikipedia (OOD)   & $+$0.137 & $-$0.009 & reversed \\\\\n\\bottomrule\n\\end{tabular}\\\\[2pt]\n{\\scriptsize $\\Delta$ relative to from-scratch uniform (Table~\\ref{tab:tau}). Resume: seed\\,42 original checkpoint. From-scratch: clean replication run.}\n\\end{center}\n\nThe resume model showed apparent distribution matching (OOD degradation), which was the basis for the ``distribution matching'' finding in earlier analyses.\nFrom-scratch retraining eliminates this pattern: all three evaluation domains show small, directionally consistent improvements, providing no evidence of distribution matching.\nThis underscores the importance of controlling for training artifacts when interpreting small effect sizes across evaluation domains.\n\n\\section{Additional Contamination Rate}\n\\label{app:rho03}\n\nTo probe the boundary between the degradation regime ($\\rho{=}0.2$, $\\Delta{=}{+}0.046$) and the improvement regime ($\\rho{=}0.4$, $\\Delta{=}{-}0.023$), we run adaptive $\\bstar$ and uniform baselines at $\\rho{=}0.3$ using the same experimental setup as the main experiments (Qwen3-0.6B, 132M FineWeb tokens, $\\tau{=}0.7$, $\\nmin{=}2$).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n\\textbf{Method} & \\textbf{Seed} & \\textbf{FineWeb} $\\downarrow$ & \\textbf{OWT} $\\downarrow$ & \\textbf{Wiki} $\\downarrow$ \\\\\n\\midrule\nUniform          & 42  & 17.422 & 18.113 & 15.204 \\\\\nAdaptive $\\bstar$ & 42  & 17.422 & 18.123 & 15.172 \\\\\n\\midrule\nUniform          & 123 & 17.433 & 18.126 & 15.204 \\\\\nAdaptive $\\bstar$ & 123 & 17.435 & 18.148 & 15.165 \\\\\n\\midrule\nUniform          & 456 & 17.419 & -- & -- \\\\\nAdaptive $\\bstar$ & 456 & 17.424 & -- & -- \\\\\n\\midrule\n$\\Delta$ (3-seed mean) & --  & $+$0.002 & -- & -- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Results at $\\rho{=}0.3$ (Qwen3-0.6B, 3 seeds).\nHoldout $\\Delta{=}{+}0.002$ ($t(2){=}1.60$, $p{=}0.25$, non-significant); OOD available for seeds 42 and 123 only, mixed in direction.}\n\\label{tab:rho03}\n\\end{table}\n\nThe holdout difference is effectively zero ($\\Delta{=}{+}0.002$, $t(2){=}1.60$, $p{=}0.25$, non-significant), placing the transition boundary between the degradation regime ($\\rho{=}0.2$, $\\Delta{=}{+}0.046$) and the improvement regime ($\\rho{=}0.4$, $\\Delta{=}{-}0.023$) within $[0.3, 0.4]$ (Figure~\\ref{fig:delta_vs_rho}).\n\nAt $\\rho{=}0.3$, 28\\% of micro-batches have $\\bstar{=}0$ (clean, no intervention), compared to ${\\sim}$6\\% at $\\rho{=}0.4$; the low intervention frequency explains why the method neither helps nor harms.\nThe progression across contamination levels ($\\rho{=}0.2$ harmful, $+$0.046; $\\rho{=}0.3$ neutral, $+$0.002; $\\rho{=}0.4$ beneficial, $-$0.023) shows a graceful transition rather than abrupt failure, consistent with the detector's signal-to-noise ratio gradually crossing the threshold needed for reliable $\\aeff$ estimation.\n\n\\section{Statistical Power Analysis}\n\\label{app:power}\n\nThe adaptive-vs-uniform comparison at $\\rho{=}0.4$ has Cohen's $d = \\bar{\\Delta}/\\mathrm{SD}_{\\Delta} = 0.023/0.006 = 3.83$ (5 seeds, paired).\nA one-sided paired $t$-test at $\\alpha{=}0.05$ with $d{=}3.83$ and $N{=}5$ achieves statistical power ${>}0.99$ (noncentrality $\\lambda = d\\sqrt{N} = 8.56$, $t_{0.05,4} = 2.13$), indicating that $N{=}5$ is more than adequate to detect an effect of this magnitude.\n\nThe low cross-seed variance ($\\sigma{=}0.006$) reflects the experimental design: seeds affect only parameter initialization, not data order (the dataloader is deterministic), so the primary stochastic axis is initialization noise at 0.6B scale.\nThe uniform baseline exhibits comparable variance ($\\sigma{=}0.008$); the low dispersion is a property of the experimental setting rather than a method artifact.\n\nWe apply Bonferroni--Holm correction for $k{=}9$ family-wise comparisons (six reweighting methods $\\times$ one contamination level, plus three additional $\\rho$ levels).\nAfter correction, $p_{\\mathrm{BH}}{=}0.011$ at $\\rho{=}0.4$, reaching conventional significance at $\\alpha{=}0.05$.\nAt $\\rho{=}0.6$ (3 seeds), $p_{\\mathrm{BH}}{=}0.064$; the family includes structurally heterogeneous tests (different methods, different $\\rho$), which makes Bonferroni--Holm conservative.\nThe uncorrected $p$-values ($0.0012$ and $0.010$ respectively), directional consistency across all seeds, and the dose-response pattern across $\\rho$ levels collectively support a real effect.\n\n\\section{Supplementary Analyses Summary}\n\\label{app:summary}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lll@{}}\n\\toprule\n\\textbf{Analysis} & \\textbf{Key result} & \\textbf{App.} \\\\\n\\midrule\nDownstream tasks & No gain (5 benchmarks, $|\\Delta|\\leq 0.01$) & \\ref{app:downstream} \\\\\nCross-model (Llama) & Mixed (MMLU $+$1.6, HellaSwag $-$0.6) & \\ref{app:cross_model} \\\\\n$\\tau$ sweep & $[0.5,0.8]$ all improve; $\\tau{>}0.8$ degrades & \\ref{app:tau_sweep} \\\\\n$\\rho{=}0.3$ boundary & $\\Delta{=}{+}0.002$ (neutral, 3 seeds) & \\ref{app:rho03} \\\\\nStatistical power & Cohen's $d{=}3.83$, power ${>}0.99$ at $N{=}5$ & \\ref{app:power} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Summary of supplementary analyses.}\n\\label{tab:appendix_summary}\n\\end{table}\n\n\\section{Use of AI Assistants}\n\\label{app:ai-assistants}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant\nthroughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing\n    pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections,\n    polishing prose, and reformatting \\LaTeX{}.\n    \\item \\textbf{Literature:} summarizing related papers to inform\n    the related-work section.\n\\end{itemize}\n\n",
      "numLines": 517,
      "startLine": 1,
      "totalLines": 517
    }
  }
}
```

</details>

---


### Tool call

_source line 8_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01GZuqfY9AHDQ46GbHY4kaci`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file",
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
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "d293f70c-6937-4dda-ac18-d482a8cddba9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Axc8ZKTov5FbVFTMh4x2Me",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12807,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12807
      },
      "output_tokens": 32,
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

_source line 9 · 2026-05-25T20:02:37.237Z_

<details><summary>↩ Tool result · `toolu_01GZuqfY9AHDQ46GbHY4kaci`</summary>

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
  "tool_name": "mcp__agent-ml-research__read_project_file"
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
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "606168b5-6648-479c-8083-e30f64fda1bd",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_project_file"
    ],
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file",
    "total_deferred_tools": 25
  }
}
```

</details>

---


### Assistant

_source line 10_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the registry to get experimental results for cross-referencing, and also read the main text sections (results.tex, experiments.tex) for cross-validation.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "e7b22cdf-633a-43d9-88fd-7b77121420bf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012YfCsaLQEnDPgXMUVf16JC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13749,
      "cache_read_input_tokens": 24254,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13749
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

_source line 11_

读取 registry 和正文相关章节进行交叉验证。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "c3f2651d-daaf-42c9-8cc9-fd5b7773ebe7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012YfCsaLQEnDPgXMUVf16JC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13749,
      "cache_read_input_tokens": 24254,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13749
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

_source line 12_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01Eu5p3LCrAKPcneme5KRGJ1`</summary>

```json
{
  "project": "provenance_weight_training",
  "limit": 0,
  "fields": [
    "*"
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
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "cc1178e4-98b5-4dd8-8eaf-6dd4e7845170",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012YfCsaLQEnDPgXMUVf16JC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13749,
      "cache_read_input_tokens": 24254,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13749
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

_source line 13 · 2026-05-25T20:02:44.083Z_

<details><summary>↩ Tool result · `toolu_01Eu5p3LCrAKPcneme5KRGJ1`</summary>

```text
Error: result (485,271 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9/tool-results/mcp-agent-ml-research-read_registry-1779739364067.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9/tool-results/mcp-agent-ml-research-read_registry-1779739364067.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9/tool-results/mcp-agent-ml-research-read_registry-1779739364067.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "33a8c7d7-82a3-4921-bbfe-870ea79a24e4",
  "tool_use_result": {
    "content": "Error: result (485,271 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9/tool-results/mcp-agent-ml-research-read_registry-1779739364067.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9/tool-results/mcp-agent-ml-research-read_registry-1779739364067.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9/tool-results/mcp-agent-ml-research-read_registry-1779739364067.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"detect_remove_q07_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-25T04:35:47.832Z\", \"updated_at\": \"2026-05-25T09:01:28.560Z\", \"hypothesis\": \"D&R q>0.7 threshold seed=456 replicate. Retains ~50% data (184,908/370k). Cross-seed for error bar with seed42 (r3) and seed123.\", \"parent\": \"detect_remove_q07_seed42_r3\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q07.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q07_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --bf16 --save_total_limit 2 --logging_steps 10 --save_steps 500\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data_filtered_q07.jsonl\", \"data_count\": 184908, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q07_seed456/final\", \"log_path\": \"/tmp/eval_q07_seed456.log\", \"metrics\": {\"holdout_ppl\": 17.32, \"owt_ppl\": 18.03, \"wiki_ppl\": 15.11}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-25T09:01:28.560Z\"}, \"detect_remove_q07_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-25T04:35:46.625Z\", \"updated_at\": \"2026-05-25T09:01:26.030Z\", \"hypothesis\": \"D&R q>0.7 threshold seed=123 replicate. Retains ~50% data (184,908/370k). Cross-seed for error bar with seed42 (r3) and seed456.\", \"parent\": \"detect_remove_q07_seed42_r3\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q07.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q07_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --bf16 --save_total_limit 2 --logging_steps 10 --save_steps 500\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data_filtered_q07.jsonl\", \"data_count\": 184908, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q07_seed123/final\", \"log_path\": \"/tmp/eval_q07_seed123.log\", \"metrics\": {\"holdout_ppl\": 17.32, \"owt_ppl\": 18.04, \"wiki_ppl\": 15.1}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-25T09:01:26.030Z\"}, \"detect_remove_q07_seed42_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-25T04:32:32.606Z\", \"updated_at\": \"2026-05-25T09:01:23.531Z\", \"hypothesis\": \"D&R q>0.7 threshold fresh rerun (r3). Retains ~50% data (184,908/370k). Prior r2 corrupted by optimizer state loss during resume. Fresh training from step 0 with full optimizer state preservation.\", \"parent\": \"detect_remove_q07_seed42_r2\", \"spec\": {\"command\": \"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q07.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q07_seed42_r3 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --bf16 --save_total_limit 2 --logging_steps 10 --save_steps 500\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data_filtered_q07.jsonl\", \"data_count\": 184908, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"pid\": 12122, \"gpu\": \"cuda:1\", \"log_path\": \"/root/provenance_weight_training/logs/detect_remove_q07_seed42_r3_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q07_seed42_r3\", \"checkpoint_source\": \"N/A (fresh training, parent is lineage only)\", \"eval_data\": \"N/A (training experiment)\"}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q07_seed42_r3/final\", \"log_path\": \"/tmp/eval_q07_seed42_r3.log\", \"metrics\": {\"holdout_ppl\": 17.32, \"owt_ppl\": 18.04, \"wiki_ppl\": 15.11}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-25T09:01:23.531Z\"}, \"detect_remove_q07_seed42_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:12:00.041Z\", \"updated_at\": \"2026-05-25T04:30:47.018Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q07.jsonl --eval_data_path data/human/eval_holdout.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q07_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --bf16 --save_total_limit 2 --save_only_model --logging_steps 10 --eval_steps 500 --save_steps 500\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"987903\", \"log_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q07_seed42/train.log\", \"submitted_at\": \"2026-05-18T12:11:59.674Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q07.jsonl\", \"data_count\": 184908, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"wall_clock_seconds\": 577078.5, \"gpu_hours\": 160.3}, \"conclusion\": \"killed\", \"hypothesis\": \"Hard filtering at q_score > 0.7 threshold retains ~50% of data (184,908/370k samples), the most conservative D&R strategy keeping only high-confidence clean samples. Expected to outperform more aggressive thresholds (q>0.3, q>0.5) due to higher data quality per sample, completing the D&R threshold sweep.\", \"completed_at\": \"2026-05-25T04:29:58.212Z\", \"notes\": \"Killed: resume from checkpoint had missing optimizer/scheduler state (--save_only_model), AdamW momentum reset corrupted training. Replaced by detect_remove_q07_seed42_r3 (fresh from step 0).\"}, \"detect_remove_q03_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-18T14:24:48.317Z\", \"updated_at\": \"2026-05-25T04:30:44.316Z\", \"hypothesis\": \"Hard filtering (detect-and-remove) at q_score > 0.3 threshold retains ~70% of data by removing only high-confidence contaminated samples. Expected to outperform q>0.5 filtering (which is more aggressive) but underperform adaptive weighting which uses soft scores instead of binary thresholds.\", \"failure_reason\": \"EXIT_CODE=127 (command not found — check bash -c wrapping / env activate)\", \"completed_at\": \"2026-05-18T16:26:07.870Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"pid\": 8472, \"note\": \"resume from checkpoint-3000, inline eval disabled (--eval_data_path removed)\"}, \"conclusion\": \"killed\", \"notes\": \"Killed: resume from checkpoint had missing optimizer/scheduler state (--save_only_model), AdamW momentum reset corrupted training. q03 already has 3 seeds from prior runs, no rerun needed.\"}, \"detect_remove_q05_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-21T11:28:28.035Z\", \"updated_at\": \"2026-05-25T04:30:42.171Z\", \"hypothesis\": \"Hard filtering (detect-and-remove) at q_score > 0.5 threshold discards contaminated samples and trains uniformly on remaining clean data. Expected to underperform adaptive weighting because it wastes information from borderline samples and the binary threshold is miscalibrated relative to the soft q_score distribution.\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q05_seed42/checkpoint-5500\", \"log_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q05_seed42/train.log\"}, \"notes\": \"ckpt-5500 used as final due to resume optimizer corruption (--save_only_model caused missing optimizer/scheduler state, AdamW momentum reset on resume → PPL degraded to 17.946). ckpt-5500 metrics: holdout=17.291, owt=18.02, wiki=15.06\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-25T03:50:28.538385+00:00\"}]}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-25T04:30:30.091Z\", \"metrics\": {\"holdout_ppl\": 17.291, \"owt_ppl\": 18.02, \"wiki_ppl\": 15.06}}, \"eval_dr_q05_ckpt5500\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-25T03:28:03.136Z\", \"updated_at\": \"2026-05-25T03:56:00.000Z\", \"conclusion\": \"success\", \"metrics\": {\"holdout_ppl\": 17.29, \"holdout_loss\": 2.8502, \"owt_ppl\": 18.02, \"owt_loss\": 2.8916, \"wiki_ppl\": 15.06, \"wiki_loss\": 2.7118}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q05_seed42/checkpoint-5500\", \"log_path\": \"/tmp/eval_dr_q05_ckpt5500.log\", \"hypothesis\": \"Interim eval of D&R q>0.5 at checkpoint-5500 (70.8% training progress) to provide early data for paper while final training completes\", \"parent\": \"detect_remove_q05_seed42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python eval_perplexity.py --checkpoints .../checkpoint-5500 --data_path {holdout,owt,wiki} --max_docs 5000 --max_length 2048\", \"server\": \"westd-41312\", \"data_path\": \"data/human/eval_holdout.jsonl, data/eval_openwebtext.jsonl, data/eval_wikipedia.jsonl\", \"data_count\": 15000, \"model_name\": \"detect_remove_q05_seed42/checkpoint-5500\", \"seed\": 42, \"checkpoint_source\": \"detect_remove_q05_seed42\", \"eval_data\": \"holdout + openwebtext + wikipedia (5000 docs each)\"}}, \"detect_remove_q07_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T07:41:19.509Z\", \"updated_at\": \"2026-05-25T03:50:18.391Z\", \"hypothesis\": \"D&R threshold t=0.7: keep q≤0.7 (184,908 samples, 49.8%), removing moderately suspicious data. Tests intermediate filtering aggressiveness between t=0.5 (41.4%) and t=0.9 (61.6%). Part of threshold sensitivity sweep.\", \"spec\": {\"pid\": 8867, \"note\": \"resume from checkpoint-2500, inline eval disabled (--eval_data_path removed)\"}, \"metrics\": {\"eval_ppl_holdout\": 17.32, \"eval_loss_holdout\": 2.8519, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048 (final checkpoint)\", \"note\": \"final checkpoint, replaces partial ckpt-3500 PPL=17.49\"}, \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q07_seed42/checkpoint-3500\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q07_seed42.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T14:26:21.761Z\"}, \"random_subset_epoch_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-24T08:45:39.415Z\", \"updated_at\": \"2026-05-24T22:13:15.428Z\", \"hypothesis\": \"Random 31.48% subset with multi-epoch training should produce PPL between uniform full-data baseline and D&R filtered multi-epoch, because data filtering quality matters more than simply repeating data multiple epochs\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/random_subset_seed42.jsonl --eval_data_path data/human/eval_holdout.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/random_subset_epoch_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --max_steps 6103 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --bf16 --save_total_limit 2 --save_only_model --logging_steps 10 --eval_steps 500 --save_steps 500\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"data_path\": \"data/random_subset_seed42.jsonl\", \"data_count\": 116935, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-24T22:00:13.455Z\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-24T22:00:17.241Z\", \"notes\": \"holdout_ppl=17.694, owt_ppl=18.349, wiki_ppl=15.317, Δ≈-0.005 vs uniform (17.699)，无显著差异——random subset multi-epoch ≈ uniform single-epoch，确认 epoch 效应中性。Cron 误判为 failed（M066，第二次），训练实际完成 6103/6103 steps。\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-24T22:00:22.253102+00:00\"}]}, \"metrics\": {\"holdout_ppl\": 17.694, \"owt_ppl\": 18.349, \"wiki_ppl\": 15.317}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/random_subset_epoch_seed42/final\", \"log_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/random_subset_epoch_seed42/step_metrics.jsonl\"}, \"contamination_20_tau07_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-24T16:52:04.527Z\", \"updated_at\": \"2026-05-24T21:15:44.342Z\", \"hypothesis\": \"ρ=0.2 + τ=0.7: previous ρ=0.2 + τ=0.8 was negative (+0.046). Testing whether lower τ=0.7 is more appropriate at low contamination where natural α_eff is high. If still negative, confirms ρ=0.2 is below the method's effective range regardless of τ.\", \"parent\": \"rho02_adaptive_tau08_seed42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u training/pretrain_weighted.py --data_path data/scored_data_rho02.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/contamination_20_tau07_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --tau 0.7 --n_min 2 --num_train_tokens 200000000 --contamination_ratio 0.2 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --seed 42 --bf16 --save_total_limit 2 --logging_steps 10\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"data_path\": \"data/scored_data_rho02.jsonl\", \"data_count\": 206111, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/contamination_20_tau07_seed42\", \"log_path\": \"~/runs/provenance_weight_training/contamination_20_tau07_seed42.log\", \"hyperparams\": {\"weighting_method\": \"adaptive\", \"tau\": 0.7, \"n_min\": 2, \"contamination_ratio\": 0.2, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"lr\": 5e-05}, \"checkpoint_source\": \"N/A (training from scratch)\", \"eval_data\": \"N/A (training experiment, not eval)\"}, \"conclusion\": \"negative\", \"metrics\": {\"holdout_ppl\": 17.35, \"holdout_loss\": 2.853, \"owt_ppl\": 18.06, \"owt_loss\": 2.893, \"wiki_ppl\": 15.11, \"wiki_loss\": 2.715}, \"notes\": \"ρ=0.2 + τ=0.7: holdout_ppl=17.35 (Δ=+0.014 vs uniform 17.336). 比 τ=0.8 的 Δ=+0.046 好 70%，但仍略差于 uniform。确认 ρ=0.2 接近方法有效范围下限，τ=0.7 减少过度干预但不足以逆转。结果可补入 appendix。\"}, \"permuted_score_control_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-24T16:02:17.992Z\", \"updated_at\": \"2026-05-24T20:59:36.176Z\", \"hypothesis\": \"Permuted q-scores (random assignment of real scores to samples) should degrade vs uniform, confirming that the detector's provenance signal is load-bearing for adaptive weighting — not merely the non-uniformity of weights.\", \"reproduce\": {\"finished_at\": \"2026-05-24T20:52:47.395Z\"}, \"failure_reason\": \"\", \"completed_at\": \"2026-05-24T16:43:05.828Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-24T16:43:14.298708+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-24T20:52:56.202366+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -u training/pretrain_weighted.py --data_path data/scored_data_random_shuffle.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/permuted_score_control_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --tau 0.7 --n_min 2 --num_train_tokens 200000000 --contamination_ratio 0.4 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --seed 42 --bf16 --save_total_limit 2 --logging_steps 10\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data_random_shuffle.jsonl\", \"data_count\": null, \"model_name\": \"models/Qwen/Qwen3-0.6B\", \"seed\": 42, \"pid\": 966241, \"gpu\": \"cuda:3\", \"retry_count\": 2, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/permuted_score_control_seed42\", \"log_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/permuted_score_control_seed42/train.log\", \"train_loss\": 8.033, \"train_runtime_sec\": 13540, \"train_samples_per_second\": 7.212, \"train_steps_per_second\": 0.451, \"max_steps_reached\": 6103, \"epoch\": 0.2629, \"final_learning_rate\": 2.07e-07}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/permuted_score_control_seed42/final\", \"log_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/permuted_score_control_seed42/train.log\", \"conclusion\": \"success\", \"metrics\": {\"holdout_ppl\": 17.919, \"holdout_loss\": 2.886, \"holdout_tokens\": 5004058, \"owt_ppl\": 18.046, \"owt_loss\": 2.893, \"owt_tokens\": 5000859, \"wiki_ppl\": 14.891, \"wiki_loss\": 2.701, \"wiki_tokens\": 5009907}, \"notes\": \"Cron 误判为 failed（无 W&B sentinel），实际训练完成 6103/6103 steps。Reclassified as success: permuted scores holdout_ppl=17.919 vs uniform~17.694 (Δ=+0.225 degradation), confirms detector signal is load-bearing. train_loss=8.033 高但符合预期（随机分配的 scores 导致 weighted loss 不稳定，但 unweighted eval 指标正常）。\"}, \"p0_nmin_5\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-24T16:01:10.072Z\", \"updated_at\": \"2026-05-24T17:11:14.799Z\", \"hypothesis\": \"n_min sensitivity: n_min=5 (>B/2=2) over-constrains ESS floor, forcing b* toward 0 more often. Expected to degrade toward uniform PPL (~17.694). Completes n_min sensitivity curve: n_min=1 (+0.048), n_min=2 (−0.020, optimal), n_min=4 (recovers uniform), n_min=5 (this experiment).\", \"reproduce\": {\"finished_at\": \"2026-05-24T16:42:23.767Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-24T16:42:22.464Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-24T16:42:31.288480+00:00\"}], \"previous_failure\": {\"conclusion\": \"negative\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/p0_nmin_5 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --tau 0.7 --n_min 5 --num_train_tokens 200000000 --contamination_ratio 0.4 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --seed 42 --bf16 --save_total_limit 2 --logging_steps 10\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": null, \"model_name\": \"models/Qwen/Qwen3-0.6B\", \"seed\": 42, \"pid\": 966103, \"gpu\": \"cuda:1\", \"retry_count\": 2, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/p0_nmin_5\", \"log_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/p0_nmin_5/train.log\"}, \"conclusion\": \"negative\", \"notes\": \"n_min≥B forces b*=0, degenerates to uniform; killed by disk full at step 80, not worth rerunning. Analytically confirmed: n_min=5 > B=4 makes ESS constraint impossible to satisfy for any b>0, so b*≡0 (uniform weights).\"}, \"p0_batchsize_16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-24T15:56:36.323Z\", \"updated_at\": \"2026-05-24T16:22:23.171Z\", \"hypothesis\": \"Batch size amplification at B=16: adaptive τ=0.7 with n_min=8 (auto-compute: 16//2=8). Validates n_min coupling rule at B=16 and completes batch-size amplification series (B=4→8→16). Expected Δ≈-0.068 based on monotonic amplification trend from B=4 (Δ=-0.020) and B=8 (Δ=-0.052).\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/p0_batchsize_16 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --tau 0.7 --n_min 8 --num_train_tokens 200000000 --contamination_ratio 0.4 --batch_size 16 --gradient_accumulation_steps 1 --learning_rate 5e-5 --seed 42 --bf16 --save_total_limit 2 --logging_steps 10\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\", \"hyperparams\": {\"weighting_method\": \"adaptive\", \"tau\": 0.7, \"n_min\": 8, \"batch_size\": 16, \"gradient_accumulation_steps\": 1, \"effective_batch_size\": 16, \"lr\": 5e-05, \"contamination_ratio\": 0.4}, \"failure_reason\": \"OOM: 18.55 GiB logits tensor, B=16 grad_accum=1 exceeds GPU memory\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-24T16:22:23.171Z\"}, \"adaptive_seed789\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-24T04:42:39.014Z\", \"updated_at\": \"2026-05-24T09:06:09.955Z\", \"hypothesis\": \"N=5 seed replication (seed=789): adaptive provenance weighting with τ=0.7, n_min=2, B=4 on ρ=0.4 data. Fourth seed to strengthen paired t-test statistical power for B=4 Δ significance.\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/adaptive_seed789 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --tau 0.7 --n_min 2 --num_train_tokens 200000000 --contamination_ratio 0.4 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --seed 789 --bf16 --save_total_limit 2 --logging_steps 10\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": 922510, \"log_path\": \"~/runs/provenance_weight_training/adaptive_seed789.log\", \"submitted_at\": \"2026-05-24T04:42:54.988Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 789, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_seed789\", \"hyperparams\": {\"weighting_method\": \"adaptive\", \"contamination_ratio\": 0.4, \"tau\": 0.7, \"n_min\": 2, \"num_train_tokens\": 200000000, \"max_steps\": 6103, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"lr\": \"5e-5\", \"save_total_limit\": 2}, \"wall_clock_seconds\": 13925.8, \"gpu_hours\": 3.87}, \"reproduce\": {\"finished_at\": \"2026-05-24T08:31:07.184Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-24T08:31:13.649238+00:00\"}]}, \"metrics\": {\"holdout_ppl\": 17.668, \"owt_ppl\": 18.365, \"wiki_ppl\": 15.33, \"train_loss\": 9.65, \"train_duration_s\": 13570}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-24T08:35:00.800Z\"}, \"adaptive_seed234\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-24T04:42:41.978Z\", \"updated_at\": \"2026-05-24T09:06:08.809Z\", \"hypothesis\": \"N=5 seed replication (seed=234): adaptive provenance weighting with τ=0.7, n_min=2, B=4 on ρ=0.4 data. Fifth seed to complete N=5 paired t-test for B=4 Δ significance.\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/adaptive_seed234 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --tau 0.7 --n_min 2 --num_train_tokens 200000000 --contamination_ratio 0.4 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --seed 234 --bf16 --save_total_limit 2 --logging_steps 10\", \"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"pid\": 922738, \"log_path\": \"~/runs/provenance_weight_training/adaptive_seed234.log\", \"submitted_at\": \"2026-05-24T04:43:00.381Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 234, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_seed234\", \"hyperparams\": {\"weighting_method\": \"adaptive\", \"contamination_ratio\": 0.4, \"tau\": 0.7, \"n_min\": 2, \"num_train_tokens\": 200000000, \"max_steps\": 6103, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"lr\": \"5e-5\", \"save_total_limit\": 2}, \"wall_clock_seconds\": 13917.9, \"gpu_hours\": 3.87}, \"reproduce\": {\"finished_at\": \"2026-05-24T08:31:23.754Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-24T08:31:32.096109+00:00\"}]}, \"metrics\": {\"holdout_ppl\": 17.678, \"owt_ppl\": 18.34, \"wiki_ppl\": 15.341, \"train_loss\": 9.695, \"train_duration_s\": 13540}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-24T08:34:58.273Z\"}, \"uniform_seed234\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-24T04:42:43.151Z\", \"updated_at\": \"2026-05-24T08:44:03.476Z\", \"hypothesis\": \"N=5 seed replication (seed=234): uniform weighting baseline on ρ=0.4 data. Fifth seed paired with adaptive_seed234 for Δ calculation.\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/uniform_seed234 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --num_train_tokens 200000000 --contamination_ratio 0.4 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --seed 234 --bf16 --save_total_limit 2 --logging_steps 10\", \"server\": \"westd-41312\", \"gpu\": \"cuda:3\", \"pid\": 923155, \"log_path\": \"~/runs/provenance_weight_training/uniform_seed234.log\", \"submitted_at\": \"2026-05-24T04:43:04.505Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 234, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/uniform_seed234\", \"hyperparams\": {\"weighting_method\": \"uniform\", \"contamination_ratio\": 0.4, \"num_train_tokens\": 200000000, \"max_steps\": 6103, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"lr\": \"5e-5\", \"save_total_limit\": 2}, \"wall_clock_seconds\": 13533.1, \"gpu_hours\": 3.76}, \"reproduce\": {\"finished_at\": \"2026-05-24T08:19:51.651Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-24T08:20:05.021154+00:00\"}]}, \"metrics\": {\"holdout_ppl\": 17.708, \"holdout_loss\": 2.874, \"owt_ppl\": 18.355, \"wiki_ppl\": 15.352, \"train_loss\": 8.008, \"train_duration_s\": 12780}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-24T08:28:37.605Z\"}, \"uniform_seed789\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-24T04:42:40.614Z\", \"updated_at\": \"2026-05-24T08:44:02.005Z\", \"hypothesis\": \"N=5 seed replication (seed=789): uniform weighting baseline on ρ=0.4 data. Fourth seed paired with adaptive_seed789 for Δ calculation.\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/uniform_seed789 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --num_train_tokens 200000000 --contamination_ratio 0.4 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --seed 789 --bf16 --save_total_limit 2 --logging_steps 10\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"pid\": 922589, \"log_path\": \"~/runs/provenance_weight_training/uniform_seed789.log\", \"submitted_at\": \"2026-05-24T04:42:57.790Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 789, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/uniform_seed789\", \"hyperparams\": {\"weighting_method\": \"uniform\", \"contamination_ratio\": 0.4, \"num_train_tokens\": 200000000, \"max_steps\": 6103, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"lr\": \"5e-5\", \"save_total_limit\": 2}, \"wall_clock_seconds\": 13535.4, \"gpu_hours\": 3.76}, \"reproduce\": {\"finished_at\": \"2026-05-24T08:19:16.269Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-24T08:19:22.467092+00:00\"}]}, \"metrics\": {\"holdout_ppl\": 17.695, \"holdout_loss\": 2.8733, \"owt_ppl\": 18.387, \"wiki_ppl\": 15.349, \"train_loss\": 7.959, \"train_duration_s\": 12790}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-24T08:28:33.161Z\"}, \"aeff_only_nmin1_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T13:41:16.042Z\", \"updated_at\": \"2026-05-24T01:50:47.441Z\", \"hypothesis\": \"α_eff-only ablation seed456: cross-seed replicate. n_min=1 removes ESS constraint. Third seed for paired t-test vs dual-constrained baseline.\", \"spec\": {\"gpu\": \"cuda:1\", \"server\": \"westd-41312\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/aeff_only_nmin1_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --tau 0.7 --n_min 1 --num_train_tokens 200000000 --contamination_ratio 0.4 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --seed 456 --bf16 --save_total_limit 2\\\"\", \"pid\": 893568, \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"log_path\": \"~/runs/provenance_weight_training/aeff_only_nmin1_seed456.log\", \"hyperparams\": {\"weighting_method\": \"adaptive\", \"contamination_ratio\": 0.4, \"tau\": 0.7, \"n_min\": 1, \"num_train_tokens\": 200000000, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"lr\": \"5e-5\", \"save_total_limit\": 2}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/aeff_only_nmin1_seed456/final\"}, \"metrics\": {\"holdout_ppl\": 17.744, \"holdout_loss\": 2.8761}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-24T01:50:47.441Z\"}, \"bs8_nmin4_adaptive_seed456_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T12:49:48.326Z\", \"updated_at\": \"2026-05-23T23:11:36.489Z\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_adaptive_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --tau 0.7 --n_min 4 --num_train_tokens 200000000 --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --lr_scheduler_type linear --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 2 --gradient_checkpointing\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"pid\": 872464, \"gpu\": \"cuda:0\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_adaptive_seed456\", \"log_path\": \"~/runs/provenance_weight_training/bs8_nmin4_adaptive_seed456_r2.log\", \"note\": \"重启 r2: 原实验 contamination_ratio 配置错误，使用 rho=0.4 数据重跑\"}, \"hypothesis\": \"B=8 第三 seed 补全 3-seed paired comparison。seed42 Δ=−0.044, seed123 Δ=−0.056。预期 Δ∈[−0.040, −0.060]。3-seed 均值将提供 batch-size amplification (B=4→B=8→B=16) 的完整统计支撑。\", \"metrics\": {\"holdout_ppl\": 17.646, \"holdout_loss\": 2.8705, \"owt_ppl\": 18.322, \"wiki_ppl\": 15.299}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-23T22:42:34.159Z\"}, \"bs8_nmin4_uniform_seed456_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T12:49:50.668Z\", \"updated_at\": \"2026-05-23T23:09:57.578Z\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_uniform_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --num_train_tokens 200000000 --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --lr_scheduler_type linear --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 2 --gradient_checkpointing\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"pid\": 872861, \"gpu\": \"cuda:2\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_uniform_seed456\", \"log_path\": \"~/runs/provenance_weight_training/bs8_nmin4_uniform_seed456_r2.log\", \"note\": \"重启 r2: 原实验 contamination_ratio 配置错误，使用 rho=0.4 数据重跑\"}, \"hypothesis\": \"seed456 uniform baseline at B=8 for paired comparison with bs8_nmin4_adaptive_seed456. Completes 3-seed set for batch-size amplification statistical analysis.\", \"metrics\": {\"holdout_ppl\": 17.702, \"holdout_loss\": 2.8737, \"owt_ppl\": 18.393, \"wiki_ppl\": 15.354}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-23T22:42:36.457Z\"}, \"aeff_only_nmin1_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T13:41:13.680Z\", \"updated_at\": \"2026-05-23T20:14:39.454Z\", \"hypothesis\": \"α_eff-only ablation seed123: cross-seed replicate of aeff_only_nmin1_seed42. n_min=1 removes ESS constraint, isolating α_eff signal contribution.\", \"spec\": {\"gpu\": \"cuda:3\", \"server\": \"westd-41312\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/aeff_only_nmin1_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --tau 0.7 --n_min 1 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --seed 123 --bf16 --save_total_limit 2\\\"\", \"pid\": 875597, \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"hyperparams\": {\"weighting_method\": \"adaptive\", \"contamination_ratio\": 0.4, \"tau\": 0.7, \"n_min\": 1, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"lr\": \"5e-5\", \"save_total_limit\": 2}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/aeff_only_nmin1_seed123/checkpoint-6103\", \"log_path\": \"~/runs/provenance_weight_training/aeff_only_nmin1_seed123.log\"}, \"metrics\": {\"holdout_ppl\": 17.733, \"holdout_loss\": 2.8755}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-23T20:11:18.697Z\"}, \"aeff_only_nmin1_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T13:41:10.968Z\", \"updated_at\": \"2026-05-23T20:11:10.688Z\", \"hypothesis\": \"α_eff-only ablation: adaptive reweighting with n_min=1 (ESS≥1 always satisfied, only α_eff≤τ active). If PPL worse than dual-constrained (n_min=2, 17.674±0.007), ESS constraint has independent value beyond α_eff signal. Addresses R11-C2 + R12-W1.\", \"spec\": {\"gpu\": \"cuda:1\", \"server\": \"westd-41312\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/aeff_only_nmin1_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --tau 0.7 --n_min 1 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --seed 42 --bf16 --save_total_limit 2\\\"\", \"pid\": 875527, \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"hyperparams\": {\"weighting_method\": \"adaptive\", \"contamination_ratio\": 0.4, \"tau\": 0.7, \"n_min\": 1, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"lr\": \"5e-5\", \"save_total_limit\": 2}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/aeff_only_nmin1_seed42/checkpoint-6103\", \"log_path\": \"~/runs/provenance_weight_training/aeff_only_nmin1_seed42.log\"}, \"metrics\": {\"holdout_ppl\": 17.75, \"holdout_loss\": 2.8763}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-23T20:11:10.688Z\"}, \"bs8_nmin4_uniform_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T12:40:18.458Z\", \"updated_at\": \"2026-05-23T13:26:34.576Z\", \"hypothesis\": \"seed456 uniform baseline at B=8 for paired comparison with bs8_nmin4_adaptive_seed456. Completes 3-seed set for batch-size amplification statistical analysis.\", \"parent\": \"\", \"spec\": {\"gpu\": \"cuda:2\", \"server\": \"westd-41312\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_uniform_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --seed 456 --bf16 --save_total_limit 2\\\"\", \"pid\": 871842, \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 235555, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"hyperparams\": {\"weighting_method\": \"uniform\", \"contamination_ratio\": 0.4, \"batch_size\": 8, \"gradient_accumulation_steps\": 2, \"effective_batch_size\": 16, \"lr\": \"5e-5\", \"save_total_limit\": 2}}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-23T13:26:34.576Z\"}, \"bs8_nmin4_adaptive_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T12:40:14.696Z\", \"updated_at\": \"2026-05-23T13:26:32.270Z\", \"hypothesis\": \"B=8 第三 seed 补全 3-seed paired comparison。seed42 Δ=−0.044, seed123 Δ=−0.056。预期 Δ∈[−0.040, −0.060]。3-seed 均值将提供 batch-size amplification (B=4→B=8→B=16) 的完整统计支撑。\", \"parent\": \"\", \"spec\": {\"gpu\": \"cuda:0\", \"server\": \"westd-41312\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_adaptive_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --tau 0.7 --n_min 4 --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --seed 456 --bf16 --save_total_limit 2\\\"\", \"pid\": 871448, \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 235555, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"hyperparams\": {\"weighting_method\": \"adaptive\", \"contamination_ratio\": 0.4, \"tau\": 0.7, \"batch_size\": 8, \"gradient_accumulation_steps\": 2, \"effective_batch_size\": 16, \"n_min\": 4, \"lr\": \"5e-5\", \"save_total_limit\": 2}}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-23T13:26:32.270Z\"}, \"bs8_nmin4_uniform_seed123_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T03:24:23.816Z\", \"updated_at\": \"2026-05-23T08:51:36.835Z\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir .../bs8_nmin4_uniform_seed123 --model_name Qwen3-0.6B --weighting_method uniform --batch_size 8 --gradient_accumulation_steps 2 --lr 5e-5 --seed 123 --bf16 --save_total_limit 2 --resume_from_checkpoint checkpoint-500\", \"server\": \"westd-41312\", \"gpu\": \"cuda:3\", \"pid\": 835333, \"log_path\": \"~/runs/provenance_weight_training/bs8_nmin4_uniform_seed123_r2.log\", \"submitted_at\": \"2026-05-23T03:25:06.274Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 235555, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"hyperparams\": {\"weighting_method\": \"uniform\", \"contamination_ratio\": 0.4, \"batch_size\": 8, \"gradient_accumulation_steps\": 2, \"effective_batch_size\": 16, \"lr\": \"5e-5\", \"scheduler\": \"linear\", \"max_length\": 2048, \"num_train_tokens\": 200000000, \"max_steps\": 6103, \"save_total_limit\": 2, \"resumed_from\": \"checkpoint-500\"}, \"wall_clock_seconds\": 19590.6, \"gpu_hours\": 5.44}, \"hypothesis\": \"Cross-seed replicate (seed=123) uniform baseline at B=8. Retry from checkpoint-500 after disk-full crash. Provides second data point for B=8 batch-size amplification.\", \"metrics\": {\"eval_ppl_holdout\": 17.687, \"eval_ppl_owt\": 18.37, \"eval_ppl_wiki\": 15.385}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_uniform_seed123/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-23T08:51:36.835Z\"}, \"bs8_nmin4_adaptive_seed123_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T03:24:19.527Z\", \"updated_at\": \"2026-05-23T08:51:34.609Z\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir .../bs8_nmin4_adaptive_seed123 --model_name Qwen3-0.6B --weighting_method adaptive --tau 0.7 --n_min 4 --batch_size 8 --gradient_accumulation_steps 2 --lr 5e-5 --seed 123 --bf16 --save_total_limit 2 --resume_from_checkpoint checkpoint-500\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"pid\": 835240, \"log_path\": \"~/runs/provenance_weight_training/bs8_nmin4_adaptive_seed123_r2.log\", \"submitted_at\": \"2026-05-23T03:25:03.062Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 235555, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"hyperparams\": {\"weighting_method\": \"adaptive\", \"contamination_ratio\": 0.4, \"tau\": 0.7, \"batch_size\": 8, \"gradient_accumulation_steps\": 2, \"effective_batch_size\": 16, \"n_min\": 4, \"lr\": \"5e-5\", \"scheduler\": \"linear\", \"max_length\": 2048, \"num_train_tokens\": 200000000, \"max_steps\": 6103, \"save_total_limit\": 2, \"resumed_from\": \"checkpoint-500\"}, \"wall_clock_seconds\": 19591.5, \"gpu_hours\": 5.44}, \"hypothesis\": \"Cross-seed replicate (seed=123) of bs8_nmin4_adaptive_seed42 (Δ=−0.044). Retry from checkpoint-500 after disk-full crash. B=8 n_min=4 adaptive should show consistent negative Δ vs uniform.\", \"metrics\": {\"eval_ppl_holdout\": 17.631, \"eval_ppl_owt\": 18.338, \"eval_ppl_wiki\": 15.353}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_adaptive_seed123/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-23T08:51:34.609Z\"}, \"rho03_adaptive_seed456_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T03:23:15.525Z\", \"updated_at\": \"2026-05-23T08:51:32.331Z\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data_rho03.jsonl --output_dir .../rho03_adaptive_seed456_r2 --model_name Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.3 --tau 0.7 --batch_size 4 --gradient_accumulation_steps 4 --lr 5e-5 --seed 456 --bf16 --save_total_limit 2\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": 834745, \"log_path\": \"~/runs/provenance_weight_training/rho03_adaptive_seed456_r2.log\", \"submitted_at\": \"2026-05-23T03:23:46.396Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_rho03.jsonl\", \"data_count\": 235555, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"hyperparams\": {\"weighting_method\": \"adaptive\", \"contamination_ratio\": 0.3, \"tau\": 0.7, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"n_min\": 2, \"lr\": \"5e-5\", \"scheduler\": \"linear\", \"max_length\": 2048, \"num_train_tokens\": 200000000, \"max_steps\": 6103, \"save_total_limit\": 2}, \"wall_clock_seconds\": 19665.9, \"gpu_hours\": 5.46}, \"hypothesis\": \"Third seed (456) for ρ=0.3 boundary check (retry, from scratch after disk-full crash). With seed42 Δ=0.000 and seed123 Δ=+0.002 on holdout, seed456 should confirm ρ=0.3 as neutral transition zone.\", \"metrics\": {\"eval_ppl_holdout\": 17.424, \"eval_ppl_owt\": 18.115, \"eval_ppl_wiki\": 15.161}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/rho03_adaptive_seed456_r2/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-23T08:51:32.331Z\"}, \"rho03_uniform_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T01:04:02.959Z\", \"updated_at\": \"2026-05-23T07:04:54.839Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_rho03.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/rho03_uniform_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.3 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --lr_scheduler_type linear --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing --resume_from_checkpoint /root/autodl-tmp/provenance_weight_training/output/models/rho03_uniform_seed456/checkpoint-1000\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"833051\", \"log_path\": \"~/runs/provenance_weight_training/rho03_uniform_seed456.log\", \"submitted_at\": \"2026-05-23T03:19:08.210Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 13490.1, \"gpu_hours\": 3.75}, \"hypothesis\": \"Third seed (456) uniform baseline at ρ=0.3 for paired comparison with rho03_adaptive_seed456. Completes 3-seed set for paired t-test at the boundary contamination ratio.\", \"reproduce\": {\"finished_at\": \"2026-05-23T06:48:09.472Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-23T06:48:15.272349+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.419, \"eval_ppl_owt\": 18.109, \"eval_ppl_wiki\": 15.168}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/rho03_uniform_seed456/final\", \"log_path\": \"~/runs/provenance_weight_training/rho03_uniform_seed456.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-23T07:03:58.335Z\"}, \"rho03_adaptive_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T01:04:00.701Z\", \"updated_at\": \"2026-05-23T03:24:17.322Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_rho03.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/rho03_adaptive_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.3 --tau 0.7 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --lr_scheduler_type linear --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing --resume_from_checkpoint /root/autodl-tmp/provenance_weight_training/output/models/rho03_adaptive_seed456/checkpoint-1000\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"832974\", \"log_path\": \"~/runs/provenance_weight_training/rho03_adaptive_seed456.log\", \"submitted_at\": \"2026-05-23T03:19:05.498Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 164.1, \"gpu_hours\": 0.05}, \"hypothesis\": \"Third seed (456) for ρ=0.3 boundary check. With seed42 Δ=0.000 and seed123 Δ=+0.002 on holdout, seed456 should confirm ρ=0.3 as neutral transition zone (Δ ≈ 0), enabling paired t-test (N=3) to formally establish non-significance at the boundary.\", \"reproduce\": {\"finished_at\": \"2026-05-23T03:21:43.508Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-23T03:21:49.561Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-23T03:21:55.579981+00:00\"}]}, \"notes\": \"失败原因: FileNotFoundError — checkpoint-1000/trainer_state.json 不存在，resume_from_checkpoint 失败 | 类型: infrastructure | fix_worker_id: worker_diagnose_rho03_adaptive_seed456_20260523T032401 | 自动修复中\"}, \"batchsize16_nmin8_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:17:10.215Z\", \"updated_at\": \"2026-05-23T03:23:40.397Z\", \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/provenance_weight_training && bash scripts/run_bs16_nmin8_r2.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"48881\", \"log_path\": \"~/runs/provenance_weight_training/batchsize16_nmin8_r2.log\", \"submitted_at\": \"2026-05-17T19:32:48.742Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 324648.2, \"gpu_hours\": 90.18}, \"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T11:44:39.058Z\"}, \"eval_uniform_1_7b_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:06:38.917Z\", \"updated_at\": \"2026-05-23T03:23:12.618Z\", \"spec\": {\"command\": \"eval_perplexity.py on uniform_1_7b_seed42_resumed/final\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"241549\", \"log_path\": \"~/runs/provenance_weight_training/eval_uniform_1_7b_v3.log\", \"submitted_at\": \"2026-05-18T19:06:38.561Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/human/eval_holdout.jsonl\", \"data_count\": 5000, \"model_name\": \"Qwen3-1.7B (uniform)\", \"seed\": 42, \"checkpoint_source\": \"uniform_1_7b_seed42_resumed\", \"eval_data\": \"data/human/eval_holdout.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed42_resumed/final\", \"wall_clock_seconds\": 11071.3, \"gpu_hours\": 3.08}, \"metrics\": {\"eval_ppl_holdout\": 13.5}, \"conclusion\": \"success\", \"hypothesis\": \"Eval uniform_1_7b_seed42_resumed on holdout: baseline PPL for 1.7B uniform training. Paired with eval_adaptive_1_7b_v2 to measure adaptive vs uniform gap at larger scale.\", \"completed_at\": \"2026-05-18T22:11:09.846Z\"}, \"eval_adaptive_1_7b_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:06:41.217Z\", \"updated_at\": \"2026-05-23T03:23:09.813Z\", \"spec\": {\"command\": \"eval_perplexity.py on adaptive_1_7b_seed42/final\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"241628\", \"log_path\": \"~/runs/provenance_weight_training/eval_adaptive_1_7b_v2.log\", \"submitted_at\": \"2026-05-18T19:06:40.866Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/human/eval_holdout.jsonl\", \"data_count\": 5000, \"model_name\": \"Qwen3-1.7B (adaptive)\", \"seed\": 42, \"checkpoint_source\": \"adaptive_1_7b_seed42\", \"eval_data\": \"data/human/eval_holdout.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed42/final\", \"wall_clock_seconds\": 11067.4, \"gpu_hours\": 3.07}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 13.27}, \"hypothesis\": \"Eval adaptive_1_7b_seed42 on holdout: if adaptive PPL < uniform PPL at 1.7B scale, the provenance weighting advantage persists with larger models, not just 0.6B.\", \"completed_at\": \"2026-05-18T22:11:08.245Z\"}, \"bs8_nmin4_uniform_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T01:08:21.983Z\", \"updated_at\": \"2026-05-23T03:23:04.956Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_uniform_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --lr_scheduler_type linear --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing --resume_from_checkpoint /root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_uniform_seed123/checkpoint-1000\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"833558\", \"log_path\": \"~/runs/provenance_weight_training/bs8_nmin4_uniform_seed123.log\", \"submitted_at\": \"2026-05-23T03:19:17.194Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 195.3, \"gpu_hours\": 0.05}, \"hypothesis\": \"Cross-seed replicate (seed=123) uniform baseline at B=8 for paired comparison with bs8_nmin4_adaptive_seed123. Provides second data point for B=8 batch-size amplification.\", \"reproduce\": {\"finished_at\": \"2026-05-23T03:22:28.059Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-23T03:22:32.518Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-23T03:22:44.697596+00:00\"}]}}, \"bs8_nmin4_adaptive_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-23T01:08:19.280Z\", \"updated_at\": \"2026-05-23T03:23:03.743Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_adaptive_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.7 --n_min 4 --num_train_tokens 200000000 --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --lr_scheduler_type linear --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing --resume_from_checkpoint /root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_adaptive_seed123/checkpoint-1000\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"833474\", \"log_path\": \"~/runs/provenance_weight_training/bs8_nmin4_adaptive_seed123.log\", \"submitted_at\": \"2026-05-23T03:19:14.537Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 179.8, \"gpu_hours\": 0.05}, \"hypothesis\": \"Cross-seed replicate (seed=123) of bs8_nmin4_adaptive_seed42 (Δ=−0.044). B=8 n_min=4 adaptive should show consistent negative Δ vs uniform, strengthening batch-size amplification evidence (B=4 Δ=−0.020, B=8 Δ=−0.044, B=16 Δ=−0.068).\", \"reproduce\": {\"finished_at\": \"2026-05-23T03:22:07.156Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-23T03:22:14.307Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-23T03:22:20.183110+00:00\"}]}}, \"rho03_uniform_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T18:58:34.743Z\", \"updated_at\": \"2026-05-23T00:24:24.189Z\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data_rho03.jsonl --output_dir .../rho03_uniform_seed123 --model_name Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.3 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --lr_scheduler_type linear --seed 123 --bf16 --gradient_checkpointing\", \"server\": \"westd-41312\", \"gpu\": \"cuda:3\", \"pid\": 805963, \"log_path\": \"~/runs/provenance_weight_training/rho03_uniform_seed123.log\", \"submitted_at\": \"2026-05-22T18:59:03.235Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_rho03.jsonl\", \"data_count\": 235555, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"hyperparams\": {\"weighting_method\": \"uniform\", \"contamination_ratio\": 0.3, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"lr\": \"5e-5\", \"scheduler\": \"linear\", \"max_length\": 2048, \"num_train_tokens\": 200000000, \"max_steps\": 6103}, \"wall_clock_seconds\": 19521.0, \"gpu_hours\": 5.42}, \"metrics\": {\"eval_ppl_holdout\": 17.433, \"eval_ppl_owt\": 18.126, \"eval_ppl_wiki\": 15.204}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/rho03_uniform_seed123/final\", \"conclusion\": \"success\", \"hypothesis\": \"Cross-seed replicate (seed=123) uniform baseline at ρ=0.3 for paired comparison with rho03_adaptive_seed123. Provides second data point for measuring adaptive Δ at the boundary contamination ratio.\", \"completed_at\": \"2026-05-23T00:24:24.189Z\"}, \"rho03_uniform_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T18:55:51.970Z\", \"updated_at\": \"2026-05-23T00:24:21.897Z\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data_rho03.jsonl --output_dir .../rho03_uniform_seed42 --model_name Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.3 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --lr_scheduler_type linear --seed 42 --bf16 --gradient_checkpointing\", \"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"pid\": 805117, \"log_path\": \"~/runs/provenance_weight_training/rho03_uniform_seed42.log\", \"submitted_at\": \"2026-05-22T18:56:37.486Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_rho03.jsonl\", \"data_count\": 235555, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"hyperparams\": {\"weighting_method\": \"uniform\", \"contamination_ratio\": 0.3, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"lr\": \"5e-5\", \"scheduler\": \"linear\", \"max_length\": 2048, \"num_train_tokens\": 200000000, \"max_steps\": 6103}, \"wall_clock_seconds\": 19664.4, \"gpu_hours\": 5.46}, \"metrics\": {\"eval_ppl_holdout\": 17.422, \"eval_ppl_owt\": 18.113, \"eval_ppl_wiki\": 15.204}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/rho03_uniform_seed42/final\", \"conclusion\": \"success\", \"hypothesis\": \"Uniform baseline at ρ=0.3 for paired comparison with rho03_adaptive_seed42. Expected PPL between ρ=0.2 uniform (17.336) and ρ=0.4 uniform (17.694), providing the control condition to measure adaptive Δ at the boundary contamination ratio.\", \"completed_at\": \"2026-05-23T00:24:21.897Z\"}, \"rho03_adaptive_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T18:58:32.055Z\", \"updated_at\": \"2026-05-23T00:24:19.490Z\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data_rho03.jsonl --output_dir .../rho03_adaptive_seed123 --model_name Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.3 --tau 0.7 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --lr_scheduler_type linear --seed 123 --bf16 --gradient_checkpointing\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"pid\": 805886, \"log_path\": \"~/runs/provenance_weight_training/rho03_adaptive_seed123.log\", \"submitted_at\": \"2026-05-22T18:59:00.783Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_rho03.jsonl\", \"data_count\": 235555, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"hyperparams\": {\"weighting_method\": \"adaptive\", \"contamination_ratio\": 0.3, \"tau\": 0.7, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"n_min\": 2, \"lr\": \"5e-5\", \"scheduler\": \"linear\", \"max_length\": 2048, \"num_train_tokens\": 200000000, \"max_steps\": 6103}, \"wall_clock_seconds\": 19518.7, \"gpu_hours\": 5.42}, \"metrics\": {\"eval_ppl_holdout\": 17.435, \"eval_ppl_owt\": 18.148, \"eval_ppl_wiki\": 15.165}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/rho03_adaptive_seed123/final\", \"conclusion\": \"success\", \"hypothesis\": \"Cross-seed replicate (seed=123) of rho03_adaptive_seed42. At ρ=0.3 boundary, adaptive τ=0.7 should show consistent Δ vs uniform across seeds, establishing statistical reliability of the boundary effect.\", \"completed_at\": \"2026-05-23T00:24:19.490Z\"}, \"rho03_adaptive_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T18:55:48.966Z\", \"updated_at\": \"2026-05-23T00:24:17.220Z\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data_rho03.jsonl --output_dir .../rho03_adaptive_seed42 --model_name Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.3 --tau 0.7 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --lr_scheduler_type linear --seed 42 --bf16 --gradient_checkpointing\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": 805034, \"log_path\": \"~/runs/provenance_weight_training/rho03_adaptive_seed42.log\", \"submitted_at\": \"2026-05-22T18:56:35.094Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_rho03.jsonl\", \"data_count\": 235555, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"hyperparams\": {\"weighting_method\": \"adaptive\", \"contamination_ratio\": 0.3, \"tau\": 0.7, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"effective_batch_size\": 16, \"n_min\": 2, \"lr\": \"5e-5\", \"scheduler\": \"linear\", \"max_length\": 2048, \"num_train_tokens\": 200000000, \"max_steps\": 6103}, \"wall_clock_seconds\": 19662.1, \"gpu_hours\": 5.46}, \"metrics\": {\"eval_ppl_holdout\": 17.422, \"eval_ppl_owt\": 18.123, \"eval_ppl_wiki\": 15.172}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/rho03_adaptive_seed42/final\", \"conclusion\": \"success\", \"hypothesis\": \"At ρ=0.3 (boundary between ρ=0.2 fail and ρ=0.4 success), adaptive τ=0.7 weighting should still improve over uniform but with smaller Δ than ρ=0.4 (Δ=−0.068). This tests the contamination threshold where detect-and-reweight becomes effective, establishing the method's sensitivity boundary.\", \"completed_at\": \"2026-05-23T00:24:17.220Z\"}, \"random_reweight_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T17:55:01.850Z\", \"updated_at\": \"2026-05-22T18:58:28.114Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export WANDB_MODE=disabled && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/random_reweight_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method random --contamination_ratio 0.4 --tau 0.8 --n_min 2 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model --resume_from_checkpoint /root/autodl-tmp/provenance_weight_training/output/models/random_reweight_seed456/checkpoint-1000\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"136144\", \"log_path\": \"~/runs/provenance_weight_training/random_reweight_seed456.log\", \"submitted_at\": \"2026-05-17T21:30:09.042Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 317580.3, \"gpu_hours\": 88.22}, \"hypothesis\": \"U(0,2) random weights baseline seed=456: third seed for Claim 1 random degradation evidence. Random weights drawn from U(0,2) should degrade PPL vs uniform and adaptive, consistent with seed42 and seed123 results, confirming detector q-scores provide real data quality signal beyond random noise.\", \"parent\": \"random_reweight_seed123_r5\", \"reproduce\": {\"finished_at\": \"2026-05-17T21:11:42.187Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T21:11:43.582Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T21:11:46.851773+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.777, \"eval_loss_holdout\": 2.8779, \"eval_holdout_tokens\": 4077068, \"total_steps\": 6103, \"train_loss\": 6.657, \"train_runtime_seconds\": 10739}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/random_reweight_seed456/final\"}, \"bs8_nmin4_uniform_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T11:29:06.990Z\", \"updated_at\": \"2026-05-22T16:46:39.834Z\", \"hypothesis\": \"Batch-size sensitivity B=8 uniform baseline: uniform weighting with effective batch=16 (bs=8 × grad_accum=2). Paired with bs8_nmin4_adaptive_seed42 to measure Δ(adaptive−uniform) at B=8. Expected: B=4 Δ=−0.020, B=8 Δ should be intermediate, B=16 Δ=−0.068. Monotonic trend confirms batch-size amplification mechanism.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=1 PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_uniform_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --max_steps 6103 --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --lr_scheduler_type linear --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\\\"\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"pid\": 764807, \"log_path\": \"~/runs/provenance_weight_training/bs8_nmin4_uniform_seed42.log\", \"submitted_at\": \"2026-05-22T11:29:28.934Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"wall_clock_seconds\": 17194.8, \"gpu_hours\": 4.78}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_uniform_seed42/final\", \"metrics\": {\"holdout_ppl\": 17.694185837410274, \"owt_ppl\": 18.363068741825792, \"wiki_ppl\": 15.336710587451519, \"holdout_loss\": 2.8732361018550434, \"owt_loss\": 2.910341514026512, \"wiki_loss\": 2.730249339271619}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T16:16:03.756Z\"}, \"bs8_nmin4_adaptive_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T10:48:54.953Z\", \"updated_at\": \"2026-05-22T16:46:38.748Z\", \"hypothesis\": \"Batch-size sensitivity B=8: adaptive reweighting with tau=0.7, n_min=4 (⌊B/2⌋), effective batch=16 (bs=8 × grad_accum=2). Tests whether adaptive advantage scales monotonically with batch size: B=4 Δ=−0.020, B=16 Δ=−0.068. B=8 should fall between, confirming batch-size amplification mechanism. Paired with bs8_nmin4_uniform_seed42.\", \"spec\": {\"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"from_scratch\", \"eval_data\": [\"holdout_combined\", \"owt_eval\", \"wiki_eval\"], \"hyperparams\": {\"batch_size\": 8, \"gradient_accumulation_steps\": 2, \"effective_batch\": 16, \"lr\": \"5e-5\", \"lr_scheduler\": \"linear\", \"max_steps\": 6103, \"tau\": 0.7, \"n_min\": 4, \"weighting_method\": \"adaptive\", \"contamination_ratio\": 0.4}, \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=0 PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_adaptive_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.7 --n_min 4 --max_steps 6103 --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --lr_scheduler_type linear --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\\\"\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": 757990}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs8_nmin4_adaptive_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/bs8_nmin4_adaptive_seed42.log\", \"metrics\": {\"holdout_ppl\": 17.650425404986372, \"owt_ppl\": 18.332103963757113, \"wiki_ppl\": 15.318017946105257, \"holdout_loss\": 2.8707598853543677, \"owt_loss\": 2.908653837793633, \"wiki_loss\": 2.729029779056454}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T16:16:01.573Z\"}, \"detect_remove_q05_v2_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T09:09:58.143Z\", \"updated_at\": \"2026-05-22T14:29:36.228Z\", \"hypothesis\": \"D&R hard filtering (remove q≤0.5 samples) with seed 456 should produce holdout PPL consistent with seed42 and seed123, confirming the stability of the filtering approach across random seeds.\", \"parent\": \"detect_remove_q05_v2_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=2 PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q05_v2_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --lr_scheduler_type linear --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\\\"\", \"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"pid\": 742953, \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q05_v2_seed456.log\", \"submitted_at\": \"2026-05-22T09:10:09.527Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 153725, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"eval_data\": [\"holdout_combined\", \"owt_eval\", \"wiki_eval\"], \"wall_clock_seconds\": 16469.8, \"gpu_hours\": 4.57}, \"reproduce\": {\"finished_at\": \"2026-05-22T13:20:27.607Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-22T13:20:37.624112+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"holdout_ppl\": 17.277, \"holdout_loss\": 2.8493, \"owt_ppl\": 18.017, \"owt_loss\": 2.8913, \"wiki_ppl\": 15.04, \"wiki_loss\": 2.7106, \"train_loss\": 11.01, \"total_steps\": 6103, \"training_time_s\": 14920}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q05_v2_seed456/final\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q05_v2_seed456.log\", \"completed_at\": \"2026-05-22T13:44:39.347Z\"}, \"random_reweight_v2_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T03:32:33.573Z\", \"updated_at\": \"2026-05-22T13:43:27.483Z\", \"hypothesis\": \"Random reweight seed456 v2: uses scored_data_random_shuffle.jsonl + adaptive weighting (matching seed42/seed123 config). Third seed for detector signal load-bearing test. Paired with random_reweight_baseline_seed42 (17.958) and random_reweight_seed123 (17.945).\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data_random_shuffle.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/random_reweight_v2_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": 699452, \"log_path\": \"~/runs/provenance_weight_training/random_reweight_v2_seed456.log\", \"data_path\": \"data/scored_data_random_shuffle.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"eval_data\": [\"holdout_combined\", \"owt_eval\", \"wiki_eval\"]}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/random_reweight_v2_seed456/final\", \"log_path\": \"~/runs/provenance_weight_training/random_reweight_v2_seed456.log\", \"metrics\": {\"holdout_ppl\": 17.951, \"owt_ppl\": 18.602, \"wiki_ppl\": 15.503}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T13:43:27.483Z\"}, \"uniform_epoch_matched_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T09:42:58.560Z\", \"updated_at\": \"2026-05-22T11:27:52.856Z\", \"hypothesis\": \"Uniform epoch-matched seed456: trains on full data (scored_data.jsonl, 371499 samples) for 2533 steps with independent linear LR schedule (5e-5→0), effective batch=16 (bs=4 × grad_accum=4). Third seed for uniform epoch-matched baseline. Paired with uniform_epoch_matched_indep_lr_seed42 (holdout=18.062) and dr_epoch_matched experiments for epoch confound quantification.\", \"parent\": \"uniform_epoch_matched_indep_lr_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=1 PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/uniform_epoch_matched_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --max_steps 2533 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"pid\": 748574, \"log_path\": \"~/runs/provenance_weight_training/uniform_epoch_matched_seed456.log\", \"submitted_at\": \"2026-05-22T09:43:09.347Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"eval_data\": [\"holdout_combined\", \"owt_eval\", \"wiki_eval\"], \"wall_clock_seconds\": 6283.5, \"gpu_hours\": 1.75}, \"reproduce\": {\"finished_at\": \"2026-05-22T11:12:24.109Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-22T11:12:29.685867+00:00\"}]}, \"metrics\": {\"holdout_ppl\": 18.068, \"holdout_loss\": 2.8941, \"owt_ppl\": 18.66, \"owt_loss\": 2.9264, \"wiki_ppl\": 15.515, \"wiki_loss\": 2.7418, \"train_loss\": 8.039, \"total_steps\": 2533}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/uniform_epoch_matched_seed456/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T11:27:52.856Z\"}, \"dr_epoch_matched_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T08:27:17.771Z\", \"updated_at\": \"2026-05-22T10:45:14.168Z\", \"hypothesis\": \"Epoch-matched D&R seed456: trains on filtered data (q≤0.5, 153725 samples) for exactly 2533 steps with independent linear LR schedule (5e-5→0), effective batch=16 (bs=4 × grad_accum=4). Third seed for epoch confound quantification. Paired with dr_epoch_matched_indep_lr_v2_seed42 (17.651) and dr_epoch_matched_seed123_r2 (17.659).\", \"parent\": \"dr_epoch_matched_indep_lr_v2_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=0 PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/dr_epoch_matched_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --max_steps 2533 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --lr_scheduler_type linear --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\\\"\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": 725040, \"log_path\": \"~/runs/provenance_weight_training/dr_epoch_matched_seed456.log\", \"submitted_at\": \"2026-05-22T08:27:29.373Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 153725, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"eval_data\": [\"holdout_combined\", \"owt_eval\", \"wiki_eval\"], \"wall_clock_seconds\": 8264.8, \"gpu_hours\": 2.3}, \"reproduce\": {\"finished_at\": \"2026-05-22T10:24:09.597Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-22T10:24:15.210830+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/dr_epoch_matched_seed456/final\", \"log_path\": \"~/runs/provenance_weight_training/dr_epoch_matched_seed456.log\", \"metrics\": {\"holdout_ppl\": 17.66, \"owt_ppl\": 18.27, \"wiki_ppl\": 15.16}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T10:45:14.168Z\"}, \"detect_remove_q05_v2_seed123_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T23:57:35.984Z\", \"updated_at\": \"2026-05-22T09:08:04.733Z\", \"hypothesis\": \"D&R hard filtering seed123 rerun with CORRECT effective batch=16 (batch_size=4 × grad_accum=4). Previous detect_remove_q05_v2_seed123 was invalid (effective batch=4). Full training on filtered data (q≤0.5, 153725 samples) for ~6103 steps with 200M token budget. Paired with detect_remove_q05_v2_seed42 for 2-seed consistency.\", \"parent\": \"detect_remove_q05_v2_seed123\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q05_v2_seed123_r2 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --lr_scheduler_type linear --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\", \"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"pid\": 682848, \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q05_v2_seed123_r2.log\", \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 153725, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"from_scratch\", \"eval_data\": [\"holdout_combined\", \"owt_eval\", \"wiki_eval\"]}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q05_v2_seed123_r2/final\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q05_v2_seed123_r2.log\", \"metrics\": {\"holdout_loss\": 2.8491, \"holdout_ppl\": 17.272, \"owt_loss\": 2.8908, \"owt_ppl\": 18.008, \"wiki_loss\": 2.7111, \"wiki_ppl\": 15.047, \"eval_holdout_tokens\": 4077068, \"eval_owt_tokens\": 6767242, \"eval_wiki_tokens\": 27000339, \"total_steps\": 6103, \"train_loss\": 11.01}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T09:08:04.733Z\"}, \"bs16_uniform_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T03:32:02.600Z\", \"updated_at\": \"2026-05-22T08:50:09.265Z\", \"hypothesis\": \"Uniform baseline at batch_size=16, seed456. Third seed for bs16 batch-size sensitivity analysis. Paired with bs16_adaptive_tau07_seed456. If 3-seed Δ(adaptive−uniform) at bs=16 confirms amplification vs bs=4, strengthens the batch-size mechanism claim.\", \"parent\": \"bs16_uniform_seed42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs16_uniform_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 16 --gradient_accumulation_steps 1 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": 697578, \"log_path\": \"/root/runs/provenance_weight_training/bs16_uniform_seed456.log\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"eval_data\": [\"holdout_combined\", \"owt_eval\", \"wiki_eval\"]}, \"metrics\": {\"holdout_loss\": 2.8745, \"holdout_ppl\": 17.717, \"owt_loss\": 2.9118, \"owt_ppl\": 18.39, \"wiki_loss\": 2.7319, \"wiki_ppl\": 15.363, \"total_steps\": 6103, \"train_loss\": 1.991}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs16_uniform_seed456/final\", \"log_path\": \"/root/runs/provenance_weight_training/bs16_uniform_seed456.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T08:18:29.641Z\"}, \"bs16_adaptive_tau07_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-22T03:32:04.878Z\", \"updated_at\": \"2026-05-22T08:50:07.781Z\", \"hypothesis\": \"Adaptive dual-constraint weighting with bs=16 (n_min=8, tau=0.7), seed456. Third seed for batch-size amplification effect. Paired with bs16_uniform_seed456. If 3-seed mean Δ(adaptive−uniform) at bs=16 >> bs=4's Δ=−0.020, confirms batch size amplifies adaptive advantage.\", \"parent\": \"bs16_adaptive_tau07_seed42\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs16_adaptive_tau07_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.7 --num_train_tokens 200000000 --batch_size 16 --gradient_accumulation_steps 1 --n_min 8 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": 698965, \"log_path\": \"~/runs/provenance_weight_training/bs16_adaptive_tau07_seed456.log\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"eval_data\": [\"holdout_combined\", \"owt_eval\", \"wiki_eval\"]}, \"metrics\": {\"holdout_loss\": 2.8704, \"holdout_ppl\": 17.645, \"owt_loss\": 2.9076, \"owt_ppl\": 18.313, \"wiki_loss\": 2.7276, \"wiki_ppl\": 15.296, \"total_steps\": 6103, \"train_loss\": 2.528}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs16_adaptive_tau07_seed456/final\", \"log_path\": \"~/runs/provenance_weight_training/bs16_adaptive_tau07_seed456.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T08:18:31.981Z\"}, \"dr_epoch_matched_seed123_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T23:54:06.369Z\", \"updated_at\": \"2026-05-22T02:22:21.103Z\", \"hypothesis\": \"Epoch-matched D&R seed123 rerun with CORRECT effective batch=16 (batch_size=4 × grad_accum=4). Previous dr_epoch_matched_seed123 was invalid (effective batch=4, missing grad_accum). Trains on filtered data (q≤0.5, 153725 samples) for 2533 steps with independent linear LR schedule (5e-5→0). Paired with detect_remove_q05_v2_seed123 to quantify seed123 epoch confound percentage.\", \"parent\": \"dr_epoch_matched_seed123\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/dr_epoch_matched_seed123_r2 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --max_steps 2533 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --lr_scheduler_type linear --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"681583\", \"log_path\": \"~/runs/provenance_weight_training/dr_epoch_matched_seed123_r2.log\", \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 153725, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"holdout_combined + owt_eval + wiki_eval\"}, \"reproduce\": {\"finished_at\": \"2026-05-22T02:07:51.990Z\"}, \"metrics\": {\"holdout_loss\": 2.8713, \"holdout_ppl\": 17.6591, \"owt_loss\": 2.9069, \"owt_ppl\": 18.2991, \"wiki_loss\": 2.7208, \"wiki_ppl\": 15.1918, \"eval_holdout_tokens\": 4077068, \"eval_owt_tokens\": 6767242, \"eval_wiki_tokens\": 27000339}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/dr_epoch_matched_seed123_r2/final\", \"log_path\": \"~/runs/provenance_weight_training/dr_epoch_matched_seed123_r2.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-22T02:22:21.103Z\"}, \"random_reweight_seed123\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T08:15:03.968Z\", \"updated_at\": \"2026-05-22T01:08:43.003Z\", \"server\": \"westd-30476\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_random_reweight_seed123.sh\\\"\", \"finished_at\": \"2026-05-22T00:52:13.127Z\"}, \"failure_reason\": \"Traceback → , in main trainer = WeightedTrainer( ^^^^^^^^^^^^^^^^ File \\\"/root/provenance_weight_training/training/pretrain_weighted.py\\\", line 101, in __init__ super().__init__(**kwargs) TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'\", \"completed_at\": \"2026-05-17T11:17:19.899Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T11:17:28.307496+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-22T00:52:18.825002+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"hypothesis\": \"Random reweight seed123 replication: shuffling q_scores before computing adaptive weights destroys the detector's contamination signal while preserving the weight distribution shape. Paired with random_reweight_baseline_seed42 (PPL=17.958) for 2-seed consistency.\", \"parent\": \"random_reweight_baseline_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_random_shuffle.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/random_reweight_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"653354\", \"data_path\": \"data/scored_data_random_shuffle.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"holdout_combined + owt_eval + wiki_eval\", \"log_path\": \"~/runs/provenance_weight_training/random_reweight_seed123.log\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/random_reweight_seed123\"}, \"metrics\": {\"holdout_loss\": 2.8873, \"holdout_ppl\": 17.945, \"owt_loss\": 2.9243, \"owt_ppl\": 18.622, \"wiki_loss\": 2.7448, \"wiki_ppl\": 15.562, \"total_steps\": 6103, \"train_loss\": 8.042, \"train_runtime_seconds\": 15820, \"eval_holdout_tokens\": 4077068}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/random_reweight_seed123/final\", \"log_path\": \"~/runs/provenance_weight_training/random_reweight_seed123.log\", \"conclusion\": \"success\"}, \"bs16_adaptive_tau07_seed123_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T18:56:36.825Z\", \"updated_at\": \"2026-05-22T00:53:30.898Z\", \"hypothesis\": \"Batch size sensitivity replication seed123: adaptive weighting with bs=16 (n_min=8) vs bs=4. If Δ(adaptive−uniform) at bs=16 is comparable to seed42's −0.063, confirms the batch-size amplification effect is not seed-specific. Paired with bs16_uniform_seed123. Restart of bs16_adaptive_tau07_seed123 which crashed at step 500 due to disk full.\", \"parent\": \"bs16_adaptive_tau07_seed123\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs16_adaptive_tau07_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.7 --num_train_tokens 200000000 --batch_size 16 --n_min 8 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_total_limit 3 --gradient_checkpointing\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"645294\", \"log_path\": \"~/runs/provenance_weight_training/bs16_adaptive_tau07_seed123.log\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"holdout_combined + owt_eval + wiki_eval\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs16_adaptive_tau07_seed123/final\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T23:23:48.322Z\", \"metrics\": {\"holdout_loss\": 2.8688, \"holdout_ppl\": 17.616, \"owt_loss\": 2.9083, \"owt_ppl\": 18.325, \"wiki_loss\": 2.731, \"wiki_ppl\": 15.348}}, \"detect_remove_q05_v2_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T19:01:59.278Z\", \"updated_at\": \"2026-05-21T23:56:51.369Z\", \"hypothesis\": \"D&R hard filtering seed123 replication with CORRECT filtered data (q≤0.5, 153725 samples, 86.4% real). Paired with detect_remove_q05_v2_seed42 for 2-seed consistency.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q05_v2_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 1 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"646037\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q05_v2_seed123.log\", \"submitted_at\": \"2026-05-21T19:02:37.493Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 153725, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"wall_clock_seconds\": 17290.1, \"gpu_hours\": 4.8}, \"parent\": \"detect_remove_q05_v2_seed42\", \"reproduce\": {\"finished_at\": \"2026-05-21T23:19:54.842Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-21T23:20:00.751774+00:00\"}]}, \"metrics\": {\"holdout_loss\": 2.8545, \"holdout_ppl\": 17.3656, \"owt_loss\": 2.9013, \"owt_ppl\": 18.198, \"wiki_loss\": 2.7234, \"wiki_ppl\": 15.2318, \"total_steps\": 24414, \"train_loss\": 2.76}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q05_v2_seed123/final\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q05_v2_seed123.log\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T23:50:47.575Z\", \"failure_reason\": \"配置错误：缺少 --gradient_accumulation_steps 4，effective batch=4 (应为 16)。Metrics 无效。\"}, \"dr_epoch_matched_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T23:05:42.275Z\", \"updated_at\": \"2026-05-21T23:53:23.303Z\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/dr_epoch_matched_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --max_steps 2533 --batch_size 4 --learning_rate 5e-5 --lr_scheduler_type linear --seed 123\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"665830\", \"log_path\": \"~/runs/provenance_weight_training/dr_epoch_matched_seed123.log\", \"submitted_at\": \"2026-05-21T23:05:41.642Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 153725, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"wall_clock_seconds\": 2638.3, \"gpu_hours\": 0.73}, \"hypothesis\": \"Epoch-matched D&R seed123: trains on filtered data (q≤0.5, 153725 samples) for exactly 2533 steps with independent linear LR schedule (5e-5→0). Paired with detect_remove_q05_v2_seed123 (full 24414 steps) to independently quantify epoch confound percentage. If full/epoch-matched PPL gap at seed123 is comparable to seed42's gap (17.285 vs 17.651 = 0.366), confirms epoch confound accounts for >90% of D&R's apparent advantage.\", \"parent\": \"dr_epoch_matched_indep_lr_v2_seed42\", \"reproduce\": {\"finished_at\": \"2026-05-21T23:32:36.344Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-21T23:32:42.223280+00:00\"}]}, \"metrics\": {\"holdout_loss\": 2.9087, \"holdout_ppl\": 18.332, \"owt_loss\": 2.9099, \"owt_ppl\": 18.354, \"wiki_loss\": 2.705, \"wiki_ppl\": 14.955}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/dr_epoch_matched_seed123/final\", \"log_path\": \"~/runs/provenance_weight_training/dr_epoch_matched_seed123.log\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T23:49:39.988Z\", \"failure_reason\": \"配置错误：缺少 --gradient_accumulation_steps 4，effective batch=4 (应为 16)，训练仅看 0.066 epoch (应为 0.264)。PPL 18.332 无效。\"}, \"bs16_uniform_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T18:28:09.678Z\", \"updated_at\": \"2026-05-21T22:58:47.511Z\", \"hypothesis\": \"Uniform baseline at batch_size=16, seed123. Paired with bs16_adaptive_tau07_seed123. If Δ(adaptive−uniform) at bs=16 seed123 is comparable to seed42's −0.063, the batch-size amplification is robust across seeds.\", \"parent\": \"bs16_uniform_seed42\", \"spec\": {\"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"holdout_combined + owt_eval + wiki_eval\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs16_uniform_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 16 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_total_limit 3 --gradient_checkpointing\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"643185\"}, \"reproduce\": {\"finished_at\": \"2026-05-21T22:37:56.489Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-21T22:38:04.855478+00:00\"}]}, \"metrics\": {\"holdout_loss\": 2.8728, \"holdout_ppl\": 17.686, \"owt_loss\": 2.9107, \"owt_ppl\": 18.369, \"wiki_loss\": 2.7332, \"wiki_ppl\": 15.381, \"train_loss\": 1.997}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs16_uniform_seed123/final\", \"log_path\": \"~/runs/provenance_weight_training/bs16_uniform_seed123.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T22:58:47.511Z\"}, \"detect_remove_q05_v2_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T16:27:14.144Z\", \"updated_at\": \"2026-05-21T20:46:41.018Z\", \"hypothesis\": \"D&R hard filtering baseline with CORRECT filtered data (q≤0.5, 153725 samples, 86.4% real). Full 6103-step linear schedule. Paired with adaptive reweighting to compare hard filtering vs soft reweighting approaches. If D&R PPL > adaptive, soft reweighting extracts more value from contaminated data than simply removing it.\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --weighting_method uniform --num_train_tokens 200000000 --seed 42\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"629320\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q05_v2_seed42.log\", \"submitted_at\": \"2026-05-21T16:27:24.071Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 153725, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"holdout_combined + owt_eval + wiki_eval\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q05_v2_seed42/final\", \"wall_clock_seconds\": 15556.9, \"gpu_hours\": 4.32}, \"reproduce\": {\"finished_at\": \"2026-05-21T20:02:25.837Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-21T20:02:31.420557+00:00\"}]}, \"metrics\": {\"holdout_loss\": 2.8499, \"holdout_ppl\": 17.2853, \"owt_loss\": 2.8911, \"owt_ppl\": 18.0139, \"wiki_loss\": 2.7116, \"wiki_ppl\": 15.0528, \"train_loss\": 11, \"total_steps\": 6103}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T20:46:41.018Z\"}, \"bs16_adaptive_tau07_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T18:28:08.369Z\", \"updated_at\": \"2026-05-21T18:56:30.480Z\", \"hypothesis\": \"Batch size sensitivity replication seed123: adaptive weighting with bs=16 (n_min=8) vs bs=4. If Δ(adaptive−uniform) at bs=16 is comparable to seed42's −0.063, confirms the batch-size amplification effect is not seed-specific. Paired with bs16_uniform_seed123.\", \"parent\": \"bs16_adaptive_tau07_seed42\", \"spec\": {\"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"holdout_combined + owt_eval + wiki_eval\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs16_adaptive_tau07_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.7 --num_train_tokens 200000000 --batch_size 16 --n_min 8 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_total_limit 3 --gradient_checkpointing\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"643108\"}, \"reproduce\": {\"finished_at\": \"2026-05-21T18:52:13.181Z\"}, \"failure_reason\": \"Traceback → packages/torch/serialization.py\\\", line 977, in save _save( File \\\"/root/miniconda3/lib/python3.12/site-packages/torch/serialization.py\\\", line 1286, in _save zip_file.write_record(name, storage, num_bytes) RuntimeError: basic_ios::clear: iostream error\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-21T18:52:16.154Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T18:52:23.195151+00:00\"}]}, \"notes\": \"失败原因: 磁盘空间不足 — torch.save(optimizer.state_dict()) 在 step 500 首次 checkpoint 时 IOException (basic_ios::clear: iostream error + enforce fail at inline_container.cc:668, unexpected pos 1513744000 vs 1513743888)。训练本身正常 (loss=2.5, lr=4.834e-05, step 500/6103)。| error_type: resource | 建议: 清理磁盘后重试\"}, \"bs16_uniform_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T14:03:21.016Z\", \"updated_at\": \"2026-05-21T18:24:16.989Z\", \"hypothesis\": \"Uniform baseline at batch_size=16 paired with bs16_adaptive_tau07_seed42. If adaptive Δ (adaptive - uniform) at bs=16 is comparable to bs=4 Δ (−0.020), demonstrates dual-constraint robustness to batch size.\", \"parent\": \"uniform_seed42\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs16_uniform_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 16 --gradient_accumulation_steps 1 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"620563\", \"log_path\": \"~/runs/provenance_weight_training/bs16_uniform_seed42.log\", \"submitted_at\": \"2026-05-21T14:03:35.736Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"models/Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs16_uniform_seed42\", \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"N/A\", \"wall_clock_seconds\": 15641.3, \"gpu_hours\": 4.34}, \"metrics\": {\"holdout_loss\": 2.8732, \"holdout_ppl\": 17.694, \"owt_loss\": 2.9104, \"owt_ppl\": 18.364, \"wiki_loss\": 2.7302, \"wiki_ppl\": 15.337, \"train_loss\": 1.965}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs16_uniform_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/bs16_uniform_seed42.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T18:24:16.990Z\"}, \"bs16_adaptive_tau07_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T13:39:47.600Z\", \"updated_at\": \"2026-05-21T18:04:39.917Z\", \"hypothesis\": \"Adaptive dual-constraint weighting with bs=16 (n_min=8) produces comparable holdout PPL to the bs=4 (n_min=2) main experiment, demonstrating batch size robustness of the dual-constraint mechanism rather than being an artifact of small-batch dynamics.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/bs16_adaptive_tau07_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.7 --num_train_tokens 200000000 --batch_size 16 --gradient_accumulation_steps 1 --n_min 8 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --gradient_checkpointing\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"613352\", \"log_path\": \"~/runs/provenance_weight_training/bs16_adaptive_tau07_seed42.log\", \"submitted_at\": \"2026-05-21T13:40:49.372Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 15333.9, \"gpu_hours\": 4.26}, \"reproduce\": {\"finished_at\": \"2026-05-21T17:52:41.541Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-21T17:52:46.934970+00:00\"}]}, \"metrics\": {\"holdout_loss\": 2.8697, \"holdout_ppl\": 17.631, \"owt_loss\": 2.9074, \"owt_ppl\": 18.309, \"wiki_loss\": 2.7269, \"wiki_ppl\": 15.286, \"train_loss\": 2.537}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/bs16_adaptive_tau07_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/bs16_adaptive_tau07_seed42.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T17:56:23.271Z\"}, \"dr_epoch_matched_indep_lr_v2_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T14:53:05.757Z\", \"updated_at\": \"2026-05-21T17:29:56.453Z\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir .../dr_epoch_matched_indep_lr_v2_seed42 --weighting_method uniform --max_steps 2533 --seed 42\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"623042\", \"log_path\": \"~/runs/provenance_weight_training/dr_epoch_matched_indep_lr_v2_seed42.log\", \"submitted_at\": \"2026-05-21T14:53:05.197Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 153725, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"holdout_combined + owt_eval + wiki_eval\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/dr_epoch_matched_indep_lr_v2_seed42/final\", \"wall_clock_seconds\": 9411.3, \"gpu_hours\": 2.61}, \"hypothesis\": \"D&R epoch-matched with CORRECT filtered data (q≤0.5, 153725 samples, 86.4% real) and independent linear LR schedule (total_steps=2533). Rerun of invalidated dr_epoch_matched_indep_lr_seed42 which used inverted filter (q>0.5, 85% synthetic). Paired with uniform_epoch_matched_indep_lr_seed42 to quantify D&R effectiveness under fair LR comparison.\", \"parent\": \"dr_epoch_matched_indep_lr_seed42\", \"metrics\": {\"holdout_ppl\": 17.65053, \"holdout_loss\": 2.87077, \"ood_owt_ppl\": 18.26112, \"ood_owt_loss\": 2.90477, \"ood_wiki_ppl\": 15.19382, \"ood_wiki_loss\": 2.72089, \"train_loss_final\": 11.11, \"total_steps\": 2533}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T17:29:56.453Z\"}, \"uniform_epoch_matched_indep_lr_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T11:56:06.966Z\", \"updated_at\": \"2026-05-21T17:25:46.073Z\", \"hypothesis\": \"Uniform weighting with epoch-matched training tokens (max_steps=2533) and independent linear LR schedule (5e-5, full decay over 2533 steps) serves as the controlled baseline for LR confound elimination. Paired with dr_epoch_matched_indep_lr_seed42 (PPL=18.78) to quantify pure epoch-matching effect without LR schedule artifacts.\", \"parent\": \"uniform_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/uniform_epoch_matched_indep_lr_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --max_steps 2533 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"606291\", \"log_path\": \"~/runs/provenance_weight_training/uniform_epoch_matched_indep_lr_seed42.log\", \"submitted_at\": \"2026-05-21T12:12:09.108Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/uniform_epoch_matched_indep_lr_seed42/final\", \"wall_clock_seconds\": 18817.0, \"gpu_hours\": 5.23}, \"reproduce\": {\"finished_at\": \"2026-05-21T13:43:41.194Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-21T13:43:49.821951+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"holdout_ppl\": 18.06206, \"holdout_loss\": 2.89381, \"ood_owt_ppl\": 18.64966, \"ood_wiki_ppl\": 15.511, \"train_loss_final\": 8.058, \"total_steps\": 2533}, \"completed_at\": \"2026-05-21T17:25:46.074Z\"}, \"random_reweight_baseline_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T11:47:32.490Z\", \"updated_at\": \"2026-05-21T16:25:30.339Z\", \"hypothesis\": \"Random reweight baseline: shuffling q_scores before computing adaptive weights destroys the detector's contamination signal while preserving the weight distribution shape. If adaptive (PPL=17.674) outperforms random reweight, the detector signal is load-bearing and not just a regularization artifact.\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data_random_shuffle.jsonl --weighting_method adaptive --tau 0.8 --seed 42\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"603550\", \"log_path\": \"~/runs/provenance_weight_training/random_reweight_baseline_seed42.log\", \"submitted_at\": \"2026-05-21T11:48:08.575Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_random_shuffle.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"holdout_combined + owt_eval + wiki_eval\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/random_reweight_baseline_seed42/final\", \"wall_clock_seconds\": 16641.8, \"gpu_hours\": 4.62}, \"metrics\": {\"holdout_ppl\": 17.95829, \"holdout_loss\": 2.88805, \"ood_owt_ppl\": 18.60614, \"ood_owt_loss\": 2.92349, \"ood_wiki_ppl\": 15.51906, \"ood_wiki_loss\": 2.74207}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-21T16:25:30.339Z\"}, \"dr_epoch_matched_indep_lr_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T11:56:34.309Z\", \"updated_at\": \"2026-05-21T14:50:52.460Z\", \"hypothesis\": \"D&R epoch-matched with independent linear LR schedule (total_steps=2533). Eliminates LR schedule confound: previous epoch-matched used 6103-step schedule but stopped at 2533. Paired with uniform_epoch_matched to quantify LR confound magnitude.\", \"parent\": \"detect_remove_q05_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/dr_epoch_matched_indep_lr_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --max_steps 2533 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"605271\", \"log_path\": \"~/runs/provenance_weight_training/dr_epoch_matched_indep_lr_seed42.log\", \"submitted_at\": \"2026-05-21T11:56:42.861Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/dr_epoch_matched_indep_lr_seed42/final\", \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 217774, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"self_trained\", \"eval_data\": \"holdout_combined + owt_eval + wiki_eval\", \"wall_clock_seconds\": 6047.8, \"gpu_hours\": 1.68}, \"conclusion\": \"failed\", \"metrics\": {\"holdout_ppl\": 18.78174, \"holdout_loss\": 2.93288, \"ood_owt_ppl\": 19.23533, \"ood_owt_loss\": 2.95675, \"ood_wiki_ppl\": 15.95958, \"ood_wiki_loss\": 2.77006, \"train_loss_final\": 5.833, \"total_steps\": 2533}, \"completed_at\": \"2026-05-21T13:37:30.667Z\", \"notes\": \"INVALIDATED: scored_data_filtered_q05.jsonl had inverted filter (kept q>0.5 = 85% synthetic instead of q≤0.5 = real data). PPL=18.782 is meaningless. Need to regenerate data and rerun.\"}, \"grid_b0_1_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T00:26:46.904Z\", \"updated_at\": \"2026-05-21T13:43:44.066Z\", \"hypothesis\": \"Grid-b sweep b=0.1 on ρ=0.4 data, seed42. Minimal reweighting — expect PPL close to uniform (~17.694). Establishes lower bound of useful b range.\", \"parent\": \"grid_b_seed42_batch\", \"notes\": \"PPL=17.657, between uniform(17.694) and b=0.3(17.640). b=0.1 provides minimal but positive improvement over uniform, consistent with near-uniform weighting at low b.\", \"server\": \"westd-47453\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-16T05:04:42.502Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_grid_b0_1_seed42.sh\\\"\", \"finished_at\": \"2026-05-16T08:42:41.654Z\", \"training_hours\": 3.63}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_grid_b0_1_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:0\"], \"pid\": \"34704\", \"log_path\": \"~/runs/provenance_weight_training/grid_b0_1_seed42.log\", \"submitted_at\": \"2026-05-17T17:20:25.910Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 332598.2, \"gpu_hours\": 92.39}, \"pid\": \"295096\", \"log_path\": \"~/runs/provenance_weight_training/grid_b0_1_seed42.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T08:42:43.936500+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.657, \"eval_loss_holdout\": 2.871}, \"checkpoint_path\": \"output/models/grid_b0_1_seed42/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T08:59:24.343Z\"}, \"rho02_adaptive_tau08_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:14:42.459Z\", \"updated_at\": \"2026-05-21T13:43:39.791Z\", \"spec\": {\"command\": \"bash -c \\\"cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau08_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:2\"], \"pid\": \"41387\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau08_seed42.log\", \"submitted_at\": \"2026-05-17T18:14:42.195Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/rho02_scored_data.jsonl\", \"data_count\": 50000, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"weighting_method\": \"adaptive\", \"tau\": 0.8, \"rho\": 0.2, \"checkpoint_path\": \"/root/autodl-tmp/output/models/rho02_adaptive_tau08_seed42/final\", \"wall_clock_seconds\": 17407.7, \"gpu_hours\": 4.84}, \"reproduce\": {\"finished_at\": \"2026-05-17T22:19:39.990Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T22:19:47.496007+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"eval_ppl_holdout\": 17.382, \"eval_loss_holdout\": 2.8555, \"eval_holdout_tokens\": 4077068, \"total_steps\": 6103, \"train_runtime_seconds\": 14599, \"vs_rho02_uniform\": \"+0.046 (17.382 vs 17.336)\", \"vs_rho04_uniform\": \"-0.312 (17.382 vs 17.694)\", \"tau\": 0.8, \"rho\": 0.2, \"b_star_pct_zero\": \"40-50%\", \"conclusion_note\": \"worse than same-rho uniform baseline\"}, \"hypothesis\": \"Adaptive weighting with τ=0.8 at ρ=0.2 (low contamination): the dual-constrained algorithm finds meaningful b* even with only 20% contamination, achieving PPL < uniform baseline (17.694), demonstrating proportion-robustness (Claim 3 safe default).\", \"completed_at\": \"2026-05-17T23:04:49.876Z\"}, \"ess_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:51:52.911Z\", \"updated_at\": \"2026-05-21T13:43:15.412Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && bash scripts/run_ess_only_seed123.sh\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"115009\", \"log_path\": \"~/runs/provenance_weight_training/ess_only_seed123.log\", \"submitted_at\": \"2026-05-17T15:31:00.484Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 92291.7, \"gpu_hours\": 25.64}, \"server\": \"westd-47453\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"233872\", \"log_path\": \"~/runs/provenance_weight_training/ess_only_seed123.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/ess_only_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method ess_only --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --logging_steps 10 --save_steps 500 --save_total_limit 3 --save_only_model --bf16\\\"\", \"finished_at\": \"2026-05-15T21:41:11.165Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:41:12.958200+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.72, \"eval_loss_holdout\": 2.8746, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py on data/human/eval_holdout.jsonl, max_docs=5000, stride=1024, fp16\", \"eval_note\": \"Also ran on scored_data.jsonl (train data): ppl=9.66, loss=2.2677, tokens=3029693\", \"train_loss\": 10.2159, \"train_steps\": 6103, \"train_runtime_seconds\": 12959.5, \"b_star_mean\": 3.55, \"b_star_median\": 1.5918, \"b_star_std\": 4.7209, \"b_star_min\": 0.2344, \"b_star_max\": 20, \"b_star_p25\": 0.8398, \"b_star_p75\": 3.8281, \"b_star_p90\": 9.5996, \"b_star_count\": 21971, \"vs_uniform_ppl_delta\": \"+0.034\", \"vs_adaptive_fix_ppl_delta\": \"+0.077\"}, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/ess_only_seed123/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:51:53.436Z\", \"hypothesis\": \"ESS-only adaptive baseline (max-intervention) seed=123: b* = max{b : ESS(b) >= n_min} ignores α_eff quality constraint, applying strongest possible downweighting. Multi-seed validation that dual-constraint (min-intervention) consistently outperforms ESS-only.\"}, \"ess_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:04:39.611Z\", \"updated_at\": \"2026-05-21T13:43:13.392Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && bash scripts/run_ess_only_seed456.sh\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"115513\", \"log_path\": \"~/runs/provenance_weight_training/ess_only_seed456.log\", \"submitted_at\": \"2026-05-17T15:33:24.322Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 92146.3, \"gpu_hours\": 25.6}, \"server\": \"westd-47453\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"pid\": \"233952\", \"log_path\": \"~/runs/provenance_weight_training/ess_only_seed456.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/ess_only_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method ess_only --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --logging_steps 10 --save_steps 500 --save_total_limit 3 --save_only_model --bf16\\\"\", \"finished_at\": \"2026-05-15T21:41:17.276Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:41:21.343173+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.76, \"eval_loss_holdout\": 2.877, \"eval_holdout_tokens\": 4077068, \"train_loss\": 1.9364, \"note\": \"re-eval on westd-41312 latest run (v2)\"}, \"checkpoint_path\": \"output/models/ess_only_seed456/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:51:54.328Z\", \"hypothesis\": \"ESS-only (max-intervention) seed456: b* = max{b : ESS(b) ≥ n_min} — proves dual-constraint adaptive (min-intervention) superior to ESS-only\"}, \"qwen06b_uniform_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T14:59:14.580Z\", \"updated_at\": \"2026-05-21T13:43:11.396Z\", \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp/provenance_weight_training && bash scripts/run_uniform_seed42_v2.sh\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"125995\", \"log_path\": \"/root/runs/provenance_weight_training/qwen06b_uniform_seed42.log\", \"submitted_at\": \"2026-05-17T18:17:17.865Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 50000, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"weighting_method\": \"uniform\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/qwen06b_uniform_seed42_v2/final\", \"wall_clock_seconds\": 14806.2, \"gpu_hours\": 4.11}, \"hypothesis\": \"Uniform baseline retrain (seed42) without inline eval overhead — provides clean PPL baseline for Claim 1/2 comparison and enables lm-eval downstream evaluation on same checkpoint\", \"reproduce\": {\"finished_at\": \"2026-05-17T21:52:18.403Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T21:52:22.072131+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.69, \"eval_loss_holdout\": 2.8733, \"eval_holdout_tokens\": 4077068, \"train_loss\": 1.9882, \"note\": \"v2 run on westd-41312 (no inline eval)\", \"downstream_arc_easy_acc_norm\": 0.6128, \"downstream_arc_challenge_acc_norm\": 0.3481, \"downstream_hellaswag_acc_norm\": 0.4836, \"downstream_piqa_acc_norm\": 0.6877, \"downstream_winogrande_acc\": 0.5856, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\", \"eval_ppl_openwebtext\": 18.365, \"eval_ppl_wikipedia\": 15.335}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T22:24:04.055Z\", \"eval_ppl_openwebtext\": 18.37, \"eval_ppl_wikipedia\": 15.34}, \"rho06_tau07_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T03:11:59.729Z\", \"updated_at\": \"2026-05-21T11:51:18.525Z\", \"hypothesis\": \"τ=0.7 at ρ=0.6 seed456: third seed completing ρ=0.6 τ=0.7 3-seed set. Together with seed42 and seed123, enables paired comparison against ρ=0.6 τ=0.8 to confirm τ=0.7 universality across contamination levels.\", \"parent\": \"rho06_tau07_seed42\", \"spec\": {\"command\": \"killed\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"603064\", \"log_path\": \"~/runs/provenance_weight_training/rho06_tau07_seed456.log\", \"submitted_at\": \"2026-05-21T11:47:34.773Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"N/A\", \"wall_clock_seconds\": 223.8, \"gpu_hours\": 0.06}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-21T11:51:18.525Z\"}, \"rho06_tau07_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T03:11:57.382Z\", \"updated_at\": \"2026-05-21T11:50:47.350Z\", \"hypothesis\": \"τ=0.7 at ρ=0.6 seed123: second seed replicating τ=0.7 advantage over τ=0.8 at higher contamination (ρ=0.6). Together with seed42 and seed456, enables paired comparison to confirm τ=0.7 universality across contamination levels.\", \"parent\": \"rho06_tau07_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/rho06_tau07_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --tau 0.7 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"601860\", \"log_path\": \"~/runs/provenance_weight_training/rho06_tau07_seed123.log\", \"submitted_at\": \"2026-05-21T11:28:57.474Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"N/A\", \"wall_clock_seconds\": 1309.9, \"gpu_hours\": 0.36}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-21T11:50:47.350Z\"}, \"ngram_adaptive_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:14:23.226Z\", \"updated_at\": \"2026-05-21T10:45:11.511Z\", \"hypothesis\": \"Multi-detector validation: adaptive weighting with n-gram PPL detector (statistical, AUC=0.73) produces lower PPL than uniform, demonstrating method works with fundamentally different detector type (not just neural classifier). Complementary to q_score (Spearman r=-0.36). Part of D079 Line A.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --model_name models/Qwen/Qwen3-0.6B --data_path data/scored_data_ngram_qscore.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/ngram_adaptive_seed42 --weighting_method adaptive --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --bf16 --save_only_model --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"226953\", \"log_path\": \"~/runs/provenance_weight_training/ngram_adaptive_seed42.log\", \"submitted_at\": \"2026-05-18T15:01:02.239Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/ngram_adaptive_seed42/final\", \"train_loss\": 9.298, \"train_runtime_s\": 14170, \"total_steps\": 6103, \"wall_clock_seconds\": 14810.3, \"gpu_hours\": 4.11}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T19:07:52.563Z\", \"metrics\": {\"holdout_ppl\": 17.820214, \"holdout_loss\": 2.880333}}, \"gpt2_adaptive_seed456_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:59:23.805Z\", \"updated_at\": \"2026-05-21T10:28:12.735Z\", \"hypothesis\": \"GPT-2 PPL detector (AUC=0.913) + adaptive weighting, seed=456. V2: from-scratch rerun after disk crash (original used --save_only_model, no optimizer for resume). No --save_only_model, no inline eval.\", \"parent\": \"gpt2_adaptive_seed42\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --seed 456 --data_path data/scored_data_gpt2ppl_qscore.jsonl (from scratch, no --save_only_model)\", \"server\": \"westd-41312\", \"gpu\": \"cuda:3\", \"pid\": \"569718\", \"log_path\": \"~/runs/provenance_weight_training/gpt2_adaptive_seed456_v2.log\", \"submitted_at\": \"2026-05-21T05:00:04.331Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_gpt2ppl_qscore.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"N/A (post-hoc eval)\", \"output_dir\": \"/root/autodl-tmp/provenance_weight_training/output/models/gpt2_adaptive_seed456_v2\", \"detector\": \"GPT-2 PPL (AUC=0.913)\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/gpt2_adaptive_seed456_v2/final\", \"wall_clock_seconds\": 18020.3, \"gpu_hours\": 5.01}, \"conclusion\": \"success\", \"metrics\": {\"holdout_ppl\": 17.79719, \"holdout_loss\": 2.87904}, \"completed_at\": \"2026-05-21T10:00:24.591Z\"}, \"adaptive_tau08_scratch_seed42_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:59:19.444Z\", \"updated_at\": \"2026-05-21T10:28:11.715Z\", \"hypothesis\": \"From-scratch adaptive (τ=0.8, ρ=0.4, n_min=2, seed=42, Qwen3-0.6B). V3: resume from v2 checkpoint-500 (has optimizer state). No --save_only_model, no inline eval.\", \"parent\": \"adaptive_tau08_scratch_seed42_v2\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --seed 42 --data_path data/scored_data.jsonl --resume_from_checkpoint v2/checkpoint-500 (has optimizer, no --save_only_model)\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": \"569244\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_tau08_scratch_seed42_v3.log\", \"submitted_at\": \"2026-05-21T04:59:56.230Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"resume_from_v2_checkpoint-500_with_optimizer\", \"eval_data\": \"N/A (post-hoc eval)\", \"output_dir\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_tau08_scratch_seed42_v2\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_tau08_scratch_seed42_v2/final\", \"wall_clock_seconds\": 18022.2, \"gpu_hours\": 5.01}, \"conclusion\": \"success\", \"metrics\": {\"holdout_ppl\": 17.6885, \"holdout_loss\": 2.87291, \"ood_owt_ppl\": 18.37026, \"ood_owt_loss\": 2.91073, \"ood_wiki_ppl\": 15.34964, \"ood_wiki_loss\": 2.73109, \"ood_eval_source\": \"eval_results/ pipeline\"}, \"completed_at\": \"2026-05-21T10:00:18.388Z\"}, \"ngram_adaptive_seed456_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:59:22.350Z\", \"updated_at\": \"2026-05-21T10:27:02.278Z\", \"hypothesis\": \"N-gram PPL detector (AUC=0.73) + adaptive weighting, seed=456. V2: from-scratch rerun after disk crash. No --save_only_model, no inline eval.\", \"parent\": \"ngram_adaptive_seed42\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --seed 456 --data_path data/scored_data_ngram_qscore.jsonl (from scratch, no --save_only_model)\", \"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"pid\": \"569464\", \"log_path\": \"~/runs/provenance_weight_training/ngram_adaptive_seed456_v2.log\", \"submitted_at\": \"2026-05-21T05:00:01.488Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_ngram_qscore.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"N/A (post-hoc eval)\", \"output_dir\": \"/root/autodl-tmp/provenance_weight_training/output/models/ngram_adaptive_seed456_v2\", \"detector\": \"N-gram PPL (AUC=0.73)\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/ngram_adaptive_seed456_v2/final\", \"wall_clock_seconds\": 18021.1, \"gpu_hours\": 5.01}, \"conclusion\": \"success\", \"metrics\": {\"holdout_ppl\": 17.82607, \"holdout_loss\": 2.88066}, \"completed_at\": \"2026-05-21T10:00:22.602Z\"}, \"gpt2_adaptive_seed123_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:59:21.265Z\", \"updated_at\": \"2026-05-21T10:27:00.177Z\", \"hypothesis\": \"GPT-2 PPL detector (AUC=0.913) + adaptive weighting, seed=123. V3: resume from v2 checkpoint-500 (has optimizer state). No --save_only_model, no inline eval.\", \"parent\": \"gpt2_adaptive_seed42\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --seed 123 --data_path data/scored_data_gpt2ppl_qscore.jsonl --resume_from_checkpoint v2/checkpoint-500 (has optimizer, no --save_only_model)\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"pid\": \"569321\", \"log_path\": \"~/runs/provenance_weight_training/gpt2_adaptive_seed123_v3.log\", \"submitted_at\": \"2026-05-21T04:59:58.685Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_gpt2ppl_qscore.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"resume_from_v2_checkpoint-500_with_optimizer\", \"eval_data\": \"N/A (post-hoc eval)\", \"output_dir\": \"/root/autodl-tmp/provenance_weight_training/output/models/gpt2_adaptive_seed123_v2\", \"detector\": \"GPT-2 PPL (AUC=0.913)\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/gpt2_adaptive_seed123_v2/final\", \"wall_clock_seconds\": 18021.8, \"gpu_hours\": 5.01}, \"conclusion\": \"success\", \"metrics\": {\"holdout_ppl\": 17.78848, \"holdout_loss\": 2.87855}, \"completed_at\": \"2026-05-21T10:00:20.515Z\"}, \"gpt2_adaptive_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T00:44:29.948Z\", \"updated_at\": \"2026-05-21T04:59:11.372Z\", \"hypothesis\": \"GPT-2 PPL detector (AUC=0.913) + adaptive weighting, seed=456. Third seed for detector ablation to complete 3-seed set with gpt2_adaptive_seed42 (PPL=17.79) and gpt2_adaptive_seed123. Tests reproducibility of method with medium-quality detector.\", \"parent\": \"gpt2_adaptive_seed42\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --seed 456 --data_path data/scored_data_gpt2ppl_qscore.jsonl (no inline eval)\", \"server\": \"westd-41312\", \"gpu\": \"cuda:3\", \"pid\": \"551638\", \"log_path\": \"~/runs/provenance_weight_training/gpt2_adaptive_seed456.log\", \"data_path\": \"data/scored_data_gpt2ppl_qscore.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"output_dir\": \"/root/autodl-tmp/provenance_weight_training/output/models/gpt2_adaptive_seed456\", \"detector\": \"GPT-2 PPL (AUC=0.913)\", \"eval_data\": \"N/A (training experiment, not eval)\", \"checkpoint_path\": \"N/A (disk full crash, checkpoint-5500 has no optimizer)\"}, \"conclusion\": \"failed\", \"failure_reason\": \"Disk 100% full — training crashed at step 6000/6103, checkpoint-6000 corrupted (36KB), checkpoint-5500 has no optimizer (--save_only_model)\", \"completed_at\": \"2026-05-21T04:59:11.372Z\"}, \"ngram_adaptive_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T04:13:00.621Z\", \"updated_at\": \"2026-05-21T04:59:09.364Z\", \"hypothesis\": \"N-gram PPL detector (statistical, AUC=0.73) + adaptive weighting, seed=456. Third seed completing 3-seed set for detector ablation. Tests consistency with ngram_adaptive_seed42 (PPL=17.82) and ngram_adaptive_seed123.\", \"parent\": \"ngram_adaptive_seed42\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --seed 456 --data_path data/scored_data_ngram_qscore.jsonl (from scratch, no --save_only_model, no inline eval)\", \"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"pid\": \"566782\", \"log_path\": \"~/runs/provenance_weight_training/ngram_adaptive_seed456.log\", \"submitted_at\": \"2026-05-21T04:13:52.043Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_ngram_qscore.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"N/A (training, post-hoc eval via eval_results/ pipeline)\", \"output_dir\": \"/root/autodl-tmp/provenance_weight_training/output/models/ngram_adaptive_seed456\", \"detector\": \"N-gram PPL (AUC=0.73)\", \"checkpoint_path\": \"N/A (disk full crash, no valid checkpoint)\", \"wall_clock_seconds\": 2717.3, \"gpu_hours\": 0.75}, \"conclusion\": \"failed\", \"failure_reason\": \"Disk 100% full — training crashed at checkpoint write, no valid checkpoint to resume\", \"completed_at\": \"2026-05-21T04:59:09.364Z\"}, \"gpt2_adaptive_seed123_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:54:05.914Z\", \"updated_at\": \"2026-05-21T04:59:07.344Z\", \"hypothesis\": \"GPT-2 PPL detector (AUC=0.913) + adaptive weighting, seed=123. V2: rerun without --save_only_model. Replaces corrupted gpt2_adaptive_seed123 (resume caused optimizer loss). Second seed for detector ablation to confirm gpt2_adaptive_seed42 pattern (PPL=17.79).\", \"parent\": \"gpt2_adaptive_seed42\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --seed 123 --data_path data/scored_data_gpt2ppl_qscore.jsonl (from scratch, no --save_only_model, no inline eval)\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"pid\": \"565346\", \"log_path\": \"~/runs/provenance_weight_training/gpt2_adaptive_seed123_v2.log\", \"submitted_at\": \"2026-05-21T03:55:09.934Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_gpt2ppl_qscore.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"N/A (training, post-hoc eval via eval_results/ pipeline)\", \"output_dir\": \"/root/autodl-tmp/provenance_weight_training/output/models/gpt2_adaptive_seed123_v2\", \"detector\": \"GPT-2 PPL (AUC=0.913)\", \"checkpoint_path\": \"N/A (disk full crash)\", \"wall_clock_seconds\": 3837.4, \"gpu_hours\": 1.07}, \"conclusion\": \"failed\", \"failure_reason\": \"Disk 100% full — training crashed at checkpoint write\", \"completed_at\": \"2026-05-21T04:59:07.344Z\"}, \"adaptive_tau08_scratch_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-21T03:54:03.912Z\", \"updated_at\": \"2026-05-21T04:59:05.334Z\", \"hypothesis\": \"From-scratch adaptive (τ=0.8, ρ=0.4, n_min=2, seed=42, Qwen3-0.6B). V2: rerun without --save_only_model to preserve optimizer state. Replaces corrupted adaptive_tau08_scratch_seed42 (resume caused optimizer loss). Completes 3-seed from-scratch set for τ=0.8 OOD comparison.\", \"parent\": \"adaptive_tau08_scratch_seed42\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --seed 42 --data_path data/scored_data.jsonl (from scratch, no --save_only_model, no inline eval)\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": \"565269\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_tau08_scratch_seed42_v2.log\", \"submitted_at\": \"2026-05-21T03:55:07.498Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"N/A (training, post-hoc eval via eval_results/ pipeline)\", \"output_dir\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_tau08_scratch_seed42_v2\", \"checkpoint_path\": \"N/A (disk full crash)\", \"wall_clock_seconds\": 3837.8, \"gpu_hours\": 1.07}, \"conclusion\": \"failed\", \"failure_reason\": \"Disk 100% full — training crashed at checkpoint write\", \"completed_at\": \"2026-05-21T04:59:05.334Z\"}, \"gpt2_adaptive_seed123\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-20T18:34:08.013Z\", \"updated_at\": \"2026-05-21T03:54:55.606Z\", \"hypothesis\": \"GPT-2 PPL detector (AUC=0.913) + adaptive weighting, seed=123. Second seed for detector ablation to confirm gpt2_adaptive_seed42 pattern (PPL=17.79, worse than TF-IDF but still meaningful reweighting). If consistent, supports claim that method works across detector quality levels.\", \"parent\": \"gpt2_adaptive_seed42\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-20T18:34:25.885Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_gpt2ppl_qscore.jsonl --eval_data_path data/human/eval_holdout.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/gpt2_adaptive_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --eval_steps 500 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"finished_at\": \"2026-05-21T00:35:49.664Z\", \"training_hours\": 6.02}, \"failure_reason\": \"Resume from --save_only_model checkpoint caused optimizer state loss. Adam reinitialized → model degraded. Results invalid.\", \"completed_at\": \"2026-05-21T00:35:54.270Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T00:36:02.306636+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --seed 123 --data_path data/scored_data_gpt2ppl_qscore.jsonl --resume_from_checkpoint checkpoint-2500 (no inline eval)\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"pid\": \"551137\", \"log_path\": \"~/runs/provenance_weight_training/gpt2_adaptive_seed123.log\", \"data_path\": \"data/scored_data_gpt2ppl_qscore.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"resume_from_checkpoint-2500\", \"output_dir\": \"/root/autodl-tmp/provenance_weight_training/output/models/gpt2_adaptive_seed123\", \"detector\": \"GPT-2 PPL (AUC=0.913)\", \"resume_note\": \"Resumed from checkpoint-2500 after timeout (6h). Removed --eval_data_path and --eval_steps to eliminate inline eval overhead (~43min/eval). Remaining ~3603 steps, ~2.3h.\", \"eval_data\": \"N/A (training experiment, not eval)\", \"checkpoint_path\": \"N/A (corrupted by optimizer loss)\"}, \"conclusion\": \"failed\"}, \"adaptive_tau08_scratch_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-20T17:17:50.273Z\", \"updated_at\": \"2026-05-21T03:54:53.604Z\", \"hypothesis\": \"From-scratch adaptive (τ=0.8, ρ=0.4, n_min=2, seed=42, Qwen3-0.6B). Replaces resume-checkpoint adaptive_fix_seed42 to complete 3-seed from-scratch set with adaptive_ood_seed123/456. Enables symmetric 3-seed OOD comparison: τ=0.7 3-seed vs τ=0.8 3-seed.\", \"parent\": \"adaptive_fix_seed42\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-20T17:18:30.262Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --eval_data_path data/human/eval_holdout.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/adaptive_tau08_scratch_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --eval_steps 500 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"finished_at\": \"2026-05-21T01:18:39.252Z\", \"training_hours\": 8.0}, \"failure_reason\": \"Resume from --save_only_model checkpoint caused optimizer state loss. Adam reinitialized → model degraded. Holdout PPL=17.905 (expected ~17.65). Results invalid.\", \"completed_at\": \"2026-05-21T01:18:42.560Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-21T01:18:47.652176+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --seed 42 --data_path data/scored_data.jsonl --resume_from_checkpoint checkpoint-3500 (no inline eval)\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": \"553579\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_tau08_scratch_seed42.log\", \"submitted_at\": \"2026-05-21T01:21:15.351Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"resume_from_checkpoint-3500\", \"eval_data\": \"N/A (training experiment, eval post-training via eval_results/ pipeline)\", \"output_dir\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_tau08_scratch_seed42\", \"resume_note\": \"Resumed from checkpoint-3500 after timeout (8h). Removed --eval_data_path and --eval_steps to eliminate inline eval overhead. Remaining ~2603 steps, ~1.6h.\", \"checkpoint_path\": \"N/A (corrupted by optimizer loss)\", \"wall_clock_seconds\": 9218.3, \"gpu_hours\": 2.56}, \"conclusion\": \"failed\"}, \"ngram_adaptive_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T22:16:21.156Z\", \"updated_at\": \"2026-05-21T02:19:10.605Z\", \"hypothesis\": \"N-gram PPL detector (statistical, AUC=0.73) + adaptive weighting, seed=123. Second seed for detector ablation to confirm ngram_adaptive_seed42 pattern (PPL=17.82). Tests consistency of method with weak statistical detector.\", \"parent\": \"ngram_adaptive_seed42\", \"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-20T22:16:55.814Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data_ngram_qscore.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/ngram_adaptive_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"finished_at\": \"2026-05-21T02:12:31.315Z\", \"training_hours\": 3.93}, \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --seed 123 --data_path data/scored_data_ngram_qscore.jsonl\", \"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"pid\": \"543911\", \"log_path\": \"~/runs/provenance_weight_training/ngram_adaptive_seed123.log\", \"data_path\": \"data/scored_data_ngram_qscore.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"from_scratch\", \"output_dir\": \"/root/autodl-tmp/provenance_weight_training/output/models/ngram_adaptive_seed123\", \"detector\": \"N-gram PPL (AUC=0.73)\"}, \"pid\": \"543911\", \"log_path\": \"~/runs/provenance_weight_training/ngram_adaptive_seed123.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-21T02:12:36.538125+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.823, \"eval_loss_holdout\": 2.8805, \"eval_holdout_tokens\": 4077068, \"train_loss\": 9.289, \"total_steps\": 6103}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/ngram_adaptive_seed123/final\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-21T02:19:10.606Z\"}, \"adaptive_1_7b_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:55:35.805Z\", \"updated_at\": \"2026-05-20T22:15:23.125Z\", \"hypothesis\": \"Adaptive (dual-constrained) at 1.7B model scale (seed=456, τ=0.8, ρ=0.4). From-scratch on westd-41312 cuda:3. Replicates adaptive_1_7b_seed42_v5 (PPL=13.27) with different seed for 3-seed error bars. Paired with uniform_1_7b_seed456.\", \"parent\": \"adaptive_1_7b_seed42_v5\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed456 --model_name models/Qwen/Qwen3-1.7B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": \"cuda:3\", \"pid\": \"494706\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_1_7b_seed456.log\", \"submitted_at\": \"2026-05-20T16:00:18.071Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-1.7B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"data/scored_data.jsonl (training, holdout eval built-in)\", \"wall_clock_seconds\": 21302.6, \"gpu_hours\": 5.92}, \"reproduce\": {\"finished_at\": \"2026-05-20T21:09:28.993Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T21:09:34.067656+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 13.2668, \"eval_ppl_openwebtext\": 13.292, \"eval_ppl_wikipedia\": 10.947, \"downstream_arc_easy_acc_norm\": 0.7146, \"downstream_arc_challenge_acc_norm\": 0.4352, \"downstream_hellaswag_acc_norm\": 0.6133, \"downstream_piqa_acc_norm\": 0.7443, \"downstream_winogrande_acc\": 0.6219, \"downstream_mean\": 0.6259, \"ood_eval_source\": \"eval_results/ pipeline\"}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed456/final\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_1_7b_seed456.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T21:55:20.639Z\"}, \"uniform_1_7b_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T15:55:34.483Z\", \"updated_at\": \"2026-05-20T21:37:05.685Z\", \"hypothesis\": \"Uniform baseline at 1.7B model scale (seed=456). From-scratch on westd-41312 cuda:2. Replicates uniform_1_7b_seed42_v5 (PPL=13.28) with different seed for 3-seed error bars. Paired with adaptive_1_7b_seed456.\", \"parent\": \"uniform_1_7b_seed42_v5\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed456 --model_name models/Qwen/Qwen3-1.7B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"pid\": \"494625\", \"log_path\": \"~/runs/provenance_weight_training/uniform_1_7b_seed456.log\", \"submitted_at\": \"2026-05-20T16:00:15.101Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-1.7B\", \"seed\": 456, \"checkpoint_source\": \"from_scratch\", \"eval_data\": \"data/scored_data.jsonl (training, holdout eval built-in)\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed456/final\", \"wall_clock_seconds\": 20190.8, \"gpu_hours\": 5.61}, \"reproduce\": {\"finished_at\": \"2026-05-20T20:54:45.983Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-20T20:54:54.034865+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 13.28, \"eval_loss_holdout\": 2.5863, \"train_loss_final\": 7.537, \"total_steps\": 6103, \"num_eval_tokens\": 4077068, \"eval_ppl_openwebtext\": 13.307, \"eval_ppl_wikipedia\": 10.953, \"downstream_arc_easy_acc_norm\": 0.7113, \"downstream_arc_challenge_acc_norm\": 0.4224, \"downstream_hellaswag_acc_norm\": 0.6132, \"downstream_piqa_acc_norm\": 0.7448, \"downstream_winogrande_acc\": 0.6251, \"downstream_mean\": 0.6234}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T21:36:45.857Z\"}, \"adaptive_ood_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T14:34:31.061Z\", \"updated_at\": \"2026-05-20T17:56:20.991Z\", \"hypothesis\": \"Retrain adaptive (τ=0.8, n_min=2, seed=456) with checkpoint saving for OOD eval. If in-dist PPL matches original 17.657 (±0.01), the checkpoint is valid for OOD generalization testing across OpenWebText/Wikipedia/FineWeb.\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --seed 456\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"pid\": 313296, \"log_path\": \"~/runs/provenance_weight_training/adaptive_ood_seed456.log\", \"submitted_at\": \"2026-05-19T14:37:05.986Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 6103, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"wall_clock_seconds\": 14843.0, \"gpu_hours\": 4.12}, \"reproduce\": {\"finished_at\": \"2026-05-19T18:26:26.904Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T18:26:32.576132+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.683, \"eval_ppl_openwebtext\": 18.366, \"eval_ppl_wikipedia\": 15.345, \"downstream_arc_easy_acc_norm\": 0.6077, \"downstream_arc_challenge_acc_norm\": 0.3541, \"downstream_hellaswag_acc_norm\": 0.48, \"downstream_piqa_acc_norm\": 0.6806, \"downstream_winogrande_acc\": 0.5714, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\"}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_ood_seed456/final\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_ood_seed456.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T18:44:28.974Z\"}, \"adaptive_ood_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T14:34:29.354Z\", \"updated_at\": \"2026-05-20T17:56:19.865Z\", \"hypothesis\": \"Retrain adaptive (τ=0.8, n_min=2, seed=123) with checkpoint saving for OOD eval. If in-dist PPL matches original 17.643 (±0.01), the checkpoint is valid for OOD generalization testing across OpenWebText/Wikipedia/FineWeb.\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --seed 123\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": 313217, \"log_path\": \"~/runs/provenance_weight_training/adaptive_ood_seed123.log\", \"submitted_at\": \"2026-05-19T14:37:03.655Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 6103, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"wall_clock_seconds\": 14843.5, \"gpu_hours\": 4.12}, \"reproduce\": {\"finished_at\": \"2026-05-19T18:26:12.673Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T18:26:17.460395+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.677, \"eval_ppl_openwebtext\": 18.373, \"eval_ppl_wikipedia\": 15.37, \"downstream_arc_easy_acc_norm\": 0.6301, \"downstream_arc_challenge_acc_norm\": 0.3481, \"downstream_hellaswag_acc_norm\": 0.4791, \"downstream_piqa_acc_norm\": 0.6844, \"downstream_winogrande_acc\": 0.5706, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\"}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_ood_seed123/final\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_ood_seed123.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T18:44:27.165Z\"}, \"uniform_1_7b_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:09:34.029Z\", \"updated_at\": \"2026-05-20T17:56:18.709Z\", \"hypothesis\": \"Uniform baseline at 1.7B model scale (seed=123). From-scratch on westd-41312 cuda:0. Replicates uniform_1_7b_seed42_v5 (PPL=13.28) with different seed for 3-seed error bars. Paired with adaptive_1_7b_seed123 for scaling claim.\", \"spec\": {\"command\": \"train uniform_1_7b_seed123\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"260414\", \"log_path\": \"~/runs/provenance_weight_training/uniform_1_7b_seed123.log\", \"submitted_at\": \"2026-05-18T23:09:43.550Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/human\", \"data_count\": 5000, \"model_name\": \"1.7B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed123/final\", \"wall_clock_seconds\": 18333.0, \"gpu_hours\": 5.09}, \"reproduce\": {\"finished_at\": \"2026-05-19T04:03:50.026Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T04:03:54.802765+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 13.2648, \"eval_loss_holdout\": 2.5851, \"train_loss_final\": 7.557, \"total_steps\": 6103, \"num_eval_tokens\": 4077068, \"eval_ppl_openwebtext\": 13.2918, \"eval_ppl_wikipedia\": 10.942, \"downstream_arc_easy_acc_norm\": 0.726, \"downstream_arc_challenge_acc_norm\": 0.4317, \"downstream_hellaswag_acc_norm\": 0.6118, \"downstream_piqa_acc_norm\": 0.7454, \"downstream_winogrande_acc\": 0.6133, \"downstream_mean\": 0.6256}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T04:15:16.584Z\"}, \"adaptive_fix_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:32:31.779Z\", \"updated_at\": \"2026-05-20T17:16:11.079Z\", \"hypothesis\": \"D012 n_min fix (3→2, batch_size//2): adaptive b* with corrected ESS constraint maintains or improves seed456 performance (baseline adaptive PPL=17.64, uniform PPL=17.70)\", \"parent\": \"adaptive_seed456\", \"notes\": \"最终清理后重提交。从 checkpoint-1000 恢复，无 inline eval。PID=127285\", \"spec\": {\"n_min\": 2, \"tau\": 0.8}, \"server\": \"westd-47453\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"pid\": \"115066\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_fix_seed456.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --eval_data_path data/human/eval_holdout.jsonl --output_dir output/models/adaptive_fix_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --eval_steps 500 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"finished_at\": \"2026-05-14T21:00:17.106Z\"}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T17:38:47.164099+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T21:00:18.079813+00:00\"}]}, \"metrics\": {\"b_star_count\": 26396, \"b_star_max\": 20, \"b_star_mean\": 1.416, \"b_star_median\": 0.88, \"b_star_min\": 0, \"b_star_note\": \"Training-only records (eval checkpoint records with b*=0 excluded)\", \"b_star_p25\": 0.54, \"b_star_p75\": 1.52, \"b_star_pct_0.5_to_1\": 35.7, \"b_star_pct_1_to_2\": 27.3, \"b_star_pct_above_2\": 16.1, \"b_star_pct_below_0.5\": 20.9, \"b_star_std\": 1.993, \"eval_holdout_tokens\": 4077068, \"eval_loss_holdout\": 2.8711, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.66/4077068\", \"eval_ppl_holdout\": 17.6566, \"eval_tokens\": 4077068, \"total_steps\": 6103, \"train_loss\": 8.3124, \"train_runtime\": 11436.05, \"train_samples_per_second\": 8.539, \"train_steps_per_second\": 0.534, \"ood_note\": \"OOD eval not available — checkpoint on decommissioned westd-47453; adaptive_ood_seed456 has OOD from from-scratch retrain\"}, \"checkpoint_path\": \"output/models/adaptive_fix_seed456/final\"}, \"adaptive_fix_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:32:31.409Z\", \"updated_at\": \"2026-05-20T17:16:06.137Z\", \"hypothesis\": \"D012 n_min fix (3→2, batch_size//2): adaptive b* with corrected ESS constraint maintains or improves seed123 performance (baseline adaptive PPL=17.63, uniform PPL=17.69)\", \"parent\": \"adaptive_seed123\", \"notes\": \"最终清理后重提交。从 checkpoint-1500 恢复，无 inline eval。PID=126944\", \"failure_reason\": \"\", \"conclusion\": \"success\", \"spec\": {\"contamination_ratio\": 0.4, \"tau\": 0.8, \"batch_size\": 4}, \"reproduce\": {\"finished_at\": \"2026-05-14T20:41:22.910Z\"}, \"completed_at\": \"\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T17:38:38.735034+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T20:41:26.828424+00:00\"}]}, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/adaptive_fix_seed123/final\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_fix_seed123.log\", \"metrics\": {\"b_star_count\": 25906, \"b_star_max\": 20, \"b_star_mean\": 1.431, \"b_star_median\": 0.88, \"b_star_min\": 0, \"b_star_note\": \"Training-only records (eval checkpoint records with b*=0 excluded)\", \"b_star_p25\": 0.54, \"b_star_p75\": 1.52, \"b_star_pct_0.5_to_1\": 35.7, \"b_star_pct_1_to_2\": 27.3, \"b_star_pct_2_to_5\": 6.3, \"b_star_pct_above_2\": 16.1, \"b_star_pct_above_5\": 1.9, \"b_star_pct_below_0.5\": 20.9, \"b_star_std\": 2.029, \"epoch\": 0.26, \"eval_holdout_tokens\": 4077068, \"eval_loss\": 2.8704, \"eval_loss_holdout\": 2.8704, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.643/4077068\", \"eval_ppl_holdout\": 17.6432, \"eval_tokens\": 4077068, \"total_steps\": 6103, \"train_loss_weighted\": 7.517, \"train_runtime_s\": 10347, \"ood_note\": \"OOD eval not available — checkpoint on decommissioned westd-47453; adaptive_ood_seed123 has OOD from from-scratch retrain\"}}, \"uniform_1_7b_seed42_v5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:51:09.912Z\", \"updated_at\": \"2026-05-20T16:42:48.020Z\", \"hypothesis\": \"Uniform baseline at 1.7B model scale (seed=42). From-scratch on westd-41312 cuda:0. v5 replaces v4 (disk full at step 500). 176GB available after cleanup.\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-20T08:52:12.203Z\"}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed42_v5 --model_name models/Qwen/Qwen3-1.7B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": 453123, \"log_path\": \"~/runs/provenance_weight_training/uniform_1_7b_seed42_v5.log\", \"submitted_at\": \"2026-05-20T08:52:46.196Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"N/A (from-scratch training)\", \"eval_data\": \"N/A (training experiment)\", \"wall_clock_seconds\": 19145.3, \"gpu_hours\": 5.32}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed42_v5/final\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 7.56, \"total_steps\": 6103, \"train_runtime_s\": 17630, \"eval_ppl_holdout\": 13.28, \"eval_ppl_openwebtext\": 13.291, \"eval_ppl_wikipedia\": 10.919, \"downstream_arc_easy_acc_norm\": 0.7235, \"downstream_arc_challenge_acc_norm\": 0.4334, \"downstream_hellaswag_acc_norm\": 0.6107, \"downstream_piqa_acc_norm\": 0.7432, \"downstream_winogrande_acc\": 0.6172, \"downstream_mean\": 0.6256, \"ood_eval_source\": \"eval_results/ pipeline\"}, \"completed_at\": \"2026-05-20T14:11:51.458Z\", \"eval_ppl_openwebtext\": 13.291, \"eval_ppl_wikipedia\": 10.919}, \"adaptive_1_7b_seed42_v5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T08:51:11.055Z\", \"updated_at\": \"2026-05-20T16:42:46.317Z\", \"hypothesis\": \"Adaptive (dual-constrained) at 1.7B model scale (seed=42, τ=0.8, ρ=0.4). From-scratch on westd-41312 cuda:1. v5 replaces v4 (disk full at step 500). Paired with uniform_1_7b_seed42_v5 for scaling claim.\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-20T08:52:14.451Z\"}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed42_v5 --model_name models/Qwen/Qwen3-1.7B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"pid\": 453200, \"log_path\": \"~/runs/provenance_weight_training/adaptive_1_7b_seed42_v5.log\", \"submitted_at\": \"2026-05-20T08:52:48.288Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"N/A (from-scratch training)\", \"eval_data\": \"N/A (training experiment)\", \"wall_clock_seconds\": 19145.2, \"gpu_hours\": 5.32}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed42_v5/final\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 9.139, \"total_steps\": 6103, \"train_runtime_s\": 18540, \"eval_ppl_holdout\": 13.27, \"eval_ppl_openwebtext\": 13.282, \"eval_ppl_wikipedia\": 10.955, \"downstream_arc_easy_acc_norm\": 0.7176, \"downstream_arc_challenge_acc_norm\": 0.4403, \"downstream_hellaswag_acc_norm\": 0.6164, \"downstream_piqa_acc_norm\": 0.7443, \"downstream_winogrande_acc\": 0.6069, \"downstream_mean\": 0.6251, \"ood_eval_source\": \"eval_results/ pipeline\"}, \"completed_at\": \"2026-05-20T14:11:53.445Z\", \"eval_ppl_openwebtext\": 13.282, \"eval_ppl_wikipedia\": 10.955}, \"adaptive_1_7b_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:54:50.927Z\", \"updated_at\": \"2026-05-20T16:41:38.288Z\", \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --model_name models/Qwen/Qwen3-1.7B --data_path data/scored_data.jsonl --output_dir .../adaptive_1_7b_seed123 --weighting_method adaptive --tau 0.8 --n_min 2 --seed 123 --batch_size 4 --gradient_accumulation_steps 4 --num_train_tokens 200000000\", \"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"pid\": 248439, \"log_path\": \"~/runs/provenance_weight_training/adaptive_1_7b_seed123.log\", \"submitted_at\": \"2026-05-18T19:54:50.523Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-1.7B\", \"seed\": 123, \"wall_clock_seconds\": 19292.5, \"gpu_hours\": 5.36}, \"hypothesis\": \"Adaptive (dual-constrained) at 1.7B model scale (seed=123, τ=0.8, ρ=0.4). From-scratch on westd-41312 cuda:1. Replicates adaptive_1_7b_seed42_v5 (PPL=13.27) with different seed for 3-seed error bars. Paired with uniform_1_7b_seed123.\", \"reproduce\": {\"finished_at\": \"2026-05-19T01:05:21.708Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T01:05:28.647322+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 13.25, \"eval_loss_holdout\": 2.5843, \"eval_ppl_openwebtext\": 13.2909, \"eval_ppl_wikipedia\": 10.9521, \"downstream_arc_easy_acc_norm\": 0.7138, \"downstream_arc_challenge_acc_norm\": 0.4386, \"downstream_hellaswag_acc_norm\": 0.6147, \"downstream_piqa_acc_norm\": 0.7459, \"downstream_winogrande_acc\": 0.6298, \"downstream_mean\": 0.6286}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed123/final\", \"completed_at\": \"2026-05-19T01:16:22.990Z\"}, \"contamination_60_uniform_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T01:38:07.226Z\", \"updated_at\": \"2026-05-20T16:39:23.889Z\", \"hypothesis\": \"Uniform baseline at ρ=0.6 seed456: pairs with contamination_60_seed456 (adaptive) to form seed456 uniform/adaptive contrast. If adaptive PPL < uniform PPL at ρ=0.6, confirms Claim 3 proportion-robustness across seeds.\", \"parent\": \"contamination_60_uniform_seed42\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_uniform_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.6 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"158709\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_uniform_seed456.log\", \"submitted_at\": \"2026-05-18T01:44:54.483Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"contamination_60_uniform_seed42\", \"eval_data\": \"data/scored_data_60.jsonl\", \"wall_clock_seconds\": 13381.1, \"gpu_hours\": 3.72}, \"reproduce\": {\"finished_at\": \"2026-05-18T05:19:32.037Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T05:19:39.289326+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.77, \"eval_loss_holdout\": 2.8775, \"eval_holdout_tokens\": 4077068, \"train_loss\": 7.637, \"train_runtime_seconds\": 12845, \"total_steps\": 6103, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048\", \"eval_ppl_openwebtext\": 18.449, \"eval_ppl_wikipedia\": 15.42, \"ood_eval_source\": \"eval_results/ pipeline (consistent with adaptive tau07 evals)\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/contamination_60_uniform_seed456/final\", \"completed_at\": \"2026-05-18T05:27:55.537Z\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_uniform_seed456.log\", \"eval_ppl_openwebtext\": 18.449, \"eval_ppl_wikipedia\": 15.42}, \"eval_adaptive_1_7b_seed123\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T16:00:55.026Z\", \"updated_at\": \"2026-05-20T16:00:55.026Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && echo '=== OOD OpenWebText ===' && python eval_perplexity.py --checkpoints /root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed123/final --data_path data/eval_openwebtext.jsonl --max_docs 5000 --max_length 2048 --output_path /root/autodl-tmp/provenance_weight_training/output/eval/adaptive_1_7b_seed123_openwebtext.json && echo '=== OOD Wikipedia ===' && python eval_perplexity.py --checkpoints /root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed123/final --data_path data/eval_wikipedia.jsonl --max_docs 5000 --max_length 2048 --output_path /root/autodl-tmp/provenance_weight_training/output/eval/adaptive_1_7b_seed123_wikipedia.json && echo '=== Downstream ===' && lm_eval --model hf --model_args pretrained=/root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed123/final,dtype=float16 --tasks arc_easy,arc_challenge,hellaswag,piqa,winogrande --batch_size auto --num_fewshot 0 --output_path /root/autodl-tmp/provenance_weight_training/output/eval/adaptive_1_7b_seed123_downstream && echo '=== ALL DONE ==='\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"495970\", \"log_path\": \"~/runs/provenance_weight_training/eval_adaptive_1_7b_seed123.log\", \"submitted_at\": \"2026-05-20T16:00:54.254Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"eval_uniform_1_7b_seed123\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-20T16:00:50.758Z\", \"updated_at\": \"2026-05-20T16:00:50.758Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && echo '=== OOD OpenWebText ===' && python eval_perplexity.py --checkpoints /root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed123/final --data_path data/eval_openwebtext.jsonl --max_docs 5000 --max_length 2048 --output_path /root/autodl-tmp/provenance_weight_training/output/eval/uniform_1_7b_seed123_openwebtext.json && echo '=== OOD Wikipedia ===' && python eval_perplexity.py --checkpoints /root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed123/final --data_path data/eval_wikipedia.jsonl --max_docs 5000 --max_length 2048 --output_path /root/autodl-tmp/provenance_weight_training/output/eval/uniform_1_7b_seed123_wikipedia.json && echo '=== Downstream ===' && lm_eval --model hf --model_args pretrained=/root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed123/final,dtype=float16 --tasks arc_easy,arc_challenge,hellaswag,piqa,winogrande --batch_size auto --num_fewshot 0 --output_path /root/autodl-tmp/provenance_weight_training/output/eval/uniform_1_7b_seed123_downstream && echo '=== ALL DONE ==='\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"495407\", \"log_path\": \"~/runs/provenance_weight_training/eval_uniform_1_7b_seed123.log\", \"submitted_at\": \"2026-05-20T16:00:49.082Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"detect_remove_q05_epoch_matched\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T06:48:49.887Z\", \"updated_at\": \"2026-05-20T14:56:11.593Z\", \"conclusion\": \"killed\"}, \"contamination_60_adaptive_seed123_tau08\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T09:38:08.373Z\", \"updated_at\": \"2026-05-20T14:40:42.968Z\", \"hypothesis\": \"Retrain adaptive (ρ=0.6, τ=0.8, seed=123) from scratch on Qwen3-0.6B to obtain checkpoint for OOD+downstream eval. Original contamination_60_seed123 (PPL=17.732) confirmed holdout performance but checkpoint was cleaned up. Paired with seed42/456 for 3-seed τ=0.8 comparison against τ=0.7.\", \"parent\": \"contamination_60_seed123\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_adaptive_seed123_tau08 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --tau 0.8 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"459396\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_adaptive_seed123_tau08.log\", \"submitted_at\": \"2026-05-20T09:40:23.876Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"N/A\", \"eval_data\": \"N/A\", \"wall_clock_seconds\": 16294.4, \"gpu_hours\": 4.53}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/contamination_60_adaptive_seed123_tau08/final\", \"conclusion\": \"success\", \"metrics\": {\"holdout_ppl\": 17.73, \"eval_ppl_openwebtext\": 18.4, \"eval_ppl_wikipedia\": 15.34, \"downstream_arc_easy_acc_norm\": 0.6014, \"downstream_arc_challenge_acc_norm\": 0.3447, \"downstream_hellaswag_acc_norm\": 0.4804, \"downstream_piqa_acc_norm\": 0.6877, \"downstream_winogrande_acc\": 0.5699, \"downstream_mean\": 0.5368}, \"completed_at\": \"2026-05-20T14:11:58.236Z\"}, \"contamination_60_adaptive_seed42_tau08\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T09:38:07.151Z\", \"updated_at\": \"2026-05-20T14:40:41.593Z\", \"hypothesis\": \"Retrain adaptive (ρ=0.6, τ=0.8, seed=42) from scratch on Qwen3-0.6B to obtain checkpoint for OOD+downstream eval. Original contamination_60_seed42_r2 (PPL=17.74) confirmed holdout performance but checkpoint was cleaned up. Paired with seed123/456 for 3-seed τ=0.8 comparison against τ=0.7 (17.735/17.727/17.732).\", \"parent\": \"contamination_60_seed42_r2\", \"spec\": {\"command\": \"python -u training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_adaptive_seed42_tau08 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --tau 0.8 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"459319\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_adaptive_seed42_tau08.log\", \"submitted_at\": \"2026-05-20T09:40:21.580Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A\", \"eval_data\": \"N/A\", \"wall_clock_seconds\": 16294.7, \"gpu_hours\": 4.53}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/contamination_60_adaptive_seed42_tau08/final\", \"conclusion\": \"success\", \"metrics\": {\"holdout_ppl\": 17.74, \"eval_ppl_openwebtext\": 18.42, \"eval_ppl_wikipedia\": 15.37, \"downstream_arc_easy_acc_norm\": 0.612, \"downstream_arc_challenge_acc_norm\": 0.3439, \"downstream_hellaswag_acc_norm\": 0.4802, \"downstream_piqa_acc_norm\": 0.685, \"downstream_winogrande_acc\": 0.5777, \"downstream_mean\": 0.5398}, \"completed_at\": \"2026-05-20T14:11:56.312Z\"}, \"adaptive_fix_seed42\": {\"status\": \"DONE\", \"retry_count\": 2, \"created_at\": \"2026-05-14T13:32:30.463Z\", \"updated_at\": \"2026-05-20T08:58:53.948Z\", \"hypothesis\": \"D012 n_min fix (3→2, batch_size//2): adaptive b* with corrected ESS constraint achieves meaningful improvement over uniform baseline (PPL=17.69) for seed=42. Parent: adaptive_seed42 (PPL=17.69, n_min=3 bug)\", \"parent\": \"adaptive_seed42\", \"notes\": \"最终清理后重提交。从 checkpoint-1500 恢复，无 inline eval。PID=126801\", \"failure_reason\": \"\", \"completed_at\": \"\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"D012 代码验证通过（n_min=max(2,batch_size//2), 无EMA, import OK）。等 GPU 释放后提交。\"}, \"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T17:38:26.312269+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T20:39:45.953045+00:00\"}]}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_adaptive_fix_seed42.sh\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"109927\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_fix_seed42.log\", \"submitted_at\": \"2026-05-17T15:01:06.089Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T20:39:44.942Z\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.6527, \"downstream_arc_easy_acc_norm\": 0.6157, \"downstream_arc_challenge_acc_norm\": 0.343, \"downstream_hellaswag_acc_norm\": 0.4785, \"downstream_piqa_acc_norm\": 0.6866, \"downstream_winogrande_acc\": 0.5777, \"downstream_mean\": 0.5403, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16\", \"eval_ppl_openwebtext\": 18.424, \"eval_ppl_wikipedia\": 15.473}, \"checkpoint_path\": \"output/models/adaptive_fix_seed42/final\", \"eval_ppl_openwebtext\": 18.42, \"eval_ppl_wikipedia\": 15.47}, \"adaptive_rho06_tau07_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T03:22:15.719Z\", \"updated_at\": \"2026-05-20T08:58:52.243Z\", \"hypothesis\": \"Pure adaptive training at ρ=0.6, τ=0.7, seed=123. Second seed for clean ρ=0.6 τ=0.7 3-seed set. From-scratch Qwen3-0.6B, no checkpoint reuse. Validates τ=0.7 as universal default across contamination levels.\", \"parent\": \"rho06_tau07_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path /root/autodl-tmp/provenance_weight_training/data/scored_data_rho06.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/adaptive_rho06_tau07_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --tau 0.7 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model --save_steps 6103\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"383947\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_rho06_tau07_seed123.log\", \"submitted_at\": \"2026-05-20T03:31:35.365Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/provenance_weight_training/data/scored_data_rho06.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"N/A (from-scratch training)\", \"eval_data\": \"N/A (training experiment)\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_rho06_tau07_seed123/final\", \"train_loss\": 9.352, \"train_runtime_hours\": 3.74, \"wall_clock_seconds\": 16928.5, \"gpu_hours\": 4.7}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T08:13:43.870Z\", \"metrics\": {\"holdout_ppl\": 17.727, \"eval_ppl_openwebtext\": 18.385, \"eval_ppl_wikipedia\": 15.329, \"downstream_arc_easy_acc_norm\": 0.5951, \"downstream_arc_challenge_acc_norm\": 0.3422, \"downstream_hellaswag_acc_norm\": 0.4811, \"downstream_piqa_acc_norm\": 0.6866, \"downstream_winogrande_acc\": 0.5754, \"downstream_mean\": 0.5361}}, \"adaptive_rho06_tau07_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T03:22:16.979Z\", \"updated_at\": \"2026-05-20T08:58:50.338Z\", \"hypothesis\": \"Pure adaptive training at ρ=0.6, τ=0.7, seed=456. Third seed completing clean ρ=0.6 τ=0.7 3-seed set. From-scratch Qwen3-0.6B, no checkpoint reuse. Together with seed42/123, enables paired comparison against ρ=0.6 τ=0.8.\", \"parent\": \"rho06_tau07_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path /root/autodl-tmp/provenance_weight_training/data/scored_data_rho06.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/adaptive_rho06_tau07_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --tau 0.7 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model --save_steps 6103\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"384114\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_rho06_tau07_seed456.log\", \"submitted_at\": \"2026-05-20T03:31:37.645Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/provenance_weight_training/data/scored_data_rho06.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"N/A (from-scratch training)\", \"eval_data\": \"N/A (training experiment)\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_rho06_tau07_seed456/final\", \"train_loss\": 9.342, \"train_runtime_hours\": 3.72, \"wall_clock_seconds\": 16928.3, \"gpu_hours\": 4.7}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T08:13:45.922Z\", \"metrics\": {\"holdout_ppl\": 17.732, \"eval_ppl_openwebtext\": 18.411, \"eval_ppl_wikipedia\": 15.424, \"downstream_arc_easy_acc_norm\": 0.6128, \"downstream_arc_challenge_acc_norm\": 0.3456, \"downstream_hellaswag_acc_norm\": 0.4806, \"downstream_piqa_acc_norm\": 0.6866, \"downstream_winogrande_acc\": 0.562, \"downstream_mean\": 0.5375}}, \"adaptive_rho06_tau07_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T03:19:02.608Z\", \"updated_at\": \"2026-05-20T08:58:48.541Z\", \"hypothesis\": \"Pure adaptive retraining at ρ=0.6, τ=0.7, seed=42. Replaces rho06_tau07_seed42 which was contaminated by hybrid checkpoint. From-scratch training with base Qwen3-0.6B to clean output dir. If PPL < 17.73 (ρ=0.6 τ=0.8 baseline), validates τ=0.7 as universal default across contamination levels.\", \"parent\": \"rho06_tau07_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path /root/autodl-tmp/provenance_weight_training/data/scored_data_rho06.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/adaptive_rho06_tau07_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --tau 0.7 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model --save_steps 6103\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"383864\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_rho06_tau07_seed42.log\", \"submitted_at\": \"2026-05-20T03:31:32.965Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/provenance_weight_training/data/scored_data_rho06.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A (from-scratch training)\", \"eval_data\": \"N/A (training experiment)\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_rho06_tau07_seed42/final\", \"train_loss\": 9.358, \"train_runtime_hours\": 3.74, \"wall_clock_seconds\": 16929.0, \"gpu_hours\": 4.7}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T08:13:41.995Z\", \"metrics\": {\"holdout_ppl\": 17.735, \"eval_ppl_openwebtext\": 18.408, \"eval_ppl_wikipedia\": 15.355, \"downstream_arc_easy_acc_norm\": 0.6132, \"downstream_arc_challenge_acc_norm\": 0.3422, \"downstream_hellaswag_acc_norm\": 0.4807, \"downstream_piqa_acc_norm\": 0.6861, \"downstream_winogrande_acc\": 0.5793, \"downstream_mean\": 0.5403}}, \"adaptive_1_7b_seed42_v4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T05:51:02.045Z\", \"updated_at\": \"2026-05-20T08:47:34.649Z\", \"hypothesis\": \"Adaptive (dual-constrained) at 1.7B model scale (seed=42, τ=0.8, ρ=0.4). From-scratch on westd-41312. Tests if adaptive advantage holds at larger model scale. v4 replaces v3. Already approved.\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-20T05:52:27.750Z\"}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed42_v4 --model_name models/Qwen/Qwen3-1.7B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.8 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": \"cuda:1\", \"pid\": 437225, \"log_path\": \"~/runs/provenance_weight_training/adaptive_1_7b_seed42_v4.log\", \"submitted_at\": \"2026-05-20T08:14:12.537Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"N/A (from-scratch training)\", \"eval_data\": \"N/A (training experiment)\", \"checkpoint_path\": \"N/A (disk full at step 500)\", \"fail_reason\": \"No space left on device (os error 28) at step 500 checkpoint save. /root/autodl-tmp/ 250GB 100% full.\", \"wall_clock_seconds\": 2002.1, \"gpu_hours\": 0.56}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-20T08:47:34.649Z\"}, \"uniform_1_7b_seed42_v4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T05:50:59.956Z\", \"updated_at\": \"2026-05-20T08:47:26.437Z\", \"hypothesis\": \"Uniform baseline at 1.7B model scale (seed=42). From-scratch training on westd-41312. Provides 1.7B uniform PPL baseline for model scaling comparison. v4 replaces v3 (killed when westd-30476 decommissioned). Already approved.\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-20T05:52:26.116Z\"}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && PYTHONUNBUFFERED=1 WANDB_MODE=disabled python -u training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed42_v4 --model_name models/Qwen/Qwen3-1.7B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": 437143, \"log_path\": \"~/runs/provenance_weight_training/uniform_1_7b_seed42_v4.log\", \"submitted_at\": \"2026-05-20T08:14:10.069Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-1.7B\", \"seed\": 42, \"checkpoint_source\": \"N/A (from-scratch training)\", \"eval_data\": \"N/A (training experiment)\", \"checkpoint_path\": \"N/A (disk full at step 500)\", \"fail_reason\": \"No space left on device (os error 28) at step 500 checkpoint save. /root/autodl-tmp/ 250GB 100% full.\", \"wall_clock_seconds\": 1996.4, \"gpu_hours\": 0.55}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-20T08:47:26.437Z\"}, \"detect_remove_q04_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:57:02.595Z\", \"updated_at\": \"2026-05-20T07:14:37.043Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q04_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q04_seed42.log\", \"data_count\": 136957}, \"hypothesis\": \"D&R threshold t=0.4: keep q≤0.4 samples. Densification point between q03 (31.5%) and q05 (41.4%, PPL=17.28). Helps pinpoint the PPL sweet spot and quantify sensitivity. Part of expanded 9-point D&R threshold curve.\", \"reproduce\": {\"finished_at\": \"2026-05-18T21:34:03.227Z\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.26, \"eval_loss_holdout\": 2.8485, \"downstream_arc_easy_acc_norm\": 0.6107, \"downstream_arc_challenge_acc_norm\": 0.3567, \"downstream_hellaswag_acc_norm\": 0.4819, \"downstream_piqa_acc_norm\": 0.6931, \"downstream_winogrande_acc\": 0.5659, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\", \"eval_ppl_openwebtext\": 18.001, \"eval_ppl_wikipedia\": 15.038}, \"completed_at\": \"2026-05-18T22:01:52.526Z\", \"eval_ppl_openwebtext\": 18, \"eval_ppl_wikipedia\": 15.04}, \"detect_remove_q03_seed42_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:56:59.443Z\", \"updated_at\": \"2026-05-20T07:14:34.819Z\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=0 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q03.jsonl --output_dir /root/autodl-tmp/output/models/detect_remove_q03_seed42_r2 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --bf16 --save_total_limit 3 --logging_steps 10 --save_steps 500'\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:0\"], \"pid\": \"59986\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q03_seed42_r2.log\", \"submitted_at\": \"2026-05-18T17:56:58.742Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q03.jsonl\", \"data_count\": 116935, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q03_seed42_r2/checkpoint-6103\", \"wall_clock_seconds\": 14691.7, \"gpu_hours\": 4.08}, \"hypothesis\": \"D&R threshold t=0.3: keep q≤0.3 (116,935 samples, 31.5%). Second most aggressive filtering level. Part of 9-point D&R sensitivity curve (q01-q09). Previous attempt failed (python: command not found). Rerun on westd-30476.\", \"reproduce\": {\"finished_at\": \"2026-05-18T21:31:12.021Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T21:31:16.535916+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.25, \"eval_loss_holdout\": 2.848, \"downstream_arc_easy_acc_norm\": 0.6301, \"downstream_arc_challenge_acc_norm\": 0.3549, \"downstream_hellaswag_acc_norm\": 0.4851, \"downstream_piqa_acc_norm\": 0.6872, \"downstream_winogrande_acc\": 0.5675, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\", \"eval_ppl_openwebtext\": 18.004, \"eval_ppl_wikipedia\": 15.037}, \"completed_at\": \"2026-05-18T22:01:50.398Z\", \"eval_ppl_openwebtext\": 18, \"eval_ppl_wikipedia\": 15.04}, \"detect_remove_q08_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:53:26.593Z\", \"updated_at\": \"2026-05-20T07:14:32.824Z\", \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --model_name models/Qwen/Qwen3-0.6B --data_path data/scored_data_filtered_q08.jsonl --output_dir .../detect_remove_q08_seed42 --weighting_method uniform --seed 42\", \"server\": \"westd-41312\", \"gpu\": \"cuda:3\", \"pid\": 248002, \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q08_seed42.log\", \"submitted_at\": \"2026-05-18T19:53:26.126Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q08.jsonl\", \"data_count\": 202455, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"wall_clock_seconds\": 14855.4, \"gpu_hours\": 4.13}, \"hypothesis\": \"D&R threshold t=0.8: keep q≤0.8 samples (~210K). Lenient filtering near q09 (228K). Part of 9-point D&R sensitivity curve. Expected PPL between q07 (17.32) and q09 (17.42) confirming right side of U-shape.\", \"reproduce\": {\"finished_at\": \"2026-05-18T23:28:13.145Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T23:28:18.092622+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.3442, \"eval_loss_holdout\": 2.8533, \"downstream_arc_easy_acc_norm\": 0.6086, \"downstream_arc_challenge_acc_norm\": 0.3592, \"downstream_hellaswag_acc_norm\": 0.4855, \"downstream_piqa_acc_norm\": 0.6937, \"downstream_winogrande_acc\": 0.5817, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\", \"eval_ppl_openwebtext\": 18.039, \"eval_ppl_wikipedia\": 15.066}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/detect_remove_q08_seed42/final\", \"completed_at\": \"2026-05-19T00:01:01.571Z\", \"downstream_arc_easy\": 0.6086, \"downstream_arc_challenge\": 0.3592, \"downstream_hellaswag\": 0.4855, \"downstream_piqa\": 0.6937, \"downstream_winogrande\": 0.5817, \"downstream_mean\": 0.5457, \"eval_ppl_openwebtext\": 18.04, \"eval_ppl_wikipedia\": 15.07}, \"adaptive_1_7b_seed42_v3\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-20T04:49:58.165Z\", \"updated_at\": \"2026-05-20T05:50:47.354Z\", \"hypothesis\": \"Adaptive (dual-constrained) at 1.7B model scale (seed=42, τ=0.8, ρ=0.4). Paired with uniform_1_7b_seed42_v3 to test if adaptive advantage holds at larger model scale. Key for model scaling claim in paper.\", \"server\": \"westd-30476\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-30476\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-20T04:50:57.591Z\"}, \"completed_at\": \"2026-05-20T05:38:50.468Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"killed\"}}, \"conclusion\": \"killed\", \"spec\": {\"kill_reason\": \"westd-30476 已注销，checkpoint 丢失\"}}, \"uniform_1_7b_seed42_v3\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-20T04:49:30.213Z\", \"updated_at\": \"2026-05-20T05:50:45.424Z\", \"hypothesis\": \"Uniform baseline at 1.7B model scale (seed=42). Provides 1.7B uniform PPL baseline for model scaling comparison. Previous uniform_1_7b_seed42 failed; this is a clean re-run on westd-30476 with verified model weights.\", \"server\": \"westd-30476\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-30476\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-20T04:50:55.085Z\"}, \"completed_at\": \"2026-05-20T05:38:48.621Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"killed\"}}, \"conclusion\": \"killed\", \"spec\": {\"kill_reason\": \"westd-30476 已注销，checkpoint 丢失\"}}, \"detect_remove_q01_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-18T06:48:51.429Z\", \"updated_at\": \"2026-05-20T05:04:46.527Z\", \"hypothesis\": \"D&R extreme threshold q>0.1: removes all samples with q_score>0.1, keeping only the most confidently clean data. Tests D&R sensitivity to threshold — if PPL degrades severely, filtering is too aggressive and most data is discarded. Paired with q>0.3/0.5/0.7/0.9 to map the full threshold-PPL curve, showing adaptive avoids this calibration problem entirely.\", \"reproduce\": {\"finished_at\": \"2026-05-18T14:54:29.368Z\"}, \"failure_reason\": \"EXIT_CODE=127 (command not found — check bash -c wrapping / env activate)\", \"completed_at\": \"2026-05-18T14:54:33.151Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T14:54:38.690732+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q01.jsonl --weighting_method uniform --num_train_tokens 200000000 --seed 42\", \"server\": \"westd-30476\", \"data_path\": \"data/scored_data_filtered_q01.jsonl\", \"data_count\": 55799, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"gpu\": \"cuda:3\", \"note\": \"Cron 误报 failed (M025)，实际仍在训练 ~48%\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q01_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q01_seed42.log\"}, \"metrics\": {\"eval_ppl_holdout\": 17.4, \"eval_ppl_openwebtext\": 18.22, \"eval_ppl_wikitext\": 28.22}, \"conclusion\": \"success\"}, \"detect_remove_q03_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:04:05.454Z\", \"updated_at\": \"2026-05-20T05:04:45.643Z\", \"spec\": {\"command\": \"D&R q03 seed456 on 30476\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:1\"], \"pid\": \"76791\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q03_seed456.log\", \"submitted_at\": \"2026-05-18T22:04:04.680Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q03.jsonl\", \"data_count\": 116935, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"wall_clock_seconds\": 13846.2, \"gpu_hours\": 3.85}, \"hypothesis\": \"D&R threshold t=0.3 seed456: cross-seed replication of q03 sweet spot (PPL=17.25 at seed42). Third seed for 3-seed mean and variance estimate at the D&R optimal threshold.\", \"reproduce\": {\"finished_at\": \"2026-05-19T01:38:41.994Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T01:38:47.039510+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.2509, \"eval_loss_holdout\": 2.8479, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048 (final checkpoint)\", \"train_loss\": 11.255, \"total_steps\": 6103, \"eval_ppl_openwebtext\": 18.03, \"eval_ppl_wikitext\": 27.61}, \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q03_seed456/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T01:54:50.846Z\"}, \"detect_remove_q03_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:04:03.208Z\", \"updated_at\": \"2026-05-20T05:04:43.723Z\", \"spec\": {\"command\": \"D&R q03 seed123 on 30476\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:0\"], \"pid\": \"76714\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q03_seed123.log\", \"submitted_at\": \"2026-05-18T22:04:02.773Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q03.jsonl\", \"data_count\": 116935, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q03_seed123/final\", \"wall_clock_seconds\": 13059, \"gpu_hours\": 3.63}, \"hypothesis\": \"Cross-seed replication of D&R q03 sweet spot: if seed123 reproduces seed42's PPL=17.25 (the U-curve optimum), q03 is a robust threshold, not a seed42 artifact. Two seeds converging validates the U-shape minimum at q03-q04.\", \"reproduce\": {\"finished_at\": \"2026-05-19T01:43:26.091Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T01:43:31.103456+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.25, \"eval_loss_holdout\": 2.8479, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"sliding_window_stride1024_maxlen2048_fp16_5000docs\", \"total_steps\": 6103, \"train_loss_final\": 11.2441, \"train_runtime_s\": 13059, \"epoch\": 0.84, \"eval_ppl_openwebtext\": 18.03, \"eval_ppl_wikitext\": 27.53}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T01:49:44.145Z\"}, \"detect_remove_q05_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T06:46:10.870Z\", \"updated_at\": \"2026-05-20T05:04:41.870Z\", \"hypothesis\": \"Detect-and-remove baseline with q>0.5 threshold and seed=456 will produce similar PPL to seed42 (17.29), confirming reproducibility of the filtering approach across seeds.\", \"parent\": \"\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir /root/autodl-tmp/output/models/detect_remove_q05_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --resume_from_checkpoint /root/autodl-tmp/output/models/detect_remove_q05_seed456/checkpoint-500\", \"server\": \"westd-30476\", \"gpu\": 1, \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 153725, \"model_name\": \"models/Qwen/Qwen3-0.6B\", \"seed\": 456, \"weighting_method\": \"uniform\", \"threshold\": 0.5, \"max_steps\": 6103, \"pid\": 26855, \"output_dir\": \"/root/autodl-tmp/output/models/detect_remove_q05_seed456\", \"tmux_session\": \"detect_remove_q05_seed456\", \"total_steps\": 6103, \"estimated_time\": \"3.5h\", \"note\": \"Resumed from checkpoint-500 after killing PID 25514 (from-scratch run without --resume_from_checkpoint) and PID 13654 (had extra --eval_data_path causing slowdown)\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q05_seed456\", \"log_path\": \"/root/autodl-tmp/output/models/detect_remove_q05_seed456/training.log\", \"resumed_from\": \"checkpoint-500\"}, \"failure_reason\": \"startup recovery: process dead, no active cron monitor\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T12:59:17.900Z\", \"metrics\": {\"eval_ppl_holdout\": 17.28, \"eval_loss_holdout\": 2.8493, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --checkpoints --max_docs 5000 --max_length 2048 --stride 1024 --fp16\", \"eval_ppl_openwebtext\": 18.01, \"eval_ppl_wikitext\": 27.68}}, \"detect_remove_q05_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T06:46:09.441Z\", \"updated_at\": \"2026-05-20T05:04:40.013Z\", \"hypothesis\": \"Uniform weighting on q05-filtered data (contamination removed) with seed 123 will show different convergence behavior compared to provenance-weighted training, serving as a detection baseline for measuring the effect of removing contaminated data.\", \"parent\": \"\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir /root/autodl-tmp/output/models/detect_remove_q05_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\", \"server\": \"westd-30476\", \"gpu\": \"0\", \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 200000000, \"model_name\": \"models/Qwen/Qwen3-0.6B\", \"seed\": 123, \"pid\": 22336, \"output_dir\": \"/root/autodl-tmp/output/models/detect_remove_q05_seed123\", \"log_path\": \"/root/autodl-tmp/output/models/detect_remove_q05_seed123.log\", \"weighting_method\": \"uniform\", \"num_train_tokens\": 200000000, \"learning_rate\": 5e-05, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q05_seed123\"}, \"failure_reason\": \"startup recovery: process dead, no active cron monitor\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T12:59:14.465Z\", \"metrics\": {\"eval_ppl_holdout\": 17.27, \"eval_loss_holdout\": 2.8491, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --checkpoints --max_docs 5000 --max_length 2048 --stride 1024 --fp16\", \"eval_ppl_openwebtext\": 18.01, \"eval_ppl_wikitext\": 27.75}}, \"detect_remove_q02_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:47:54.392Z\", \"updated_at\": \"2026-05-20T05:04:38.545Z\", \"spec\": {\"command\": \"detect_remove_q02_seed42 training\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"65827\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q02_seed42.log\", \"submitted_at\": \"2026-05-18T19:47:54.017Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q02_seed42/final\", \"data_count\": 91654, \"data_path\": \"data/scored_data_filtered_q02.jsonl\", \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"wall_clock_seconds\": 13347.2, \"gpu_hours\": 3.71}, \"reproduce\": {\"finished_at\": \"2026-05-18T23:22:37.551Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T23:22:43.918775+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.27, \"eval_loss_holdout\": 2.8491, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048 (final checkpoint)\", \"train_loss\": 11.348, \"train_steps\": 6103, \"data_count\": 91654, \"eval_ppl_openwebtext\": 18.06, \"eval_ppl_wikitext\": 27.64}, \"conclusion\": \"success\", \"hypothesis\": \"D&R q>0.2 threshold retains ~23% of data (q_score<=0.2). Maps the left side of the U-curve between q01(17.40) and q03(17.25). If PPL closer to q03 than q01, the steep rise only occurs at extreme filtering (q01). If closer to q01, the left branch rises steeply from q03 onward.\", \"completed_at\": \"2026-05-18T23:30:21.249Z\"}, \"epoch_matched_dr_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:14:29.174Z\", \"updated_at\": \"2026-05-20T05:04:36.608Z\", \"hypothesis\": \"Cross-seed confirmation of D080: epoch-matched D&R (1 content epoch, ~83M tokens) will produce PPL similar to adaptive (~17.65), proving D&R's apparent 0.36 PPL advantage over adaptive is entirely from multi-epoch training, not data quality filtering. Seed 456 for 3-seed significance.\", \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir /root/autodl-tmp/output/models/epoch_matched_dr_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --num_train_tokens 83000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --bf16 --save_only_model --save_total_limit 3\", \"server\": \"westd-30476\", \"gpu\": 1, \"pid\": \"unknown\", \"log_path\": \"~/runs/provenance_weight_training/epoch_matched_dr_seed456.log\", \"submitted_at\": \"2026-05-18T14:15:10.126Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 153725, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"output_dir\": \"/root/autodl-tmp/output/models/epoch_matched_dr_seed456\", \"num_train_tokens\": 83000000, \"weighting_method\": \"uniform\", \"wall_clock_seconds\": 2350.3, \"gpu_hours\": 0.65}, \"reproduce\": {\"finished_at\": \"2026-05-18T14:54:03.288Z\"}, \"failure_reason\": \"EXIT_CODE=127 (command not found — check bash -c wrapping / env activate)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T14:54:20.380Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T14:54:25.712372+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.66, \"eval_loss_holdout\": 2.8712, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048\", \"eval_ppl_openwebtext\": 18.27, \"eval_ppl_wikitext\": 28.14}}, \"epoch_matched_dr_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:14:28.033Z\", \"updated_at\": \"2026-05-20T05:04:34.758Z\", \"hypothesis\": \"Cross-seed confirmation of D080: epoch-matched D&R (1 content epoch, ~83M tokens) will produce PPL similar to adaptive (~17.65), proving D&R's apparent 0.36 PPL advantage over adaptive is entirely from multi-epoch training, not data quality filtering. Seed 123 for 3-seed significance.\", \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir /root/autodl-tmp/output/models/epoch_matched_dr_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --num_train_tokens 83000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --bf16 --save_only_model --save_total_limit 3\", \"server\": \"westd-30476\", \"gpu\": 0, \"pid\": \"unknown\", \"log_path\": \"~/runs/provenance_weight_training/epoch_matched_dr_seed123.log\", \"submitted_at\": \"2026-05-18T14:15:07.644Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 153725, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"output_dir\": \"/root/autodl-tmp/output/models/epoch_matched_dr_seed123\", \"num_train_tokens\": 83000000, \"weighting_method\": \"uniform\", \"wall_clock_seconds\": 2321.3, \"gpu_hours\": 0.64}, \"reproduce\": {\"finished_at\": \"2026-05-18T14:53:34.631Z\"}, \"failure_reason\": \"EXIT_CODE=127 (command not found — check bash -c wrapping / env activate)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T14:53:48.912Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T14:53:58.046964+00:00\"}]}, \"notes\": \"失败原因: EXIT_CODE=127 (command not found)，训练在 step ~201/2532 后中断。wall_clock=2321s 但日志仅记录到 ~7min。已派 Worker worker_diagnose_epoch_matched_dr_seed123_20260518T145604 深查。\", \"metrics\": {\"eval_ppl_holdout\": 17.66, \"eval_loss_holdout\": 2.8713, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048\", \"eval_ppl_openwebtext\": 18.3, \"eval_ppl_wikitext\": 27.9}}, \"eval_q04\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T21:49:30.129Z\", \"updated_at\": \"2026-05-20T04:49:10.488Z\", \"spec\": {\"command\": \"python eval_perplexity.py --checkpoints /root/autodl-tmp/output/models/detect_remove_q04_seed42/final --data_path data/human/eval_holdout.jsonl --max_docs 5000 --max_length 2048\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:1\"], \"pid\": \"75261\", \"log_path\": \"~/runs/provenance_weight_training/eval_q04.log\", \"submitted_at\": \"2026-05-18T21:49:29.738Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/human/eval_holdout.jsonl\", \"data_count\": 5000, \"model_name\": \"detect_remove_q04_seed42\", \"seed\": 42, \"checkpoint_source\": \"detect_remove_q04_seed42\", \"eval_data\": \"human/eval_holdout.jsonl\", \"wall_clock_seconds\": 109387.9, \"gpu_hours\": 30.39}, \"metrics\": {\"loss\": 2.8485, \"perplexity\": 17.2626, \"num_tokens\": 4077068, \"elapsed_seconds\": 103.8, \"downstream_arc_easy_acc_norm\": 0.6107, \"downstream_arc_challenge_acc_norm\": 0.3567, \"downstream_hellaswag_acc_norm\": 0.4819, \"downstream_piqa_acc_norm\": 0.6931, \"downstream_winogrande_acc\": 0.5659, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q04_seed42/final\", \"log_path\": \"/tmp/eval_q04.log\", \"hypothesis\": \"Detect-remove at q=0.4 threshold should show lower PPL than epoch-matched baseline, with slightly higher PPL than q=0.3 due to retaining more borderline-quality documents.\", \"completed_at\": \"2026-05-20T04:12:37.643Z\"}, \"eval_q03_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T21:49:14.814Z\", \"updated_at\": \"2026-05-20T04:47:07.748Z\", \"spec\": {\"command\": \"python eval_perplexity.py --checkpoints /root/autodl-tmp/output/models/detect_remove_q03_seed42_r2/final --data_path data/human/eval_holdout.jsonl --max_docs 5000 --max_length 2048\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:0\"], \"pid\": \"75089\", \"log_path\": \"~/runs/provenance_weight_training/eval_q03_r2.log\", \"submitted_at\": \"2026-05-18T21:49:14.346Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/human/eval_holdout.jsonl\", \"data_count\": 5000, \"model_name\": \"detect_remove_q03_seed42_r2\", \"seed\": 42, \"checkpoint_source\": \"detect_remove_q03_seed42_r2\", \"eval_data\": \"human/eval_holdout.jsonl\", \"wall_clock_seconds\": 109401.5, \"gpu_hours\": 30.39}, \"metrics\": {\"loss\": 2.848, \"perplexity\": 17.2538, \"num_tokens\": 4077068, \"elapsed_seconds\": 111, \"downstream_arc_easy_acc_norm\": 0.6301, \"downstream_arc_challenge_acc_norm\": 0.3549, \"downstream_hellaswag_acc_norm\": 0.4851, \"downstream_piqa_acc_norm\": 0.6872, \"downstream_winogrande_acc\": 0.5675, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q03_seed42_r2/final\", \"log_path\": \"/tmp/eval_q03_r2.log\", \"hypothesis\": \"Detect-remove at q=0.3 threshold (r2 rerun) should show lower PPL than epoch-matched baseline because aggressive filtering removes more low-quality synthetic data while retaining high-provenance human content.\", \"completed_at\": \"2026-05-20T04:12:35.816Z\"}, \"eval_rho06_batch_v7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:09:06.933Z\", \"updated_at\": \"2026-05-20T04:14:19.316Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=0 python eval_perplexity.py --checkpoints /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_ess_only_seed123/final /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_ess_only_seed456/final /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_random_seed123/final /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_random_seed456/final --data_path data/human/eval_holdout.jsonl --max_docs 5000 --max_length 2048 2>&1 | tee /tmp/eval_rho06_batch.log\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"213243\", \"log_path\": \"~/runs/provenance_weight_training/eval_rho06_batch_v7.log\", \"submitted_at\": \"2026-05-18T12:09:06.600Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 144312.7, \"gpu_hours\": 40.09}, \"metrics\": {\"contamination_60_ess_only_seed123\": {\"loss\": 2.8771, \"perplexity\": 17.76, \"tokens\": 4077068}, \"contamination_60_ess_only_seed456\": {\"loss\": 2.8771, \"perplexity\": 17.76, \"tokens\": 4077068}, \"contamination_60_random_seed123\": {\"loss\": 2.8832, \"perplexity\": 17.87, \"tokens\": 4077068}, \"contamination_60_random_seed456\": {\"loss\": 2.8837, \"perplexity\": 17.88, \"tokens\": 4077068}, \"eval_data\": \"data/human/eval_holdout.jsonl\", \"max_docs\": 5000, \"max_length\": 2048}, \"hypothesis\": \"Contamination-aware weighting (rho=0.6) with ESS-only vs random selection should show different perplexity on held-out human text, with ESS-only selection better capturing human-like text distribution.\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/contamination_60_*/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T04:14:19.316Z\"}, \"eval_q01_final_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:18:30.245Z\", \"updated_at\": \"2026-05-20T04:12:43.210Z\", \"spec\": {\"command\": \"python eval_perplexity.py --checkpoints /root/autodl-tmp/output/models/detect_remove_q01_seed42/final --data_path data/human/eval_holdout.jsonl --max_docs 5000 --max_length 2048\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"64426\", \"log_path\": \"~/runs/provenance_weight_training/eval_q01_final_v2.log\", \"submitted_at\": \"2026-05-18T19:18:29.874Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/human/eval_holdout.jsonl\", \"data_count\": 5000, \"model_name\": \"detect_remove_q01_seed42\", \"seed\": 42, \"checkpoint_source\": \"detect_remove_q01_seed42\", \"eval_data\": \"human/eval_holdout.jsonl\", \"wall_clock_seconds\": 118453.3, \"gpu_hours\": 32.9}, \"metrics\": {\"loss\": 2.8563, \"perplexity\": 17.3965, \"num_tokens\": 4077068, \"elapsed_seconds\": 105.1}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q01_seed42/final\", \"log_path\": \"/tmp/eval_q01.log\", \"hypothesis\": \"Detect-remove at q=0.1 (most aggressive filtering) should show the lowest PPL among all thresholds if data quality dominates, or degraded PPL if the severe data reduction causes underfitting.\", \"completed_at\": \"2026-05-20T04:12:43.210Z\"}, \"eval_q07_final\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:33:23.528Z\", \"updated_at\": \"2026-05-20T04:12:41.391Z\", \"spec\": {\"command\": \"python eval_perplexity.py --checkpoints /root/autodl-tmp/output/models/detect_remove_q07_seed42/final --data_path data/human/eval_holdout.jsonl --max_docs 5000 --max_length 2048\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:2\"], \"pid\": \"59032\", \"log_path\": \"~/runs/provenance_weight_training/eval_q07_final.log\", \"submitted_at\": \"2026-05-18T17:33:23.135Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/human/eval_holdout.jsonl\", \"data_count\": 5000, \"model_name\": \"detect_remove_q07_seed42\", \"seed\": 42, \"checkpoint_source\": \"detect_remove_q07_seed42\", \"eval_data\": \"human/eval_holdout.jsonl\", \"wall_clock_seconds\": 124758.3, \"gpu_hours\": 34.66}, \"metrics\": {\"loss\": 2.8519, \"perplexity\": 17.3201, \"num_tokens\": 4077068, \"elapsed_seconds\": 103.8}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q07_seed42/final\", \"log_path\": \"/tmp/eval_q07.log\", \"hypothesis\": \"Detect-remove at q=0.7 threshold should show lower PPL than epoch-matched baseline, with the PPL gap narrowing as higher thresholds retain more data including lower-provenance documents.\", \"completed_at\": \"2026-05-20T04:12:41.391Z\"}, \"eval_q06\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T21:49:17.026Z\", \"updated_at\": \"2026-05-20T04:12:39.559Z\", \"spec\": {\"command\": \"python eval_perplexity.py --checkpoints /root/autodl-tmp/output/models/detect_remove_q06_seed42/final --data_path data/human/eval_holdout.jsonl --max_docs 5000 --max_length 2048\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:2\"], \"pid\": \"75168\", \"log_path\": \"~/runs/provenance_weight_training/eval_q06.log\", \"submitted_at\": \"2026-05-18T21:49:16.263Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/human/eval_holdout.jsonl\", \"data_count\": 5000, \"model_name\": \"detect_remove_q06_seed42\", \"seed\": 42, \"checkpoint_source\": \"detect_remove_q06_seed42\", \"eval_data\": \"human/eval_holdout.jsonl\", \"wall_clock_seconds\": 109403.3, \"gpu_hours\": 30.39}, \"metrics\": {\"loss\": 2.8507, \"perplexity\": 17.2993, \"num_tokens\": 4077068, \"elapsed_seconds\": 106.9}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q06_seed42/final\", \"log_path\": \"/tmp/eval_q06.log\", \"hypothesis\": \"Detect-remove at q=0.6 threshold should show lower PPL than epoch-matched baseline but higher than q=0.3/0.4 as the less aggressive filtering retains more synthetic-origin content.\", \"completed_at\": \"2026-05-20T04:12:39.559Z\"}, \"eval_epoch_matched_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:33:21.793Z\", \"updated_at\": \"2026-05-20T04:12:33.833Z\", \"spec\": {\"command\": \"python eval_perplexity.py --checkpoints /root/autodl-tmp/output/models/epoch_matched_dr_seed456/final --data_path data/human/eval_holdout.jsonl --max_docs 5000 --max_length 2048\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:1\"], \"pid\": \"58952\", \"log_path\": \"~/runs/provenance_weight_training/eval_epoch_matched_seed456.log\", \"submitted_at\": \"2026-05-18T17:33:21.443Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/human/eval_holdout.jsonl\", \"data_count\": 5000, \"model_name\": \"epoch_matched_dr_seed456\", \"seed\": 456, \"checkpoint_source\": \"epoch_matched_dr_seed456\", \"eval_data\": \"human/eval_holdout.jsonl\", \"wall_clock_seconds\": 124752.4, \"gpu_hours\": 34.65}, \"metrics\": {\"loss\": 2.8712, \"perplexity\": 17.6574, \"num_tokens\": 4077068, \"elapsed_seconds\": 103.6}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/epoch_matched_dr_seed456/final\", \"log_path\": \"/tmp/eval_epoch_seed456.log\", \"hypothesis\": \"Epoch-matched detect-remove baseline (seed456) should achieve similar held-out PPL as seed123, confirming reproducibility of the epoch-matched baseline across random seeds.\", \"completed_at\": \"2026-05-20T04:12:33.833Z\"}, \"eval_epoch_matched_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:33:20.074Z\", \"updated_at\": \"2026-05-20T04:12:31.028Z\", \"spec\": {\"command\": \"python eval_perplexity.py --checkpoints /root/autodl-tmp/output/models/epoch_matched_dr_seed123/final --data_path data/human/eval_holdout.jsonl --max_docs 5000 --max_length 2048\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:0\"], \"pid\": \"58873\", \"log_path\": \"~/runs/provenance_weight_training/eval_epoch_matched_seed123.log\", \"submitted_at\": \"2026-05-18T17:33:19.707Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/human/eval_holdout.jsonl\", \"data_count\": 5000, \"model_name\": \"epoch_matched_dr_seed123\", \"seed\": 123, \"checkpoint_source\": \"epoch_matched_dr_seed123\", \"eval_data\": \"human/eval_holdout.jsonl\", \"wall_clock_seconds\": 124751.3, \"gpu_hours\": 34.65}, \"metrics\": {\"loss\": 2.8713, \"perplexity\": 17.6599, \"num_tokens\": 4077068, \"elapsed_seconds\": 104.3}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/epoch_matched_dr_seed123/final\", \"log_path\": \"/tmp/eval_epoch_seed123.log\", \"hypothesis\": \"Epoch-matched detect-remove baseline (seed123) should achieve similar held-out PPL as uniform training, confirming that matched training budget controls for compute rather than data filtering effects.\", \"completed_at\": \"2026-05-20T04:12:31.028Z\"}, \"eval_ngram_uniform\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:15:52.785Z\", \"updated_at\": \"2026-05-20T04:04:40.459Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && python eval_perplexity.py --checkpoints /root/autodl-tmp/provenance_weight_training/output/models/ngram_uniform_seed42/final --data_path data/human/eval_holdout.jsonl --max_docs 5000 --max_length 2048\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"243502\", \"log_path\": \"~/runs/provenance_weight_training/eval_ngram_uniform.log\", \"submitted_at\": \"2026-05-18T19:15:52.408Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 118128.1, \"gpu_hours\": 32.81}, \"metrics\": {\"loss\": 2.8733, \"perplexity\": 17.69, \"tokens\": 4077068, \"eval_data\": \"data/human/eval_holdout.jsonl\", \"max_docs\": 5000, \"max_length\": 2048, \"checkpoint\": \"ngram_uniform_seed42/final\"}, \"hypothesis\": \"Uniform n-gram weighting treats all documents equally regardless of n-gram rarity, serving as a baseline to compare against adaptive weighting for held-out human text perplexity.\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/ngram_uniform_seed42/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T04:04:40.459Z\"}, \"eval_ngram_adaptive\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:15:51.010Z\", \"updated_at\": \"2026-05-20T04:02:52.006Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && python eval_perplexity.py --checkpoints /root/autodl-tmp/provenance_weight_training/output/models/ngram_adaptive_seed42/final --data_path data/human/eval_holdout.jsonl --max_docs 5000 --max_length 2048\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"243422\", \"log_path\": \"~/runs/provenance_weight_training/eval_ngram_adaptive.log\", \"submitted_at\": \"2026-05-18T19:15:50.620Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 118021.4, \"gpu_hours\": 32.78}, \"metrics\": {\"loss\": 2.8803, \"perplexity\": 17.82, \"tokens\": 4077068, \"eval_data\": \"data/human/eval_holdout.jsonl\", \"max_docs\": 5000, \"max_length\": 2048, \"checkpoint\": \"ngram_adaptive_seed42/final\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/ngram_adaptive_seed42/final\", \"hypothesis\": \"N-gram adaptive weighting assigns higher weights to documents with rare n-gram patterns, which should yield lower perplexity on held-out human text compared to uniform weighting by better capturing the distribution of natural language.\", \"completed_at\": \"2026-05-20T04:02:52.006Z\"}, \"uniform_seed42_downstream\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T03:31:40.139Z\", \"updated_at\": \"2026-05-20T03:56:46.798Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python -m lm_eval --model hf --model_args pretrained=/root/autodl-tmp/provenance_weight_training/output/models/qwen06b_uniform_seed42_v2/final,dtype=float16 --tasks arc_easy,arc_challenge,hellaswag,piqa,winogrande --batch_size auto --num_fewshot 0 --output_path /root/autodl-tmp/provenance_weight_training/output/eval_results/uniform_seed42_downstream\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"384367\", \"log_path\": \"~/runs/provenance_weight_training/uniform_seed42_downstream.log\", \"submitted_at\": \"2026-05-20T03:31:39.674Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_source\": \"qwen06b_uniform_seed42\", \"eval_data\": \"arc_easy,arc_challenge,hellaswag,piqa,winogrande (0-shot)\", \"data_path\": \"lm_eval built-in benchmarks\", \"data_count\": 0, \"model_name\": \"Qwen/Qwen3-0.6B (uniform baseline)\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/qwen06b_uniform_seed42_v2/final\", \"wall_clock_seconds\": 1504.9, \"gpu_hours\": 0.42}, \"hypothesis\": \"Downstream benchmark eval (ARC-Easy/Challenge, HellaSwag, PIQA, WinoGrande) for uniform_seed42 baseline. Completes 3-seed uniform downstream comparison needed for Table in paper.\", \"parent\": \"qwen06b_uniform_seed42\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T03:56:44.553Z\", \"metrics\": {\"downstream_arc_easy_acc_norm\": 0.6128, \"downstream_arc_challenge_acc_norm\": 0.3481, \"downstream_hellaswag_acc_norm\": 0.4836, \"downstream_piqa_acc_norm\": 0.6877, \"downstream_winogrande_acc\": 0.5856, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\"}}, \"adaptive_fromscratch_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T18:50:48.052Z\", \"updated_at\": \"2026-05-20T03:32:28.070Z\", \"hypothesis\": \"From-scratch adaptive (no resume artifact) at seed42 to complete 3-seed consistent dataset. If in-dist PPL matches seed123/456 range (~17.677-17.683) and OOD shows no reversal, distribution matching was a resume artifact.\", \"parent\": \"adaptive_fix_seed42\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --seed 42 (from-scratch, no resume)\", \"server\": \"westd-41312\", \"gpu\": \"cuda:0\", \"pid\": 337777, \"log_path\": \"~/runs/provenance_weight_training/adaptive_fromscratch_seed42.log\", \"submitted_at\": \"2026-05-19T18:52:11.626Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 6103, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A (from-scratch training, not eval)\", \"eval_data\": \"N/A (training experiment)\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_fromscratch_seed42/final\", \"wall_clock_seconds\": 31216.4, \"gpu_hours\": 8.67}, \"reproduce\": {\"finished_at\": \"2026-05-19T22:42:07.612Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T22:42:12.912658+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_fromscratch_seed42/final\", \"metrics\": {\"train_loss\": 9.976, \"eval_ppl_holdout\": 17.689, \"eval_ppl_openwebtext\": 18.37, \"eval_ppl_wikipedia\": 15.349, \"downstream_arc_easy_acc_norm\": 0.6178, \"downstream_arc_challenge_acc_norm\": 0.3524, \"downstream_hellaswag_acc_norm\": 0.4806, \"downstream_piqa_acc_norm\": 0.6844, \"downstream_winogrande_acc\": 0.5801, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\", \"eval_method\": \"eval_ppl_ood.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"training_time_s\": 13660}, \"conclusion\": \"success\", \"log_path\": \"/tmp/eval_fromscratch_seed42.log\", \"completed_at\": \"2026-05-20T03:32:28.071Z\"}, \"hybrid_rho06_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T11:24:56.795Z\", \"updated_at\": \"2026-05-20T03:22:56.658Z\", \"spec\": {\"hypothesis\": \"Hybrid filter+reweight at ρ=0.6: remove q>0.95, then adaptive reweight. Tests if hybrid approach scales to higher contamination.\", \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"contamination_ratio\": 0.6, \"data_count\": 244502, \"command\": \"bash scripts/run_hybrid_rho06_seed42.sh\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data_hybrid_rho06.jsonl\", \"gpu\": \"cuda:3\", \"pid\": 3727, \"tau\": 0.7, \"n_min\": 2, \"weighting_method\": \"adaptive\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T00:17:27.859Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T00:17:28.940Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T00:17:34.914461+00:00\"}]}, \"metrics\": {\"eval_loss_holdout\": 2.8637, \"eval_ppl_holdout\": 17.526, \"eval_ppl_openwebtext\": 18.208, \"eval_ppl_wikipedia\": 15.267, \"downstream_arc_easy_acc_norm\": 0.6208, \"downstream_arc_challenge_acc_norm\": 0.3524, \"downstream_hellaswag_acc_norm\": 0.4801, \"downstream_piqa_acc_norm\": 0.6931, \"downstream_winogrande_acc\": 0.5785, \"eval_source\": \"rho06_tau07_seed42 eval worker - evaluated hybrid checkpoint by mistake\"}, \"hypothesis\": \"Hybrid filter+reweight on ρ=0.6: remove q>0.95 samples (extreme outliers) then apply adaptive reweighting to remainder. At higher contamination, extreme outliers distort ESS more severely, so pre-filtering should yield larger relative improvement over pure-adaptive than at ρ=0.4.\", \"parent\": \"hybrid_rho04_seed42\"}, \"rho06_tau07_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T02:19:11.044Z\", \"updated_at\": \"2026-05-20T03:20:40.603Z\", \"hypothesis\": \"Adaptive at ρ=0.6 with τ=0.7 (seed=42). results.tex L97 claims τ=0.7 optimal at ρ=0.6 but lacks complete eval. If PPL < current ρ=0.6 τ=0.8 result (17.73 batch_adaptive or hybrid 17.53), validates τ=0.7 as universal default across contamination levels.\", \"spec\": {\"command\": \"python train.py --weighting_method adaptive --contamination_ratio 0.6 --tau 0.7 --seed 42 --max_steps 6103 --batch_size 4 --learning_rate 5e-05 --model_name Qwen/Qwen3-0.6B\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"log_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/hybrid_rho06_seed42/step_metrics.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/hybrid_rho06_seed42/final\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-20T03:16:49.813Z\", \"metrics\": {\"eval_ppl_holdout\": 17.526, \"eval_ppl_openwebtext\": 18.208, \"eval_ppl_wikipedia\": 15.267, \"downstream_arc_easy_acc_norm\": 0.6208, \"downstream_arc_challenge_acc_norm\": 0.3524, \"downstream_hellaswag_acc_norm\": 0.4801, \"downstream_piqa_acc_norm\": 0.6931, \"downstream_winogrande_acc\": 0.5785}}, \"tau07_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:48:42.641Z\", \"updated_at\": \"2026-05-20T03:03:58.338Z\", \"hypothesis\": \"τ=0.7 sensitivity test (seed=42, ρ=0.4). Third seed for τ=0.7, completing 3-seed set (42/123/456) to match τ=0.8's 3 seeds. Enables paired 3-seed comparison for R3-N2 τ sensitivity response.\", \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --weighting_method adaptive --contamination_ratio 0.4 --tau 0.7 --seed 42\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"tau\": 0.7, \"n_min\": null, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"weighting_method\": \"adaptive\", \"log_path\": \"~/runs/provenance_weight_training/tau07_seed42.log\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/tau07_seed42/final\"}, \"metrics\": {\"eval_ppl_holdout\": 17.68, \"eval_ppl_openwebtext\": 18.348, \"eval_ppl_wikipedia\": 15.331, \"downstream_arc_easy_acc_norm\": 0.6166, \"downstream_arc_challenge_acc_norm\": 0.3473, \"downstream_hellaswag_acc_norm\": 0.4795, \"downstream_piqa_acc_norm\": 0.6861, \"downstream_winogrande_acc\": 0.5817, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\", \"eval_method\": \"eval_ppl_ood.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/tau07_seed42/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T03:03:58.338Z\"}, \"tau07_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:44:04.805Z\", \"updated_at\": \"2026-05-20T03:03:31.130Z\", \"hypothesis\": \"τ=0.7 sensitivity test (seed=456, ρ=0.4). R3-N2 requires multi-seed τ sensitivity data. Paired with tau07_seed123 for 2-seed mean±std at τ=0.7. Direct comparison against adaptive_ood_seed456 (τ=0.8, same seed) isolates τ effect.\", \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --data_path /root/autodl-tmp/provenance_weight_training/data/scored_data.jsonl --output_dir output/models/tau07_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.7 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model --save_steps 6103\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"344534\", \"log_path\": \"~/runs/provenance_weight_training/tau07_seed456.log\", \"submitted_at\": \"2026-05-19T20:46:27.554Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"tau\": 0.7, \"n_min\": 2, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"weighting_method\": \"adaptive\", \"wall_clock_seconds\": 22623.6, \"gpu_hours\": 6.28}, \"metrics\": {\"eval_ppl_holdout\": 17.677, \"eval_ppl_openwebtext\": 18.344, \"eval_ppl_wikipedia\": 15.315, \"downstream_arc_easy_acc_norm\": 0.6111, \"downstream_arc_challenge_acc_norm\": 0.3515, \"downstream_hellaswag_acc_norm\": 0.4811, \"downstream_piqa_acc_norm\": 0.6834, \"downstream_winogrande_acc\": 0.5722, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\", \"eval_method\": \"eval_ppl_ood.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/tau07_seed456/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T03:03:31.130Z\"}, \"tau07_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T20:44:02.827Z\", \"updated_at\": \"2026-05-20T03:03:29.289Z\", \"hypothesis\": \"τ=0.7 sensitivity test (seed=123, ρ=0.4). R3-N2 requires multi-seed τ sensitivity data. Currently have τ=0.8 × 3 seeds. Adding τ=0.7 × 2 seeds enables direct paired comparison: if τ=0.7 degrades PPL vs τ=0.8 at same seed, confirms τ=0.8 is near-optimal. If equivalent, suggests robustness to τ choice.\", \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --data_path /root/autodl-tmp/provenance_weight_training/data/scored_data.jsonl --output_dir output/models/tau07_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.7 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model --save_steps 6103\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"344455\", \"log_path\": \"~/runs/provenance_weight_training/tau07_seed123.log\", \"submitted_at\": \"2026-05-19T20:46:25.278Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"tau\": 0.7, \"n_min\": 2, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"weighting_method\": \"adaptive\", \"wall_clock_seconds\": 22624.0, \"gpu_hours\": 6.28}, \"metrics\": {\"eval_ppl_holdout\": 17.666, \"eval_ppl_openwebtext\": 18.348, \"eval_ppl_wikipedia\": 15.345, \"downstream_arc_easy_acc_norm\": 0.6309, \"downstream_arc_challenge_acc_norm\": 0.3481, \"downstream_hellaswag_acc_norm\": 0.4775, \"downstream_piqa_acc_norm\": 0.6866, \"downstream_winogrande_acc\": 0.5675, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\", \"eval_method\": \"eval_ppl_ood.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/tau07_seed123/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-20T03:03:29.289Z\"}, \"tau07_downstream_eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-20T02:19:08.294Z\", \"updated_at\": \"2026-05-20T03:02:14.151Z\", \"hypothesis\": \"Downstream eval for τ=0.7 (3 seeds). Paper switched main results to τ=0.7; must confirm downstream benchmarks match or exceed τ=0.8 and uniform. Reviewer will ask for downstream under recommended setting.\", \"spec\": {\"command\": \"lm_eval --model hf --tasks arc_easy,arc_challenge,hellaswag,piqa,winogrande on tau07_seed{42,123,456}\", \"server\": \"westd-41312\", \"data_path\": \"tau07_seed{42,123,456}/final\", \"data_count\": 5, \"model_name\": \"Qwen/Qwen3-0.6B (τ=0.7)\", \"seed\": 0, \"checkpoint_source\": \"tau07_seed42/123/456\", \"eval_data\": \"arc_easy,arc_challenge,hellaswag,piqa,winogrande\"}, \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-20T03:02:14.151Z\"}, \"uniform_ood_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T14:34:32.747Z\", \"updated_at\": \"2026-05-19T20:08:50.226Z\", \"hypothesis\": \"Retrain uniform (b=0, seed=123) with checkpoint saving for OOD eval. If in-dist PPL matches original 17.686 (±0.01), the checkpoint is valid for OOD generalization testing across OpenWebText/Wikipedia/FineWeb.\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method uniform --seed 123\", \"server\": \"westd-41312\", \"gpu\": \"cuda:2\", \"pid\": 313437, \"log_path\": \"~/runs/provenance_weight_training/uniform_ood_seed123.log\", \"submitted_at\": \"2026-05-19T14:37:08.809Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/provenance_weight_training/data/mixed_data.jsonl\", \"data_count\": 6103, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"wall_clock_seconds\": 14841.9, \"gpu_hours\": 4.12}, \"reproduce\": {\"finished_at\": \"2026-05-19T18:09:16.577Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T18:09:21.547740+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.6861, \"eval_ppl_openwebtext\": 18.3678, \"eval_ppl_wikipedia\": 15.3768, \"downstream_arc_easy_acc_norm\": 0.6229, \"downstream_arc_challenge_acc_norm\": 0.3507, \"downstream_hellaswag_acc_norm\": 0.4797, \"downstream_piqa_acc_norm\": 0.685, \"downstream_winogrande_acc\": 0.5762, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\"}, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/uniform_ood_seed123/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T18:44:30.750Z\"}, \"uniform_ood_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T14:34:34.440Z\", \"updated_at\": \"2026-05-19T20:08:44.104Z\", \"hypothesis\": \"Retrain uniform (b=0, seed=456) with checkpoint saving for OOD eval. If in-dist PPL matches original 17.702 (±0.01), the checkpoint is valid for OOD generalization testing across OpenWebText/Wikipedia/FineWeb.\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method uniform --seed 456\", \"server\": \"westd-41312\", \"gpu\": \"cuda:3\", \"pid\": 313688, \"log_path\": \"~/runs/provenance_weight_training/uniform_ood_seed456.log\", \"submitted_at\": \"2026-05-19T14:37:11.107Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/provenance_weight_training/data/mixed_data.jsonl\", \"data_count\": 6103, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"wall_clock_seconds\": 14841.4, \"gpu_hours\": 4.12}, \"reproduce\": {\"finished_at\": \"2026-05-19T18:09:49.204Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T18:09:57.258996+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.7015, \"eval_ppl_openwebtext\": 18.3865, \"eval_ppl_wikipedia\": 15.3594, \"downstream_arc_easy_acc_norm\": 0.6166, \"downstream_arc_challenge_acc_norm\": 0.3439, \"downstream_hellaswag_acc_norm\": 0.4826, \"downstream_piqa_acc_norm\": 0.6795, \"downstream_winogrande_acc\": 0.5667, \"downstream_eval_method\": \"lm_eval 0.4.11, 0-shot, float16, batch_size=auto\"}, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/uniform_ood_seed456/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T18:44:32.478Z\"}, \"w2_distribution_matching_eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:51:37.385Z\", \"updated_at\": \"2026-05-19T07:52:31.452Z\", \"hypothesis\": \"If adaptive weighting's FineWeb PPL improvement is genuine quality gain (not tautological distribution matching), then adaptive should also show lower PPL on non-FineWeb eval sets (C4/OpenWebText, Wikipedia). If the improvement is purely distribution matching, adaptive will only win on FineWeb-derived evals.\", \"spec\": {\"command\": \"eval_perplexity.py --checkpoints adaptive/uniform --data_path fineweb/openwebtext/wikipedia --max_docs 5000 --max_length 2048\", \"server\": \"westd-41312\", \"data_path\": \"data/human/eval_holdout.jsonl, data/eval_openwebtext.jsonl, data/eval_wikipedia.jsonl\", \"data_count\": \"5000 docs x 3 eval sets x 2 models = 6 runs\", \"model_name\": \"qwen06b adaptive_fix_seed42 vs qwen06b_uniform_seed42_v2\", \"seed\": 42, \"checkpoint_source\": \"adaptive_fix_seed42/final, qwen06b_uniform_seed42_v2/final\", \"eval_data\": \"FineWeb holdout (4.1M tokens), OpenWebText (6.8M tokens), Wikipedia (27M tokens)\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_fix_seed42/final\", \"log_path\": \"/tmp/eval_all.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-19T07:52:31.452Z\"}, \"detect_remove_q07_epoch_matched_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-18T23:59:28.901Z\", \"updated_at\": \"2026-05-19T03:07:24.735Z\", \"hypothesis\": \"Epoch-matched D&R q07: 1 epoch through q07 filtered data (184,908 samples, ~100M tokens, 3047 steps). Part of 5-point epoch-matched curve (q01/q03/q05/q07/q09). If PPL converges to ~17.65-17.74 range like q03(17.74) and q05(17.65), confirms U-shape sweet spot is entirely multi-epoch artifact across the full threshold range.\", \"reproduce\": {\"finished_at\": \"2026-05-19T03:02:01.393Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"completed_at\": \"2026-05-19T01:10:23.679Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-19T01:10:31.706284+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T03:02:06.510586+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q07.jsonl --output_dir /root/autodl-tmp/output/models/detect_remove_q07_epoch_matched_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --max_steps 3047 --seed 42\", \"server\": \"westd-30476\", \"data_path\": \"data/scored_data_filtered_q07.jsonl\", \"data_count\": 184908, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42}, \"notes\": \"首次运行 EXIT_CODE=1 失败(~70min)，自动重试后训练完成(3047 steps, 6425s, EXIT_CODE=0)。Model saved to /root/autodl-tmp/output/models/detect_remove_q07_epoch_matched_seed42/final。等待 eval holdout PPL。\", \"metrics\": {\"eval_ppl_holdout\": 17.62, \"eval_loss_holdout\": 2.8689, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"sliding_window_stride1024_maxlen2048_fp16_5000docs\", \"total_steps\": 3047}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q07_epoch_matched_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q07_epoch_matched_seed42.log\"}, \"detect_remove_q09_epoch_matched_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T00:28:26.693Z\", \"updated_at\": \"2026-05-19T02:49:02.649Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=3 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q09.jsonl --output_dir /root/autodl-tmp/output/models/detect_remove_q09_epoch_matched_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --max_steps 3770 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"89871\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q09_epoch_matched_seed42.log\", \"submitted_at\": \"2026-05-19T00:28:58.885Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q09.jsonl\", \"data_count\": 228743, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"wall_clock_seconds\": 8403.8, \"gpu_hours\": 2.33}, \"hypothesis\": \"Epoch-matched D&R q09: 1 epoch through q09 filtered data (228,743 samples, ~124M tokens, 3770 steps). Most lenient filter in the curve (61.6% retained, only 1.6x epochs in multi-epoch). Part of 5-point epoch-matched curve. If PPL converges to ~17.65-17.74 range, confirms U-shape is entirely multi-epoch artifact even at the least-filtered end.\", \"reproduce\": {\"finished_at\": \"2026-05-19T02:42:50.661Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T02:42:55.919377+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.628, \"eval_loss_holdout\": 2.8695, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"sliding_window_stride1024_maxlen2048_fp16_5000docs\", \"total_steps\": 3770, \"train_loss_final\": 9.9127}, \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q09_epoch_matched_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q09_epoch_matched_seed42.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-19T02:49:02.649Z\"}, \"detect_remove_q01_epoch_matched_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:27:06.364Z\", \"updated_at\": \"2026-05-19T00:33:17.339Z\", \"hypothesis\": \"Epoch-matched D&R q01: 1 epoch through q01 filtered data (55,799 samples, ~30M tokens, 919 steps). Most extreme filter (15% retained, 4.8x epochs in multi-epoch). If PPL ≈ 17.65 (same as epoch-matched q05 and q03), confirms ALL multi-epoch D&R advantages come from extra epochs regardless of threshold. Three epoch-matched points (q01, q03, q05) spanning the full threshold range converging to same PPL = clean confound isolation.\", \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q01.jsonl --output_dir .../detect_remove_q01_epoch_matched_seed42 --model_name Qwen3-0.6B --weighting_method uniform --max_steps 919 --seed 42\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"86112\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q01_epoch_matched_seed42.log\", \"submitted_at\": \"2026-05-18T23:51:39.940Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q01.jsonl\", \"data_count\": 55799, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"wall_clock_seconds\": 2497.4, \"gpu_hours\": 0.69}, \"reproduce\": {\"finished_at\": \"2026-05-19T00:24:24.218Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-19T00:24:30.596234+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 18.0436, \"eval_loss_holdout\": 2.8928, \"eval_holdout_tokens\": 4077068}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q01_epoch_matched_seed42/final\", \"completed_at\": \"2026-05-19T00:33:17.339Z\"}, \"ngram_uniform_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T14:14:25.095Z\", \"updated_at\": \"2026-05-19T00:08:24.320Z\", \"hypothesis\": \"Uniform baseline for n-gram detector comparison. Control condition: uniform weighting on ngram-scored data. Expected to perform worse than ngram_adaptive, confirming adaptive advantage generalizes across detectors.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --model_name models/Qwen/Qwen3-0.6B --data_path data/scored_data_ngram_qscore.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/ngram_uniform_seed42 --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --bf16 --save_only_model --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"227105\", \"log_path\": \"~/runs/provenance_weight_training/ngram_uniform_seed42.log\", \"submitted_at\": \"2026-05-18T15:01:05.106Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/ngram_uniform_seed42/final\", \"train_loss\": 7.99, \"train_runtime_s\": 12800, \"total_steps\": 6103, \"wall_clock_seconds\": 14808.9, \"gpu_hours\": 4.11}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T19:07:54.054Z\", \"metrics\": {\"eval_ppl_holdout\": 17.69, \"eval_loss_holdout\": 2.8733}}, \"detect_remove_q03_epoch_matched_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:18:10.019Z\", \"updated_at\": \"2026-05-18T23:35:57.701Z\", \"hypothesis\": \"Epoch-matched D&R q03: 1 epoch through q03 filtered data (116,935 samples, ~63M tokens, 1927 steps). If PPL ≈ 17.65 (same as epoch-matched q05), q03 vs q05 multi-epoch gap (17.25 vs 17.28) comes entirely from extra epochs (3.2x vs 2.4x), not data quality. If PPL significantly below 17.65, q03's stricter filtering genuinely yields higher quality data even at matched training budget.\", \"parent\": \"detect_remove_q03_seed42_r2\", \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q03.jsonl --output_dir .../detect_remove_q03_epoch_matched_seed42 --model_name Qwen3-0.6B --weighting_method uniform --max_steps 1927 --seed 42\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:2\"], \"pid\": \"78529\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q03_epoch_matched_seed42.log\", \"submitted_at\": \"2026-05-18T22:18:34.216Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q03.jsonl\", \"data_count\": 116935, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q03_epoch_matched_seed42/final\", \"wall_clock_seconds\": 4643.5, \"gpu_hours\": 1.29}, \"reproduce\": {\"finished_at\": \"2026-05-18T23:28:29.606Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T23:28:34.763822+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.74, \"eval_loss_holdout\": 2.876, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"sliding_window_stride1024_maxlen2048_fp16_5000docs\", \"total_steps\": 1927, \"train_loss_final\": 11.3917, \"interpretation\": \"PPL 17.74 vs epoch-matched q05 (17.65): q03 stricter filtering yields HIGHER PPL (+0.09) under matched training budget, not lower. This contradicts the hypothesis that stricter filtering improves data quality per-token. Meanwhile multi-epoch q03 (17.25) is much lower, confirming that the PPL advantage of q03 in multi-epoch setting comes from more training epochs on filtered data, not from higher per-token quality. Conclusion: under fixed training budget, stricter filtering (q03) actually hurts slightly compared to moderate filtering (q05), likely because removing too many borderline samples reduces diversity without sufficient quality gain.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T23:35:57.701Z\"}, \"gpt2_adaptive_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:27:04.666Z\", \"updated_at\": \"2026-05-18T23:32:50.660Z\", \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --model_name models/Qwen/Qwen3-0.6B --data_path data/scored_data_gpt2ppl_qscore.jsonl --output_dir .../gpt2_adaptive_seed42 --weighting_method adaptive --tau 0.8 --n_min 2 --seed 42\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"245417\", \"log_path\": \"~/runs/provenance_weight_training/gpt2_adaptive_seed42.log\", \"submitted_at\": \"2026-05-18T19:27:04.198Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_gpt2ppl_qscore.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/gpt2_adaptive_seed42/final\", \"wall_clock_seconds\": 14464.1, \"gpu_hours\": 4.02}, \"hypothesis\": \"GPT-2 PPL detector (AUC=0.913) + adaptive weighting: tests whether a weaker but practical detector still enables effective adaptive training. If adaptive PPL < uniform with GPT-2 scores, method generalizes beyond high-AUC TF-IDF detector.\", \"reproduce\": {\"finished_at\": \"2026-05-18T23:25:26.511Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T23:25:31.727843+00:00\"}]}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/gpt2_adaptive_seed42/final\", \"metrics\": {\"eval_ppl_holdout\": 17.79, \"eval_loss_holdout\": 2.879, \"train_loss\": 10.58, \"train_steps\": 6103, \"train_runtime_hours\": 3.92}, \"completed_at\": \"2026-05-18T23:28:08.287Z\"}, \"gpt2_uniform_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:27:06.537Z\", \"updated_at\": \"2026-05-18T23:08:25.414Z\", \"spec\": {\"command\": \"WANDB_MODE=disabled python training/pretrain_weighted.py --model_name models/Qwen/Qwen3-0.6B --data_path data/scored_data_gpt2ppl_qscore.jsonl --output_dir .../gpt2_uniform_seed42 --weighting_method uniform --seed 42\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"245496\", \"log_path\": \"~/runs/provenance_weight_training/gpt2_uniform_seed42.log\", \"submitted_at\": \"2026-05-18T19:27:06.149Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_gpt2ppl_qscore.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/gpt2_uniform_seed42/final\", \"wall_clock_seconds\": 13279.3, \"gpu_hours\": 3.69}, \"hypothesis\": \"GPT-2 PPL-scored data with uniform weighting (no provenance reweighting) serves as a baseline; without adaptive weighting, the model cannot distinguish high-quality from low-quality training data, resulting in higher holdout perplexity compared to adaptive methods.\", \"reproduce\": {\"finished_at\": \"2026-05-18T23:02:03.184Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T23:02:07.864942+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.69, \"eval_loss_holdout\": 2.8733, \"train_loss\": 7.989, \"train_steps\": 6103, \"train_runtime_hours\": 3.54}, \"completed_at\": \"2026-05-18T23:08:25.414Z\"}, \"detect_remove_q06_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:57:05.891Z\", \"updated_at\": \"2026-05-18T22:01:54.629Z\", \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=2 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q06.jsonl --output_dir /root/autodl-tmp/output/models/detect_remove_q06_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --bf16 --save_total_limit 3 --logging_steps 10 --save_steps 500'\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:2\"], \"pid\": \"60238\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_q06_seed42.log\", \"submitted_at\": \"2026-05-18T17:57:05.534Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_filtered_q06.jsonl\", \"data_count\": 170000, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q06_seed42/checkpoint-6103\", \"wall_clock_seconds\": 14689.1, \"gpu_hours\": 4.08}, \"hypothesis\": \"D&R threshold t=0.6: keep q≤0.6 samples. Densification point between q05 (PPL=17.28) and q07 (PPL=17.32). Shows degradation slope as more contaminated data is included. Part of expanded 9-point D&R threshold curve.\", \"reproduce\": {\"finished_at\": \"2026-05-18T21:31:47.836Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T21:31:53.610706+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.3, \"eval_loss_holdout\": 2.8507}, \"completed_at\": \"2026-05-18T22:01:54.629Z\"}, \"adaptive_1_7b_planb_control\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:27:09.816Z\", \"updated_at\": \"2026-05-18T19:27:09.816Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --model_name /root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed42/checkpoint-2500 --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_planb_control --weighting_method adaptive --contamination_ratio 0.4 --num_train_tokens 100000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"245637\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_1_7b_planb_control.log\", \"submitted_at\": \"2026-05-18T19:27:09.389Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"eval_q01_final\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:16:20.167Z\", \"updated_at\": \"2026-05-18T19:16:20.167Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && python eval_perplexity.py --checkpoints /root/autodl-tmp/output/models/detect_remove_q01_seed42/final --data_path data/eval_holdout.jsonl --max_docs 5000 --max_length 2048\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"64266\", \"log_path\": \"~/runs/provenance_weight_training/eval_q01_final.log\", \"submitted_at\": \"2026-05-18T19:16:19.810Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"adaptive_1_7b_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T11:47:25.251Z\", \"updated_at\": \"2026-05-18T19:07:03.284Z\", \"hypothesis\": \"Scale validation: adaptive provenance weighting on Qwen3-1.7B (2.8x larger than 0.6B). If adaptive still outperforms uniform at 1.7B scale, demonstrates method generality beyond small models. Key for Main conference upgrade (D079 Line B). Expected: adaptive < uniform by ≥0.03 PPL (consistent with 0.6B gap).\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --model_name models/Qwen/Qwen3-1.7B --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed42 --weighting_method adaptive --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --resume_from_checkpoint /root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed42/checkpoint-2500\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"226766\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_1_7b_seed42.log\", \"submitted_at\": \"2026-05-18T15:00:59.483Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed42/final\", \"train_loss\": 5.36, \"train_runtime_s\": 10990, \"total_steps\": 6103, \"wall_clock_seconds\": 14763.8, \"gpu_hours\": 4.1}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T19:07:03.284Z\"}, \"status_check_41312\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:32:36.750Z\", \"updated_at\": \"2026-05-18T18:32:36.750Z\", \"spec\": {\"command\": \"bash -c \\\"sleep 120 && echo '=== eval_uniform_1_7b_v2 log ===' && cat /root/runs/provenance_weight_training/eval_uniform_1_7b_v2.log && echo '=== nvidia-smi ===' && nvidia-smi && echo '=== adaptive_1_7b progress ===' && ls -la /root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed42/ && tail -5 /root/runs/provenance_weight_training/adaptive_1_7b_seed42.log && echo '=== ngram progress ===' && ls /root/autodl-tmp/provenance_weight_training/output/models/ngram_adaptive_seed42/ && ls /root/autodl-tmp/provenance_weight_training/output/models/ngram_uniform_seed42/\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"240306\", \"log_path\": \"~/runs/provenance_weight_training/status_check_41312.log\", \"submitted_at\": \"2026-05-18T18:32:36.404Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"eval_adaptive_1_7b\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:32:07.436Z\", \"updated_at\": \"2026-05-18T18:32:07.436Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/provenance_weight_training && echo '=== Checking adaptive_1_7b final ===' && ls -la output/models/adaptive_1_7b_seed42/final/ 2>/dev/null && echo '=== Starting adaptive_1_7b eval ===' && python eval_perplexity.py --checkpoints output/models/adaptive_1_7b_seed42/final --data_path data/human/eval_holdout.jsonl || echo 'EVAL FAILED - final directory may not exist yet'\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/provenance_weight_training/eval_adaptive_1_7b.log\", \"submitted_at\": \"2026-05-18T18:32:07.080Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"eval_uniform_1_7b_v2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:32:05.664Z\", \"updated_at\": \"2026-05-18T18:32:05.664Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/provenance_weight_training && nvidia-smi && echo '=== Starting uniform_1_7b eval ===' && python eval_perplexity.py --checkpoints output/models/uniform_1_7b_seed42_resumed/final --data_path data/human/eval_holdout.jsonl\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"240255\", \"log_path\": \"~/runs/provenance_weight_training/eval_uniform_1_7b_v2.log\", \"submitted_at\": \"2026-05-18T18:32:05.316Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"eval_uniform_1_7b_resumed\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:59:51.854Z\", \"updated_at\": \"2026-05-18T17:59:51.854Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/provenance_weight_training && python eval_perplexity.py --checkpoints output/models/uniform_1_7b_seed42_resumed/final --data_path data/human/eval_holdout.jsonl\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/provenance_weight_training/eval_uniform_1_7b_resumed.log\", \"submitted_at\": \"2026-05-18T17:59:51.470Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"uniform_1_7b_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T11:47:26.566Z\", \"updated_at\": \"2026-05-18T15:45:29.875Z\", \"hypothesis\": \"Uniform weighting baseline on Qwen3-1.7B for scale validation. Control condition for comparing adaptive provenance weighting at larger model scale. Part of D079 Line B.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --model_name models/Qwen/Qwen3-1.7B --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed42 --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --resume_from_checkpoint /root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed42/checkpoint-3000\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"226623\", \"log_path\": \"~/runs/provenance_weight_training/uniform_1_7b_seed42.log\", \"submitted_at\": \"2026-05-18T15:00:55.785Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 2489.8, \"gpu_hours\": 0.69}, \"reproduce\": {\"finished_at\": \"2026-05-18T15:42:18.572Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-18T15:42:25.542Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T15:42:32.973826+00:00\"}]}, \"notes\": \"失败原因: FileNotFoundError — checkpoint-3000/trainer_state.json 缺失，resume 崩溃 | 已有成果: checkpoint-3000 存在但不完整 | 建议: 找有效 checkpoint 重 resume 或从头训练\"}, \"detect_remove_q09_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T07:41:18.054Z\", \"updated_at\": \"2026-05-18T14:09:50.472Z\", \"hypothesis\": \"D&R threshold t=0.9 (most lenient): keep q≤0.9 (228,743 samples, 61.6%), only removing the most confidently synthetic data. Expected PPL close to uniform baseline since minimal data is removed. Part of threshold sensitivity sweep (t=0.1/0.3/0.5/0.7/0.9) showing D&R requires careful calibration while adaptive does not.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q09.jsonl --output_dir /root/autodl-tmp/output/models/detect_remove_q09_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\", \"server\": \"westd-30476\", \"gpu\": 3, \"data_path\": \"data/scored_data_filtered_q09.jsonl\", \"data_count\": 228743, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"pid\": 27362, \"tmux_session\": \"detect_remove_q09_seed42\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/detect_remove_q09_seed42\", \"log_path\": \"/root/autodl-tmp/output/models/detect_remove_q09_seed42.log\"}, \"failure_reason\": \"startup recovery: process dead, no active cron monitor\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T12:59:21.395Z\", \"metrics\": {\"eval_ppl_holdout\": 17.42, \"eval_loss_holdout\": 2.8577, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --checkpoints --max_docs 5000 --max_length 2048 --stride 1024 --fp16\"}}, \"contamination_60_ess_only_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T06:18:41.546Z\", \"updated_at\": \"2026-05-18T12:55:23.532Z\", \"hypothesis\": \"Cross-seed replication (seed456) of ESS-only at ρ=0.6. D075 found ESS-only(17.770) ≈ uniform(17.766) at ρ=0.6, suggesting max-intervention collapses at high contamination. 3-seed data tests if this collapse is robust or seed-specific, strengthening Claim 1 four-tier hierarchy cross-ρ evidence.\", \"parent\": \"contamination_60_ess_only_seed42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_ess_only_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method ess_only --contamination_ratio 0.6 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"models/Qwen/Qwen3-0.6B\", \"eval_data\": \"N/A (training experiment, not eval)\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.762, \"eval_loss_holdout\": 2.8771, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --checkpoints --max_docs 5000 --max_length 2048\"}, \"checkpoint_path\": \"/root/provenance_weight_training/output/contamination_60_ess_only_seed456/\", \"log_path\": \"/root/provenance_weight_training/logs/contamination_60_ess_only_seed456.log\", \"completed_at\": \"2026-05-18T12:31:20.928Z\"}, \"contamination_60_ess_only_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T06:18:40.225Z\", \"updated_at\": \"2026-05-18T12:55:22.289Z\", \"hypothesis\": \"Cross-seed replication (seed123) of ESS-only at ρ=0.6. D075 found ESS-only(17.770) ≈ uniform(17.766) at ρ=0.6, suggesting max-intervention collapses at high contamination. 3-seed data tests if this collapse is robust or seed-specific, strengthening Claim 1 four-tier hierarchy cross-ρ evidence.\", \"parent\": \"contamination_60_ess_only_seed42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_ess_only_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method ess_only --contamination_ratio 0.6 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.763, \"eval_loss_holdout\": 2.8771, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --checkpoints --max_docs 5000 --max_length 2048\"}, \"checkpoint_path\": \"/root/provenance_weight_training/output/contamination_60_ess_only_seed123/\", \"log_path\": \"/root/provenance_weight_training/logs/contamination_60_ess_only_seed123.log\", \"completed_at\": \"2026-05-18T12:31:22.387Z\"}, \"ess_only_seed456_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T20:25:26.810Z\", \"updated_at\": \"2026-05-18T12:35:23.819Z\", \"hypothesis\": \"ESS-only (max-intervention) seed456 re-run on westd-41312: b* = max{b : ESS(b) >= n_min} — proves dual-constraint adaptive (min-intervention) superior to ESS-only across seeds\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export WANDB_MODE=disabled && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/ess_only_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method ess_only --contamination_ratio 0.4 --n_min 2 --tau 0.8 --max_steps 6103 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --warmup_ratio 0.05 --weight_decay 0.01 --bf16 --save_total_limit 3 --save_only_model --resume_from_checkpoint /root/autodl-tmp/provenance_weight_training/output/models/ess_only_seed456/checkpoint-2500\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:1\"], \"pid\": \"133521\", \"log_path\": \"~/runs/provenance_weight_training/ess_only_seed456_r2.log\", \"submitted_at\": \"2026-05-17T21:00:43.303Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 219.9, \"gpu_hours\": 0.06}, \"reproduce\": {\"finished_at\": \"2026-05-17T21:04:21.425Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T21:04:23.229Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T21:04:28.148336+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.762, \"eval_loss_holdout\": 2.877, \"eval_holdout_tokens\": 4077068, \"total_steps\": 6103, \"train_loss\": 5.998, \"train_runtime_seconds\": 7611}}, \"ess_only_seed123_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T20:25:27.652Z\", \"updated_at\": \"2026-05-18T12:35:22.330Z\", \"hypothesis\": \"ESS-only (max-intervention) seed123 re-run on westd-41312: b* = max{b : ESS(b) >= n_min} — proves dual-constraint adaptive (min-intervention) superior to ESS-only across seeds\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export WANDB_MODE=disabled && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/ess_only_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method ess_only --contamination_ratio 0.4 --n_min 2 --tau 0.8 --max_steps 6103 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --warmup_ratio 0.05 --weight_decay 0.01 --bf16 --save_total_limit 3 --save_only_model --resume_from_checkpoint /root/autodl-tmp/provenance_weight_training/output/models/ess_only_seed123/checkpoint-2000\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"133444\", \"log_path\": \"~/runs/provenance_weight_training/ess_only_seed123_r2.log\", \"submitted_at\": \"2026-05-17T21:00:40.838Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 234.0, \"gpu_hours\": 0.06}, \"reproduce\": {\"finished_at\": \"2026-05-17T21:04:32.320Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T21:04:34.797Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T21:04:40.672713+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.721, \"eval_loss_holdout\": 2.8747, \"eval_holdout_tokens\": 4077068, \"total_steps\": 6103, \"train_loss\": 6.86, \"train_runtime_seconds\": 8674}}, \"detect_remove_q05_epoch_matched_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T07:20:02.608Z\", \"updated_at\": \"2026-05-18T12:31:37.482Z\", \"hypothesis\": \"Epoch-matched control: training with uniform weighting on filtered data (q>0.5 removed) for exactly 2533 steps (matching content-level 1 epoch of the contaminated data). If PPL is comparable to the full 6103-step D&R run, the D&R benefit comes from data quality not extra training; if PPL is worse, the extra training contributes meaningfully.\", \"notes\": \"Content-level 1 epoch: 153K samples × ~540 avg tokens = ~83M tokens → max_steps=2533. NOT Trainer epoch (9607 steps/315M tokens).\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_filtered_q05.jsonl --output_dir /root/autodl-tmp/output/models/detect_remove_q05_epoch_matched_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.4 --max_steps 2533 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\", \"server\": \"westd-30476\", \"gpu\": 2, \"data_path\": \"data/scored_data_filtered_q05.jsonl\", \"data_count\": 153725, \"model_name\": \"models/Qwen/Qwen3-0.6B\", \"seed\": 42, \"pid\": 20387, \"output_dir\": \"/root/autodl-tmp/output/models/detect_remove_q05_epoch_matched_seed42\", \"log_path\": \"/root/autodl-tmp/output/logs/detect_remove_q05_epoch_matched_seed42.log\", \"tmux_session\": \"detect_remove_q05_epoch_matched_seed42\", \"weighting_method\": \"uniform\", \"max_steps\": 2533}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.65, \"eval_loss_holdout\": 2.8707, \"eval_holdout_tokens\": 4077068, \"train_loss_final\": 3.184, \"total_steps\": 2533, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048 --stride 1024 --fp16\", \"vs_full_dr_q05\": \"+0.360 (17.650 vs 17.290, epoch-matched worse)\", \"vs_adaptive\": \"-0.001 (17.650 vs 17.651, nearly identical to adaptive)\", \"interpretation\": \"D&R 0.36 PPL advantage over epoch-matched is entirely from multi-epoch training on clean data, not from data quality filtering\"}, \"checkpoint_path\": \"/root/provenance_weight_training/output/detect_remove_q05_epoch_matched_seed42/\", \"completed_at\": \"2026-05-18T12:31:37.482Z\"}, \"contamination_60_random_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T06:18:42.911Z\", \"updated_at\": \"2026-05-18T12:31:19.522Z\", \"hypothesis\": \"Cross-seed replication (seed123) of random reweighting at ρ=0.6. Random weights ignore detector scores entirely. If PPL > ESS-only and > uniform (consistent with seed42), completes four-tier ablation hierarchy (adaptive < uniform < ESS-only < random) at ρ=0.6 with 3-seed evidence, confirming Claim 1 holds cross-ρ.\", \"parent\": \"contamination_60_random_seed42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_random_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method random --contamination_ratio 0.6 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\", \"server\": \"westd-41312\", \"gpu\": 2, \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"models/Qwen/Qwen3-0.6B\", \"eval_data\": \"N/A (training experiment, not eval)\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.87, \"eval_loss_holdout\": 2.8832, \"eval_holdout_tokens\": 4077068}, \"checkpoint_path\": \"/root/provenance_weight_training/output/contamination_60_random_seed123/\", \"log_path\": \"/root/provenance_weight_training/logs/contamination_60_random_seed123.log\", \"completed_at\": \"2026-05-18T12:31:19.522Z\"}, \"contamination_60_random_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T06:18:44.245Z\", \"updated_at\": \"2026-05-18T12:31:18.086Z\", \"hypothesis\": \"Cross-seed replication (seed456) of random reweighting at ρ=0.6. Random weights ignore detector scores entirely. If PPL > ESS-only and > uniform (consistent with seed42), completes four-tier ablation hierarchy (adaptive < uniform < ESS-only < random) at ρ=0.6 with 3-seed evidence, confirming Claim 1 holds cross-ρ.\", \"parent\": \"contamination_60_random_seed42\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_random_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method random --contamination_ratio 0.6 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\", \"server\": \"westd-41312\", \"gpu\": 3, \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"models/Qwen/Qwen3-0.6B\", \"eval_data\": \"N/A (training experiment, not eval)\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.88, \"eval_loss_holdout\": 2.8837, \"eval_holdout_tokens\": 4077068}, \"checkpoint_path\": \"/root/provenance_weight_training/output/contamination_60_random_seed456/\", \"log_path\": \"/root/provenance_weight_training/logs/contamination_60_random_seed456.log\", \"completed_at\": \"2026-05-18T12:31:18.086Z\"}, \"uniform_1_7b_seed42_r2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:08:26.207Z\", \"updated_at\": \"2026-05-18T12:08:26.207Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=3 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/uniform_1_7b_seed42 --model_name /root/autodl-tmp/provenance_weight_training/models/Qwen/Qwen3-1.7B --weighting_method uniform --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"212584\", \"log_path\": \"~/runs/provenance_weight_training/uniform_1_7b_seed42_r2.log\", \"submitted_at\": \"2026-05-18T12:08:25.866Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"adaptive_1_7b_seed42_r2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:08:21.071Z\", \"updated_at\": \"2026-05-18T12:08:21.071Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=2 WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/adaptive_1_7b_seed42 --model_name /root/autodl-tmp/provenance_weight_training/models/Qwen/Qwen3-1.7B --weighting_method adaptive --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"212439\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_1_7b_seed42_r2.log\", \"submitted_at\": \"2026-05-18T12:08:20.748Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"eval_rho06_batch_v6\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:08:16.687Z\", \"updated_at\": \"2026-05-18T12:08:16.687Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=0 python eval_perplexity.py --checkpoint_paths /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_ess_only_seed123/final /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_ess_only_seed456/final /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_random_seed123/final /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_random_seed456/final --data_path data/human/eval_holdout.jsonl --max_docs 5000 --max_length 2048 --stride 1024 --fp16 2>&1 | tee /tmp/eval_rho06_batch.log\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"212283\", \"log_path\": \"~/runs/provenance_weight_training/eval_rho06_batch_v6.log\", \"submitted_at\": \"2026-05-18T12:08:16.111Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"env_probe_41312_v2\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:07:47.283Z\", \"updated_at\": \"2026-05-18T12:07:47.283Z\", \"spec\": {\"command\": \"bash -c \\\"find /root -maxdepth 4 -name 'python*' -type f 2>/dev/null | head -20 && echo '---' && find /usr -maxdepth 4 -name 'python*' -type f 2>/dev/null | head -10 && echo '---' && ls /root/.venv/bin/python* 2>/dev/null && ls /root/venv/bin/python* 2>/dev/null && cat /root/.profile 2>/dev/null | head -20\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/provenance_weight_training/env_probe_41312_v2.log\", \"submitted_at\": \"2026-05-18T12:07:46.950Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"env_probe_41312\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:07:29.821Z\", \"updated_at\": \"2026-05-18T12:07:29.821Z\", \"spec\": {\"command\": \"bash -c \\\"echo PATH=$PATH && which python3 2>/dev/null && which python 2>/dev/null && ls /root/miniconda3/bin/python 2>/dev/null && ls /root/anaconda3/bin/python 2>/dev/null && ls /opt/conda/bin/python 2>/dev/null && cat /root/.bashrc 2>/dev/null | grep -i 'conda\\\\|python\\\\|PATH' || echo 'no matches'\\\"\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/provenance_weight_training/env_probe_41312.log\", \"submitted_at\": \"2026-05-18T12:07:29.499Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"eval_rho06_batch_v5\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T11:47:24.659Z\", \"updated_at\": \"2026-05-18T12:06:30.452Z\", \"spec\": {\"command\": \"cd /root/provenance_weight_training && CUDA_VISIBLE_DEVICES=0 python eval_perplexity.py --checkpoint_paths /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_ess_only_seed123/final /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_ess_only_seed456/final /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_random_seed123/final /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_random_seed456/final --data_path data/human/eval_holdout.jsonl --max_docs 5000 --max_length 2048 --stride 1024 --fp16 2>&1 | tee /tmp/eval_rho06_batch.log\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/provenance_weight_training/eval_rho06_batch_v5.log\", \"submitted_at\": \"2026-05-18T12:06:30.114Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"contamination_60_grid_b0_3_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-18T04:04:45.048Z\", \"updated_at\": \"2026-05-18T09:24:10.985Z\", \"hypothesis\": \"Grid b=0.3 at ρ=0.6: tests whether grid-best remains near b=0.3 at higher contamination. If PPL ≈ contamination_60_seed42_r2 (adaptive, 17.74), confirms adaptive ≈ grid-best holds cross-ρ, strengthening Claim 2 generality.\", \"parent\": \"contamination_60_seed42_r2\", \"failure_reason\": \"SSH check failed 5x — last error: [Errno None] Unable to connect to port 30476 on 36.103.198.204\", \"completed_at\": \"2026-05-18T05:20:42.781Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T05:20:47.849092+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method grid --grid_b_value 0.3 --contamination_ratio 0.6 --resume_from_checkpoint checkpoint-1500\", \"server\": \"westd-30476\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 200000000, \"model_name\": \"models/Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"contamination_60_grid_b0_3_seed42/checkpoint-1500\", \"eval_data\": \"data/scored_data_60.jsonl\"}, \"checkpoint_path\": \"/root/autodl-tmp/output/models/contamination_60_grid_b0_3_seed42/final\", \"log_path\": \"/root/autodl-tmp/output/models/contamination_60_grid_b0_3_seed42/train_resume.log\", \"metrics\": {\"eval_ppl_holdout\": 17.634, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048 --stride 1024 --fp16\", \"checkpoint_1500_ppl\": 18.583, \"total_steps\": 6103, \"note\": \"resume from checkpoint-1500 with ~30% LR offset; final PPL improved over checkpoint-1500, no degradation\"}, \"conclusion\": \"success\"}, \"contamination_60_random_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T04:27:24.364Z\", \"updated_at\": \"2026-05-18T09:23:46.870Z\", \"hypothesis\": \"Random reweighting baseline at ρ=0.6: random weights ignore detector scores entirely. If PPL > ESS-only (17.77) and > uniform (17.766), completes four-tier ablation hierarchy (adaptive < uniform < ESS-only < random) at ρ=0.6, confirming Claim 1 structural argument holds cross-ρ.\", \"parent\": \"\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir /root/autodl-tmp/output/models/contamination_60_random_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method random --contamination_ratio 0.6 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\", \"server\": \"westd-30476\", \"gpu\": \"cuda:3\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-18T08:36:52.838Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T08:36:54.608Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T08:37:00.026076+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.832, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048 --stride 1024 --fp16\", \"total_steps\": 6103, \"note\": \"resume from checkpoint-1000; cron falsely marked failed due to log path mismatch\"}, \"checkpoint_path\": \"/root/autodl-tmp/output/models/contamination_60_random_seed42/final\", \"log_path\": \"/root/autodl-tmp/output/models/contamination_60_random_seed42/train_resume.log\"}, \"grid_b0_2_seed456\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-18T01:38:11.212Z\", \"updated_at\": \"2026-05-18T06:13:39.221Z\", \"hypothesis\": \"Cross-seed replication (seed456) of grid b=0.2: 3rd seed for b=0.2 plateau confirmation, completing Claim 2 cross-seed grid curve at the optimal region.\", \"parent\": \"grid_b0_2_seed42\", \"failure_reason\": \"SSH check failed 5x — last error: [Errno None] Unable to connect to port 30476 on 36.103.198.204\", \"completed_at\": \"2026-05-18T05:20:07.918Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"python training/pretrain_weighted.py --resume_from_checkpoint checkpoint-5500 --weighting_method grid --grid_b_value 0.2 --seed 456\", \"server\": \"westd-30476\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 200000000, \"model_name\": \"Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"grid_b0_2_seed456/checkpoint-5500\", \"eval_data\": \"N/A (training, not eval)\"}, \"metrics\": {\"eval_ppl_holdout\": 17.645, \"eval_loss_holdout\": 2.87, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048 --stride 1024 --fp16\", \"eval_checkpoint\": \"checkpoint-5500\", \"note\": \"eval at checkpoint-5500; final checkpoint degraded due to --save_only_model LR reset on resume\"}, \"checkpoint_path\": \"/root/autodl-tmp/output/models/grid_b0_2_seed456/checkpoint-5500\", \"log_path\": \"/root/autodl-tmp/output/models/grid_b0_2_seed456/step_metrics.jsonl\", \"conclusion\": \"success\"}, \"grid_b0_2_seed123\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-18T01:38:09.495Z\", \"updated_at\": \"2026-05-18T06:13:37.877Z\", \"hypothesis\": \"Cross-seed replication (seed123) of grid b=0.2: if PPL ≈ grid_b0_2_seed42 (17.64) and within plateau [0.2,0.3], confirms grid-best region is not seed-specific, strengthening Claim 2.\", \"parent\": \"grid_b0_2_seed42\", \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-18T05:20:30.898Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T05:20:39.515822+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-18T05:59:17.253325+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"python training/pretrain_weighted.py --resume_from_checkpoint checkpoint-5500 --weighting_method grid --grid_b_value 0.2 --seed 123\", \"server\": \"westd-30476\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 200000000, \"model_name\": \"Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"grid_b0_2_seed123/checkpoint-5500\", \"eval_data\": \"N/A (training, not eval)\"}, \"metrics\": {\"eval_ppl_holdout\": 17.637, \"eval_loss_holdout\": 2.87, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048 --stride 1024 --fp16\", \"eval_checkpoint\": \"checkpoint-5500\", \"note\": \"eval at checkpoint-5500; final checkpoint degraded due to --save_only_model LR reset on resume\"}, \"checkpoint_path\": \"/root/autodl-tmp/output/models/grid_b0_2_seed123/checkpoint-5500\", \"log_path\": \"/root/autodl-tmp/output/models/grid_b0_2_seed123/step_metrics.jsonl\", \"conclusion\": \"success\", \"reproduce\": {\"finished_at\": \"2026-05-18T05:59:08.599Z\"}}, \"contamination_60_adaptive_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T01:38:05.737Z\", \"updated_at\": \"2026-05-18T05:56:46.834Z\", \"hypothesis\": \"Cross-seed replication (seed456) of adaptive weighting at ρ=0.6: pairs with contamination_60_uniform_seed456 for 3rd seed contrast. If adaptive PPL < uniform PPL at ρ=0.6, completes Claim 3 proportion-robustness 3-seed evidence.\", \"parent\": \"contamination_60_seed42_r2\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/contamination_60_adaptive_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --tau 0.8 --n_min 2 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:0\"], \"pid\": \"158632\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_adaptive_seed456.log\", \"submitted_at\": \"2026-05-18T01:44:51.691Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"contamination_60_seed42_r2\", \"eval_data\": \"data/scored_data_60.jsonl\", \"wall_clock_seconds\": 14209.4, \"gpu_hours\": 3.95}, \"reproduce\": {\"finished_at\": \"2026-05-18T05:36:41.822Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T05:36:46.155880+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.735, \"eval_loss_holdout\": 2.8755, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --stride 1024 --fp16\"}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/contamination_60_adaptive_seed456/final\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_adaptive_seed456.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T05:41:41.076Z\"}, \"grid_b0_1_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T01:41:20.961Z\", \"updated_at\": \"2026-05-18T05:28:09.690Z\", \"hypothesis\": \"Grid-b sweep b=0.1 on ρ=0.4 data, seed123. Minimal reweighting to establish lower bound of useful b range. Expect PPL close to uniform (~17.694) and consistent with seed42 result (17.657).\", \"parent\": \"grid_b0_1_seed42\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/grid_b0_1_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method grid --grid_b_value 0.1 --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"pid\": \"158918\", \"log_path\": \"~/runs/provenance_weight_training/grid_b0_1_seed123.log\", \"submitted_at\": \"2026-05-18T01:45:00.689Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 247666, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"grid_b0_1_seed42\", \"eval_data\": \"data/scored_data.jsonl\", \"wall_clock_seconds\": 13365.6, \"gpu_hours\": 3.71}, \"reproduce\": {\"finished_at\": \"2026-05-18T05:19:43.419Z\"}, \"metrics\": {\"eval_ppl_holdout\": 17.646, \"eval_loss_holdout\": 2.8705, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048 --fp16\"}, \"checkpoint_path\": \"output/models/grid_b0_1_seed123/final\", \"log_path\": \"~/runs/provenance_weight_training/grid_b0_1_seed123.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T05:27:46.319Z\"}, \"grid_b0_1_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T01:41:21.496Z\", \"updated_at\": \"2026-05-18T05:28:09.099Z\", \"hypothesis\": \"Grid-b sweep b=0.1 on ρ=0.4 data, seed456. Minimal reweighting to establish lower bound of useful b range. Expect PPL close to uniform (~17.694) and consistent with seed42 result (17.657).\", \"parent\": \"grid_b0_1_seed42\", \"spec\": {\"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"159304\", \"data_path\": \"data/scored_data.jsonl\", \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"command\": \"python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/provenance_weight_training/output/models/grid_b0_1_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method grid --grid_b_value 0.1 --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\", \"data_count\": 247666, \"checkpoint_source\": \"grid_b0_1_seed42\", \"eval_data\": \"data/scored_data.jsonl\"}, \"reproduce\": {\"finished_at\": \"2026-05-18T05:19:52.891Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T05:20:03.157900+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.663, \"eval_loss_holdout\": 2.8715, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048 --fp16\"}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/grid_b0_1_seed456/final\", \"log_path\": \"~/runs/provenance_weight_training/grid_b0_1_seed456.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T05:27:34.520Z\"}, \"contamination_60_ess_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:29:38.654Z\", \"updated_at\": \"2026-05-18T04:48:21.069Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir output/models/contamination_60_ess_only_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method ess_only --contamination_ratio 0.6 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:2\"], \"pid\": \"265012\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_ess_only_seed42.log\", \"submitted_at\": \"2026-05-15T23:29:46.475Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A\", \"eval_data\": \"N/A\", \"wall_clock_seconds\": 14168.4, \"gpu_hours\": 3.94}, \"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-15T23:29:46.475Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir output/models/contamination_60_ess_only_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method ess_only --contamination_ratio 0.6 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"finished_at\": \"2026-05-16T03:10:18.007Z\", \"training_hours\": 3.68}, \"pid\": \"265012\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_ess_only_seed42.log\", \"hypothesis\": \"ESS-only (max-intervention) on ρ=0.6 data: b* = max{b : ESS(b) ≥ n_min}. Tests if dual-constraint advantage over ESS-only holds at higher contamination (ρ=0.4→0.6). Paired with adaptive and grid_b0.5 for Claim 1+3 cross-validation.\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T03:10:20.449362+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.77, \"eval_loss_holdout\": 2.8775, \"eval_holdout_tokens\": 4077068, \"train_loss\": 9.842, \"total_steps\": 6103, \"train_runtime_seconds\": 13152}, \"checkpoint_path\": \"output/models/contamination_60_ess_only_seed42/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T03:25:54.836Z\", \"notes\": \"ρ=0.6 ESS-only PPL=17.77 ≈ uniform (17.766), max-intervention 在高 contamination 下完全失效。vs ρ=0.4 ESS-only avg 17.723 → ρ增加0.2导致+0.047退化。关键对比: dual(17.74) < ESS-only(17.77), Claim 1 在 ρ=0.6 下仍成立(gap=0.03, 小于 ρ=0.4 的 gap=0.07)。ESS-only 崩溃而 dual 仍有效 → 强化 \\\"dual-constraint 在高 contamination 下更重要\\\" 叙事。⚠️ 服务器 westd-47453 已下线，checkpoint 不可用。eval 结果已记录在 registry metrics 中。\"}, \"contamination_60_uniform_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T00:12:01.324Z\", \"updated_at\": \"2026-05-18T03:30:01.455Z\", \"hypothesis\": \"Uniform baseline at ρ=0.6 seed123: pairs with contamination_60_seed123 (adaptive) to form seed123 uniform/adaptive contrast. If adaptive PPL < uniform PPL at ρ=0.6, confirms Claim 3 proportion-robustness holds cross-seed at higher contamination.\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir /root/autodl-tmp/output/models/contamination_60_uniform_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.6 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"66327\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 200000000, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123}, \"checkpoint_path\": \"/root/autodl-tmp/output/models/contamination_60_uniform_seed123/final\", \"metrics\": {\"eval_ppl_holdout\": 17.754, \"eval_loss_holdout\": 2.8766, \"eval_holdout_tokens\": 4077068, \"total_steps\": 6103, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048\"}, \"conclusion\": \"success\", \"log_path\": \"/root/autodl-tmp/output/models/contamination_60_uniform_seed123/eval_output.log\", \"completed_at\": \"2026-05-18T03:30:01.455Z\"}, \"contamination_60_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T23:04:52.646Z\", \"updated_at\": \"2026-05-18T03:02:27.875Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir /root/autodl-tmp/output/models/contamination_60_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --tau 0.8 --n_min 2 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --bf16 --save_total_limit 3 --save_only_model --dataloader_num_workers 0\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:2\"], \"pid\": \"63153\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_seed123.log\", \"submitted_at\": \"2026-05-17T23:06:06.738Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"wall_clock_seconds\": 14181.1, \"gpu_hours\": 3.94}, \"hypothesis\": \"Cross-seed replication (seed123) of adaptive weighting at ρ=0.6: confirms contamination_60_seed42_r2 result is not seed-specific, strengthening Claim 3 proportion-robustness across contamination levels.\", \"reproduce\": {\"finished_at\": \"2026-05-18T02:55:06.709Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T02:55:10.838537+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.732, \"eval_loss_holdout\": 2.8754, \"eval_holdout_tokens\": 4077068, \"train_loss\": 9.6302, \"train_runtime_seconds\": 13638.6, \"total_steps\": 6103, \"eval_method\": \"eval_perplexity.py --max_docs 5000 --max_length 2048\"}, \"checkpoint_path\": \"/root/autodl-tmp/output/models/contamination_60_seed123/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T03:02:27.875Z\"}, \"grid_b0_3_seed123_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:18:02.595Z\", \"updated_at\": \"2026-05-18T01:54:20.680Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && export WANDB_MODE=disabled && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir /root/autodl-tmp/output/models/grid_b0_3_seed123 --model_name models/Qwen/Qwen3-0.6B --weighting_method grid --grid_b_value 0.3 --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 123 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model --resume_from_checkpoint /root/autodl-tmp/output/models/grid_b0_3_seed123/checkpoint-1000\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:1\"], \"pid\": \"53821\", \"log_path\": \"~/runs/provenance_weight_training/grid_b0_3_seed123_r2.log\", \"submitted_at\": \"2026-05-17T21:00:46.891Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"b=0.3 is grid-optimal cross-seed (confirmed at seed42 PPL=17.640). Retry on westd-30476 after previous failure. If seed123 b=0.3 PPL < b=0.5 seed123 (17.638), confirms grid-best is not seed-specific.\", \"parent\": \"grid_b0_5_seed123\", \"reproduce\": {\"finished_at\": \"2026-05-17T20:56:39.769Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T20:56:41.721Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T20:56:45.078984+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.5792, \"eval_loss_holdout\": 2.8667, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"re_eval_date\": \"2026-05-18\", \"eval_results_path\": \"/root/autodl-tmp/output/models/grid_b0_3_seed123/eval_results.json\", \"re_eval_note\": \"re-eval confirms original PPL=17.58; JSON artifact now saved\"}}, \"grid_b0_3_seed456_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T18:31:21.951Z\", \"updated_at\": \"2026-05-18T01:17:18.486Z\", \"hypothesis\": \"Cross-seed replication (seed456) of grid b=0.3: if PPL ≈ grid_b0_3_seed42 (17.640) and < b=0.5 seed456 (17.65), confirms grid-best=0.3 is not seed-specific, strengthening Claim 2 (adaptive ≈ grid-best).\", \"parent\": \"grid_b0_3_seed456\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method grid --grid_b_value 0.3 --seed 456 --num_train_tokens 200000000\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:0\"], \"pid\": \"54779\", \"log_path\": \"~/runs/provenance_weight_training/grid_b0_3_seed456_r2.log\", \"submitted_at\": \"2026-05-17T21:01:36.455Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 200000000, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"checkpoint_source\": \"N/A (fresh training, not eval)\", \"eval_data\": \"N/A (training experiment)\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/grid_b0_3_seed456_r2/final\", \"wall_clock_seconds\": 15342.0, \"gpu_hours\": 4.26}, \"server\": \"westd-30476\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-30476\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-17T20:52:01.783Z\", \"finished_at\": \"2026-05-18T00:38:02.877Z\", \"training_hours\": 3.77}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T00:38:07.191932+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.64, \"eval_loss_holdout\": 2.87, \"eval_holdout_tokens\": 4077068, \"total_steps\": 6103, \"train_loss\": 9.085, \"vs_uniform\": \"-0.054 (17.64 vs 17.694)\", \"vs_grid_b03_seed42\": \"0.000 (17.64 vs 17.640)\", \"vs_grid_b05_seed456\": \"-0.01 (17.64 vs 17.65)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T01:17:18.486Z\"}, \"batchsize16_nmin8_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T20:27:38.588Z\", \"updated_at\": \"2026-05-17T23:50:52.194Z\", \"hypothesis\": \"Coupling rule validation at bs=16: n_min=max(2,16//2)=8 with per_device_train_batch_size=16 (not 4×4 grad_accum). If PPL comparable to bs=4 adaptive, confirms coupling rule generalizes across batch sizes. Critical: micro-batch must exceed n_min for ESS constraint to be satisfiable.\", \"parent\": \"batchsize16_nmin8_r2\", \"spec\": {\"command\": \"bash scripts/run_bs16_nmin8_r2.sh\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"48891\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 50000, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"weighting_method\": \"adaptive\", \"per_device_train_batch_size\": 16, \"gradient_accumulation_steps\": 1, \"n_min\": 8, \"tau\": 0.8, \"checkpoint_source\": \"N/A\", \"eval_data\": \"N/A\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/batchsize16_nmin8_r2/final\", \"log_path\": \"~/runs/provenance_weight_training/batchsize16_nmin8_r3.log\"}, \"metrics\": {\"eval_ppl_holdout\": 17.65, \"eval_loss_holdout\": 2.871, \"eval_holdout_tokens\": 4077068, \"total_steps\": 6103, \"train_loss\": 2.6308, \"train_runtime_seconds\": 15057, \"vs_adaptive_bs4\": \"-0.003 (17.65 vs 17.6527)\", \"vs_bs8_nmin4\": \"-0.01 (17.65 vs 17.66)\", \"batch_size\": 16, \"n_min\": 8}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T23:50:52.194Z\"}, \"grid_b0_3_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:28:37.148Z\", \"updated_at\": \"2026-05-17T18:14:49.813Z\", \"hypothesis\": \"b=0.3 is grid-optimal cross-seed (confirmed at seed42 PPL=17.640 < b=0.5 seed42 17.651). If seed456 also shows b=0.3 as best, confirms grid-best is not seed-specific and strengthens Claim 2 (adaptive ≈ grid-best).\", \"parent\": \"grid_b0_5_seed456\", \"server\": \"westd-41312\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-17T05:35:41.476Z\"}, \"gpu_id\": [\"cuda:3\"], \"spec\": {\"command\": \"python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b0_3_seed456 --model_name models/Qwen/Qwen3-0.6B --weighting_method grid --grid_b_value 0.3 --contamination_ratio 0.4 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 456 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"88491\", \"log_path\": \"~/runs/provenance_weight_training/grid_b0_3_seed456.log\", \"submitted_at\": \"2026-05-17T12:53:05.146Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"contamination_ratio\": 0.4, \"b_value\": 0.3, \"checkpoint_source\": \"none\", \"eval_data\": \"data/human/eval_holdout.jsonl\", \"wall_clock_seconds\": 19304.7, \"gpu_hours\": 5.36}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-17T18:14:49.813Z\"}, \"batch_adaptive_tau_rho06_r5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:42:41.503Z\", \"updated_at\": \"2026-05-17T18:11:09.279Z\", \"spec\": {\"command\": \"bash scripts/run_batch_adaptive_tau_rho06_seed42.sh\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:2\"], \"pid\": \"22904\", \"log_path\": \"~/runs/provenance_weight_training/batch_adaptive_tau_rho06_r5.log\", \"submitted_at\": \"2026-05-17T13:42:41.242Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 371499, \"data_path\": \"data/scored_data_rho06.jsonl\", \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A (training from scratch)\", \"eval_data\": \"N/A (training experiment)\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/batch_adaptive_tau_rho06_seed42/final\", \"wall_clock_seconds\": 16108.0, \"gpu_hours\": 4.47}, \"hypothesis\": \"Batch-adaptive τ on ρ=0.6 data: per-batch τ_batch = clamp(α_eff_natural + 0.3, 0.5, 0.95) adapts threshold to local contamination density. At higher contamination, adaptive τ should outperform fixed τ=0.8 more clearly than at ρ=0.4 (which was negative).\", \"parent\": \"batch_adaptive_tau_rho04_seed42\", \"reproduce\": {\"finished_at\": \"2026-05-17T17:34:39.613Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T17:34:45.570181+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.73, \"eval_loss_holdout\": 2.8754, \"eval_holdout_tokens\": 4077068, \"train_loss\": 9.267, \"train_runtime_seconds\": 13903, \"total_steps\": 6103, \"vs_uniform_rho06\": \"-0.036\", \"vs_adaptive_fixed_tau08_rho06\": \"-0.010\", \"vs_grid_best_rho06\": \"+0.026\", \"vs_hybrid_rho06\": \"+0.200\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-17T18:11:09.279Z\"}, \"random_reweight_seed123_r5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T12:59:58.565Z\", \"updated_at\": \"2026-05-17T18:11:08.071Z\", \"spec\": {\"command\": \"bash scripts/run_random_reweight_seed123.sh\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:0\"], \"pid\": \"20073\", \"log_path\": \"~/runs/provenance_weight_training/random_reweight_seed123_r5.log\", \"submitted_at\": \"2026-05-17T12:59:58.325Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 371499, \"data_path\": \"data/scored_data.jsonl\", \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"checkpoint_source\": \"N/A (training from scratch)\", \"eval_data\": \"N/A (training experiment)\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/random_reweight_seed123/final\", \"wall_clock_seconds\": 18669.7, \"gpu_hours\": 5.19}, \"hypothesis\": \"Cross-seed replication (seed123) of random reweighting baseline: U(0,2) random weights replacing detector q-scores. If PPL > uniform (17.688), confirms detector signal is load-bearing across seeds, strengthening Claim 1.\", \"parent\": \"random_reweight_v2_seed42\", \"reproduce\": {\"finished_at\": \"2026-05-17T16:41:41.672Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T16:41:47.517255+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.8, \"eval_loss_holdout\": 2.8793, \"eval_holdout_tokens\": 4077068, \"train_loss\": 8.0176, \"train_runtime_seconds\": 13267, \"total_steps\": 6103, \"vs_uniform_seed123\": \"+0.114\", \"vs_adaptive_fix_seed123\": \"+0.157\", \"vs_random_reweight_v2_seed42\": \"consistent (+0.136 seed42 vs +0.114 seed123)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T18:11:08.071Z\"}, \"rho02_adaptive_tau09_r5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:42:23.804Z\", \"updated_at\": \"2026-05-17T18:02:05.662Z\", \"spec\": {\"command\": \"bash scripts/run_rho02_adaptive_tau09_seed42.sh\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"22095\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r5.log\", \"submitted_at\": \"2026-05-17T13:42:23.566Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 371499, \"data_path\": \"data/scored_data_rho02.jsonl\", \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A (training from scratch)\", \"eval_data\": \"N/A (training experiment)\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/rho02_adaptive_tau09_seed42/final\", \"wall_clock_seconds\": 15582.1, \"gpu_hours\": 4.33}, \"hypothesis\": \"Adaptive weighting with τ=0.9 on ρ=0.2 (low contamination): even at 20% contamination, stricter α_eff threshold should find non-trivial b* and outperform uniform, demonstrating proportion-robustness (Claim 3).\", \"parent\": \"adaptive_fix_seed42\", \"reproduce\": {\"finished_at\": \"2026-05-17T17:54:21.963Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T17:54:27.825996+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.45, \"eval_loss_holdout\": 2.8593, \"eval_holdout_tokens\": 4077068, \"train_loss\": 11.864, \"epoch\": 0.47, \"b_star_mean\": 4.3493, \"b_star_median\": 2.9609, \"b_star_std\": 4.3982, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_pct_zero\": 2.65, \"alpha_eff_mean\": 0.8277, \"alpha_eff_median\": 0.8826, \"alpha_eff_pct_at_max\": 42.95, \"ess_mean\": 2.3784, \"ess_median\": 2.0121}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-17T18:02:05.662Z\"}, \"bs8_auto_nmin_r5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T13:42:31.839Z\", \"updated_at\": \"2026-05-17T17:47:01.475Z\", \"spec\": {\"command\": \"bash scripts/run_bs8_auto_nmin_seed42.sh\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:1\"], \"pid\": \"22466\", \"log_path\": \"~/runs/provenance_weight_training/bs8_auto_nmin_r5.log\", \"submitted_at\": \"2026-05-17T13:42:31.602Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 371499, \"data_path\": \"data/scored_data.jsonl\", \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A (training from scratch)\", \"eval_data\": \"N/A (training experiment)\", \"checkpoint_path\": \"/root/autodl-tmp/output/models/bs8_auto_nmin_seed42/final\", \"wall_clock_seconds\": 14669.9, \"gpu_hours\": 4.07}, \"hypothesis\": \"bs=8 with auto n_min=4 (max(2,bs//2)). Previous bs8_nmin2 failed (PPL=17.73) because explicit n_min=2 was too loose for bs=8. Auto n_min=4 should recover performance, validating the coupling rule.\", \"parent\": \"bs8_nmin2_seed42_r2\", \"reproduce\": {\"finished_at\": \"2026-05-17T17:37:20.718Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T17:37:27.586541+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.66, \"eval_loss_holdout\": 2.8716, \"eval_holdout_tokens\": 4077068, \"train_loss\": 5.163, \"total_steps\": 6103, \"train_runtime_seconds\": 14064, \"epoch\": 0.26, \"b_star_mean\": 1.0957, \"b_star_median\": 0.9, \"b_star_std\": 0.7563, \"b_star_pct_zero\": 0.11, \"b_star_pct_below_0.5\": 10.43, \"ess_mean\": 4.4925, \"ess_median\": 4.0446, \"alpha_eff_mean\": 0.7023, \"alpha_eff_median\": 0.7572, \"alpha_eff_pct_at_max\": 38.88}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T17:47:01.475Z\"}, \"llama3b_adaptive_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T11:24:54.473Z\", \"updated_at\": \"2026-05-17T14:21:50.544Z\", \"spec\": {\"hypothesis\": \"Llama-3.2-3B adaptive τ=0.8 at ρ=0.4. Paired with llama3b_uniform to test cross-model generalization of adaptive reweighting.\", \"model_name\": \"unsloth/Llama-3.2-3B\", \"seed\": 42, \"contamination_ratio\": 0.4, \"data_count\": 371499, \"command\": \"bash scripts/run_llama3b_adaptive_seed42.sh\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data.jsonl\", \"gpu\": \"cuda:1\", \"pid\": 4005}, \"hypothesis\": \"Adaptive b* generalizes across model architectures: Llama-3.2-3B with provenance-weighted training should show PPL improvement over uniform baseline proportional to Qwen3-0.6B results, confirming the method is not architecture-specific and dual-constraint b* transfers.\", \"parent\": \"adaptive_fix_seed42\", \"conclusion\": \"negative\", \"reproduce\": {\"finished_at\": \"2026-05-17T13:58:27.135Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-17T13:58:28.583Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T13:58:31.913203+00:00\"}]}, \"metrics\": {\"ppl\": 10.58, \"eval_loss\": 2.359, \"eval_tokens\": 4017316}, \"notes\": \"诊断中: cron 报 process dead 5× + no W&B，但 memory.md 有 PPL=10.58 结论。疑似训练完成但监控缺失。Worker worker_diagnose_llama3b_adaptive_seed42_20260517T140045 正在 SSH 确认。日志文件 /root/runs/provenance_weight_training/llama3b_adaptive_seed42.log 不存在。\"}, \"batchsize16_nmin8_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-16T03:04:54.440Z\", \"updated_at\": \"2026-05-17T14:13:30.199Z\", \"notes\": \"westd-47453 permanently down (2026-05-17). Experiment was queued on 47453 (launcher PID 375555) waiting for GPU, never actually ran. Data lost. Needs migration to westd-30476.\", \"hypothesis\": \"batch_size=16 with auto n_min=8 (max(2,bs//2)): larger batch provides more stable ESS estimates and the coupling rule n_min=bs//2 maintains the same ESS dynamic range ratio as bs=4/n_min=2, so PPL should match or improve vs bs=4 baseline.\", \"completed_at\": \"\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"westd-47453 permanently down (2026-05-17). Experiment was queued on 47453 (launcher PID 375555) waiting for GPU, never actually ran. Data lost. Needs migration to westd-30476.\"}, \"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T14:13:32.124104+00:00\"}]}, \"spec\": {\"server\": \"westd-41312\", \"gpu\": [\"cuda:2\"], \"account\": \"root\", \"command\": \"bash scripts/run_batchsize16_nmin8_seed42.sh\", \"pid\": \"50284\", \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"batch_size\": 16, \"n_min\": 8, \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499}, \"reproduce\": {\"finished_at\": \"2026-05-17T14:13:27.986Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"failed\"}, \"llama3b_uniform_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T11:24:52.580Z\", \"updated_at\": \"2026-05-17T13:42:46.955Z\", \"spec\": {\"hypothesis\": \"Llama-3.2-3B uniform baseline at ρ=0.4. Cross-model generalization test — if adaptive improves over uniform on 3B model (not just 0.6B), strengthens paper claims.\", \"model_name\": \"unsloth/Llama-3.2-3B\", \"seed\": 42, \"contamination_ratio\": 0.4, \"data_count\": 371499, \"command\": \"bash scripts/run_llama3b_uniform_seed42.sh\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data.jsonl\", \"gpu\": \"cuda:0\", \"pid\": 3112}, \"hypothesis\": \"Uniform weighting baseline on Llama-3.2-3B establishes reference PPL for cross-model generalization experiment, enabling fair comparison with adaptive weighting on the same architecture and data.\", \"parent\": \"uniform_seed42\", \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/llama3b_uniform_seed42/final\", \"log_path\": \"/root/autodl-tmp/provenance_weight_training/output/logs/llama3b_uniform_seed42.log\", \"metrics\": {\"ppl\": 10.38, \"eval_loss\": 2.3397, \"eval_tokens\": 1526195, \"train_loss\": 7.2987, \"train_steps\": 6103, \"train_runtime_seconds\": 94309}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T13:42:46.955Z\"}, \"random_reweight_seed123_r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T12:57:05.055Z\", \"updated_at\": \"2026-05-17T13:18:38.368Z\", \"spec\": {\"command\": \"bash -c \\\"export WANDB_MODE=disabled && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_random_reweight_seed123.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:0\"], \"pid\": \"18979\", \"log_path\": \"~/runs/provenance_weight_training/random_reweight_seed123_r4.log\", \"submitted_at\": \"2026-05-17T12:57:04.815Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1293.6, \"gpu_hours\": 0.36}, \"hypothesis\": \"Cross-seed replication (seed123) of random reweighting baseline: U(0,2) random weights replacing detector q-scores. If PPL > uniform (17.688), confirms detector signal is load-bearing across seeds, strengthening Claim 1.\", \"parent\": \"random_reweight_v2_seed42\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T13:18:38.368Z\"}, \"rho02_adaptive_tau09_r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T12:49:18.411Z\", \"updated_at\": \"2026-05-17T12:53:29.865Z\", \"spec\": {\"command\": \"bash -c \\\"export WANDB_MODE=disabled && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"18281\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r4.log\", \"submitted_at\": \"2026-05-17T12:49:18.183Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 246.5, \"gpu_hours\": 0.07}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T12:53:24.682Z\", \"failure_reason\": \"Script crash: pretrain_weighted.py: error: unrecognized arguments: --dataloader_num_workers 0. Tmux session killed during cleanup.\"}, \"random_reweight_seed123_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T12:49:16.975Z\", \"updated_at\": \"2026-05-17T12:53:23.551Z\", \"spec\": {\"command\": \"bash -c \\\"export WANDB_MODE=disabled && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_random_reweight_seed123.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:0\"], \"pid\": \"18188\", \"log_path\": \"~/runs/provenance_weight_training/random_reweight_seed123_r3.log\", \"submitted_at\": \"2026-05-17T12:49:16.724Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 246.8, \"gpu_hours\": 0.07}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T12:53:23.551Z\"}, \"grid_b0_2_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T00:26:47.719Z\", \"updated_at\": \"2026-05-17T12:52:35.008Z\", \"hypothesis\": \"Grid-b sweep b=0.2 on ρ=0.4 data, seed42. Interpolation between b=0.1 and b=0.3 to characterize PPL curve shape in low-b region.\", \"parent\": \"grid_b_seed42_batch\", \"conclusion\": \"success\", \"notes\": \"Director 预算修正砍掉：b=0.1 和 b=0.3 两点足够推断趋势，b=0.2 不再需要。→ D042 修正：grid_b0_2 重新加入，排在 grid_b0_1/b0_3 之后的下一个空 GPU。\", \"spec\": {\"command\": \"bash /root/provenance_weight_training/scripts/run_grid_b0_2_seed42.sh\", \"server\": \"westd-41312\", \"gpu\": [\"cuda:3\"], \"pid\": \"45224\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"contamination_ratio\": 0.4, \"b_value\": 0.2, \"checkpoint_source\": \"none\", \"eval_data\": \"n/a\"}, \"checkpoint_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/grid_b0_2_seed42/final/\", \"log_path\": \"/root/autodl-tmp/provenance_weight_training/output/models/grid_b0_2_seed42/step_metrics.jsonl\", \"metrics\": {\"eval_ppl_holdout\": 17.64, \"eval_loss_holdout\": 2.8704, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\"}, \"completed_at\": \"2026-05-17T12:52:35.008Z\"}, \"rho02_adaptive_tau09_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:24:41.471Z\", \"updated_at\": \"2026-05-17T11:44:37.903Z\", \"spec\": {\"command\": \"bash -c \\\"export WANDB_MODE=disabled && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"10727\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r3.log\", \"submitted_at\": \"2026-05-17T11:26:28.291Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1089.6, \"gpu_hours\": 0.3}, \"server\": \"westd-30476\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"hypothesis\": \"Adaptive weighting with τ=0.9 on ρ=0.2 (low contamination): even at 20% contamination, stricter α_eff threshold should find non-trivial b* and outperform uniform, demonstrating proportion-robustness (Claim 3).\", \"parent\": \"adaptive_fix_seed42\", \"pid\": \"10727\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r3.log\", \"reproduce\": {\"command\": \"bash -c \\\"export WANDB_MODE=disabled && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T11:44:37.903Z\"}, \"batch_adaptive_tau_rho06_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:24:40.398Z\", \"updated_at\": \"2026-05-17T11:44:36.509Z\", \"spec\": {\"command\": \"bash -c \\\"export WANDB_MODE=disabled && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_batch_adaptive_tau_rho06_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:2\"], \"pid\": \"10209\", \"log_path\": \"~/runs/provenance_weight_training/batch_adaptive_tau_rho06_r3.log\", \"submitted_at\": \"2026-05-17T11:26:23.874Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1092.6, \"gpu_hours\": 0.3}, \"server\": \"westd-30476\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"hypothesis\": \"Batch-adaptive τ on ρ=0.6 data: per-batch τ_batch = clamp(α_eff_natural + 0.3, 0.5, 0.95) adapts threshold to local contamination density. At higher contamination, adaptive τ should outperform fixed τ=0.8 more clearly than at ρ=0.4 (which was negative).\", \"parent\": \"batch_adaptive_tau_rho04_seed42\", \"pid\": \"10209\", \"log_path\": \"~/runs/provenance_weight_training/batch_adaptive_tau_rho06_r3.log\", \"reproduce\": {\"command\": \"bash -c \\\"export WANDB_MODE=disabled && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_batch_adaptive_tau_rho06_seed42.sh\\\"\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T11:44:36.509Z\"}, \"bs8_auto_nmin_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:24:39.323Z\", \"updated_at\": \"2026-05-17T11:44:35.233Z\", \"spec\": {\"command\": \"bash -c \\\"export WANDB_MODE=disabled && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_bs8_auto_nmin_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:1\"], \"pid\": \"10119\", \"log_path\": \"~/runs/provenance_weight_training/bs8_auto_nmin_r3.log\", \"submitted_at\": \"2026-05-17T11:26:19.279Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1096.0, \"gpu_hours\": 0.3}, \"server\": \"westd-30476\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"hypothesis\": \"bs=8 with auto n_min=4 (max(2,bs//2)). Previous bs8_nmin2 failed (PPL=17.73) because explicit n_min=2 was too loose for bs=8. Auto n_min=4 should recover performance, validating the coupling rule.\", \"parent\": \"bs8_nmin2_seed42_r2\", \"pid\": \"10119\", \"log_path\": \"~/runs/provenance_weight_training/bs8_auto_nmin_r3.log\", \"reproduce\": {\"command\": \"bash -c \\\"export WANDB_MODE=disabled && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_bs8_auto_nmin_seed42.sh\\\"\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T11:44:35.233Z\"}, \"random_reweight_seed123_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T11:24:38.169Z\", \"updated_at\": \"2026-05-17T11:44:33.731Z\", \"spec\": {\"command\": \"bash -c \\\"export WANDB_MODE=disabled && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_random_reweight_seed123.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:0\"], \"pid\": \"10035\", \"log_path\": \"~/runs/provenance_weight_training/random_reweight_seed123_r2.log\", \"submitted_at\": \"2026-05-17T11:26:15.828Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1097.9, \"gpu_hours\": 0.3}, \"server\": \"westd-30476\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"hypothesis\": \"Cross-seed replication (seed123) of random reweighting baseline: U(0,2) random weights replacing detector q-scores. If PPL > uniform (17.688), confirms detector signal is load-bearing across seeds, strengthening Claim 1.\", \"parent\": \"random_reweight_v2_seed42\", \"pid\": \"10035\", \"log_path\": \"~/runs/provenance_weight_training/random_reweight_seed123_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export WANDB_MODE=disabled && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_random_reweight_seed123.sh\\\"\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T11:44:33.731Z\"}, \"rho02_adaptive_tau09_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:25:34.927Z\", \"updated_at\": \"2026-05-17T11:19:34.469Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:3\"], \"pid\": \"7951\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\", \"submitted_at\": \"2026-05-17T11:15:37.586Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 142.8, \"gpu_hours\": 0.04}, \"server\": \"westd-30476\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"pid\": \"7951\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_rho02_adaptive_tau09_seed42.sh\\\"\", \"finished_at\": \"2026-05-17T11:16:27.699Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T11:16:40.596896+00:00\"}]}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T11:18:00.344Z\", \"failure_reason\": \"TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer' — same as bs8_auto_nmin_r2 and batch_adaptive_tau_rho06_r2, transformers version incompatibility on westd-30476\", \"metrics\": {\"error\": \"TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'\", \"error_stage\": \"initialization\", \"training_completed\": false, \"note\": \"Crashed before any training. Same bug as rho02_adaptive_tau09_seed42. Fix: replace tokenizer= with processing_class= in pretrain_weighted.py line ~101.\"}}, \"batch_adaptive_tau_rho06_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:25:31.543Z\", \"updated_at\": \"2026-05-17T11:16:18.424Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_batch_adaptive_tau_rho06_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:2\"], \"pid\": \"7746\", \"log_path\": \"~/runs/provenance_weight_training/batch_adaptive_tau_rho06_r2.log\", \"submitted_at\": \"2026-05-17T11:15:32.058Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 46.4, \"gpu_hours\": 0.01}, \"server\": \"westd-30476\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"pid\": \"7746\", \"log_path\": \"~/runs/provenance_weight_training/batch_adaptive_tau_rho06_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_batch_adaptive_tau_rho06_seed42.sh\\\"\", \"finished_at\": \"2026-05-17T11:16:15.950Z\"}, \"failure_reason\": \"Traceback → , in main trainer = WeightedTrainer( ^^^^^^^^^^^^^^^^ File \\\"/root/provenance_weight_training/training/pretrain_weighted.py\\\", line 101, in __init__ super().__init__(**kwargs) TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T11:16:18.424Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T11:16:24.981007+00:00\"}]}}, \"bs8_auto_nmin_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:25:26.255Z\", \"updated_at\": \"2026-05-17T11:16:07.184Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_bs8_auto_nmin_seed42.sh\\\"\", \"server\": \"westd-30476\", \"gpu\": [\"cuda:1\"], \"pid\": \"7543\", \"log_path\": \"~/runs/provenance_weight_training/bs8_auto_nmin_r2.log\", \"submitted_at\": \"2026-05-17T11:15:23.530Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 43.7, \"gpu_hours\": 0.01}, \"server\": \"westd-30476\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"7543\", \"log_path\": \"~/runs/provenance_weight_training/bs8_auto_nmin_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_bs8_auto_nmin_seed42.sh\\\"\", \"finished_at\": \"2026-05-17T11:16:04.481Z\"}, \"failure_reason\": \"Traceback → , in main trainer = WeightedTrainer( ^^^^^^^^^^^^^^^^ File \\\"/root/provenance_weight_training/training/pretrain_weighted.py\\\", line 101, in __init__ super().__init__(**kwargs) TypeError: Trainer.__init__() got an unexpected keyword argument 'tokenizer'\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-17T11:16:07.184Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-17T11:16:11.345912+00:00\"}]}}, \"rho02_adaptive_tau09_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:02:16.962Z\", \"updated_at\": \"2026-05-17T10:50:00.000Z\", \"spec\": {\"command\": \"bash scripts/run_rho02_adaptive_tau09_seed42.sh\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:1\"], \"pid\": \"367604\", \"data_path\": \"data/scored_data_rho02.jsonl\", \"data_count\": 206111, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"contamination_ratio\": 0.2, \"tau\": 0.9, \"n_min\": 2, \"weighting_method\": \"adaptive\", \"log_path\": \"~/runs/provenance_weight_training/rho02_adaptive_tau09_seed42.log\"}, \"notes\": \"Retry: first attempt failed due to CUDA_VISIBLE_DEVICES=-1 in script overriding submit_training_job env. Fixed by removing export line from script. PID 367604.\", \"hypothesis\": \"Adaptive weighting with τ=0.9 on ρ=0.2 (low contamination): even at 20% contamination, stricter α_eff threshold should find non-trivial b* and outperform uniform, demonstrating the method works across contamination levels (Claim 3 proportion-robustness).\", \"parent\": \"adaptive_fix_seed42\", \"conclusion\": \"failed\", \"failure_reason\": \"westd-47453 server down, data lost\", \"completed_at\": \"2026-05-17T10:50:00.000Z\"}, \"batch_adaptive_tau_rho06_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:16:35.042Z\", \"updated_at\": \"2026-05-17T10:50:00.000Z\", \"spec\": {\"command\": \"bash /root/provenance_weight_training/scripts/run_batch_adaptive_tau_rho06_seed42.sh\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:2\"], \"pid\": \"372142\", \"log_path\": \"~/runs/provenance_weight_training/batch_adaptive_tau_rho06_seed42.log\", \"submitted_at\": \"2026-05-16T23:46:46.802Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_rho06.jsonl\", \"data_count\": 244502, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"contamination_ratio\": 0.6, \"weighting_method\": \"batch_adaptive_tau\", \"tau\": 0.7, \"n_min\": 2}, \"hypothesis\": \"Batch-adaptive τ on ρ=0.6 data: per-batch τ_batch = clamp(α_eff_natural + 0.3, 0.5, 0.95) adapts threshold to local contamination density. At higher contamination, more batches have high α_eff_natural, so adaptive τ should outperform fixed τ=0.8 more clearly than at ρ=0.4.\", \"parent\": \"batch_adaptive_tau_rho04_seed42\", \"conclusion\": \"failed\", \"failure_reason\": \"westd-47453 server down, data lost\", \"completed_at\": \"2026-05-17T10:50:00.000Z\"}, \"bs8_auto_nmin_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:16:38.352Z\", \"updated_at\": \"2026-05-17T10:50:00.000Z\", \"spec\": {\"command\": \"bash /root/provenance_weight_training/scripts/run_bs8_auto_nmin_seed42.sh\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:3\"], \"pid\": \"370013\", \"log_path\": \"~/runs/provenance_weight_training/bs8_auto_nmin_seed42.log\", \"submitted_at\": \"2026-05-16T23:26:39.790Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"contamination_ratio\": 0.4, \"batch_size\": 8, \"n_min\": \"auto (max(2, bs//2) = 4)\", \"weighting_method\": \"adaptive\", \"tau\": 0.8}, \"hypothesis\": \"bs=8 with auto n_min=4 (max(2,bs//2)). Previous bs8_nmin2 failed (PPL=17.73) because explicit n_min=2 was too loose for bs=8. Auto n_min=4 should recover performance.\", \"parent\": \"bs8_nmin2_seed42_r2\", \"conclusion\": \"failed\", \"failure_reason\": \"westd-47453 server down, data lost\", \"completed_at\": \"2026-05-17T10:50:00.000Z\"}, \"grid_b0_3_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:08:31.061Z\", \"updated_at\": \"2026-05-17T10:50:00.000Z\", \"hypothesis\": \"b=0.3 is grid-optimal cross-seed (confirmed at seed42 PPL=17.640 < b=0.5 seed42 17.651). If seed123 also shows b=0.3 as best, confirms grid-best is not seed-specific and strengthens Claim 2 (adaptive ≈ grid-best).\", \"parent\": \"grid_b0_5_seed123\", \"server\": \"westd-47453\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_grid_b0_3_seed123.sh\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:0\"], \"pid\": \"396682\", \"log_path\": \"~/runs/provenance_weight_training/grid_b0_3_seed123.log\", \"submitted_at\": \"2026-05-17T07:32:54.221Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"failed\", \"failure_reason\": \"westd-47453 server down, data lost\", \"completed_at\": \"2026-05-17T10:50:00.000Z\"}, \"random_reweight_v2_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T14:42:44.958Z\", \"updated_at\": \"2026-05-17T07:33:09.061Z\", \"spec\": {\"command\": \"bash scripts/run_random_reweight_v2_seed42.sh\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:0\"], \"pid\": \"354002\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"weighting_method\": \"random\", \"log_path\": \"/root/autodl-tmp/output/models/random_reweight_v2_seed42/train.log\"}, \"hypothesis\": \"Random reweighting baseline v2: U(0,2) random weights (mean=1) replacing detector q-scores. Tests if detector signal is load-bearing — if random weights ≈ adaptive, detector is not contributing. Expected: adaptive > random → provenance signal matters.\", \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.83, \"eval_loss_holdout\": 2.8809}, \"checkpoint_path\": \"/root/autodl-tmp/output/models/random_reweight_v2_seed42\", \"completed_at\": \"2026-05-17T07:33:09.061Z\"}, \"tau_095_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:03:32.419Z\", \"updated_at\": \"2026-05-17T03:00:52.678Z\", \"hypothesis\": \"τ=0.95 forces α_eff > 0.95 before allowing downweighting, which should collapse b* toward near-max values (overfit to quality constraint) and degrade PPL toward ESS-only levels (~17.72), confirming the method requires τ ≤ 0.8 to balance quality and stability.\", \"parent\": \"adaptive_fix_seed42\", \"spec\": {\"checkpoint_path\": \"/root/provenance_weight_training/output/models/tau_095_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/tau_095_seed42.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T18:21:58.713Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:22:00.219145+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.723, \"eval_loss\": 2.8749, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"train_loss\": 10.198, \"total_steps\": 6103, \"train_runtime_s\": 13699, \"train_samples_per_second\": 7.128, \"b_star_count\": 24412, \"b_star_mean\": 3.0775, \"b_star_median\": 1.52, \"b_star_std\": 3.9923, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.8, \"b_star_p75\": 3.46, \"b_star_pct_zero\": 0, \"b_star_pct_below_0.5\": 8.5, \"b_star_pct_0.5_to_1\": 24.7, \"b_star_pct_1_to_2\": 26.4, \"b_star_pct_above_2\": 40.3}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T18:29:07.389Z\"}, \"batch_adaptive_tau_rho04_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:16:32.221Z\", \"updated_at\": \"2026-05-17T03:00:22.336Z\", \"spec\": {\"hypothesis\": \"Batch-adaptive τ: τ_batch = clamp(α_eff_natural + 0.3, 0.5, τ). Reduces over-intervention on clean batches. Expected PPL ≤ fixed-τ adaptive (17.653).\", \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"contamination_ratio\": 0.4, \"command\": \"bash scripts/run_batch_adaptive_tau_rho04_seed42.sh\", \"server\": \"westd-47453\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"gpu\": \"cuda:2\", \"pid\": 326274}, \"conclusion\": \"negative\", \"metrics\": {\"eval_loss_holdout\": 2.8725, \"eval_ppl_holdout\": 17.681, \"train_loss\": 9.8206, \"train_runtime_sec\": 45402.86}, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/batch_adaptive_tau_rho04_seed42/checkpoint-6103\", \"log_path\": \"/root/provenance_weight_training/output/logs/batch_adaptive_tau_rho04_seed42.log\", \"hypothesis\": \"Batch-adaptive τ (τ_batch = clamp(α_eff_natural + 0.3, 0.5, τ)) reduces over-intervention on clean batches by lowering τ when the batch already has low contamination, yielding lower holdout PPL than fixed τ=0.8.\", \"completed_at\": \"2026-05-16T23:44:28.133Z\", \"parent\": \"adaptive_fix_seed42\"}, \"p0_contamination_60_datagen\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:37:10.827Z\", \"updated_at\": \"2026-05-17T03:00:18.545Z\", \"spec\": {\"command\": \"python scripts/prepare_rho06_data.py\", \"server\": \"westd-47453\", \"data_path\": \"/root/provenance_weight_training/data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B (TF-IDF scoring)\", \"seed\": 42, \"checkpoint_path\": \"/root/provenance_weight_training/data/scored_data_60.jsonl\", \"log_path\": \"/root/provenance_weight_training/scripts/prepare_rho06_data.py\"}, \"conclusion\": \"success\", \"metrics\": {\"total_lines\": 371499, \"synthetic_count\": 222900, \"human_count\": 148599, \"actual_contamination_ratio\": 0.6, \"q_score_mean\": 0.6243, \"q_score_std\": 0.3703, \"q_score_median\": 0.7753, \"file_size_mb\": 907}, \"completed_at\": \"2026-05-15T20:08:12.383Z\", \"hypothesis\": \"TF-IDF scoring on ρ=0.6 contamination data produces well-calibrated bimodal q-scores that separate human/synthetic, enabling downstream adaptive reweighting experiments at higher contamination levels.\"}, \"datagen_synthetic_4gpu\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T19:12:11.474Z\", \"updated_at\": \"2026-05-17T03:00:16.173Z\", \"spec\": {\"command\": \"4x parallel generate_synthetic.py --depth 1 --num_tokens 33000000 --batch_size 128\", \"server\": \"westd-47453\", \"data_path\": \"/root/provenance_weight_training/data/synthetic/shard_{0,1,2,3}/\", \"data_count\": \"target 132M tokens across 4 shards\", \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": \"42/1042/2042/3042\", \"hypothesis\": \"4-GPU parallel generation produces 132M synthetic tokens in ~2.5h\", \"gpu\": \"cuda:0,1,2,3\", \"checkpoint_path\": \"/root/provenance_weight_training/data/synthetic/shard_{0,1,2,3}/\", \"log_path\": \"/root/provenance_weight_training/data/synthetic/gen_gpu{0,1,2,3}.log\", \"total_docs\": 340992, \"total_tokens\": 132033764}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T21:50:46.682Z\", \"hypothesis\": \"4-GPU parallel synthetic data generation (Qwen3-0.6B, depth=1, 33M tokens/shard) produces sufficient scale and diversity for provenance contamination experiments while maintaining consistent stylistic distribution for detector calibration.\"}, \"grid_b5_0_seed123\": {\"status\": \"DONE\", \"retry_count\": 2, \"created_at\": \"2026-05-14T02:52:56.873Z\", \"updated_at\": \"2026-05-17T03:00:06.065Z\", \"server\": \"westd-47453\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-14T11:22:30Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b5_0_seed123 --weighting_method grid --grid_b_value 5.0 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 123 --logging_steps 10 --save_steps 500 --eval_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4\\\"\", \"finished_at\": \"2026-05-14T15:09:25.359Z\", \"training_hours\": 3.78}, \"completed_at\": \"2026-05-14T11:20:36.319Z\", \"notes\": \"PID 94717 已确认存活（SSH 验证 2026-05-14T11:39）。旧 PID 92798 已 kill，cron 重新注册。\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"前次提交 (PID 92793) 未实际启动训练，标记 killed。等 eval PID 92274 完成后重新提交。\"}, \"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T11:36:18.619551+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T15:09:26.285900+00:00\"}]}, \"failure_reason\": \"\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b5_0_seed123 --weighting_method grid --grid_b_value 5.0 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 123 --logging_steps 10 --save_steps 500 --eval_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:3\"], \"pid\": \"94717\", \"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"log_path\": \"~/runs/provenance_weight_training/grid_b5_0_seed123.log\"}, \"metrics\": {\"train_loss\": 10.8468, \"total_steps\": 6103, \"train_runtime_s\": 14434, \"gpu_hours\": 4.01, \"eval_ppl_holdout\": 17.8039, \"eval_loss\": 2.8794, \"eval_holdout_tokens\": 4077068}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/provenance_weight_training/output/models/grid_b5_0_seed123/final/\", \"log_path\": \"~/runs/provenance_weight_training/grid_b5_0_seed123.log\", \"hypothesis\": \"Grid-b sweep b=5.0 seed=123: extreme downweighting (near-zero weight for synthetic). Establishes ceiling of degradation from over-aggressive fixed reweighting, proving that wrong b choice can be worse than no reweighting at all.\"}, \"grid_b3_0_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T02:52:56.285Z\", \"updated_at\": \"2026-05-17T03:00:04.124Z\", \"spec\": {\"checkpoint_path\": \"/root/provenance_weight_training/output/models/grid_b3_0_seed123/final/\", \"log_path\": \"/root/provenance_weight_training/output/models/grid_b3_0_seed123/\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T14:23:51.699Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T14:23:52.658692+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 10.7422, \"total_steps\": 6103, \"train_runtime_s\": 12955.83, \"gpu_hours\": 3.6, \"eval_ppl_holdout\": 17.76, \"eval_loss\": 2.877, \"eval_holdout_tokens\": 4077068}, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/grid_b3_0_seed123/final/\", \"completed_at\": \"2026-05-14T14:24:22.860Z\", \"log_path\": \"~/runs/provenance_weight_training/grid_b3_0_seed123.log\", \"notes\": \"训练完成，eval 未执行（should_evaluate=false，缺少 --eval_data_path 和 --eval_steps）。Checkpoint: /root/provenance_weight_training/output/models/grid_b3_0_seed123/final/ (model.safetensors 1.19GB)。需补跑 eval。\", \"hypothesis\": \"Grid-b sweep b=3.0 seed=123: very aggressive downweighting well past optimal. Multi-seed confirmation that high-b regime consistently degrades PPL, strengthening the case that grid search sensitivity motivates adaptive b*.\"}, \"grid_b2_0_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T02:52:55.329Z\", \"updated_at\": \"2026-05-17T03:00:02.264Z\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b2_0_seed123 --weighting_method grid --grid_b_value 2.0 --contamination_ratio 0.4 --seed 123\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:1\"], \"pid\": \"88022\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"log_path\": \"~/runs/provenance_weight_training/grid_b2_0_seed123.log\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 10.61, \"total_steps\": 6103, \"train_runtime_s\": 13058.8, \"gpu_hours\": 3.63, \"train_samples_per_second\": 7.478, \"train_steps_per_second\": 0.467, \"eval_ppl_holdout\": 17.725, \"eval_loss\": 2.875, \"eval_holdout_tokens\": 4077068}, \"reproduce\": {\"finished_at\": \"2026-05-14T14:14:05.530Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T14:14:06.752002+00:00\"}]}, \"checkpoint_path\": \"output/models/grid_b2_0_seed123/final\", \"log_path\": \"~/runs/provenance_weight_training/grid_b2_0_seed123.log\", \"completed_at\": \"2026-05-14T14:14:33.471Z\", \"hypothesis\": \"Grid-b sweep b=2.0 seed=123: strong downweighting regime past optimal. PPL should degrade further, establishing that aggressive fixed-b over-suppresses synthetic data and motivates adaptive per-batch b* selection.\"}, \"grid_b1_5_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T02:52:43.491Z\", \"updated_at\": \"2026-05-17T03:00:00.380Z\", \"spec\": {\"checkpoint_path\": \"/root/provenance_weight_training/output/models/grid_b1_5_seed123/final/\", \"wall_clock_seconds\": 15053.1, \"gpu_hours\": 4.18}, \"reproduce\": {\"finished_at\": \"2026-05-14T11:06:15.864Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T11:06:16.350913+00:00\"}]}, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/grid_b1_5_seed123/final/\", \"metrics\": {\"train_loss\": 10.4776, \"total_steps\": 6103, \"train_runtime_s\": 15053.1, \"gpu_hours\": 4.18, \"eval_ppl_holdout\": 17.701, \"eval_loss\": 2.8736}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:18:32.771Z\", \"hypothesis\": \"Grid-b sweep b=1.5 seed=123: testing diminishing returns region. PPL should be higher than b=1.0 as stronger downweighting begins to over-suppress useful synthetic samples, confirming U-shaped PPL-vs-b curve.\"}, \"grid_b1_0_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T02:52:42.784Z\", \"updated_at\": \"2026-05-17T02:59:58.125Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b1_0_seed123 --weighting_method grid --grid_b_value 1.0 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 123 --logging_steps 10 --save_steps 500 --eval_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:2\"], \"pid\": \"68306\", \"log_path\": \"~/runs/provenance_weight_training/grid_b1_0_seed123.log\", \"submitted_at\": \"2026-05-14T06:53:47.084Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/grid_b1_0_seed123/final/\", \"wall_clock_seconds\": 13950, \"gpu_hours\": 3.88}, \"reproduce\": {\"finished_at\": \"2026-05-14T10:46:17.839Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T10:46:18.691130+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.674, \"eval_loss\": 2.8721, \"eval_holdout_tokens\": 4077068, \"train_loss\": 10.218, \"total_steps\": 6103, \"train_runtime_s\": 13878, \"gpu_hours\": 3.88}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T18:53:00Z\", \"hypothesis\": \"Grid-b sweep b=1.0 seed=123: moderate exponential downweighting. Multi-seed data point establishing that b>0.5 yields diminishing returns, supporting the grid-b PPL curve monotonically increasing past optimal.\"}, \"grid_b0_5_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T02:52:42.314Z\", \"updated_at\": \"2026-05-17T02:59:55.641Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b0_5_seed123 --weighting_method grid --grid_b_value 0.5 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 123 --logging_steps 10 --save_steps 500 --eval_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:1\"], \"pid\": \"68163\", \"log_path\": \"~/runs/provenance_weight_training/grid_b0_5_seed123.log\", \"submitted_at\": \"2026-05-14T06:53:43.648Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/grid_b0_5_seed123/final/\", \"wall_clock_seconds\": 13678.0, \"gpu_hours\": 3.8}, \"reproduce\": {\"finished_at\": \"2026-05-14T10:33:23.511Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T10:33:24.806181+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.638, \"eval_loss\": 2.87, \"eval_holdout_tokens\": 4077068, \"train_loss\": 9.601, \"total_steps\": 6103, \"train_runtime_s\": 13104, \"gpu_hours\": 3.8}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T10:41:41.614Z\", \"hypothesis\": \"Grid-b sweep b=0.5 seed=123: multi-seed validation that b=0.5 is near-optimal in grid search. Establishes grid-best baseline PPL for comparison with adaptive b* (which should match without requiring grid search).\"}, \"hybrid_rho04_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:16:41.634Z\", \"updated_at\": \"2026-05-17T00:22:29.508Z\", \"spec\": {\"hypothesis\": \"Hybrid filter+reweight: remove q>0.95, then adaptive reweight remainder. Combines detect_remove's elimination of worst samples with adaptive's soft reweighting. Data: 253,584 rows (from 371,499).\", \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"contamination_ratio\": 0.4, \"command\": \"bash scripts/run_hybrid_rho04_seed42.sh\", \"server\": \"westd-41312\", \"data_path\": \"data/scored_data_hybrid.jsonl\", \"data_count\": 253584, \"gpu\": \"cuda:2\", \"pid\": 3656, \"tau\": 0.8, \"n_min\": 2, \"weighting_method\": \"adaptive\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/provenance_weight_training/output/models/hybrid_rho04_seed42/final\", \"log_path\": \"/root/autodl-tmp/provenance_weight_training/output/logs/hybrid_rho04_seed42.log\", \"hypothesis\": \"Hybrid filter+reweight (remove q>0.95 then adaptive reweight remainder with rho=0.4) will achieve lower holdout PPL than pure adaptive reweighting by eliminating the most contaminated samples before soft reweighting, combining the strengths of detect_remove and adaptive methods.\", \"completed_at\": \"2026-05-17T00:22:23.173Z\", \"metrics\": {\"eval_loss_holdout\": 2.863, \"eval_ppl_holdout\": 17.514}}, \"threshold_q03_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-16T05:34:34.545Z\", \"updated_at\": \"2026-05-16T23:25:26.414Z\", \"hypothesis\": \"Hard-filter threshold sensitivity: remove q>0.3 samples, train uniformly on remaining. Paired with detect_remove (q>0.5) and threshold_q07 (q>0.7) to test if filtering requires precise threshold calibration while adaptive does not.\", \"reproduce\": {\"finished_at\": \"2026-05-16T10:30:31.843Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-16T10:30:32.935Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T10:30:35.110226+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"bash scripts/run_threshold_q03_seed42.sh (restart)\", \"server\": \"westd-47453\", \"data_path\": \"data/scored_data_filtered_q03.jsonl\", \"data_count\": 116935, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"gpu\": \"cuda:3\", \"pid\": 325196, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/threshold_q03_seed42/final\", \"log_path\": \"/root/autodl-tmp/threshold_q03_restart.log\"}, \"conclusion\": \"success\", \"notes\": \"Training completed successfully. 6103/6103 steps, train_loss=11.24, runtime=45076s (~12.5h). Model saved to output/models/threshold_q03_seed42/final (1.19GB safetensors). WANDB_MODE=disabled, offline run available at wandb/offline-run-20260516_184629-s7vw5rw5.\", \"metrics\": {\"eval_loss_holdout\": 2.848, \"eval_ppl_holdout\": 17.253}}, \"rho02_uniform_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T09:02:18.437Z\", \"updated_at\": \"2026-05-16T21:36:26.041Z\", \"spec\": {\"checkpoint_path\": \"output/models/rho02_uniform_seed42/final\", \"log_path\": \"output/logs/rho02_uniform_seed42.log\"}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl_holdout\": 17.336, \"eval_loss_holdout\": 2.853, \"eval_holdout_tokens\": 4077068}, \"hypothesis\": \"Uniform weighting at ρ=0.2 contamination provides the baseline loss level; adaptive reweighting methods should achieve lower loss on clean validation data by downweighting contaminated samples.\", \"completed_at\": \"2026-05-16T21:32:06.395Z\"}, \"threshold_q07_seed42\": {\"status\": \"DONE\", \"retry_count\": 2, \"created_at\": \"2026-05-16T05:34:35.477Z\", \"updated_at\": \"2026-05-16T21:07:12.412Z\", \"hypothesis\": \"Hard-filter threshold sensitivity: remove q>0.7 samples (least aggressive, keeps most data+contamination), train uniformly. If PPL varies >0.1 across q=0.3/0.5/0.7 thresholds, proves filtering needs precise calibration while adaptive is threshold-free.\", \"server\": \"westd-47453\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-16T06:00:07.874Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_threshold_q07_seed42.sh\\\"\"}, \"completed_at\": \"2026-05-16T10:22:01.172Z\", \"notes\": \"Resume r2 failed: ValueError \\\"Your setup doesn't support bf16/gpu\\\" — all 4x GPUs were occupied by other processes when resume script launched. Training stuck at step 5999, checkpoint-5500 intact. Needs retry when GPU is free.\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"Resume r2 from checkpoint-5500 (stuck at step 5999 due to disk full + wandb error loop). wandb/ deleted, WANDB_MODE=disabled. 604 steps remaining.\"}}, \"spec\": {\"command\": \"bash -c 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_threshold_q07_resume_r2.sh'\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:0\"], \"pid\": \"355121\", \"data_path\": \"/root/provenance_weight_training/data/scored_data_filtered_q07.jsonl\", \"data_count\": 184908, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"resume_from\": \"checkpoint-5500\"}, \"conclusion\": \"failed\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\"}, \"random_reweight_seed42\": {\"status\": \"DONE\", \"retry_count\": 3, \"created_at\": \"2026-05-16T07:16:33.821Z\", \"updated_at\": \"2026-05-16T13:33:42.598Z\", \"hypothesis\": \"Random reweighting baseline: U(0,2) random weights (mean=1) replacing detector q-scores. Tests if detector signal is load-bearing — if random weights ≈ adaptive, detector is not contributing. Expected: adaptive > random → provenance signal matters.\", \"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-16T07:16:51.087Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && bash scripts/run_random_reweight_seed42.sh\\\"\", \"finished_at\": \"2026-05-16T10:22:28.062Z\", \"training_hours\": 3.09}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"completed_at\": \"2026-05-16T07:17:18.186Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T07:17:20.059724+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T09:30:52.354459+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T10:22:31.379909+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"失败原因: wandb.errors.UsageError: No API key configured — 脚本未继承 WANDB_API_KEY 环境变量 | fix_worker_id: worker_diagnose_random_reweight_seed42_20260516T072019 | 修复后将重提交到 cuda:2\"}}, \"notes\": \"根因诊断：实际只跑~500步(8%)，\\\"6092/8477\\\"是eval进度条非training。WANDB_MODE=offline写~150MB到30GB根分区→磁盘满→OOM killer在eval期间杀进程→save从未执行→零checkpoint。修复：WANDB_MODE=disabled + output_dir改数据盘。v2脚本已dry-run验证通过。\", \"spec\": {\"command\": \"bash scripts/run_random_reweight_seed42.sh\", \"server\": \"westd-47453\", \"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"weighting_method\": \"random\", \"contamination_ratio\": 0.4, \"gpu\": \"cuda:2\", \"pid\": 318752, \"log_path\": \"~/runs/provenance_weight_training/random_reweight_seed42.log\", \"checkpoint_path\": \"output/models/random_reweight_seed42\", \"num_train_tokens\": 200000000, \"max_steps\": 6103}, \"conclusion\": \"failed\"}, \"contamination_60_tau06_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:04:51.670Z\", \"updated_at\": \"2026-05-16T07:15:22.736Z\", \"spec\": {\"hypothesis\": \"ρ=0.6 τ=0.6 diagnostic: second data point for ρ=0.6 τ-PPL curve. Tests deeper τ downshift for higher contamination.\", \"parent\": \"contamination_60_seed42_r2\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir output/models/contamination_60_tau06_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --tau 0.6 --n_min 2 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:2\"], \"pid\": \"287971\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"log_path\": \"~/runs/provenance_weight_training/contamination_60_tau06_seed42.log\", \"account\": \"root\", \"checkpoint_source\": \"N/A\", \"eval_data\": \"N/A\"}, \"hypothesis\": \"ρ=0.6 τ=0.6 diagnostic: second data point for ρ=0.6 τ-PPL curve. Tests deeper τ downshift for higher contamination.\", \"parent\": \"contamination_60_seed42_r2\", \"notes\": \"D045 第二数据点。GPU 队列: cuda:2 (ess_only 完成后)。脚本: scripts/run_contamination_60_tau06.sh。优先级最高。\", \"checkpoint_path\": \"output/models/contamination_60_tau06_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_tau06_seed42.log\", \"metrics\": {\"eval_ppl_holdout\": 17.7359, \"eval_loss_holdout\": 2.8756, \"eval_holdout_tokens\": 4077068, \"train_loss\": 8.9804, \"train_runtime_seconds\": 13367.3, \"train_samples_per_second\": 7.305, \"total_steps\": 6103, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T07:15:22.736Z\"}, \"contamination_60_tau07_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:04:49.597Z\", \"updated_at\": \"2026-05-16T06:10:38.506Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir output/models/contamination_60_tau07_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --tau 0.7 --n_min 2 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:0\"], \"pid\": \"282223\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_tau07_seed42.log\", \"submitted_at\": \"2026-05-16T02:09:01.658Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A\", \"eval_data\": \"N/A\", \"wall_clock_seconds\": 14272.7, \"gpu_hours\": 3.96}, \"hypothesis\": \"ρ=0.6 τ=0.7 diagnostic: Reviewer-suggested formula τ=1-ρ×0.5=0.7. Tests if τ downshift recovers adaptive to grid-best level (PPL≤17.71 target).\", \"parent\": \"contamination_60_seed42_r2\", \"notes\": \"D045 最高优先级。cuda:0, PID=282223, ρ=0.6 τ=0.7 (formula τ=1-ρ×0.5)。参数确认: tau=0.7, n_min=2, ρ=0.6, data=scored_data_60.jsonl (371499 samples)。\\n\\n**结果分析**: PPL=17.73。vs τ=0.8(17.74): -0.01 改善，formula 方向正确。vs grid-best(17.704): +0.026 未达标。vs uniform(17.766): -0.036 显著优于。vs ESS-only(17.77): -0.04。\\n\\n**Claim 3 解读**: formula τ=1-ρ×0.5 给出正确方向但非必需——default τ=0.8 已足够好（τ sensitivity 低）。支持 \\\"proportion-agnostic\\\" framing：无需知道 ρ 即可有效工作。\", \"reproduce\": {\"finished_at\": \"2026-05-16T05:58:17.061Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T05:58:19.203891+00:00\"}]}, \"checkpoint_path\": \"output/models/contamination_60_tau07_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_tau07_seed42.log\", \"metrics\": {\"eval_ppl_holdout\": 17.73, \"eval_loss_holdout\": 2.875, \"eval_holdout_tokens\": 4077068, \"train_loss\": 9.358, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T06:06:54.366Z\"}, \"detect_remove_baseline_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T00:26:48.402Z\", \"updated_at\": \"2026-05-16T05:25:32.239Z\", \"hypothesis\": \"Detect-and-remove baseline: hard-filter q&gt;0.5 samples then train uniformly on remaining data. Answers reviewer question \\\"why not just filter instead of reweight?\\\" Expected to underperform adaptive weighting due to information loss from discarded samples.\", \"parent\": \"uniform_seed42\", \"notes\": \"完成时 conclusion 指引: b=0 throughout; adaptive degenerates to uniform post-filtering. detect-and-remove alone sufficient — adaptive adds no value on already-clean data. 写论文时注意: filtered subset (~153K) 训练 200M tokens 重复 ~2.4x，而 adaptive 用全部 ~371K 只过 1 遍，effective epoch 不同需在 experiment section 说明。\", \"spec\": {\"checkpoint_path\": \"output/models/detect_remove_baseline_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/detect_remove_baseline_seed42.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-16T05:19:15.608Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T05:19:17.956961+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.29, \"eval_loss_holdout\": 2.8499, \"eval_holdout_tokens\": 4077068, \"train_loss\": 11.003, \"train_runtime_seconds\": 13248, \"total_steps\": 6103, \"train_samples_per_second\": 7.371}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T05:25:32.239Z\"}, \"grid_b0_3_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T00:26:45.815Z\", \"updated_at\": \"2026-05-16T05:03:15.767Z\", \"hypothesis\": \"Grid-b sweep b=0.3 on ρ=0.4 data, seed42. Near suspected optimal region (grid-best b=0.5). Tests if b<0.5 improves PPL. Part of b* curve characterization for Claim 2.\", \"parent\": \"grid_b_seed42_batch\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --weighting_method grid --grid_b_value 0.3 --seed 42\", \"server\": \"westd-47453\", \"gpu\": \"cuda:1\", \"pid\": 274304, \"log_path\": \"/root/runs/provenance_weight_training/grid_b0_3_seed42.log\", \"submitted_at\": \"2026-05-16T01:13:08.506Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"models/Qwen/Qwen3-0.6B\", \"eval_data\": \"data/human/eval_holdout.jsonl\", \"checkpoint_path\": \"/root/provenance_weight_training/output/models/grid_b0_3_seed42/final\", \"wall_clock_seconds\": 13807.3, \"gpu_hours\": 3.84}, \"reproduce\": {\"finished_at\": \"2026-05-16T04:57:12.423Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T04:57:14.788065+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.64, \"eval_loss_holdout\": 2.8702, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"train_loss\": 9.1154, \"train_runtime_seconds\": 13365.79, \"train_samples_per_second\": 7.306, \"total_steps\": 6103, \"b_fixed\": 0.3, \"alpha_eff_typical_range\": \"0.07-0.88\", \"ess_typical_range\": \"2.3-4.0\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T05:03:15.767Z\"}, \"tau_095_nmin2_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-16T01:22:54.457Z\", \"updated_at\": \"2026-05-16T03:05:15.616Z\", \"hypothesis\": \"τ=0.95 rerun with correct n_min=2 (original tau_095_seed42 used n_min=3 confound). Most strict α_eff threshold, may over-constrain b*.\", \"parent\": \"tau_095_seed42\", \"completed_at\": \"2026-05-16T02:45:16.182Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"killed\"}}, \"notes\": \"D048: 原始 tau_095_seed42 已确认 n_min=2，数据干净。二次 killed，不重跑。\", \"conclusion\": \"killed\"}, \"tau_09_nmin2_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-16T01:22:52.989Z\", \"updated_at\": \"2026-05-16T03:05:14.824Z\", \"hypothesis\": \"τ=0.9 rerun with correct n_min=2 (original tau_09_seed42 used n_min=3 confound). Tests if τ>0.8 still degrades with corrected n_min.\", \"parent\": \"tau_09_seed42\", \"completed_at\": \"2026-05-16T02:45:15.433Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"killed\"}}, \"notes\": \"D048: 原始 tau_09_seed42 已确认 n_min=2，数据干净。二次 killed，不重跑。\", \"conclusion\": \"killed\"}, \"nmin5_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:52:01.911Z\", \"updated_at\": \"2026-05-16T03:03:02.805Z\", \"spec\": {\"hypothesis\": \"n_min=5 > batch_size=4, code clamps to n_min=4, ESS(b=0)=4 is only feasible point → b*=0 always → degenerate uniform case. Validates theoretical prediction.\", \"parent\": \"adaptive_fix_seed42\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T03:03:02.017Z\", \"notes\": \"D047 砍掉，GPU 预算不够。\"}, \"grid_b5_0_seed456\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T06:59:39.050Z\", \"updated_at\": \"2026-05-16T03:01:26.368Z\", \"hypothesis\": \"Grid-b weighting with b=5.0, seed=456, for multi-seed validation of best-b baseline\", \"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-15T00:52:41.923Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b5_0_seed456 --weighting_method grid --grid_b_value 5.0 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 456 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --eval_data_path data/human/eval_holdout.jsonl --eval_steps 500\\\"\", \"finished_at\": \"2026-05-15T09:31:34.604Z\", \"training_hours\": 8.65}, \"failure_reason\": \"\", \"notes\": \"checkpoint_artifact: true. D026 决策：seed456 b≥2.0 的 PPL 异常高（checkpoint 问题），论文只报 2-seed 数据。\", \"completed_at\": \"2026-05-15T07:46:15.281Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T07:46:16.570901+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:31:35.946616+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"方案 A 重跑：无 inline eval，从 checkpoint-3000 恢复（~3100 步剩余）。PID=183240, cuda:2, timeout=5h。训练完后 post-hoc eval。\"}}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b5_0_seed456 --weighting_method grid --grid_b_value 5.0 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 456 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --bf16 --resume_from_checkpoint output/models/grid_b5_0_seed456/checkpoint-3000\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:2\"], \"pid\": \"183240\", \"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"log_path\": \"~/runs/provenance_weight_training/grid_b5_0_seed456.log\"}, \"metrics\": {\"eval_ppl_holdout\": 17.993, \"eval_loss\": 2.89, \"eval_holdout_tokens\": 4077068, \"train_loss\": 5.488, \"total_steps\": 6103, \"train_runtime_s\": 6601, \"gpu_hours\": 1.83, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"checkpoint_path\": \"output/models/grid_b5_0_seed456/final\", \"conclusion\": \"success\"}, \"grid_b3_0_seed456\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T06:59:38.011Z\", \"updated_at\": \"2026-05-16T03:01:25.067Z\", \"hypothesis\": \"Grid-b weighting with b=3.0, seed=456, for multi-seed validation of best-b baseline\", \"server\": \"westd-47453\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-15T00:52:41.254Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b3_0_seed456 --weighting_method grid --grid_b_value 3.0 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 456 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --eval_data_path data/human/eval_holdout.jsonl --eval_steps 500\\\"\", \"finished_at\": \"2026-05-15T09:31:37.181Z\", \"training_hours\": 8.65}, \"failure_reason\": \"\", \"notes\": \"checkpoint_artifact: true. D026 决策：seed456 b≥2.0 的 PPL 异常高（checkpoint 问题），论文只报 2-seed 数据。\", \"completed_at\": \"2026-05-15T07:46:09.092Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T07:46:12.926805+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:31:39.113223+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"方案 A 重跑：无 inline eval，从 checkpoint-3000 恢复（~3100 步剩余）。PID=183446, cuda:3, timeout=5h。训练完后 post-hoc eval。\"}}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b3_0_seed456 --weighting_method grid --grid_b_value 3.0 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 456 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --bf16 --resume_from_checkpoint output/models/grid_b3_0_seed456/checkpoint-3000\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:3\"], \"pid\": \"183446\", \"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"log_path\": \"~/runs/provenance_weight_training/grid_b3_0_seed456.log\"}, \"metrics\": {\"eval_ppl_holdout\": 17.921, \"eval_loss\": 2.886, \"eval_holdout_tokens\": 4077068, \"train_loss\": 5.435, \"total_steps\": 6103, \"train_runtime_s\": 6602, \"gpu_hours\": 1.83, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"checkpoint_path\": \"output/models/grid_b3_0_seed456/final\", \"conclusion\": \"success\"}, \"grid_b2_0_seed456\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T06:59:37.073Z\", \"updated_at\": \"2026-05-16T03:01:24.083Z\", \"hypothesis\": \"Grid-b weighting with b=2.0, seed=456, for multi-seed validation of best-b baseline\", \"server\": \"westd-47453\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T22:22:43.944Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b2_0_seed456 --weighting_method grid --grid_b_value 2.0 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 456 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --eval_data_path data/human/eval_holdout.jsonl --eval_steps 500\\\"\", \"finished_at\": \"2026-05-15T09:15:04.029Z\", \"training_hours\": 10.87}, \"failure_reason\": \"eval overhead timeout at 65.5% (checkpoint-3500 available). Eval dataset 8477 samples × every 500 steps caused ~40min per eval round, exceeding original timeout.\", \"completed_at\": \"2026-05-15T07:31:09.178Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T07:31:10.598336+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:15:05.368569+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"恢复自 checkpoint-3500（原超时于 65.5%）。timeout 增至 6h（原因：eval 8477 条 × 每 500 步 ≈ 40min/轮）。PID=182488, cuda:0。\"}}, \"notes\": \"checkpoint_artifact: true. D026 决策：seed456 b≥2.0 的 PPL 异常高（checkpoint 问题），论文只报 2-seed 数据。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b2_0_seed456 --weighting_method grid --grid_b_value 2.0 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 456 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --bf16 --resume_from_checkpoint output/models/grid_b2_0_seed456/checkpoint-3500\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:0\"], \"pid\": \"183161\", \"log_path\": \"~/runs/provenance_weight_training/grid_b2_0_seed456.log\", \"submitted_at\": \"2026-05-15T07:40:59.398Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 6408.6, \"gpu_hours\": 1.78}, \"metrics\": {\"eval_ppl_holdout\": 17.989, \"eval_loss\": 2.8898, \"eval_holdout_tokens\": 4077068, \"train_loss\": 10.625, \"total_steps\": 6103, \"train_runtime_s\": 12969, \"gpu_hours\": 3.6, \"train_samples_per_second\": 7.53, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\"}, \"checkpoint_path\": \"output/models/grid_b2_0_seed456/final\", \"conclusion\": \"success\"}, \"ess_only_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:20:13.656Z\", \"updated_at\": \"2026-05-16T03:01:02.547Z\", \"hypothesis\": \"ESS-only adaptive baseline (max-intervention): b* = max{b : ESS(b) ≥ n_min} — proves min-intervention (adaptive) superior to max-intervention (ESS-only)\", \"server\": \"westd-47453\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T09:13:26.412Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/ess_only_seed42 --weighting_method ess_only --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --tau 0.8 --bf16\\\"\", \"finished_at\": \"2026-05-15T12:50:22.690Z\", \"training_hours\": 3.62}, \"spec\": {\"n_min\": 2, \"weighting_method\": \"ess_only\"}, \"pid\": \"189240\", \"log_path\": \"~/runs/provenance_weight_training/ess_only_seed42.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T12:50:24.148259+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"eval_ppl\": 17.73, \"eval_loss\": 2.875, \"b_star_median\": 1.58, \"b_star_mean\": 3.51, \"vs_uniform_ppl_delta\": \"+0.038\", \"vs_adaptive_ppl_delta\": \"+0.08\"}, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/ess_only_seed42\", \"completed_at\": \"2026-05-15T13:29:03.148Z\"}, \"adaptive_v2_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:19.549Z\", \"updated_at\": \"2026-05-16T02:50:32.828Z\", \"hypothesis\": \"Adaptive v2 (n_min fix: 3→2, no EMA) maintains or improves seed456 performance (baseline adaptive PPL=17.64)\", \"conclusion\": \"killed\", \"notes\": \"D012 修正：取消 v2（含 EMA），改用 adaptive_fix（仅修 n_min=2，无 EMA）\", \"completed_at\": \"2026-05-16T02:50:32.054Z\"}, \"adaptive_v2_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:19.157Z\", \"updated_at\": \"2026-05-16T02:50:31.386Z\", \"hypothesis\": \"Adaptive v2 (n_min fix: 3→2, no EMA) maintains or improves seed123 performance (baseline adaptive PPL=17.63)\", \"conclusion\": \"killed\", \"notes\": \"D012 修正：取消 v2（含 EMA），改用 adaptive_fix（仅修 n_min=2，无 EMA）\", \"completed_at\": \"2026-05-16T02:50:30.507Z\"}, \"adaptive_v2_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:18.265Z\", \"updated_at\": \"2026-05-16T02:50:29.963Z\", \"hypothesis\": \"Adaptive v2 (n_min fix: 3→2, no EMA) fixes ESS clamping issue, achieves meaningful improvement over uniform baseline for seed=42\", \"conclusion\": \"killed\", \"notes\": \"D012 修正：取消 v2（含 EMA），改用 adaptive_fix（仅修 n_min=2，无 EMA）\", \"completed_at\": \"2026-05-16T02:50:29.147Z\"}, \"tau_07_nmin2_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:22:51.146Z\", \"updated_at\": \"2026-05-16T02:45:14.675Z\", \"spec\": {\"hypothesis\": \"τ=0.7 rerun with correct n_min=2 (original tau_07_seed42 used n_min=3 confound). Slightly below optimal τ=0.8.\", \"parent\": \"tau_07_seed42\"}, \"hypothesis\": \"τ=0.7 rerun with correct n_min=2 (original tau_07_seed42 used n_min=3 confound). Slightly below optimal τ=0.8.\", \"parent\": \"tau_07_seed42\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T02:45:14.675Z\"}, \"tau_06_nmin2_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:22:49.217Z\", \"updated_at\": \"2026-05-16T02:45:13.922Z\", \"spec\": {\"hypothesis\": \"τ=0.6 rerun with correct n_min=2 (original tau_06_seed42 used n_min=3 confound). Tests lower τ region with proper ESS constraint.\", \"parent\": \"tau_06_seed42\"}, \"hypothesis\": \"τ=0.6 rerun with correct n_min=2 (original tau_06_seed42 used n_min=3 confound). Tests lower τ region with proper ESS constraint.\", \"parent\": \"tau_06_seed42\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T02:45:13.922Z\"}, \"tau_05_nmin2_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:22:47.367Z\", \"updated_at\": \"2026-05-16T02:45:13.057Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/tau_05_nmin2_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --tau 0.5 --n_min 2 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:0\"], \"pid\": \"281298\", \"log_path\": \"~/runs/provenance_weight_training/tau_05_nmin2_seed42.log\", \"submitted_at\": \"2026-05-16T01:58:41.186Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 2791.9, \"gpu_hours\": 0.78}, \"hypothesis\": \"τ=0.5 rerun with correct n_min=2 (original tau_05_seed42 used n_min=3 confound). Most permissive α_eff threshold, expect b*≈0 for many batches.\", \"parent\": \"tau_05_seed42\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T02:45:13.057Z\"}, \"contamination_60_seed42_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:53:48.975Z\", \"updated_at\": \"2026-05-16T01:57:12.472Z\", \"hypothesis\": \"Retry of contamination_60_seed42 (failed due to GPU conflict on cuda:2). ρ=0.6 adaptive weighting (τ=0.8, n_min=2) on higher contamination data. Tests graceful degradation as ρ increases from 0.4→0.6.\", \"parent\": \"contamination_60_seed42\", \"server\": \"westd-47453\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir output/models/contamination_60_seed42_r2 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:0\"], \"pid\": \"257977\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_seed42_r2.log\", \"submitted_at\": \"2026-05-15T21:54:22.934Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14569.5, \"gpu_hours\": 4.05}, \"pid\": \"257977\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_seed42_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir output/models/contamination_60_seed42_r2 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"finished_at\": \"2026-05-16T01:51:18.700Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T01:51:20.683620+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.74, \"eval_loss_holdout\": 2.8759, \"eval_tokens\": 4077068, \"eval_method\": \"sliding_window_2048_stride1024\", \"train_loss\": 9.6349, \"train_runtime_seconds\": 14092.25}, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/contamination_60_seed42_r2/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T01:57:12.472Z\"}, \"contamination_60_grid_b0_5_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:19:25.407Z\", \"updated_at\": \"2026-05-16T01:47:52.701Z\", \"hypothesis\": \"ρ=0.6 grid-best (b=0.5) baseline: fixed b=0.5 on 60% contamination. Tests if grid-optimal b from ρ=0.4 transfers to higher contamination, or if adaptive b* adapts better.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir output/models/contamination_60_grid_b0_5_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method grid --grid_b_value 0.5 --contamination_ratio 0.6 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:3\"], \"pid\": \"255781\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_grid_b0_5_seed42.log\", \"submitted_at\": \"2026-05-15T21:49:22.242Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/provenance_weight_training/data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A\", \"eval_data\": \"N/A\", \"wall_clock_seconds\": 13153.5, \"gpu_hours\": 3.65}, \"parent\": \"grid_b0_5_seed456\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:3\"], \"reproduce\": {\"finished_at\": \"2026-05-16T01:28:34.213Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T01:28:35.712Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T01:28:37.428483+00:00\"}]}, \"notes\": \"训练完成 6103/6103 steps。EXIT_CODE=129 (SIGHUP) 发生在训练完成后（与 contamination_60_uniform_seed42 同一模式）。WANDB_MODE=disabled 导致 cron 误判为 failed。实际 success，等 eval PPL。\", \"metrics\": {\"eval_ppl\": 17.704, \"eval_loss\": 2.8738, \"eval_tokens\": 4077068, \"eval_docs\": 5000}, \"checkpoint_path\": \"output/models/contamination_60_grid_b0_5_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_grid_b0_5_seed42.log\"}, \"contamination_60_uniform_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:19:24.785Z\", \"updated_at\": \"2026-05-16T01:12:50.897Z\", \"hypothesis\": \"ρ=0.6 uniform baseline: no reweighting on 60% contamination data. Establishes baseline PPL degradation at higher contamination for comparison with adaptive and grid methods.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir output/models/contamination_60_uniform_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.6 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:1\"], \"pid\": \"250074\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_uniform_seed42.log\", \"submitted_at\": \"2026-05-15T21:26:23.538Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 12988.3, \"gpu_hours\": 3.61, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/contamination_60_uniform_seed42/final\"}, \"parent\": \"uniform_seed42\", \"server\": \"westd-47453\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T21:19:46.484Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir output/models/contamination_60_uniform_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method uniform --contamination_ratio 0.6 --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --save_steps 500 --logging_steps 10 --bf16 --save_total_limit 3 --save_only_model\\\"\", \"finished_at\": \"2026-05-16T01:02:50.356Z\", \"training_hours\": 3.72}, \"pid\": \"250074\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_uniform_seed42.log\", \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T01:02:51.880Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T01:02:54.397978+00:00\"}]}, \"notes\": \"训练实际已完成 (6103/6103 steps, 3:35:04)。模型已保存到 output/models/contamination_60_uniform_seed42/final。EXIT_CODE=129 (SIGHUP) 发生在训练完成后。WANDB_MODE=disabled 导致 cron 误判为 failed。train_loss=7.649 (avg), train_runtime=12904s。需要 eval 获取 PPL。\", \"metrics\": {\"eval_ppl_holdout\": 17.766, \"eval_loss_holdout\": 2.8773, \"eval_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py sliding-window (stride=1024, max_length=2048, fp16) on data/human/eval_holdout.jsonl\", \"train_loss\": 7.649, \"train_runtime_seconds\": 12904}, \"checkpoint_path\": \"output/models/contamination_60_uniform_seed42/final\"}, \"bs8_nmin2_seed42_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:48:45.682Z\", \"updated_at\": \"2026-05-16T00:26:45.368Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/bs8_nmin2_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --max_length 2048 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 3 --save_only_model --bf16\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:2\"], \"pid\": \"238714\", \"log_path\": \"~/runs/provenance_weight_training/bs8_nmin2_seed42_r2.log\", \"submitted_at\": \"2026-05-15T18:48:45.530Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 200000000, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A (training resubmit, not eval)\", \"eval_data\": \"N/A (training resubmit, not eval)\", \"wall_clock_seconds\": 14753.4, \"gpu_hours\": 4.1}, \"hypothesis\": \"batch_size=8 with n_min=2 (correct coupling: n_min=max(2,bs//2)=4→override to 2 for wider ESS dynamic range [2,8]). Resubmit after zombie cleanup on cuda:2. Parent: bs8_nmin2_seed42 (OOM due to zombie).\", \"parent\": \"bs8_nmin2_seed42\", \"plan_id\": \"p0_batchsize_8\", \"notes\": \"训练完成 6103/6103 steps, train_loss=5.4065. EXIT_CODE=129 (SIGHUP) 发生在训练完成后 W&B finalization 阶段，不影响结果。Checkpoint 验证通过。Eval PPL=17.73 > uniform avg 17.694 (+0.036), 与 ESS-only 水平相当(~17.72)。**NEGATIVE but informative**: B=8, n_min=2 (n_min/B=0.25) 导致 ESS range [2,8] 过宽，b* 无法有效约束。与 B=4,n_min=2 (n_min/B=0.5, works) 和 B=4,n_min=4 (n_min/B=1.0, degenerates to uniform) 共同支持 coupling rule n_min=⌊B/2⌋ 的必要性。Director 决策：写入 experiments n_min analysis，不放 limitation section。\", \"reproduce\": {\"finished_at\": \"2026-05-15T22:54:37.472Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T22:54:38.917Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:54:40.392745+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.73, \"eval_loss_holdout\": 2.8752, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py on data/human/eval_holdout.jsonl, max_docs=5000, stride=1024, fp16\", \"train_loss\": 5.4065, \"train_steps\": 6103, \"train_runtime_seconds\": 14621.6}, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/bs8_nmin2_seed42/final\"}, \"grid_b_low_serial_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:56:07.484Z\", \"updated_at\": \"2026-05-15T23:43:07.407Z\", \"hypothesis\": \"Grid-b low sweep (b=0.1, 0.2, 0.3 serial, hardcoded) on ρ=0.4 data, seed42. No shell variables — each b value hardcoded to avoid quoting issues. R3 of grid_b_low_seed42.\", \"parent\": \"grid_b_seed42_batch\", \"spec\": {\"command\": \"bash /root/provenance_weight_training/run_grid_b_low_serial.sh\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:2\"], \"pid\": \"265606\", \"log_path\": \"~/runs/provenance_weight_training/grid_b_low_serial_seed42.log\", \"submitted_at\": \"2026-05-15T23:33:20.929Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 351.2, \"gpu_hours\": 0.1}, \"conclusion\": \"killed\", \"notes\": \"R4 killed: cuda:2 GPU冲突，与contamination_60_ess_only_seed42双进程占满显存(93042/97887 MiB)，仅完成48/6103步。第3次因GPU冲突失败(R3=cuda:0撞contamination_60, R4=cuda:2撞ess_only)。PID 265617已确认死亡，cuda:2显存恢复至~46.5GB，ess_only速度从~4.5s/it恢复至2.12s/it。需在空卡上R5重启——cuda:1预计~1h21m后释放（contamination_60_uniform完成）。\", \"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-15T23:33:18.725Z\", \"command\": \"bash /root/provenance_weight_training/run_grid_b_low_serial.sh\"}, \"pid\": \"265606\", \"log_path\": \"~/runs/provenance_weight_training/grid_b_low_serial_seed42.log\", \"completed_at\": \"2026-05-15T23:39:12.167Z\"}, \"grid_b_low_seed42_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:53:08.449Z\", \"updated_at\": \"2026-05-15T21:57:46.419Z\", \"hypothesis\": \"Low-b grid sweep (b=0.1, 0.2, 0.3) on ρ=0.4 data, seed42. R3: uses standalone shell script to avoid quoting issues. Confirms behavior in b<0.5 region.\", \"parent\": \"grid_b_low_seed42_r2\", \"spec\": {\"command\": \"bash /root/provenance_weight_training/scripts/run_grid_b_low_seed42.sh\", \"server\": \"westd-47453\", \"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A (training, not eval)\", \"eval_data\": \"N/A (training, not eval)\"}, \"conclusion\": \"failed\", \"notes\": \"Worker 提交时未指定 GPU，导致与 cuda:0 上的 contamination_60_seed42_r2 冲突。PID 258500 在启动后秒级崩溃。grid_b_low 需在 GPU 释放后单独提交（每个 b 值独立实验或硬编码脚本 + 显式 CUDA_VISIBLE_DEVICES）。\", \"completed_at\": \"2026-05-15T21:57:46.419Z\"}, \"grid_b_low_seed42_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:19:36.129Z\", \"updated_at\": \"2026-05-15T21:55:52.896Z\", \"hypothesis\": \"Low-b grid sweep (b=0.1, 0.2, 0.3) on ρ=0.4 data, seed42. Confirms behavior in b<0.5 region — expect minimal reweighting effect and PPL close to uniform. Establishes that b=0.5 is already near the lower useful bound.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && for b in 0.1 0.2 0.3; do echo '=== Training grid b='$b' ===' && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b_low_b${b}_seed42 --weighting_method grid --grid_b_value $b --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --bf16 || exit 1; done\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:0\"], \"pid\": \"256582\", \"log_path\": \"~/runs/provenance_weight_training/grid_b_low_seed42_r2.log\", \"submitted_at\": \"2026-05-15T21:50:10.451Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 24.1, \"gpu_hours\": 0.01}, \"parent\": \"grid_b_seed42_batch\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:0\"], \"reproduce\": {\"finished_at\": \"2026-05-15T21:50:31.477Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T21:50:34.583Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:50:36.985471+00:00\"}]}, \"notes\": \"失败根因：bash -c \\\"...\\\" 双引号内的 $b 被外层 shell 提前展开为空字符串，导致 --grid_b_value 收到空参数，argparse 报错 \\\"expected one argument\\\" 立即退出。日志首行 \\\"Training grid b= ===\\\" 确认 $b 为空。修复方法：将 $b 转义为 \\\\$b（如 \\\\$b 和 \\\\${b}），或改用 bash -c '...'（需处理内部单引号），或拆成三条独立命令分别指定 b=0.1/0.2/0.3。\"}, \"baseline_qwen3_0.6b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:53:53.450Z\", \"updated_at\": \"2026-05-15T21:54:29.041Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python eval_perplexity.py --checkpoints models/Qwen/Qwen3-0.6B --data_path data/human/eval_holdout.jsonl --max_docs 5000\", \"server\": \"westd-47453\", \"data_path\": \"data/human/eval_holdout.jsonl\", \"data_count\": 5000, \"model_name\": \"Qwen3-0.6B\", \"seed\": 0, \"checkpoint_source\": \"models/Qwen/Qwen3-0.6B\", \"eval_data\": \"data/human/eval_holdout.jsonl\", \"checkpoint_path\": \"models/Qwen/Qwen3-0.6B\", \"log_path\": \"/root/runs/provenance_weight_training/qwen3_0.6b_baseline_eval.log\"}, \"checkpoint_path\": \"models/Qwen/Qwen3-0.6B\", \"log_path\": \"/root/runs/provenance_weight_training/qwen3_baseline_eval.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:54:15.419Z\", \"hypothesis\": \"Raw Qwen3-0.6B pretrained checkpoint baseline PPL (no continued pretraining). Reference point for quantifying absolute improvement from training.\", \"metrics\": {\"eval_ppl_holdout\": 22.97, \"eval_loss\": 3.134, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"sliding_window_stride1024_maxlen2048_fp16\"}, \"notes\": \"Baseline PPL=22.9654 (loss=3.1340), tokens=4,077,068, time=249s. Weight SHA256=f47f71177f32bcd101b7573ec9171e6a57f4f4d31148d38e382306f42996874b. Pretrained weights confirmed (std ~0.02-0.03, layernorm varies across layers). Compared to ess_only_seed456 PPL=17.72: continued pretraining reduces PPL by 22.8%.\"}, \"contamination_60_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:12:18.751Z\", \"updated_at\": \"2026-05-15T21:26:20.768Z\", \"spec\": {\"data_path\": \"data/scored_data_60.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"contamination_ratio\": 0.6, \"hyperparams\": {\"n_min\": 2, \"tau\": 0.8, \"batch_size\": 4, \"gradient_accumulation_steps\": 4, \"learning_rate\": 5e-05, \"max_length\": 2048}}, \"hypothesis\": \"ρ=0.6 contamination robustness test: adaptive weighting (τ=0.8, n_min=2) on higher contamination ratio data. Baseline adaptive_fix_seed42 (ρ=0.4) PPL=17.6527. Tests if adaptive method degrades gracefully as contamination increases from 0.4→0.6.\", \"parent\": \"adaptive_fix_seed42\", \"notes\": \"数据验证通过: scored_data_60.jsonl 371,499行/907MB, synthetic=222900/human=148599, actual ρ=0.6。q_score: mean=0.6243, std=0.3703, median=0.7753。字段: text/depth/source_model/prompt_tokens/generated_tokens/decoding/q_score。符号链接 scored_data_rho06.jsonl → scored_data_60.jsonl。配置基于 adaptive_fix_seed42，改 data_path + contamination_ratio=0.6。\\n\\n**失败诊断**: GPU 分配冲突——实验被分配到 cuda:2，但 bs8_nmin2_seed42_r2 (pid=238714) 已在 cuda:2 运行，占用 79.78 GiB 显存。启动 24 秒即 OOM。非代码问题，需在空闲 GPU 上重试。\", \"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-15T21:23:32.567Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data_60.jsonl --output_dir output/models/contamination_60_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.6 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 4 --gradient_accumulation_steps 4 --learning_rate 5e-5 --max_length 2048 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 3 --save_only_model --bf16\\\"\", \"finished_at\": \"2026-05-15T21:23:56.641Z\", \"training_hours\": 0.01}, \"pid\": \"249588\", \"log_path\": \"~/runs/provenance_weight_training/contamination_60_seed42.log\", \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 48.00 MiB. GPU 0 has a total capacity of 94.97 GiB of which 34.81 MiB is free. Process 238719 has 79.78 GiB memory in use. Including non-PyTorch memory, this process has 15.14 GiB memory in use. Of the allocated \", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T21:23:57.827Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:23:59.292519+00:00\"}]}}, \"nmin4_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:36:45.229Z\", \"updated_at\": \"2026-05-15T21:22:25.975Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/nmin4_seed42 --weighting_method adaptive --n_min 4 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --tau 0.8 --bf16\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:1\"], \"pid\": \"225265\", \"log_path\": \"~/runs/provenance_weight_training/nmin4_seed42.log\", \"submitted_at\": \"2026-05-15T16:44:47.426Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen3-0.6B\", \"seed\": 42, \"wall_clock_seconds\": 16658.5, \"gpu_hours\": 4.63}, \"hypothesis\": \"n_min=4 (=batch_size) ablation: forces b*=0 always since ESS constraint cannot be satisfied with any b>0 when n_min=batch_size. Should degrade to uniform-equivalent PPL (~17.69). Key boundary condition for n_min sensitivity analysis.\", \"server\": \"westd-47453\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T16:43:55.347Z\", \"finished_at\": \"2026-05-15T21:16:33.618Z\", \"training_hours\": 4.54}, \"notes\": \"Mid-training check @step 2036/6103: b=0.0, ess=4.0 (=n_min), weighted_loss==unweighted_loss — confirms b*=0 degenerates to uniform weighting as theoretically predicted. Eval commands prepared for post-training.\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:16:35.372420+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.6947, \"eval_loss\": 2.8733, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"train_loss\": 7.989, \"total_steps\": 6103, \"train_runtime_s\": 16231, \"train_samples_per_second\": 6.016, \"b_star_count\": 24412, \"b_star_mean\": 0, \"b_star_median\": 0, \"b_star_std\": 0, \"b_star_min\": 0, \"b_star_max\": 0, \"b_star_pct_zero\": 100, \"ess_mean\": 4, \"ess_min\": 4, \"ess_max\": 4}, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/nmin4_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/nmin4_seed42.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:22:25.975Z\"}, \"bs8_nmin2_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:38:48.783Z\", \"updated_at\": \"2026-05-15T18:48:29.014Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/bs8_nmin2_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --max_length 2048 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 3 --save_only_model --bf16\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:2\"], \"pid\": \"237410\", \"log_path\": \"~/runs/provenance_weight_training/bs8_nmin2_seed42.log\", \"submitted_at\": \"2026-05-15T18:39:14.671Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 37.4, \"gpu_hours\": 0.01}, \"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"pid\": \"237410\", \"log_path\": \"~/runs/provenance_weight_training/bs8_nmin2_seed42.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/bs8_nmin2_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 2 --tau 0.8 --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --max_length 2048 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 3 --save_only_model --bf16\\\"\", \"finished_at\": \"2026-05-15T18:39:50.935Z\"}, \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 128.00 MiB. GPU 0 has a total capacity of 94.97 GiB of which 116.81 MiB is free. Process 236702 has 79.78 GiB memory in use. Including non-PyTorch memory, this process has 15.06 GiB memory in use. Of the allocate\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T18:39:52.061Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:39:53.502042+00:00\"}]}, \"notes\": \"OOM failed: GPU 2 was occupied by zombie PID 236702 (old bs8_seed42). Superseded by bs8_nmin2_seed42_r2. Config: n_min=2, bs=8, grad_accum=2, tau=0.8, adaptive, seed=42.\"}, \"bs8_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:04:41.935Z\", \"updated_at\": \"2026-05-15T18:43:36.187Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/bs8_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 4 --tau 0.8 --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --max_length 2048 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 3 --save_only_model --bf16\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:2\"], \"pid\": \"236697\", \"log_path\": \"~/runs/provenance_weight_training/bs8_seed42.log\", \"submitted_at\": \"2026-05-15T18:31:59.603Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 695.9, \"gpu_hours\": 0.19}, \"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"pid\": \"236697\", \"log_path\": \"~/runs/provenance_weight_training/bs8_seed42.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/bs8_seed42 --model_name models/Qwen/Qwen3-0.6B --weighting_method adaptive --contamination_ratio 0.4 --num_train_tokens 200000000 --n_min 4 --tau 0.8 --batch_size 8 --gradient_accumulation_steps 2 --learning_rate 5e-5 --max_length 2048 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 3 --save_only_model --bf16\\\"\", \"finished_at\": \"2026-05-15T18:43:32.689Z\"}, \"conclusion\": \"failed\", \"notes\": \"Killed at 1% (71/6103 steps). Wrong config: n_min=4 matches same ESS/bs ratio as n_min=2/bs=4. Director instructed restart with n_min=2 + bs=8 for wider ESS dynamic range [2,8]. Replaced by bs8_nmin2_seed42.\", \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"completed_at\": \"2026-05-15T18:43:35.489Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:43:39.292154+00:00\"}]}}, \"tau_09_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:03:28.658Z\", \"updated_at\": \"2026-05-15T18:07:01.223Z\", \"hypothesis\": \"τ sensitivity sweep: τ=0.9 (stricter α_eff threshold), testing if higher quality threshold improves PPL. Baseline τ=0.8 PPL=17.65.\", \"parent\": \"adaptive_fix_seed42\", \"spec\": {\"checkpoint_path\": \"/root/provenance_weight_training/output/models/tau_0.9_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/tau_09_seed42.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T17:48:21.169Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:48:25.502664+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"eval_ppl_holdout\": 17.712, \"eval_loss\": 2.8742, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15\", \"b_star_count\": 24412, \"b_star_mean\": 2.36, \"b_star_median\": 1.32, \"b_star_std\": 3.04, \"b_star_pct_above_2\": 33.7}, \"completed_at\": \"2026-05-15T18:07:01.223Z\"}, \"tau_07_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:03:27.838Z\", \"updated_at\": \"2026-05-15T17:57:12.394Z\", \"hypothesis\": \"τ sensitivity sweep: τ=0.7 (slightly below baseline), testing if moderate τ reduction improves or degrades PPL. Baseline τ=0.8 PPL=17.65.\", \"parent\": \"adaptive_fix_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/tau_0.7_seed42 --weighting_method adaptive --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --tau 0.7 --bf16\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:0\"], \"pid\": \"209824\", \"log_path\": \"~/runs/provenance_weight_training/tau_07_seed42.log\", \"submitted_at\": \"2026-05-15T13:35:52.041Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 200000000, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A - training from scratch\", \"eval_data\": \"N/A - training experiment\", \"wall_clock_seconds\": 15680.4, \"gpu_hours\": 4.36}, \"reproduce\": {\"finished_at\": \"2026-05-15T17:48:03.537Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:48:04.960427+00:00\"}]}, \"metrics\": {\"train_loss\": 9.6707, \"total_steps\": 6103, \"train_runtime_s\": 15065, \"train_samples_per_second\": 6.482, \"eval_ppl_holdout\": 17.6793, \"eval_loss\": 2.8724, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15\", \"b_star_count\": 24412, \"b_star_mean\": 0.8943, \"b_star_median\": 0.58, \"b_star_std\": 1.4007, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.3306, \"b_star_p75\": 0.9712, \"b_star_pct_zero\": 5.8, \"b_star_pct_below_0.5\": 36, \"b_star_pct_0.5_to_1\": 34.2, \"b_star_pct_1_to_2\": 16.2, \"b_star_pct_above_2\": 7.7}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/provenance_weight_training/output/models/tau_0.7_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/tau_07_seed42.log\", \"completed_at\": \"2026-05-15T17:57:12.394Z\"}, \"tau_06_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:01:37.442Z\", \"updated_at\": \"2026-05-15T17:09:55.541Z\", \"hypothesis\": \"τ sensitivity sweep: τ=0.6 (lower α_eff threshold) may allow more aggressive downweighting, testing if PPL improves or degrades vs τ=0.8 baseline (adaptive_fix PPL=17.65). Key evidence for Claim 3 (τ as robust empirical hyperparameter).\", \"parent\": \"adaptive_fix_seed42\", \"server\": \"westd-47453\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-15T10:01:53.614Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/tau_0.6_seed42 --weighting_method adaptive --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --tau 0.6 --bf16\\\"\", \"finished_at\": \"2026-05-15T13:47:39.608Z\", \"training_hours\": 3.76}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/tau_0.6_seed42 --weighting_method adaptive --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --tau 0.6 --bf16\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:3\"], \"pid\": \"195746\", \"log_path\": \"~/runs/provenance_weight_training/tau_06_seed42.log\", \"submitted_at\": \"2026-05-15T10:01:55.290Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 13972.6, \"gpu_hours\": 3.88, \"tau\": 0.6, \"seed\": 42, \"rho\": 0.4, \"model\": \"Qwen3-0.6B\", \"tokens\": \"200M\", \"method\": \"adaptive\", \"parent\": \"adaptive_fix_seed42\", \"checkpoint_path\": \"/root/provenance_weight_training/output/models/tau_0.6_seed42/final\", \"eval_results_path\": \"/root/provenance_weight_training/output/eval/posthoc_eval_tau_06_seed42.json\"}, \"pid\": \"195746\", \"log_path\": \"~/runs/provenance_weight_training/tau_06_seed42.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:47:40.932954+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.6805, \"eval_loss\": 2.8725, \"train_loss\": 9.275, \"total_steps\": 6103, \"train_runtime_s\": 13436.64, \"train_samples_per_second\": 7.267, \"b_star_mean\": 0.5899, \"b_star_median\": 0.3746, \"b_star_std\": 1.0693, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.1195, \"b_star_p75\": 0.66, \"b_star_zero_frac\": 0.156, \"b_star_nonzero_mean\": 0.699, \"b_star_nonzero_median\": 0.4473}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/provenance_weight_training/output/models/tau_0.6_seed42/final\", \"completed_at\": \"2026-05-15T13:54:47.892Z\", \"notes\": \"PPL=17.681 劣于 τ=0.8 baseline (17.650)，conclusion=negative。概念修正：τ 越低 → α_eff 下界越松 → b* 更小 → 降权力度更弱（非更激进）。正确因果链：τ 越高 → α_eff 下界越严 → min-intervention 需要更大 b* 才能满足约束 → 降权力度更强。\"}, \"tau_05_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:03:27.263Z\", \"updated_at\": \"2026-05-15T17:06:51.535Z\", \"hypothesis\": \"τ sensitivity sweep: τ=0.5 (most permissive α_eff threshold), testing lower bound of useful τ range. Baseline τ=0.8 PPL=17.65.\", \"parent\": \"adaptive_fix_seed42\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/tau_0.5_seed42 --weighting_method adaptive --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --tau 0.5 --bf16\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:1\"], \"pid\": \"205652\", \"log_path\": \"~/runs/provenance_weight_training/tau_05_seed42.log\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 200000000, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_source\": \"N/A - training from scratch\", \"eval_data\": \"N/A - training experiment\"}, \"gpu\": \"cuda:1\", \"server\": \"westd-47453\", \"reproduce\": {\"finished_at\": \"2026-05-15T16:40:01.070Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T16:40:02.552045+00:00\"}]}, \"metrics\": {\"train_loss\": 8.849, \"total_steps\": 6103, \"epoch\": 0.26, \"train_runtime_s\": 13431.4, \"train_samples_per_second\": 7.27, \"eval_ppl_holdout\": 17.688, \"eval_loss\": 2.8729, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, autocast fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15\", \"b_star_count\": 24412, \"b_star_mean\": 0.3923, \"b_star_median\": 0.1707, \"b_star_std\": 0.8821, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0, \"b_star_p75\": 0.4366, \"b_star_pct_zero\": 29.1, \"b_star_pct_below_0.5\": 78.4, \"b_star_pct_0.5_to_1\": 12.9, \"b_star_pct_1_to_2\": 5.7, \"b_star_pct_above_2\": 2.9}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T16:44:08.996Z\", \"checkpoint_path\": \"output/models/tau_0.5_seed42/final\", \"log_path\": \"~/runs/provenance_weight_training/tau_05_seed42.log\"}, \"adaptive_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T02:25:03.137Z\", \"updated_at\": \"2026-05-15T16:43:10.982Z\", \"hypothesis\": \"Adaptive b* (from α_eff theory) matches or exceeds grid-searched best-b without grid search, seed=456\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/adaptive_seed456 --weighting_method adaptive --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 456 --logging_steps 10 --save_steps 500 --eval_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:3\"], \"pid\": \"59058\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_seed456.log\", \"submitted_at\": \"2026-05-14T02:46:25.330Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"checkpoint_path\": \"output/models/adaptive_seed456/final\", \"wall_clock_seconds\": 15161.8, \"gpu_hours\": 4.21}, \"metrics\": {\"train_loss\": 9.2354, \"train_runtime_s\": 13130.09, \"total_steps\": 6103, \"train_samples_per_second\": 7.437, \"train_steps_per_second\": 0.465, \"epoch\": 0.26, \"weighting_method\": \"adaptive\", \"tau\": 0.8, \"n_min\": 3, \"contamination_ratio\": 0.4, \"b_star\": \"per-batch adaptive (0.0-3.8)\", \"alpha_eff_range\": \"0.09-0.80 (capped at tau)\", \"eval_ppl_holdout\": 17.6419, \"eval_loss_holdout\": 2.8703, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.64/4080000 from inline eval\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T06:59:07.123Z\", \"notes\": \"⚠️ success 仅指训练完成无报错。MVP 假设验证待 held-out eval perplexity 结果。\"}, \"adaptive_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T02:25:02.771Z\", \"updated_at\": \"2026-05-15T16:43:08.120Z\", \"hypothesis\": \"Adaptive b* (from α_eff theory) matches or exceeds grid-searched best-b without grid search, seed=123\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/adaptive_seed123 --weighting_method adaptive --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 123 --logging_steps 10 --save_steps 500 --eval_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:2\"], \"pid\": \"58978\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_seed123.log\", \"submitted_at\": \"2026-05-14T02:46:24.381Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"checkpoint_path\": \"output/models/adaptive_seed123/final\", \"wall_clock_seconds\": 15162.4, \"gpu_hours\": 4.21}, \"metrics\": {\"train_loss\": 9.2665, \"train_runtime_s\": 13197.18, \"total_steps\": 6103, \"train_samples_per_second\": 7.399, \"train_steps_per_second\": 0.462, \"epoch\": 0.26, \"weighting_method\": \"adaptive\", \"tau\": 0.8, \"n_min\": 3, \"contamination_ratio\": 0.4, \"b_star\": \"per-batch adaptive (0.0-3.8)\", \"alpha_eff_range\": \"0.04-0.80 (capped at tau)\", \"eval_ppl_holdout\": 17.6308, \"eval_loss_holdout\": 2.8696, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.63/4080000 from inline eval\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T06:59:06.757Z\", \"notes\": \"⚠️ success 仅指训练完成无报错。MVP 假设验证待 held-out eval perplexity 结果。\"}, \"adaptive_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T02:25:01.824Z\", \"updated_at\": \"2026-05-15T16:43:05.333Z\", \"hypothesis\": \"Adaptive b* (from α_eff theory) matches or exceeds grid-searched best-b without grid search, seed=42\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/adaptive_seed42 --weighting_method adaptive --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --eval_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:1\"], \"pid\": \"58888\", \"log_path\": \"~/runs/provenance_weight_training/adaptive_seed42.log\", \"submitted_at\": \"2026-05-14T02:46:23.000Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_path\": \"output/models/adaptive_seed42/final\", \"wall_clock_seconds\": 15162.9, \"gpu_hours\": 4.21}, \"metrics\": {\"train_loss\": 9.2665, \"train_runtime_s\": 13115.09, \"total_steps\": 6103, \"train_samples_per_second\": 7.445, \"train_steps_per_second\": 0.465, \"epoch\": 0.26, \"weighting_method\": \"adaptive\", \"tau\": 0.8, \"n_min\": 3, \"contamination_ratio\": 0.4, \"b_star\": \"per-batch adaptive (0.0-3.8)\", \"alpha_eff_range\": \"0.03-0.80 (capped at tau)\", \"eval_ppl_holdout\": 17.644, \"eval_loss_holdout\": 2.8704, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; confirmed unchanged from prior post-hoc (was 17.644/4077068)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T06:59:05.861Z\", \"notes\": \"⚠️ success 仅指训练完成无报错。MVP 假设验证待 held-out eval perplexity 结果。\"}, \"uniform_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:17:55.165Z\", \"updated_at\": \"2026-05-15T16:42:59.635Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/mixed_data.jsonl --output_dir output/models/uniform_seed456 --weighting_method uniform --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 456 --logging_steps 10 --save_steps 500 --eval_steps 500 --save_total_limit 2 --save_only_model --resume_from_checkpoint output/models/uniform_seed456/checkpoint-500\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:3\"], \"pid\": \"47890\", \"log_path\": \"~/runs/provenance_weight_training/uniform_seed456.log\", \"submitted_at\": \"2026-05-13T23:23:58.435Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/provenance_weight_training/data/mixed_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/uniform_seed456/final/\", \"wall_clock_seconds\": 12349.2, \"gpu_hours\": 3.43}, \"hypothesis\": \"Uniform weighting baseline (no provenance information) for comparison with grid-b and adaptive methods\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 7.2895, \"total_steps\": 6103, \"train_duration_s\": 11974, \"eval_ppl_holdout\": 17.7015, \"eval_loss_holdout\": 2.8737, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.70/4080000 from inline eval\"}, \"completed_at\": \"2026-05-14T02:49:47.621Z\"}, \"uniform_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:17:53.217Z\", \"updated_at\": \"2026-05-15T16:42:57.800Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/mixed_data.jsonl --output_dir output/models/uniform_seed123 --weighting_method uniform --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 123 --logging_steps 10 --save_steps 500 --eval_steps 500 --save_total_limit 2 --save_only_model --resume_from_checkpoint output/models/uniform_seed123/checkpoint-500\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:2\"], \"pid\": \"47749\", \"log_path\": \"~/runs/provenance_weight_training/uniform_seed123.log\", \"submitted_at\": \"2026-05-13T23:23:55.904Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/provenance_weight_training/data/mixed_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 123, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/uniform_seed123/final/\", \"wall_clock_seconds\": 12350.8, \"gpu_hours\": 3.43}, \"hypothesis\": \"Uniform weighting baseline (no provenance information) for comparison with grid-b and adaptive methods\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 7.3121, \"total_steps\": 6103, \"train_duration_s\": 11994, \"eval_ppl_holdout\": 17.6861, \"eval_loss_holdout\": 2.8728, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.69/4080000 from inline eval\"}, \"completed_at\": \"2026-05-14T02:49:46.681Z\"}, \"uniform_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:17:51.722Z\", \"updated_at\": \"2026-05-15T16:42:55.867Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/provenance_weight_training && python training/pretrain_weighted.py --data_path data/mixed_data.jsonl --output_dir output/models/uniform_seed42 --weighting_method uniform --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --eval_steps 500 --save_total_limit 2 --save_only_model --resume_from_checkpoint output/models/uniform_seed42/checkpoint-500\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:1\"], \"pid\": \"47603\", \"log_path\": \"~/runs/provenance_weight_training/uniform_seed42.log\", \"submitted_at\": \"2026-05-13T23:23:53.026Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/provenance_weight_training/data/mixed_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/uniform_seed42/final/\", \"wall_clock_seconds\": 12352.2, \"gpu_hours\": 3.43}, \"hypothesis\": \"Uniform weighting baseline (no provenance information) for comparison with grid-b and adaptive methods\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 7.3104, \"total_steps\": 6103, \"train_duration_s\": 11946, \"eval_ppl_holdout\": 17.6939, \"eval_loss_holdout\": 2.8732, \"eval_holdout_tokens\": 4077068, \"eval_method\": \"eval_perplexity.py (sliding window, stride=1024, max_docs=5000, fp16)\", \"eval_note\": \"unified post-hoc eval 2026-05-15; was 17.69/4080000 from inline eval\"}, \"completed_at\": \"2026-05-14T02:49:45.269Z\"}, \"detector_modernbert\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:40:06.106Z\", \"updated_at\": \"2026-05-15T15:51:50.219Z\", \"conclusion\": \"killed\", \"hypothesis\": \"ModernBERT-base can distinguish Qwen3-0.6B synthetic text from FineWeb human text with AUC>=0.95 and ECE<=0.05\", \"notes\": \"Superseded by TF-IDF detector (detector_tfidf_lr). Never ran — cancelled at QUEUED stage.\", \"completed_at\": \"2026-05-15T15:51:50.219Z\"}, \"nmin1_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:48:31.298Z\", \"updated_at\": \"2026-05-15T14:36:49.692Z\", \"hypothesis\": \"n_min=1 sensitivity: minimal ESS constraint allows more aggressive downweighting, testing if adaptive method degrades with overly permissive ESS bound\", \"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-15T09:34:56.077Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/nmin1_seed42 --weighting_method adaptive --n_min 1 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --tau 0.8 --bf16\\\"\", \"finished_at\": \"2026-05-15T14:27:21.174Z\", \"training_hours\": 4.87}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/nmin1_seed42 --weighting_method adaptive --n_min 1 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --tau 0.8 --bf16\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:2\"], \"pid\": \"194005\", \"log_path\": \"~/runs/provenance_weight_training/nmin1_seed42.log\", \"submitted_at\": \"2026-05-15T09:36:06.479Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 18033.6, \"gpu_hours\": 5.01}, \"pid\": \"194005\", \"log_path\": \"~/runs/provenance_weight_training/nmin1_seed42.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T14:27:22.547409+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.789, \"eval_loss\": 2.8786, \"eval_holdout_tokens\": 4077068, \"b_star_mean\": 7.197, \"b_star_median\": 1.746, \"b_star_std\": 8.374, \"b_star_min\": 0, \"b_star_max\": 20, \"b_star_p25\": 0.803, \"b_star_p75\": 20, \"b_star_zero_frac\": 0.019, \"b_star_pct_below_0.5\": 13.1, \"b_star_pct_0.5_to_1\": 19.1, \"b_star_pct_1_to_2\": 21.1, \"b_star_pct_above_2\": 46.7, \"b_star_count\": 24412, \"alpha_eff_mean\": 0.714, \"alpha_eff_median\": 0.8}, \"notes\": \"训练完成(EXIT_CODE=0, 4h50m)。PPL=17.789，比 adaptive_fix(n_min=2, 17.650) 差 +0.139，比 uniform(17.690) 差 +0.099。n_min=1 导致极端 b* 分布：46.7% batch b*≥2，p75=20.0(上限)，mean=7.197。ESS 约束几乎失效，over-downweighting 明显。confirms n_min=2 是更优选择。\", \"checkpoint_path\": \"/root/provenance_weight_training/output/models/nmin1_seed42\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T14:36:40.056Z\"}, \"golden_ratio_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:20:12.943Z\", \"updated_at\": \"2026-05-15T13:33:31.162Z\", \"hypothesis\": \"Golden Ratio oracle baseline: w=1/φ≈0.618 for synthetic (q>0.5), w=1.0 for real — requires known proportion, serves as oracle upper bound for adaptive method\", \"server\": \"westd-47453\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-15T09:34:55.278Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/golden_ratio_seed42 --weighting_method golden_ratio --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --tau 0.8 --bf16\\\"\", \"finished_at\": \"2026-05-15T13:21:54.212Z\", \"training_hours\": 3.78}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/golden_ratio_seed42 --weighting_method golden_ratio --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 42 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4 --tau 0.8 --bf16\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:0\"], \"pid\": \"193921\", \"log_path\": \"~/runs/provenance_weight_training/golden_ratio_seed42.log\", \"submitted_at\": \"2026-05-15T09:36:04.200Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 14247.0, \"gpu_hours\": 3.96}, \"pid\": \"193921\", \"log_path\": \"/root/provenance_weight_training/output/models/golden_ratio_seed42/step_metrics.jsonl\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:21:55.558374+00:00\"}]}, \"metrics\": {\"eval_ppl_holdout\": 17.654, \"eval_loss\": 2.871, \"train_loss\": 2.1145, \"train_loss_last500\": 2.109, \"eval_holdout_tokens\": 4077068, \"total_steps\": 6103, \"train_runtime_s\": 13442, \"gpu_hours\": 3.73}, \"checkpoint_path\": \"/root/provenance_weight_training/output/models/golden_ratio_seed42/final\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T13:33:31.162Z\"}, \"tau_0.6_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:58:48.894Z\", \"updated_at\": \"2026-05-15T12:39:47.541Z\", \"hypothesis\": \"τ sensitivity sweep: τ=0.6 (lower α_eff threshold) may allow more aggressive downweighting, testing if PPL improves or degrades vs τ=0.8 baseline (adaptive_fix PPL=17.65). Key evidence for Claim 3 (τ as robust empirical hyperparameter).\", \"parent\": \"adaptive_fix_seed42\", \"conclusion\": \"killed\", \"notes\": \"废弃: exp_id 含点号不合法，已用 tau_06_seed42 替代\", \"completed_at\": \"2026-05-15T12:39:47.541Z\"}, \"grid_b_low_seed42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-15T01:18:54.793Z\", \"updated_at\": \"2026-05-15T09:33:21.503Z\", \"hypothesis\": \"Grid-b extension to b<0.5 (b=0.1/0.2/0.3 serial), seed42, confirming whether grid-best lies at b=0.5 or below\", \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"completed_at\": \"2026-05-15T05:23:13.303Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\"}, \"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:02:07.651872+00:00\"}]}, \"spec\": {\"command\": \"bash run_grid_b_low_seed42.sh\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:1\"], \"pid\": \"163662\", \"log_path\": \"~/runs/provenance_weight_training/grid_b_low_seed42.log\", \"submitted_at\": \"2026-05-15T09:20:20Z\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"wall_clock_seconds\": 774.2, \"gpu_hours\": 0.22}, \"notes\": \"cron框架误杀(infrastructure bug)。根因: WANDB_MODE=disabled + tmux wrapper PID 不匹配，reconcile_crons 判定进程死亡并发送 SIGTERM。训练实际曾完成 3 个 b 值(8477/8477×3)，但第二次重启后在 step 431 被杀，所有 checkpoint 目录丢失(grid_b0_1/0_2/0_3_seed42 不存在)。需在 cuda:2/3 释放后完全重跑。\", \"reproduce\": {\"finished_at\": \"2026-05-15T09:02:05.942Z\"}, \"conclusion\": \"failed\"}, \"grid_b1_5_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T06:59:35.658Z\", \"updated_at\": \"2026-05-15T01:03:24.328Z\", \"spec\": {\"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456}, \"hypothesis\": \"Grid-b weighting with b=1.5, seed=456, for multi-seed validation of best-b baseline\", \"server\": \"westd-47453\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-14T21:10:45.479Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b1_5_seed456 --weighting_method grid --grid_b_value 1.5 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 456 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4\\\"\", \"finished_at\": \"2026-05-15T00:50:58.269Z\", \"training_hours\": 3.67}, \"pid\": \"142985\", \"log_path\": \"~/runs/provenance_weight_training/grid_b1_5_seed456.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T00:51:00.583331+00:00\"}]}, \"checkpoint_path\": \"output/models/grid_b1_5_seed456/final\", \"metrics\": {\"train_loss\": 10.435, \"total_steps\": 6103, \"train_runtime_s\": 12950.16, \"gpu_hours\": 3.67, \"train_samples_per_second\": 7.54, \"eval_loss\": 2.8741, \"eval_ppl_holdout\": 17.71, \"eval_holdout_tokens\": 4077068, \"eval_loss_holdout\": 2.875, \"eval_tokens\": 5004058}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:56:27.189Z\"}, \"grid_b1_0_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T06:59:34.733Z\", \"updated_at\": \"2026-05-15T01:03:23.307Z\", \"spec\": {\"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456}, \"hypothesis\": \"Grid-b weighting with b=1.0, seed=456, for multi-seed validation of best-b baseline\", \"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-14T21:10:44.681Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b1_0_seed456 --weighting_method grid --grid_b_value 1.0 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 456 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4\\\"\", \"finished_at\": \"2026-05-15T00:50:55.540Z\", \"training_hours\": 3.67}, \"pid\": \"142902\", \"log_path\": \"~/runs/provenance_weight_training/grid_b1_0_seed456.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T00:50:56.660568+00:00\"}]}, \"checkpoint_path\": \"output/models/grid_b1_0_seed456/final\", \"metrics\": {\"train_loss\": 10.178, \"total_steps\": 6103, \"train_runtime_s\": 12963.87, \"gpu_hours\": 3.67, \"train_samples_per_second\": 7.532, \"eval_loss\": 2.8725, \"eval_ppl_holdout\": 17.68, \"eval_holdout_tokens\": 4077068, \"eval_loss_holdout\": 2.8734, \"eval_tokens\": 5004058}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T00:56:26.614Z\"}, \"grid_b0_5_seed456\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T06:58:17.956Z\", \"updated_at\": \"2026-05-15T01:03:04.640Z\", \"hypothesis\": \"Grid-b weighting with b=0.5, seed=456, for multi-seed validation of best-b baseline\", \"server\": \"westd-47453\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-47453\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-14T21:10:43.728Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b0_5_seed456 --weighting_method grid --grid_b_value 0.5 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 456 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4\\\"\", \"finished_at\": \"2026-05-15T00:57:32.591Z\", \"training_hours\": 3.78}, \"failure_reason\": \"\", \"completed_at\": \"2026-05-14T21:13:26.329Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T21:13:27.262433+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T00:57:33.835977+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"失败原因: CUDA OOM at step 0 — GPU 0 被 3 个进程挤爆（PID 138525: 68.61GiB + PID 139132: 19.21GiB + 本进程 7.08GiB > 94.97GiB）。实验分配 cuda:1 但进程实际跑在 GPU 0 上，疑 CUDA_VISIBLE_DEVICES 未正确注入或有残留进程干扰。已有成果: 无（0% 进度）。建议: 清理 GPU 0 残留进程后在 cuda:1 上重新提交，补充 --eval_data_path 和 --eval_steps 参数。\"}}, \"notes\": \"重提交成功（retry_count=1）。原 OOM 因 cuda:1 残留 eval 进程。已清理 exit marker，日志重定向正常。step 56/6103, ETA ~3.5h。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/provenance_weight_training && WANDB_MODE=disabled python training/pretrain_weighted.py --data_path data/scored_data.jsonl --output_dir output/models/grid_b0_5_seed456 --weighting_method grid --grid_b_value 0.5 --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 200000000 --batch_size 4 --gradient_accumulation_steps 4 --max_length 2048 --learning_rate 5e-5 --seed 456 --logging_steps 10 --save_steps 500 --save_total_limit 2 --save_only_model --contamination_ratio 0.4\\\"\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:1\"], \"pid\": \"144400\", \"log_path\": \"~/runs/provenance_weight_training/grid_b0_5_seed456.log\", \"submitted_at\": \"2026-05-14T21:20:21.115Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 456, \"wall_clock_seconds\": 13363.5, \"gpu_hours\": 3.71}, \"pid\": 145062, \"log_path\": \"~/runs/provenance_weight_training/grid_b0_5_seed456.log\", \"metrics\": {\"train_loss\": 9.5622, \"total_steps\": 6103, \"train_runtime_s\": 12953.96, \"gpu_hours\": 3.6, \"train_samples_per_second\": 7.538, \"eval_loss\": 2.8705, \"eval_ppl_holdout\": 17.65, \"eval_holdout_tokens\": 4077068}, \"checkpoint_path\": \"output/models/grid_b0_5_seed456/final\", \"conclusion\": \"success\"}, \"grid_b_seed42_batch\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T23:50:09.001Z\", \"updated_at\": \"2026-05-14T22:21:47.253Z\", \"spec\": {\"command\": \"bash run_grid_b_seed42.sh (6 b values serial: 0.5, 1.0, 1.5, 2.0, 3.0, 5.0)\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:0\"], \"pid\": \"50134\", \"log_path\": \"~/runs/provenance_weight_training/grid_b_seed42_batch.log\", \"submitted_at\": \"2026-05-13T23:50:08.990Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/provenance_weight_training/data/scored_data.jsonl\", \"data_count\": 371499, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42, \"wall_clock_seconds\": 81098.3, \"gpu_hours\": 22.53}, \"hypothesis\": \"Grid-b weighting with 6 b values (0.5, 1.0, 1.5, 2.0, 3.0, 5.0) for seed=42, establishes best-b baseline for comparison with adaptive b*\", \"metrics\": {\"b_values\": [0.5, 1, 1.5, 2, 3, 5], \"b0_5_train_loss\": 9.598, \"b0_5_completed\": true, \"b1_0_completed\": true, \"b1_5_completed\": true, \"b2_0_current_step\": 5149, \"b2_0_total_steps\": 6103, \"completed_b_values\": [0.5, 1, 1.5, 2, 3], \"current_b\": 5, \"total_steps\": 6103, \"current_step\": 3422, \"b5_0_progress_pct\": 56, \"eta_minutes\": 95, \"b2_0_completed\": true, \"b2_0_train_loss\": 10.621, \"b2_0_train_runtime_s\": 13034, \"b3_0_completed\": true, \"b3_0_train_loss\": 10.754, \"b3_0_train_runtime_s\": 13036, \"all_completed\": true, \"b1_0_train_loss\": 10.223, \"b1_5_train_loss\": 10.485, \"b5_0_train_loss\": 10.858, \"b0_5_runtime_s\": 13036, \"b1_0_runtime_s\": 12968, \"b1_5_runtime_s\": 14789, \"b2_0_runtime_s\": 13034, \"b3_0_runtime_s\": 13036, \"b5_0_runtime_s\": 13115, \"note\": \"eval_ppl missing - no --eval_data_path in batch script, post-hoc eval pending\", \"b0_5_eval_ppl\": 17.651, \"b1_0_eval_ppl\": 17.692, \"b1_5_eval_ppl\": 17.718, \"b2_0_eval_ppl\": 17.741, \"b3_0_eval_ppl\": 17.774, \"b5_0_eval_ppl\": 17.818, \"eval_holdout_tokens\": 4077068, \"best_b\": 0.5, \"best_eval_ppl\": 17.651}, \"reproduce\": {\"finished_at\": \"2026-05-14T22:05:39.706Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T22:05:40.772794+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/models/grid_b{0.5,1.0,1.5,2.0,3.0,5.0}_seed42/final/\", \"log_path\": \"~/runs/provenance_weight_training/grid_b_seed42_batch.log\", \"completed_at\": \"2026-05-14T22:21:47.253Z\"}, \"diagnostic_contamination100\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:14:09.555Z\", \"updated_at\": \"2026-05-14T08:48:08.828Z\", \"hypothesis\": \"Diagnostic: does 100% synthetic contamination significantly degrade held-out PPL vs 40%? If PPL ≈ 17.7, contamination sensitivity is too low for this scale.\", \"spec\": {\"command\": \"python training/pretrain_weighted.py --data_path data/synthetic_only.jsonl --output_dir output/models/diagnostic_contamination100_seed42 --weighting_method uniform --model_name models/Qwen/Qwen3-0.6B --num_train_tokens 20000000 --seed 42\", \"server\": \"westd-47453\", \"gpu\": [\"cuda:3\"], \"pid\": \"77187\", \"data_path\": \"data/synthetic_only.jsonl\", \"data_count\": 0, \"model_name\": \"Qwen/Qwen3-0.6B\", \"seed\": 42}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T08:48:07.663Z\", \"notes\": \"Director 指令 kill：GPU 2/3 显存打满影响 grid-b seed123 训练速度。诊断实验等 grid-b round 1 完成后重跑。\"}, \"detector_tfidf_lr\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T23:28:08.894Z\", \"updated_at\": \"2026-05-13T23:28:28.425Z\", \"spec\": {\"command\": \"python train_tfidf_detector.py (combo_degrade: unigrams, max_features=10000, C=0.01, truncate 100 words)\", \"server\": \"westd-47453\", \"data_path\": \"/root/provenance_weight_training/data/detector.jsonl\", \"data_count\": 67960, \"model_name\": \"TF-IDF + LogisticRegression\", \"seed\": 42, \"checkpoint_path\": \"/root/provenance_weight_training/output/detector_tfidf/\", \"log_path\": \"/root/provenance_weight_training/output/detector_tfidf/calibration_results.json\"}, \"conclusion\": \"success\", \"hypothesis\": \"TF-IDF + LogisticRegression detector provides spread q-scores (AUC~0.94, not binarized) for provenance weighting, replacing over-accurate ModernBERT (D007)\", \"metrics\": {\"auc\": 0.939, \"accuracy\": 0.858, \"ece_raw\": 0.24, \"ece_calibrated\": 0.048, \"temperature_T\": 0.204, \"q_score_mean\": 0.6, \"q_score_std\": 0.374, \"q_score_median\": 0.707, \"mid_range_ratio\": 0.463}, \"completed_at\": \"2026-05-13T23:28:28.425Z\"}}, \"count\": 269, \"total\": 269, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.7285}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 14_

<details open><summary>🔧 Tool call — Glob · `toolu_01WTTT1TnXxbWweNHqEeRRje`</summary>

```json
{
  "pattern": "**/docs/paper/sections/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "cd785130-cb6b-4c45-8d18-9f69bc1a90ce",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012YfCsaLQEnDPgXMUVf16JC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13749,
      "cache_read_input_tokens": 24254,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13749
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

_source line 15 · 2026-05-25T20:02:44.467Z_

<details><summary>↩ Tool result · `toolu_01WTTT1TnXxbWweNHqEeRRje`</summary>

```text
docs/paper/sections/checklist.tex
docs/paper/sections/introduction.tex
docs/paper/sections/experiments.tex
docs/paper/sections/abstract.tex
docs/paper/sections/method.tex
docs/paper/sections/limitations.tex
docs/paper/sections/conclusion.tex
docs/paper/sections/appendix.tex
docs/paper/sections/discussion.tex
docs/paper/sections/results.tex
docs/paper/sections/related_work.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "d6ea2e67-c90e-4db5-bedb-a11ef0a2f355",
  "tool_use_result": {
    "filenames": [
      "docs/paper/sections/checklist.tex",
      "docs/paper/sections/introduction.tex",
      "docs/paper/sections/experiments.tex",
      "docs/paper/sections/abstract.tex",
      "docs/paper/sections/method.tex",
      "docs/paper/sections/limitations.tex",
      "docs/paper/sections/conclusion.tex",
      "docs/paper/sections/appendix.tex",
      "docs/paper/sections/discussion.tex",
      "docs/paper/sections/results.tex",
      "docs/paper/sections/related_work.tex"
    ],
    "durationMs": 31,
    "numFiles": 11,
    "truncated": false
  }
}
```

</details>

---


### Assistant

_source line 16_

<details><summary>Logged reasoning block</summary>

```text
The registry is too large. Let me use agents to do the heavy lifting. I'll:
1. Read results.tex and experiments.tex for cross-referencing
2. Use an agent to query the registry for specific experiment data

Let me read the main text sections first, then use agents to query registry.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "c5b0a0e7-55e8-42eb-a957-6dad448066b6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QSSq7mbtWG6BumyNLQhcdm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 960,
      "cache_read_input_tokens": 38003,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 960
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

_source line 17_

Registry 太大，用子代理查询。先读正文关键章节进行交叉验证。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "74dcbb60-5ced-4cb5-8646-8dab6dd6c32a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QSSq7mbtWG6BumyNLQhcdm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 960,
      "cache_read_input_tokens": 38003,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 960
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

_source line 18_

<details open><summary>🔧 Tool call — Read · `toolu_01DKtrSZP61S7z5HMgGHrism`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "6bbf5a2e-2b79-4410-aecc-8b9b187833d2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QSSq7mbtWG6BumyNLQhcdm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 960,
      "cache_read_input_tokens": 38003,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 960
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

_source line 19 · 2026-05-25T20:02:49.016Z_

<details><summary>↩ Tool result · `toolu_01DKtrSZP61S7z5HMgGHrism`</summary>

```text
1	\begin{table}[t]
2	\centering
3	\small
4	\setlength{\tabcolsep}{3pt}
5	\resizebox{\columnwidth}{!}{%
6	\begin{tabular}{@{}lcccc@{}}
7	\toprule
8	\textbf{Method} & \textbf{Seed 42} & \textbf{Seed 123} & \textbf{Seed 456} & \textbf{Mean} \\
9	\midrule
10	Uniform                & 17.694 & 17.686 & 17.702 & 17.697 $\pm$ .008 \\
11	Adaptive $\bstar$ (ours) & \textbf{17.680} & \textbf{17.666} & \textbf{17.677} & \textbf{17.674} $\pm$ .006 \\
12	ESS-only               & 17.730 & 17.720 & 17.760 & 17.737 $\pm$ .021 \\
13	Random $\mathcal{U}(0,2)$ & 17.830 & 17.800 & 17.777 & 17.802 $\pm$ .027 \\
14	Permuted $q$-scores  & 17.919 & --     & --     & 17.919 \\
15	\bottomrule
16	\end{tabular}}
17	\caption{Main comparison: held-out PPL ($\downarrow$) at $\rho{=}0.4$, 1 content epoch.
18	Adaptive and Uniform: 5-seed means (seeds 42, 123, 456, 789, 234); ESS-only and Random: 3-seed means (seeds 42, 123, 456); Permuted: single seed (42).
19	Adaptive uses $\tau{=}0.7$, $\nmin{=}2$.
20	Permuted randomly shuffles $q$-scores across samples, destroying provenance signal while preserving weight non-uniformity ($\Delta{=}{+}0.225$).}
21	\label{tab:main}
22	\end{table}
23	
24	\subsection{Main Results}
25	\label{sec:main-results}
26	
27	Table~\ref{tab:main} reports held-out perplexity at $\rho = 0.4$ across five seeds.
28	Continued pretraining reduces PPL from 22.970 to the 17.3--17.8 range; method comparisons operate within a narrow residual.
29	
30	Adaptive $\bstar$ achieves 5-seed mean PPL 17.674, compared to 17.697 for uniform ($\Delta{=}{-}0.023$, directionally consistent across all seeds) and 17.620 for grid $b{=}0.3$ (3-seed mean, post-hoc oracle; gap $+$0.054; Table~\ref{tab:aux}).
31	A paired $t$-test yields $t(4){=}{-}8.21$, $p{=}0.0012$; after Bonferroni--Holm correction for nine family-wise comparisons, $p_{\mathrm{BH}}{=}0.011$, reaching conventional significance at $\alpha{=}0.05$.
32	The engineering benefit is eliminating $b$ grid search (nine full training runs~\citep{drayson2025detection}, ${\sim}$16 GPU-hours at 0.6B scale, scaling linearly with model size), though grid search yields a larger improvement.
33	The grid-best $b{=}0.3$ is a post-hoc oracle from nine candidates with $5.5{\times}$ higher cross-seed standard deviation than adaptive ($\sigma{=}0.033$ vs.\ $0.006$); the noisy PPL plateau at $b \in [0.1, 0.5]$ (Figure~\ref{fig:grid_b_trend}) makes validation-based selection unreliable.
34	At the nearest fixed point ($b{=}1.0$), PPL equals uniform (17.692 vs.\ 17.694): per-batch adaptation is essential.
35	
36	The ablation hierarchy at $\rho{=}0.4$ (Adaptive ${<}$ Uniform ${<}$ ESS-only ${<}$ Random ${<}$ Permuted, Table~\ref{tab:main}) reveals two requirements for effective reweighting: detector signal and minimum intervention.
37	Random weights $\mathcal{U}(0,2)$ (17.802) confirm that non-uniform weighting alone does not help; permuted $q$-scores (17.919, $\Delta{=}{+}0.225$) further isolate provenance signal as load-bearing, since shuffling destroys the detector's sample-level information while preserving identical weight non-uniformity.
38	ESS-only (mean $17.737 {\pm} 0.021$) uses the same $q$-scores but maximizes $b$ up to the stability ceiling, concentrating weights on a few high-confidence samples; it degrades PPL by 0.043 relative to uniform.
39	Only the dual-constrained adaptive method, which limits $b$ to the minimum needed, improves in-distribution PPL over uniform (mean $\Delta{=}{-}0.023$, directionally consistent across all seeds).
40	Figure~\ref{fig:grid_b_trend} contextualizes both results: adaptive $\bstar$ operates near the curve minimum while ESS-only $\bstar$ (mean ${\approx}$3.5) falls in the degradation zone.
41	
42	\begin{figure}[t]
43	\centering
44	\includegraphics[width=\columnwidth]{grid_b_trend_clean}
45	\caption{Held-out PPL as a function of fixed sharpening exponent $b$ (grid search, $\rho{=}0.4$).
46	Seed\,42 provides the full nine-point sweep (circles); cross-seed markers at $b{=}0.5$ (triangles) confirm the plateau region.
47	The shaded region marks $b \geq 2$ where PPL degrades past the uniform baseline; ESS-only $\bstar$ (overall mean ${\approx}$3.5) falls in this degradation zone, while adaptive $\bstar$ (mean ${\approx}$0.9) operates near the curve minimum.}
48	\label{fig:grid_b_trend}
49	\end{figure}
50	
51	\paragraph{Hard filtering and multi-epoch exposure.}
52	Detect \& Remove at its best threshold ($q{>}0.3$) achieves 3-seed mean PPL $17.250 \pm 0.001$ at full training length, outperforming all reweighting methods by a wide margin ($\Delta{=}{-}0.424$ vs.\ adaptive $\bstar$).
53	All three D\&R thresholds beat both uniform and adaptive $\bstar$ ($q{>}0.5$: $17.280 \pm 0.010$; $q{>}0.7$: $17.320 \pm 0.001$; 3 seeds each), with cross-seed variance near zero (holdout $\pm$0.00, Table~\ref{tab:epoch_match}).
54	Aggressive filtering retains only 31.5\% of tokens at $q{>}0.3$, so the model sees surviving data ${\sim}$3.2 \emph{content epochs} versus one for reweighting; an epoch-matched control (D\&R at $q{>}0.5$, ${\sim}$1.0 content epochs) yields PPL $17.657 \pm 0.005$ vs.\ $17.674 \pm 0.007$ for adaptive $\bstar$ ($\Delta{=}0.017$), attributing ${>}$95\% of D\&R's full-length advantage to multi-epoch exposure on filtered data (Table~\ref{tab:epoch_match}).
55	This decomposition identifies the \emph{mechanism}: filtering concentrates compute on high-confidence real data, and multi-epoch exposure amplifies the benefit, rather than undermining D\&R's practical effectiveness.
56	The raw threshold--PPL curve is U-shaped ($q{>}0.3$: 17.25, $q{>}0.9$: 17.42), but epoch-matched comparisons eliminate the U-shape, revealing monotonically decreasing PPL that saturates at $q{\geq}0.5$ (Figure~\ref{fig:dr_dual_curve}; Appendix~\ref{app:hybrid}).
57	For practitioners, D\&R is the strongest strategy when the corpus is small relative to training compute, as aggressive filtering naturally creates multi-epoch regimes that amplify quality gains; controlled comparisons should report the effective content-epoch count alongside PPL.
58	
59	\begin{figure}[t]
60	\centering
61	\includegraphics[width=\columnwidth]{dr_dual_curve}
62	\caption{D\&R threshold--PPL relationship ($\rho{=}0.4$, 3 seeds).
63	Blue: raw (multi-epoch) PPL with effective epoch counts annotated.
64	Orange: epoch-matched PPL (single content epoch), saturating at the adaptive $\bstar$ level (green dashed).}
65	\label{fig:dr_dual_curve}
66	\end{figure}
67	
68	\begin{figure}[t]
69	\centering
70	\includegraphics[width=\columnwidth]{delta_vs_rho}
71	\caption{Effect of contamination ratio on adaptive reweighting effectiveness.
72	$\Delta$ = adaptive $-$ uniform holdout PPL (lower is better).
73	Error bars show $\pm$1 SD across seeds.
74	The method transitions from harmful to beneficial between $\rho{=}0.3$ and $0.4$ (shaded).}
75	\label{fig:delta_vs_rho}
76	\end{figure}
77	
78	\subsection{Robustness and Boundary Conditions}
79	\label{sec:robustness}
80	
81	Across three seeds at $\rho = 0.6$, adaptive $\bstar$ ($17.731 \pm 0.004$) directionally outperforms uniform on in-distribution PPL ($17.763 \pm 0.008$, $\Delta{=}{-}0.032$, 3 seeds, paired $t{=}{-}9.95$, $p_{\mathrm{BH}}{=}0.064$), with a larger effect size than at $\rho{=}0.4$ ($\Delta{=}{-}0.023$).
82	The ablation hierarchy is preserved (Grid 17.634\footnote{Single seed; full per-seed results in Appendix~\ref{app:rho06}.} ${<}$ Adaptive 17.731 ${<}$ Uniform 17.763 ${\approx}$ ESS-only 17.763 ${<}$ Random 17.861), but the ESS-only/uniform gap collapses to effectively zero (three-seed means both $17.763$) as ESS binding rises to ${\sim}$49\%.
83	Random remains substantially worse than uniform (gap 0.098, $\sigma{=}0.025$): detector signal is load-bearing even when the stability constraint dominates; the adaptive method's continued advantage is driven by the $\aeff$ quality constraint, which operates independently of the ESS ceiling.
84	Three-seed paired comparison confirms $\tau{=}0.7$ outperforms $\tau{=}0.8$ on both holdout and out-of-distribution (OOD) metrics (\S\ref{sec:sensitivity}).
85	
86	\begin{table}[t]
87	\centering
88	\small
89	\setlength{\tabcolsep}{3pt}
90	\resizebox{\columnwidth}{!}{%
91	\begin{tabular}{@{}lccc@{}}
92	\toprule
93	\textbf{Method} & \textbf{Epochs} & \textbf{PPL (raw)} $\downarrow$ & \textbf{PPL (ep.-matched)} $\downarrow$ \\
94	\midrule
95	D\&R ($q{>}0.3$) & ${\sim}$3.2 & \textbf{17.250} $\pm$ .001 & 17.74 \\
96	D\&R ($q{>}0.5$) & ${\sim}$2.4 & 17.280 $\pm$ .010 & 17.657 $\pm$ .005 \\
97	D\&R ($q{>}0.7$) & ${\sim}$2.0 & 17.32 & 17.62 \\
98	\midrule
99	Adaptive $\bstar$ & ${\sim}$1.0 & \multicolumn{2}{c}{17.674 $\pm$ .007} \\
100	Uniform           & ${\sim}$1.0 & \multicolumn{2}{c}{17.697 $\pm$ .008} \\
101	\bottomrule
102	\end{tabular}}
103	\caption{D\&R threshold comparison ($\rho{=}0.4$).
104	Raw PPL traces a U-shape across thresholds; epoch-matched PPL (single content epoch) decreases monotonically and saturates near the adaptive $\bstar$ level.
105	D\&R's 0.424 PPL advantage (at $q{>}0.3$) shrinks to $\Delta{=}0.017$ when content epochs are equalized.
106	All raw PPL values are 3-seed means; epoch-matched values at $q{>}0.3$ and $q{>}0.7$ are single-seed.
107	Full 9-threshold sweep in Table~\ref{tab:dr_threshold}.}
108	\label{tab:epoch_match}
109	\end{table}
110	
111	\paragraph{Scale.}
112	At 1.7B parameters (Qwen3-1.7B, $\rho{=}0.4$, $\tau{=}0.8$, 3 seeds), the method scales without degradation but the benefit diminishes.
113	Adaptive $\bstar$ achieves holdout PPL $13.26$ vs.\ uniform $13.27$ ($\Delta{=}{-}0.013$); OOD results are mixed in direction across domains (OWT $\Delta{=}{-}0.008$, Wiki $\Delta{=}{+}0.013$) and downstream accuracy is unchanged ($\Delta{\approx}{+}0.002$).
114	The diminished effect is consistent with larger models being more robust to self-generated contamination: Qwen3-1.7B's own outputs are likely closer to its training distribution, reducing the distributional shift that reweighting corrects.
115	A preliminary Llama-3.2-3B cross-model result (Appendix~\ref{app:cross_model}) shows mixed downstream effects (MMLU $+$1.6 percentage points, HellaSwag $-$0.6 percentage points), leaving cross-architecture generalization as an open question.
116	\paragraph{Out-of-distribution evaluation.}
117	To test whether the in-distribution improvement reflects distribution matching, we evaluate all three from-scratch seeds on OpenWebText and Wikipedia.
118	At $\rho{=}0.4$, adaptive reweighting improves mean PPL on all three evaluation domains: FineWeb $\Delta{=}{-}0.023$ (5 seeds), OpenWebText $\Delta{=}{-}0.028$, Wikipedia $\Delta{=}{-}0.029$ (3 seeds each); downstream accuracy is identical (0.5414).
119	OOD improvements exceed the in-distribution gain, indicating genuine quality improvement rather than distribution matching toward the training mixture ($\tau{=}0.8$'s OOD effect is smaller; $\tau{=}0.7$'s advantage reflects active OOD improvement, \S\ref{sec:sensitivity}).
120	
121	\paragraph{Calibration, not just discrimination.}
122	Replacing TF-IDF+LR with generative perplexity detectors reverses the advantage across three seeds (GPT-2: AUC\,=\,0.91, ECE\,=\,0.131, $\Delta{=}{+}0.098$; N-gram: AUC\,=\,0.73, ECE\,=\,0.069, $\Delta{=}{+}0.129$; Figure~\ref{fig:overview}b; Appendix~\ref{app:detector}).
123	The TF-IDF vs.\ GPT-2 contrast (comparable AUC, $2.7{\times}$ ECE gap) isolates calibration as an empirically observed requirement in our self-contamination setting; N-gram's better ECE (0.069) does not compensate for insufficient AUC (0.73), indicating that both discrimination and calibration are jointly necessary (Figure~\ref{fig:overview}b).
124	
125	\begin{table}[t]
126	\centering
127	\small
128	\setlength{\tabcolsep}{3pt}
129	\resizebox{\columnwidth}{!}{%
130	\begin{tabular}{@{}lcccl@{}}
131	\toprule
132	\textbf{Method} & \textbf{Seeds} & \textbf{Oracle?} & \textbf{Epochs} & \textbf{Mean PPL} $\downarrow$ \\
133	\midrule
134	Grid ($b{=}0.3$) & 3 & post-hoc & 1 & \textbf{17.620} $\pm$ .033 \\
135	Golden Ratio     & 1 & known $\rho$ & 1 & 17.654 \\
136	D\&R ($q{>}0.3$) & 3 & post-hoc & ${\sim}$3.2 & \textbf{17.250} $\pm$ .001 \\
137	\bottomrule
138	\end{tabular}}
139	\caption{Auxiliary baselines at $\rho{=}0.4$. Grid-best selected post-hoc from nine candidates (Appendix~\ref{app:grid}). Golden Ratio requires known $\rho$~\citep{he2025golden}. D\&R uses ${\sim}$3.2 content epochs (Table~\ref{tab:epoch_match}).}
140	\label{tab:aux}
141	\end{table}
142	
143	\subsection{Hyperparameter Sensitivity}
144	\label{sec:sensitivity}
145	
146	\paragraph{Quality threshold $\tau$.}
147	$\tau{=}0.7$ outperforms $\tau{=}0.8$ on holdout at both contamination levels ($\rho{=}0.4$: 17.674 vs.\ 17.683; $\rho{=}0.6$: paired $t{=}{-}4.70$, $p{<}0.05$; \S\ref{sec:robustness}) and achieves larger OOD gains ($\rho{=}0.4$: $\Delta{=}{-}0.028$/$-$0.029 vs.\ $-$0.005/$-$0.009; Table~\ref{tab:tau}, Appendix~\ref{app:tau_rho}).
148	$\tau \in [0.5, 0.8]$ all improve holdout over uniform, while $\tau {>} 0.8$ degrades (Appendix~\ref{app:tau_sweep}).
149	We also tested per-batch adaptive $\tau$ clamping, which did not improve over fixed thresholds (Appendix~\ref{app:batch_adaptive}).
150	
151	\paragraph{ESS floor $\nmin$.}
152	The default $\nmin{=}2$ ($\nmin/B{=}0.5$) is optimal; extremes degrade ($\nmin{=}1$: PPL $17.742{\pm}0.009$, 3 seeds, worse than uniform; $\nmin{=}B$: recovers uniform).
153	Neither constraint alone improves over uniform ($\nmin{=}1$: $+$0.048; ESS-only: $+$0.043); both must act jointly for the method to outperform uniform training.
154	The coupling $\nmin{=}\lfloor B/2 \rfloor$ is also empirically motivated: at $B{=}8$, keeping $\nmin{=}2$ (ratio $0.25$) degrades PPL by $+$0.036 vs.\ uniform, whereas $\nmin{=}4$ (ratio $0.5$) yields $\Delta{=}{-}0.052{\pm}0.007$.
155	Under this coupling, the adaptive advantage monotonically increases across $B \in \{4, 8, 16\}$: $\Delta{=}{-}0.023{\pm}0.006$ (5 seeds), $-$0.052${\pm}$0.007 (3 seeds, $p{=}0.006$), and $-$0.068${\pm}$0.005 (3 seeds), corresponding to $1.0{\times}$, $2.3{\times}$, and $3.0{\times}$ amplification ($p{<}0.01$ at $B \geq 8$).
156	The gap to grid-best narrows from 0.040 ($B{=}4$) to 0.009 ($B{=}16$, seed\,42; Figure~\ref{fig:batch_amp}).
157	
158	\begin{figure}[t]
159	\centering
160	\includegraphics[width=\columnwidth]{batch_size_amplification}
161	\caption{Batch-size amplification of adaptive reweighting ($\nmin{=}\lfloor B/2 \rfloor$).
162	The adaptive advantage over uniform increases monotonically with micro-batch size, from $1.0{\times}$ ($B{=}4$) to $3.0{\times}$ ($B{=}16$); $\Delta$ values and $\pm$1\,SD shown above each bar.}
163	\label{fig:batch_amp}
164	\end{figure}
165	
166	\paragraph{Constraint regime.}
167	\label{sec:regime}
168	Over 24{,}412 micro-batches (seed\,42), 5.8\% are clean ($\aeff(0) \geq \tau$, $\bstar{=}0$), ${\sim}$50\% are $\aeff$-binding (quality constraint dominates), and ${\sim}$44\% are ESS-binding (stability constraint dominates); the distribution is stable across seeds (coefficient of variation ${<}2\%$; Figure~\ref{fig:regime_decomp}).
169	The $\aeff$-binding majority indicates that detector quality signal, not training stability, is the primary bottleneck, reinforcing the calibration requirement (\S\ref{sec:robustness}).
170	
171	\begin{figure}[t]
172	\centering
173	\includegraphics[width=\columnwidth]{constraint_regime_decomposition}
174	\caption{Constraint regime decomposition at two contamination levels (seed\,42).
175	At $\rho{=}0.4$, ${\sim}$50\% of batches are $\aeff$-binding and ${\sim}$44\% ESS-binding, with ${\sim}$6\% clean; at $\rho{=}0.6$, the constraints are nearly balanced (${\sim}$49\% ESS-binding, ${\sim}$47\% $\aeff$-binding).}
176	\label{fig:regime_decomp}
177	\end{figure}
178	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "dede26bd-a77c-48ad-bd50-cc6d721daf2c",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/results.tex",
      "content": "\\begin{table}[t]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n\\textbf{Method} & \\textbf{Seed 42} & \\textbf{Seed 123} & \\textbf{Seed 456} & \\textbf{Mean} \\\\\n\\midrule\nUniform                & 17.694 & 17.686 & 17.702 & 17.697 $\\pm$ .008 \\\\\nAdaptive $\\bstar$ (ours) & \\textbf{17.680} & \\textbf{17.666} & \\textbf{17.677} & \\textbf{17.674} $\\pm$ .006 \\\\\nESS-only               & 17.730 & 17.720 & 17.760 & 17.737 $\\pm$ .021 \\\\\nRandom $\\mathcal{U}(0,2)$ & 17.830 & 17.800 & 17.777 & 17.802 $\\pm$ .027 \\\\\nPermuted $q$-scores  & 17.919 & --     & --     & 17.919 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Main comparison: held-out PPL ($\\downarrow$) at $\\rho{=}0.4$, 1 content epoch.\nAdaptive and Uniform: 5-seed means (seeds 42, 123, 456, 789, 234); ESS-only and Random: 3-seed means (seeds 42, 123, 456); Permuted: single seed (42).\nAdaptive uses $\\tau{=}0.7$, $\\nmin{=}2$.\nPermuted randomly shuffles $q$-scores across samples, destroying provenance signal while preserving weight non-uniformity ($\\Delta{=}{+}0.225$).}\n\\label{tab:main}\n\\end{table}\n\n\\subsection{Main Results}\n\\label{sec:main-results}\n\nTable~\\ref{tab:main} reports held-out perplexity at $\\rho = 0.4$ across five seeds.\nContinued pretraining reduces PPL from 22.970 to the 17.3--17.8 range; method comparisons operate within a narrow residual.\n\nAdaptive $\\bstar$ achieves 5-seed mean PPL 17.674, compared to 17.697 for uniform ($\\Delta{=}{-}0.023$, directionally consistent across all seeds) and 17.620 for grid $b{=}0.3$ (3-seed mean, post-hoc oracle; gap $+$0.054; Table~\\ref{tab:aux}).\nA paired $t$-test yields $t(4){=}{-}8.21$, $p{=}0.0012$; after Bonferroni--Holm correction for nine family-wise comparisons, $p_{\\mathrm{BH}}{=}0.011$, reaching conventional significance at $\\alpha{=}0.05$.\nThe engineering benefit is eliminating $b$ grid search (nine full training runs~\\citep{drayson2025detection}, ${\\sim}$16 GPU-hours at 0.6B scale, scaling linearly with model size), though grid search yields a larger improvement.\nThe grid-best $b{=}0.3$ is a post-hoc oracle from nine candidates with $5.5{\\times}$ higher cross-seed standard deviation than adaptive ($\\sigma{=}0.033$ vs.\\ $0.006$); the noisy PPL plateau at $b \\in [0.1, 0.5]$ (Figure~\\ref{fig:grid_b_trend}) makes validation-based selection unreliable.\nAt the nearest fixed point ($b{=}1.0$), PPL equals uniform (17.692 vs.\\ 17.694): per-batch adaptation is essential.\n\nThe ablation hierarchy at $\\rho{=}0.4$ (Adaptive ${<}$ Uniform ${<}$ ESS-only ${<}$ Random ${<}$ Permuted, Table~\\ref{tab:main}) reveals two requirements for effective reweighting: detector signal and minimum intervention.\nRandom weights $\\mathcal{U}(0,2)$ (17.802) confirm that non-uniform weighting alone does not help; permuted $q$-scores (17.919, $\\Delta{=}{+}0.225$) further isolate provenance signal as load-bearing, since shuffling destroys the detector's sample-level information while preserving identical weight non-uniformity.\nESS-only (mean $17.737 {\\pm} 0.021$) uses the same $q$-scores but maximizes $b$ up to the stability ceiling, concentrating weights on a few high-confidence samples; it degrades PPL by 0.043 relative to uniform.\nOnly the dual-constrained adaptive method, which limits $b$ to the minimum needed, improves in-distribution PPL over uniform (mean $\\Delta{=}{-}0.023$, directionally consistent across all seeds).\nFigure~\\ref{fig:grid_b_trend} contextualizes both results: adaptive $\\bstar$ operates near the curve minimum while ESS-only $\\bstar$ (mean ${\\approx}$3.5) falls in the degradation zone.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{grid_b_trend_clean}\n\\caption{Held-out PPL as a function of fixed sharpening exponent $b$ (grid search, $\\rho{=}0.4$).\nSeed\\,42 provides the full nine-point sweep (circles); cross-seed markers at $b{=}0.5$ (triangles) confirm the plateau region.\nThe shaded region marks $b \\geq 2$ where PPL degrades past the uniform baseline; ESS-only $\\bstar$ (overall mean ${\\approx}$3.5) falls in this degradation zone, while adaptive $\\bstar$ (mean ${\\approx}$0.9) operates near the curve minimum.}\n\\label{fig:grid_b_trend}\n\\end{figure}\n\n\\paragraph{Hard filtering and multi-epoch exposure.}\nDetect \\& Remove at its best threshold ($q{>}0.3$) achieves 3-seed mean PPL $17.250 \\pm 0.001$ at full training length, outperforming all reweighting methods by a wide margin ($\\Delta{=}{-}0.424$ vs.\\ adaptive $\\bstar$).\nAll three D\\&R thresholds beat both uniform and adaptive $\\bstar$ ($q{>}0.5$: $17.280 \\pm 0.010$; $q{>}0.7$: $17.320 \\pm 0.001$; 3 seeds each), with cross-seed variance near zero (holdout $\\pm$0.00, Table~\\ref{tab:epoch_match}).\nAggressive filtering retains only 31.5\\% of tokens at $q{>}0.3$, so the model sees surviving data ${\\sim}$3.2 \\emph{content epochs} versus one for reweighting; an epoch-matched control (D\\&R at $q{>}0.5$, ${\\sim}$1.0 content epochs) yields PPL $17.657 \\pm 0.005$ vs.\\ $17.674 \\pm 0.007$ for adaptive $\\bstar$ ($\\Delta{=}0.017$), attributing ${>}$95\\% of D\\&R's full-length advantage to multi-epoch exposure on filtered data (Table~\\ref{tab:epoch_match}).\nThis decomposition identifies the \\emph{mechanism}: filtering concentrates compute on high-confidence real data, and multi-epoch exposure amplifies the benefit, rather than undermining D\\&R's practical effectiveness.\nThe raw threshold--PPL curve is U-shaped ($q{>}0.3$: 17.25, $q{>}0.9$: 17.42), but epoch-matched comparisons eliminate the U-shape, revealing monotonically decreasing PPL that saturates at $q{\\geq}0.5$ (Figure~\\ref{fig:dr_dual_curve}; Appendix~\\ref{app:hybrid}).\nFor practitioners, D\\&R is the strongest strategy when the corpus is small relative to training compute, as aggressive filtering naturally creates multi-epoch regimes that amplify quality gains; controlled comparisons should report the effective content-epoch count alongside PPL.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{dr_dual_curve}\n\\caption{D\\&R threshold--PPL relationship ($\\rho{=}0.4$, 3 seeds).\nBlue: raw (multi-epoch) PPL with effective epoch counts annotated.\nOrange: epoch-matched PPL (single content epoch), saturating at the adaptive $\\bstar$ level (green dashed).}\n\\label{fig:dr_dual_curve}\n\\end{figure}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{delta_vs_rho}\n\\caption{Effect of contamination ratio on adaptive reweighting effectiveness.\n$\\Delta$ = adaptive $-$ uniform holdout PPL (lower is better).\nError bars show $\\pm$1 SD across seeds.\nThe method transitions from harmful to beneficial between $\\rho{=}0.3$ and $0.4$ (shaded).}\n\\label{fig:delta_vs_rho}\n\\end{figure}\n\n\\subsection{Robustness and Boundary Conditions}\n\\label{sec:robustness}\n\nAcross three seeds at $\\rho = 0.6$, adaptive $\\bstar$ ($17.731 \\pm 0.004$) directionally outperforms uniform on in-distribution PPL ($17.763 \\pm 0.008$, $\\Delta{=}{-}0.032$, 3 seeds, paired $t{=}{-}9.95$, $p_{\\mathrm{BH}}{=}0.064$), with a larger effect size than at $\\rho{=}0.4$ ($\\Delta{=}{-}0.023$).\nThe ablation hierarchy is preserved (Grid 17.634\\footnote{Single seed; full per-seed results in Appendix~\\ref{app:rho06}.} ${<}$ Adaptive 17.731 ${<}$ Uniform 17.763 ${\\approx}$ ESS-only 17.763 ${<}$ Random 17.861), but the ESS-only/uniform gap collapses to effectively zero (three-seed means both $17.763$) as ESS binding rises to ${\\sim}$49\\%.\nRandom remains substantially worse than uniform (gap 0.098, $\\sigma{=}0.025$): detector signal is load-bearing even when the stability constraint dominates; the adaptive method's continued advantage is driven by the $\\aeff$ quality constraint, which operates independently of the ESS ceiling.\nThree-seed paired comparison confirms $\\tau{=}0.7$ outperforms $\\tau{=}0.8$ on both holdout and out-of-distribution (OOD) metrics (\\S\\ref{sec:sensitivity}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n\\textbf{Method} & \\textbf{Epochs} & \\textbf{PPL (raw)} $\\downarrow$ & \\textbf{PPL (ep.-matched)} $\\downarrow$ \\\\\n\\midrule\nD\\&R ($q{>}0.3$) & ${\\sim}$3.2 & \\textbf{17.250} $\\pm$ .001 & 17.74 \\\\\nD\\&R ($q{>}0.5$) & ${\\sim}$2.4 & 17.280 $\\pm$ .010 & 17.657 $\\pm$ .005 \\\\\nD\\&R ($q{>}0.7$) & ${\\sim}$2.0 & 17.32 & 17.62 \\\\\n\\midrule\nAdaptive $\\bstar$ & ${\\sim}$1.0 & \\multicolumn{2}{c}{17.674 $\\pm$ .007} \\\\\nUniform           & ${\\sim}$1.0 & \\multicolumn{2}{c}{17.697 $\\pm$ .008} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{D\\&R threshold comparison ($\\rho{=}0.4$).\nRaw PPL traces a U-shape across thresholds; epoch-matched PPL (single content epoch) decreases monotonically and saturates near the adaptive $\\bstar$ level.\nD\\&R's 0.424 PPL advantage (at $q{>}0.3$) shrinks to $\\Delta{=}0.017$ when content epochs are equalized.\nAll raw PPL values are 3-seed means; epoch-matched values at $q{>}0.3$ and $q{>}0.7$ are single-seed.\nFull 9-threshold sweep in Table~\\ref{tab:dr_threshold}.}\n\\label{tab:epoch_match}\n\\end{table}\n\n\\paragraph{Scale.}\nAt 1.7B parameters (Qwen3-1.7B, $\\rho{=}0.4$, $\\tau{=}0.8$, 3 seeds), the method scales without degradation but the benefit diminishes.\nAdaptive $\\bstar$ achieves holdout PPL $13.26$ vs.\\ uniform $13.27$ ($\\Delta{=}{-}0.013$); OOD results are mixed in direction across domains (OWT $\\Delta{=}{-}0.008$, Wiki $\\Delta{=}{+}0.013$) and downstream accuracy is unchanged ($\\Delta{\\approx}{+}0.002$).\nThe diminished effect is consistent with larger models being more robust to self-generated contamination: Qwen3-1.7B's own outputs are likely closer to its training distribution, reducing the distributional shift that reweighting corrects.\nA preliminary Llama-3.2-3B cross-model result (Appendix~\\ref{app:cross_model}) shows mixed downstream effects (MMLU $+$1.6 percentage points, HellaSwag $-$0.6 percentage points), leaving cross-architecture generalization as an open question.\n\\paragraph{Out-of-distribution evaluation.}\nTo test whether the in-distribution improvement reflects distribution matching, we evaluate all three from-scratch seeds on OpenWebText and Wikipedia.\nAt $\\rho{=}0.4$, adaptive reweighting improves mean PPL on all three evaluation domains: FineWeb $\\Delta{=}{-}0.023$ (5 seeds), OpenWebText $\\Delta{=}{-}0.028$, Wikipedia $\\Delta{=}{-}0.029$ (3 seeds each); downstream accuracy is identical (0.5414).\nOOD improvements exceed the in-distribution gain, indicating genuine quality improvement rather than distribution matching toward the training mixture ($\\tau{=}0.8$'s OOD effect is smaller; $\\tau{=}0.7$'s advantage reflects active OOD improvement, \\S\\ref{sec:sensitivity}).\n\n\\paragraph{Calibration, not just discrimination.}\nReplacing TF-IDF+LR with generative perplexity detectors reverses the advantage across three seeds (GPT-2: AUC\\,=\\,0.91, ECE\\,=\\,0.131, $\\Delta{=}{+}0.098$; N-gram: AUC\\,=\\,0.73, ECE\\,=\\,0.069, $\\Delta{=}{+}0.129$; Figure~\\ref{fig:overview}b; Appendix~\\ref{app:detector}).\nThe TF-IDF vs.\\ GPT-2 contrast (comparable AUC, $2.7{\\times}$ ECE gap) isolates calibration as an empirically observed requirement in our self-contamination setting; N-gram's better ECE (0.069) does not compensate for insufficient AUC (0.73), indicating that both discrimination and calibration are jointly necessary (Figure~\\ref{fig:overview}b).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccl@{}}\n\\toprule\n\\textbf{Method} & \\textbf{Seeds} & \\textbf{Oracle?} & \\textbf{Epochs} & \\textbf{Mean PPL} $\\downarrow$ \\\\\n\\midrule\nGrid ($b{=}0.3$) & 3 & post-hoc & 1 & \\textbf{17.620} $\\pm$ .033 \\\\\nGolden Ratio     & 1 & known $\\rho$ & 1 & 17.654 \\\\\nD\\&R ($q{>}0.3$) & 3 & post-hoc & ${\\sim}$3.2 & \\textbf{17.250} $\\pm$ .001 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Auxiliary baselines at $\\rho{=}0.4$. Grid-best selected post-hoc from nine candidates (Appendix~\\ref{app:grid}). Golden Ratio requires known $\\rho$~\\citep{he2025golden}. D\\&R uses ${\\sim}$3.2 content epochs (Table~\\ref{tab:epoch_match}).}\n\\label{tab:aux}\n\\end{table}\n\n\\subsection{Hyperparameter Sensitivity}\n\\label{sec:sensitivity}\n\n\\paragraph{Quality threshold $\\tau$.}\n$\\tau{=}0.7$ outperforms $\\tau{=}0.8$ on holdout at both contamination levels ($\\rho{=}0.4$: 17.674 vs.\\ 17.683; $\\rho{=}0.6$: paired $t{=}{-}4.70$, $p{<}0.05$; \\S\\ref{sec:robustness}) and achieves larger OOD gains ($\\rho{=}0.4$: $\\Delta{=}{-}0.028$/$-$0.029 vs.\\ $-$0.005/$-$0.009; Table~\\ref{tab:tau}, Appendix~\\ref{app:tau_rho}).\n$\\tau \\in [0.5, 0.8]$ all improve holdout over uniform, while $\\tau {>} 0.8$ degrades (Appendix~\\ref{app:tau_sweep}).\nWe also tested per-batch adaptive $\\tau$ clamping, which did not improve over fixed thresholds (Appendix~\\ref{app:batch_adaptive}).\n\n\\paragraph{ESS floor $\\nmin$.}\nThe default $\\nmin{=}2$ ($\\nmin/B{=}0.5$) is optimal; extremes degrade ($\\nmin{=}1$: PPL $17.742{\\pm}0.009$, 3 seeds, worse than uniform; $\\nmin{=}B$: recovers uniform).\nNeither constraint alone improves over uniform ($\\nmin{=}1$: $+$0.048; ESS-only: $+$0.043); both must act jointly for the method to outperform uniform training.\nThe coupling $\\nmin{=}\\lfloor B/2 \\rfloor$ is also empirically motivated: at $B{=}8$, keeping $\\nmin{=}2$ (ratio $0.25$) degrades PPL by $+$0.036 vs.\\ uniform, whereas $\\nmin{=}4$ (ratio $0.5$) yields $\\Delta{=}{-}0.052{\\pm}0.007$.\nUnder this coupling, the adaptive advantage monotonically increases across $B \\in \\{4, 8, 16\\}$: $\\Delta{=}{-}0.023{\\pm}0.006$ (5 seeds), $-$0.052${\\pm}$0.007 (3 seeds, $p{=}0.006$), and $-$0.068${\\pm}$0.005 (3 seeds), corresponding to $1.0{\\times}$, $2.3{\\times}$, and $3.0{\\times}$ amplification ($p{<}0.01$ at $B \\geq 8$).\nThe gap to grid-best narrows from 0.040 ($B{=}4$) to 0.009 ($B{=}16$, seed\\,42; Figure~\\ref{fig:batch_amp}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{batch_size_amplification}\n\\caption{Batch-size amplification of adaptive reweighting ($\\nmin{=}\\lfloor B/2 \\rfloor$).\nThe adaptive advantage over uniform increases monotonically with micro-batch size, from $1.0{\\times}$ ($B{=}4$) to $3.0{\\times}$ ($B{=}16$); $\\Delta$ values and $\\pm$1\\,SD shown above each bar.}\n\\label{fig:batch_amp}\n\\end{figure}\n\n\\paragraph{Constraint regime.}\n\\label{sec:regime}\nOver 24{,}412 micro-batches (seed\\,42), 5.8\\% are clean ($\\aeff(0) \\geq \\tau$, $\\bstar{=}0$), ${\\sim}$50\\% are $\\aeff$-binding (quality constraint dominates), and ${\\sim}$44\\% are ESS-binding (stability constraint dominates); the distribution is stable across seeds (coefficient of variation ${<}2\\%$; Figure~\\ref{fig:regime_decomp}).\nThe $\\aeff$-binding majority indicates that detector quality signal, not training stability, is the primary bottleneck, reinforcing the calibration requirement (\\S\\ref{sec:robustness}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{constraint_regime_decomposition}\n\\caption{Constraint regime decomposition at two contamination levels (seed\\,42).\nAt $\\rho{=}0.4$, ${\\sim}$50\\% of batches are $\\aeff$-binding and ${\\sim}$44\\% ESS-binding, with ${\\sim}$6\\% clean; at $\\rho{=}0.6$, the constraints are nearly balanced (${\\sim}$49\\% ESS-binding, ${\\sim}$47\\% $\\aeff$-binding).}\n\\label{fig:regime_decomp}\n\\end{figure}\n",
      "numLines": 178,
      "startLine": 1,
      "totalLines": 178
    }
  }
}
```

</details>

---


### Tool call

_source line 20_

<details open><summary>🔧 Tool call — Read · `toolu_01TGj9RwPXBdpC7PTtXV5C4K`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "36f3f3ec-5f50-41db-b8d7-9dd74199bd8b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QSSq7mbtWG6BumyNLQhcdm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 960,
      "cache_read_input_tokens": 38003,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 960
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

_source line 21 · 2026-05-25T20:02:49.493Z_

<details><summary>↩ Tool result · `toolu_01TGj9RwPXBdpC7PTtXV5C4K`</summary>

```text
1	\paragraph{Training Data.}
2	We sample a 132M-token subset of FineWeb~\citep{penedo2024fineweb} as the real-data source, comparable to typical domain-adaptive continued pretraining budgets~\citep{gururangan2020dont}.
3	To simulate web-scale synthetic contamination, we generate continuations with Qwen3-0.6B~\citep{yang2025qwen3}, the same architecture used for continued pretraining, and inject them at token-level ratio $\rho = 0.4$ via uniform random mixing.\footnote{$\rho$ denotes the token-level contamination ratio. Because synthetic documents are shorter on average (304 vs.\ 560 words), the document-level synthetic fraction is 55.6\% at $\rho{=}0.4$.}
4	This self-contamination design means generator and trainee share the same distribution, providing a controlled testbed with known ground-truth labels but limiting ecological validity; cross-model transfer results (Appendix~\ref{app:cross_model}) are mixed, and we discuss implications for detection difficulty in \S\ref{sec:limitations}.
5	
6	\paragraph{Detector.}
7	We train a TF-IDF + Logistic Regression classifier on a held-out labeled split (AUC\,=\,0.94, calibrated ECE\,=\,0.048 after temperature scaling with $T{=}0.204$).
8	The resulting $q$-scores have mean 0.60, standard deviation 0.37, and median 0.71, with 46.3\% of samples in the uncertain range $[0.2, 0.8]$.
9	We use this lightweight detector rather than neural alternatives (e.g., ModernBERT at AUC\,${\geq}$\,0.98 in \citealt{drayson2025detection}) to test whether score \emph{calibration} may matter as much as raw discrimination for reweighting.
10	To evaluate detector sensitivity, we additionally test two generative baselines: a GPT-2-based perplexity scorer (AUC\,=\,0.91) and an N-gram language model perplexity scorer (AUC\,=\,0.73); results are reported in \S\ref{sec:robustness} (implementation details in Appendix~\ref{app:detector_details}).
11	
12	\paragraph{Training.}
13	Table~\ref{tab:config} summarizes the training configuration.
14	We use $B{=}4$ as the default micro-batch size, reflecting memory constraints typical of continued pretraining setups; \S\ref{sec:sensitivity} demonstrates that larger batches amplify the adaptive advantage.
15	All main comparisons use three random seeds (42, 123, 456) trained from scratch (Appendix~\ref{app:resume_artifact}); the primary comparison is extended to five seeds (adding 789, 234).
16	
17	\begin{table}[t]
18	\centering
19	\small
20	\begin{tabular}{@{}ll@{\hspace{8pt}}ll@{}}
21	\toprule
22	Model & Qwen3-0.6B & Optimizer & AdamW \\
23	Steps & 6{,}103 & Peak LR & $5{\times}10^{-5}$ \\
24	Micro-batch & $B{=}4$ & Schedule & linear + warmup \\
25	Grad.\ accum. & 4 ($B_{\mathrm{eff}}{=}16$) & Seq.\ len. & 2048 \\
26	Precision & bf16 & GPU & 1$\times$ RTX PRO 6000 \\
27	\bottomrule
28	\end{tabular}
29	\caption{Training configuration for continued pretraining.}
30	\label{tab:config}
31	\end{table}
32	
33	\paragraph{Evaluation.}
34	We report held-out perplexity (PPL) on 5{,}000 documents from a FineWeb holdout set ($\sim$4M tokens) containing only human-authored text, via sliding-window evaluation (stride 1024).
35	All evaluations are post-hoc with a unified pipeline; training involves no inline evaluation.
36	
37	\paragraph{Methods.}
38	We compare six approaches:
39	\begin{itemize}[nosep,leftmargin=*]
40	  \item \textbf{Uniform}: $w_j = 1$ for all $j$ (no contamination handling).
41	  \item \textbf{Grid-$b$}: fixed $b \in \{0.1, 0.2, 0.3, 0.5, 1.0, 1.5, 2.0, 3.0, 5.0\}$ (nine candidates), best selected post-hoc by held-out PPL.
42	        Represents validation-based selection~\citep{drayson2025detection}.
43	  \item \textbf{ESS-only}: $\bstar = \max\{b : \mathrm{ESS}(b) \geq \nmin\}$, the maximum-intervention variant retaining only the stability constraint, ablating $\aeff$.
44	  \item \textbf{Golden Ratio}: $w = 1/\varphi \approx 0.618$ for synthetic ($q_j > 0.5$), $w = 1$ otherwise~\citep{he2025golden}.
45	        Requires known provenance labels (oracle).
46	  \item \textbf{Adaptive} (ours): per-batch $\bstar$ from the dual-constraint formulation (\S\ref{sec:method}), with $\tau = 0.7$ (default; $\tau{=}0.8$ comparable, \S\ref{sec:sensitivity}) and $\nmin = 2$ (half the micro-batch size).
47	  \item \textbf{Detect \& Remove}: hard filtering that discards samples with $q_j > 0.5$ and trains uniformly on the remainder.
48	        Requires a calibrated detection threshold; threshold sensitivity is analyzed in \S\ref{sec:main-results}.
49	\end{itemize}
50	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "98bd2775-9f8c-48ea-b429-f88eada6c232",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/experiments.tex",
      "content": "\\paragraph{Training Data.}\nWe sample a 132M-token subset of FineWeb~\\citep{penedo2024fineweb} as the real-data source, comparable to typical domain-adaptive continued pretraining budgets~\\citep{gururangan2020dont}.\nTo simulate web-scale synthetic contamination, we generate continuations with Qwen3-0.6B~\\citep{yang2025qwen3}, the same architecture used for continued pretraining, and inject them at token-level ratio $\\rho = 0.4$ via uniform random mixing.\\footnote{$\\rho$ denotes the token-level contamination ratio. Because synthetic documents are shorter on average (304 vs.\\ 560 words), the document-level synthetic fraction is 55.6\\% at $\\rho{=}0.4$.}\nThis self-contamination design means generator and trainee share the same distribution, providing a controlled testbed with known ground-truth labels but limiting ecological validity; cross-model transfer results (Appendix~\\ref{app:cross_model}) are mixed, and we discuss implications for detection difficulty in \\S\\ref{sec:limitations}.\n\n\\paragraph{Detector.}\nWe train a TF-IDF + Logistic Regression classifier on a held-out labeled split (AUC\\,=\\,0.94, calibrated ECE\\,=\\,0.048 after temperature scaling with $T{=}0.204$).\nThe resulting $q$-scores have mean 0.60, standard deviation 0.37, and median 0.71, with 46.3\\% of samples in the uncertain range $[0.2, 0.8]$.\nWe use this lightweight detector rather than neural alternatives (e.g., ModernBERT at AUC\\,${\\geq}$\\,0.98 in \\citealt{drayson2025detection}) to test whether score \\emph{calibration} may matter as much as raw discrimination for reweighting.\nTo evaluate detector sensitivity, we additionally test two generative baselines: a GPT-2-based perplexity scorer (AUC\\,=\\,0.91) and an N-gram language model perplexity scorer (AUC\\,=\\,0.73); results are reported in \\S\\ref{sec:robustness} (implementation details in Appendix~\\ref{app:detector_details}).\n\n\\paragraph{Training.}\nTable~\\ref{tab:config} summarizes the training configuration.\nWe use $B{=}4$ as the default micro-batch size, reflecting memory constraints typical of continued pretraining setups; \\S\\ref{sec:sensitivity} demonstrates that larger batches amplify the adaptive advantage.\nAll main comparisons use three random seeds (42, 123, 456) trained from scratch (Appendix~\\ref{app:resume_artifact}); the primary comparison is extended to five seeds (adding 789, 234).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{@{}ll@{\\hspace{8pt}}ll@{}}\n\\toprule\nModel & Qwen3-0.6B & Optimizer & AdamW \\\\\nSteps & 6{,}103 & Peak LR & $5{\\times}10^{-5}$ \\\\\nMicro-batch & $B{=}4$ & Schedule & linear + warmup \\\\\nGrad.\\ accum. & 4 ($B_{\\mathrm{eff}}{=}16$) & Seq.\\ len. & 2048 \\\\\nPrecision & bf16 & GPU & 1$\\times$ RTX PRO 6000 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Training configuration for continued pretraining.}\n\\label{tab:config}\n\\end{table}\n\n\\paragraph{Evaluation.}\nWe report held-out perplexity (PPL) on 5{,}000 documents from a FineWeb holdout set ($\\sim$4M tokens) containing only human-authored text, via sliding-window evaluation (stride 1024).\nAll evaluations are post-hoc with a unified pipeline; training involves no inline evaluation.\n\n\\paragraph{Methods.}\nWe compare six approaches:\n\\begin{itemize}[nosep,leftmargin=*]\n  \\item \\textbf{Uniform}: $w_j = 1$ for all $j$ (no contamination handling).\n  \\item \\textbf{Grid-$b$}: fixed $b \\in \\{0.1, 0.2, 0.3, 0.5, 1.0, 1.5, 2.0, 3.0, 5.0\\}$ (nine candidates), best selected post-hoc by held-out PPL.\n        Represents validation-based selection~\\citep{drayson2025detection}.\n  \\item \\textbf{ESS-only}: $\\bstar = \\max\\{b : \\mathrm{ESS}(b) \\geq \\nmin\\}$, the maximum-intervention variant retaining only the stability constraint, ablating $\\aeff$.\n  \\item \\textbf{Golden Ratio}: $w = 1/\\varphi \\approx 0.618$ for synthetic ($q_j > 0.5$), $w = 1$ otherwise~\\citep{he2025golden}.\n        Requires known provenance labels (oracle).\n  \\item \\textbf{Adaptive} (ours): per-batch $\\bstar$ from the dual-constraint formulation (\\S\\ref{sec:method}), with $\\tau = 0.7$ (default; $\\tau{=}0.8$ comparable, \\S\\ref{sec:sensitivity}) and $\\nmin = 2$ (half the micro-batch size).\n  \\item \\textbf{Detect \\& Remove}: hard filtering that discards samples with $q_j > 0.5$ and trains uniformly on the remainder.\n        Requires a calibrated detection threshold; threshold sensitivity is analyzed in \\S\\ref{sec:main-results}.\n\\end{itemize}\n",
      "numLines": 50,
      "startLine": 1,
      "totalLines": 50
    }
  }
}
```

</details>

---


### Tool call

_source line 22_

<details open><summary>🔧 Tool call — Read · `toolu_017W7NRQdMxm6jCM5mTdJpHn`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "5969cab3-6116-4180-bacb-d3d7193e2e0c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QSSq7mbtWG6BumyNLQhcdm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 960,
      "cache_read_input_tokens": 38003,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 960
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

_source line 23 · 2026-05-25T20:02:50.018Z_

<details><summary>↩ Tool result · `toolu_017W7NRQdMxm6jCM5mTdJpHn`</summary>

```text
1	\paragraph{D\&R as the strongest strategy.}
2	D\&R outperforms all reweighting methods by $0.35$--$0.42$ PPL (Table~\ref{tab:epoch_match}), but epoch-matched controls attribute ${>}$95\% of this advantage to multi-epoch exposure on filtered data rather than superior per-token learning.
3	This benefit was invisible in \citet{drayson2025detection}, where from-scratch pretraining rarely completes one epoch; in continued pretraining, it becomes the dominant factor.
4	
5	\paragraph{When uniform beats reweighting.}
6	Table~\ref{tab:decision} summarizes three prerequisites for effective soft reweighting: (i)~sufficient detector discrimination \emph{and} calibration (AUC\,$\geq$\,0.9, ECE\,$\leq$\,0.05; \S\ref{sec:robustness}); (ii)~contamination $\rho \geq 0.4$, below which the method degrades ($+$0.046 at $\rho{=}0.2$; Appendix~\ref{app:rho02}) with a sharp transition in $[0.3, 0.4]$ (Figure~\ref{fig:delta_vs_rho}, Appendix~\ref{app:rho03}); (iii)~generator--trainee mismatch (at 1.7B the benefit diminishes to $\Delta{=}{-}0.013$ with OOD mixed).
7	When any condition is violated, uniform is the safer default.
8	
9	\begin{table}[t]
10	\centering
11	\small
12	\setlength{\tabcolsep}{3pt}
13	\resizebox{\columnwidth}{!}{%
14	\begin{tabular}{@{}lcll@{}}
15	\toprule
16	\textbf{Condition} & \textbf{Observed?} & \textbf{Evidence} & \textbf{$\Delta$ PPL} \\
17	\midrule
18	Detector AUC $\geq 0.9$ & Yes & N-gram (0.73) degrades & $+$0.129 \\
19	Detector ECE $\leq 0.05$ & Yes & GPT-2 (0.131) degrades & $+$0.098 \\
20	Contamination $\rho \geq 0.4$ & Yes & $\rho{=}0.2$ degrades & $+$0.046 \\
21	Generator $\neq$ trainee & Tentative & 1.7B: $\Delta{=}{-}0.013$, OOD mixed & -- \\
22	\bottomrule
23	\end{tabular}}
24	\caption{Decision summary for practitioners.
25	$\Delta$ values are relative to uniform (positive = worse).
26	When any observed condition is violated, uniform is the safer default.}
27	\label{tab:decision}
28	\end{table}
29	
30	\paragraph{Effect size and downstream impact.}
31	The in-distribution improvement ($\Delta{=}{-}0.023$ at $\rho{=}0.4$) does not transfer to downstream accuracy (0.5414 vs.\ 0.5414, 3 seeds; Appendix~\ref{app:downstream}), consistent with nonlinear PPL-to-accuracy transfer~\citep{tay2023scale,ye2025mixing}; the paradigm's impact at current scales is modest (Appendix~\ref{app:power}; Table~\ref{tab:appendix_summary}).
32	
33	\paragraph{Limitations of $\aeff$ as a proxy.}
34	The $\aeff$ diagnostic correlates with the true batch-level real fraction at Pearson $r \approx 0.79$ (${\sim}$63\% of variance; Appendix~\ref{app:alpha_validation}), stable across seeds (Spearman $\rho_s \geq 0.86$; Table~\ref{tab:alpha_corr_perseed}).
35	The ceiling is set by detector calibration, not batch size.
36	Because \citet{wang2026survive}'s convergence guarantee requires the \emph{true} real fraction, the ${\sim}$37\% unexplained variance means some batches satisfying $\aeff \geq \tau$ may have true fractions below $\tau$; the $\nmin$ constraint mitigates this by capping $b$ at the ESS floor~\citep{owen2013mc}.
37	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "59115334-eb68-439b-8a21-0cf4fc30c862",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/discussion.tex",
      "content": "\\paragraph{D\\&R as the strongest strategy.}\nD\\&R outperforms all reweighting methods by $0.35$--$0.42$ PPL (Table~\\ref{tab:epoch_match}), but epoch-matched controls attribute ${>}$95\\% of this advantage to multi-epoch exposure on filtered data rather than superior per-token learning.\nThis benefit was invisible in \\citet{drayson2025detection}, where from-scratch pretraining rarely completes one epoch; in continued pretraining, it becomes the dominant factor.\n\n\\paragraph{When uniform beats reweighting.}\nTable~\\ref{tab:decision} summarizes three prerequisites for effective soft reweighting: (i)~sufficient detector discrimination \\emph{and} calibration (AUC\\,$\\geq$\\,0.9, ECE\\,$\\leq$\\,0.05; \\S\\ref{sec:robustness}); (ii)~contamination $\\rho \\geq 0.4$, below which the method degrades ($+$0.046 at $\\rho{=}0.2$; Appendix~\\ref{app:rho02}) with a sharp transition in $[0.3, 0.4]$ (Figure~\\ref{fig:delta_vs_rho}, Appendix~\\ref{app:rho03}); (iii)~generator--trainee mismatch (at 1.7B the benefit diminishes to $\\Delta{=}{-}0.013$ with OOD mixed).\nWhen any condition is violated, uniform is the safer default.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcll@{}}\n\\toprule\n\\textbf{Condition} & \\textbf{Observed?} & \\textbf{Evidence} & \\textbf{$\\Delta$ PPL} \\\\\n\\midrule\nDetector AUC $\\geq 0.9$ & Yes & N-gram (0.73) degrades & $+$0.129 \\\\\nDetector ECE $\\leq 0.05$ & Yes & GPT-2 (0.131) degrades & $+$0.098 \\\\\nContamination $\\rho \\geq 0.4$ & Yes & $\\rho{=}0.2$ degrades & $+$0.046 \\\\\nGenerator $\\neq$ trainee & Tentative & 1.7B: $\\Delta{=}{-}0.013$, OOD mixed & -- \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Decision summary for practitioners.\n$\\Delta$ values are relative to uniform (positive = worse).\nWhen any observed condition is violated, uniform is the safer default.}\n\\label{tab:decision}\n\\end{table}\n\n\\paragraph{Effect size and downstream impact.}\nThe in-distribution improvement ($\\Delta{=}{-}0.023$ at $\\rho{=}0.4$) does not transfer to downstream accuracy (0.5414 vs.\\ 0.5414, 3 seeds; Appendix~\\ref{app:downstream}), consistent with nonlinear PPL-to-accuracy transfer~\\citep{tay2023scale,ye2025mixing}; the paradigm's impact at current scales is modest (Appendix~\\ref{app:power}; Table~\\ref{tab:appendix_summary}).\n\n\\paragraph{Limitations of $\\aeff$ as a proxy.}\nThe $\\aeff$ diagnostic correlates with the true batch-level real fraction at Pearson $r \\approx 0.79$ (${\\sim}$63\\% of variance; Appendix~\\ref{app:alpha_validation}), stable across seeds (Spearman $\\rho_s \\geq 0.86$; Table~\\ref{tab:alpha_corr_perseed}).\nThe ceiling is set by detector calibration, not batch size.\nBecause \\citet{wang2026survive}'s convergence guarantee requires the \\emph{true} real fraction, the ${\\sim}$37\\% unexplained variance means some batches satisfying $\\aeff \\geq \\tau$ may have true fractions below $\\tau$; the $\\nmin$ constraint mitigates this by capping $b$ at the ESS floor~\\citep{owen2013mc}.\n",
      "numLines": 37,
      "startLine": 1,
      "totalLines": 37
    }
  }
}
```

</details>

---


### Tool call

_source line 24_

<details open><summary>🔧 Tool call — Agent · `toolu_01NuYPDyvrMJLcBKrQo3rorZ`</summary>

```json
{
  "description": "Registry audit queries",
  "prompt": "I need you to query a large JSON registry file at:\n/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9/tool-results/mcp-agent-ml-research-read_registry-1779739364067.txt\n\nThis file has schema: {result: string} where the result is a JSON string. Probe the structure with jq (type/length/keys), then parse the inner JSON.\n\nI need you to extract ALL experiment results that match these categories (report exact numbers, IDs, seeds, and metrics):\n\n1. **Grid search experiments** at ρ=0.4: all b values and their PPLs (holdout)\n2. **τ sweep experiments**: τ=0.50, 0.60, 0.70, 0.80, 0.90, 0.95 — holdout PPL, OWT PPL, Wiki PPL\n3. **ρ=0.6 experiments**: Adaptive, Uniform, ESS-only, Random, Grid — per-seed and mean PPLs\n4. **ρ=0.2 experiment**: adaptive vs uniform delta\n5. **ρ=0.3 experiments**: per-seed holdout, OWT, Wiki PPLs\n6. **Detector comparison**: TF-IDF+LR, GPT-2 PPL, N-gram PPL — AUC, ECE, mean PPL\n7. **α_eff correlation data**: Pearson r, Spearman r, MAE, Bias at B=4,8,16\n8. **Downstream benchmarks**: ARC-C, ARC-E, HellaSwag, PIQA, WinoGrande scores\n9. **Cross-model Llama experiments**: MMLU, HellaSwag scores\n10. **D&R threshold experiments**: all thresholds (q>0.1 through q>0.9), retention %, epochs, raw PPL, epoch-matched PPL\n11. **Hybrid experiments**: PPL at ρ=0.4 and ρ=0.6\n12. **Main results at ρ=0.4**: 5-seed adaptive holdout mean, SD, uniform mean, all per-seed values\n13. **Training hyperparameters**: lr, batch_size, grad_accum, max_length, warmup, weight_decay\n14. **Data stats**: total samples, tokens, real/synthetic split\n15. **Detector training details**: TF-IDF features count, LR C value, AUC, ECE, temperature T\n16. **Statistical tests**: p-values (uncorrected and BH-corrected), Cohen's d, t-statistics\n17. **b*=0 trajectory stats**: % clean batches per seed, Spearman correlation with real fraction\n18. **Per-seed α_eff correlation**: Pearson r(α_eff, q̄), Spearman ρ_s, b*=0 % for seeds 42, 123, 456\n\nReport ALL numbers you find, organized by category. Include experiment IDs. If a number is not found in the registry, say \"NOT FOUND\". This is for a paper audit so completeness and exactness matter.",
  "run_in_background": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "687c42f9-2ddf-45c6-9021-d7fe2157834c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QSSq7mbtWG6BumyNLQhcdm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 960,
      "cache_read_input_tokens": 38003,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 960
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


### System

_source line 25_

```json
{
  "type": "system",
  "subtype": "task_started",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Registry audit queries",
  "task_type": "local_agent",
  "prompt": "I need you to query a large JSON registry file at:\n/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9/tool-results/mcp-agent-ml-research-read_registry-1779739364067.txt\n\nThis file has schema: {result: string} where the result is a JSON string. Probe the structure with jq (type/length/keys), then parse the inner JSON.\n\nI need you to extract ALL experiment results that match these categories (report exact numbers, IDs, seeds, and metrics):\n\n1. **Grid search experiments** at ρ=0.4: all b values and their PPLs (holdout)\n2. **τ sweep experiments**: τ=0.50, 0.60, 0.70, 0.80, 0.90, 0.95 — holdout PPL, OWT PPL, Wiki PPL\n3. **ρ=0.6 experiments**: Adaptive, Uniform, ESS-only, Random, Grid — per-seed and mean PPLs\n4. **ρ=0.2 experiment**: adaptive vs uniform delta\n5. **ρ=0.3 experiments**: per-seed holdout, OWT, Wiki PPLs\n6. **Detector comparison**: TF-IDF+LR, GPT-2 PPL, N-gram PPL — AUC, ECE, mean PPL\n7. **α_eff correlation data**: Pearson r, Spearman r, MAE, Bias at B=4,8,16\n8. **Downstream benchmarks**: ARC-C, ARC-E, HellaSwag, PIQA, WinoGrande scores\n9. **Cross-model Llama experiments**: MMLU, HellaSwag scores\n10. **D&R threshold experiments**: all thresholds (q>0.1 through q>0.9), retention %, epochs, raw PPL, epoch-matched PPL\n11. **Hybrid experiments**: PPL at ρ=0.4 and ρ=0.6\n12. **Main results at ρ=0.4**: 5-seed adaptive holdout mean, SD, uniform mean, all per-seed values\n13. **Training hyperparameters**: lr, batch_size, grad_accum, max_length, warmup, weight_decay\n14. **Data stats**: total samples, tokens, real/synthetic split\n15. **Detector training details**: TF-IDF features count, LR C value, AUC, ECE, temperature T\n16. **Statistical tests**: p-values (uncorrected and BH-corrected), Cohen's d, t-statistics\n17. **b*=0 trajectory stats**: % clean batches per seed, Spearman correlation with real fraction\n18. **Per-seed α_eff correlation**: Pearson r(α_eff, q̄), Spearman ρ_s, b*=0 % for seeds 42, 123, 456\n\nReport ALL numbers you find, organized by category. Include experiment IDs. If a number is not found in the registry, say \"NOT FOUND\". This is for a paper audit so completeness and exactness matter.",
  "uuid": "291b4880-35aa-4c8f-a0bf-d21f850f32a7",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### Tool result

_source line 26 · 2026-05-25T20:03:08.485Z_

<details><summary>↩ Tool result · `toolu_01NuYPDyvrMJLcBKrQo3rorZ`</summary>

```text
Async agent launched successfully.
agentId: acb0ad2099cf0088b (internal ID - do not mention to user. Use SendMessage with to: 'acb0ad2099cf0088b' to continue this agent.)
The agent is working in the background. You will be notified automatically when it completes.
Do not duplicate this agent's work — avoid working with the same files or topics it is using. Work on non-overlapping tasks, or briefly tell the user what you launched and end your response.
output_file: /tmp/claude-1000/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9/tasks/acb0ad2099cf0088b.output
Do NOT Read or tail this file via the shell tool — it is the full sub-agent JSONL transcript and reading it will overflow your context. If the user asks for progress, say the agent is still running; you'll get a completion notification.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "410cabfb-1dd1-408b-8f60-17058563cb37",
  "tool_use_result": {
    "isAsync": true,
    "status": "async_launched",
    "agentId": "acb0ad2099cf0088b",
    "description": "Registry audit queries",
    "prompt": "I need you to query a large JSON registry file at:\n/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9/tool-results/mcp-agent-ml-research-read_registry-1779739364067.txt\n\nThis file has schema: {result: string} where the result is a JSON string. Probe the structure with jq (type/length/keys), then parse the inner JSON.\n\nI need you to extract ALL experiment results that match these categories (report exact numbers, IDs, seeds, and metrics):\n\n1. **Grid search experiments** at ρ=0.4: all b values and their PPLs (holdout)\n2. **τ sweep experiments**: τ=0.50, 0.60, 0.70, 0.80, 0.90, 0.95 — holdout PPL, OWT PPL, Wiki PPL\n3. **ρ=0.6 experiments**: Adaptive, Uniform, ESS-only, Random, Grid — per-seed and mean PPLs\n4. **ρ=0.2 experiment**: adaptive vs uniform delta\n5. **ρ=0.3 experiments**: per-seed holdout, OWT, Wiki PPLs\n6. **Detector comparison**: TF-IDF+LR, GPT-2 PPL, N-gram PPL — AUC, ECE, mean PPL\n7. **α_eff correlation data**: Pearson r, Spearman r, MAE, Bias at B=4,8,16\n8. **Downstream benchmarks**: ARC-C, ARC-E, HellaSwag, PIQA, WinoGrande scores\n9. **Cross-model Llama experiments**: MMLU, HellaSwag scores\n10. **D&R threshold experiments**: all thresholds (q>0.1 through q>0.9), retention %, epochs, raw PPL, epoch-matched PPL\n11. **Hybrid experiments**: PPL at ρ=0.4 and ρ=0.6\n12. **Main results at ρ=0.4**: 5-seed adaptive holdout mean, SD, uniform mean, all per-seed values\n13. **Training hyperparameters**: lr, batch_size, grad_accum, max_length, warmup, weight_decay\n14. **Data stats**: total samples, tokens, real/synthetic split\n15. **Detector training details**: TF-IDF features count, LR C value, AUC, ECE, temperature T\n16. **Statistical tests**: p-values (uncorrected and BH-corrected), Cohen's d, t-statistics\n17. **b*=0 trajectory stats**: % clean batches per seed, Spearman correlation with real fraction\n18. **Per-seed α_eff correlation**: Pearson r(α_eff, q̄), Spearman ρ_s, b*=0 % for seeds 42, 123, 456\n\nReport ALL numbers you find, organized by category. Include experiment IDs. If a number is not found in the registry, say \"NOT FOUND\". This is for a paper audit so completeness and exactness matter.",
    "outputFile": "/tmp/claude-1000/-home-ubuntu--agent-ml-research-idea-gen-0509-10-projects-provenance-weight-training/b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9/tasks/acb0ad2099cf0088b.output",
    "canReadOutputFile": true
  }
}
```

</details>

---


### System

_source line 27_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Check file size",
  "usage": {
    "total_tokens": 14756,
    "tool_uses": 1,
    "duration_ms": 4352
  },
  "last_tool_name": "Bash",
  "uuid": "02885d91-4513-4b0a-a647-c79237c97d68",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 28_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Probe outer JSON structure",
  "usage": {
    "total_tokens": 14760,
    "tool_uses": 2,
    "duration_ms": 6310
  },
  "last_tool_name": "Bash",
  "uuid": "e9ad9f25-057b-46a4-b161-53855c317736",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 29_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Parse inner JSON and probe structure",
  "usage": {
    "total_tokens": 16233,
    "tool_uses": 3,
    "duration_ms": 11817
  },
  "last_tool_name": "Bash",
  "uuid": "fcc91346-a3a5-4963-bfd2-ea6b9d3346fa",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 30_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Explore experiments structure",
  "usage": {
    "total_tokens": 16815,
    "tool_uses": 4,
    "duration_ms": 17454
  },
  "last_tool_name": "Bash",
  "uuid": "3f314231-75a8-46c4-8873-ff9a211d2350",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 31_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running List all experiment IDs and statuses",
  "usage": {
    "total_tokens": 17956,
    "tool_uses": 5,
    "duration_ms": 22301
  },
  "last_tool_name": "Bash",
  "uuid": "0f8a394a-6e01-42c0-bfc1-3f0079c29e82",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 32_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Examine full structure of one experiment",
  "usage": {
    "total_tokens": 22298,
    "tool_uses": 6,
    "duration_ms": 30821
  },
  "last_tool_name": "Bash",
  "uuid": "a2b7871b-c966-4236-b405-8be015cb0a16",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 33_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract grid search experiments",
  "usage": {
    "total_tokens": 22299,
    "tool_uses": 7,
    "duration_ms": 34583
  },
  "last_tool_name": "Bash",
  "uuid": "48282330-d8d8-4fdf-a82d-8b7350ebf9f4",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 34_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract tau sweep experiments",
  "usage": {
    "total_tokens": 22300,
    "tool_uses": 8,
    "duration_ms": 37096
  },
  "last_tool_name": "Bash",
  "uuid": "8da6e66f-d5d5-4c26-b1f1-318f7851cf48",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 35_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Dump experiments to temp file for easier querying",
  "usage": {
    "total_tokens": 25191,
    "tool_uses": 9,
    "duration_ms": 44004
  },
  "last_tool_name": "Bash",
  "uuid": "0296f4bc-acdc-420f-8ac1-4f28e4a416cd",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 36_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract grid search experiments with metrics",
  "usage": {
    "total_tokens": 25755,
    "tool_uses": 10,
    "duration_ms": 52539
  },
  "last_tool_name": "Bash",
  "uuid": "c224a5db-2ffe-4502-a507-c514d3d7dadc",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 37_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract tau sweep experiments",
  "usage": {
    "total_tokens": 25756,
    "tool_uses": 11,
    "duration_ms": 59344
  },
  "last_tool_name": "Bash",
  "uuid": "791de3da-798e-47ee-b30c-2be82af31e32",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 38_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract rho=0.6 experiments",
  "usage": {
    "total_tokens": 25757,
    "tool_uses": 12,
    "duration_ms": 67682
  },
  "last_tool_name": "Bash",
  "uuid": "49dcd05f-fead-4eca-a8db-0a89ea93dd3a",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 39_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract rho=0.2 and rho=0.3 experiments",
  "usage": {
    "total_tokens": 35540,
    "tool_uses": 13,
    "duration_ms": 77940
  },
  "last_tool_name": "Bash",
  "uuid": "0149d111-b844-42c5-8682-d5a7fe4a3f6e",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 40_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract detector comparison experiments",
  "usage": {
    "total_tokens": 35587,
    "tool_uses": 14,
    "duration_ms": 82292
  },
  "last_tool_name": "Bash",
  "uuid": "ebeb2a42-74d1-42ed-b7f2-a47f70054de1",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 41_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract downstream benchmarks",
  "usage": {
    "total_tokens": 35634,
    "tool_uses": 15,
    "duration_ms": 85719
  },
  "last_tool_name": "Bash",
  "uuid": "e285fe6d-ff8a-4d9c-9507-d6f44e20eb5f",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 42_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract Llama and 1.7B experiments",
  "usage": {
    "total_tokens": 40409,
    "tool_uses": 16,
    "duration_ms": 93374
  },
  "last_tool_name": "Bash",
  "uuid": "66c130cf-bbe8-43f7-8485-e624b66a3825",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 43_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract D&R threshold experiments",
  "usage": {
    "total_tokens": 40478,
    "tool_uses": 17,
    "duration_ms": 98139
  },
  "last_tool_name": "Bash",
  "uuid": "97d8f911-2adb-4e64-8923-af58e68a4586",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 44_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract hybrid and main rho=0.4 experiments",
  "usage": {
    "total_tokens": 40547,
    "tool_uses": 18,
    "duration_ms": 107564
  },
  "last_tool_name": "Bash",
  "uuid": "8d86f0e9-6461-4e1b-9066-76a6df604ea1",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 45_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get remaining seed details and OOD experiments",
  "usage": {
    "total_tokens": 51058,
    "tool_uses": 19,
    "duration_ms": 116800
  },
  "last_tool_name": "Bash",
  "uuid": "b8c43546-f9d8-4def-99f4-e65dcaa09d95",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 46_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract ESS-only, random, permuted control experiments",
  "usage": {
    "total_tokens": 51105,
    "tool_uses": 20,
    "duration_ms": 121098
  },
  "last_tool_name": "Bash",
  "uuid": "0fb0c129-6865-4489-9886-dd488e3bdcb5",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 47_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Search for statistical tests and correlation data",
  "usage": {
    "total_tokens": 51152,
    "tool_uses": 21,
    "duration_ms": 127728
  },
  "last_tool_name": "Bash",
  "uuid": "b32f1dff-a4b8-4f9b-85f2-49fa22286ac4",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 48_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Deep dive into alpha_eff and b*=0 experiments",
  "usage": {
    "total_tokens": 56993,
    "tool_uses": 22,
    "duration_ms": 135655
  },
  "last_tool_name": "Bash",
  "uuid": "8fe1d838-ab77-4cfc-9ed8-4e5b59fde5ca",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 49_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get full 1.7B downstream metrics",
  "usage": {
    "total_tokens": 57040,
    "tool_uses": 23,
    "duration_ms": 142227
  },
  "last_tool_name": "Bash",
  "uuid": "869f8bc6-c266-47b3-a476-9097f53300b4",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 50_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get BS16, nmin, W2, eval_q experiments",
  "usage": {
    "total_tokens": 57087,
    "tool_uses": 24,
    "duration_ms": 146124
  },
  "last_tool_name": "Bash",
  "uuid": "867a1376-d391-4d38-85d0-15fb490a6214",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 51_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get Llama full details and search for MMLU",
  "usage": {
    "total_tokens": 67329,
    "tool_uses": 25,
    "duration_ms": 154981
  },
  "last_tool_name": "Bash",
  "uuid": "e296d17d-8bb8-46c8-b253-72fde4ccbdea",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 52_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Search for statistical tests across all experiments",
  "usage": {
    "total_tokens": 67376,
    "tool_uses": 26,
    "duration_ms": 160623
  },
  "last_tool_name": "Bash",
  "uuid": "f264c79c-2898-4b5d-b40d-40f03328771a",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 53_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get training hyperparams, data stats, detector details",
  "usage": {
    "total_tokens": 67423,
    "tool_uses": 27,
    "duration_ms": 167576
  },
  "last_tool_name": "Bash",
  "uuid": "1cdab153-2800-4e53-9631-c7ec0f3949da",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 54_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get statistical test notes and baseline details",
  "usage": {
    "total_tokens": 72261,
    "tool_uses": 28,
    "duration_ms": 176130
  },
  "last_tool_name": "Bash",
  "uuid": "04f9d0f1-9c8f-4c1c-8d6c-da8559e6ffdc",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 55_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get tau07 full details and rho=0.6 adaptive data",
  "usage": {
    "total_tokens": 72330,
    "tool_uses": 29,
    "duration_ms": 183897
  },
  "last_tool_name": "Bash",
  "uuid": "a0fa3e35-6083-493e-a92a-59764144be37",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 56_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get grid_b_low and grid_b0_3 details",
  "usage": {
    "total_tokens": 72399,
    "tool_uses": 30,
    "duration_ms": 188906
  },
  "last_tool_name": "Bash",
  "uuid": "b8b33924-0112-4b4c-a247-e8187bee1c96",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 57_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get grid_b_seed42_batch and baseline full metrics",
  "usage": {
    "total_tokens": 79329,
    "tool_uses": 31,
    "duration_ms": 195197
  },
  "last_tool_name": "Bash",
  "uuid": "36fa388c-e62a-4459-94a9-f736d913421d",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 58_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Extract ALL downstream benchmarks from all experiments",
  "usage": {
    "total_tokens": 79376,
    "tool_uses": 32,
    "duration_ms": 199343
  },
  "last_tool_name": "Bash",
  "uuid": "fad03bd6-0e1f-4e09-9b55-6b02c263e675",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 59_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get remaining rho=0.6 seeds and D&R retention stats",
  "usage": {
    "total_tokens": 84240,
    "tool_uses": 33,
    "duration_ms": 209714
  },
  "last_tool_name": "Bash",
  "uuid": "2817da53-9ddc-4c39-8c27-aa09250b91d2",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 60_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get D&R spec data counts for retention percentages",
  "usage": {
    "total_tokens": 84290,
    "tool_uses": 34,
    "duration_ms": 214139
  },
  "last_tool_name": "Bash",
  "uuid": "d568a527-30c3-44c0-99b3-c1ec024ff2fb",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 61_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Search for alpha_eff correlation data and b*=0 stats",
  "usage": {
    "total_tokens": 89198,
    "tool_uses": 35,
    "duration_ms": 227769
  },
  "last_tool_name": "Bash",
  "uuid": "10fd951e-083a-495f-948e-a0649f5a4cd2",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 62_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get tau sweep b_star details and rho02 full data",
  "usage": {
    "total_tokens": 90764,
    "tool_uses": 36,
    "duration_ms": 234655
  },
  "last_tool_name": "Bash",
  "uuid": "5072b12e-62b8-4aad-91f1-a4656b412595",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 63_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get remaining experiment details",
  "usage": {
    "total_tokens": 90836,
    "tool_uses": 37,
    "duration_ms": 240181
  },
  "last_tool_name": "Bash",
  "uuid": "d6c488bf-7a06-4f74-8b81-288ba1548b30",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 64_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get GPT2 and ngram detector details",
  "usage": {
    "total_tokens": 94049,
    "tool_uses": 38,
    "duration_ms": 250734
  },
  "last_tool_name": "Bash",
  "uuid": "c1433bbb-8409-4b09-838c-29f33da5b795",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 65_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get baseline and all OOD PPLs",
  "usage": {
    "total_tokens": 94050,
    "tool_uses": 39,
    "duration_ms": 255430
  },
  "last_tool_name": "Bash",
  "uuid": "03898fc3-dc5d-4a95-bd5b-a605486729dc",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 66_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "acb0ad2099cf0088b",
  "tool_use_id": "toolu_01NuYPDyvrMJLcBKrQo3rorZ",
  "description": "Running Get remaining missing data",
  "usage": {
    "total_tokens": 99420,
    "tool_uses": 40,
    "duration_ms": 266625
  },
  "last_tool_name": "Bash",
  "uuid": "707ff89d-bf1f-4083-b3a0-64bdfeb75f0d",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### System

_source line 67_

```json
{
  "type": "system",
  "subtype": "task_updated",
  "task_id": "acb0ad2099cf0088b",
  "patch": {
    "status": "completed",
    "end_time": 1779739807158
  },
  "uuid": "8d3e56ab-077f-44cc-9a08-e77d17a77f41",
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9"
}
```

---


### Assistant

_source line 68_

<details><summary>Logged reasoning block</summary>

```text
Let me now systematically go through the appendix.tex and cross-reference every number with the main text sections I've already read. While waiting for the registry agent, I can start the cross-validation between appendix and main text.

Let me organize my audit by section:

### Section: Grid Search (app:grid, lines 78-104)
**Table tab:grid_full** - Grid search at ρ=0.4, seed 42:
- b=0.1: 17.657
- b=0.2: 17.640
- b=0.3: **17.640** (bold, best)


- b=0.5: 17.651
- b=1.0: 17.692
- b=1.5: 17.718
- b=2.0: 17.741
- b=3.0: 17.774
- b=5.0: 17.818

The caption reports a three-seed mean of 17.655 ± 0.009 for b=0.1 and identifies b=0.3 as the post-hoc best. When I check results.tex line 30, it mentions 17.620 for the grid b=0.3 configuration with a three-seed mean and post-hoc oracle designation, but there's a discrepancy I need to investigate further.

Looking at the appendix table, b=0.3 shows 17.640 for seed 42, which is a single-seed result, while results.tex reports the three-seed mean as 17.620—these are measuring different things so they're consistent. The auxiliary table confirms Grid (b=0.3) across three seeds gives 17.620 ± 0.033. I also notice that at b=1.0, the PPL equals the uniform baseline at 17.692 versus 17.694, which is worth noting as a reference point.

Now I'm checking the quality threshold sweep results. The table shows how performance varies across different τ values, with τ=0.70 appearing to be the sweet spot—it achieves the best holdout perplexity of 17.674 ± 0.006 with a -0.020 improvement, and shows consistent gains across the other datasets as well. The τ=0.80 setting is slightly worse, suggesting diminishing returns at higher thresholds. I'm verifying the baseline numbers across different seed configurations. The caption references a 3-seed uniform baseline of 17.694, which I can confirm by averaging the three specific seeds from the results table. Now I'm checking whether the delta values are calculated correctly—the τ=0.7 delta of -0.020 matches the difference between 17.674 and 17.694, so that checks out. I need to reconcile the 5-seed comparison mentioned in the caption with what's actually in the main results table. Now I'm cross-referencing the robustness and sensitivity results across the tables—checking that the τ=0.7 versus τ=0.8 comparisons and their delta values align consistently with what's reported in the text, particularly for the OWT and Wiki datasets at different contamination levels. I'm verifying the remaining tau values match their expected deltas, and they all check out. Now I'm moving into the tau-rho rank preservation section, cross-referencing the figure captions and statistical annotations with the results file to ensure the reported differences and seed counts are consistent. I'm noticing a discrepancy in the adaptive baseline values across different sections—the hybrid table shows 17.689 for seed 42 at τ=0.8, but the appendix τ sweep table reports 17.683±.006 for the same parameters with multiple seeds, and I need to reconcile whether the resume artifact section's checkpoint-resumed run explains this difference. I'm realizing the hybrid table uses τ=0.8 while the ρ=0.6 reference table uses τ=0.7 for Adaptive, so those 17.740 and 17.735 values aren't directly comparable. Now checking the D&R numbers—the hybrid table shows seed 42 only at 17.285, but the results.tex 3-seed mean is 17.280 ± .010, and there's a reference value of 17.291 that doesn't quite match either.

Looking at the D&R threshold table, q>0.5 shows 17.28 (likely seed 42), which is 17.285 rounded to 2 decimal places—so that checks out, though the rounding convention could push it to 17.29 depending on the exact value. I'm noticing the threshold table lists 17.28 for q>0.5 with seed 42, but the hybrid table shows 17.285 for the same condition—this could be a rounding difference, though standard rounding would give 17.29 rather than 17.28. The results.tex file reports 17.280 ± .010 as a 3-seed average, which is different from the single-seed values, so these numbers are likely coming from different experimental runs. seed 42, q>0.5), there's roughly a 0.005 discrepancy that seems odd. Let me cross-check the other D&R variants: q>0.3 shows consistent values across all sources at 17.250, and q>0.7 matches at 17.32 for the holdout set, though the OWT and Wiki variants aren't in these tables. Now I'm looking at the q>0.1 entry in the threshold table to continue verifying. Now I'm checking the full threshold table across all q values, and I notice the raw perplexity stays remarkably stable around 17.2-17.4 regardless of threshold, while epoch-matched values cluster around 17.6-17.7 when available. The q>0.3 entry with 17.250 matches what's reported in the epoch matching results, confirming this is the right reference point. I'm realizing the discrepancy might stem from different seeding approaches—the epoch-matched value of 17.657 in the table is a 3-seed mean, while the threshold table's 17.65 could be from a single seed run, which would explain why they don't match exactly when rounded.

Now I'm moving on to cross-check other sections, starting with the downstream task evaluation metrics. Now I'm cross-referencing these numbers against the discussion and results sections to verify consistency. Let me calculate the mean across all five tasks for both the adaptive and uniform approaches with seed 42, but I'm getting 0.5474 and 0.5522 respectively—neither matches the reported 0.5414 value.

Looking at the caption more carefully, it clarifies that the table shows τ=0.8 results, while the 0.5414 figure refers to τ=0.7 models trained from scratch. Since seed 42 uses checkpoint-resumption at τ=0.8, I can't directly verify the 0.5414 claim from this table, though I can confirm it's consistently cited across the paper.

Now examining the higher contamination results at ρ=0.6, where the grid search with b=0.3 only has seed 42 available, while the adaptive and uniform sampling methods show all three seeds with tighter variance, and the random uniform approach produces notably higher values around 17.86. The full-precision p-value is 0.004, but when rounded to three decimal places it becomes 0.010, which matches what the reference lists as the uncorrected p-value. The results file shows p_BH=0.064, which is the Benjamini-Hochberg corrected version—likely applying a correction factor across the nine family-wise comparisons to transform the uncorrected 0.010 to 0.064.

Now I'm verifying the mean values for each sampling method by averaging their three replicates, and they all check out correctly. Moving on to calculate the standard deviations... I'm finishing the variance calculations for the ESS-only approach and then checking the random sampling results—all the standard deviations are rounding correctly. The difference between the adaptive and uniform means checks out at -0.032, and I'm cross-referencing this against the results file to confirm everything aligns.

Now I'm verifying the gap between ESS-only and uniform performance at different correlation levels, but I'm noticing a discrepancy—the text claims a 0.043 gap at ρ=0.4, but my calculation from the table shows 0.040 instead. I see the discrepancy now—the ESS-only result is being compared against the 3-seed uniform baseline of 17.694, not the full 5-seed uniform mean of 17.697, which gives the 0.043 degradation they report.

Now checking the appendix entries: at ρ=0.4, the 0.043 gap holds with the 3-seed means, and at ρ=0.6 both methods converge to 17.763 with no gap. For the Δ=−0.032 claim, I'm verifying it across individual seeds—the per-seed differences average to exactly −0.032 as stated. Moving on to check the Adaptive-vs-Grid comparison at ρ=0.

4, where the 3-seed mean for Adaptive is 17.674 and Grid is 17.620, giving the reported 0.054 gap. At ρ=0.6, I'm now verifying the 0.097 gap between Adaptive's 3-seed mean of 17.731 and Grid's seed 42 result.

Moving into the α_eff proxy validation section, I'm checking the correlation metrics from the alpha_corr table across different batch sizes—Pearson and Spearman correlations are consistently in the 0.68–0.71 range, with MAE values decreasing as batch size increases from 4 to 16, and biases staying tightly clustered around -0.03.

I'm also verifying the per-seed breakdown, which shows strong Spearman correlations (0.87–0.88) across all three seeds with minimal variance in the b*=0 percentages around 5.8%.

Now I'm cross-referencing the proxy correlation discrepancy—the table reports r(α_eff, q̄) ≈ 0.80, while the discussion mentions r(α_eff, true real fraction) ≈ 0.79, but these measure different things since q̄ is a noisy proxy for the true batch composition, which explains the slight difference.

Checking the clean batch percentage against results.tex confirms 5.8% with the seed 42 setting, and verifying the Spearman correlation claim that ρ_s ≥ 0.86 holds since the minimum value in the table is 0.8692.

The spread calculations all check out: Pearson correlation varies by 0.0025 across seeds, Spearman by 0.0069, and the clean batch percentage by 0.2 percentage points.

Now I'm looking at the detector comparison metrics—TF-IDF with logistic regression achieves the best performance at AUC 0.94 with low calibration error, while GPT-2 perplexity and n-gram perplexity baselines perform progressively worse. The delta values represent deviations from the uniform baseline perplexity of 17.694, and I'm verifying these calculations match the reported numbers. I'm noticing a discrepancy between the detector table showing TF-IDF adaptive at τ=0.8 with PPL 17.650, versus the tau sweep table reporting τ=0.80 with 17.683±.006 from three from-scratch seeds. These don't match, so I need to check whether the detector comparison used different experimental conditions or a different seed set than the tau sweep. I'm noticing a discrepancy between the detector table and τ sweep results for the same conditions—17.650 vs 17.683 for TF-IDF at τ=0.8 with 3 seeds. The difference of 0.033 seems too large to be noise, so either the experimental setups differ (maybe different n_min values or seed selections) or there's an actual inconsistency in how the results were generated. The detector table might have been run earlier when the resume artifact was still present, which would explain why it doesn't match the τ sweep results that explicitly used from-scratch seeds. I should flag this as a potential inconsistency between the two experimental runs. Now I'm checking the detector configuration details against the reference materials—verifying the TF-IDF setup with 50k features, the logistic regression parameters, and the temperature calibration that brought ECE down to around 0.048.

There's a minor discrepancy where the detector section rounds ECE to 0.05 while the main text reports 0.048, but these are close enough that it's likely just a rounding difference. For the synthetic data generation, they're using nucleus sampling with specific temperature and token parameters to create roughly 100M synthetic tokens. Now I'm cross-referencing the contamination results, particularly the ρ=0.2 case where the performance delta matches the reference value.

Looking at the cross-model transfer results, the MMLU benchmark shows the adaptive approach outperforming uniform sampling by about 1.57 percentage points with similar confidence intervals.

For HellaSwag, the adaptive method actually underperforms slightly at 72.49% compared to uniform's 73.08%, a difference of roughly 0.6 percentage points in the opposite direction. Cross-checking against the results section confirms these values match when rounded. There's a minor discrepancy in the HellaSwag calculation—the raw difference is -0.59 but the table reports -0.60, likely due to rounding conventions.

Now looking at the checkpoint resume artifact, I'm seeing results from the first thousand training steps comparing different hyperparameter configurations. The resume approach shows a delta of -0.041 while from-scratch achieves -0.005 at τ=0.8, and across different datasets the resume method varies: FineWeb drops by 0.041, OWT gains 0.058, and Wiki improves by 0.137.

But when I cross-reference this against the τ sweep table, there's a discrepancy—the τ sweep table shows -0.011 for τ=0.80 on the holdout set, not -0.005. The τ sweep uses a 3-seed uniform baseline of 17.694, and at τ=0.80 the holdout reaches 17.683, giving -0.011. So the resume section's from-scratch value doesn't match what the τ sweep table reports for the same condition.

Looking more carefully at the footnote, the resume table's Δ=-0.005 is relative to a single-seed clean replication run, not the 3-seed mean. That means seed 42's from-scratch adaptive at τ=0.8 should be 17.694 - 0.005 = 17.689, which matches what I see in the hybrid table for the same configuration—so those are actually consistent. The τ sweep table's -0.011 is the 3-seed average, which is a different baseline entirely.

Now I'm moving into the ρ=0.3 section and looking at the per-seed results across different datasets. The uniform and adaptive configurations show some variation across seeds and datasets, with adaptive sometimes matching uniform exactly and sometimes showing small differences. Now I'm cross-checking the statistical significance claims against the reference data—the t-test result holds up, and I'm verifying that the transition boundary around ρ=0.3 is real by confirming the delta values shift from positive to negative as expected, plus the micro-batch statistics align with what's reported in the tables. Verifying each calculation against the source documents—the effect size, noncentrality parameter, standard deviations, and all p-values check out against the tables and results file.

Now I'm checking the appendix summary table to confirm the downstream task results show minimal change, the cross-model performance shifts are as expected, the temperature sweep shows improvement in the middle range with degradation at higher values, and the statistical power calculation confirms we have sufficient samples.

Looking at the trajectory figure caption, the training step count of 6,103 matches what's documented in the configuration table.

Verifying the correlation coefficient and batch size effects—at B=16 the adaptive advantage triples with the reported effect size and standard error, and I'm cross-referencing these numbers against the results section to ensure consistency.

Checking the remaining appendix sections for the paired t-test statistics and effect sizes on the rank preservation analysis.

Now I'm reviewing the training configuration from the experiments table: the model is Qwen3-0.6B trained for 6,103 steps with an effective batch size of 16 (micro-batch of 4 with 4× gradient accumulation), using bfloat16 precision, AdamW optimizer with a peak learning rate of 5×10^-5, linear schedule with warmup, 2048 token sequences, and a single GPU.

The reference mentions warmup steps of 100 and weight decay of 0.01, but these details don't appear explicitly in the paper or appendix—they're likely in the code. For the dataset, the paper confirms the 132M-token subset of FineWeb, though the exact breakdown of 371,499 total samples (222,899 real, 148,600 synthetic) isn't stated in the text itself.

Now I'm verifying the math on the synthetic data ratio. The paper mentions a token-level contamination ratio ρ = 0.4 with a resulting document-level synthetic fraction of 55.6%, but when I calculate 148,600 synthetic documents out of 371,499 total, that's exactly 40%, which seems to contradict what's stated about the document-level fraction.

The key insight is that ρ = 0.4 refers to tokens, not documents. Since synthetic documents are shorter on average (304 vs 560 words), you'd need a higher proportion of synthetic documents to reach 40% token contamination, which would explain why the document-level fraction is 55.6%. But the numbers I'm working with don't seem to align with this—either the reference numbers aren't from the paper itself, or I'm misinterpreting what the paper actually specifies about the dataset composition. So these reference numbers are for me to verify against the registry, not against the paper text.

Actually, if 148,600/371,499 = 40.0% by document, but the paper says document-level is 55.6%, then the reference numbers don't match the paper's claim. Unless the reference numbers are wrong or I'm computing wrong. Let me recalculate: 148,600/(148,600+222,899) = 148,600/371,499 = 0.3999... ≈ 40.0% synthetic by document count. But the paper says 55.6%. So either:
1. The reference numbers are approximate / from a different stage
2. The paper's 55.6% is wrong
3. The sample counts include duplicates or something else

Hmm, actually maybe the reference numbers are the MIXED corpus, where ρ=0.4 means 40% tokens are synthetic. If synthetic docs average 304 words and real docs average 560 words, I can work backwards to find what document-level percentage would produce 40% token-level synthetic content. Setting up the ratio of synthetic to real documents based on their average lengths, I get that we'd need about 55.1% of documents to be synthetic to hit that 40% token target, which matches the paper's 55.6% pretty closely—the small difference is just rounding. The reference numbers don't align with the paper's 55.6% claim—whether I calculate it as 40.0% or 60.0% depending on which column represents synthetic data, neither matches. Since the 55.6% figure is mathematically consistent with the word length ratio, the reference numbers might be from a different configuration or have the labels reversed, but without more context I can't resolve this discrepancy.

Now I'm compiling my findings and noticing several inconsistencies across the tables. There's a meaningful difference between the detector table and τ sweep results for TF-IDF+LR (0.033 PPL gap), arithmetic errors in the cross-model deltas like the HellaSwag calculation, and some issues with the hybrid table entries that I need to examine more closely. Looking at the detector table and tau sweep table, both claim the same experimental setup with ρ=0.4, τ=0.8, and 3 seeds using TF-IDF+LR. The arithmetic checks out for both—the detector table shows a delta of -0.044 and the tau table shows -0.011—but these are different values, which suggests they might actually be from different experimental runs despite the matching parameters.

I'm hypothesizing that the detector table might include seed 42 with resume contamination while the tau sweep uses only from-scratch seeds. If seed 42 resume produces a PPL around 17.653, I can work backwards to see if the other seeds in each experiment would be consistent with their reported means. So the other seeds in the detector table average around 17.649, compared to 17.680 in the τ sweep—that 0.031 difference suggests these might be entirely different seed sets. But the gap is suspicious enough that I think the detector table was probably built from older resumed results while the τ sweep got updated with fresh from-scratch runs, which would explain the systematic 0.033 PPL difference between the two tables.

Actually, I need to reconsider this more carefully. The detector table compares different detector types at τ=0.8, so the TF-IDF entry there should match the τ=0.8 point in the τ sweep table exactly. If they don't match, one of them is wrong. The τ sweep explicitly says "3 from-scratch seeds," but the detector table just says "3 seeds" without that specification, which means it probably includes the contaminated seed 42. So the detector table's TF-IDF value of 17.650 is likely the problematic one, and it should be recalculated using the same from-scratch seeds as the τ sweep.

If I update that TF-IDF entry to 17.683, the Δ value shrinks from -0.044 to -0.011, which is much smaller in magnitude but still supports the claim that TF-IDF produces the only improvement over uniform. The caption already hedges this with a note about τ=0.7 achieving 17.674, so the finding remains defensible. I should verify the other numerical claims too—the 2.7× ECE gap between TF-IDF and GPT-2 checks out (0.131 / 0.048 ≈ 2.729), and I need to look at the raw PPL curve claim about the U-shaped minimum at q>0.3.

Looking at the epoch-matched PPL values across thresholds, I see 17.74 → 17.65 → 17.62, which does decrease, but then it ticks back up to 17.628 at q>0.9. That's not strictly monotonic—there's a slight increase at the tail, so the claim about monotonic decrease needs adjustment.

But wait, the paper says "saturates" at q≥0.5, which means it levels off rather than continuously decreasing. The small uptick from 17.62 to 17.628 is within noise, and saturation allows for this kind of plateau behavior. The data actually supports the saturation claim starting at q=0.5, where the PPL stops meaningfully improving.

Now I need to verify the coupling rule claim about the relationship between batch size B and minimum sequence length n_min. Now I'm cross-checking the perplexity improvements across batch sizes—B=4 shows a −0.023 delta, B=8 reaches −0.052, and B=16 peaks at −0.068, confirming the 3.0× amplification ratio. Let me verify the baseline uniform results in the main table to ensure the mean calculation is consistent.

Actually, I see the issue now—the table caption mentions 5-seed means (seeds 42, 123, 456, 789, 234), but only three seed columns are displayed. The mean of 17.697 reflects all five seeds, not just the three visible ones. The three shown seeds average to 17.694, so seeds 789 and 234 together must account for the difference.

For the Adaptive condition, the 5-seed mean of 17.674 happens to match the 3-seed mean exactly, which means seeds 789 and 234 average to the same value. The standard deviations reported (0.008 for Uniform, 0.006 for Adaptive) are calculated across all five seeds, so I can't fully verify them with only the three visible columns.

Let me now pull together the full audit. I'm also double-checking the table values—the main results show Uniform at 17.697 using five seeds (42, 123, 456, 789, 234), while the appendix baseline with three seeds (42, 123, 456) gives 17.694, which is consistent with the documentation. For the τ=0.70 Adaptive condition in the appendix, Holdout is 17.674 with a delta of -0.020, and I need to verify this aligns with what the main text reports.

The deltas check out: comparing the 5-seed adaptive mean of 17.674 against the 3-seed uniform baseline of 17.694 gives -0.020, and against the 5-seed uniform of 17.697 gives -0.023, both correctly reported in their respective contexts. For the ESS-only gap at ρ=0.4, the 3-seed ESS-only mean of 17.737 minus the 3-seed uniform of 17.694 yields the reported gap of 0.043, which matches the main text's claim that ESS-only degrades performance by that amount relative to uniform.

The main table shows ESS-only at 17.737 and uniform at 17.697, which would give 0.040, but that's comparing 3-seed ESS-only against 5-seed uniform—the 0.043 figure correctly uses the 3-seed uniform baseline since both methods are 3-seed in that comparison. It's methodologically sound but could potentially confuse readers about which baseline is being used.

Now I'm checking the t-test values in the caption for Table tab:rho06, which reports paired t=−15.4 with p=0.004 at full precision, noting that 3-decimal rounding yields t=−9.95 and p=0.010. Let me verify this by computing the per-seed differences and running the test.

Computing the per-seed deltas and their statistics: the mean difference is −0.032 with a standard deviation of about 0.00557, giving a standard error of 0.003216 and thus t = −9.95. So the rounded version checks out, which means the full-precision t-statistic of −15.4 must come from tighter per-seed deltas that haven't been rounded yet.

Now I'm checking the p-value for this t-statistic with 2 degrees of freedom. At t(2) = −9.95, the two-tailed p-value comes out to around 0.010, which matches what the caption reports. The full-precision t = −15.4 gives p ≈ 0.004, suggesting the test is sensitive to the precision of the underlying values.

Looking at results.tex, I see it reports the rounded t-statistic with the Benjamini-Hochberg corrected p-value, so there's a mix of precision levels being used. Now I need to compile all the discrepancies I've found and determine which ones actually need fixing.

The main issue is that the detector table shows TF-IDF+LR at τ=0.8 with a PPL of 17.650±.010, but the tau table reports 17.683±.006 for the same condition using three fresh seeds—this suggests the detector table may have pulled contaminated results. There are also minor arithmetic issues like the HellaSwag cross-model difference being off by 0.01 percentage points, and some ECE values that appear rounded differently than stated elsewhere. A few other discrepancies between tables turn out to be just rounding artifacts rather than actual errors. I need to verify whether the TF-IDF detector result should match the τ sweep baseline of 17.683±.006, which would give Δ=-0.011 instead of -0.044, but I'm uncertain about updating it without confirming the from-scratch 3-seed mean for that specific experiment. I should also check if the standard deviation needs updating and whether the resume artifact contamination affects only TF-IDF or the other detectors too. τ sweep τ=0.8 is described as "3 from-scratch seeds (Appendix app:resume_artifact)". The detector comparison might use different seeds (e.g., seeds that were always from-scratch, not the same 42/123/456). In that case, 17.650 could be correct for those seeds.

But that would be very unusual to use different seed sets for different tables. And the SD of 0.010 for TF-IDF vs 0.006 for τ=0.80 suggests different data. If they used the same seeds, the SD should be the same.

I think what happened is the detector table uses 3 seeds that may include the resume-contaminated seed 42, while the τ sweep uses from-scratch seeds (likely 42, 123, 456 from-scratch).

Given the resume artifact section's explicit warning about this, I should flag this discrepancy rather than blindly change it. The user said to fix what can be fixed directly, so I'll address the clear arithmetic issues and flag the uncertain ones. For the cross-model HellaSwag Δ = -0.59, this is probably just rounding of the source values, so I'll flag it but not fix. For the detector details "0.12 to 0.05", I should update it to "0.12 to 0.048" for consistency, though "0.05" could reasonably be interpreted as approximate.

Now I'm checking the appendix text more carefully. At B=16, the adaptive advantage shows a 3.0× amplification with Δ = -0.068±0.005, and the Spearman correlation is listed as r = 0.699 with the true real fraction. Looking at the table, the binarized version shows r = 0.699 at B=4, but the continuous version is around r ≈ 0.77–0.79, so there's a mismatch in which version is being cited here.

Let me verify all the numbers in the trajectory caption and the following paragraph. The training steps (6,103), seed (42), and ρ (0.4) all check out. The batch size notation is consistent—B=4 is the base batch with B=16 after gradient accumulation. The Spearman r = 0.699 matches the table at B=4, and I need to confirm the adaptive advantage values against the results file.

Now I'm compiling the full audit report and checking whether any appendix cross-references point to other appendix sections. I've already verified the main table numbers, so I'm looking for internal appendix citations—like the 5-seed comparison yielding Δ=−0.023, the τ=0.8 resume artifact reference, and the ρ=0.4 value of 0.043. These all check out.

I'm also being more careful with the discussion.tex cross-references now. The +0.046 at ρ=0.2 and the sharp transition in [0.3, 0.4] both match what I've verified, and the Pearson r ≈ 0.79 is distinct from the 0.80 q̄ correlation in the per-seed table—the caption clarifies this difference. Many of these numbers can't be fully verified against the registry without access to it, but I'll note that in my report.

Before I compile everything, let me double-check the Bonferroni-Holm correction claims. The uncorrected p-values are 0.0012 at ρ=0.4 and 0.010 at ρ=0.6. With k=9 comparisons, the threshold is α/9 = 0.00556, so the smallest p-value passes. Multiplying by 9 gives the corrected p ≈ 0.011, which matches what's stated in the text.

For the second p-value at ρ=0.6, I need to recalculate using the Bonferroni-Holm formula where each adjusted p-value is the maximum of the previous adjustment and the current p-value times the remaining degrees of freedom. The calculation seems off—0.010 × 8 gives 0.080, not 0.064, so there's a discrepancy I need to resolve.

Looking at the notation more carefully, "p_BH" in the paper could refer to either Bonferroni-Holm or Benjamini-Hochberg, even though the text explicitly mentions Bonferroni-Holm. Let me check if Benjamini-Hochberg produces the 0.064 value instead. So the 9 comparisons break down into 6 reweighting methods tested at ρ=0.4 against uniform, plus 3 additional tests at different ρ levels (0.2, 0.3, and 0.6). The ρ=0.6 adaptive versus uniform comparison is one of those three additional tests, and I'm trying to figure out which rank position it occupies in the sorted p-value list to work backwards to that 0.064 adjusted value. Working backward from the adjusted p-value of 0.064, I can check if it's consistent with either correction method. For Holm, that would require a non-integer rank, which is impossible. For Benjamini-Hochberg, I'm solving for what rank would produce that adjusted value, but the math isn't working out either.

This suggests the uncorrected p-value might not be exactly 0.010—the caption mentions full precision gives p=0.004, which rounds to 0.010 at three decimal places. Let me recalculate using the full precision value instead.

If I apply Benjamini-Hochberg with p=0.004 at different ranks, I get values like 0.018 or 0.00514, neither of which matches 0.064 either. I'm wondering if they're using a different correction method entirely, or perhaps applying the step-up procedure in a way I haven't considered yet—maybe accounting for the maximum of preceding adjusted p-values in the BH calculation. I'm checking whether 0.064 could result from the Benjamini-Hochberg formula with different uncorrected p-values, testing r=1, 2, and 3 to see what raw p-value would produce that adjusted result. Even with the full-precision p=0.004, the math doesn't work out to give 0.064, which makes me suspect there might be an error in the reported p_BH value itself.

Actually, I should reconsider what "Bonferroni-Holm" means here—it's the Holm stepwise procedure, not standard Benjamini-Hochberg. In that method, I'd need to sort all nine p-values and apply the stepwise adjustment where each adjusted p-value is the maximum of the previous adjustments. If the ρ=0.6 test sits at rank 7 with uncorrected p=0.010, its Holm adjustment would be 0.010 × 3 = 0.030, but that's still nowhere near 0.064.

The only way to get 0.064 is if an earlier test in the ranking has a larger adjusted value that carries forward—for instance, if some test at rank 4 has p=0.01067, its adjustment would be 0.01067 × 6 = 0.064, and then all subsequent tests would inherit at least that value.

Without the full table of nine p-values, I can't verify whether this is what actually happened, so I'll note this as a limitation rather than flag it as an error. The Benjamini-Hochberg correction depends on the entire family of comparisons, and I'm only seeing the final reported values.

Now let me check the specific claims in the appendix. The TF-IDF versus GPT-2 comparison checks out—the ECE ratio of 0.131 to 0.048 does equal approximately 2.7×. For the N-gram analysis, it has better calibration than GPT-2 with an ECE of 0.069 versus 0.131, but its discriminative ability is weak at an AUC of 0.73. Let me continue examining the next claim about discriminative power.

The TF-IDF+LR detector shows the only improvement over uniform calibration with an ECE of 0.048, which corresponds to a delta of -0.044 in the table—negative indicating improvement. Even if the TF-IDF perplexity were actually 17.683 instead of 17.650, the delta would shift to -0.011, still negative and still supporting the improvement claim. I should verify one more set of numbers from line 363 before finalizing my audit. I'm working through the math on the synthetic token ratio—if they're targeting ~100M synthetic tokens but only using them at ρ=0.4, that means roughly 53M tokens end up in the final corpus, which suggests the 100M figure refers to what was generated before the mixing ratio was applied. Wait, I need to reconsider what "132M-token subset" actually refers to. If that's the total mixed corpus, then the real data would be about 79M tokens and synthetic would be roughly 53M—meaning they're generating around 100M tokens but only using about half of it. That interpretation makes more sense than the total being 220M. The wording is genuinely ambiguous—"132M-token subset of FineWeb" suggests that's the real data contribution, but if ρ=0.4 means 40% synthetic, the math doesn't align unless 132M is the total budget. The detector section mentions targeting ~100M synthetic tokens, which would fit better if the real portion is around 79-88M, so I'll assume that's the intended setup and move forward.

Now I'm checking whether the registry agent has finished its validation, and if not, I'll compile my audit findings organized by the number of values checked, issues discovered, and corrections made.

Tallying up across all the tables, I'm looking at roughly 200+ individual numbers that need verification—spanning PPL values, thresholds, metrics, and in-text references. The critical issue I've identified so far is an inconsistency in the TF-IDF perplexity values in the detector table.

For that detector table discrepancy, the tau sweep value of 17.683 appears more reliable since it explicitly used three from-scratch seeds, whereas the detector table doesn't specify its seeding approach. But I can't simply swap in the tau value without checking whether the other detector rows (GPT-2, N-gram) were run under the same conditions—if they weren't, changing just one number would break the cross-detector comparison.

Actually, the resume artifact only contaminated the adaptive model's training checkpoint at seed 42 and τ=0.8, so it wouldn't affect GPT-2 or N-gram detectors since those are separate experiment types. The key question is whether all three detectors in that table used the same seeds and training setup, because if the TF-IDF detector was updated to use from-scratch seeds but the others weren't, the comparison becomes invalid. are from-scratch could make the comparison invalid. The user should verify this against the actual experiment logs to be sure.

For the ECE rounding issue, I need to be more careful here. The threshold mentioned is "0.05" but the actual final ECE value is "0.048", so I should update that result to reflect the precise number rather than the rounded threshold.

On the HellaSwag delta, I'm catching an arithmetic error: 72.49 - 73.08 equals -0.59, not -0.60. I'll correct this to -0.59pp, though I should check if there's additional precision in the underlying values that might justify the original rounding. There's a 0.01 percentage point discrepancy in the table—the calculation shows -0.59 but it's displayed as -0.60. I need to make three fixes: correct the HellaSwag delta to -0.59pp, update the ECE value to 0.048, and note the detector table inconsistency. For the ECE change, I should clarify whether to update just the final value or the full range from 0.12 to 0.048 depending on what the context actually describes. to verify exactly without the full distribution data. Let me proceed with finalizing the edits.

I want to do one more cross-check on the ESS binding percentages across different ρ values. The appendix mentions ~49% of batches at one point, while results.tex shows ~44% ESS-binding at ρ=0.4 and ~50% at ρ=0.6. There's a slight discrepancy between ~43% and ~44% that I should flag, though it's minor. The ~43% versus ~44% discrepancy is minor since both use the approximation symbol, but I should standardize the appendix to match results.tex at ~44% for consistency. I'm settling on three concrete fixes: updating the HellaSwag delta from -0.60 to -0.59, correcting the ECE value to 0.048, and flagging the detector table inconsistency, then I'll document the remaining cross-checks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "c188d9a1-d056-4e39-a3c1-797d8a472a5d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019wN8wqHoGRPpBeGJySyWCQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 49492,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 22,
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

_source line 69_

Registry 查询在后台运行中，先基于正文交叉验证开始审计。读取 discussion.tex 中需要的交叉引用数字。

现在系统地审计 appendix 每个数字。先做正文-附录交叉验证，registry 结果到了再补充。

我已经完成了正文（results.tex, experiments.tex, discussion.tex）与 appendix 的全面交叉验证。以下是几个需要确认的点，让我先修复明确的算术错误。

**发现 1**: Cross-model HellaSwag Δ 算术错误 — 72.49 − 73.08 = −0.59，表中写 −0.60pp。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "e9a3a991-213f-4008-8871-5ea2baf8520e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019wN8wqHoGRPpBeGJySyWCQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 49492,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 22,
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

_source line 70_

<details open><summary>🔧 Tool call — Edit · `toolu_01PsSsLesDKSBPkAP1b36obJ`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/appendix.tex",
  "old_string": "HellaSwag (10-shot, acc\\_norm) & 73.08\\% $\\pm$ .44 & 72.49\\% $\\pm$ .45 & $-$0.60pp \\\\",
  "new_string": "HellaSwag (10-shot, acc\\_norm) & 73.08\\% $\\pm$ .44 & 72.49\\% $\\pm$ .45 & $-$0.59pp \\\\"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "630e1949-d3b8-4e1b-b058-1b4118dba920",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019wN8wqHoGRPpBeGJySyWCQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 49492,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 22,
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

_source line 71 · 2026-05-25T20:16:26.751Z_

<details><summary>↩ Tool result · `toolu_01PsSsLesDKSBPkAP1b36obJ`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "2f3a470f-e832-49bd-b1ec-938b002f5400",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/appendix.tex",
    "oldString": "HellaSwag (10-shot, acc\\_norm) & 73.08\\% $\\pm$ .44 & 72.49\\% $\\pm$ .45 & $-$0.60pp \\\\",
    "newString": "HellaSwag (10-shot, acc\\_norm) & 73.08\\% $\\pm$ .44 & 72.49\\% $\\pm$ .45 & $-$0.59pp \\\\",
    "originalFile": "\\section{Proofs}\n\\label{app:proofs}\n\n\\begin{proposition}[$\\alpha_{\\mathrm{eff}}$ monotonicity]\n\\label{prop:monotone}\n$\\alpha_{\\mathrm{eff}}(b)$ is non-decreasing in $b$, and strictly increasing whenever the batch contains at least two samples with distinct $q$-values.\n\\end{proposition}\n\n\\begin{proof}[Proof of Proposition~\\ref{prop:monotone}]\nLet $w_i(b) = (1 - q_i)^b$, $W(b) = \\sum_{j=1}^B w_j(b)$, and $\\pi_i(b) = w_i(b) / W(b)$.\nThen\n\\begin{equation*}\n  \\alpha_{\\mathrm{eff}}(b) = \\sum_{i=1}^{B} \\pi_i(b)\\, (1 - q_i).\n\\end{equation*}\nTaking the derivative with respect to $b$:\n\\begin{align*}\n  \\frac{d\\pi_i}{db}\n  &= \\pi_i \\!\\left(\\frac{d \\ln w_i}{db} - \\frac{d \\ln W}{db}\\right) \\\\\n  &= \\pi_i \\!\\left(\\ln(1{-}q_i) - \\textstyle\\sum_j \\pi_j \\ln(1{-}q_j)\\right).\n\\end{align*}\nSubstituting,\n\\begin{align*}\n  \\frac{d\\alpha_{\\mathrm{eff}}}{db}\n  &= \\sum_i (1{-}q_i)\\, \\pi_i \\!\\left(\\ln(1{-}q_i) - \\mathbb{E}_{\\pi}[\\ln(1{-}q)]\\right) \\\\\n  &= \\mathrm{Cov}_{\\pi}\\!\\bigl(1{-}q_i,\\, \\ln(1{-}q_i)\\bigr).\n\\end{align*}\nSince $(1{-}q_i)$ and $\\ln(1{-}q_i)$ are both increasing functions of $(1{-}q_i)$, they are positively associated, so the covariance is non-negative.\n\\end{proof}\n\n\\begin{proposition}[ESS monotonicity]\n\\label{prop:ess_mono}\n$\\mathrm{ESS}(b)$ is non-increasing in $b$, and strictly decreasing whenever the batch contains at least two samples with distinct $q$-values.\n\\end{proposition}\n\n\\begin{proof}\nWrite $\\mathrm{ESS}(b) = 1 / \\sum_i \\pi_i(b)^2$, where $\\pi_i(b) = w_i(b) / W(b)$.\nThe denominator $\\sum_i \\pi_i^2$ is the Herfindahl index $H$.\nDifferentiating $H$ with respect to $b$:\n\\begin{equation*}\n  \\frac{dH}{db} = 2 \\sum_i \\pi_i^2 \\bigl(\\ln(1{-}q_i) - \\mathbb{E}_{\\pi}[\\ln(1{-}q)]\\bigr).\n\\end{equation*}\nSince $\\pi_i \\propto (1{-}q_i)^b$, larger $\\pi_i$ implies larger $\\ln(1{-}q_i)$; the $\\pi^2$-weighted sum assigns greater mass to terms where $\\ln(1{-}q_i) > \\mathbb{E}_\\pi[\\ln(1{-}q)]$, so $dH/db \\geq 0$, with strict inequality when at least two $q$-values differ.\nThus $H$ is non-decreasing and $\\mathrm{ESS} = 1/H$ is non-increasing.\nThis is a standard property of exponential tilting~\\citep{kish1965survey,owen2013mc}.\n\\end{proof}\n\n\\section{Algorithm Details}\n\\label{app:algorithm}\n\n\\begin{algorithm}[h]\n\\caption{Per-batch adaptive $b^{*}$ selection}\n\\label{alg:bstar}\n\\begin{algorithmic}[1]\n\\REQUIRE Batch scores $\\{q_i\\}_{i=1}^{B}$, threshold~$\\tau$, ESS floor~$n_{\\min}$, bound~$b_{\\max}$, tol.~$\\varepsilon$\n\\ENSURE Optimal sharpening exponent $b^{*}$\n\\IF{$\\alpha_{\\mathrm{eff}}(0) \\geq \\tau$}\n  \\STATE \\textbf{return} $0$ \\COMMENT{clean batch}\n\\ENDIF\n\\STATE $b_\\tau \\gets \\textsc{Bisect}(\\alpha_{\\mathrm{eff}}(\\cdot){=}\\tau,\\; [0, b_{\\max}],\\; \\varepsilon)$\n\\IF{$\\mathrm{ESS}(b_\\tau) \\geq n_{\\min}$}\n  \\STATE \\textbf{return} $b_\\tau$ \\COMMENT{$\\alpha_{\\mathrm{eff}}$-binding}\n\\ELSE\n  \\STATE $b_{\\mathrm{ESS}} \\gets \\textsc{Bisect}(\\mathrm{ESS}(\\cdot){=}n_{\\min},\\; [0, b_{\\max}],\\; \\varepsilon)$\n  \\STATE \\textbf{return} $b_{\\mathrm{ESS}}$ \\COMMENT{ESS-binding}\n\\ENDIF\n\\end{algorithmic}\n\\end{algorithm}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{bstar_trajectory_adaptive_fix}\n\\caption{Adaptive $\\bstar$ trajectory over 6{,}103 training steps (seed\\,42, $\\rho{=}0.4$).\nThe exponent alternates between clean ($\\bstar{=}0$), $\\aeff$-binding, and ESS-binding regimes with no systematic drift, reflecting per-batch adaptation to local $q$-score composition.}\n\\label{fig:bstar_traj}\n\\end{figure}\nWe compute $\\bstar$ at the micro-batch level ($B{=}4$) rather than the effective batch ($B{=}16$ after gradient accumulation) because $q$-score statistics exhibit sufficient variance within micro-batches: Spearman $r{=}0.699$ with the true real fraction, and at $B{=}16$ the adaptive advantage amplifies $3.0{\\times}$ ($\\Delta{=}{-}0.068{\\pm}0.005$; \\S\\ref{sec:sensitivity}).\n\n\\section{Grid Search Details}\n\\label{app:grid}\n\nTable~\\ref{tab:grid_full} reports held-out PPL for all grid-$b$ values at $\\rho = 0.4$ (seed\\,42).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}cc@{}}\n\\toprule\n$b$ & PPL $\\downarrow$ \\\\\n\\midrule\n0.1 & 17.657 \\\\\n0.2 & 17.640 \\\\\n0.3 & \\textbf{17.640} \\\\\n0.5 & 17.651 \\\\\n1.0 & 17.692 \\\\\n1.5 & 17.718 \\\\\n2.0 & 17.741 \\\\\n3.0 & 17.774 \\\\\n5.0 & 17.818 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Full grid search results ($\\rho{=}0.4$, seed\\,42).\n$b \\in [0.1, 0.5]$ forms a broad plateau (three-seed mean for $b{=}0.1$: $17.655 \\pm 0.009$); $b{=}0.3$ is the post-hoc best.}\n\\label{tab:grid_full}\n\\end{table}\n\n\\section{Quality Threshold Sweep}\n\\label{app:tau_sweep}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}ccccccc@{}}\n\\toprule\n$\\tau$ & Holdout $\\downarrow$ & $\\Delta_{\\text{H}}$ & OWT $\\downarrow$ & $\\Delta_{\\text{O}}$ & Wiki $\\downarrow$ & $\\Delta_{\\text{W}}$ \\\\\n\\midrule\n0.50 & 17.688 & $-$0.006 & -- & -- & -- & -- \\\\\n0.60 & 17.681 & $-$0.013 & -- & -- & -- & -- \\\\\n0.70$^\\star$ & \\textbf{17.674{\\tiny$\\pm$.006}} & $\\boldsymbol{-}$\\textbf{0.020} & \\textbf{18.347{\\tiny$\\pm$.003}} & $\\boldsymbol{-}$\\textbf{0.028} & \\textbf{15.330{\\tiny$\\pm$.015}} & $\\boldsymbol{-}$\\textbf{0.029} \\\\\n0.80$^\\star$ & 17.683{\\tiny$\\pm$.006} & $-$0.011 & 18.370{\\tiny$\\pm$.005} & $-$0.005 & 15.350 & $-$0.009 \\\\\n0.90 & 17.712 & $+$0.018 & -- & -- & -- & -- \\\\\n0.95 & 17.723 & $+$0.029 & -- & -- & -- & -- \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Quality threshold sweep ($\\nmin{=}2$, $\\rho{=}0.4$).\n$\\Delta$ relative to 3-seed uniform baseline (Holdout 17.694, OWT 18.375, Wiki 15.359).\n$^\\star$\\,$\\tau{=}0.7$: 5-seed mean (SD from 5 seeds); $\\tau{=}0.8$: 3 from-scratch seeds (Appendix~\\ref{app:resume_artifact}). The 5-seed comparison in Table~\\ref{tab:main} yields $\\Delta{=}{-}0.023$.\nOther values from single-seed exploratory sweep (seed\\,42, holdout only).\n$\\tau{=}0.7$ achieves the lowest holdout and largest OOD gains ($|\\Delta| \\geq 0.028$); $\\tau{=}0.8$'s OOD effect is smaller ($|\\Delta| \\leq 0.009$).}\n\\label{tab:tau}\n\\end{table}\n\n\\section{Batch-Adaptive $\\tau$}\n\\label{app:batch_adaptive}\n\nWe tested a per-batch adaptive variant that clamps $\\tau$ between 0.5 and the fixed threshold based on local $\\aeff(0)$, allowing the quality floor to relax in batches with low estimated real fraction.\nAt both contamination levels ($\\rho \\in \\{0.4, 0.6\\}$), the adaptive variant did not outperform the fixed threshold (single-seed exploratory at each level), suggesting the quality constraint does not require adaptation to local contamination density.\nThis supports the ``two hyperparameters with good defaults'' characterization: neither $\\tau$ nor $\\nmin$ benefits from per-batch tuning.\n\n\\section{\\texorpdfstring{$\\tau$--$\\rho$}{tau-rho} Rank Preservation}\n\\label{app:tau_rho}\n\nFigure~\\ref{fig:tau_rho_rank} shows the $\\tau$--PPL relationship at two contamination levels.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{tau_rho_rank_preservation}\n\\caption{(a) Held-out PPL as a function of quality threshold $\\tau$ at $\\rho \\in \\{0.4, 0.6\\}$.\n$\\tau{=}0.7$ and $\\tau{=}0.8$ yield comparable holdout PPL at $\\rho{=}0.4$; at $\\rho{=}0.6$, $\\tau{=}0.7$ is statistically better (paired $t{=}{-}4.70$, $p{<}0.05$, 3 seeds, $\\Delta{=}{-}0.005$). $\\tau{=}0.7$ also achieves lower OOD perplexity at both levels ($\\rho{=}0.6$: $\\Delta_{\\text{OWT}}{=}{-}0.014$, $\\Delta_{\\text{Wiki}}{=}{-}0.013$, 2 seeds).\n(b) Normalized PPL gap relative to uniform at shared $\\tau$ values.}\n\\label{fig:tau_rho_rank}\n\\end{figure}\n\n\\section{Hybrid and Threshold Comparison}\n\\label{app:hybrid}\n\nTable~\\ref{tab:hybrid} compares method families across contamination levels.\nTable~\\ref{tab:dr_threshold} shows D\\&R sensitivity to the detection threshold at both full training length and epoch-matched settings.\nRaw PPL traces a U-shaped curve with a minimum at $q{>}0.3$ (17.250, 3 seeds), but this curve conflates filtering quality with multi-epoch exposure: aggressive thresholds retain less data and repeat it more often.\nEpoch-matched comparisons (rightmost column of Table~\\ref{tab:dr_threshold}) remove the multi-epoch confound: the U-shape vanishes and PPL decreases monotonically, saturating near the adaptive $\\bstar$ level at $q{\\geq}0.5$.\nFigure~\\ref{fig:dr_dual_curve} visualizes the two curves.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\n\\textbf{Method} & $\\rho{=}0.4$ & $\\rho{=}0.6$ \\\\\n\\midrule\nUniform & 17.694 & 17.766 \\\\\nAdaptive $\\bstar$ & 17.689 & 17.740 \\\\\nHybrid ($q{>}0.95$ + adaptive) & 17.514 & 17.530$^*$ \\\\\nDetect \\& Remove ($q{>}0.5$) & 17.285 & -- \\\\\nDetect \\& Remove ($q{>}0.3$) & 17.250 & -- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Method comparison across contamination levels (seed\\,42, $\\tau{=}0.8$).\n$^*$Hybrid at $\\rho{=}0.6$ filters high-confidence synthetic ($q{>}0.95$), reducing effective $\\rho$ to ${\\approx}0.4$; PPL is not directly comparable to $\\rho{=}0.6$ baselines.}\n\\label{tab:hybrid}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{@{}ccccc@{}}\n\\toprule\n\\textbf{Thresh.} & \\textbf{Ret.\\ \\%} & \\textbf{Epochs} & \\textbf{Raw PPL} $\\downarrow$ & \\textbf{Ep.-matched} $\\downarrow$ \\\\\n\\midrule\n$q > 0.1$ & 15.0\\% & ${\\sim}$10.0 & 17.40 & 18.04 \\\\\n$q > 0.2$ & ${\\sim}$23\\% & ${\\sim}$5.0 & 17.27 & -- \\\\\n$q > 0.3$ & 31.5\\% & ${\\sim}$3.2 & \\textbf{17.250}$^\\dagger$ & 17.74 \\\\\n$q > 0.4$ & ${\\sim}$38\\% & ${\\sim}$2.8 & 17.26 & -- \\\\\n$q > 0.5$ & 41.4\\% & ${\\sim}$2.4 & 17.28 & 17.65 \\\\\n$q > 0.6$ & ${\\sim}$46\\% & ${\\sim}$1.7 & 17.30 & -- \\\\\n$q > 0.7$ & 49.8\\% & ${\\sim}$2.0 & 17.32 & 17.62 \\\\\n$q > 0.8$ & ${\\sim}$56\\% & ${\\sim}$1.3 & 17.34 & -- \\\\\n$q > 0.9$ & 61.6\\% & ${\\sim}$1.1 & 17.42 & 17.628 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{D\\&R threshold sensitivity ($\\rho{=}0.4$, seed\\,42 unless noted).\nRaw PPL traces a U-shaped curve (minimum at $q{>}0.3$); epoch-matched PPL (single content epoch) decreases monotonically and saturates near the adaptive $\\bstar$ level (${\\approx}$17.65) at $q{\\geq}0.5$; the U-shape is thus a multi-epoch artifact.\n$^\\dagger$\\,3-seed mean $17.250 \\pm 0.001$.}\n\\label{tab:dr_threshold}\n\\end{table}\n\nSee Figure~\\ref{fig:dr_dual_curve} (\\S\\ref{sec:main-results}) for the dual-curve visualization.\n\n\\section{Downstream Task Evaluation}\n\\label{app:downstream}\n\nTable~\\ref{tab:downstream} reports downstream benchmark accuracy for adaptive vs.\\ uniform training at $\\rho{=}0.4$ (seed\\,42, Qwen3-0.6B).\nAcross multiple seeds, downstream differences are mixed in direction and uniformly within standard error, indicating that adaptive reweighting has no meaningful downstream impact.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llccc@{}}\n\\toprule\n\\textbf{Benchmark} & \\textbf{Metric} & \\textbf{Adaptive} & \\textbf{Uniform} & $\\boldsymbol{\\Delta}$ \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{Seed 42 (checkpoint resume)}} \\\\\nARC-Challenge & acc\\_norm & 0.343 & 0.348 & $-$0.005 \\\\\nARC-Easy & acc & 0.650 & 0.657 & $-$0.007 \\\\\nHellaSwag & acc\\_norm & 0.479 & 0.484 & $-$0.005 \\\\\nPIQA & acc & 0.687 & 0.686 & $+$0.001 \\\\\nWinoGrande & acc & 0.578 & 0.586 & $-$0.008 \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{From-scratch 2-seed mean (seeds 123, 456)}} \\\\\n\\multicolumn{3}{@{}l}{Mean $\\Delta$ across 5 tasks} & & $+$0.001 \\\\\n\\multicolumn{3}{@{}l}{Direction} & \\multicolumn{2}{c}{mixed (seed 123: 3/5$-$; seed 456: 3/5$+$)} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Downstream benchmarks (Qwen3-0.6B, $\\rho{=}0.4$).\nSeed\\,42 used a checkpoint-resumed adaptive model; from-scratch seeds (123, 456) show mixed direction with mean $|\\Delta| \\leq 0.01$.\nAll differences within standard error ($\\pm 0.01$).\nModels use $\\tau{=}0.8$; $\\tau{=}0.7$ yields identical 3-seed means (0.5414).}\n\\label{tab:downstream}\n\\end{table}\n\n\\section{Higher Contamination Details}\n\\label{app:rho06}\n\nTable~\\ref{tab:rho06} reports results at $\\rho{=}0.6$.\nThe full five-method ablation preserves the hierarchy from $\\rho{=}0.4$ across all three seeds: Grid ${<}$ Adaptive ${<}$ Uniform ${\\approx}$ ESS-only ${<}$ Random.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n\\textbf{Method} & \\textbf{Seed 42} & \\textbf{Seed 123} & \\textbf{Seed 456} & \\textbf{Mean} \\\\\n\\midrule\nGrid ($b{=}0.3$)$^\\ddagger$ & \\textbf{17.634} & -- & -- & -- \\\\\nAdaptive $\\bstar$ & 17.735 & 17.727 & 17.732 & 17.731 $\\pm$ .004 \\\\\nUniform           & 17.766 & 17.754 & 17.770 & 17.763 $\\pm$ .008 \\\\\nESS-only          & 17.770 & 17.760 & 17.760 & 17.763 $\\pm$ .006 \\\\\nRandom $\\mathcal{U}(0,2)$ & 17.832 & 17.870 & 17.880 & 17.861 $\\pm$ .025 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Results at $\\rho{=}0.6$ (Qwen3-0.6B, $\\nmin{=}2$).\nAdaptive uses $\\tau{=}0.7$ (consistent with main results); other methods are $\\tau$-independent.\n$^\\ddagger$Post-hoc oracle; seed\\,42 only.\nAdaptive vs.\\ Uniform: $\\Delta{=}{-}0.032$, paired $t{=}{-}15.4$, $p{=}0.004$ (full precision; 3dp rounding yields $t{=}{-}9.95$, $p{=}0.010$).\nESS-only collapses onto Uniform (both $17.763$); Random ($17.861$) confirms detector signal is load-bearing.}\n\\label{tab:rho06}\n\\end{table}\n\nThe ESS-only/Uniform gap collapses from 0.043 at $\\rho{=}0.4$ to 0.000 at $\\rho{=}0.6$ (three-seed means: both $17.763$); ESS binding rises to ${\\sim}$49\\% of batches (from ${\\sim}$43\\% at $\\rho{=}0.4$), and the constraints become nearly balanced rather than $\\aeff$-dominant.\nThe adaptive method maintains its advantage ($\\Delta{=}{-}0.032$, consistent across seeds) through the $\\aeff$ quality constraint, which operates independently of the ESS ceiling.\nRandom reweighting ($17.861 \\pm 0.025$) is substantially worse than Uniform, with the highest cross-seed variance; uninformed weights add noise without corrective signal.\nThe Adaptive-vs-Grid gap is 0.054 at $\\rho{=}0.4$ (mean-to-mean, consistent with Table~\\ref{tab:aux}) and 0.097 at $\\rho{=}0.6$ (adaptive 3-seed mean vs.\\ grid seed\\,42; the $\\rho{=}0.6$ grid result is preliminary and may not generalize across seeds).\n\n\\section{\\texorpdfstring{$\\alpha_{\\mathrm{eff}}$}{alpha-eff} Proxy Validation}\n\\label{app:alpha_validation}\n\nTable~\\ref{tab:alpha_corr} reports the correlation between $\\aeff(0)$ (the detector-based proxy at $b{=}0$) and the true batch-level real fraction $\\alpha_{\\mathrm{true}}$, computed over all training batches at $\\rho{=}0.4$ (seed\\,42).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}ccccc@{}}\n\\toprule\n$B$ & Pearson $r$ & Spearman $r$ & MAE$\\downarrow$ & Bias \\\\\n\\midrule\n4  & 0.706 & 0.699 & 0.114 & $-$0.029 \\\\\n8  & 0.697 & 0.683 & 0.097 & $-$0.027 \\\\\n16 & 0.707 & 0.691 & 0.075 & $-$0.031 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Correlation between $\\aeff(0)$ and true batch-level real fraction across batch sizes ($\\rho{=}0.4$, seed\\,42).\nValues use a binarized proxy $\\hat{r}_i = \\mathbf{1}[q_i \\leq 0.5]$ for discrete comparison; the continuous formulation used during training (\\S\\ref{sec:method}) achieves $r \\approx 0.77$--$0.79$ depending on batch size.\nThe consistent negative bias (${\\approx}{-}0.03$) indicates that $\\aeff$ slightly underestimates the true real fraction, biasing the method toward conservative intervention.}\n\\label{tab:alpha_corr}\n\\end{table}\n\nMean absolute error (MAE) decreases with batch size (0.114 $\\to$ 0.075) as expected from averaging, but the rank-order information that drives $\\bstar$ selection is already well-captured at $B{=}4$.\n\n\\paragraph{Cross-seed stability.}\nTable~\\ref{tab:alpha_corr_perseed} reports the correlation between $\\aeff$ and the batch mean $q$-score ($\\bar{q}$, computed from known labels) across all three seeds.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}cccc@{}}\n\\toprule\n\\textbf{Seed} & Pearson $r(\\aeff, \\bar{q})$ & Spearman $\\rho_s$ & $\\bstar{=}0$ (\\%) \\\\\n\\midrule\n42  & 0.8019 & 0.8761 & 5.8 \\\\\n123 & 0.7994 & 0.8692 & 5.7 \\\\\n456 & 0.8006 & 0.8749 & 5.9 \\\\\n\\midrule\n\\textbf{Spread} & 0.0025 & 0.0069 & 0.2 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Per-seed $\\aeff$--$\\bar{q}$ correlation ($\\rho{=}0.4$, $B{=}4$).\nCross-seed spread is $<$0.003 for Pearson $r$ and $<$0.007 for Spearman $\\rho_s$, indicating stable proxy fidelity across random seeds.\n$r(\\aeff, \\bar{q}) = 0.80$ measures the proxy's fidelity to batch composition; the ground-truth correlation $r(\\aeff, \\text{true real fraction}) \\approx 0.79$ (\\S\\ref{sec:discussion}) is slightly lower due to detector noise.\nThe per-seed table demonstrates cross-seed stability rather than superseding the ground-truth estimate.}\n\\label{tab:alpha_corr_perseed}\n\\end{table}\n\n\\section{Detector Comparison}\n\\label{app:detector}\n\nSee Figure~\\ref{fig:overview}b (\\S\\ref{sec:robustness}) for the detector requirements visualization.\n\nTable~\\ref{tab:detector} compares three detector families for adaptive reweighting.\nThe discriminative TF-IDF+LR detector (ECE\\,=\\,0.048) produces the only improvement over uniform.\nThe TF-IDF vs.\\ GPT-2 contrast (comparable AUC: 0.94 vs.\\ 0.91, but $2.7{\\times}$ ECE gap: 0.048 vs.\\ 0.131) isolates calibration as an empirically observed requirement; however, N-gram's better ECE (0.069) does not compensate for its low AUC (0.73); both sufficient discrimination and good calibration are jointly necessary in our setting.\nTF-IDF+LR's $q$-scores have reliable probabilistic semantics, so the $\\aeff$ proxy accurately tracks batch quality.\nGenerative detectors assign high $q$-scores to fluent, predictable human text (false positives concentrated among high-quality samples), systematically inflating $\\aeff$ for clean batches and deflating it for contaminated ones, which inverts the minimum-intervention logic.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llccccc@{}}\n\\toprule\n\\textbf{Detector} & \\textbf{Type} & \\textbf{AUC} & \\textbf{ECE} & \\textbf{Mean PPL} & $\\boldsymbol{\\Delta}$ \\\\\n\\midrule\nTF-IDF+LR & Discriminative & 0.94 & 0.048 & 17.650{\\tiny$\\pm$.010} & $-$0.044 \\\\\nGPT-2 PPL & Generative & 0.91 & 0.131 & 17.792{\\tiny$\\pm$.005} & $+$0.098 \\\\\nN-gram PPL & Generative & 0.73 & 0.069 & 17.823{\\tiny$\\pm$.003} & $+$0.129 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Detector comparison for adaptive reweighting ($\\rho{=}0.4$, $\\tau{=}0.8$, 3 seeds).\nUniform baseline PPL\\,=\\,17.694.\n$\\Delta$ = Adaptive $-$ Uniform (negative is better).\nTF-IDF+LR calibrated via temperature scaling.\nThe $\\tau$ confound is conservative: TF-IDF+LR at $\\tau{=}0.7$ achieves 17.674 (Table~\\ref{tab:main}).}\n\\label{tab:detector}\n\\end{table}\n\n\\section{Detector and Synthetic Data Details}\n\\label{app:detector_details}\n\n\\paragraph{TF-IDF+LR detector.}\nTF-IDF features (unigrams + bigrams, max 50{,}000 features, sublinear TF) fed to Logistic Regression (C\\,=\\,1.0, L2 penalty, solver\\,=\\,lbfgs, max\\_iter\\,=\\,100).\nTrained on a held-out labeled split (10K documents per class).\nPost-hoc temperature scaling applied when uncalibrated ECE exceeds 0.05: a scalar $T$ is searched via \\texttt{scipy.optimize.minimize\\_scalar} over $[0.1, 10.0]$ on a 20\\% stratified validation split, yielding $T{=}0.204$ (ECE reduced from 0.12 to 0.05).\nThe detector is selected automatically from six configurations as the first satisfying AUC $\\in [0.85, 0.98]$ and mid-range score ratio $\\geq 5\\%$.\n\n\\paragraph{Synthetic data generation.}\nContinuations generated with Qwen3-0.6B (self-generation) using nucleus sampling ($p{=}0.95$, $T{=}0.8$), producing up to 384 tokens per continuation from a 128-token prefix prompt (512 total), targeting ${\\sim}$100M synthetic tokens.\nSource prompts are the first 128 tokens of randomly sampled FineWeb documents, used as prefix continuations.\nInjected at token-level ratio $\\rho$ via uniform random mixing across the training corpus.\n\n\\section{Low Contamination Analysis}\n\\label{app:rho02}\n\nAt $\\rho{=}0.2$, the adaptive method degrades by $+$0.046 PPL relative to uniform (0.26\\% relative, seed\\,42).\nThe detector's mean $q$-score at this contamination level is 0.393 (vs.\\ 0.487 at $\\rho{=}0.4$), indicating that many clean samples receive moderate $q$-scores, blurring the provenance signal.\nThe regime decomposition reveals 13.7\\% clean batches ($\\bstar{=}0$), 60.1\\% $\\aeff$-binding, and 26.3\\% ESS-binding, with mean $\\bstar{=}1.735$ in reweighted batches.\nThe high $\\aeff$-binding rate (60.1\\% vs.\\ ${\\sim}$50\\% at $\\rho{=}0.4$) means the method actively intervenes rather than defaulting to $\\bstar{=}0$, but the unreliable signal causes it to suppress useful training data.\nThis is consistent with the generative detector failures: when $q$-scores do not reliably separate provenance, the minimum intervention framework amplifies the error rather than correcting it.\nThe effective range of the method is $\\rho \\geq 0.4$ with $\\tau \\in [0.7, 0.8]$ (\\S\\ref{sec:sensitivity}); lower $\\tau$ values may extend the range but have not been tested at $\\rho{=}0.2$.\n\n\\section{Cross-Model Transfer}\n\\label{app:cross_model}\n\nTable~\\ref{tab:cross_model} reports a single exploratory run with Llama-3.2-3B as a cross-generator (synthetic data generated by Llama, training on Qwen3-0.6B); this does not establish generality.\nResults are mixed: MMLU improves while HellaSwag slightly degrades, consistent with the pattern observed in Qwen3-1.7B downstream evaluation (\\S\\ref{sec:robustness}).\nPerplexity comparison omitted due to inconsistent evaluation configurations; checkpoints were not retained for re-evaluation.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n\\textbf{Metric} & \\textbf{Uniform} & \\textbf{Adaptive} & $\\boldsymbol{\\Delta}$ \\\\\n\\midrule\nMMLU (5-shot) & 51.85\\% $\\pm$ .41 & 53.42\\% $\\pm$ .41 & $+$1.57pp \\\\\nHellaSwag (10-shot, acc\\_norm) & 73.08\\% $\\pm$ .44 & 72.49\\% $\\pm$ .45 & $-$0.60pp \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Cross-model transfer: Llama-3.2-3B generator, Qwen3-0.6B trainer ($\\rho{=}0.4$, single seed).\nMixed results reflect evaluation-set distribution sensitivity rather than consistent quality differences.}\n\\label{tab:cross_model}\n\\end{table}\n\n\\section{Checkpoint Resume Artifact}\n\\label{app:resume_artifact}\n\nThe checkpoint-resume artifact described here affected early $\\tau{=}0.8$ experiments only.\nAll results in Tables~\\ref{tab:main}--\\ref{tab:epoch_match} use independent from-scratch training ($\\tau{=}0.7$; Table~\\ref{tab:main} Adaptive/Uniform: five seeds, others: three seeds).\n\nThe adaptive model for seed\\,42 in early $\\tau{=}0.8$ runs was trained with a checkpoint-resumed run whose first ${\\sim}$1{,}000 steps used different hyperparameters (learning rate warmup, gradient accumulation configuration) than seeds 123 and 456, which were trained from scratch.\nThe resume artifact inflates the in-distribution effect ($\\Delta{=}{-}0.041$ resume vs.\\ $\\Delta{=}{-}0.005$ from-scratch at $\\tau{=}0.8$) and reverses the out-of-distribution direction:\n\n\\begin{center}\n\\small\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n\\textbf{Domain} & \\textbf{Resume} & \\textbf{From-scratch} & \\textbf{Dir.} \\\\\n\\midrule\nFineWeb (in-dist) & $-$0.041 & $-$0.005 & same \\\\\nOpenWebText (OOD) & $+$0.058 & $-$0.005 & reversed \\\\\nWikipedia (OOD)   & $+$0.137 & $-$0.009 & reversed \\\\\n\\bottomrule\n\\end{tabular}\\\\[2pt]\n{\\scriptsize $\\Delta$ relative to from-scratch uniform (Table~\\ref{tab:tau}). Resume: seed\\,42 original checkpoint. From-scratch: clean replication run.}\n\\end{center}\n\nThe resume model showed apparent distribution matching (OOD degradation), which was the basis for the ``distribution matching'' finding in earlier analyses.\nFrom-scratch retraining eliminates this pattern: all three evaluation domains show small, directionally consistent improvements, providing no evidence of distribution matching.\nThis underscores the importance of controlling for training artifacts when interpreting small effect sizes across evaluation domains.\n\n\\section{Additional Contamination Rate}\n\\label{app:rho03}\n\nTo probe the boundary between the degradation regime ($\\rho{=}0.2$, $\\Delta{=}{+}0.046$) and the improvement regime ($\\rho{=}0.4$, $\\Delta{=}{-}0.023$), we run adaptive $\\bstar$ and uniform baselines at $\\rho{=}0.3$ using the same experimental setup as the main experiments (Qwen3-0.6B, 132M FineWeb tokens, $\\tau{=}0.7$, $\\nmin{=}2$).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n\\textbf{Method} & \\textbf{Seed} & \\textbf{FineWeb} $\\downarrow$ & \\textbf{OWT} $\\downarrow$ & \\textbf{Wiki} $\\downarrow$ \\\\\n\\midrule\nUniform          & 42  & 17.422 & 18.113 & 15.204 \\\\\nAdaptive $\\bstar$ & 42  & 17.422 & 18.123 & 15.172 \\\\\n\\midrule\nUniform          & 123 & 17.433 & 18.126 & 15.204 \\\\\nAdaptive $\\bstar$ & 123 & 17.435 & 18.148 & 15.165 \\\\\n\\midrule\nUniform          & 456 & 17.419 & -- & -- \\\\\nAdaptive $\\bstar$ & 456 & 17.424 & -- & -- \\\\\n\\midrule\n$\\Delta$ (3-seed mean) & --  & $+$0.002 & -- & -- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Results at $\\rho{=}0.3$ (Qwen3-0.6B, 3 seeds).\nHoldout $\\Delta{=}{+}0.002$ ($t(2){=}1.60$, $p{=}0.25$, non-significant); OOD available for seeds 42 and 123 only, mixed in direction.}\n\\label{tab:rho03}\n\\end{table}\n\nThe holdout difference is effectively zero ($\\Delta{=}{+}0.002$, $t(2){=}1.60$, $p{=}0.25$, non-significant), placing the transition boundary between the degradation regime ($\\rho{=}0.2$, $\\Delta{=}{+}0.046$) and the improvement regime ($\\rho{=}0.4$, $\\Delta{=}{-}0.023$) within $[0.3, 0.4]$ (Figure~\\ref{fig:delta_vs_rho}).\n\nAt $\\rho{=}0.3$, 28\\% of micro-batches have $\\bstar{=}0$ (clean, no intervention), compared to ${\\sim}$6\\% at $\\rho{=}0.4$; the low intervention frequency explains why the method neither helps nor harms.\nThe progression across contamination levels ($\\rho{=}0.2$ harmful, $+$0.046; $\\rho{=}0.3$ neutral, $+$0.002; $\\rho{=}0.4$ beneficial, $-$0.023) shows a graceful transition rather than abrupt failure, consistent with the detector's signal-to-noise ratio gradually crossing the threshold needed for reliable $\\aeff$ estimation.\n\n\\section{Statistical Power Analysis}\n\\label{app:power}\n\nThe adaptive-vs-uniform comparison at $\\rho{=}0.4$ has Cohen's $d = \\bar{\\Delta}/\\mathrm{SD}_{\\Delta} = 0.023/0.006 = 3.83$ (5 seeds, paired).\nA one-sided paired $t$-test at $\\alpha{=}0.05$ with $d{=}3.83$ and $N{=}5$ achieves statistical power ${>}0.99$ (noncentrality $\\lambda = d\\sqrt{N} = 8.56$, $t_{0.05,4} = 2.13$), indicating that $N{=}5$ is more than adequate to detect an effect of this magnitude.\n\nThe low cross-seed variance ($\\sigma{=}0.006$) reflects the experimental design: seeds affect only parameter initialization, not data order (the dataloader is deterministic), so the primary stochastic axis is initialization noise at 0.6B scale.\nThe uniform baseline exhibits comparable variance ($\\sigma{=}0.008$); the low dispersion is a property of the experimental setting rather than a method artifact.\n\nWe apply Bonferroni--Holm correction for $k{=}9$ family-wise comparisons (six reweighting methods $\\times$ one contamination level, plus three additional $\\rho$ levels).\nAfter correction, $p_{\\mathrm{BH}}{=}0.011$ at $\\rho{=}0.4$, reaching conventional significance at $\\alpha{=}0.05$.\nAt $\\rho{=}0.6$ (3 seeds), $p_{\\mathrm{BH}}{=}0.064$; the family includes structurally heterogeneous tests (different methods, different $\\rho$), which makes Bonferroni--Holm conservative.\nThe uncorrected $p$-values ($0.0012$ and $0.010$ respectively), directional consistency across all seeds, and the dose-response pattern across $\\rho$ levels collectively support a real effect.\n\n\\section{Supplementary Analyses Summary}\n\\label{app:summary}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lll@{}}\n\\toprule\n\\textbf{Analysis} & \\textbf{Key result} & \\textbf{App.} \\\\\n\\midrule\nDownstream tasks & No gain (5 benchmarks, $|\\Delta|\\leq 0.01$) & \\ref{app:downstream} \\\\\nCross-model (Llama) & Mixed (MMLU $+$1.6, HellaSwag $-$0.6) & \\ref{app:cross_model} \\\\\n$\\tau$ sweep & $[0.5,0.8]$ all improve; $\\tau{>}0.8$ degrades & \\ref{app:tau_sweep} \\\\\n$\\rho{=}0.3$ boundary & $\\Delta{=}{+}0.002$ (neutral, 3 seeds) & \\ref{app:rho03} \\\\\nStatistical power & Cohen's $d{=}3.83$, power ${>}0.99$ at $N{=}5$ & \\ref{app:power} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Summary of supplementary analyses.}\n\\label{tab:appendix_summary}\n\\end{table}\n\n\\section{Use of AI Assistants}\n\\label{app:ai-assistants}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant\nthroughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing\n    pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections,\n    polishing prose, and reformatting \\LaTeX{}.\n    \\item \\textbf{Literature:} summarizing related papers to inform\n    the related-work section.\n\\end{itemize}\n\n",
    "structuredPatch": [
      {
        "oldStart": 394,
        "oldLines": 7,
        "newStart": 394,
        "newLines": 7,
        "lines": [
          " \\textbf{Metric} & \\textbf{Uniform} & \\textbf{Adaptive} & $\\boldsymbol{\\Delta}$ \\\\",
          " \\midrule",
          " MMLU (5-shot) & 51.85\\% $\\pm$ .41 & 53.42\\% $\\pm$ .41 & $+$1.57pp \\\\",
          "-HellaSwag (10-shot, acc\\_norm) & 73.08\\% $\\pm$ .44 & 72.49\\% $\\pm$ .45 & $-$0.60pp \\\\",
          "+HellaSwag (10-shot, acc\\_norm) & 73.08\\% $\\pm$ .44 & 72.49\\% $\\pm$ .45 & $-$0.59pp \\\\",
          " \\bottomrule",
          " \\end{tabular}}",
          " \\caption{Cross-model transfer: Llama-3.2-3B generator, Qwen3-0.6B trainer ($\\rho{=}0.4$, single seed)."
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

_source line 72_

<details><summary>Logged reasoning block</summary>

```text
Excellent! The registry agent has returned with comprehensive data. Let me now cross-reference the registry data against the appendix numbers.

Key findings from registry:

### Critical Issue #1: Detector table vs τ sweep (CONFIRMED)
Registry shows the `adaptive_seed42` (τ=0.8) has holdout PPL = 17.644. And `adaptive_seed123` = 17.6308, `adaptive_seed456` = 17.6419. These are the original τ=0.8 runs with n_min=3.

The `adaptive_fix` series (τ=0.8, n_min=2): seed42=17.6527, seed123=17.6432, seed456=17.6566.


The τ=0.7 from-scratch runs show slightly higher perplexity: seed42=17.68, seed123=17.666, seed456=17.677. But the detector table reports TF-IDF at τ=0.8 as 17.650±.010, while the tau sweep table lists τ=0.80 from-scratch at 17.683±.006. Computing the mean of the original adaptive runs at τ=0.8 with n_min=3 gives approximately 17.638, which sits between these reported values.

However, when I calculate the adaptive_fix series with τ=0.8 and n_min=2, the mean comes to about 17.651—that matches the detector table's 17.650 almost exactly. So the detector table is pulling from the adaptive_fix runs, not the τ sweep. The τ=0.80 value of 17.683 from the tau table appears to be from a different experimental setup, likely the from-scratch tau sweep runs, though I need to verify which specific experiments produced that result.

Looking at the registry more carefully, I can see tau07_seed42 gives 17.68, which aligns with the paper's τ=0.7 result. But for τ=0.8, I'm trying to trace whether the 17.683 comes from tau08 experiments or if there are other from-scratch runs not clearly labeled in the registry.

The resume artifact section clarifies things though—it notes a -0.005 difference for from-scratch FineWeb at seed 42, which means the from-scratch adaptive at τ=0.8 should be 17.689, matching what the hybrid table shows for that configuration.

But when I work backward from the 3-seed mean of 17.683 in the paper, the other two seeds average to 17.680, while the `adaptive_fix` series shows 17.650 for those same seeds. That's a meaningful gap, suggesting the `adaptive_fix` experiments might be using different hyperparameters like n_min=2 instead of n_min=3, or some other training variation. Looking at the individual seed results from the registry, I can compute the mean and standard deviation directly: the three adaptive_fix runs average to 17.6508, which matches the table's 17.650, but when I calculate the standard deviation from those same seeds, I get roughly 0.007, which is smaller than the reported ±.010—there's a slight discrepancy in the uncertainty estimate.

The τ sweep table reports 17.683 for τ=0.8, which appears to come from a separate set of from-scratch runs that aren't obviously labeled in the registry, possibly stored under different experiment IDs or added after the registry was last updated. This reveals the core problem: the detector table and τ sweep table are reporting different PPL values (17.650 vs 17.683, a difference of 0.033) for what should be identical experimental conditions, and I'm flagging this as the primary inconsistency.

Now I'm noticing a second critical issue—the registry shows n_min=3 as the default for the original experiments, but the paper consistently states n_min=2 throughout (in the τ sweep caption, ρ sweep caption, and experiments.tex). If the original runs actually used n_min=3 while the paper claims n_min=2, that's a significant discrepancy that could affect the validity of the reported results.

Looking at the actual numbers, the main results table appears to be using the τ=0.7, n_min=2 runs (tau07_seed*) rather than the original adaptive_seed* runs with τ=0.8 and n_min=3, which explains why the registry values don't match the published numbers. The 2dp rounding doesn't match either—17.2853 rounds to 17.29, not 17.28. I'm wondering if the threshold table might be using the 3-seed mean instead, which would be around 17.278, closer to what's shown.

Looking at the other entries in the table, I notice q>0.3 has a footnote explicitly marking it as the 3-seed mean, but q>0.5 doesn't have that notation even though it appears to also be the 3-seed mean. The caption says "seed 42 unless noted," which creates an inconsistency if q>0.5 is actually derived from multiple seeds without being marked.

Now I'm cross-checking the grid_full results against the registry to verify the seed 42 values with ρ=0.4. Generating metrics table...

Let me recalculate using the more precise mean of 17.6197 to see if that closes the gap with the paper's reported standard deviation. The deviations work out slightly differently, giving me 0.0351 instead of the paper's 0.033—still a small discrepancy. I'm wondering if the _r2 suffix on these registry entries indicates re-runs, and whether there might be earlier versions with different values that could explain the variance.

Now I'm cross-checking the rho06 results across different methods and seeds against what the paper reports. Looking at the Grid b=0.3 and Adaptive methods with seeds 42, 123, and 456, everything matches perfectly between the paper and registry values.

The Uniform sampling method also shows perfect alignment across all three seeds. For the ESS-only approach, most values match exactly, though seeds 123 and 456 show minor rounding differences (17.760 vs 17.763, and 17.760 vs 17.762) that are negligible. The Random method rounds cleanly across all seeds, with the registry values matching the paper's reported numbers.

Now I'm checking whether the paper's mean calculation is consistent with its reported values. If I use the registry values for ESS-only (17.770, 17.763, 17.762), the mean would be 17.765, not the 17.763 shown in the paper. But when I use the paper's own rounded values (17.770, 17.760, 17.760), the mean comes out to exactly 17.763, which matches. So the paper appears to have rounded the individual seed results before computing the mean, which introduces a slight discrepancy between what the registry values would produce and what the paper reports. The registry values give a slightly different mean of 17.765 and a lower standard deviation around 0.004, which would change the reported statistics compared to what the paper shows.

However, the difference is minimal—just 0.002 between 17.765 and 17.763—so the paper's claim that ESS-only approximates Uniform still holds roughly. The registry might contain different experimental runs than the paper used, especially given the _r2 suffixes indicating re-runs, so I shouldn't read too much into the discrepancies.

Now I'm cross-checking the D&R threshold table against both the paper values and registry entries to see where they align. Now I'm noticing a discrepancy in how the results are reported—the paper shows 17.28 for q>0.5, but the registry values don't match that when using seed 42 alone. The 3-seed mean for v2 does round to 17.28, which suggests the paper might be using averaged results despite the caption implying single-seed results. There's a labeling inconsistency here that needs clarification. I'm checking which D&R thresholds actually use 3-seed data: q>0.3 and q>0.7 are clearly marked with footnotes, but q>0.5's value of 17.28 is also a 3-seed mean (averaging around 17.278), not the single seed 42 value of 17.285, so it should have a footnote too. Generating comparison tables... I'm wondering if there's another version of the hybrid experiment I'm missing, but the registry only shows one hybrid rho06 entry, so this 0.004 PPL difference between paper and registry is real and worth flagging. Now I'm cross-checking the rho03 results, looking at uniform and adaptive methods across different seeds and datasets to see if those match up. I'm noticing a discrepancy—seeds 234 and 789 appear in the registry but only with τ=0.8 settings, not the τ=0.7 used in the main table. The main table claims a 5-seed mean of 17.674 for adaptive at τ=0.7, but I can only verify three seeds (42, 123, 456). I need to figure out where the τ=0.7 results for seeds 234 and 789 are, or if the mean calculation is based on different seeds than expected. The naming convention might have shifted, so seeds 234 and 789 could actually be τ=0.7 runs even though they're not explicitly labeled that way—the small difference between τ=0.7 and τ=0.8 makes them plausible either way. Now I'm noticing a major discrepancy in the detector configuration: the registry shows TF-IDF with 10,000 max features and C=0.01, but the paper specifies 50,000 features and C=1.0—that's a substantial gap I need to reconcile.

The final metrics align perfectly though (AUC 0.939 vs 0.94, ECE 0.048, temperature 0.204), which suggests the registry might be documenting an earlier iteration of the detector while the paper describes the final tuned version, or the registry specs were extracted incompletely. to match almost exactly, which suggests the registry entry does correspond to the actual downstream task run. The slight differences in ARC-E, HellaSwag, and WinoGrande scores are within rounding error, so this one checks out as verifiable.

But now I'm noticing there's also a τ=0.7 variant in the registry with its own downstream scores that are similarly close to the paper's reported numbers, which means I need to track which threshold version corresponds to which reported result. I'm noticing a major discrepancy in the ARC-E scores between the registry and paper values—0.6128 versus 0.657 is far too large to be rounding error. Since the uniform baseline doesn't depend on τ, these scores should match regardless of which τ setting the paper lists them under, which suggests either different experimental runs or a data mismatch I need to investigate further. I'm going through each claim systematically to see what I can actually verify against the registry data. Most of the grid search and parameter-specific values check out, though there are some inconsistencies—the hybrid model results are slightly off, the detector comparison doesn't align with the τ sweep findings, and several downstream evaluation metrics appear to come from a different evaluation pipeline than what's stored in the registry. The cross-model results have gaps too, with some MMLU and HellaSwag scores missing entirely and an arithmetic discrepancy in the delta calculations. I'll focus on flagging what's verifiable versus what remains unconfirmed due to these mismatches in evaluation versions and configurations.

Now I'm compiling the final report with targeted fixes: correcting the HellaSwag delta and ECE rounding, then flagging the detector table inconsistency, the hybrid discrepancy, the ESS-only rounding issue, and the D&R labeling question rather than changing them outright since these involve either minor numerical differences or unclear averaging methods. I'm not certain of the correct values.

Actually, let me reconsider which of these I should fix:

Fix 3 (detector table): This is the most significant issue. The detector table TF-IDF PPL should match either the τ sweep or be a separate, clearly documented experiment. I should NOT change this without knowing which source is canonical. Flag only.

Fix 4 (hybrid ρ=0.6): 17.530 vs 17.526. The registry clearly shows 17.526. I should change the paper to 17.526 unless there's another run. But given the * footnote and the context, I'm not 100% sure. Let me check: 17.526 rounds to 17.53 at 2dp. The paper shows 17.530 at 3dp. If the actual value is 17.526, the paper should say 17.526. I'll flag rather than fix without being certain there isn't a different version of this run.

Fix 5 (ESS-only): Paper shows 17.760 for seeds 123 and 456, registry shows 17.763 and 17.762. This affects the mean (17.763 vs 17.765). I'll flag but not fix, as the registry values might be from different runs.

Fix 6 (D&R q>0.5 labeling): The table shows 17.28 which matches the 3-seed mean (17.278 ≈ 17.28) but the caption says "seed 42 unless noted." I'm uncertain whether this is actually the 3-seed mean or if it should have a footnote clarifying this.

Now let me finalize my fixes: I'll correct the HellaSwag Δ from -0.60 to -0.59 and the ECE description from 0.05 to 0.048. For the remaining issues—the detector table discrepancy, the hybrid ρ=0.6 value, the ESS-only per-seed values, and the D&R q>0.5 labeling—I'll flag these for further investigation rather than making changes without certainty.

The rounding in results.tex checks out (1.57 rounds to 1.6, 0.59 rounds to 0.6), so the appendix table correction I've already made is the key fix. Let me verify the ρ=0.2 Δ value: the registry shows 17.382 minus 17.336 equals +0.046, which matches the reference and paper. The appendix correctly notes this is at τ=0.8 for the adaptive case.

Now I'm noticing a major discrepancy in the regime decomposition—the appendix reports 13.7% clean batches while the registry shows 40-50% for b*=0, which seems contradictory. I need to reread the appendix carefully to understand what conditions these statistics are actually describing. decomposition at b*=0 shows 13.7%, which is much lower than the registry's 40-50% for τ=0.8—so the appendix must be describing a τ=0.7 run instead. But when I cross-check the delta values, the appendix's +0.046 matches the τ=0.8 registry entry, not τ=0.7, which creates a contradiction about which threshold was actually used. I'm realizing the threshold logic works the opposite way—at τ=0.7, more batches should pass the lower threshold and be marked clean, so the 13.7% figure only makes sense if τ is actually higher than 0.8, not lower.

Looking at the detector's performance at ρ=0.2, the mean q-score is around 0.393, which means α_eff(0) ≈ 0.61 for most batches. This would make most batches exceed a τ=0.7 threshold, contradicting the 13.7% clean rate unless the threshold is significantly higher.

But wait—if α_eff(0) is typically 0.61 and τ=0.7, then only batches where α_eff(0) ≥ 0.7 get b*=0, which would indeed be rare. That actually explains the 13.7% figure. The detector's moderate q-scores on real samples suppress the effective alpha, making it hard to reach the threshold even with low contamination.

The inconsistency is that τ=0.8 should be even stricter, yet the registry shows 40-50% clean batches there—which doesn't align with having only 13.7% at the lower τ=0.7 threshold.

I think the registry value might be an estimate from the notes rather than a precise metric, or it's from a different experimental setup. I'll flag this discrepancy but move forward with finalizing the report. Now I need to verify the training hyperparameters, particularly the warmup schedule.

The reference mentions specific warmup and weight decay values, but the registry shows these as "NOT FOUND". The paper describes a linear warmup schedule but doesn't specify the number of steps, and weight decay isn't mentioned anywhere in the appendix or experiments section. These details might exist in the code but aren't documented in the paper itself, so I can't verify them against the provided materials.

Now I'm tallying up all the numbers I've audited across the tables—the grid results, the tau sweep comparisons, the hybrid configurations, the threshold analysis, and the downstream tasks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "39d4555a-79ba-4de2-abe0-caebdca3599c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VKmWBopM6dtqYQ41azagc4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 40833,
      "cache_read_input_tokens": 49492,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 40833
      },
      "output_tokens": 29,
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

_source line 73_

Registry agent 完成了。现在做 ECE 精度修复。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "4c1ad7a5-58f2-42f5-a660-a10269bf4f71",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VKmWBopM6dtqYQ41azagc4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 40833,
      "cache_read_input_tokens": 49492,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 40833
      },
      "output_tokens": 29,
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

_source line 74_

<details open><summary>🔧 Tool call — Edit · `toolu_01CpdWqF2J2XtEFUQFtyTstP`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/appendix.tex",
  "old_string": "yielding $T{=}0.204$ (ECE reduced from 0.12 to 0.05).",
  "new_string": "yielding $T{=}0.204$ (ECE reduced from 0.12 to 0.048)."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "18a7ac93-c47c-4f02-9716-3630b796c95d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VKmWBopM6dtqYQ41azagc4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 40833,
      "cache_read_input_tokens": 49492,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 40833
      },
      "output_tokens": 29,
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

_source line 75 · 2026-05-25T20:20:19.417Z_

<details><summary>↩ Tool result · `toolu_01CpdWqF2J2XtEFUQFtyTstP`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "e0b742ff-04a7-4879-9805-7a7675a546f2",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/appendix.tex",
    "oldString": "yielding $T{=}0.204$ (ECE reduced from 0.12 to 0.05).",
    "newString": "yielding $T{=}0.204$ (ECE reduced from 0.12 to 0.048).",
    "originalFile": "\\section{Proofs}\n\\label{app:proofs}\n\n\\begin{proposition}[$\\alpha_{\\mathrm{eff}}$ monotonicity]\n\\label{prop:monotone}\n$\\alpha_{\\mathrm{eff}}(b)$ is non-decreasing in $b$, and strictly increasing whenever the batch contains at least two samples with distinct $q$-values.\n\\end{proposition}\n\n\\begin{proof}[Proof of Proposition~\\ref{prop:monotone}]\nLet $w_i(b) = (1 - q_i)^b$, $W(b) = \\sum_{j=1}^B w_j(b)$, and $\\pi_i(b) = w_i(b) / W(b)$.\nThen\n\\begin{equation*}\n  \\alpha_{\\mathrm{eff}}(b) = \\sum_{i=1}^{B} \\pi_i(b)\\, (1 - q_i).\n\\end{equation*}\nTaking the derivative with respect to $b$:\n\\begin{align*}\n  \\frac{d\\pi_i}{db}\n  &= \\pi_i \\!\\left(\\frac{d \\ln w_i}{db} - \\frac{d \\ln W}{db}\\right) \\\\\n  &= \\pi_i \\!\\left(\\ln(1{-}q_i) - \\textstyle\\sum_j \\pi_j \\ln(1{-}q_j)\\right).\n\\end{align*}\nSubstituting,\n\\begin{align*}\n  \\frac{d\\alpha_{\\mathrm{eff}}}{db}\n  &= \\sum_i (1{-}q_i)\\, \\pi_i \\!\\left(\\ln(1{-}q_i) - \\mathbb{E}_{\\pi}[\\ln(1{-}q)]\\right) \\\\\n  &= \\mathrm{Cov}_{\\pi}\\!\\bigl(1{-}q_i,\\, \\ln(1{-}q_i)\\bigr).\n\\end{align*}\nSince $(1{-}q_i)$ and $\\ln(1{-}q_i)$ are both increasing functions of $(1{-}q_i)$, they are positively associated, so the covariance is non-negative.\n\\end{proof}\n\n\\begin{proposition}[ESS monotonicity]\n\\label{prop:ess_mono}\n$\\mathrm{ESS}(b)$ is non-increasing in $b$, and strictly decreasing whenever the batch contains at least two samples with distinct $q$-values.\n\\end{proposition}\n\n\\begin{proof}\nWrite $\\mathrm{ESS}(b) = 1 / \\sum_i \\pi_i(b)^2$, where $\\pi_i(b) = w_i(b) / W(b)$.\nThe denominator $\\sum_i \\pi_i^2$ is the Herfindahl index $H$.\nDifferentiating $H$ with respect to $b$:\n\\begin{equation*}\n  \\frac{dH}{db} = 2 \\sum_i \\pi_i^2 \\bigl(\\ln(1{-}q_i) - \\mathbb{E}_{\\pi}[\\ln(1{-}q)]\\bigr).\n\\end{equation*}\nSince $\\pi_i \\propto (1{-}q_i)^b$, larger $\\pi_i$ implies larger $\\ln(1{-}q_i)$; the $\\pi^2$-weighted sum assigns greater mass to terms where $\\ln(1{-}q_i) > \\mathbb{E}_\\pi[\\ln(1{-}q)]$, so $dH/db \\geq 0$, with strict inequality when at least two $q$-values differ.\nThus $H$ is non-decreasing and $\\mathrm{ESS} = 1/H$ is non-increasing.\nThis is a standard property of exponential tilting~\\citep{kish1965survey,owen2013mc}.\n\\end{proof}\n\n\\section{Algorithm Details}\n\\label{app:algorithm}\n\n\\begin{algorithm}[h]\n\\caption{Per-batch adaptive $b^{*}$ selection}\n\\label{alg:bstar}\n\\begin{algorithmic}[1]\n\\REQUIRE Batch scores $\\{q_i\\}_{i=1}^{B}$, threshold~$\\tau$, ESS floor~$n_{\\min}$, bound~$b_{\\max}$, tol.~$\\varepsilon$\n\\ENSURE Optimal sharpening exponent $b^{*}$\n\\IF{$\\alpha_{\\mathrm{eff}}(0) \\geq \\tau$}\n  \\STATE \\textbf{return} $0$ \\COMMENT{clean batch}\n\\ENDIF\n\\STATE $b_\\tau \\gets \\textsc{Bisect}(\\alpha_{\\mathrm{eff}}(\\cdot){=}\\tau,\\; [0, b_{\\max}],\\; \\varepsilon)$\n\\IF{$\\mathrm{ESS}(b_\\tau) \\geq n_{\\min}$}\n  \\STATE \\textbf{return} $b_\\tau$ \\COMMENT{$\\alpha_{\\mathrm{eff}}$-binding}\n\\ELSE\n  \\STATE $b_{\\mathrm{ESS}} \\gets \\textsc{Bisect}(\\mathrm{ESS}(\\cdot){=}n_{\\min},\\; [0, b_{\\max}],\\; \\varepsilon)$\n  \\STATE \\textbf{return} $b_{\\mathrm{ESS}}$ \\COMMENT{ESS-binding}\n\\ENDIF\n\\end{algorithmic}\n\\end{algorithm}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{bstar_trajectory_adaptive_fix}\n\\caption{Adaptive $\\bstar$ trajectory over 6{,}103 training steps (seed\\,42, $\\rho{=}0.4$).\nThe exponent alternates between clean ($\\bstar{=}0$), $\\aeff$-binding, and ESS-binding regimes with no systematic drift, reflecting per-batch adaptation to local $q$-score composition.}\n\\label{fig:bstar_traj}\n\\end{figure}\nWe compute $\\bstar$ at the micro-batch level ($B{=}4$) rather than the effective batch ($B{=}16$ after gradient accumulation) because $q$-score statistics exhibit sufficient variance within micro-batches: Spearman $r{=}0.699$ with the true real fraction, and at $B{=}16$ the adaptive advantage amplifies $3.0{\\times}$ ($\\Delta{=}{-}0.068{\\pm}0.005$; \\S\\ref{sec:sensitivity}).\n\n\\section{Grid Search Details}\n\\label{app:grid}\n\nTable~\\ref{tab:grid_full} reports held-out PPL for all grid-$b$ values at $\\rho = 0.4$ (seed\\,42).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}cc@{}}\n\\toprule\n$b$ & PPL $\\downarrow$ \\\\\n\\midrule\n0.1 & 17.657 \\\\\n0.2 & 17.640 \\\\\n0.3 & \\textbf{17.640} \\\\\n0.5 & 17.651 \\\\\n1.0 & 17.692 \\\\\n1.5 & 17.718 \\\\\n2.0 & 17.741 \\\\\n3.0 & 17.774 \\\\\n5.0 & 17.818 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Full grid search results ($\\rho{=}0.4$, seed\\,42).\n$b \\in [0.1, 0.5]$ forms a broad plateau (three-seed mean for $b{=}0.1$: $17.655 \\pm 0.009$); $b{=}0.3$ is the post-hoc best.}\n\\label{tab:grid_full}\n\\end{table}\n\n\\section{Quality Threshold Sweep}\n\\label{app:tau_sweep}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}ccccccc@{}}\n\\toprule\n$\\tau$ & Holdout $\\downarrow$ & $\\Delta_{\\text{H}}$ & OWT $\\downarrow$ & $\\Delta_{\\text{O}}$ & Wiki $\\downarrow$ & $\\Delta_{\\text{W}}$ \\\\\n\\midrule\n0.50 & 17.688 & $-$0.006 & -- & -- & -- & -- \\\\\n0.60 & 17.681 & $-$0.013 & -- & -- & -- & -- \\\\\n0.70$^\\star$ & \\textbf{17.674{\\tiny$\\pm$.006}} & $\\boldsymbol{-}$\\textbf{0.020} & \\textbf{18.347{\\tiny$\\pm$.003}} & $\\boldsymbol{-}$\\textbf{0.028} & \\textbf{15.330{\\tiny$\\pm$.015}} & $\\boldsymbol{-}$\\textbf{0.029} \\\\\n0.80$^\\star$ & 17.683{\\tiny$\\pm$.006} & $-$0.011 & 18.370{\\tiny$\\pm$.005} & $-$0.005 & 15.350 & $-$0.009 \\\\\n0.90 & 17.712 & $+$0.018 & -- & -- & -- & -- \\\\\n0.95 & 17.723 & $+$0.029 & -- & -- & -- & -- \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Quality threshold sweep ($\\nmin{=}2$, $\\rho{=}0.4$).\n$\\Delta$ relative to 3-seed uniform baseline (Holdout 17.694, OWT 18.375, Wiki 15.359).\n$^\\star$\\,$\\tau{=}0.7$: 5-seed mean (SD from 5 seeds); $\\tau{=}0.8$: 3 from-scratch seeds (Appendix~\\ref{app:resume_artifact}). The 5-seed comparison in Table~\\ref{tab:main} yields $\\Delta{=}{-}0.023$.\nOther values from single-seed exploratory sweep (seed\\,42, holdout only).\n$\\tau{=}0.7$ achieves the lowest holdout and largest OOD gains ($|\\Delta| \\geq 0.028$); $\\tau{=}0.8$'s OOD effect is smaller ($|\\Delta| \\leq 0.009$).}\n\\label{tab:tau}\n\\end{table}\n\n\\section{Batch-Adaptive $\\tau$}\n\\label{app:batch_adaptive}\n\nWe tested a per-batch adaptive variant that clamps $\\tau$ between 0.5 and the fixed threshold based on local $\\aeff(0)$, allowing the quality floor to relax in batches with low estimated real fraction.\nAt both contamination levels ($\\rho \\in \\{0.4, 0.6\\}$), the adaptive variant did not outperform the fixed threshold (single-seed exploratory at each level), suggesting the quality constraint does not require adaptation to local contamination density.\nThis supports the ``two hyperparameters with good defaults'' characterization: neither $\\tau$ nor $\\nmin$ benefits from per-batch tuning.\n\n\\section{\\texorpdfstring{$\\tau$--$\\rho$}{tau-rho} Rank Preservation}\n\\label{app:tau_rho}\n\nFigure~\\ref{fig:tau_rho_rank} shows the $\\tau$--PPL relationship at two contamination levels.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{tau_rho_rank_preservation}\n\\caption{(a) Held-out PPL as a function of quality threshold $\\tau$ at $\\rho \\in \\{0.4, 0.6\\}$.\n$\\tau{=}0.7$ and $\\tau{=}0.8$ yield comparable holdout PPL at $\\rho{=}0.4$; at $\\rho{=}0.6$, $\\tau{=}0.7$ is statistically better (paired $t{=}{-}4.70$, $p{<}0.05$, 3 seeds, $\\Delta{=}{-}0.005$). $\\tau{=}0.7$ also achieves lower OOD perplexity at both levels ($\\rho{=}0.6$: $\\Delta_{\\text{OWT}}{=}{-}0.014$, $\\Delta_{\\text{Wiki}}{=}{-}0.013$, 2 seeds).\n(b) Normalized PPL gap relative to uniform at shared $\\tau$ values.}\n\\label{fig:tau_rho_rank}\n\\end{figure}\n\n\\section{Hybrid and Threshold Comparison}\n\\label{app:hybrid}\n\nTable~\\ref{tab:hybrid} compares method families across contamination levels.\nTable~\\ref{tab:dr_threshold} shows D\\&R sensitivity to the detection threshold at both full training length and epoch-matched settings.\nRaw PPL traces a U-shaped curve with a minimum at $q{>}0.3$ (17.250, 3 seeds), but this curve conflates filtering quality with multi-epoch exposure: aggressive thresholds retain less data and repeat it more often.\nEpoch-matched comparisons (rightmost column of Table~\\ref{tab:dr_threshold}) remove the multi-epoch confound: the U-shape vanishes and PPL decreases monotonically, saturating near the adaptive $\\bstar$ level at $q{\\geq}0.5$.\nFigure~\\ref{fig:dr_dual_curve} visualizes the two curves.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\n\\textbf{Method} & $\\rho{=}0.4$ & $\\rho{=}0.6$ \\\\\n\\midrule\nUniform & 17.694 & 17.766 \\\\\nAdaptive $\\bstar$ & 17.689 & 17.740 \\\\\nHybrid ($q{>}0.95$ + adaptive) & 17.514 & 17.530$^*$ \\\\\nDetect \\& Remove ($q{>}0.5$) & 17.285 & -- \\\\\nDetect \\& Remove ($q{>}0.3$) & 17.250 & -- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Method comparison across contamination levels (seed\\,42, $\\tau{=}0.8$).\n$^*$Hybrid at $\\rho{=}0.6$ filters high-confidence synthetic ($q{>}0.95$), reducing effective $\\rho$ to ${\\approx}0.4$; PPL is not directly comparable to $\\rho{=}0.6$ baselines.}\n\\label{tab:hybrid}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{@{}ccccc@{}}\n\\toprule\n\\textbf{Thresh.} & \\textbf{Ret.\\ \\%} & \\textbf{Epochs} & \\textbf{Raw PPL} $\\downarrow$ & \\textbf{Ep.-matched} $\\downarrow$ \\\\\n\\midrule\n$q > 0.1$ & 15.0\\% & ${\\sim}$10.0 & 17.40 & 18.04 \\\\\n$q > 0.2$ & ${\\sim}$23\\% & ${\\sim}$5.0 & 17.27 & -- \\\\\n$q > 0.3$ & 31.5\\% & ${\\sim}$3.2 & \\textbf{17.250}$^\\dagger$ & 17.74 \\\\\n$q > 0.4$ & ${\\sim}$38\\% & ${\\sim}$2.8 & 17.26 & -- \\\\\n$q > 0.5$ & 41.4\\% & ${\\sim}$2.4 & 17.28 & 17.65 \\\\\n$q > 0.6$ & ${\\sim}$46\\% & ${\\sim}$1.7 & 17.30 & -- \\\\\n$q > 0.7$ & 49.8\\% & ${\\sim}$2.0 & 17.32 & 17.62 \\\\\n$q > 0.8$ & ${\\sim}$56\\% & ${\\sim}$1.3 & 17.34 & -- \\\\\n$q > 0.9$ & 61.6\\% & ${\\sim}$1.1 & 17.42 & 17.628 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{D\\&R threshold sensitivity ($\\rho{=}0.4$, seed\\,42 unless noted).\nRaw PPL traces a U-shaped curve (minimum at $q{>}0.3$); epoch-matched PPL (single content epoch) decreases monotonically and saturates near the adaptive $\\bstar$ level (${\\approx}$17.65) at $q{\\geq}0.5$; the U-shape is thus a multi-epoch artifact.\n$^\\dagger$\\,3-seed mean $17.250 \\pm 0.001$.}\n\\label{tab:dr_threshold}\n\\end{table}\n\nSee Figure~\\ref{fig:dr_dual_curve} (\\S\\ref{sec:main-results}) for the dual-curve visualization.\n\n\\section{Downstream Task Evaluation}\n\\label{app:downstream}\n\nTable~\\ref{tab:downstream} reports downstream benchmark accuracy for adaptive vs.\\ uniform training at $\\rho{=}0.4$ (seed\\,42, Qwen3-0.6B).\nAcross multiple seeds, downstream differences are mixed in direction and uniformly within standard error, indicating that adaptive reweighting has no meaningful downstream impact.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llccc@{}}\n\\toprule\n\\textbf{Benchmark} & \\textbf{Metric} & \\textbf{Adaptive} & \\textbf{Uniform} & $\\boldsymbol{\\Delta}$ \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{Seed 42 (checkpoint resume)}} \\\\\nARC-Challenge & acc\\_norm & 0.343 & 0.348 & $-$0.005 \\\\\nARC-Easy & acc & 0.650 & 0.657 & $-$0.007 \\\\\nHellaSwag & acc\\_norm & 0.479 & 0.484 & $-$0.005 \\\\\nPIQA & acc & 0.687 & 0.686 & $+$0.001 \\\\\nWinoGrande & acc & 0.578 & 0.586 & $-$0.008 \\\\\n\\midrule\n\\multicolumn{5}{@{}l}{\\textit{From-scratch 2-seed mean (seeds 123, 456)}} \\\\\n\\multicolumn{3}{@{}l}{Mean $\\Delta$ across 5 tasks} & & $+$0.001 \\\\\n\\multicolumn{3}{@{}l}{Direction} & \\multicolumn{2}{c}{mixed (seed 123: 3/5$-$; seed 456: 3/5$+$)} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Downstream benchmarks (Qwen3-0.6B, $\\rho{=}0.4$).\nSeed\\,42 used a checkpoint-resumed adaptive model; from-scratch seeds (123, 456) show mixed direction with mean $|\\Delta| \\leq 0.01$.\nAll differences within standard error ($\\pm 0.01$).\nModels use $\\tau{=}0.8$; $\\tau{=}0.7$ yields identical 3-seed means (0.5414).}\n\\label{tab:downstream}\n\\end{table}\n\n\\section{Higher Contamination Details}\n\\label{app:rho06}\n\nTable~\\ref{tab:rho06} reports results at $\\rho{=}0.6$.\nThe full five-method ablation preserves the hierarchy from $\\rho{=}0.4$ across all three seeds: Grid ${<}$ Adaptive ${<}$ Uniform ${\\approx}$ ESS-only ${<}$ Random.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n\\textbf{Method} & \\textbf{Seed 42} & \\textbf{Seed 123} & \\textbf{Seed 456} & \\textbf{Mean} \\\\\n\\midrule\nGrid ($b{=}0.3$)$^\\ddagger$ & \\textbf{17.634} & -- & -- & -- \\\\\nAdaptive $\\bstar$ & 17.735 & 17.727 & 17.732 & 17.731 $\\pm$ .004 \\\\\nUniform           & 17.766 & 17.754 & 17.770 & 17.763 $\\pm$ .008 \\\\\nESS-only          & 17.770 & 17.760 & 17.760 & 17.763 $\\pm$ .006 \\\\\nRandom $\\mathcal{U}(0,2)$ & 17.832 & 17.870 & 17.880 & 17.861 $\\pm$ .025 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Results at $\\rho{=}0.6$ (Qwen3-0.6B, $\\nmin{=}2$).\nAdaptive uses $\\tau{=}0.7$ (consistent with main results); other methods are $\\tau$-independent.\n$^\\ddagger$Post-hoc oracle; seed\\,42 only.\nAdaptive vs.\\ Uniform: $\\Delta{=}{-}0.032$, paired $t{=}{-}15.4$, $p{=}0.004$ (full precision; 3dp rounding yields $t{=}{-}9.95$, $p{=}0.010$).\nESS-only collapses onto Uniform (both $17.763$); Random ($17.861$) confirms detector signal is load-bearing.}\n\\label{tab:rho06}\n\\end{table}\n\nThe ESS-only/Uniform gap collapses from 0.043 at $\\rho{=}0.4$ to 0.000 at $\\rho{=}0.6$ (three-seed means: both $17.763$); ESS binding rises to ${\\sim}$49\\% of batches (from ${\\sim}$43\\% at $\\rho{=}0.4$), and the constraints become nearly balanced rather than $\\aeff$-dominant.\nThe adaptive method maintains its advantage ($\\Delta{=}{-}0.032$, consistent across seeds) through the $\\aeff$ quality constraint, which operates independently of the ESS ceiling.\nRandom reweighting ($17.861 \\pm 0.025$) is substantially worse than Uniform, with the highest cross-seed variance; uninformed weights add noise without corrective signal.\nThe Adaptive-vs-Grid gap is 0.054 at $\\rho{=}0.4$ (mean-to-mean, consistent with Table~\\ref{tab:aux}) and 0.097 at $\\rho{=}0.6$ (adaptive 3-seed mean vs.\\ grid seed\\,42; the $\\rho{=}0.6$ grid result is preliminary and may not generalize across seeds).\n\n\\section{\\texorpdfstring{$\\alpha_{\\mathrm{eff}}$}{alpha-eff} Proxy Validation}\n\\label{app:alpha_validation}\n\nTable~\\ref{tab:alpha_corr} reports the correlation between $\\aeff(0)$ (the detector-based proxy at $b{=}0$) and the true batch-level real fraction $\\alpha_{\\mathrm{true}}$, computed over all training batches at $\\rho{=}0.4$ (seed\\,42).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}ccccc@{}}\n\\toprule\n$B$ & Pearson $r$ & Spearman $r$ & MAE$\\downarrow$ & Bias \\\\\n\\midrule\n4  & 0.706 & 0.699 & 0.114 & $-$0.029 \\\\\n8  & 0.697 & 0.683 & 0.097 & $-$0.027 \\\\\n16 & 0.707 & 0.691 & 0.075 & $-$0.031 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Correlation between $\\aeff(0)$ and true batch-level real fraction across batch sizes ($\\rho{=}0.4$, seed\\,42).\nValues use a binarized proxy $\\hat{r}_i = \\mathbf{1}[q_i \\leq 0.5]$ for discrete comparison; the continuous formulation used during training (\\S\\ref{sec:method}) achieves $r \\approx 0.77$--$0.79$ depending on batch size.\nThe consistent negative bias (${\\approx}{-}0.03$) indicates that $\\aeff$ slightly underestimates the true real fraction, biasing the method toward conservative intervention.}\n\\label{tab:alpha_corr}\n\\end{table}\n\nMean absolute error (MAE) decreases with batch size (0.114 $\\to$ 0.075) as expected from averaging, but the rank-order information that drives $\\bstar$ selection is already well-captured at $B{=}4$.\n\n\\paragraph{Cross-seed stability.}\nTable~\\ref{tab:alpha_corr_perseed} reports the correlation between $\\aeff$ and the batch mean $q$-score ($\\bar{q}$, computed from known labels) across all three seeds.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}cccc@{}}\n\\toprule\n\\textbf{Seed} & Pearson $r(\\aeff, \\bar{q})$ & Spearman $\\rho_s$ & $\\bstar{=}0$ (\\%) \\\\\n\\midrule\n42  & 0.8019 & 0.8761 & 5.8 \\\\\n123 & 0.7994 & 0.8692 & 5.7 \\\\\n456 & 0.8006 & 0.8749 & 5.9 \\\\\n\\midrule\n\\textbf{Spread} & 0.0025 & 0.0069 & 0.2 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Per-seed $\\aeff$--$\\bar{q}$ correlation ($\\rho{=}0.4$, $B{=}4$).\nCross-seed spread is $<$0.003 for Pearson $r$ and $<$0.007 for Spearman $\\rho_s$, indicating stable proxy fidelity across random seeds.\n$r(\\aeff, \\bar{q}) = 0.80$ measures the proxy's fidelity to batch composition; the ground-truth correlation $r(\\aeff, \\text{true real fraction}) \\approx 0.79$ (\\S\\ref{sec:discussion}) is slightly lower due to detector noise.\nThe per-seed table demonstrates cross-seed stability rather than superseding the ground-truth estimate.}\n\\label{tab:alpha_corr_perseed}\n\\end{table}\n\n\\section{Detector Comparison}\n\\label{app:detector}\n\nSee Figure~\\ref{fig:overview}b (\\S\\ref{sec:robustness}) for the detector requirements visualization.\n\nTable~\\ref{tab:detector} compares three detector families for adaptive reweighting.\nThe discriminative TF-IDF+LR detector (ECE\\,=\\,0.048) produces the only improvement over uniform.\nThe TF-IDF vs.\\ GPT-2 contrast (comparable AUC: 0.94 vs.\\ 0.91, but $2.7{\\times}$ ECE gap: 0.048 vs.\\ 0.131) isolates calibration as an empirically observed requirement; however, N-gram's better ECE (0.069) does not compensate for its low AUC (0.73); both sufficient discrimination and good calibration are jointly necessary in our setting.\nTF-IDF+LR's $q$-scores have reliable probabilistic semantics, so the $\\aeff$ proxy accurately tracks batch quality.\nGenerative detectors assign high $q$-scores to fluent, predictable human text (false positives concentrated among high-quality samples), systematically inflating $\\aeff$ for clean batches and deflating it for contaminated ones, which inverts the minimum-intervention logic.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llccccc@{}}\n\\toprule\n\\textbf{Detector} & \\textbf{Type} & \\textbf{AUC} & \\textbf{ECE} & \\textbf{Mean PPL} & $\\boldsymbol{\\Delta}$ \\\\\n\\midrule\nTF-IDF+LR & Discriminative & 0.94 & 0.048 & 17.650{\\tiny$\\pm$.010} & $-$0.044 \\\\\nGPT-2 PPL & Generative & 0.91 & 0.131 & 17.792{\\tiny$\\pm$.005} & $+$0.098 \\\\\nN-gram PPL & Generative & 0.73 & 0.069 & 17.823{\\tiny$\\pm$.003} & $+$0.129 \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Detector comparison for adaptive reweighting ($\\rho{=}0.4$, $\\tau{=}0.8$, 3 seeds).\nUniform baseline PPL\\,=\\,17.694.\n$\\Delta$ = Adaptive $-$ Uniform (negative is better).\nTF-IDF+LR calibrated via temperature scaling.\nThe $\\tau$ confound is conservative: TF-IDF+LR at $\\tau{=}0.7$ achieves 17.674 (Table~\\ref{tab:main}).}\n\\label{tab:detector}\n\\end{table}\n\n\\section{Detector and Synthetic Data Details}\n\\label{app:detector_details}\n\n\\paragraph{TF-IDF+LR detector.}\nTF-IDF features (unigrams + bigrams, max 50{,}000 features, sublinear TF) fed to Logistic Regression (C\\,=\\,1.0, L2 penalty, solver\\,=\\,lbfgs, max\\_iter\\,=\\,100).\nTrained on a held-out labeled split (10K documents per class).\nPost-hoc temperature scaling applied when uncalibrated ECE exceeds 0.05: a scalar $T$ is searched via \\texttt{scipy.optimize.minimize\\_scalar} over $[0.1, 10.0]$ on a 20\\% stratified validation split, yielding $T{=}0.204$ (ECE reduced from 0.12 to 0.05).\nThe detector is selected automatically from six configurations as the first satisfying AUC $\\in [0.85, 0.98]$ and mid-range score ratio $\\geq 5\\%$.\n\n\\paragraph{Synthetic data generation.}\nContinuations generated with Qwen3-0.6B (self-generation) using nucleus sampling ($p{=}0.95$, $T{=}0.8$), producing up to 384 tokens per continuation from a 128-token prefix prompt (512 total), targeting ${\\sim}$100M synthetic tokens.\nSource prompts are the first 128 tokens of randomly sampled FineWeb documents, used as prefix continuations.\nInjected at token-level ratio $\\rho$ via uniform random mixing across the training corpus.\n\n\\section{Low Contamination Analysis}\n\\label{app:rho02}\n\nAt $\\rho{=}0.2$, the adaptive method degrades by $+$0.046 PPL relative to uniform (0.26\\% relative, seed\\,42).\nThe detector's mean $q$-score at this contamination level is 0.393 (vs.\\ 0.487 at $\\rho{=}0.4$), indicating that many clean samples receive moderate $q$-scores, blurring the provenance signal.\nThe regime decomposition reveals 13.7\\% clean batches ($\\bstar{=}0$), 60.1\\% $\\aeff$-binding, and 26.3\\% ESS-binding, with mean $\\bstar{=}1.735$ in reweighted batches.\nThe high $\\aeff$-binding rate (60.1\\% vs.\\ ${\\sim}$50\\% at $\\rho{=}0.4$) means the method actively intervenes rather than defaulting to $\\bstar{=}0$, but the unreliable signal causes it to suppress useful training data.\nThis is consistent with the generative detector failures: when $q$-scores do not reliably separate provenance, the minimum intervention framework amplifies the error rather than correcting it.\nThe effective range of the method is $\\rho \\geq 0.4$ with $\\tau \\in [0.7, 0.8]$ (\\S\\ref{sec:sensitivity}); lower $\\tau$ values may extend the range but have not been tested at $\\rho{=}0.2$.\n\n\\section{Cross-Model Transfer}\n\\label{app:cross_model}\n\nTable~\\ref{tab:cross_model} reports a single exploratory run with Llama-3.2-3B as a cross-generator (synthetic data generated by Llama, training on Qwen3-0.6B); this does not establish generality.\nResults are mixed: MMLU improves while HellaSwag slightly degrades, consistent with the pattern observed in Qwen3-1.7B downstream evaluation (\\S\\ref{sec:robustness}).\nPerplexity comparison omitted due to inconsistent evaluation configurations; checkpoints were not retained for re-evaluation.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n\\textbf{Metric} & \\textbf{Uniform} & \\textbf{Adaptive} & $\\boldsymbol{\\Delta}$ \\\\\n\\midrule\nMMLU (5-shot) & 51.85\\% $\\pm$ .41 & 53.42\\% $\\pm$ .41 & $+$1.57pp \\\\\nHellaSwag (10-shot, acc\\_norm) & 73.08\\% $\\pm$ .44 & 72.49\\% $\\pm$ .45 & $-$0.59pp \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Cross-model transfer: Llama-3.2-3B generator, Qwen3-0.6B trainer ($\\rho{=}0.4$, single seed).\nMixed results reflect evaluation-set distribution sensitivity rather than consistent quality differences.}\n\\label{tab:cross_model}\n\\end{table}\n\n\\section{Checkpoint Resume Artifact}\n\\label{app:resume_artifact}\n\nThe checkpoint-resume artifact described here affected early $\\tau{=}0.8$ experiments only.\nAll results in Tables~\\ref{tab:main}--\\ref{tab:epoch_match} use independent from-scratch training ($\\tau{=}0.7$; Table~\\ref{tab:main} Adaptive/Uniform: five seeds, others: three seeds).\n\nThe adaptive model for seed\\,42 in early $\\tau{=}0.8$ runs was trained with a checkpoint-resumed run whose first ${\\sim}$1{,}000 steps used different hyperparameters (learning rate warmup, gradient accumulation configuration) than seeds 123 and 456, which were trained from scratch.\nThe resume artifact inflates the in-distribution effect ($\\Delta{=}{-}0.041$ resume vs.\\ $\\Delta{=}{-}0.005$ from-scratch at $\\tau{=}0.8$) and reverses the out-of-distribution direction:\n\n\\begin{center}\n\\small\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n\\textbf{Domain} & \\textbf{Resume} & \\textbf{From-scratch} & \\textbf{Dir.} \\\\\n\\midrule\nFineWeb (in-dist) & $-$0.041 & $-$0.005 & same \\\\\nOpenWebText (OOD) & $+$0.058 & $-$0.005 & reversed \\\\\nWikipedia (OOD)   & $+$0.137 & $-$0.009 & reversed \\\\\n\\bottomrule\n\\end{tabular}\\\\[2pt]\n{\\scriptsize $\\Delta$ relative to from-scratch uniform (Table~\\ref{tab:tau}). Resume: seed\\,42 original checkpoint. From-scratch: clean replication run.}\n\\end{center}\n\nThe resume model showed apparent distribution matching (OOD degradation), which was the basis for the ``distribution matching'' finding in earlier analyses.\nFrom-scratch retraining eliminates this pattern: all three evaluation domains show small, directionally consistent improvements, providing no evidence of distribution matching.\nThis underscores the importance of controlling for training artifacts when interpreting small effect sizes across evaluation domains.\n\n\\section{Additional Contamination Rate}\n\\label{app:rho03}\n\nTo probe the boundary between the degradation regime ($\\rho{=}0.2$, $\\Delta{=}{+}0.046$) and the improvement regime ($\\rho{=}0.4$, $\\Delta{=}{-}0.023$), we run adaptive $\\bstar$ and uniform baselines at $\\rho{=}0.3$ using the same experimental setup as the main experiments (Qwen3-0.6B, 132M FineWeb tokens, $\\tau{=}0.7$, $\\nmin{=}2$).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n\\textbf{Method} & \\textbf{Seed} & \\textbf{FineWeb} $\\downarrow$ & \\textbf{OWT} $\\downarrow$ & \\textbf{Wiki} $\\downarrow$ \\\\\n\\midrule\nUniform          & 42  & 17.422 & 18.113 & 15.204 \\\\\nAdaptive $\\bstar$ & 42  & 17.422 & 18.123 & 15.172 \\\\\n\\midrule\nUniform          & 123 & 17.433 & 18.126 & 15.204 \\\\\nAdaptive $\\bstar$ & 123 & 17.435 & 18.148 & 15.165 \\\\\n\\midrule\nUniform          & 456 & 17.419 & -- & -- \\\\\nAdaptive $\\bstar$ & 456 & 17.424 & -- & -- \\\\\n\\midrule\n$\\Delta$ (3-seed mean) & --  & $+$0.002 & -- & -- \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Results at $\\rho{=}0.3$ (Qwen3-0.6B, 3 seeds).\nHoldout $\\Delta{=}{+}0.002$ ($t(2){=}1.60$, $p{=}0.25$, non-significant); OOD available for seeds 42 and 123 only, mixed in direction.}\n\\label{tab:rho03}\n\\end{table}\n\nThe holdout difference is effectively zero ($\\Delta{=}{+}0.002$, $t(2){=}1.60$, $p{=}0.25$, non-significant), placing the transition boundary between the degradation regime ($\\rho{=}0.2$, $\\Delta{=}{+}0.046$) and the improvement regime ($\\rho{=}0.4$, $\\Delta{=}{-}0.023$) within $[0.3, 0.4]$ (Figure~\\ref{fig:delta_vs_rho}).\n\nAt $\\rho{=}0.3$, 28\\% of micro-batches have $\\bstar{=}0$ (clean, no intervention), compared to ${\\sim}$6\\% at $\\rho{=}0.4$; the low intervention frequency explains why the method neither helps nor harms.\nThe progression across contamination levels ($\\rho{=}0.2$ harmful, $+$0.046; $\\rho{=}0.3$ neutral, $+$0.002; $\\rho{=}0.4$ beneficial, $-$0.023) shows a graceful transition rather than abrupt failure, consistent with the detector's signal-to-noise ratio gradually crossing the threshold needed for reliable $\\aeff$ estimation.\n\n\\section{Statistical Power Analysis}\n\\label{app:power}\n\nThe adaptive-vs-uniform comparison at $\\rho{=}0.4$ has Cohen's $d = \\bar{\\Delta}/\\mathrm{SD}_{\\Delta} = 0.023/0.006 = 3.83$ (5 seeds, paired).\nA one-sided paired $t$-test at $\\alpha{=}0.05$ with $d{=}3.83$ and $N{=}5$ achieves statistical power ${>}0.99$ (noncentrality $\\lambda = d\\sqrt{N} = 8.56$, $t_{0.05,4} = 2.13$), indicating that $N{=}5$ is more than adequate to detect an effect of this magnitude.\n\nThe low cross-seed variance ($\\sigma{=}0.006$) reflects the experimental design: seeds affect only parameter initialization, not data order (the dataloader is deterministic), so the primary stochastic axis is initialization noise at 0.6B scale.\nThe uniform baseline exhibits comparable variance ($\\sigma{=}0.008$); the low dispersion is a property of the experimental setting rather than a method artifact.\n\nWe apply Bonferroni--Holm correction for $k{=}9$ family-wise comparisons (six reweighting methods $\\times$ one contamination level, plus three additional $\\rho$ levels).\nAfter correction, $p_{\\mathrm{BH}}{=}0.011$ at $\\rho{=}0.4$, reaching conventional significance at $\\alpha{=}0.05$.\nAt $\\rho{=}0.6$ (3 seeds), $p_{\\mathrm{BH}}{=}0.064$; the family includes structurally heterogeneous tests (different methods, different $\\rho$), which makes Bonferroni--Holm conservative.\nThe uncorrected $p$-values ($0.0012$ and $0.010$ respectively), directional consistency across all seeds, and the dose-response pattern across $\\rho$ levels collectively support a real effect.\n\n\\section{Supplementary Analyses Summary}\n\\label{app:summary}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\setlength{\\tabcolsep}{3pt}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lll@{}}\n\\toprule\n\\textbf{Analysis} & \\textbf{Key result} & \\textbf{App.} \\\\\n\\midrule\nDownstream tasks & No gain (5 benchmarks, $|\\Delta|\\leq 0.01$) & \\ref{app:downstream} \\\\\nCross-model (Llama) & Mixed (MMLU $+$1.6, HellaSwag $-$0.6) & \\ref{app:cross_model} \\\\\n$\\tau$ sweep & $[0.5,0.8]$ all improve; $\\tau{>}0.8$ degrades & \\ref{app:tau_sweep} \\\\\n$\\rho{=}0.3$ boundary & $\\Delta{=}{+}0.002$ (neutral, 3 seeds) & \\ref{app:rho03} \\\\\nStatistical power & Cohen's $d{=}3.83$, power ${>}0.99$ at $N{=}5$ & \\ref{app:power} \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{Summary of supplementary analyses.}\n\\label{tab:appendix_summary}\n\\end{table}\n\n\\section{Use of AI Assistants}\n\\label{app:ai-assistants}\n\nWe used Claude (Anthropic) as an AI coding and writing assistant\nthroughout this work. Specifically:\n\\begin{itemize}\n    \\item \\textbf{Code:} drafting experiment scripts, data-processing\n    pipelines, and analysis utilities; debugging and refactoring.\n    \\item \\textbf{Writing:} drafting and revising paper sections,\n    polishing prose, and reformatting \\LaTeX{}.\n    \\item \\textbf{Literature:} summarizing related papers to inform\n    the related-work section.\n\\end{itemize}\n\n",
    "structuredPatch": [
      {
        "oldStart": 360,
        "oldLines": 7,
        "newStart": 360,
        "newLines": 7,
        "lines": [
          " \\paragraph{TF-IDF+LR detector.}",
          " TF-IDF features (unigrams + bigrams, max 50{,}000 features, sublinear TF) fed to Logistic Regression (C\\,=\\,1.0, L2 penalty, solver\\,=\\,lbfgs, max\\_iter\\,=\\,100).",
          " Trained on a held-out labeled split (10K documents per class).",
          "-Post-hoc temperature scaling applied when uncalibrated ECE exceeds 0.05: a scalar $T$ is searched via \\texttt{scipy.optimize.minimize\\_scalar} over $[0.1, 10.0]$ on a 20\\% stratified validation split, yielding $T{=}0.204$ (ECE reduced from 0.12 to 0.05).",
          "+Post-hoc temperature scaling applied when uncalibrated ECE exceeds 0.05: a scalar $T$ is searched via \\texttt{scipy.optimize.minimize\\_scalar} over $[0.1, 10.0]$ on a 20\\% stratified validation split, yielding $T{=}0.204$ (ECE reduced from 0.12 to 0.048).",
          " The detector is selected automatically from six configurations as the first satisfying AUC $\\in [0.85, 0.98]$ and mid-range score ratio $\\geq 5\\%$.",
          " ",
          " \\paragraph{Synthetic data generation.}"
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

_source line 76_

<details><summary>Logged reasoning block</summary>

```text
Now let me also verify one thing that bothered me: the HellaSwag Δ in results.tex. It says "HellaSwag −0.6 percentage points" which rounds correctly from -0.59. So the results.tex is fine, only the appendix table was wrong with -0.60pp (should be -0.59pp). Already fixed.

Now let me compile the full audit report.

Wait, I should also check if there are other numbers in results.tex that reference appendix numbers and might need cross-checking. I already did this comprehensively.


Now I'm putting together the final report.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "fec06cd8-6fac-4cd0-b38b-4f6a0ee898d0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012UQwR53YbSEjWn9jP3QCic",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12958,
      "cache_read_input_tokens": 90325,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12958
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

_source line 77_

现在验证修复后的文件完整性。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "1b0257c2-2de7-4a66-9812-4f1e07e69a74",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012UQwR53YbSEjWn9jP3QCic",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12958,
      "cache_read_input_tokens": 90325,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12958
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

_source line 78_

<details open><summary>🔧 Tool call — Read · `toolu_019M5b3k6FV2Anfdx2eWQoEV`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/appendix.tex",
  "offset": 360,
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
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "b902fe07-4900-4457-8193-e2fbbb0dbb91",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012UQwR53YbSEjWn9jP3QCic",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12958,
      "cache_read_input_tokens": 90325,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12958
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

_source line 79 · 2026-05-25T20:20:26.381Z_

<details><summary>↩ Tool result · `toolu_019M5b3k6FV2Anfdx2eWQoEV`</summary>

```text
360	\paragraph{TF-IDF+LR detector.}
361	TF-IDF features (unigrams + bigrams, max 50{,}000 features, sublinear TF) fed to Logistic Regression (C\,=\,1.0, L2 penalty, solver\,=\,lbfgs, max\_iter\,=\,100).
362	Trained on a held-out labeled split (10K documents per class).
363	Post-hoc temperature scaling applied when uncalibrated ECE exceeds 0.05: a scalar $T$ is searched via \texttt{scipy.optimize.minimize\_scalar} over $[0.1, 10.0]$ on a 20\% stratified validation split, yielding $T{=}0.204$ (ECE reduced from 0.12 to 0.048).
364	The detector is selected automatically from six configurations as the first satisfying AUC $\in [0.85, 0.98]$ and mid-range score ratio $\geq 5\%$.
365	
366	\paragraph{Synthetic data generation.}
367	Continuations generated with Qwen3-0.6B (self-generation) using nucleus sampling ($p{=}0.95$, $T{=}0.8$), producing up to 384 tokens per continuation from a 128-token prefix prompt (512 total), targeting ${\sim}$100M synthetic tokens.
368	Source prompts are the first 128 tokens of randomly sampled FineWeb documents, used as prefix continuations.
369	Injected at token-level ratio $\rho$ via uniform random mixing across the training corpus.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "81b75c3b-abdd-4a4a-8e4c-35982b1d4172",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/appendix.tex",
      "content": "\\paragraph{TF-IDF+LR detector.}\nTF-IDF features (unigrams + bigrams, max 50{,}000 features, sublinear TF) fed to Logistic Regression (C\\,=\\,1.0, L2 penalty, solver\\,=\\,lbfgs, max\\_iter\\,=\\,100).\nTrained on a held-out labeled split (10K documents per class).\nPost-hoc temperature scaling applied when uncalibrated ECE exceeds 0.05: a scalar $T$ is searched via \\texttt{scipy.optimize.minimize\\_scalar} over $[0.1, 10.0]$ on a 20\\% stratified validation split, yielding $T{=}0.204$ (ECE reduced from 0.12 to 0.048).\nThe detector is selected automatically from six configurations as the first satisfying AUC $\\in [0.85, 0.98]$ and mid-range score ratio $\\geq 5\\%$.\n\n\\paragraph{Synthetic data generation.}\nContinuations generated with Qwen3-0.6B (self-generation) using nucleus sampling ($p{=}0.95$, $T{=}0.8$), producing up to 384 tokens per continuation from a 128-token prefix prompt (512 total), targeting ${\\sim}$100M synthetic tokens.\nSource prompts are the first 128 tokens of randomly sampled FineWeb documents, used as prefix continuations.\nInjected at token-level ratio $\\rho$ via uniform random mixing across the training corpus.",
      "numLines": 10,
      "startLine": 360,
      "totalLines": 517
    }
  }
}
```

</details>

---


### Tool call

_source line 80_

<details open><summary>🔧 Tool call — Read · `toolu_01PWbHRCgpC6YaSpCAMm5x9S`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/appendix.tex",
  "offset": 395,
  "limit": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "37f7352f-ed89-410c-b830-2f839ff46b5a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012UQwR53YbSEjWn9jP3QCic",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12958,
      "cache_read_input_tokens": 90325,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12958
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

_source line 81 · 2026-05-25T20:20:26.857Z_

<details><summary>↩ Tool result · `toolu_01PWbHRCgpC6YaSpCAMm5x9S`</summary>

```text
395	\midrule
396	MMLU (5-shot) & 51.85\% $\pm$ .41 & 53.42\% $\pm$ .41 & $+$1.57pp \\
397	HellaSwag (10-shot, acc\_norm) & 73.08\% $\pm$ .44 & 72.49\% $\pm$ .45 & $-$0.59pp \\
398	\bottomrule
399	\end{tabular}}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "b3102bed-765e-4f5f-a501-84fe25c4fa05",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_10/projects/provenance_weight_training/docs/paper/sections/appendix.tex",
      "content": "\\midrule\nMMLU (5-shot) & 51.85\\% $\\pm$ .41 & 53.42\\% $\\pm$ .41 & $+$1.57pp \\\\\nHellaSwag (10-shot, acc\\_norm) & 73.08\\% $\\pm$ .44 & 72.49\\% $\\pm$ .45 & $-$0.59pp \\\\\n\\bottomrule\n\\end{tabular}}",
      "numLines": 5,
      "startLine": 395,
      "totalLines": 517
    }
  }
}
```

</details>

---


### Assistant

_source line 82_

两处修复已生效。下面是完整审计报告。

---

## Appendix 数字真实性审计报告

**审计范围**: `appendix.tex` 全部 12 张表 + 行间数字，共约 **260 个数字**

### 一、已修复问题（2 处）

| 文件:行号 | 数字 | 问题 | 处理 |
|-----------|------|------|------|
| appendix.tex:397 | Δ=−0.60pp | HellaSwag 72.49−73.08=−0.59，非−0.60 | 已改为 −0.59pp |
| appendix.tex:363 | ECE "to 0.05" | 全文其他位置（experiments.tex, tab:detector）均用 0.048，此处精度不一致 | 已改为 0.048 |

### 二、出处存疑 / 需人工确认的数字（4 处）

#### 1. **[严重]** Tab:detector TF-IDF PPL 与 Tab:tau τ=0.80 不一致

- Tab:detector（L344）: TF-IDF+LR, τ=0.8, 3 seeds → **17.650 ± .010**, Δ=−0.044
- Tab:tau（L120）: τ=0.80, 3 from-scratch seeds → **17.683 ± .006**, Δ=−0.011
- 差值 **0.033**，超过 SD
- Registry 交叉验证：`adaptive_fix` 系列（τ=0.8, n_min=2）3-seed mean ≈ 17.651，与 tab:detector 吻合；tab:tau 的 17.683 可能来自另一批 from-scratch 训练
- **疑因**: Tab:detector 可能混入了 checkpoint-resumed seed 42 结果（resume artifact section 已警告此问题），或两表使用了不同实验批次
- **建议**: 确认 tab:detector 的 TF-IDF 行是否使用纯 from-scratch seeds；若是，更新为与 tab:tau 一致的 17.683±.006（Δ=−0.011）

#### 2. **[轻微]** Tab:hybrid ρ=0.6 Hybrid PPL

- 论文（L172）: 17.530
- Registry `hybrid_rho06_seed42`: **17.526**
- 差值 0.004，需确认是否有更新版本的实验

#### 3. **[轻微]** Tab:rho06 ESS-only seeds 123/456

- 论文: 两个都写 **17.760**
- Registry: seed 123 = **17.763**, seed 456 = **17.762**
- 影响: 若用 registry 值，mean 从 17.763 变为 17.765（仍与 Uniform 17.763 接近，但不完全相等）

#### 4. **[标注]** Tab:dr_threshold q>0.5 可能是 3-seed 均值

- 表中 q>0.5 Raw PPL = 17.28，caption 写 "seed 42 unless noted"
- Registry seed 42: 17.291 (v1) / 17.285 (v2)，均 ≠ 17.28
- Registry 3-seed v2 均值: (17.285+17.272+17.277)/3 = **17.278 ≈ 17.28** ✓
- 建议: 如确实是 3-seed mean，应像 q>0.3 一样加 † 脚注

### 三、正文 ↔ Appendix 交叉一致性验证

| 交叉项 | Appendix | 正文 (results/experiments/discussion) | 一致? |
|--------|----------|---------------------------------------|-------|
| Adaptive τ=0.7 5-seed holdout | 17.674±.006 (tab:tau) | 17.674±.006 (tab:main) | ✓ |
| Uniform 3-seed baseline | 17.694 (tab:tau caption) | (17.694+17.686+17.702)/3=17.694 | ✓ |
| Δ_H at τ=0.7 vs 3-seed unif | −0.020 | (17.674−17.694=−0.020) | ✓ |
| Δ at 5-seed (tab:main) | −0.023 (caption note) | 17.674−17.697=−0.023 | ✓ |
| τ=0.7 OWT Δ | −0.028 | −0.028 (results L147) | ✓ |
| τ=0.7 Wiki Δ | −0.029 | −0.029 (results L147) | ✓ |
| τ=0.8 OWT Δ | −0.005 | −0.005 (results L147) | ✓ |
| τ=0.8 Wiki Δ | −0.009 | −0.009 (results L147) | ✓ |
| ρ=0.6 adaptive mean | 17.731±.004 | 17.731±0.004 (results L81) | ✓ |
| ρ=0.6 uniform mean | 17.763±.008 | 17.763±0.008 (results L81) | ✓ |
| ρ=0.6 hierarchy | Grid < Adaptive < Uniform ≈ ESS < Random | Same (results L82) | ✓ |
| ρ=0.6 paired t (3dp) | t=−9.95, p=0.010 | t=−9.95, p_BH=0.064 (results L81) | ✓ |
| p_BH=0.011 at ρ=0.4 | app:power L476 | results L31 | ✓ |
| p_BH=0.064 at ρ=0.6 | app:power L477 | results L81 | ✓ |
| Grid b=0.3 3-seed mean | 17.620±.033 (tab:aux via cross-ref) | 17.620±.033 (tab:aux) | ✓ |
| b=1.0 ≈ uniform | 17.692 (tab:grid_full) | 17.692 vs 17.694 (results L34) | ✓ |
| D&R q>0.3 3-seed | 17.250±.001 | 17.250±.001 (tab:epoch_match) | ✓ |
| D&R q>0.7 raw | 17.32 | 17.32 (tab:epoch_match) | ✓ |
| ESS-only gap at ρ=0.4 | 0.043 (L271) | 0.043 (results L38) | ✓ |
| B=16 Δ amplification | 3.0×, −0.068±0.005 (L76) | 3.0×, −0.068±0.005 (results L155) | ✓ |
| Spearman r B=4 | 0.699 (tab:alpha_corr & L76) | 0.699 | ✓ |
| ρ=0.2 Δ | +0.046 (L374) | +0.046 (discussion L6) | ✓ |
| ρ=0.3 Δ | +0.002 (L461) | Within [0.3,0.4] boundary (discussion L6) | ✓ |
| Cross-model MMLU | +1.57pp (tab:cross_model) | +1.6pp (results L115, rounded) | ✓ |
| Cohen's d | 3.83 = 0.023/0.006 (L469) | — (arithmetic ✓) | ✓ |
| Downstream mean | 0.5414 (tab:downstream caption) | 0.5414 (discussion L31) | ✓ |
| ECE gap 2.7× | 0.131/0.048=2.73 (L332) | 2.7× (results L122) | ✓ |
| τ-ρ paired t | −4.70 (fig caption L149) | −4.70 (results L147) | ✓ |
| Training steps | 6,103 (L72) | 6,103 (experiments tab:config) | ✓ |

### 四、Registry 交叉验证

| 数据 | 论文 | Registry | 一致? |
|------|------|----------|-------|
| Grid b=0.1–5.0 seed 42 | 9 values | 9 values exact match | ✓ |
| Grid b=0.3 3-seed mean | 17.620 | (17.64+17.579+17.64)/3=17.620 | ✓ |
| ρ=0.6 Adaptive 3 seeds | 17.735/17.727/17.732 | 17.735/17.727/17.732 | ✓ |
| ρ=0.6 Uniform 3 seeds | 17.766/17.754/17.770 | 17.766/17.754/17.77 | ✓ |
| ρ=0.6 Random 3 seeds | 17.832/17.870/17.880 | 17.832/17.87/17.88 | ✓ |
| ρ=0.6 Grid b=0.3 | 17.634 | 17.634 | ✓ |
| ρ=0.3 all 6 holdout values | match | match exactly | ✓ |
| D&R q>0.3 3-seed | 17.250 | 17.25/17.25/17.2509 → 17.250 | ✓ |
| D&R q>0.7 3-seed | 17.32 | 17.32/17.32/17.32 | ✓ |
| Epoch-matched all 5 values | match | match exactly | ✓ |
| Hybrid ρ=0.4 | 17.514 | 17.514 | ✓ |
| GPT-2 detector 3-seed PPL | 17.792 | (17.79+17.788+17.797)/3=17.792 | ✓ |
| N-gram detector 3-seed PPL | 17.823 | (17.820+17.823+17.826)/3=17.823 | ✓ |
| Golden Ratio seed 42 | 17.654 (tab:aux) | 17.654 | ✓ |
| ρ=0.2 Δ=+0.046 | 17.382−17.336=0.046 | 17.382−17.336=0.046 | ✓ |
| Detector AUC=0.94, ECE=0.048, T=0.204 | match | AUC=0.939≈0.94, ECE=0.048, T=0.204 | ✓ |
| α_eff correlation, per-seed stats | — | NOT in registry (separate analysis script) | 无法验证 |
| Cross-model MMLU/HellaSwag | — | NOT in registry | 无法验证 |
| Detector hyperparams (50k, C=1.0) | — | Registry 记录不同值 (10k, C=0.01)，可能是旧版配置 | 无法验证 |

### 五、算术抽检（全部通过）

- Tab:rho06 所有 mean/SD: 手动重算均一致 ✓
- Tab:tau 所有 Δ: 手动重算均一致 ✓
- Tab:detector Δ: 17.650−17.694=−0.044 ✓ (算术正确，但基数可能有问题，见第二节)
- Tab:rho03 Δ: (17.427−17.425)/=+0.002 ✓
- Cohen's d: 0.023/0.006=3.83 ✓; λ=3.83×√5=8.56 ✓
- Tab:alpha_corr_perseed spread: max−min 算术 ✓
- Cross-model MMLU Δ: 53.42−51.85=1.57 ✓

### 总结

- **审计数字**: ~260
- **已修复**: 2（HellaSwag Δ 算术、ECE 精度）
- **需确认**: 4（detector table 最重要，其余为小数点级精度问题）
- **无法从 registry 验证**: 3 类（α_eff 相关分析、Llama MMLU/HellaSwag、detector 超参细节）
- **正文-附录一致性**: 全部 30+ 项交叉引用一致

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "b883e8c8-4e70-4c1d-86d0-e21cb1b9cee9",
  "uuid": "ca8a6e00-77d7-48d6-b16a-3e008c234833",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VUhNUMJ4pF89MB5PJvqh5U",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 987,
      "cache_read_input_tokens": 103283,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 987
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
