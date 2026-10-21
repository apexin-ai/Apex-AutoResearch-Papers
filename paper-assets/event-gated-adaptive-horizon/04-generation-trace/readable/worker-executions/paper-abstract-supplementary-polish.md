# paper abstract supplementary polish

**Why Temporal Abstraction Can Fail in Imagination-Based RL: A Diagnostic Analysis of Variable-Rate DreamerV3** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 28
- **Recorded user turns:** 0
- **Tool calls:** 9
- **Original source:** `logs/workers/worker_paper_abstract-supplementary-polish_20260518T142422.log`
- **Structured JSON:** [`bd471d4f184f8beba501.json`](../../sessions/bd/bd471d4f184f8beba501.json)

## Before a recorded user message

28 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon",
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
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
  "uuid": "8c999c37-f304-421b-a876-73ae1d1257ea",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-9-projects-event-gated-adaptive-horizon/memory/"
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
    "resetsAt": 1779122400,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "03a0e80b-9c27-4966-9ba8-fd8edf0f6911",
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me read the three files first to understand their current content, then make the edits.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "3a55647d-1fb9-4552-9d05-349516eebe7e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019zUGGy1wVqbUx8zfqePjoH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13925,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13925
      },
      "output_tokens": 36,
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

读取三个文件。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "0f79a8e8-0cef-483e-a74b-842efe0334ab",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019zUGGy1wVqbUx8zfqePjoH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13925,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13925
      },
      "output_tokens": 36,
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

<details open><summary>🔧 Tool call — Read · `toolu_01NX1bbkMdwqHdMskSyYjbTY`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/abstract_body.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "5cb1105f-3ea6-4723-8f81-19ca27196321",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019zUGGy1wVqbUx8zfqePjoH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13925,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13925
      },
      "output_tokens": 36,
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

_source line 7 · 2026-05-18T14:24:32.518Z_

<details><summary>↩ Tool result · `toolu_01NX1bbkMdwqHdMskSyYjbTY`</summary>

```text
1	Temporal abstraction via variable-rate imagination is a natural extension of world-model reinforcement learning, yet we find that every variable-rate configuration of DreamerV3 degrades performance, despite the success of identical $\Delta t$-conditioning in MPC-based methods. Through factorial diagnostics on two continuous-control tasks (Walker Walk, Cheetah Run), we identify the combination of trained temporal embedding and multi-rate data exposure as the causal factor and characterize the resulting failure mode: \emph{conditioning-induced value overestimation} (CIVO). The trained embedding enables the RSSM reward head to develop a $2.78\times$ prediction gap between $\Delta t{=}1$ and $\Delta t{=}2$, which the critic internalizes as optimistic values. This mechanism universally degrades performance to below 30\% of baseline across all six tested seeds in two environments ($n{=}6$), with five progressing toward full collapse and one self-correcting to a stable but degraded state. Gradient decomposition reveals that despite the reward head providing the largest gradient contribution (38--49\%), the observation decoder channel (16--22\%) carries the critical $\Delta t$-specific spatial information that drives the fidelity gap. Full-pathway gradient stopping partially prevents CIVO but succeeds in only 50\% of cases; this exposes additional mechanisms beyond gradient-mediated co-adaptation. A lightweight online detector that monitors value-to-evaluation ratio dynamics identifies CIVO onset with 100\% sensitivity (5/5 cases) and provides predictive warning before performance degradation in 2/5 cases, which supports early intervention without a reference baseline. The contrast with MPC-based methods identifies the feedback architecture (imagination-based bootstrapping versus re-planning) as the structural factor that transforms manageable model imprecision into pathological value dynamics.
2	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "13f1799b-3feb-4acd-93e2-0683d635f4bb",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/abstract_body.tex",
      "content": "Temporal abstraction via variable-rate imagination is a natural extension of world-model reinforcement learning, yet we find that every variable-rate configuration of DreamerV3 degrades performance, despite the success of identical $\\Delta t$-conditioning in MPC-based methods. Through factorial diagnostics on two continuous-control tasks (Walker Walk, Cheetah Run), we identify the combination of trained temporal embedding and multi-rate data exposure as the causal factor and characterize the resulting failure mode: \\emph{conditioning-induced value overestimation} (CIVO). The trained embedding enables the RSSM reward head to develop a $2.78\\times$ prediction gap between $\\Delta t{=}1$ and $\\Delta t{=}2$, which the critic internalizes as optimistic values. This mechanism universally degrades performance to below 30\\% of baseline across all six tested seeds in two environments ($n{=}6$), with five progressing toward full collapse and one self-correcting to a stable but degraded state. Gradient decomposition reveals that despite the reward head providing the largest gradient contribution (38--49\\%), the observation decoder channel (16--22\\%) carries the critical $\\Delta t$-specific spatial information that drives the fidelity gap. Full-pathway gradient stopping partially prevents CIVO but succeeds in only 50\\% of cases; this exposes additional mechanisms beyond gradient-mediated co-adaptation. A lightweight online detector that monitors value-to-evaluation ratio dynamics identifies CIVO onset with 100\\% sensitivity (5/5 cases) and provides predictive warning before performance degradation in 2/5 cases, which supports early intervention without a reference baseline. The contrast with MPC-based methods identifies the feedback architecture (imagination-based bootstrapping versus re-planning) as the structural factor that transforms manageable model imprecision into pathological value dynamics.\n",
      "numLines": 2,
      "startLine": 1,
      "totalLines": 2
    }
  }
}
```

</details>

---

### Tool call

_source line 8_

<details open><summary>🔧 Tool call — Read · `toolu_01P6AHcawt4Q7x9t3MQSdDTr`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "3e797370-ca86-4869-943c-f06fd93dd96c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019zUGGy1wVqbUx8zfqePjoH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13925,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13925
      },
      "output_tokens": 36,
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

_source line 9 · 2026-05-18T14:24:32.806Z_

<details><summary>↩ Tool result · `toolu_01P6AHcawt4Q7x9t3MQSdDTr`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	We have presented a systematic factorial diagnostic of temporal abstraction in DreamerV3 across two continuous-control environments. The analysis identifies the combination of trained $\dt$-embedding and multi-rate data exposure as the causal factor behind conditioning-induced value overestimation (CIVO). The key findings are:
5	
6	\begin{enumerate}[nosep,leftmargin=*]
7	\item Every variable-rate imagination configuration degrades relative to the $\dt{=}1$ baseline, with degradation scaling monotonically with $\dt$.
8	\item A normalized value-to-eval threshold of $\nve \geq 1.5\times$ (35K+ window) achieves 15/16 CIVO classification ($n{=}16$, 93.8\%), with the single false positive arising from a mechanistically distinct non-CIVO collapse. The combination of trained $\dt$-embedding and multi-rate data exposure is the causal factor; unexposed, frozen, or removed embeddings prevent overestimation.
9	\item The RSSM reward head develops a $2.78\times$ prediction gap between $\dt{=}1$ and $\dt{=}2$ under trained conditioning. This systematic bias drives critic overestimation.
10	\item The same CIVO trigger produces stochastic downstream outcomes (full collapse and transient CIVO with self-correction) across seeds of identical configurations.
11	\item Restricting imagination to $\dt{=}1$ does not fully prevent collapse: two of four seeds fail (50\%) via two qualitatively distinct pathways, one CIVO-driven with entropy decrease and one entropy-driven with entropy increase. The bimodal distribution, with no intermediate outcomes, confirms that the trained $\dt$-embedding creates vulnerability through multiple independent mechanisms.
12	\item A lightweight online detector that monitors the dynamics of the value-to-evaluation ratio identifies CIVO onset with 100\% sensitivity across five positive cases, with predictive detection (alert before performance degradation) in two of five. A timing guideline ($<$70K steps = high confidence) separates genuine CIVO from late-stage false positives.
13	\end{enumerate}
14	
15	The contrast with TAWM's success in MPC identifies the feedback architecture as the critical factor: $\dt$-conditioning succeeds when errors are contained by re-planning from real states, but fails when errors compound through imagination-based actor-critic bootstrapping.
16	
17	\paragraph{Limitations.}
18	Our primary factorial analysis focuses on Walker Walk; cross-environment evidence (Cheetah Run) is confirmed across two seeds but limited to a single trigger configuration. Both use a single world-model architecture (DreamerV3/RSSM). Generalization to other environments and architectures, particularly transformer-based world models such as DreamerV4, remains an open question. The $\nve$ threshold ($1.5\times$, 35K+ window) is sensitive to value overestimation broadly but not perfectly specific to CIVO (15/16, one non-CIVO false positive); generalization to other tasks and architectures is pending validation. The detector's thresholds were calibrated on thirteen runs across three environments; generalization to different reward scales and architectures requires further validation. Whether the protection conferred by removing the temporal embedding persists beyond 105K training steps also remains open: one control seed (009c, seed~2) exhibited NVE rising to $1.14\times$ at 105K steps on an upward trajectory, suggesting that longer training horizons may eventually erode this safeguard.
19	
20	\paragraph{Future directions.}
21	Our findings suggest three avenues. First, hierarchical temporal abstraction at the representation level (as in THICK and Hieros) may avoid the flat-conditioning failure mode by maintaining separate dynamics for each temporal scale. Second, gradient decomposition reveals that gradient importance is decoupled from magnitude: the reward head provides the largest share (38--49\%) but reward-only SGS fails, while the observation decoder channel (16--22\%) carries the critical $\dt$-specific information driving the fidelity gap. Full-pathway gradient stopping \sgsclaim{} (seed~1 eval \sgseval{}, seed~2 collapsed). Cutting the observation decoder gradient pathway is thus necessary but not sufficient; the 50\% recovery rate points to redundant mechanisms in CIVO's feedback loop that future interventions must address jointly. Third, extending this diagnostic framework to transformer-based world models and continuous-control benchmarks would clarify whether CIVO is RSSM-specific or a broader vulnerability of temporal conditioning in imagination-based RL. Fourth, our findings suggest that freezing the temporal embedding while allowing the gate mechanism to learn (untrained embedding with adaptive horizon selection) may decouple the benefits of temporal abstraction from the CIVO vulnerability, a direction we are actively investigating.
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "6d4f3206-eb20-491c-a566-cbcf603ae55c",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/conclusion.tex",
      "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nWe have presented a systematic factorial diagnostic of temporal abstraction in DreamerV3 across two continuous-control environments. The analysis identifies the combination of trained $\\dt$-embedding and multi-rate data exposure as the causal factor behind conditioning-induced value overestimation (CIVO). The key findings are:\n\n\\begin{enumerate}[nosep,leftmargin=*]\n\\item Every variable-rate imagination configuration degrades relative to the $\\dt{=}1$ baseline, with degradation scaling monotonically with $\\dt$.\n\\item A normalized value-to-eval threshold of $\\nve \\geq 1.5\\times$ (35K+ window) achieves 15/16 CIVO classification ($n{=}16$, 93.8\\%), with the single false positive arising from a mechanistically distinct non-CIVO collapse. The combination of trained $\\dt$-embedding and multi-rate data exposure is the causal factor; unexposed, frozen, or removed embeddings prevent overestimation.\n\\item The RSSM reward head develops a $2.78\\times$ prediction gap between $\\dt{=}1$ and $\\dt{=}2$ under trained conditioning. This systematic bias drives critic overestimation.\n\\item The same CIVO trigger produces stochastic downstream outcomes (full collapse and transient CIVO with self-correction) across seeds of identical configurations.\n\\item Restricting imagination to $\\dt{=}1$ does not fully prevent collapse: two of four seeds fail (50\\%) via two qualitatively distinct pathways, one CIVO-driven with entropy decrease and one entropy-driven with entropy increase. The bimodal distribution, with no intermediate outcomes, confirms that the trained $\\dt$-embedding creates vulnerability through multiple independent mechanisms.\n\\item A lightweight online detector that monitors the dynamics of the value-to-evaluation ratio identifies CIVO onset with 100\\% sensitivity across five positive cases, with predictive detection (alert before performance degradation) in two of five. A timing guideline ($<$70K steps = high confidence) separates genuine CIVO from late-stage false positives.\n\\end{enumerate}\n\nThe contrast with TAWM's success in MPC identifies the feedback architecture as the critical factor: $\\dt$-conditioning succeeds when errors are contained by re-planning from real states, but fails when errors compound through imagination-based actor-critic bootstrapping.\n\n\\paragraph{Limitations.}\nOur primary factorial analysis focuses on Walker Walk; cross-environment evidence (Cheetah Run) is confirmed across two seeds but limited to a single trigger configuration. Both use a single world-model architecture (DreamerV3/RSSM). Generalization to other environments and architectures, particularly transformer-based world models such as DreamerV4, remains an open question. The $\\nve$ threshold ($1.5\\times$, 35K+ window) is sensitive to value overestimation broadly but not perfectly specific to CIVO (15/16, one non-CIVO false positive); generalization to other tasks and architectures is pending validation. The detector's thresholds were calibrated on thirteen runs across three environments; generalization to different reward scales and architectures requires further validation. Whether the protection conferred by removing the temporal embedding persists beyond 105K training steps also remains open: one control seed (009c, seed~2) exhibited NVE rising to $1.14\\times$ at 105K steps on an upward trajectory, suggesting that longer training horizons may eventually erode this safeguard.\n\n\\paragraph{Future directions.}\nOur findings suggest three avenues. First, hierarchical temporal abstraction at the representation level (as in THICK and Hieros) may avoid the flat-conditioning failure mode by maintaining separate dynamics for each temporal scale. Second, gradient decomposition reveals that gradient importance is decoupled from magnitude: the reward head provides the largest share (38--49\\%) but reward-only SGS fails, while the observation decoder channel (16--22\\%) carries the critical $\\dt$-specific information driving the fidelity gap. Full-pathway gradient stopping \\sgsclaim{} (seed~1 eval \\sgseval{}, seed~2 collapsed). Cutting the observation decoder gradient pathway is thus necessary but not sufficient; the 50\\% recovery rate points to redundant mechanisms in CIVO's feedback loop that future interventions must address jointly. Third, extending this diagnostic framework to transformer-based world models and continuous-control benchmarks would clarify whether CIVO is RSSM-specific or a broader vulnerability of temporal conditioning in imagination-based RL. Fourth, our findings suggest that freezing the temporal embedding while allowing the gate mechanism to learn (untrained embedding with adaptive horizon selection) may decouple the benefits of temporal abstraction from the CIVO vulnerability, a direction we are actively investigating.\n",
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

_source line 10_

<details open><summary>🔧 Tool call — Read · `toolu_01CDQnp8r9FC2gKiR8kqZBJF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "394b4335-27a9-458f-a93f-f0ab2aa38af0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019zUGGy1wVqbUx8zfqePjoH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13925,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13925
      },
      "output_tokens": 36,
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

_source line 11 · 2026-05-18T14:24:33.566Z_

<details><summary>↩ Tool result · `toolu_01CDQnp8r9FC2gKiR8kqZBJF`</summary>

```text
1	% --- APPENDIX ---
2	
3	\section{Complete Experimental Results}
4	\label{sec:complete_results}
5	
6	Table~\ref{tab:complete_results} reports all 26 experimental configurations. The main text (Table~\ref{tab:main_results}) presents the subset most relevant to the causal argument; this table includes the additional variable-rate configurations (006, 007, 005), multi-seed factorial runs (009b, 008d\_s3, 008d\_s4), SGS interventions (018), cross-environment seeds (010b\_s0), and mitigation experiments (008e\_v3).
7	
8	\begin{table*}[t]
9	\centering
10	\caption{Complete experimental results. NVE reports peak $\nve$ in the 35K+ window (\S\ref{sec:metrics}). CIVO-positive seeds are shaded; $\dagger$\,marks a false positive (non-CIVO collapse with elevated NVE).}
11	\label{tab:complete_results}
12	\footnotesize
13	\setlength{\tabcolsep}{4pt}
14	\begin{tabular}{llcccccl}
15	\toprule
16	\textbf{Exp} & \textbf{Config} & \textbf{dt\_emb} & \textbf{Sub} & \textbf{H} & \textbf{Eval@final} & \textbf{NVE} & \textbf{Outcome} \\
17	\midrule
18	001 & Baseline ($\dt{=}1$) & --- & --- & 15 & 915.7 @105K & 1.00$\times$ & Healthy \\
19	\rowcolor{gray!15}
20	006 & Fixed $\dt{=}2$ & trn & ON & 15 & 132.9 @65K & 4.83$\times$ & Collapsed \\
21	007 & Fixed $\dt{=}4$ & trn & ON & 15 & 152.5 @55K & --- & Collapsed \\
22	005 & Learned gate & adaptive & OFF & 15 & 98.8 @145K & --- & Collapsed \\
23	\midrule
24	\rowcolor{gray!15}
25	008d & Factorial (s1) & trn & ON & 8 & 82.8 @55K & 4.12$\times$ & Full collapse \\
26	\rowcolor{gray!15}
27	009b & Factorial (s2) & trn & ON & 8 & 267.9 @105K & 1.62$\times$ & Transient CIVO \\
28	\rowcolor{gray!15}
29	008d\_s3 & Factorial (s3) & trn & ON & 8 & 268$^\diamond$ @105K & 1.53$\times$ & Late-onset collapse \\
30	\rowcolor{gray!15}
31	008d\_s4 & Factorial (s4) & trn & ON & 8 & 63.6 @105K & 3.03$\times$ & Full collapse \\
32	008f & No dt\_emb (s1) & --- & ON & 8 & 503.0 @105K & 0.97$\times$ & Healthy \\
33	008a & Unexposed emb & exp$^a$ & OFF & 15 & 777.7 @105K & 0.93$\times$ & Healthy \\
34	008a\_s1 & Unexposed emb & exp$^a$ & OFF & 15 & 630.9 @105K & 0.43$\times$ & Healthy \\
35	008a\_s2 & Unexposed emb & exp$^a$ & OFF & 15 & 899.4 @105K & 0.51$\times$ & Healthy \\
36	015b & Frozen emb & frz$^b$ & ON & 8 & 204.2 @105K & 1.45$\times$ & Grad.\ starvation \\
37	022b & Frozen emb + Gumbel gate & frz$^b$ & ON & 8 & 300.7 @105K & 0.63$\times$ & No CIVO \\
38	\midrule
39	018 s1 & Full-SGS & trn$^\ddagger$ & ON & 8 & \sgseval{} @105K & \sgsnve{}$\times$$^*$ & No collapse \\
40	\rowcolor{gray!15}
41	018 s2 & Full-SGS & trn$^\ddagger$ & ON & 8 & 40.8 @105K & --- & Collapsed \\
42	008e\_v3 s1 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.94$\times$ & Healthy \\
43	008e\_v3 s2$^\dagger$ & Mitigation & trn & ON & 15 & 137.0 @105K & 3.78$\times$ & Non-CIVO collapse \\
44	\rowcolor{gray!15}
45	008e\_v3 s3 & Mitigation & trn & ON & 15 & 92.7 @105K & 4.02$\times$ & CIVO collapse \\
46	008e\_v3 s4 & Mitigation & trn & ON & 15 & 899.3 @105K & 0.99$\times$ & Healthy \\
47	\midrule
48	\multicolumn{8}{l}{\textit{Cross-environment validation}} \\
49	\rowcolor{gray!15}
50	010b & Cheetah Run & trn & ON & 8 & 51.7 @105K & 8.27$\times$ & Collapsed \\
51	\rowcolor{gray!15}
52	010b\_s0 & Cheetah Run & trn & ON & 8 & 0.83 @105K & 70.64$\times$ & Full collapse \\
53	\rowcolor{gray!15}
54	021 & Cheetah Run & trn$^\ddagger$ & ON & 8 & 221.5 @105K & 9.94$\times$$^d$ & Recovery \\
55	024b s0 & Cheetah Run & --- & ON & 8 & 96.5 @105K & $<$0.20$\times$ & Healthy \\
56	024b s1 & Cheetah Run & --- & ON & 8 & 77.3 @105K & 0.10$\times$ & Healthy \\
57	\rowcolor{gray!15}
58	019b & PickCube-v1 & trn & ON & 8 & 26.64 @200K & 3.78$\times$$^c$ & Transient onset \\
59	\bottomrule
60	\end{tabular}
61	\vspace{1pt}
62	{\raggedright\footnotesize
63	trn = trained ($d{=}32$, subsample ON);
64	trn$^\ddagger$ = full-pathway SGS (all non-KL gradients detached);
65	exp$^a$ = trained, subsample OFF;
66	frz$^b$ = frozen ($d{=}32$, \texttt{requires\_grad=False});
67	--- = removed ($d{=}0$).\\
68	$^*$ Seed 1 only: peak NVE with transient exceedances (1.60$\times$ at 35K, 1.66$\times$ at 95K); self-correcting, no sustained escalation. Seed 2 collapsed.\\
69	$^\diamond$ Transitional; train returns still declining (peak 470 to 139 over final 8K steps). Collapse had not reached equilibrium at 105K.\\
70	$^c$ NVE normalized against exp\_019a\_v2 (vanilla DreamerV3 on PickCube-v1).\\
71	$^d$ Peak NVE $9.94\times$ at 45K (transient, self-correcting to $<$1$\times$ by 55K); final eval 221.5.\par}
72	\end{table*}
73	
74	\section{NVE Threshold Sensitivity Analysis}
75	\label{sec:appendix_sensitivity}
76	
77	We report the full sensitivity analysis for the NVE diagnostic framework introduced in Section~\ref{sec:results}. The main text reports Task~B2 (any CIVO detection, $\nve \geq 1.5\times$). Here we additionally present Task~B1, which restricts the positive class to \emph{sustained} CIVO, specifically experiments exhibiting persistent, accelerating value overestimation that progresses to performance collapse. Transient CIVO cases (e.g., exp~009b, which self-corrects after a brief excursion above the threshold) are classified as negative in B1.
78	
79	\subsection{Per-Experiment NVE Values}
80	
81	Table~\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all ten factorial experiments (including four 008e\_v3 seeds). Experiments are sorted by descending NVE. Experiment 008e\_v3\_s2 exhibits elevated NVE ($3.78\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\_v3\_s3 exhibits CIVO with NVE $4.02\times$ despite $\Delta t{=}1$ imagination.
82	
83	\begin{table}[h]
84	\centering
85	\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\ = transient CIVO with self-correction.}
86	\label{tab:nve_raw}
87	\small
88	\begin{tabular}{@{}lrccc@{}}
89	\toprule
90	Experiment & NVE & Mechanism & B1 & B2 \\
91	\midrule
92	006          & 4.84 & sustained CIVO & $+$ & $+$ \\
93	008d         & 4.13 & sustained CIVO & $+$ & $+$ \\
94	008e\_v3\_s3 & 4.02 & CIVO           & $+$ & $+$ \\
95	008e\_v3\_s2 & 3.78 & IRD (non-CIVO) & $-$ & $-$ \\
96	009b         & 1.62 & transient CIVO & $-$ & $+$ \\
97	001          & 1.00 & non-CIVO       & $-$ & $-$ \\
98	008e\_v3\_s4 & 0.99 & non-CIVO       & $-$ & $-$ \\
99	008f         & 0.97 & non-CIVO       & $-$ & $-$ \\
100	008e\_v3\_s1 & 0.94 & non-CIVO       & $-$ & $-$ \\
101	008a         & 0.93 & non-CIVO       & $-$ & $-$ \\
102	\bottomrule
103	\end{tabular}
104	\end{table}
105	
106	\subsection{Multi-Threshold Classification Performance}
107	
108	Table~\ref{tab:sensitivity_b1} reports Task~B1 classification metrics across six NVE thresholds. Task~B1 achieves $\text{AUROC} = 1.000$ because the minimum positive NVE ($4.02\times$, exp~008e\_v3\_s3) exceeds the maximum negative NVE ($3.78\times$, exp~008e\_v3\_s2), yielding perfect rank separation. The optimal threshold lies in the interval $(3.78, 4.02]$; we report $\geq 3.9\times$ as a representative value. Table~\ref{tab:sensitivity_b2} provides the corresponding analysis for Task~B2 ($\text{AUROC} = 0.958$, imperfect separation due to 008e\_v3\_s2).
109	
110	\begin{table*}[t]
111	\centering
112	\caption{\textbf{Task~B1}: Sustained CIVO detection sensitivity analysis ($n_{\text{pos}}=3$, $n_{\text{neg}}=7$, $n=10$, $\text{AUROC}=1.000$). All confidence intervals are two-sided Clopper-Pearson exact binomial ($\alpha=0.05$). $^\dagger$Optimal threshold in $(3.78, 4.02]$.}
113	\label{tab:sensitivity_b1}
114	\small
115	\setlength{\tabcolsep}{5pt}
116	\begin{tabular}{@{}lcccccccc@{}}
117	\toprule
118	Threshold & TP & FP & FN & TN & Accuracy [95\% CI] & Precision & Recall & F1 \\
119	\midrule
120	$\geq 1.0\times$ & 3 & 3 & 0 & 4 & 70.0\% \; [34.8, 93.3] & 50.0\% & 100\% & 66.7\% \\
121	$\geq 1.2\times$ & 3 & 2 & 0 & 5 & 80.0\% \; [44.4, 97.5] & 60.0\% & 100\% & 75.0\% \\
122	$\geq 1.5\times$ & 3 & 2 & 0 & 5 & 80.0\% \; [44.4, 97.5] & 60.0\% & 100\% & 75.0\% \\
123	\rowcolor{gray!15}
124	$\geq 1.7\times$ & 3 & 1 & 0 & 6 & 90.0\% \; [55.5, 99.7] & 75.0\% & 100\% & 85.7\% \\
125	$\geq 2.0\times$ & 3 & 1 & 0 & 6 & 90.0\% \; [55.5, 99.7] & 75.0\% & 100\% & 85.7\% \\
126	\rowcolor{gray!15}
127	$\geq 3.9\times^\dagger$ & 3 & 0 & 0 & 7 & 100\% \; [69.2, 100] & 100\% & 100\% & 100\% \\
128	\bottomrule
129	\end{tabular}
130	\end{table*}
131	
132	\begin{table*}[t]
133	\centering
134	\caption{\textbf{Task~B2}: Any CIVO detection sensitivity analysis ($n_{\text{pos}}=4$, $n_{\text{neg}}=6$, $n=10$, $\text{AUROC}=0.958$). The single false positive at $\geq 1.5\times$ is 008e\_v3\_s2 (IRD mechanism, not CIVO). The $1.5\times$ threshold (highlighted) maximizes F1 while maintaining perfect recall.}
135	\label{tab:sensitivity_b2}
136	\small
137	\setlength{\tabcolsep}{5pt}
138	\begin{tabular}{@{}lcccccccc@{}}
139	\toprule
140	Threshold & TP & FP & FN & TN & Accuracy [95\% CI] & Precision & Recall & F1 \\
141	\midrule
142	$\geq 1.0\times$ & 4 & 2 & 0 & 4 & 80.0\% \; [44.4, 97.5] & 66.7\% & 100\% & 80.0\% \\
143	$\geq 1.2\times$ & 4 & 1 & 0 & 5 & 90.0\% \; [55.5, 99.7] & 80.0\% & 100\% & 88.9\% \\
144	\rowcolor{gray!15}
145	$\geq 1.5\times$ & 4 & 1 & 0 & 5 & 90.0\% \; [55.5, 99.7] & 80.0\% & 100\% & 88.9\% \\
146	$\geq 1.7\times$ & 3 & 1 & 1 & 5 & 80.0\% \; [44.4, 97.5] & 75.0\% & 75.0\% & 75.0\% \\
147	$\geq 2.0\times$ & 3 & 1 & 1 & 5 & 80.0\% \; [44.4, 97.5] & 75.0\% & 75.0\% & 75.0\% \\
148	$\geq 3.9\times$ & 3 & 0 & 1 & 6 & 90.0\% \; [55.5, 99.7] & 100\% & 75.0\% & 85.7\% \\
149	\bottomrule
150	\end{tabular}
151	\end{table*}
152	
153	\subsection{Threshold Recommendation}
154	
155	For the main diagnostic (Task~B2), we recommend $\nve \geq 1.5\times$ as the operating threshold for three reasons:
156	
157	\begin{enumerate}[nosep,leftmargin=*]
158	\item \textbf{Maximum recall.} The $1.5\times$ threshold achieves 100\% recall, detecting all four CIVO cases including the transient case (009b, $\nve = 1.62\times$). Raising the threshold to $1.7\times$ loses 009b, dropping recall to 75.0\%.
159	\item \textbf{Best F1.} At $1.5\times$, F1 = 88.9\%, the highest among all tested thresholds for B2. The single false positive (008e\_v3\_s2) is mechanistically identifiable as IRD rather than CIVO.
160	\item \textbf{Sensitivity--specificity tradeoff.} Lower thresholds ($1.0\times$) add false positives without gaining true positives. Higher thresholds ($\geq 1.7\times$) sacrifice recall without eliminating the 008e\_v3\_s2 false positive (which requires $\tau > 3.78$).
161	\end{enumerate}
162	
163	For Task~B1 (sustained CIVO only), perfect classification is achievable at $\nve \geq 3.9\times$, but with only $n_{\text{pos}} = 3$ the statistical power remains limited (accuracy 95\% CI: [69.2\%, 100\%]).
164	
165	\paragraph{Limitations.} With $n = 10$ experiments, Clopper-Pearson confidence intervals remain wide (e.g., 90.0\% accuracy has 95\% CI [55.5\%, 99.7\%]). These results should be interpreted as a diagnostic proof-of-concept rather than a validated clinical threshold. Replication across additional environments and seeds is needed to establish tighter bounds.
166	
167	% --- APPENDIX B: Factorial Ablation Details ---
168	
169	\section{Factorial Ablation Details}
170	\label{sec:appendix_factorial}
171	
172	This appendix provides the full factorial ablation results summarized in \S\ref{sec:f3f5_summary} of the main text.
173	
174	\subsection{F3: Unexposed Temporal Embedding Suppresses Value Drift}
175	\label{sec:f3}
176	
177	\begin{figure}[t]
178	\centering
179	\includegraphics[width=\columnwidth]{figures/paper/fig3_factorial_grid.pdf}
180	\caption{Factorial isolation of CIVO trigger. Only the combination of trained $e_{\dt}$ and multi-rate data (upper-left cell) produces pathological NVE. Neither factor alone is sufficient.}
181	\label{fig:factorial_grid}
182	\end{figure}
183	
184	The causal claim that trained embedding \emph{plus} multi-rate exposure jointly trigger CIVO rests on two complementary controls that each remove one factor while holding the other constant.
185	
186	\paragraph{Evidence A: exposure is necessary (exp\_008a).}
187	Exp\_008a uses a trained embedding ($d{=}32$, gradients enabled) that is never exposed to $\dt{>}1$ transitions during world-model training (subsample OFF). Despite sharing the same embedding architecture as exp\_008d, its NVE remains in the $0.43$--$0.93\times$ range across 3 seeds (105K steps). Performance follows two V-shaped recovery cycles, reaching 777.7 at 105K (85\% of baseline). The critical trigger is not the embedding's capacity to represent temporal information, but its adaptation to multi-rate data that enables precise but inaccurate $\dt{>}1$ state predictions within the RSSM.
188	
189	This contrasts with exp\_006 (trained $e_{\dt}$, subsample ON, $H{=}15$), where NVE accelerates from $1.61\times$ at 45K to $2.31\times$ at 55K before catastrophic collapse to 132.9 at 65K. Both experiments use identical trained embeddings ($d{=}32$, gradients enabled) and $H{=}15$, differing only in whether the world model sees $\dt{>}1$ transitions during training, confirming that multi-rate data exposure, not embedding architecture, is the operative variable.
190	
191	\paragraph{Evidence B: trainability is necessary (exp\_015b).}
192	Exp\_015b uses a frozen random-projection embedding ($d{=}32$, \texttt{requires\_grad=False}, subsample ON, $H{=}8$), the same multi-rate data regime as exp\_008d, but with a non-trainable temporal signal. Despite full exposure to $\dt{>}1$ transitions, the NVE peaks at $1.45\times$ at 55K but does not sustain escalation: it retreats to $0.65\times$ by 65K and settles at $0.55\times$ by 105K (trajectory: $0.81 \rightarrow 1.26 \rightarrow 1.45 \rightarrow 0.65 \rightarrow 1.05 \rightarrow 0.60 \rightarrow 0.59 \rightarrow 0.55$). The transient peak approaches but does not exceed the $1.5\times$ CIVO threshold, and critically, the ratio self-corrects rather than exhibiting the monotonic escalation seen in trained-embedding runs. Final evaluation reaches only 204.2 at 105K, low but through a qualitatively different failure mode than CIVO. Actor loss approaches zero (gradient starvation; see \S\ref{sec:pathways}), indicating that the frozen embedding provides no useful gradient signal for temporal adaptation.
193	
194	The contrast with exp\_008d is stark: under identical data conditions (subsample ON, $H{=}8$), the trained embedding drives NVE to $4.12\times$ with sustained monotonic escalation ($1.78 \rightarrow 1.71 \rightarrow 2.09 \rightarrow 4.12$) and triggers full collapse (eval 82.8), while the frozen embedding peaks transiently at $1.45\times$ before self-correcting to $0.55\times$, a qualitative difference between sustained and transient overestimation. This demonstrates that a $\dt$-embedding must be able to \emph{co-adapt} with RSSM dynamics to produce the systematic reward-prediction bias that drives CIVO; a static random projection, regardless of its exposure to multi-rate data, cannot create this bias.
195	
196	Together, these two controls establish that CIVO requires the \emph{joint} presence of (i)~a trainable embedding that can co-adapt with RSSM dynamics, and (ii)~multi-rate training data that drives this co-adaptation toward biased temporal predictions. Neither factor alone is sufficient.
197	
198	Cross-environment validation on Cheetah Run replicates the causal pattern: trained $e_{\dt}$ triggers CIVO in both tested seeds (exp\_010b, 2 seeds, NVE $8.27$--$70.64\times$, collapse to 51.7/0.83) while removing the embedding eliminates it (exp\_024b, 2 seeds, NVE $<0.2\times$, eval 96.5/77.3). This extends the necessary-condition finding from Walker Walk to a second locomotion environment with qualitatively different dynamics (6-joint vs.\ 2-joint).
199	
200	\begin{table}[h]
201	\centering
202	\small
203	\caption{Causal isolation: $e_{\dt}$ configuration $\times$ multi-rate data exposure. The combination of trained embedding and multi-rate exposure is the sole trigger for CIVO. Neither factor alone is sufficient.}
204	\label{tab:causal_matrix}
205	\begin{tabular}{lcc}
206	\toprule
207	& Multi-rate data (\textsc{on}) & Single-rate data (\textsc{off}) \\
208	\midrule
209	Trained $e_{\dt}$ & exp\_008d: \textbf{CIVO} & exp\_008a: healthy \\
210	 & NVE 4.12$\times$, collapse & NVE 0.93$\times$ \\
211	\midrule
212	Frozen $e_{\dt}$ & exp\_015b: grad.\ starvation & --- \\
213	 & peak NVE 1.45$\times$ (transient) & \\
214	\midrule
215	Removed $e_{\dt}$ & exp\_008f: no CIVO & --- \\
216	 & NVE $\leq$0.97$\times$ & \\
217	\bottomrule
218	\end{tabular}
219	\end{table}
220	
221	Only the upper-left cell (trained embedding with multi-rate exposure) triggers CIVO (Table~\ref{tab:causal_matrix}). This 2$\times$2 structure establishes that both factors are jointly necessary.
222	
223	\subsection{F4: Degradation Scales Monotonically with \texorpdfstring{$\dt$}{dt}}
224	\label{sec:f4}
225	
226	\begin{figure}[t]
227	\centering
228	\includegraphics[width=\columnwidth]{figures/paper/fig5_dt_amplification.pdf}
229	\caption{Peak evaluation return as a function of imagination $\dt$. Performance degrades monotonically: $\dt{=}1$ (915.7) $>$ $\dt{=}2$ (485.3, $-47\%$) $>$ $\dt{=}4$ (176.9, $-81\%$).}
230	\label{fig:dt_amplification}
231	\end{figure}
232	
233	The magnitude of degradation scales monotonically with the imagination step size (Figure~\ref{fig:dt_amplification}). From the $\dt{=}1$ baseline (915.7 at 105K), fixed $\dt{=}2$ (exp\_006) achieves a peak of only 485.3 ($-47\%$), and fixed $\dt{=}4$ (exp\_007) peaks at 176.9 ($-81\%$). This monotonic relationship is consistent with compounding model error: larger temporal gaps amplify the RSSM's prediction inaccuracy at each imagination step, and these errors accumulate across the rollout horizon.
234	
235	\subsection{F5: Imagination Horizon and Subsampling Are Secondary Factors}
236	\label{sec:f5}
237	
238	Neither horizon length nor temporal subsampling triggers collapse without multi-rate data exposure: both trained-but-unexposed configurations (008a, 008c) maintain $\nve < 0.93\times$ (\S\ref{sec:f3}), while the trained-and-exposed counterpart (008d) collapses with $\nve = 4.12\times$.  The no-embedding configurations show cross-seed variance (008f: 503.0 vs.\ 009c: 148.3) but neither exhibits $\nve > 1.5\times$, confirming that low evaluation alone does not indicate CIVO.
239	
240	The $3.2\times$ performance gap (008a: 777.7 vs.\ 008c: 240.9) quantifies the horizon effect independently of CIVO, as both conditions maintain healthy NVE ($\leq$0.93$\times$).
241	
242	% --- APPENDIX C: Full Analysis & Discussion ---
243	
244	\section{Full Analysis \& Discussion}
245	\label{sec:appendix_analysis}
246	
247	This appendix provides the complete mechanistic analysis summarized in Section~\ref{sec:discussion} of the main text.
248	
249	\subsection{The CIVO Mechanism}
250	\label{sec:civo_mechanism}
251	
252	The RSSM fidelity analysis (Table~\ref{tab:rssm_fidelity}) reveals the mechanistic core of CIVO.  The trained $\dt$-embedding enables the reward head to learn temporally differentiated predictions, but these predictions are asymmetrically accurate: reward MAE at $\dt{=}1$ is $0.0568$, while at $\dt{=}2$ it rises to $0.1579$, a $2.78\times$ gap.  This gap is not an artifact of prediction difficulty alone; the no-embedding configuration (008f) exhibits a $1.01\times$ gap, and the baseline shows $1.56\times$.  The trained embedding actively amplifies the fidelity discrepancy by allowing the reward head to co-adapt with the temporal signal.
253	
254	This asymmetric fidelity initiates a feedback loop with four stages: (1) the trained $\dt$-embedding causes RSSM predictions at $\dt > 1$ to carry systematically biased reward estimates; (2) the critic, trained entirely on imagined trajectories, internalizes these biased rewards as optimistic value estimates; (3) the actor exploits the overestimated regions of the value landscape, shifting its policy toward states that appear high-value only under the biased model; and (4) this policy shift further skews the distribution of imagined states, reinforcing the bias.  The diagnostic signature is a sustained $\nve$ above $1.5\times$, followed by evaluation collapse.
255	
256	A random-policy control experiment ($N{=}100$ rollouts, 95\% bootstrap CI) decomposes CIVO into two necessary stages.  \textbf{Stage~1 (dynamics bias):} even under a random policy, $\dt{=}2$ imagination produces $1.68\times$ higher mean reward than $\dt{=}1$ in the trained-embedding model (008d): the RSSM prior already generates reward-favorable trajectories at $\dt > 1$, independent of actor behavior.  \textbf{Stage~2 (actor exploitation):} the trained actor learns to exploit these biased regions, amplifying the ratio to $2.90\times$.  In the no-embedding control (008f), neither stage is present: the random-policy ratio is $1.11\times$ and the trained-actor ratio is $0.98\times$.  The decomposition attributes $\approx 36\%$ of the total effect to dynamics bias and $\approx 64\%$ to actor exploitation, confirming that both stages are necessary for CIVO to manifest.
257	
258	This mechanism is analogous to delusional bias \citep{lu2018nondelusional}, but differs in origin: delusional bias arises from policy-class constraints, while CIVO is model-induced: the reward head's co-adaptation with the temporal embedding produces systematically upward-biased predictions at $\dt > 1$.  The consequence (policy exploitation of overestimated regions) is similar, but the causal pathway is distinct.
259	
260	\subsection{Selective Gradient Stopping and Gradient Decomposition}
261	\label{sec:sgs_gradient_analysis}
262	
263	\subsubsection{Gradient Decomposition Results}
264	\label{sec:gradient_decomposition}
265	
266	\begin{figure}[t]
267	\centering
268	\includegraphics[width=0.75\columnwidth]{figures/fig3_gradient_decomposition.pdf}
269	\caption{Gradient contribution to $e_{\Delta t}$ by loss component at two training checkpoints. The reward head contributes the largest share (38--49\%) yet reward-only SGS (exp\_016e) fails; the observation decoder channel (16--22\%) carries the critical $\dt$-specific spatial information that drives the RSSM fidelity gap.}
270	\label{fig:gradient_decomp}
271	\end{figure}
272	
273	Exp\_016e collapses in the same qualitative pattern as the unmodified control: peak evaluation 326.7 at 75K steps followed by catastrophic decline to 31.7 at 95K, with NVE reaching $10.42\times$. The SGS intervention neither prevented nor attenuated CIVO.
274	
275	To explain this null result, we performed a gradient decomposition analysis using \texttt{torch.autograd.grad} to measure each loss component's contribution to $\nabla_\theta e_{\Delta t}$, where $\theta$ denotes the temporal embedding parameters. Table~\ref{tab:gradient_decomposition} reports the results.
276	
277	\begin{table}[h]
278	\centering
279	\caption{Gradient contributions to the temporal embedding $e_{\Delta t}$ by loss component, measured via \texttt{torch.autograd.grad} with training configuration \texttt{gate\_fixed\_dt=2}. Gradient norms are $\ell_2$ norms of $\nabla_\theta \mathcal{L}_i$ for each loss $\mathcal{L}_i$.}
280	\label{tab:gradient_decomposition}
281	\small
282	\begin{tabular}{lrrrr}
283	\toprule
284	& \multicolumn{2}{c}{\textbf{@55K}} & \multicolumn{2}{c}{\textbf{@112K}} \\
285	\cmidrule(lr){2-3} \cmidrule(lr){4-5}
286	Loss component & Share & (\%) & Share & (\%) \\
287	\midrule
288	Reward head & --- & 49.0 & --- & 38.1 \\
289	KL dynamics & --- & 34.7 & --- & 40.4 \\
290	Observation decoders & --- & 16.3 & --- & 21.5 \\
291	\bottomrule
292	\end{tabular}
293	\end{table}
294	
295	The gradient decomposition reveals a counterintuitive structure: the reward head provides the largest gradient contribution (49.0\% at 55K, 38.1\% at 112K), yet reward-only SGS (exp\_016e) fails catastrophically (NVE $10.42\times$). The observation decoder channel contributes the smallest share (16.3\% at 55K, 21.5\% at 112K) yet carries the critical $\dt$-specific spatial information.  This dissociation between gradient magnitude and causal importance explains why exp\_016e, which targets the largest pathway, is functionally insufficient for CIVO prevention.
296	
297	The gradient structure is relatively stable across training (reward shifts from 49\% to 38\%, obs from 16\% to 22\%, KL from 35\% to 40\%), unlike what a magnitude-based account would predict. The reward head's large gradient contribution reflects the scalar reward prediction task's sensitivity to temporal embedding parameters, but this gradient does not encode $\Delta t$-specific structural information about spatial dynamics. The observation decoder channel, despite its smaller magnitude, is the only pathway that encodes how the RSSM should differentially predict multi-dimensional proprioceptive states across temporal scales.
298	
299	\paragraph{Why the smallest channel is causally critical.} The observation decoder is the only loss component whose gradients encode how the RSSM should differentially predict multi-dimensional proprioceptive states ($14$ orientations, $9$ velocities, $1$ height) across temporal scales.  This $\dt$-specific spatial information shapes the latent state representation in ways that propagate to reward prediction: the RSSM fidelity gap ($2.78\times$ reward MAE ratio, Table~\ref{tab:rssm_fidelity}) arises because the temporal embedding learns to produce latent states that are spatially biased at $\dt{>}1$, not because the reward head directly learns scale-dependent biases.  Full-SGS targets this causal chain by preventing observation-decoder gradients from updating $e_{\Delta t}$, though its 50\% recovery rate (1/2 seeds) indicates that breaking the gradient pathway alone does not fully eliminate the vulnerability.
300	
301	\subsubsection{Implications for the CIVO Mechanism}
302	\label{sec:sgs_implications}
303	
304	The gradient decomposition reveals that gradient magnitude and causal importance are decoupled in CIVO.
305	
306	\paragraph{Gradient importance $\neq$ gradient magnitude.} The reward head contributes the largest gradient share (38--49\%) to $e_{\Delta t}$, yet reward-only SGS fails.  The observation decoder contributes the smallest share (16--22\%), yet its removal (via Full-SGS) is necessary for CIVO mitigation.  This dissociation arises because the reward head's gradient, while large, does not encode $\dt$-specific structural information: it adjusts $e_{\Delta t}$ to minimize a scalar prediction error that is largely $\dt$-invariant.  The observation decoder's gradient, though smaller, encodes how the RSSM should differentially reconstruct 24-dimensional proprioceptive states across temporal scales. This is the channel through which $e_{\Delta t}$ learns scale-dependent latent biases.
307	
308	\paragraph{Reframing the intervention target.} Any gradient-level strategy that targets the reward head alone (reward prediction regularization, reward-conditioned value clipping, or reward-only SGS) targets the largest pathway but not the informationally critical one.  The failure of exp\_016e (NVE $10.42\times$) despite detaching the dominant gradient source confirms this.  Full-pathway SGS (exp\_018) detaches $e_{\Delta t}$ from all non-KL gradients, retaining only the KL dynamics contribution (34--40\%).  However, this intervention yields mixed results: seed~1 avoids collapse (eval 448.3) while seed~2 collapses (eval 40.8), indicating that removing the observation decoder gradient channel is necessary but not sufficient.
309	
310	Cross-environment validation on Cheetah Run (exp\_021) further clarifies the role of Full-SGS.  The intervention did not prevent the initial CIVO onset: NVE peaked at $9.94\times$ at 45K (comparable to the unmitigated exp\_010b's $8.27\times$).  However, unlike exp\_010b, which collapsed permanently to eval 51.7, exp\_021 self-corrected within ${\sim}$10K steps, with sustained NVE dropping to $0.34\times$ (55K--105K) and final evaluation recovering to 221.5.  This pattern reframes Full-SGS as \emph{enabling recovery from CIVO} rather than preventing its onset: the gradient detachment constrains value growth after the transient spike, allowing the critic to recalibrate.  Performance nonetheless remains at 38.7\% of baseline (572.5), likely because Full-SGS over-aggressively blocks actor gradients (actor gradient norms near zero throughout training).  Combined with exp\_018's mixed Walker results (1/2 seeds), these findings indicate that gradient-level interventions alone do not fully eliminate the CIVO vulnerability, and that additional mechanisms (e.g., forward-pass conditioning effects, residual capacity-dependent instabilities) operate beyond the gradient pathway.
311	
312	\paragraph{Connection to RSSM fidelity analysis.} The trained-embedding condition (exp\_008d) shows a $2.78\times$ reward gap between $\Delta t{=}1$ and $\Delta t{=}2$ transitions (Table~\ref{tab:rssm_fidelity}).  This gap arises because the observation decoder gradients shape $e_{\Delta t}$ to produce latent states that are spatially biased at $\dt{>}1$, and the reward head inherits these biases \textit{through the latent state} rather than learning them directly.  The reward head's large gradient contribution reflects sensitivity to $e_{\Delta t}$'s parameters but not causal responsibility for the fidelity gap.
313	
314	\subsubsection{Entropy Dynamics Across Configurations}
315	\label{sec:entropy_dynamics}
316	
317	\begin{figure}[h]
318	\centering
319	\includegraphics[width=0.85\columnwidth]{figures/fig4_entropy_dynamics.pdf}
320	\caption{Actor entropy trajectories for three configurations. All start at ${\sim}8$ nats and converge to similar values (${\sim}{-}4.5$ to ${-}5$). The CIVO-triggering configuration (008d, red) follows a normal entropy reduction trajectory; the divergence from the control (008f) is subtle in entropy space, consistent with CIVO operating through the value channel rather than the entropy channel. 018v2 (Full-SGS, seed~1) shows slightly lower terminal entropy.}
321	\label{fig:entropy_dynamics}
322	\end{figure}
323	
324	\subsubsection{Exp\_016e Reinterpreted as Stochastic Variation}
325	\label{sec:016e_reinterp}
326	
327	The gradient decomposition establishes that exp\_016e targets the largest gradient pathway (reward: 38--49\%) but not the informationally critical one (observation decoders: 16--22\%).  The apparent timing differences between exp\_016e and exp\_008d (later collapse onset, 75K vs.\ 25K, and higher peak evaluation, 326.7 vs.\ 167.2) must be attributed to stochastic variation rather than SGS effects, since the critical observation decoder channel remains intact.  All three trajectories (exp\_008d, exp\_009b, exp\_016e) share the invariant identified by the NVE diagnostic: each crosses the $1.5\times$ pathological threshold at some point during training.
328	
329	\subsection{Post-CIVO Outcomes: Why Seeds Diverge}
330	\label{sec:seed_divergence}
331	
332	\begin{table}[h]
333	\centering
334	\caption{Post-CIVO outcomes for the 008d configuration. Peak/Final NVE measured in the 35K+ window.}
335	\label{tab:post_civo}
336	\footnotesize
337	\setlength{\tabcolsep}{3pt}
338	\begin{tabular}{lcccl}
339	\toprule
340	\textbf{Seed} & \textbf{Peak} & \textbf{Final} & \textbf{Eval} & \textbf{Outcome} \\
341	\midrule
342	s1 (008d) & 4.12$\times$ & 4.12$\times$ & 82.8 & Full collapse \\
343	s2 (009b) & 1.62$\times$ & 0.38$\times$ & 267.9 & Transient CIVO \\
344	\bottomrule
345	\end{tabular}
346	\end{table}
347	
348	The two post-CIVO outcomes (Table~\ref{tab:post_civo}), full collapse and transient CIVO with self-correction, both cross the $\nve > 1.5\times$ threshold, yet the downstream damage is stochastic.\footnote{Exp\_009e was excluded from multi-seed analyses due to a seed configuration error (default seed=0, identical to exp\_008d).}  Bootstrap resampling ($B{=}10000$) over the $n{=}2$ effective seeds yields peak NVE mean $3.085$ (95\% CI: $[2.05, 4.12]$), collapse rate $0.5$, and Cohen's $d = 2.60$ (mean difference $2.205$) relative to the no-embedding control, confirming a large effect despite the limited sample.  We hypothesize that the divergence relates to the critic's representational capacity at the time of CIVO onset.  \citet{lyle2022capacity} demonstrate that deep RL networks suffer progressive capacity loss, in which early-learned features become increasingly difficult to overwrite.  If the critic's capacity is already partially consumed when CIVO injects overestimation, the network cannot recalibrate (seed~0); if sufficient capacity remains, the critic can absorb transient overestimation and recover (seed~2).
349	
350	\subsection{Why MPC Is Immune}
351	\label{sec:mpc_immune}
352	
353	\citet{nhu2025tawm} show that $\dt$-conditioning benefits TD-MPC2, raising the question of why it fails in DreamerV3.  The critical difference is that MPC re-plans from real states at every step, so imagination errors do not accumulate into the training signal because there is no critic bootstrapping from imagined trajectories.  In DreamerV3, the actor-critic trains entirely within imagination, and any systematic reward-prediction bias at $\dt > 1$ is amplified through the closed actor-critic loop.
354	
355	\subsection{The \texorpdfstring{$\dt$}{dt}-Embedding Dilemma}
356	\label{sec:embedding_dilemma}
357	
358	The factorial results reveal a fundamental tension: removing the $\dt$-embedding (008f) eliminates CIVO but at a $13\times$ cost to reward prediction quality ($0.7469$ vs.\ $0.0568$ MAE), as the world model cannot distinguish temporal scales.  Restricting imagination to $\dt{=}1$ while retaining the trained embedding (008e\_v3) avoids collapse in 2 of 4 seeds (50\%), while the remaining two collapse via distinct mechanisms: Pathway~A (CIVO-driven, entropy decrease; s3, NVE $4.02\times$) and Pathway~B (entropy-driven, entropy increase; s2, NVE $3.78\times$; \S\ref{sec:f6}).  Neither approach alone provides a complete solution.
359	
360	\subsection{Multiple Vulnerability Pathways}
361	\label{sec:pathways}
362	
363	The two collapse mechanisms identified in \S\ref{sec:f6}, CIVO (Pathway~A, value-driven, entropy decreasing) and non-CIVO instability (Pathway~B, eval-driven, entropy increasing), have distinct diagnostic signatures but a shared root cause: the trained $\dt$-embedding's learned features affect both reward prediction across temporal scales (Pathway~A) and the representation space in which the actor operates (Pathway~B).  This explains why $\nve$ is sensitive but not perfectly specific: Pathway~B's late evaluation decline inflates $\nve$ through the same arithmetic as CIVO, yielding the sole false positive ($3.78\times$ for 008e\_v3 s2).  Distinguishing the two requires examining the temporal profile and entropy direction of collapse.
364	
365	\subsection{Implications for Temporal Abstraction in World Models}
366	\label{sec:implications}
367	
368	CIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \citep{gumbsch2024thick}, Hieros \citep{mattes2024hieros}, LS-Imagine \citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.
369	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "46f91eda-fe70-451b-bbcd-817ba0558f65",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
      "content": "% --- APPENDIX ---\n\n\\section{Complete Experimental Results}\n\\label{sec:complete_results}\n\nTable~\\ref{tab:complete_results} reports all 26 experimental configurations. The main text (Table~\\ref{tab:main_results}) presents the subset most relevant to the causal argument; this table includes the additional variable-rate configurations (006, 007, 005), multi-seed factorial runs (009b, 008d\\_s3, 008d\\_s4), SGS interventions (018), cross-environment seeds (010b\\_s0), and mitigation experiments (008e\\_v3).\n\n\\begin{table*}[t]\n\\centering\n\\caption{Complete experimental results. NVE reports peak $\\nve$ in the 35K+ window (\\S\\ref{sec:metrics}). CIVO-positive seeds are shaded; $\\dagger$\\,marks a false positive (non-CIVO collapse with elevated NVE).}\n\\label{tab:complete_results}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llcccccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{dt\\_emb} & \\textbf{Sub} & \\textbf{H} & \\textbf{Eval@final} & \\textbf{NVE} & \\textbf{Outcome} \\\\\n\\midrule\n001 & Baseline ($\\dt{=}1$) & --- & --- & 15 & 915.7 @105K & 1.00$\\times$ & Healthy \\\\\n\\rowcolor{gray!15}\n006 & Fixed $\\dt{=}2$ & trn & ON & 15 & 132.9 @65K & 4.83$\\times$ & Collapsed \\\\\n007 & Fixed $\\dt{=}4$ & trn & ON & 15 & 152.5 @55K & --- & Collapsed \\\\\n005 & Learned gate & adaptive & OFF & 15 & 98.8 @145K & --- & Collapsed \\\\\n\\midrule\n\\rowcolor{gray!15}\n008d & Factorial (s1) & trn & ON & 8 & 82.8 @55K & 4.12$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n009b & Factorial (s2) & trn & ON & 8 & 267.9 @105K & 1.62$\\times$ & Transient CIVO \\\\\n\\rowcolor{gray!15}\n008d\\_s3 & Factorial (s3) & trn & ON & 8 & 268$^\\diamond$ @105K & 1.53$\\times$ & Late-onset collapse \\\\\n\\rowcolor{gray!15}\n008d\\_s4 & Factorial (s4) & trn & ON & 8 & 63.6 @105K & 3.03$\\times$ & Full collapse \\\\\n008f & No dt\\_emb (s1) & --- & ON & 8 & 503.0 @105K & 0.97$\\times$ & Healthy \\\\\n008a & Unexposed emb & exp$^a$ & OFF & 15 & 777.7 @105K & 0.93$\\times$ & Healthy \\\\\n008a\\_s1 & Unexposed emb & exp$^a$ & OFF & 15 & 630.9 @105K & 0.43$\\times$ & Healthy \\\\\n008a\\_s2 & Unexposed emb & exp$^a$ & OFF & 15 & 899.4 @105K & 0.51$\\times$ & Healthy \\\\\n015b & Frozen emb & frz$^b$ & ON & 8 & 204.2 @105K & 1.45$\\times$ & Grad.\\ starvation \\\\\n022b & Frozen emb + Gumbel gate & frz$^b$ & ON & 8 & 300.7 @105K & 0.63$\\times$ & No CIVO \\\\\n\\midrule\n018 s1 & Full-SGS & trn$^\\ddagger$ & ON & 8 & \\sgseval{} @105K & \\sgsnve{}$\\times$$^*$ & No collapse \\\\\n\\rowcolor{gray!15}\n018 s2 & Full-SGS & trn$^\\ddagger$ & ON & 8 & 40.8 @105K & --- & Collapsed \\\\\n008e\\_v3 s1 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.94$\\times$ & Healthy \\\\\n008e\\_v3 s2$^\\dagger$ & Mitigation & trn & ON & 15 & 137.0 @105K & 3.78$\\times$ & Non-CIVO collapse \\\\\n\\rowcolor{gray!15}\n008e\\_v3 s3 & Mitigation & trn & ON & 15 & 92.7 @105K & 4.02$\\times$ & CIVO collapse \\\\\n008e\\_v3 s4 & Mitigation & trn & ON & 15 & 899.3 @105K & 0.99$\\times$ & Healthy \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cross-environment validation}} \\\\\n\\rowcolor{gray!15}\n010b & Cheetah Run & trn & ON & 8 & 51.7 @105K & 8.27$\\times$ & Collapsed \\\\\n\\rowcolor{gray!15}\n010b\\_s0 & Cheetah Run & trn & ON & 8 & 0.83 @105K & 70.64$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n021 & Cheetah Run & trn$^\\ddagger$ & ON & 8 & 221.5 @105K & 9.94$\\times$$^d$ & Recovery \\\\\n024b s0 & Cheetah Run & --- & ON & 8 & 96.5 @105K & $<$0.20$\\times$ & Healthy \\\\\n024b s1 & Cheetah Run & --- & ON & 8 & 77.3 @105K & 0.10$\\times$ & Healthy \\\\\n\\rowcolor{gray!15}\n019b & PickCube-v1 & trn & ON & 8 & 26.64 @200K & 3.78$\\times$$^c$ & Transient onset \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize\ntrn = trained ($d{=}32$, subsample ON);\ntrn$^\\ddagger$ = full-pathway SGS (all non-KL gradients detached);\nexp$^a$ = trained, subsample OFF;\nfrz$^b$ = frozen ($d{=}32$, \\texttt{requires\\_grad=False});\n--- = removed ($d{=}0$).\\\\\n$^*$ Seed 1 only: peak NVE with transient exceedances (1.60$\\times$ at 35K, 1.66$\\times$ at 95K); self-correcting, no sustained escalation. Seed 2 collapsed.\\\\\n$^\\diamond$ Transitional; train returns still declining (peak 470 to 139 over final 8K steps). Collapse had not reached equilibrium at 105K.\\\\\n$^c$ NVE normalized against exp\\_019a\\_v2 (vanilla DreamerV3 on PickCube-v1).\\\\\n$^d$ Peak NVE $9.94\\times$ at 45K (transient, self-correcting to $<$1$\\times$ by 55K); final eval 221.5.\\par}\n\\end{table*}\n\n\\section{NVE Threshold Sensitivity Analysis}\n\\label{sec:appendix_sensitivity}\n\nWe report the full sensitivity analysis for the NVE diagnostic framework introduced in Section~\\ref{sec:results}. The main text reports Task~B2 (any CIVO detection, $\\nve \\geq 1.5\\times$). Here we additionally present Task~B1, which restricts the positive class to \\emph{sustained} CIVO, specifically experiments exhibiting persistent, accelerating value overestimation that progresses to performance collapse. Transient CIVO cases (e.g., exp~009b, which self-corrects after a brief excursion above the threshold) are classified as negative in B1.\n\n\\subsection{Per-Experiment NVE Values}\n\nTable~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all ten factorial experiments (including four 008e\\_v3 seeds). Experiments are sorted by descending NVE. Experiment 008e\\_v3\\_s2 exhibits elevated NVE ($3.78\\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\\_v3\\_s3 exhibits CIVO with NVE $4.02\\times$ despite $\\Delta t{=}1$ imagination.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\\ = transient CIVO with self-correction.}\n\\label{tab:nve_raw}\n\\small\n\\begin{tabular}{@{}lrccc@{}}\n\\toprule\nExperiment & NVE & Mechanism & B1 & B2 \\\\\n\\midrule\n006          & 4.84 & sustained CIVO & $+$ & $+$ \\\\\n008d         & 4.13 & sustained CIVO & $+$ & $+$ \\\\\n008e\\_v3\\_s3 & 4.02 & CIVO           & $+$ & $+$ \\\\\n008e\\_v3\\_s2 & 3.78 & IRD (non-CIVO) & $-$ & $-$ \\\\\n009b         & 1.62 & transient CIVO & $-$ & $+$ \\\\\n001          & 1.00 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s4 & 0.99 & non-CIVO       & $-$ & $-$ \\\\\n008f         & 0.97 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s1 & 0.94 & non-CIVO       & $-$ & $-$ \\\\\n008a         & 0.93 & non-CIVO       & $-$ & $-$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Multi-Threshold Classification Performance}\n\nTable~\\ref{tab:sensitivity_b1} reports Task~B1 classification metrics across six NVE thresholds. Task~B1 achieves $\\text{AUROC} = 1.000$ because the minimum positive NVE ($4.02\\times$, exp~008e\\_v3\\_s3) exceeds the maximum negative NVE ($3.78\\times$, exp~008e\\_v3\\_s2), yielding perfect rank separation. The optimal threshold lies in the interval $(3.78, 4.02]$; we report $\\geq 3.9\\times$ as a representative value. Table~\\ref{tab:sensitivity_b2} provides the corresponding analysis for Task~B2 ($\\text{AUROC} = 0.958$, imperfect separation due to 008e\\_v3\\_s2).\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B1}: Sustained CIVO detection sensitivity analysis ($n_{\\text{pos}}=3$, $n_{\\text{neg}}=7$, $n=10$, $\\text{AUROC}=1.000$). All confidence intervals are two-sided Clopper-Pearson exact binomial ($\\alpha=0.05$). $^\\dagger$Optimal threshold in $(3.78, 4.02]$.}\n\\label{tab:sensitivity_b1}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 3 & 3 & 0 & 4 & 70.0\\% \\; [34.8, 93.3] & 50.0\\% & 100\\% & 66.7\\% \\\\\n$\\geq 1.2\\times$ & 3 & 2 & 0 & 5 & 80.0\\% \\; [44.4, 97.5] & 60.0\\% & 100\\% & 75.0\\% \\\\\n$\\geq 1.5\\times$ & 3 & 2 & 0 & 5 & 80.0\\% \\; [44.4, 97.5] & 60.0\\% & 100\\% & 75.0\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.7\\times$ & 3 & 1 & 0 & 6 & 90.0\\% \\; [55.5, 99.7] & 75.0\\% & 100\\% & 85.7\\% \\\\\n$\\geq 2.0\\times$ & 3 & 1 & 0 & 6 & 90.0\\% \\; [55.5, 99.7] & 75.0\\% & 100\\% & 85.7\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 3.9\\times^\\dagger$ & 3 & 0 & 0 & 7 & 100\\% \\; [69.2, 100] & 100\\% & 100\\% & 100\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B2}: Any CIVO detection sensitivity analysis ($n_{\\text{pos}}=4$, $n_{\\text{neg}}=6$, $n=10$, $\\text{AUROC}=0.958$). The single false positive at $\\geq 1.5\\times$ is 008e\\_v3\\_s2 (IRD mechanism, not CIVO). The $1.5\\times$ threshold (highlighted) maximizes F1 while maintaining perfect recall.}\n\\label{tab:sensitivity_b2}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 4 & 2 & 0 & 4 & 80.0\\% \\; [44.4, 97.5] & 66.7\\% & 100\\% & 80.0\\% \\\\\n$\\geq 1.2\\times$ & 4 & 1 & 0 & 5 & 90.0\\% \\; [55.5, 99.7] & 80.0\\% & 100\\% & 88.9\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.5\\times$ & 4 & 1 & 0 & 5 & 90.0\\% \\; [55.5, 99.7] & 80.0\\% & 100\\% & 88.9\\% \\\\\n$\\geq 1.7\\times$ & 3 & 1 & 1 & 5 & 80.0\\% \\; [44.4, 97.5] & 75.0\\% & 75.0\\% & 75.0\\% \\\\\n$\\geq 2.0\\times$ & 3 & 1 & 1 & 5 & 80.0\\% \\; [44.4, 97.5] & 75.0\\% & 75.0\\% & 75.0\\% \\\\\n$\\geq 3.9\\times$ & 3 & 0 & 1 & 6 & 90.0\\% \\; [55.5, 99.7] & 100\\% & 75.0\\% & 85.7\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\subsection{Threshold Recommendation}\n\nFor the main diagnostic (Task~B2), we recommend $\\nve \\geq 1.5\\times$ as the operating threshold for three reasons:\n\n\\begin{enumerate}[nosep,leftmargin=*]\n\\item \\textbf{Maximum recall.} The $1.5\\times$ threshold achieves 100\\% recall, detecting all four CIVO cases including the transient case (009b, $\\nve = 1.62\\times$). Raising the threshold to $1.7\\times$ loses 009b, dropping recall to 75.0\\%.\n\\item \\textbf{Best F1.} At $1.5\\times$, F1 = 88.9\\%, the highest among all tested thresholds for B2. The single false positive (008e\\_v3\\_s2) is mechanistically identifiable as IRD rather than CIVO.\n\\item \\textbf{Sensitivity--specificity tradeoff.} Lower thresholds ($1.0\\times$) add false positives without gaining true positives. Higher thresholds ($\\geq 1.7\\times$) sacrifice recall without eliminating the 008e\\_v3\\_s2 false positive (which requires $\\tau > 3.78$).\n\\end{enumerate}\n\nFor Task~B1 (sustained CIVO only), perfect classification is achievable at $\\nve \\geq 3.9\\times$, but with only $n_{\\text{pos}} = 3$ the statistical power remains limited (accuracy 95\\% CI: [69.2\\%, 100\\%]).\n\n\\paragraph{Limitations.} With $n = 10$ experiments, Clopper-Pearson confidence intervals remain wide (e.g., 90.0\\% accuracy has 95\\% CI [55.5\\%, 99.7\\%]). These results should be interpreted as a diagnostic proof-of-concept rather than a validated clinical threshold. Replication across additional environments and seeds is needed to establish tighter bounds.\n\n% --- APPENDIX B: Factorial Ablation Details ---\n\n\\section{Factorial Ablation Details}\n\\label{sec:appendix_factorial}\n\nThis appendix provides the full factorial ablation results summarized in \\S\\ref{sec:f3f5_summary} of the main text.\n\n\\subsection{F3: Unexposed Temporal Embedding Suppresses Value Drift}\n\\label{sec:f3}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig3_factorial_grid.pdf}\n\\caption{Factorial isolation of CIVO trigger. Only the combination of trained $e_{\\dt}$ and multi-rate data (upper-left cell) produces pathological NVE. Neither factor alone is sufficient.}\n\\label{fig:factorial_grid}\n\\end{figure}\n\nThe causal claim that trained embedding \\emph{plus} multi-rate exposure jointly trigger CIVO rests on two complementary controls that each remove one factor while holding the other constant.\n\n\\paragraph{Evidence A: exposure is necessary (exp\\_008a).}\nExp\\_008a uses a trained embedding ($d{=}32$, gradients enabled) that is never exposed to $\\dt{>}1$ transitions during world-model training (subsample OFF). Despite sharing the same embedding architecture as exp\\_008d, its NVE remains in the $0.43$--$0.93\\times$ range across 3 seeds (105K steps). Performance follows two V-shaped recovery cycles, reaching 777.7 at 105K (85\\% of baseline). The critical trigger is not the embedding's capacity to represent temporal information, but its adaptation to multi-rate data that enables precise but inaccurate $\\dt{>}1$ state predictions within the RSSM.\n\nThis contrasts with exp\\_006 (trained $e_{\\dt}$, subsample ON, $H{=}15$), where NVE accelerates from $1.61\\times$ at 45K to $2.31\\times$ at 55K before catastrophic collapse to 132.9 at 65K. Both experiments use identical trained embeddings ($d{=}32$, gradients enabled) and $H{=}15$, differing only in whether the world model sees $\\dt{>}1$ transitions during training, confirming that multi-rate data exposure, not embedding architecture, is the operative variable.\n\n\\paragraph{Evidence B: trainability is necessary (exp\\_015b).}\nExp\\_015b uses a frozen random-projection embedding ($d{=}32$, \\texttt{requires\\_grad=False}, subsample ON, $H{=}8$), the same multi-rate data regime as exp\\_008d, but with a non-trainable temporal signal. Despite full exposure to $\\dt{>}1$ transitions, the NVE peaks at $1.45\\times$ at 55K but does not sustain escalation: it retreats to $0.65\\times$ by 65K and settles at $0.55\\times$ by 105K (trajectory: $0.81 \\rightarrow 1.26 \\rightarrow 1.45 \\rightarrow 0.65 \\rightarrow 1.05 \\rightarrow 0.60 \\rightarrow 0.59 \\rightarrow 0.55$). The transient peak approaches but does not exceed the $1.5\\times$ CIVO threshold, and critically, the ratio self-corrects rather than exhibiting the monotonic escalation seen in trained-embedding runs. Final evaluation reaches only 204.2 at 105K, low but through a qualitatively different failure mode than CIVO. Actor loss approaches zero (gradient starvation; see \\S\\ref{sec:pathways}), indicating that the frozen embedding provides no useful gradient signal for temporal adaptation.\n\nThe contrast with exp\\_008d is stark: under identical data conditions (subsample ON, $H{=}8$), the trained embedding drives NVE to $4.12\\times$ with sustained monotonic escalation ($1.78 \\rightarrow 1.71 \\rightarrow 2.09 \\rightarrow 4.12$) and triggers full collapse (eval 82.8), while the frozen embedding peaks transiently at $1.45\\times$ before self-correcting to $0.55\\times$, a qualitative difference between sustained and transient overestimation. This demonstrates that a $\\dt$-embedding must be able to \\emph{co-adapt} with RSSM dynamics to produce the systematic reward-prediction bias that drives CIVO; a static random projection, regardless of its exposure to multi-rate data, cannot create this bias.\n\nTogether, these two controls establish that CIVO requires the \\emph{joint} presence of (i)~a trainable embedding that can co-adapt with RSSM dynamics, and (ii)~multi-rate training data that drives this co-adaptation toward biased temporal predictions. Neither factor alone is sufficient.\n\nCross-environment validation on Cheetah Run replicates the causal pattern: trained $e_{\\dt}$ triggers CIVO in both tested seeds (exp\\_010b, 2 seeds, NVE $8.27$--$70.64\\times$, collapse to 51.7/0.83) while removing the embedding eliminates it (exp\\_024b, 2 seeds, NVE $<0.2\\times$, eval 96.5/77.3). This extends the necessary-condition finding from Walker Walk to a second locomotion environment with qualitatively different dynamics (6-joint vs.\\ 2-joint).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Causal isolation: $e_{\\dt}$ configuration $\\times$ multi-rate data exposure. The combination of trained embedding and multi-rate exposure is the sole trigger for CIVO. Neither factor alone is sufficient.}\n\\label{tab:causal_matrix}\n\\begin{tabular}{lcc}\n\\toprule\n& Multi-rate data (\\textsc{on}) & Single-rate data (\\textsc{off}) \\\\\n\\midrule\nTrained $e_{\\dt}$ & exp\\_008d: \\textbf{CIVO} & exp\\_008a: healthy \\\\\n & NVE 4.12$\\times$, collapse & NVE 0.93$\\times$ \\\\\n\\midrule\nFrozen $e_{\\dt}$ & exp\\_015b: grad.\\ starvation & --- \\\\\n & peak NVE 1.45$\\times$ (transient) & \\\\\n\\midrule\nRemoved $e_{\\dt}$ & exp\\_008f: no CIVO & --- \\\\\n & NVE $\\leq$0.97$\\times$ & \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOnly the upper-left cell (trained embedding with multi-rate exposure) triggers CIVO (Table~\\ref{tab:causal_matrix}). This 2$\\times$2 structure establishes that both factors are jointly necessary.\n\n\\subsection{F4: Degradation Scales Monotonically with \\texorpdfstring{$\\dt$}{dt}}\n\\label{sec:f4}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig5_dt_amplification.pdf}\n\\caption{Peak evaluation return as a function of imagination $\\dt$. Performance degrades monotonically: $\\dt{=}1$ (915.7) $>$ $\\dt{=}2$ (485.3, $-47\\%$) $>$ $\\dt{=}4$ (176.9, $-81\\%$).}\n\\label{fig:dt_amplification}\n\\end{figure}\n\nThe magnitude of degradation scales monotonically with the imagination step size (Figure~\\ref{fig:dt_amplification}). From the $\\dt{=}1$ baseline (915.7 at 105K), fixed $\\dt{=}2$ (exp\\_006) achieves a peak of only 485.3 ($-47\\%$), and fixed $\\dt{=}4$ (exp\\_007) peaks at 176.9 ($-81\\%$). This monotonic relationship is consistent with compounding model error: larger temporal gaps amplify the RSSM's prediction inaccuracy at each imagination step, and these errors accumulate across the rollout horizon.\n\n\\subsection{F5: Imagination Horizon and Subsampling Are Secondary Factors}\n\\label{sec:f5}\n\nNeither horizon length nor temporal subsampling triggers collapse without multi-rate data exposure: both trained-but-unexposed configurations (008a, 008c) maintain $\\nve < 0.93\\times$ (\\S\\ref{sec:f3}), while the trained-and-exposed counterpart (008d) collapses with $\\nve = 4.12\\times$.  The no-embedding configurations show cross-seed variance (008f: 503.0 vs.\\ 009c: 148.3) but neither exhibits $\\nve > 1.5\\times$, confirming that low evaluation alone does not indicate CIVO.\n\nThe $3.2\\times$ performance gap (008a: 777.7 vs.\\ 008c: 240.9) quantifies the horizon effect independently of CIVO, as both conditions maintain healthy NVE ($\\leq$0.93$\\times$).\n\n% --- APPENDIX C: Full Analysis & Discussion ---\n\n\\section{Full Analysis \\& Discussion}\n\\label{sec:appendix_analysis}\n\nThis appendix provides the complete mechanistic analysis summarized in Section~\\ref{sec:discussion} of the main text.\n\n\\subsection{The CIVO Mechanism}\n\\label{sec:civo_mechanism}\n\nThe RSSM fidelity analysis (Table~\\ref{tab:rssm_fidelity}) reveals the mechanistic core of CIVO.  The trained $\\dt$-embedding enables the reward head to learn temporally differentiated predictions, but these predictions are asymmetrically accurate: reward MAE at $\\dt{=}1$ is $0.0568$, while at $\\dt{=}2$ it rises to $0.1579$, a $2.78\\times$ gap.  This gap is not an artifact of prediction difficulty alone; the no-embedding configuration (008f) exhibits a $1.01\\times$ gap, and the baseline shows $1.56\\times$.  The trained embedding actively amplifies the fidelity discrepancy by allowing the reward head to co-adapt with the temporal signal.\n\nThis asymmetric fidelity initiates a feedback loop with four stages: (1) the trained $\\dt$-embedding causes RSSM predictions at $\\dt > 1$ to carry systematically biased reward estimates; (2) the critic, trained entirely on imagined trajectories, internalizes these biased rewards as optimistic value estimates; (3) the actor exploits the overestimated regions of the value landscape, shifting its policy toward states that appear high-value only under the biased model; and (4) this policy shift further skews the distribution of imagined states, reinforcing the bias.  The diagnostic signature is a sustained $\\nve$ above $1.5\\times$, followed by evaluation collapse.\n\nA random-policy control experiment ($N{=}100$ rollouts, 95\\% bootstrap CI) decomposes CIVO into two necessary stages.  \\textbf{Stage~1 (dynamics bias):} even under a random policy, $\\dt{=}2$ imagination produces $1.68\\times$ higher mean reward than $\\dt{=}1$ in the trained-embedding model (008d): the RSSM prior already generates reward-favorable trajectories at $\\dt > 1$, independent of actor behavior.  \\textbf{Stage~2 (actor exploitation):} the trained actor learns to exploit these biased regions, amplifying the ratio to $2.90\\times$.  In the no-embedding control (008f), neither stage is present: the random-policy ratio is $1.11\\times$ and the trained-actor ratio is $0.98\\times$.  The decomposition attributes $\\approx 36\\%$ of the total effect to dynamics bias and $\\approx 64\\%$ to actor exploitation, confirming that both stages are necessary for CIVO to manifest.\n\nThis mechanism is analogous to delusional bias \\citep{lu2018nondelusional}, but differs in origin: delusional bias arises from policy-class constraints, while CIVO is model-induced: the reward head's co-adaptation with the temporal embedding produces systematically upward-biased predictions at $\\dt > 1$.  The consequence (policy exploitation of overestimated regions) is similar, but the causal pathway is distinct.\n\n\\subsection{Selective Gradient Stopping and Gradient Decomposition}\n\\label{sec:sgs_gradient_analysis}\n\n\\subsubsection{Gradient Decomposition Results}\n\\label{sec:gradient_decomposition}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/fig3_gradient_decomposition.pdf}\n\\caption{Gradient contribution to $e_{\\Delta t}$ by loss component at two training checkpoints. The reward head contributes the largest share (38--49\\%) yet reward-only SGS (exp\\_016e) fails; the observation decoder channel (16--22\\%) carries the critical $\\dt$-specific spatial information that drives the RSSM fidelity gap.}\n\\label{fig:gradient_decomp}\n\\end{figure}\n\nExp\\_016e collapses in the same qualitative pattern as the unmodified control: peak evaluation 326.7 at 75K steps followed by catastrophic decline to 31.7 at 95K, with NVE reaching $10.42\\times$. The SGS intervention neither prevented nor attenuated CIVO.\n\nTo explain this null result, we performed a gradient decomposition analysis using \\texttt{torch.autograd.grad} to measure each loss component's contribution to $\\nabla_\\theta e_{\\Delta t}$, where $\\theta$ denotes the temporal embedding parameters. Table~\\ref{tab:gradient_decomposition} reports the results.\n\n\\begin{table}[h]\n\\centering\n\\caption{Gradient contributions to the temporal embedding $e_{\\Delta t}$ by loss component, measured via \\texttt{torch.autograd.grad} with training configuration \\texttt{gate\\_fixed\\_dt=2}. Gradient norms are $\\ell_2$ norms of $\\nabla_\\theta \\mathcal{L}_i$ for each loss $\\mathcal{L}_i$.}\n\\label{tab:gradient_decomposition}\n\\small\n\\begin{tabular}{lrrrr}\n\\toprule\n& \\multicolumn{2}{c}{\\textbf{@55K}} & \\multicolumn{2}{c}{\\textbf{@112K}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nLoss component & Share & (\\%) & Share & (\\%) \\\\\n\\midrule\nReward head & --- & 49.0 & --- & 38.1 \\\\\nKL dynamics & --- & 34.7 & --- & 40.4 \\\\\nObservation decoders & --- & 16.3 & --- & 21.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe gradient decomposition reveals a counterintuitive structure: the reward head provides the largest gradient contribution (49.0\\% at 55K, 38.1\\% at 112K), yet reward-only SGS (exp\\_016e) fails catastrophically (NVE $10.42\\times$). The observation decoder channel contributes the smallest share (16.3\\% at 55K, 21.5\\% at 112K) yet carries the critical $\\dt$-specific spatial information.  This dissociation between gradient magnitude and causal importance explains why exp\\_016e, which targets the largest pathway, is functionally insufficient for CIVO prevention.\n\nThe gradient structure is relatively stable across training (reward shifts from 49\\% to 38\\%, obs from 16\\% to 22\\%, KL from 35\\% to 40\\%), unlike what a magnitude-based account would predict. The reward head's large gradient contribution reflects the scalar reward prediction task's sensitivity to temporal embedding parameters, but this gradient does not encode $\\Delta t$-specific structural information about spatial dynamics. The observation decoder channel, despite its smaller magnitude, is the only pathway that encodes how the RSSM should differentially predict multi-dimensional proprioceptive states across temporal scales.\n\n\\paragraph{Why the smallest channel is causally critical.} The observation decoder is the only loss component whose gradients encode how the RSSM should differentially predict multi-dimensional proprioceptive states ($14$ orientations, $9$ velocities, $1$ height) across temporal scales.  This $\\dt$-specific spatial information shapes the latent state representation in ways that propagate to reward prediction: the RSSM fidelity gap ($2.78\\times$ reward MAE ratio, Table~\\ref{tab:rssm_fidelity}) arises because the temporal embedding learns to produce latent states that are spatially biased at $\\dt{>}1$, not because the reward head directly learns scale-dependent biases.  Full-SGS targets this causal chain by preventing observation-decoder gradients from updating $e_{\\Delta t}$, though its 50\\% recovery rate (1/2 seeds) indicates that breaking the gradient pathway alone does not fully eliminate the vulnerability.\n\n\\subsubsection{Implications for the CIVO Mechanism}\n\\label{sec:sgs_implications}\n\nThe gradient decomposition reveals that gradient magnitude and causal importance are decoupled in CIVO.\n\n\\paragraph{Gradient importance $\\neq$ gradient magnitude.} The reward head contributes the largest gradient share (38--49\\%) to $e_{\\Delta t}$, yet reward-only SGS fails.  The observation decoder contributes the smallest share (16--22\\%), yet its removal (via Full-SGS) is necessary for CIVO mitigation.  This dissociation arises because the reward head's gradient, while large, does not encode $\\dt$-specific structural information: it adjusts $e_{\\Delta t}$ to minimize a scalar prediction error that is largely $\\dt$-invariant.  The observation decoder's gradient, though smaller, encodes how the RSSM should differentially reconstruct 24-dimensional proprioceptive states across temporal scales. This is the channel through which $e_{\\Delta t}$ learns scale-dependent latent biases.\n\n\\paragraph{Reframing the intervention target.} Any gradient-level strategy that targets the reward head alone (reward prediction regularization, reward-conditioned value clipping, or reward-only SGS) targets the largest pathway but not the informationally critical one.  The failure of exp\\_016e (NVE $10.42\\times$) despite detaching the dominant gradient source confirms this.  Full-pathway SGS (exp\\_018) detaches $e_{\\Delta t}$ from all non-KL gradients, retaining only the KL dynamics contribution (34--40\\%).  However, this intervention yields mixed results: seed~1 avoids collapse (eval 448.3) while seed~2 collapses (eval 40.8), indicating that removing the observation decoder gradient channel is necessary but not sufficient.\n\nCross-environment validation on Cheetah Run (exp\\_021) further clarifies the role of Full-SGS.  The intervention did not prevent the initial CIVO onset: NVE peaked at $9.94\\times$ at 45K (comparable to the unmitigated exp\\_010b's $8.27\\times$).  However, unlike exp\\_010b, which collapsed permanently to eval 51.7, exp\\_021 self-corrected within ${\\sim}$10K steps, with sustained NVE dropping to $0.34\\times$ (55K--105K) and final evaluation recovering to 221.5.  This pattern reframes Full-SGS as \\emph{enabling recovery from CIVO} rather than preventing its onset: the gradient detachment constrains value growth after the transient spike, allowing the critic to recalibrate.  Performance nonetheless remains at 38.7\\% of baseline (572.5), likely because Full-SGS over-aggressively blocks actor gradients (actor gradient norms near zero throughout training).  Combined with exp\\_018's mixed Walker results (1/2 seeds), these findings indicate that gradient-level interventions alone do not fully eliminate the CIVO vulnerability, and that additional mechanisms (e.g., forward-pass conditioning effects, residual capacity-dependent instabilities) operate beyond the gradient pathway.\n\n\\paragraph{Connection to RSSM fidelity analysis.} The trained-embedding condition (exp\\_008d) shows a $2.78\\times$ reward gap between $\\Delta t{=}1$ and $\\Delta t{=}2$ transitions (Table~\\ref{tab:rssm_fidelity}).  This gap arises because the observation decoder gradients shape $e_{\\Delta t}$ to produce latent states that are spatially biased at $\\dt{>}1$, and the reward head inherits these biases \\textit{through the latent state} rather than learning them directly.  The reward head's large gradient contribution reflects sensitivity to $e_{\\Delta t}$'s parameters but not causal responsibility for the fidelity gap.\n\n\\subsubsection{Entropy Dynamics Across Configurations}\n\\label{sec:entropy_dynamics}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.85\\columnwidth]{figures/fig4_entropy_dynamics.pdf}\n\\caption{Actor entropy trajectories for three configurations. All start at ${\\sim}8$ nats and converge to similar values (${\\sim}{-}4.5$ to ${-}5$). The CIVO-triggering configuration (008d, red) follows a normal entropy reduction trajectory; the divergence from the control (008f) is subtle in entropy space, consistent with CIVO operating through the value channel rather than the entropy channel. 018v2 (Full-SGS, seed~1) shows slightly lower terminal entropy.}\n\\label{fig:entropy_dynamics}\n\\end{figure}\n\n\\subsubsection{Exp\\_016e Reinterpreted as Stochastic Variation}\n\\label{sec:016e_reinterp}\n\nThe gradient decomposition establishes that exp\\_016e targets the largest gradient pathway (reward: 38--49\\%) but not the informationally critical one (observation decoders: 16--22\\%).  The apparent timing differences between exp\\_016e and exp\\_008d (later collapse onset, 75K vs.\\ 25K, and higher peak evaluation, 326.7 vs.\\ 167.2) must be attributed to stochastic variation rather than SGS effects, since the critical observation decoder channel remains intact.  All three trajectories (exp\\_008d, exp\\_009b, exp\\_016e) share the invariant identified by the NVE diagnostic: each crosses the $1.5\\times$ pathological threshold at some point during training.\n\n\\subsection{Post-CIVO Outcomes: Why Seeds Diverge}\n\\label{sec:seed_divergence}\n\n\\begin{table}[h]\n\\centering\n\\caption{Post-CIVO outcomes for the 008d configuration. Peak/Final NVE measured in the 35K+ window.}\n\\label{tab:post_civo}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{lcccl}\n\\toprule\n\\textbf{Seed} & \\textbf{Peak} & \\textbf{Final} & \\textbf{Eval} & \\textbf{Outcome} \\\\\n\\midrule\ns1 (008d) & 4.12$\\times$ & 4.12$\\times$ & 82.8 & Full collapse \\\\\ns2 (009b) & 1.62$\\times$ & 0.38$\\times$ & 267.9 & Transient CIVO \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe two post-CIVO outcomes (Table~\\ref{tab:post_civo}), full collapse and transient CIVO with self-correction, both cross the $\\nve > 1.5\\times$ threshold, yet the downstream damage is stochastic.\\footnote{Exp\\_009e was excluded from multi-seed analyses due to a seed configuration error (default seed=0, identical to exp\\_008d).}  Bootstrap resampling ($B{=}10000$) over the $n{=}2$ effective seeds yields peak NVE mean $3.085$ (95\\% CI: $[2.05, 4.12]$), collapse rate $0.5$, and Cohen's $d = 2.60$ (mean difference $2.205$) relative to the no-embedding control, confirming a large effect despite the limited sample.  We hypothesize that the divergence relates to the critic's representational capacity at the time of CIVO onset.  \\citet{lyle2022capacity} demonstrate that deep RL networks suffer progressive capacity loss, in which early-learned features become increasingly difficult to overwrite.  If the critic's capacity is already partially consumed when CIVO injects overestimation, the network cannot recalibrate (seed~0); if sufficient capacity remains, the critic can absorb transient overestimation and recover (seed~2).\n\n\\subsection{Why MPC Is Immune}\n\\label{sec:mpc_immune}\n\n\\citet{nhu2025tawm} show that $\\dt$-conditioning benefits TD-MPC2, raising the question of why it fails in DreamerV3.  The critical difference is that MPC re-plans from real states at every step, so imagination errors do not accumulate into the training signal because there is no critic bootstrapping from imagined trajectories.  In DreamerV3, the actor-critic trains entirely within imagination, and any systematic reward-prediction bias at $\\dt > 1$ is amplified through the closed actor-critic loop.\n\n\\subsection{The \\texorpdfstring{$\\dt$}{dt}-Embedding Dilemma}\n\\label{sec:embedding_dilemma}\n\nThe factorial results reveal a fundamental tension: removing the $\\dt$-embedding (008f) eliminates CIVO but at a $13\\times$ cost to reward prediction quality ($0.7469$ vs.\\ $0.0568$ MAE), as the world model cannot distinguish temporal scales.  Restricting imagination to $\\dt{=}1$ while retaining the trained embedding (008e\\_v3) avoids collapse in 2 of 4 seeds (50\\%), while the remaining two collapse via distinct mechanisms: Pathway~A (CIVO-driven, entropy decrease; s3, NVE $4.02\\times$) and Pathway~B (entropy-driven, entropy increase; s2, NVE $3.78\\times$; \\S\\ref{sec:f6}).  Neither approach alone provides a complete solution.\n\n\\subsection{Multiple Vulnerability Pathways}\n\\label{sec:pathways}\n\nThe two collapse mechanisms identified in \\S\\ref{sec:f6}, CIVO (Pathway~A, value-driven, entropy decreasing) and non-CIVO instability (Pathway~B, eval-driven, entropy increasing), have distinct diagnostic signatures but a shared root cause: the trained $\\dt$-embedding's learned features affect both reward prediction across temporal scales (Pathway~A) and the representation space in which the actor operates (Pathway~B).  This explains why $\\nve$ is sensitive but not perfectly specific: Pathway~B's late evaluation decline inflates $\\nve$ through the same arithmetic as CIVO, yielding the sole false positive ($3.78\\times$ for 008e\\_v3 s2).  Distinguishing the two requires examining the temporal profile and entropy direction of collapse.\n\n\\subsection{Implications for Temporal Abstraction in World Models}\n\\label{sec:implications}\n\nCIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \\citep{gumbsch2024thick}, Hieros \\citep{mattes2024hieros}, LS-Imagine \\citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \\citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.\n",
      "numLines": 369,
      "startLine": 1,
      "totalLines": 369
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
Now I have all three files. Let me make the three edits:

1. Abstract: Replace the sentence about the detector
2. Conclusion: Add Reproducibility paragraph before Future directions
3. Appendix: Add hyperparameters section at the end

Let me also check for label conflicts - the new table uses `tab:hyperparams` and `sec:hyperparameters`. Let me check if these exist already.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "19dd5cfa-6df9-42d5-aaa0-f68c120a9cf4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Yb3meHhWVNJ9W5AsUKnVNU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14432,
      "cache_read_input_tokens": 25372,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14432
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

执行三处修改。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "6177c716-e2d1-4a41-9022-a758a61d6f3b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Yb3meHhWVNJ9W5AsUKnVNU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14432,
      "cache_read_input_tokens": 25372,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14432
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

<details open><summary>🔧 Tool call — Edit · `toolu_01UeXGgyeRrMx9mAvgMUToFH`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/abstract_body.tex",
  "old_string": "A lightweight online detector that monitors value-to-evaluation ratio dynamics identifies CIVO onset with 100\\% sensitivity (5/5 cases) and provides predictive warning before performance degradation in 2/5 cases, which supports early intervention without a reference baseline.",
  "new_string": "A lightweight online detector that monitors value-to-evaluation ratio dynamics identifies all five CIVO cases (100\\% sensitivity) with no missed detections, including advance warning before performance degradation in two cases. This enables early intervention without a reference baseline."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "4bfc95e2-9156-4272-9ef0-38a7be461353",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Yb3meHhWVNJ9W5AsUKnVNU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14432,
      "cache_read_input_tokens": 25372,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14432
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

_source line 15 · 2026-05-18T14:24:44.680Z_

<details><summary>↩ Tool result · `toolu_01UeXGgyeRrMx9mAvgMUToFH`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/abstract_body.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "9c9a3519-4b7b-45eb-af30-1ed3b4d52707",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/abstract_body.tex",
    "oldString": "A lightweight online detector that monitors value-to-evaluation ratio dynamics identifies CIVO onset with 100\\% sensitivity (5/5 cases) and provides predictive warning before performance degradation in 2/5 cases, which supports early intervention without a reference baseline.",
    "newString": "A lightweight online detector that monitors value-to-evaluation ratio dynamics identifies all five CIVO cases (100\\% sensitivity) with no missed detections, including advance warning before performance degradation in two cases. This enables early intervention without a reference baseline.",
    "originalFile": "Temporal abstraction via variable-rate imagination is a natural extension of world-model reinforcement learning, yet we find that every variable-rate configuration of DreamerV3 degrades performance, despite the success of identical $\\Delta t$-conditioning in MPC-based methods. Through factorial diagnostics on two continuous-control tasks (Walker Walk, Cheetah Run), we identify the combination of trained temporal embedding and multi-rate data exposure as the causal factor and characterize the resulting failure mode: \\emph{conditioning-induced value overestimation} (CIVO). The trained embedding enables the RSSM reward head to develop a $2.78\\times$ prediction gap between $\\Delta t{=}1$ and $\\Delta t{=}2$, which the critic internalizes as optimistic values. This mechanism universally degrades performance to below 30\\% of baseline across all six tested seeds in two environments ($n{=}6$), with five progressing toward full collapse and one self-correcting to a stable but degraded state. Gradient decomposition reveals that despite the reward head providing the largest gradient contribution (38--49\\%), the observation decoder channel (16--22\\%) carries the critical $\\Delta t$-specific spatial information that drives the fidelity gap. Full-pathway gradient stopping partially prevents CIVO but succeeds in only 50\\% of cases; this exposes additional mechanisms beyond gradient-mediated co-adaptation. A lightweight online detector that monitors value-to-evaluation ratio dynamics identifies CIVO onset with 100\\% sensitivity (5/5 cases) and provides predictive warning before performance degradation in 2/5 cases, which supports early intervention without a reference baseline. The contrast with MPC-based methods identifies the feedback architecture (imagination-based bootstrapping versus re-planning) as the structural factor that transforms manageable model imprecision into pathological value dynamics.\n",
    "structuredPatch": [
      {
        "oldStart": 1,
        "oldLines": 1,
        "newStart": 1,
        "newLines": 1,
        "lines": [
          "-Temporal abstraction via variable-rate imagination is a natural extension of world-model reinforcement learning, yet we find that every variable-rate configuration of DreamerV3 degrades performance, despite the success of identical $\\Delta t$-conditioning in MPC-based methods. Through factorial diagnostics on two continuous-control tasks (Walker Walk, Cheetah Run), we identify the combination of trained temporal embedding and multi-rate data exposure as the causal factor and characterize the resulting failure mode: \\emph{conditioning-induced value overestimation} (CIVO). The trained embedding enables the RSSM reward head to develop a $2.78\\times$ prediction gap between $\\Delta t{=}1$ and $\\Delta t{=}2$, which the critic internalizes as optimistic values. This mechanism universally degrades performance to below 30\\% of baseline across all six tested seeds in two environments ($n{=}6$), with five progressing toward full collapse and one self-correcting to a stable but degraded state. Gradient decomposition reveals that despite the reward head providing the largest gradient contribution (38--49\\%), the observation decoder channel (16--22\\%) carries the critical $\\Delta t$-specific spatial information that drives the fidelity gap. Full-pathway gradient stopping partially prevents CIVO but succeeds in only 50\\% of cases; this exposes additional mechanisms beyond gradient-mediated co-adaptation. A lightweight online detector that monitors value-to-evaluation ratio dynamics identifies CIVO onset with 100\\% sensitivity (5/5 cases) and provides predictive warning before performance degradation in 2/5 cases, which supports early intervention without a reference baseline. The contrast with MPC-based methods identifies the feedback architecture (imagination-based bootstrapping versus re-planning) as the structural factor that transforms manageable model imprecision into pathological value dynamics.",
          "+Temporal abstraction via variable-rate imagination is a natural extension of world-model reinforcement learning, yet we find that every variable-rate configuration of DreamerV3 degrades performance, despite the success of identical $\\Delta t$-conditioning in MPC-based methods. Through factorial diagnostics on two continuous-control tasks (Walker Walk, Cheetah Run), we identify the combination of trained temporal embedding and multi-rate data exposure as the causal factor and characterize the resulting failure mode: \\emph{conditioning-induced value overestimation} (CIVO). The trained embedding enables the RSSM reward head to develop a $2.78\\times$ prediction gap between $\\Delta t{=}1$ and $\\Delta t{=}2$, which the critic internalizes as optimistic values. This mechanism universally degrades performance to below 30\\% of baseline across all six tested seeds in two environments ($n{=}6$), with five progressing toward full collapse and one self-correcting to a stable but degraded state. Gradient decomposition reveals that despite the reward head providing the largest gradient contribution (38--49\\%), the observation decoder channel (16--22\\%) carries the critical $\\Delta t$-specific spatial information that drives the fidelity gap. Full-pathway gradient stopping partially prevents CIVO but succeeds in only 50\\% of cases; this exposes additional mechanisms beyond gradient-mediated co-adaptation. A lightweight online detector that monitors value-to-evaluation ratio dynamics identifies all five CIVO cases (100\\% sensitivity) with no missed detections, including advance warning before performance degradation in two cases. This enables early intervention without a reference baseline. The contrast with MPC-based methods identifies the feedback architecture (imagination-based bootstrapping versus re-planning) as the structural factor that transforms manageable model imprecision into pathological value dynamics."
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

_source line 16_

<details open><summary>🔧 Tool call — Edit · `toolu_01KV4Sf8fcPLKDwKTutkW8kZ`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/conclusion.tex",
  "old_string": "\\paragraph{Future directions.}",
  "new_string": "\\paragraph{Reproducibility.}\nCode, experiment configurations, and training logs will be released upon acceptance to facilitate replication of all reported experiments.\n\n\\paragraph{Future directions.}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "213d5d94-77be-4a1e-a2dc-ea01fc61c064",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Yb3meHhWVNJ9W5AsUKnVNU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14432,
      "cache_read_input_tokens": 25372,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14432
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

_source line 17 · 2026-05-18T14:24:47.175Z_

<details><summary>↩ Tool result · `toolu_01KV4Sf8fcPLKDwKTutkW8kZ`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/conclusion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "f7b5e8ee-7b5f-4b21-82a8-a0f088da3abb",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/conclusion.tex",
    "oldString": "\\paragraph{Future directions.}",
    "newString": "\\paragraph{Reproducibility.}\nCode, experiment configurations, and training logs will be released upon acceptance to facilitate replication of all reported experiments.\n\n\\paragraph{Future directions.}",
    "originalFile": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nWe have presented a systematic factorial diagnostic of temporal abstraction in DreamerV3 across two continuous-control environments. The analysis identifies the combination of trained $\\dt$-embedding and multi-rate data exposure as the causal factor behind conditioning-induced value overestimation (CIVO). The key findings are:\n\n\\begin{enumerate}[nosep,leftmargin=*]\n\\item Every variable-rate imagination configuration degrades relative to the $\\dt{=}1$ baseline, with degradation scaling monotonically with $\\dt$.\n\\item A normalized value-to-eval threshold of $\\nve \\geq 1.5\\times$ (35K+ window) achieves 15/16 CIVO classification ($n{=}16$, 93.8\\%), with the single false positive arising from a mechanistically distinct non-CIVO collapse. The combination of trained $\\dt$-embedding and multi-rate data exposure is the causal factor; unexposed, frozen, or removed embeddings prevent overestimation.\n\\item The RSSM reward head develops a $2.78\\times$ prediction gap between $\\dt{=}1$ and $\\dt{=}2$ under trained conditioning. This systematic bias drives critic overestimation.\n\\item The same CIVO trigger produces stochastic downstream outcomes (full collapse and transient CIVO with self-correction) across seeds of identical configurations.\n\\item Restricting imagination to $\\dt{=}1$ does not fully prevent collapse: two of four seeds fail (50\\%) via two qualitatively distinct pathways, one CIVO-driven with entropy decrease and one entropy-driven with entropy increase. The bimodal distribution, with no intermediate outcomes, confirms that the trained $\\dt$-embedding creates vulnerability through multiple independent mechanisms.\n\\item A lightweight online detector that monitors the dynamics of the value-to-evaluation ratio identifies CIVO onset with 100\\% sensitivity across five positive cases, with predictive detection (alert before performance degradation) in two of five. A timing guideline ($<$70K steps = high confidence) separates genuine CIVO from late-stage false positives.\n\\end{enumerate}\n\nThe contrast with TAWM's success in MPC identifies the feedback architecture as the critical factor: $\\dt$-conditioning succeeds when errors are contained by re-planning from real states, but fails when errors compound through imagination-based actor-critic bootstrapping.\n\n\\paragraph{Limitations.}\nOur primary factorial analysis focuses on Walker Walk; cross-environment evidence (Cheetah Run) is confirmed across two seeds but limited to a single trigger configuration. Both use a single world-model architecture (DreamerV3/RSSM). Generalization to other environments and architectures, particularly transformer-based world models such as DreamerV4, remains an open question. The $\\nve$ threshold ($1.5\\times$, 35K+ window) is sensitive to value overestimation broadly but not perfectly specific to CIVO (15/16, one non-CIVO false positive); generalization to other tasks and architectures is pending validation. The detector's thresholds were calibrated on thirteen runs across three environments; generalization to different reward scales and architectures requires further validation. Whether the protection conferred by removing the temporal embedding persists beyond 105K training steps also remains open: one control seed (009c, seed~2) exhibited NVE rising to $1.14\\times$ at 105K steps on an upward trajectory, suggesting that longer training horizons may eventually erode this safeguard.\n\n\\paragraph{Future directions.}\nOur findings suggest three avenues. First, hierarchical temporal abstraction at the representation level (as in THICK and Hieros) may avoid the flat-conditioning failure mode by maintaining separate dynamics for each temporal scale. Second, gradient decomposition reveals that gradient importance is decoupled from magnitude: the reward head provides the largest share (38--49\\%) but reward-only SGS fails, while the observation decoder channel (16--22\\%) carries the critical $\\dt$-specific information driving the fidelity gap. Full-pathway gradient stopping \\sgsclaim{} (seed~1 eval \\sgseval{}, seed~2 collapsed). Cutting the observation decoder gradient pathway is thus necessary but not sufficient; the 50\\% recovery rate points to redundant mechanisms in CIVO's feedback loop that future interventions must address jointly. Third, extending this diagnostic framework to transformer-based world models and continuous-control benchmarks would clarify whether CIVO is RSSM-specific or a broader vulnerability of temporal conditioning in imagination-based RL. Fourth, our findings suggest that freezing the temporal embedding while allowing the gate mechanism to learn (untrained embedding with adaptive horizon selection) may decouple the benefits of temporal abstraction from the CIVO vulnerability, a direction we are actively investigating.\n",
    "structuredPatch": [
      {
        "oldStart": 17,
        "oldLines": 5,
        "newStart": 17,
        "newLines": 8,
        "lines": [
          " \\paragraph{Limitations.}",
          " Our primary factorial analysis focuses on Walker Walk; cross-environment evidence (Cheetah Run) is confirmed across two seeds but limited to a single trigger configuration. Both use a single world-model architecture (DreamerV3/RSSM). Generalization to other environments and architectures, particularly transformer-based world models such as DreamerV4, remains an open question. The $\\nve$ threshold ($1.5\\times$, 35K+ window) is sensitive to value overestimation broadly but not perfectly specific to CIVO (15/16, one non-CIVO false positive); generalization to other tasks and architectures is pending validation. The detector's thresholds were calibrated on thirteen runs across three environments; generalization to different reward scales and architectures requires further validation. Whether the protection conferred by removing the temporal embedding persists beyond 105K training steps also remains open: one control seed (009c, seed~2) exhibited NVE rising to $1.14\\times$ at 105K steps on an upward trajectory, suggesting that longer training horizons may eventually erode this safeguard.",
          " ",
          "+\\paragraph{Reproducibility.}",
          "+Code, experiment configurations, and training logs will be released upon acceptance to facilitate replication of all reported experiments.",
          "+",
          " \\paragraph{Future directions.}",
          " Our findings suggest three avenues. First, hierarchical temporal abstraction at the representation level (as in THICK and Hieros) may avoid the flat-conditioning failure mode by maintaining separate dynamics for each temporal scale. Second, gradient decomposition reveals that gradient importance is decoupled from magnitude: the reward head provides the largest share (38--49\\%) but reward-only SGS fails, while the observation decoder channel (16--22\\%) carries the critical $\\dt$-specific information driving the fidelity gap. Full-pathway gradient stopping \\sgsclaim{} (seed~1 eval \\sgseval{}, seed~2 collapsed). Cutting the observation decoder gradient pathway is thus necessary but not sufficient; the 50\\% recovery rate points to redundant mechanisms in CIVO's feedback loop that future interventions must address jointly. Third, extending this diagnostic framework to transformer-based world models and continuous-control benchmarks would clarify whether CIVO is RSSM-specific or a broader vulnerability of temporal conditioning in imagination-based RL. Fourth, our findings suggest that freezing the temporal embedding while allowing the gate mechanism to learn (untrained embedding with adaptive horizon selection) may decouple the benefits of temporal abstraction from the CIVO vulnerability, a direction we are actively investigating."
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

_source line 18_

<details open><summary>🔧 Tool call — Edit · `toolu_011vHViBbsR8evivwWhEVsg2`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
  "old_string": "CIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \\citep{gumbsch2024thick}, Hieros \\citep{mattes2024hieros}, LS-Imagine \\citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \\citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.",
  "new_string": "CIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \\citep{gumbsch2024thick}, Hieros \\citep{mattes2024hieros}, LS-Imagine \\citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \\citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.\n\n\\section{DreamerV3 Hyperparameters}\n\\label{sec:hyperparameters}\n\nTable~\\ref{tab:hyperparams} lists the DreamerV3 hyperparameters used across all experiments. Unless otherwise noted, we use the default DreamerV3 configuration for continuous-control tasks (\\texttt{dmc\\_proprio}).\n\n\\begin{table}[h]\n\\centering\n\\caption{DreamerV3 hyperparameters for all experiments. Modifications from defaults are marked with $\\diamond$.}\n\\label{tab:hyperparams}\n\\small\n\\begin{tabular}{ll}\n\\toprule\n\\textbf{Parameter} & \\textbf{Value} \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{World Model}} \\\\\nRSSM discrete states & 32 classes $\\times$ 32 categories \\\\\nRSSM stochastic dim & 32 \\\\\nRSSM deterministic dim & 512 \\\\\nMLP hidden size & 512 \\\\\nMLP layers & 2 \\\\\nActivation & SiLU \\\\\nNormalization & LayerNorm \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Training}} \\\\\nBatch size & 16 sequences $\\times$ 64 steps \\\\\nLearning rate & $3 \\times 10^{-4}$ (Adam, $\\epsilon{=}10^{-8}$) \\\\\nSequence length & 64 \\\\\nTraining ratio & 512 \\\\\nFree nats & 1.0 \\\\\nKL balance ($\\alpha$) & 0.8 \\\\\nDiscount ($\\gamma$) & 0.997 \\\\\n$\\lambda$-return & 0.95 \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Policy}} \\\\\nImagination horizon$^\\diamond$ & 8 or 15 (see Table~\\ref{tab:complete_results}) \\\\\nActor entropy scale & $3 \\times 10^{-4}$ \\\\\nActor gradient & Reinforce + dynamics backprop \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Temporal Abstraction}$^\\diamond$} \\\\\nGate enabled & True (all non-baseline) \\\\\nGate fixed $\\dt$ & 1 or 2 (per config) \\\\\nSubsample max $\\dt$ & 1 (OFF) or 2 (ON) \\\\\n$\\dt$-embedding dim & 32 \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Environment}} \\\\\nAction repeat & 2 (Walker Walk, Cheetah Run) \\\\\nObservation & Proprioceptive (no pixels) \\\\\nTotal environment steps & 105K \\\\\nEvaluation frequency & Every 10K steps \\\\\nEvaluation episodes & 10 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "6f3195b5-ca89-42ca-a0a3-134e57047d03",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Yb3meHhWVNJ9W5AsUKnVNU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14432,
      "cache_read_input_tokens": 25372,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14432
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

_source line 19 · 2026-05-18T14:25:02.431Z_

<details><summary>↩ Tool result · `toolu_011vHViBbsR8evivwWhEVsg2`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "21d3a315-94bd-426e-b032-575d80538896",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
    "oldString": "CIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \\citep{gumbsch2024thick}, Hieros \\citep{mattes2024hieros}, LS-Imagine \\citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \\citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.",
    "newString": "CIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \\citep{gumbsch2024thick}, Hieros \\citep{mattes2024hieros}, LS-Imagine \\citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \\citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.\n\n\\section{DreamerV3 Hyperparameters}\n\\label{sec:hyperparameters}\n\nTable~\\ref{tab:hyperparams} lists the DreamerV3 hyperparameters used across all experiments. Unless otherwise noted, we use the default DreamerV3 configuration for continuous-control tasks (\\texttt{dmc\\_proprio}).\n\n\\begin{table}[h]\n\\centering\n\\caption{DreamerV3 hyperparameters for all experiments. Modifications from defaults are marked with $\\diamond$.}\n\\label{tab:hyperparams}\n\\small\n\\begin{tabular}{ll}\n\\toprule\n\\textbf{Parameter} & \\textbf{Value} \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{World Model}} \\\\\nRSSM discrete states & 32 classes $\\times$ 32 categories \\\\\nRSSM stochastic dim & 32 \\\\\nRSSM deterministic dim & 512 \\\\\nMLP hidden size & 512 \\\\\nMLP layers & 2 \\\\\nActivation & SiLU \\\\\nNormalization & LayerNorm \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Training}} \\\\\nBatch size & 16 sequences $\\times$ 64 steps \\\\\nLearning rate & $3 \\times 10^{-4}$ (Adam, $\\epsilon{=}10^{-8}$) \\\\\nSequence length & 64 \\\\\nTraining ratio & 512 \\\\\nFree nats & 1.0 \\\\\nKL balance ($\\alpha$) & 0.8 \\\\\nDiscount ($\\gamma$) & 0.997 \\\\\n$\\lambda$-return & 0.95 \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Policy}} \\\\\nImagination horizon$^\\diamond$ & 8 or 15 (see Table~\\ref{tab:complete_results}) \\\\\nActor entropy scale & $3 \\times 10^{-4}$ \\\\\nActor gradient & Reinforce + dynamics backprop \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Temporal Abstraction}$^\\diamond$} \\\\\nGate enabled & True (all non-baseline) \\\\\nGate fixed $\\dt$ & 1 or 2 (per config) \\\\\nSubsample max $\\dt$ & 1 (OFF) or 2 (ON) \\\\\n$\\dt$-embedding dim & 32 \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Environment}} \\\\\nAction repeat & 2 (Walker Walk, Cheetah Run) \\\\\nObservation & Proprioceptive (no pixels) \\\\\nTotal environment steps & 105K \\\\\nEvaluation frequency & Every 10K steps \\\\\nEvaluation episodes & 10 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}",
    "originalFile": "% --- APPENDIX ---\n\n\\section{Complete Experimental Results}\n\\label{sec:complete_results}\n\nTable~\\ref{tab:complete_results} reports all 26 experimental configurations. The main text (Table~\\ref{tab:main_results}) presents the subset most relevant to the causal argument; this table includes the additional variable-rate configurations (006, 007, 005), multi-seed factorial runs (009b, 008d\\_s3, 008d\\_s4), SGS interventions (018), cross-environment seeds (010b\\_s0), and mitigation experiments (008e\\_v3).\n\n\\begin{table*}[t]\n\\centering\n\\caption{Complete experimental results. NVE reports peak $\\nve$ in the 35K+ window (\\S\\ref{sec:metrics}). CIVO-positive seeds are shaded; $\\dagger$\\,marks a false positive (non-CIVO collapse with elevated NVE).}\n\\label{tab:complete_results}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llcccccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{dt\\_emb} & \\textbf{Sub} & \\textbf{H} & \\textbf{Eval@final} & \\textbf{NVE} & \\textbf{Outcome} \\\\\n\\midrule\n001 & Baseline ($\\dt{=}1$) & --- & --- & 15 & 915.7 @105K & 1.00$\\times$ & Healthy \\\\\n\\rowcolor{gray!15}\n006 & Fixed $\\dt{=}2$ & trn & ON & 15 & 132.9 @65K & 4.83$\\times$ & Collapsed \\\\\n007 & Fixed $\\dt{=}4$ & trn & ON & 15 & 152.5 @55K & --- & Collapsed \\\\\n005 & Learned gate & adaptive & OFF & 15 & 98.8 @145K & --- & Collapsed \\\\\n\\midrule\n\\rowcolor{gray!15}\n008d & Factorial (s1) & trn & ON & 8 & 82.8 @55K & 4.12$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n009b & Factorial (s2) & trn & ON & 8 & 267.9 @105K & 1.62$\\times$ & Transient CIVO \\\\\n\\rowcolor{gray!15}\n008d\\_s3 & Factorial (s3) & trn & ON & 8 & 268$^\\diamond$ @105K & 1.53$\\times$ & Late-onset collapse \\\\\n\\rowcolor{gray!15}\n008d\\_s4 & Factorial (s4) & trn & ON & 8 & 63.6 @105K & 3.03$\\times$ & Full collapse \\\\\n008f & No dt\\_emb (s1) & --- & ON & 8 & 503.0 @105K & 0.97$\\times$ & Healthy \\\\\n008a & Unexposed emb & exp$^a$ & OFF & 15 & 777.7 @105K & 0.93$\\times$ & Healthy \\\\\n008a\\_s1 & Unexposed emb & exp$^a$ & OFF & 15 & 630.9 @105K & 0.43$\\times$ & Healthy \\\\\n008a\\_s2 & Unexposed emb & exp$^a$ & OFF & 15 & 899.4 @105K & 0.51$\\times$ & Healthy \\\\\n015b & Frozen emb & frz$^b$ & ON & 8 & 204.2 @105K & 1.45$\\times$ & Grad.\\ starvation \\\\\n022b & Frozen emb + Gumbel gate & frz$^b$ & ON & 8 & 300.7 @105K & 0.63$\\times$ & No CIVO \\\\\n\\midrule\n018 s1 & Full-SGS & trn$^\\ddagger$ & ON & 8 & \\sgseval{} @105K & \\sgsnve{}$\\times$$^*$ & No collapse \\\\\n\\rowcolor{gray!15}\n018 s2 & Full-SGS & trn$^\\ddagger$ & ON & 8 & 40.8 @105K & --- & Collapsed \\\\\n008e\\_v3 s1 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.94$\\times$ & Healthy \\\\\n008e\\_v3 s2$^\\dagger$ & Mitigation & trn & ON & 15 & 137.0 @105K & 3.78$\\times$ & Non-CIVO collapse \\\\\n\\rowcolor{gray!15}\n008e\\_v3 s3 & Mitigation & trn & ON & 15 & 92.7 @105K & 4.02$\\times$ & CIVO collapse \\\\\n008e\\_v3 s4 & Mitigation & trn & ON & 15 & 899.3 @105K & 0.99$\\times$ & Healthy \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cross-environment validation}} \\\\\n\\rowcolor{gray!15}\n010b & Cheetah Run & trn & ON & 8 & 51.7 @105K & 8.27$\\times$ & Collapsed \\\\\n\\rowcolor{gray!15}\n010b\\_s0 & Cheetah Run & trn & ON & 8 & 0.83 @105K & 70.64$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n021 & Cheetah Run & trn$^\\ddagger$ & ON & 8 & 221.5 @105K & 9.94$\\times$$^d$ & Recovery \\\\\n024b s0 & Cheetah Run & --- & ON & 8 & 96.5 @105K & $<$0.20$\\times$ & Healthy \\\\\n024b s1 & Cheetah Run & --- & ON & 8 & 77.3 @105K & 0.10$\\times$ & Healthy \\\\\n\\rowcolor{gray!15}\n019b & PickCube-v1 & trn & ON & 8 & 26.64 @200K & 3.78$\\times$$^c$ & Transient onset \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize\ntrn = trained ($d{=}32$, subsample ON);\ntrn$^\\ddagger$ = full-pathway SGS (all non-KL gradients detached);\nexp$^a$ = trained, subsample OFF;\nfrz$^b$ = frozen ($d{=}32$, \\texttt{requires\\_grad=False});\n--- = removed ($d{=}0$).\\\\\n$^*$ Seed 1 only: peak NVE with transient exceedances (1.60$\\times$ at 35K, 1.66$\\times$ at 95K); self-correcting, no sustained escalation. Seed 2 collapsed.\\\\\n$^\\diamond$ Transitional; train returns still declining (peak 470 to 139 over final 8K steps). Collapse had not reached equilibrium at 105K.\\\\\n$^c$ NVE normalized against exp\\_019a\\_v2 (vanilla DreamerV3 on PickCube-v1).\\\\\n$^d$ Peak NVE $9.94\\times$ at 45K (transient, self-correcting to $<$1$\\times$ by 55K); final eval 221.5.\\par}\n\\end{table*}\n\n\\section{NVE Threshold Sensitivity Analysis}\n\\label{sec:appendix_sensitivity}\n\nWe report the full sensitivity analysis for the NVE diagnostic framework introduced in Section~\\ref{sec:results}. The main text reports Task~B2 (any CIVO detection, $\\nve \\geq 1.5\\times$). Here we additionally present Task~B1, which restricts the positive class to \\emph{sustained} CIVO, specifically experiments exhibiting persistent, accelerating value overestimation that progresses to performance collapse. Transient CIVO cases (e.g., exp~009b, which self-corrects after a brief excursion above the threshold) are classified as negative in B1.\n\n\\subsection{Per-Experiment NVE Values}\n\nTable~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all ten factorial experiments (including four 008e\\_v3 seeds). Experiments are sorted by descending NVE. Experiment 008e\\_v3\\_s2 exhibits elevated NVE ($3.78\\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\\_v3\\_s3 exhibits CIVO with NVE $4.02\\times$ despite $\\Delta t{=}1$ imagination.\n\n\\begin{table}[h]\n\\centering\n\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\\ = transient CIVO with self-correction.}\n\\label{tab:nve_raw}\n\\small\n\\begin{tabular}{@{}lrccc@{}}\n\\toprule\nExperiment & NVE & Mechanism & B1 & B2 \\\\\n\\midrule\n006          & 4.84 & sustained CIVO & $+$ & $+$ \\\\\n008d         & 4.13 & sustained CIVO & $+$ & $+$ \\\\\n008e\\_v3\\_s3 & 4.02 & CIVO           & $+$ & $+$ \\\\\n008e\\_v3\\_s2 & 3.78 & IRD (non-CIVO) & $-$ & $-$ \\\\\n009b         & 1.62 & transient CIVO & $-$ & $+$ \\\\\n001          & 1.00 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s4 & 0.99 & non-CIVO       & $-$ & $-$ \\\\\n008f         & 0.97 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s1 & 0.94 & non-CIVO       & $-$ & $-$ \\\\\n008a         & 0.93 & non-CIVO       & $-$ & $-$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Multi-Threshold Classification Performance}\n\nTable~\\ref{tab:sensitivity_b1} reports Task~B1 classification metrics across six NVE thresholds. Task~B1 achieves $\\text{AUROC} = 1.000$ because the minimum positive NVE ($4.02\\times$, exp~008e\\_v3\\_s3) exceeds the maximum negative NVE ($3.78\\times$, exp~008e\\_v3\\_s2), yielding perfect rank separation. The optimal threshold lies in the interval $(3.78, 4.02]$; we report $\\geq 3.9\\times$ as a representative value. Table~\\ref{tab:sensitivity_b2} provides the corresponding analysis for Task~B2 ($\\text{AUROC} = 0.958$, imperfect separation due to 008e\\_v3\\_s2).\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B1}: Sustained CIVO detection sensitivity analysis ($n_{\\text{pos}}=3$, $n_{\\text{neg}}=7$, $n=10$, $\\text{AUROC}=1.000$). All confidence intervals are two-sided Clopper-Pearson exact binomial ($\\alpha=0.05$). $^\\dagger$Optimal threshold in $(3.78, 4.02]$.}\n\\label{tab:sensitivity_b1}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 3 & 3 & 0 & 4 & 70.0\\% \\; [34.8, 93.3] & 50.0\\% & 100\\% & 66.7\\% \\\\\n$\\geq 1.2\\times$ & 3 & 2 & 0 & 5 & 80.0\\% \\; [44.4, 97.5] & 60.0\\% & 100\\% & 75.0\\% \\\\\n$\\geq 1.5\\times$ & 3 & 2 & 0 & 5 & 80.0\\% \\; [44.4, 97.5] & 60.0\\% & 100\\% & 75.0\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.7\\times$ & 3 & 1 & 0 & 6 & 90.0\\% \\; [55.5, 99.7] & 75.0\\% & 100\\% & 85.7\\% \\\\\n$\\geq 2.0\\times$ & 3 & 1 & 0 & 6 & 90.0\\% \\; [55.5, 99.7] & 75.0\\% & 100\\% & 85.7\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 3.9\\times^\\dagger$ & 3 & 0 & 0 & 7 & 100\\% \\; [69.2, 100] & 100\\% & 100\\% & 100\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B2}: Any CIVO detection sensitivity analysis ($n_{\\text{pos}}=4$, $n_{\\text{neg}}=6$, $n=10$, $\\text{AUROC}=0.958$). The single false positive at $\\geq 1.5\\times$ is 008e\\_v3\\_s2 (IRD mechanism, not CIVO). The $1.5\\times$ threshold (highlighted) maximizes F1 while maintaining perfect recall.}\n\\label{tab:sensitivity_b2}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 4 & 2 & 0 & 4 & 80.0\\% \\; [44.4, 97.5] & 66.7\\% & 100\\% & 80.0\\% \\\\\n$\\geq 1.2\\times$ & 4 & 1 & 0 & 5 & 90.0\\% \\; [55.5, 99.7] & 80.0\\% & 100\\% & 88.9\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.5\\times$ & 4 & 1 & 0 & 5 & 90.0\\% \\; [55.5, 99.7] & 80.0\\% & 100\\% & 88.9\\% \\\\\n$\\geq 1.7\\times$ & 3 & 1 & 1 & 5 & 80.0\\% \\; [44.4, 97.5] & 75.0\\% & 75.0\\% & 75.0\\% \\\\\n$\\geq 2.0\\times$ & 3 & 1 & 1 & 5 & 80.0\\% \\; [44.4, 97.5] & 75.0\\% & 75.0\\% & 75.0\\% \\\\\n$\\geq 3.9\\times$ & 3 & 0 & 1 & 6 & 90.0\\% \\; [55.5, 99.7] & 100\\% & 75.0\\% & 85.7\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\subsection{Threshold Recommendation}\n\nFor the main diagnostic (Task~B2), we recommend $\\nve \\geq 1.5\\times$ as the operating threshold for three reasons:\n\n\\begin{enumerate}[nosep,leftmargin=*]\n\\item \\textbf{Maximum recall.} The $1.5\\times$ threshold achieves 100\\% recall, detecting all four CIVO cases including the transient case (009b, $\\nve = 1.62\\times$). Raising the threshold to $1.7\\times$ loses 009b, dropping recall to 75.0\\%.\n\\item \\textbf{Best F1.} At $1.5\\times$, F1 = 88.9\\%, the highest among all tested thresholds for B2. The single false positive (008e\\_v3\\_s2) is mechanistically identifiable as IRD rather than CIVO.\n\\item \\textbf{Sensitivity--specificity tradeoff.} Lower thresholds ($1.0\\times$) add false positives without gaining true positives. Higher thresholds ($\\geq 1.7\\times$) sacrifice recall without eliminating the 008e\\_v3\\_s2 false positive (which requires $\\tau > 3.78$).\n\\end{enumerate}\n\nFor Task~B1 (sustained CIVO only), perfect classification is achievable at $\\nve \\geq 3.9\\times$, but with only $n_{\\text{pos}} = 3$ the statistical power remains limited (accuracy 95\\% CI: [69.2\\%, 100\\%]).\n\n\\paragraph{Limitations.} With $n = 10$ experiments, Clopper-Pearson confidence intervals remain wide (e.g., 90.0\\% accuracy has 95\\% CI [55.5\\%, 99.7\\%]). These results should be interpreted as a diagnostic proof-of-concept rather than a validated clinical threshold. Replication across additional environments and seeds is needed to establish tighter bounds.\n\n% --- APPENDIX B: Factorial Ablation Details ---\n\n\\section{Factorial Ablation Details}\n\\label{sec:appendix_factorial}\n\nThis appendix provides the full factorial ablation results summarized in \\S\\ref{sec:f3f5_summary} of the main text.\n\n\\subsection{F3: Unexposed Temporal Embedding Suppresses Value Drift}\n\\label{sec:f3}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig3_factorial_grid.pdf}\n\\caption{Factorial isolation of CIVO trigger. Only the combination of trained $e_{\\dt}$ and multi-rate data (upper-left cell) produces pathological NVE. Neither factor alone is sufficient.}\n\\label{fig:factorial_grid}\n\\end{figure}\n\nThe causal claim that trained embedding \\emph{plus} multi-rate exposure jointly trigger CIVO rests on two complementary controls that each remove one factor while holding the other constant.\n\n\\paragraph{Evidence A: exposure is necessary (exp\\_008a).}\nExp\\_008a uses a trained embedding ($d{=}32$, gradients enabled) that is never exposed to $\\dt{>}1$ transitions during world-model training (subsample OFF). Despite sharing the same embedding architecture as exp\\_008d, its NVE remains in the $0.43$--$0.93\\times$ range across 3 seeds (105K steps). Performance follows two V-shaped recovery cycles, reaching 777.7 at 105K (85\\% of baseline). The critical trigger is not the embedding's capacity to represent temporal information, but its adaptation to multi-rate data that enables precise but inaccurate $\\dt{>}1$ state predictions within the RSSM.\n\nThis contrasts with exp\\_006 (trained $e_{\\dt}$, subsample ON, $H{=}15$), where NVE accelerates from $1.61\\times$ at 45K to $2.31\\times$ at 55K before catastrophic collapse to 132.9 at 65K. Both experiments use identical trained embeddings ($d{=}32$, gradients enabled) and $H{=}15$, differing only in whether the world model sees $\\dt{>}1$ transitions during training, confirming that multi-rate data exposure, not embedding architecture, is the operative variable.\n\n\\paragraph{Evidence B: trainability is necessary (exp\\_015b).}\nExp\\_015b uses a frozen random-projection embedding ($d{=}32$, \\texttt{requires\\_grad=False}, subsample ON, $H{=}8$), the same multi-rate data regime as exp\\_008d, but with a non-trainable temporal signal. Despite full exposure to $\\dt{>}1$ transitions, the NVE peaks at $1.45\\times$ at 55K but does not sustain escalation: it retreats to $0.65\\times$ by 65K and settles at $0.55\\times$ by 105K (trajectory: $0.81 \\rightarrow 1.26 \\rightarrow 1.45 \\rightarrow 0.65 \\rightarrow 1.05 \\rightarrow 0.60 \\rightarrow 0.59 \\rightarrow 0.55$). The transient peak approaches but does not exceed the $1.5\\times$ CIVO threshold, and critically, the ratio self-corrects rather than exhibiting the monotonic escalation seen in trained-embedding runs. Final evaluation reaches only 204.2 at 105K, low but through a qualitatively different failure mode than CIVO. Actor loss approaches zero (gradient starvation; see \\S\\ref{sec:pathways}), indicating that the frozen embedding provides no useful gradient signal for temporal adaptation.\n\nThe contrast with exp\\_008d is stark: under identical data conditions (subsample ON, $H{=}8$), the trained embedding drives NVE to $4.12\\times$ with sustained monotonic escalation ($1.78 \\rightarrow 1.71 \\rightarrow 2.09 \\rightarrow 4.12$) and triggers full collapse (eval 82.8), while the frozen embedding peaks transiently at $1.45\\times$ before self-correcting to $0.55\\times$, a qualitative difference between sustained and transient overestimation. This demonstrates that a $\\dt$-embedding must be able to \\emph{co-adapt} with RSSM dynamics to produce the systematic reward-prediction bias that drives CIVO; a static random projection, regardless of its exposure to multi-rate data, cannot create this bias.\n\nTogether, these two controls establish that CIVO requires the \\emph{joint} presence of (i)~a trainable embedding that can co-adapt with RSSM dynamics, and (ii)~multi-rate training data that drives this co-adaptation toward biased temporal predictions. Neither factor alone is sufficient.\n\nCross-environment validation on Cheetah Run replicates the causal pattern: trained $e_{\\dt}$ triggers CIVO in both tested seeds (exp\\_010b, 2 seeds, NVE $8.27$--$70.64\\times$, collapse to 51.7/0.83) while removing the embedding eliminates it (exp\\_024b, 2 seeds, NVE $<0.2\\times$, eval 96.5/77.3). This extends the necessary-condition finding from Walker Walk to a second locomotion environment with qualitatively different dynamics (6-joint vs.\\ 2-joint).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Causal isolation: $e_{\\dt}$ configuration $\\times$ multi-rate data exposure. The combination of trained embedding and multi-rate exposure is the sole trigger for CIVO. Neither factor alone is sufficient.}\n\\label{tab:causal_matrix}\n\\begin{tabular}{lcc}\n\\toprule\n& Multi-rate data (\\textsc{on}) & Single-rate data (\\textsc{off}) \\\\\n\\midrule\nTrained $e_{\\dt}$ & exp\\_008d: \\textbf{CIVO} & exp\\_008a: healthy \\\\\n & NVE 4.12$\\times$, collapse & NVE 0.93$\\times$ \\\\\n\\midrule\nFrozen $e_{\\dt}$ & exp\\_015b: grad.\\ starvation & --- \\\\\n & peak NVE 1.45$\\times$ (transient) & \\\\\n\\midrule\nRemoved $e_{\\dt}$ & exp\\_008f: no CIVO & --- \\\\\n & NVE $\\leq$0.97$\\times$ & \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOnly the upper-left cell (trained embedding with multi-rate exposure) triggers CIVO (Table~\\ref{tab:causal_matrix}). This 2$\\times$2 structure establishes that both factors are jointly necessary.\n\n\\subsection{F4: Degradation Scales Monotonically with \\texorpdfstring{$\\dt$}{dt}}\n\\label{sec:f4}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig5_dt_amplification.pdf}\n\\caption{Peak evaluation return as a function of imagination $\\dt$. Performance degrades monotonically: $\\dt{=}1$ (915.7) $>$ $\\dt{=}2$ (485.3, $-47\\%$) $>$ $\\dt{=}4$ (176.9, $-81\\%$).}\n\\label{fig:dt_amplification}\n\\end{figure}\n\nThe magnitude of degradation scales monotonically with the imagination step size (Figure~\\ref{fig:dt_amplification}). From the $\\dt{=}1$ baseline (915.7 at 105K), fixed $\\dt{=}2$ (exp\\_006) achieves a peak of only 485.3 ($-47\\%$), and fixed $\\dt{=}4$ (exp\\_007) peaks at 176.9 ($-81\\%$). This monotonic relationship is consistent with compounding model error: larger temporal gaps amplify the RSSM's prediction inaccuracy at each imagination step, and these errors accumulate across the rollout horizon.\n\n\\subsection{F5: Imagination Horizon and Subsampling Are Secondary Factors}\n\\label{sec:f5}\n\nNeither horizon length nor temporal subsampling triggers collapse without multi-rate data exposure: both trained-but-unexposed configurations (008a, 008c) maintain $\\nve < 0.93\\times$ (\\S\\ref{sec:f3}), while the trained-and-exposed counterpart (008d) collapses with $\\nve = 4.12\\times$.  The no-embedding configurations show cross-seed variance (008f: 503.0 vs.\\ 009c: 148.3) but neither exhibits $\\nve > 1.5\\times$, confirming that low evaluation alone does not indicate CIVO.\n\nThe $3.2\\times$ performance gap (008a: 777.7 vs.\\ 008c: 240.9) quantifies the horizon effect independently of CIVO, as both conditions maintain healthy NVE ($\\leq$0.93$\\times$).\n\n% --- APPENDIX C: Full Analysis & Discussion ---\n\n\\section{Full Analysis \\& Discussion}\n\\label{sec:appendix_analysis}\n\nThis appendix provides the complete mechanistic analysis summarized in Section~\\ref{sec:discussion} of the main text.\n\n\\subsection{The CIVO Mechanism}\n\\label{sec:civo_mechanism}\n\nThe RSSM fidelity analysis (Table~\\ref{tab:rssm_fidelity}) reveals the mechanistic core of CIVO.  The trained $\\dt$-embedding enables the reward head to learn temporally differentiated predictions, but these predictions are asymmetrically accurate: reward MAE at $\\dt{=}1$ is $0.0568$, while at $\\dt{=}2$ it rises to $0.1579$, a $2.78\\times$ gap.  This gap is not an artifact of prediction difficulty alone; the no-embedding configuration (008f) exhibits a $1.01\\times$ gap, and the baseline shows $1.56\\times$.  The trained embedding actively amplifies the fidelity discrepancy by allowing the reward head to co-adapt with the temporal signal.\n\nThis asymmetric fidelity initiates a feedback loop with four stages: (1) the trained $\\dt$-embedding causes RSSM predictions at $\\dt > 1$ to carry systematically biased reward estimates; (2) the critic, trained entirely on imagined trajectories, internalizes these biased rewards as optimistic value estimates; (3) the actor exploits the overestimated regions of the value landscape, shifting its policy toward states that appear high-value only under the biased model; and (4) this policy shift further skews the distribution of imagined states, reinforcing the bias.  The diagnostic signature is a sustained $\\nve$ above $1.5\\times$, followed by evaluation collapse.\n\nA random-policy control experiment ($N{=}100$ rollouts, 95\\% bootstrap CI) decomposes CIVO into two necessary stages.  \\textbf{Stage~1 (dynamics bias):} even under a random policy, $\\dt{=}2$ imagination produces $1.68\\times$ higher mean reward than $\\dt{=}1$ in the trained-embedding model (008d): the RSSM prior already generates reward-favorable trajectories at $\\dt > 1$, independent of actor behavior.  \\textbf{Stage~2 (actor exploitation):} the trained actor learns to exploit these biased regions, amplifying the ratio to $2.90\\times$.  In the no-embedding control (008f), neither stage is present: the random-policy ratio is $1.11\\times$ and the trained-actor ratio is $0.98\\times$.  The decomposition attributes $\\approx 36\\%$ of the total effect to dynamics bias and $\\approx 64\\%$ to actor exploitation, confirming that both stages are necessary for CIVO to manifest.\n\nThis mechanism is analogous to delusional bias \\citep{lu2018nondelusional}, but differs in origin: delusional bias arises from policy-class constraints, while CIVO is model-induced: the reward head's co-adaptation with the temporal embedding produces systematically upward-biased predictions at $\\dt > 1$.  The consequence (policy exploitation of overestimated regions) is similar, but the causal pathway is distinct.\n\n\\subsection{Selective Gradient Stopping and Gradient Decomposition}\n\\label{sec:sgs_gradient_analysis}\n\n\\subsubsection{Gradient Decomposition Results}\n\\label{sec:gradient_decomposition}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/fig3_gradient_decomposition.pdf}\n\\caption{Gradient contribution to $e_{\\Delta t}$ by loss component at two training checkpoints. The reward head contributes the largest share (38--49\\%) yet reward-only SGS (exp\\_016e) fails; the observation decoder channel (16--22\\%) carries the critical $\\dt$-specific spatial information that drives the RSSM fidelity gap.}\n\\label{fig:gradient_decomp}\n\\end{figure}\n\nExp\\_016e collapses in the same qualitative pattern as the unmodified control: peak evaluation 326.7 at 75K steps followed by catastrophic decline to 31.7 at 95K, with NVE reaching $10.42\\times$. The SGS intervention neither prevented nor attenuated CIVO.\n\nTo explain this null result, we performed a gradient decomposition analysis using \\texttt{torch.autograd.grad} to measure each loss component's contribution to $\\nabla_\\theta e_{\\Delta t}$, where $\\theta$ denotes the temporal embedding parameters. Table~\\ref{tab:gradient_decomposition} reports the results.\n\n\\begin{table}[h]\n\\centering\n\\caption{Gradient contributions to the temporal embedding $e_{\\Delta t}$ by loss component, measured via \\texttt{torch.autograd.grad} with training configuration \\texttt{gate\\_fixed\\_dt=2}. Gradient norms are $\\ell_2$ norms of $\\nabla_\\theta \\mathcal{L}_i$ for each loss $\\mathcal{L}_i$.}\n\\label{tab:gradient_decomposition}\n\\small\n\\begin{tabular}{lrrrr}\n\\toprule\n& \\multicolumn{2}{c}{\\textbf{@55K}} & \\multicolumn{2}{c}{\\textbf{@112K}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nLoss component & Share & (\\%) & Share & (\\%) \\\\\n\\midrule\nReward head & --- & 49.0 & --- & 38.1 \\\\\nKL dynamics & --- & 34.7 & --- & 40.4 \\\\\nObservation decoders & --- & 16.3 & --- & 21.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe gradient decomposition reveals a counterintuitive structure: the reward head provides the largest gradient contribution (49.0\\% at 55K, 38.1\\% at 112K), yet reward-only SGS (exp\\_016e) fails catastrophically (NVE $10.42\\times$). The observation decoder channel contributes the smallest share (16.3\\% at 55K, 21.5\\% at 112K) yet carries the critical $\\dt$-specific spatial information.  This dissociation between gradient magnitude and causal importance explains why exp\\_016e, which targets the largest pathway, is functionally insufficient for CIVO prevention.\n\nThe gradient structure is relatively stable across training (reward shifts from 49\\% to 38\\%, obs from 16\\% to 22\\%, KL from 35\\% to 40\\%), unlike what a magnitude-based account would predict. The reward head's large gradient contribution reflects the scalar reward prediction task's sensitivity to temporal embedding parameters, but this gradient does not encode $\\Delta t$-specific structural information about spatial dynamics. The observation decoder channel, despite its smaller magnitude, is the only pathway that encodes how the RSSM should differentially predict multi-dimensional proprioceptive states across temporal scales.\n\n\\paragraph{Why the smallest channel is causally critical.} The observation decoder is the only loss component whose gradients encode how the RSSM should differentially predict multi-dimensional proprioceptive states ($14$ orientations, $9$ velocities, $1$ height) across temporal scales.  This $\\dt$-specific spatial information shapes the latent state representation in ways that propagate to reward prediction: the RSSM fidelity gap ($2.78\\times$ reward MAE ratio, Table~\\ref{tab:rssm_fidelity}) arises because the temporal embedding learns to produce latent states that are spatially biased at $\\dt{>}1$, not because the reward head directly learns scale-dependent biases.  Full-SGS targets this causal chain by preventing observation-decoder gradients from updating $e_{\\Delta t}$, though its 50\\% recovery rate (1/2 seeds) indicates that breaking the gradient pathway alone does not fully eliminate the vulnerability.\n\n\\subsubsection{Implications for the CIVO Mechanism}\n\\label{sec:sgs_implications}\n\nThe gradient decomposition reveals that gradient magnitude and causal importance are decoupled in CIVO.\n\n\\paragraph{Gradient importance $\\neq$ gradient magnitude.} The reward head contributes the largest gradient share (38--49\\%) to $e_{\\Delta t}$, yet reward-only SGS fails.  The observation decoder contributes the smallest share (16--22\\%), yet its removal (via Full-SGS) is necessary for CIVO mitigation.  This dissociation arises because the reward head's gradient, while large, does not encode $\\dt$-specific structural information: it adjusts $e_{\\Delta t}$ to minimize a scalar prediction error that is largely $\\dt$-invariant.  The observation decoder's gradient, though smaller, encodes how the RSSM should differentially reconstruct 24-dimensional proprioceptive states across temporal scales. This is the channel through which $e_{\\Delta t}$ learns scale-dependent latent biases.\n\n\\paragraph{Reframing the intervention target.} Any gradient-level strategy that targets the reward head alone (reward prediction regularization, reward-conditioned value clipping, or reward-only SGS) targets the largest pathway but not the informationally critical one.  The failure of exp\\_016e (NVE $10.42\\times$) despite detaching the dominant gradient source confirms this.  Full-pathway SGS (exp\\_018) detaches $e_{\\Delta t}$ from all non-KL gradients, retaining only the KL dynamics contribution (34--40\\%).  However, this intervention yields mixed results: seed~1 avoids collapse (eval 448.3) while seed~2 collapses (eval 40.8), indicating that removing the observation decoder gradient channel is necessary but not sufficient.\n\nCross-environment validation on Cheetah Run (exp\\_021) further clarifies the role of Full-SGS.  The intervention did not prevent the initial CIVO onset: NVE peaked at $9.94\\times$ at 45K (comparable to the unmitigated exp\\_010b's $8.27\\times$).  However, unlike exp\\_010b, which collapsed permanently to eval 51.7, exp\\_021 self-corrected within ${\\sim}$10K steps, with sustained NVE dropping to $0.34\\times$ (55K--105K) and final evaluation recovering to 221.5.  This pattern reframes Full-SGS as \\emph{enabling recovery from CIVO} rather than preventing its onset: the gradient detachment constrains value growth after the transient spike, allowing the critic to recalibrate.  Performance nonetheless remains at 38.7\\% of baseline (572.5), likely because Full-SGS over-aggressively blocks actor gradients (actor gradient norms near zero throughout training).  Combined with exp\\_018's mixed Walker results (1/2 seeds), these findings indicate that gradient-level interventions alone do not fully eliminate the CIVO vulnerability, and that additional mechanisms (e.g., forward-pass conditioning effects, residual capacity-dependent instabilities) operate beyond the gradient pathway.\n\n\\paragraph{Connection to RSSM fidelity analysis.} The trained-embedding condition (exp\\_008d) shows a $2.78\\times$ reward gap between $\\Delta t{=}1$ and $\\Delta t{=}2$ transitions (Table~\\ref{tab:rssm_fidelity}).  This gap arises because the observation decoder gradients shape $e_{\\Delta t}$ to produce latent states that are spatially biased at $\\dt{>}1$, and the reward head inherits these biases \\textit{through the latent state} rather than learning them directly.  The reward head's large gradient contribution reflects sensitivity to $e_{\\Delta t}$'s parameters but not causal responsibility for the fidelity gap.\n\n\\subsubsection{Entropy Dynamics Across Configurations}\n\\label{sec:entropy_dynamics}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.85\\columnwidth]{figures/fig4_entropy_dynamics.pdf}\n\\caption{Actor entropy trajectories for three configurations. All start at ${\\sim}8$ nats and converge to similar values (${\\sim}{-}4.5$ to ${-}5$). The CIVO-triggering configuration (008d, red) follows a normal entropy reduction trajectory; the divergence from the control (008f) is subtle in entropy space, consistent with CIVO operating through the value channel rather than the entropy channel. 018v2 (Full-SGS, seed~1) shows slightly lower terminal entropy.}\n\\label{fig:entropy_dynamics}\n\\end{figure}\n\n\\subsubsection{Exp\\_016e Reinterpreted as Stochastic Variation}\n\\label{sec:016e_reinterp}\n\nThe gradient decomposition establishes that exp\\_016e targets the largest gradient pathway (reward: 38--49\\%) but not the informationally critical one (observation decoders: 16--22\\%).  The apparent timing differences between exp\\_016e and exp\\_008d (later collapse onset, 75K vs.\\ 25K, and higher peak evaluation, 326.7 vs.\\ 167.2) must be attributed to stochastic variation rather than SGS effects, since the critical observation decoder channel remains intact.  All three trajectories (exp\\_008d, exp\\_009b, exp\\_016e) share the invariant identified by the NVE diagnostic: each crosses the $1.5\\times$ pathological threshold at some point during training.\n\n\\subsection{Post-CIVO Outcomes: Why Seeds Diverge}\n\\label{sec:seed_divergence}\n\n\\begin{table}[h]\n\\centering\n\\caption{Post-CIVO outcomes for the 008d configuration. Peak/Final NVE measured in the 35K+ window.}\n\\label{tab:post_civo}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{lcccl}\n\\toprule\n\\textbf{Seed} & \\textbf{Peak} & \\textbf{Final} & \\textbf{Eval} & \\textbf{Outcome} \\\\\n\\midrule\ns1 (008d) & 4.12$\\times$ & 4.12$\\times$ & 82.8 & Full collapse \\\\\ns2 (009b) & 1.62$\\times$ & 0.38$\\times$ & 267.9 & Transient CIVO \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe two post-CIVO outcomes (Table~\\ref{tab:post_civo}), full collapse and transient CIVO with self-correction, both cross the $\\nve > 1.5\\times$ threshold, yet the downstream damage is stochastic.\\footnote{Exp\\_009e was excluded from multi-seed analyses due to a seed configuration error (default seed=0, identical to exp\\_008d).}  Bootstrap resampling ($B{=}10000$) over the $n{=}2$ effective seeds yields peak NVE mean $3.085$ (95\\% CI: $[2.05, 4.12]$), collapse rate $0.5$, and Cohen's $d = 2.60$ (mean difference $2.205$) relative to the no-embedding control, confirming a large effect despite the limited sample.  We hypothesize that the divergence relates to the critic's representational capacity at the time of CIVO onset.  \\citet{lyle2022capacity} demonstrate that deep RL networks suffer progressive capacity loss, in which early-learned features become increasingly difficult to overwrite.  If the critic's capacity is already partially consumed when CIVO injects overestimation, the network cannot recalibrate (seed~0); if sufficient capacity remains, the critic can absorb transient overestimation and recover (seed~2).\n\n\\subsection{Why MPC Is Immune}\n\\label{sec:mpc_immune}\n\n\\citet{nhu2025tawm} show that $\\dt$-conditioning benefits TD-MPC2, raising the question of why it fails in DreamerV3.  The critical difference is that MPC re-plans from real states at every step, so imagination errors do not accumulate into the training signal because there is no critic bootstrapping from imagined trajectories.  In DreamerV3, the actor-critic trains entirely within imagination, and any systematic reward-prediction bias at $\\dt > 1$ is amplified through the closed actor-critic loop.\n\n\\subsection{The \\texorpdfstring{$\\dt$}{dt}-Embedding Dilemma}\n\\label{sec:embedding_dilemma}\n\nThe factorial results reveal a fundamental tension: removing the $\\dt$-embedding (008f) eliminates CIVO but at a $13\\times$ cost to reward prediction quality ($0.7469$ vs.\\ $0.0568$ MAE), as the world model cannot distinguish temporal scales.  Restricting imagination to $\\dt{=}1$ while retaining the trained embedding (008e\\_v3) avoids collapse in 2 of 4 seeds (50\\%), while the remaining two collapse via distinct mechanisms: Pathway~A (CIVO-driven, entropy decrease; s3, NVE $4.02\\times$) and Pathway~B (entropy-driven, entropy increase; s2, NVE $3.78\\times$; \\S\\ref{sec:f6}).  Neither approach alone provides a complete solution.\n\n\\subsection{Multiple Vulnerability Pathways}\n\\label{sec:pathways}\n\nThe two collapse mechanisms identified in \\S\\ref{sec:f6}, CIVO (Pathway~A, value-driven, entropy decreasing) and non-CIVO instability (Pathway~B, eval-driven, entropy increasing), have distinct diagnostic signatures but a shared root cause: the trained $\\dt$-embedding's learned features affect both reward prediction across temporal scales (Pathway~A) and the representation space in which the actor operates (Pathway~B).  This explains why $\\nve$ is sensitive but not perfectly specific: Pathway~B's late evaluation decline inflates $\\nve$ through the same arithmetic as CIVO, yielding the sole false positive ($3.78\\times$ for 008e\\_v3 s2).  Distinguishing the two requires examining the temporal profile and entropy direction of collapse.\n\n\\subsection{Implications for Temporal Abstraction in World Models}\n\\label{sec:implications}\n\nCIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \\citep{gumbsch2024thick}, Hieros \\citep{mattes2024hieros}, LS-Imagine \\citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \\citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.\n",
    "structuredPatch": [
      {
        "oldStart": 366,
        "oldLines": 3,
        "newStart": 366,
        "newLines": 57,
        "lines": [
          " \\label{sec:implications}",
          " ",
          " CIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \\citep{gumbsch2024thick}, Hieros \\citep{mattes2024hieros}, LS-Imagine \\citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \\citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.",
          "+",
          "+\\section{DreamerV3 Hyperparameters}",
          "+\\label{sec:hyperparameters}",
          "+",
          "+Table~\\ref{tab:hyperparams} lists the DreamerV3 hyperparameters used across all experiments. Unless otherwise noted, we use the default DreamerV3 configuration for continuous-control tasks (\\texttt{dmc\\_proprio}).",
          "+",
          "+\\begin{table}[h]",
          "+\\centering",
          "+\\caption{DreamerV3 hyperparameters for all experiments. Modifications from defaults are marked with $\\diamond$.}",
          "+\\label{tab:hyperparams}",
          "+\\small",
          "+\\begin{tabular}{ll}",
          "+\\toprule",
          "+\\textbf{Parameter} & \\textbf{Value} \\\\",
          "+\\midrule",
          "+\\multicolumn{2}{l}{\\textit{World Model}} \\\\",
          "+RSSM discrete states & 32 classes $\\times$ 32 categories \\\\",
          "+RSSM stochastic dim & 32 \\\\",
          "+RSSM deterministic dim & 512 \\\\",
          "+MLP hidden size & 512 \\\\",
          "+MLP layers & 2 \\\\",
          "+Activation & SiLU \\\\",
          "+Normalization & LayerNorm \\\\",
          "+\\midrule",
          "+\\multicolumn{2}{l}{\\textit{Training}} \\\\",
          "+Batch size & 16 sequences $\\times$ 64 steps \\\\",
          "+Learning rate & $3 \\times 10^{-4}$ (Adam, $\\epsilon{=}10^{-8}$) \\\\",
          "+Sequence length & 64 \\\\",
          "+Training ratio & 512 \\\\",
          "+Free nats & 1.0 \\\\",
          "+KL balance ($\\alpha$) & 0.8 \\\\",
          "+Discount ($\\gamma$) & 0.997 \\\\",
          "+$\\lambda$-return & 0.95 \\\\",
          "+\\midrule",
          "+\\multicolumn{2}{l}{\\textit{Policy}} \\\\",
          "+Imagination horizon$^\\diamond$ & 8 or 15 (see Table~\\ref{tab:complete_results}) \\\\",
          "+Actor entropy scale & $3 \\times 10^{-4}$ \\\\",
          "+Actor gradient & Reinforce + dynamics backprop \\\\",
          "+\\midrule",
          "+\\multicolumn{2}{l}{\\textit{Temporal Abstraction}$^\\diamond$} \\\\",
          "+Gate enabled & True (all non-baseline) \\\\",
          "+Gate fixed $\\dt$ & 1 or 2 (per config) \\\\",
          "+Subsample max $\\dt$ & 1 (OFF) or 2 (ON) \\\\",
          "+$\\dt$-embedding dim & 32 \\\\",
          "+\\midrule",
          "+\\multicolumn{2}{l}{\\textit{Environment}} \\\\",
          "+Action repeat & 2 (Walker Walk, Cheetah Run) \\\\",
          "+Observation & Proprioceptive (no pixels) \\\\",
          "+Total environment steps & 105K \\\\",
          "+Evaluation frequency & Every 10K steps \\\\",
          "+Evaluation episodes & 10 \\\\",
          "+\\bottomrule",
          "+\\end{tabular}",
          "+\\end{table}"
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

_source line 20_

验证三处修改。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "ecbfbbd4-8704-4c16-bf62-d049e12658fb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FpgoTaYiSW94q4AENjNLAK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1908,
      "cache_read_input_tokens": 39804,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1908
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

_source line 21_

<details open><summary>🔧 Tool call — Grep · `toolu_01Lz9RUSqn1RcZuZRoPo7FVE`</summary>

```json
{
  "pattern": "—|–",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/abstract_body.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "424f4aca-0683-4381-9329-1ad638395115",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FpgoTaYiSW94q4AENjNLAK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1908,
      "cache_read_input_tokens": 39804,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1908
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

_source line 22 · 2026-05-18T14:25:05.772Z_

<details><summary>↩ Tool result · `toolu_01Lz9RUSqn1RcZuZRoPo7FVE`</summary>

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
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "9167aa91-a087-49c9-b6f3-51070ed5fb6e",
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

_source line 23_

<details open><summary>🔧 Tool call — Read · `toolu_019Kjo2M1b94cNY3buvrJq7m`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/conclusion.tex",
  "offset": 16,
  "limit": 8
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "ccebec97-efaa-48e7-854c-ba1b39fbbbe4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FpgoTaYiSW94q4AENjNLAK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1908,
      "cache_read_input_tokens": 39804,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1908
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

_source line 24 · 2026-05-18T14:25:06.548Z_

<details><summary>↩ Tool result · `toolu_019Kjo2M1b94cNY3buvrJq7m`</summary>

```text
16	
17	\paragraph{Limitations.}
18	Our primary factorial analysis focuses on Walker Walk; cross-environment evidence (Cheetah Run) is confirmed across two seeds but limited to a single trigger configuration. Both use a single world-model architecture (DreamerV3/RSSM). Generalization to other environments and architectures, particularly transformer-based world models such as DreamerV4, remains an open question. The $\nve$ threshold ($1.5\times$, 35K+ window) is sensitive to value overestimation broadly but not perfectly specific to CIVO (15/16, one non-CIVO false positive); generalization to other tasks and architectures is pending validation. The detector's thresholds were calibrated on thirteen runs across three environments; generalization to different reward scales and architectures requires further validation. Whether the protection conferred by removing the temporal embedding persists beyond 105K training steps also remains open: one control seed (009c, seed~2) exhibited NVE rising to $1.14\times$ at 105K steps on an upward trajectory, suggesting that longer training horizons may eventually erode this safeguard.
19	
20	\paragraph{Reproducibility.}
21	Code, experiment configurations, and training logs will be released upon acceptance to facilitate replication of all reported experiments.
22	
23	\paragraph{Future directions.}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "494d7d15-39c7-4e43-beb7-453d26c13109",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/conclusion.tex",
      "content": "\n\\paragraph{Limitations.}\nOur primary factorial analysis focuses on Walker Walk; cross-environment evidence (Cheetah Run) is confirmed across two seeds but limited to a single trigger configuration. Both use a single world-model architecture (DreamerV3/RSSM). Generalization to other environments and architectures, particularly transformer-based world models such as DreamerV4, remains an open question. The $\\nve$ threshold ($1.5\\times$, 35K+ window) is sensitive to value overestimation broadly but not perfectly specific to CIVO (15/16, one non-CIVO false positive); generalization to other tasks and architectures is pending validation. The detector's thresholds were calibrated on thirteen runs across three environments; generalization to different reward scales and architectures requires further validation. Whether the protection conferred by removing the temporal embedding persists beyond 105K training steps also remains open: one control seed (009c, seed~2) exhibited NVE rising to $1.14\\times$ at 105K steps on an upward trajectory, suggesting that longer training horizons may eventually erode this safeguard.\n\n\\paragraph{Reproducibility.}\nCode, experiment configurations, and training logs will be released upon acceptance to facilitate replication of all reported experiments.\n\n\\paragraph{Future directions.}",
      "numLines": 8,
      "startLine": 16,
      "totalLines": 25
    }
  }
}
```

</details>

---

### Tool call

_source line 25_

<details open><summary>🔧 Tool call — Grep · `toolu_015pmQKmrZsL9ganp8qveUKg`</summary>

```json
{
  "pattern": "tab:hyperparams|sec:hyperparameters",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "c933c4d9-ada7-4a9d-891d-fc2a50b92bea",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FpgoTaYiSW94q4AENjNLAK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1908,
      "cache_read_input_tokens": 39804,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1908
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

_source line 26 · 2026-05-18T14:25:07.431Z_

<details><summary>↩ Tool result · `toolu_015pmQKmrZsL9ganp8qveUKg`</summary>

```text
docs/paper/sections/appendix.tex:371:\label{sec:hyperparameters}
docs/paper/sections/appendix.tex:373:Table~\ref{tab:hyperparams} lists the DreamerV3 hyperparameters used across all experiments. Unless otherwise noted, we use the default DreamerV3 configuration for continuous-control tasks (\texttt{dmc\_proprio}).
docs/paper/sections/appendix.tex:378:\label{tab:hyperparams}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "64be05f9-4229-4eeb-9b7c-3b470680dfda",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/appendix.tex:371:\\label{sec:hyperparameters}\ndocs/paper/sections/appendix.tex:373:Table~\\ref{tab:hyperparams} lists the DreamerV3 hyperparameters used across all experiments. Unless otherwise noted, we use the default DreamerV3 configuration for continuous-control tasks (\\texttt{dmc\\_proprio}).\ndocs/paper/sections/appendix.tex:378:\\label{tab:hyperparams}",
    "numLines": 3
  }
}
```

</details>

---

### Assistant

_source line 27_

三处修改完成：

1. **Abstract** — 措辞已替换，拆为两句避免 -ing 结尾，无 em-dash 或解释性 en-dash。
2. **Conclusion** — Reproducibility 段落已插入 Limitations 和 Future directions 之间（第 20-21 行）。
3. **Appendix** — 超参表已追加在末尾，`tab:hyperparams` 和 `sec:hyperparameters` 无冲突（仅在新增内容中出现）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "uuid": "3e0f0f3a-79f6-4e55-a485-39a632a631e7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018uJAX9Wb2ZaFHETxaUZZuJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 982,
      "cache_read_input_tokens": 41712,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 982
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

_source line 28_

三处修改完成：

1. **Abstract** — 措辞已替换，拆为两句避免 -ing 结尾，无 em-dash 或解释性 en-dash。
2. **Conclusion** — Reproducibility 段落已插入 Limitations 和 Future directions 之间（第 20-21 行）。
3. **Appendix** — 超参表已追加在末尾，`tab:hyperparams` 和 `sec:hyperparameters` 无冲突（仅在新增内容中出现）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 45305,
  "duration_api_ms": 45954,
  "num_turns": 10,
  "stop_reason": "end_turn",
  "session_id": "c884e31d-deac-423d-aa35-71953a8abc7e",
  "total_cost_usd": 0.31743725000000006,
  "usage": {
    "input_tokens": 5,
    "cache_creation_input_tokens": 31247,
    "cache_read_input_tokens": 118335,
    "output_tokens": 2429,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 31247,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 150,
        "cache_read_input_tokens": 41712,
        "cache_creation_input_tokens": 982,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 982
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2116,
      "outputTokens": 22,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.0022259999999999997,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 5,
      "outputTokens": 2429,
      "cacheReadInputTokens": 118335,
      "cacheCreationInputTokens": 31247,
      "webSearchRequests": 0,
      "costUSD": 0.31521125,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "9925d097-3e9d-4378-9d6c-c100912da4f9"
}
```

</details>

---
