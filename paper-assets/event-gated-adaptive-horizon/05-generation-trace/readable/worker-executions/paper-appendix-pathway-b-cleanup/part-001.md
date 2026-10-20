# paper appendix pathway b cleanup — Part 1 of 5

**Why Temporal Abstraction Can Fail in Imagination-Based RL: A Diagnostic Analysis of Variable-Rate DreamerV3** · Worker execution logs

[Transcript overview](../paper-appendix-pathway-b-cleanup.md) · [Part 2 →](part-002.md) · [Structured JSON](../../../sessions/e0/e0781cc7ee2836897cbf.json)

## Before a recorded user message

## Before a recorded user message

192 recorded events


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
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
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
  "uuid": "26b4b095-ba25-46d4-b459-36d3adfc1403",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-9-projects-event-gated-adaptive-horizon/memory/"
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
    "resetsAt": 1779743400,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "c3f660e0-827a-4246-aa02-18c453605a54",
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f"
}
```

---


### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the appendix.tex file to understand its full content, then systematically find and fix all references to old data.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "046ca1b6-d8e2-4ca7-8899-f7e1351bfdce",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017eYoPU73d8ivmuso2Z3yyG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12435,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12435
      },
      "output_tokens": 26,
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

读取 appendix.tex 全文。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "f84a3117-62aa-4d00-89f0-e551f881bc1a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017eYoPU73d8ivmuso2Z3yyG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12435,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12435
      },
      "output_tokens": 26,
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

<details open><summary>🔧 Tool call — Read · `toolu_01R3TvAHyjDPTJGTfdDRC9Tf`</summary>

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
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "fd820c5e-2a03-4f2c-a3da-cd0618a3635f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017eYoPU73d8ivmuso2Z3yyG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12435,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12435
      },
      "output_tokens": 26,
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

_source line 7 · 2026-05-25T16:23:20.342Z_

<details><summary>↩ Tool result · reported error · `toolu_01R3TvAHyjDPTJGTfdDRC9Tf`</summary>

```text
File content (36931 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "785d623b-2ef1-4766-8b2f-e8ee9bf4a26d",
  "tool_use_result": "Error: File content (36931 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file."
}
```

</details>

---


### Assistant

_source line 8_

文件太大，分段读取并同时搜索关键词。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "5aeee847-c3ce-4002-85ac-72e1a13bd64e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JiVHAXvDYHCzZYZD4RgsDc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 211,
      "cache_read_input_tokens": 23882,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 211
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

_source line 9_

<details open><summary>🔧 Tool call — Read · `toolu_019bJgNu4xJH8MigPanX5fMt`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
  "limit": 300
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "e74f49ce-015f-426a-92c9-5a12a95f1314",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JiVHAXvDYHCzZYZD4RgsDc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 211,
      "cache_read_input_tokens": 23882,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 211
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

_source line 10 · 2026-05-25T16:23:23.706Z_

<details><summary>↩ Tool result · `toolu_019bJgNu4xJH8MigPanX5fMt`</summary>

```text
1	% --- APPENDIX ---
2	
3	\section{Complete Experimental Results}
4	\label{sec:complete_results}
5	
6	Table~\ref{tab:complete_results} reports all 45 experimental configurations. The main text (Table~\ref{tab:main_results}) presents the subset most relevant to the causal argument; this table includes the additional variable-rate configurations (006, 007, 005), multi-seed factorial runs (009b, 008d\_s3, 008d\_s4), SGS interventions (018), cross-environment seeds (010b\_s0), and mitigation experiments (008e\_v3).
7	
8	\begin{table*}[t]
9	\centering
10	\caption{Complete experimental results. NVE reports peak $\nve$ in the 35K+ window (\S\ref{sec:metrics}). CIVO-positive seeds are shaded; $\dagger$\,marks a false positive (non-CIVO collapse with elevated NVE).}
11	\label{tab:complete_results}
12	\scriptsize
13	\setlength{\tabcolsep}{3pt}
14	\begin{tabular}{llcccccl}
15	\toprule
16	\textbf{Exp} & \textbf{Config} & \textbf{dt\_emb} & \textbf{Sub} & \textbf{H} & \textbf{Eval@final} & \textbf{NVE} & \textbf{Outcome} \\
17	\midrule
18	001 & Baseline ($\dt{=}1$, s1) & --- & --- & 15 & 915.7 @105K & 1.00$\times$ & Healthy \\
19	001 s2 & Baseline ($\dt{=}1$, s2) & --- & --- & 15 & 443.5 @105K & ---$^e$ & Healthy \\
20	\rowcolor{gray!15}
21	006 & Fixed $\dt{=}2$ & trn & ON & 15 & 132.9 @65K & 4.83$\times$ & Collapsed \\
22	007 & Fixed $\dt{=}4$ & trn & ON & 15 & 152.5 @55K & --- & Collapsed \\
23	005 & Learned gate & adaptive & OFF & 15 & 98.8 @145K & --- & Collapsed \\
24	\midrule
25	\rowcolor{gray!15}
26	008d & Factorial (s1) & trn & ON & 8 & 82.8 @55K$^\heartsuit$ & 4.12$\times$ & Full collapse \\
27	\rowcolor{gray!15}
28	009b & Factorial (s2) & trn & ON & 8 & 267.9 @105K & 1.62$\times$ & Transient CIVO \\
29	\rowcolor{gray!15}
30	008d\_s3 & Factorial (s3) & trn & ON & 8 & 268$^\diamond$ @105K & 1.53$\times$ & Late-onset collapse \\
31	\rowcolor{gray!15}
32	008d\_s4 & Factorial (s4) & trn & ON & 8 & 63.6 @105K & 4.62$\times$ & Full collapse \\
33	\rowcolor{gray!15}
34	059 & Factorial (s5) & trn & ON & 8 & 95.8 @105K & 4.72$\times$ & Collapse$^\dagger$ \\
35	\rowcolor{gray!15}
36	068 & Factorial repro (s1) & trn & ON & 8 & 39.1 @105K & 4.12$\times$ & Full collapse \\
37	008f & No dt\_emb (s1) & --- & ON & 8 & 503.0 @105K & 0.97$\times$ & Healthy \\
38	008f s4 & No dt\_emb (s4) & --- & ON & 8 & 289.3 @105K & 0.76$\times$ & Healthy \\
39	009c s3 & No dt\_emb (s3) & --- & ON & 8 & 311.9 @105K & 1.04$\times$ & Healthy \\
40	008a & Unexposed emb & exp$^a$ & OFF & 15 & 777.7 @105K & 0.93$\times$ & Healthy \\
41	008a\_s1 & Unexposed emb & exp$^a$ & OFF & 15 & 630.9 @105K & 0.83$\times$ & Healthy \\
42	008a\_s2 & Unexposed emb & exp$^a$ & OFF & 15 & 899.4 @105K & 0.89$\times$ & Healthy \\
43	008a\_s3 & Unexposed emb & exp$^a$ & OFF & 15 & 855.9 @105K & --- & Healthy \\
44	015b & Frozen emb & frz$^b$ & ON & 8 & 204.2 @105K & 1.45$\times$ & Grad.\ starvation \\
45	022b & Frozen emb + Gumbel gate & frz$^b$ & ON & 8 & 300.7 @105K & 0.63$\times$ & No CIVO \\
46	042 & Frozen emb (dedicated) & frz$^b$ & ON & 8 & 612.0 @105K & 0.19$\times$ & Healthy \\
47	047 & Frozen emb (s1) & frz$^b$ & ON & 8 & 144.2 @215K & 1.71$\times$ & Transient (self-corr.) \\
48	057 & Frozen emb (s2) & frz$^b$ & ON & 8 & 123.9 @215K & 1.88$\times$ & Transient (self-corr.) \\
49	067 & Frozen emb (s0) & frz$^b$ & ON & 8 & 281.5 @105K & 0.19$\times$ & Healthy \\
50	\midrule
51	018 s1 & Full-SGS & trn$^\ddagger$ & ON & 8 & \sgseval{} @105K & \sgsnve{}$\times$$^*$ & Partial mitig.\ (CIVO+) \\
52	\rowcolor{gray!15}
53	018 s2 & Full-SGS & trn$^\ddagger$ & ON & 8 & 40.8 @105K & --- & Collapsed \\
54	008e\_v3 s1 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.94$\times$ & Healthy \\
55	008e\_v3 s2$^\dagger$ & Mitigation & trn & ON & 15 & 137.0 @105K & 3.78$\times$ & Non-CIVO collapse \\
56	\rowcolor{gray!15}
57	008e\_v3 s3 & Mitigation & trn & ON & 15 & 92.7 @105K & 4.02$\times$ & CIVO collapse \\
58	008e\_v3 s4 & Mitigation & trn & ON & 15 & 899.3 @105K & 0.99$\times$ & Healthy \\
59	008e\_v3 s5 & Mitigation & trn & ON & 15 & 853.1 @105K & 0.61$\times$ & Healthy \\
60	\midrule
61	\multicolumn{8}{l}{\textit{Cross-environment validation}} \\
62	\rowcolor{gray!15}
63	010b & Cheetah Run & trn & ON & 8 & 51.7 @105K & 8.27$\times$ & Collapsed \\
64	\rowcolor{gray!15}
65	010b\_s0 & Cheetah Run & trn & ON & 8 & 0.83 @105K & 108.52$\times$ & Full collapse \\
66	\rowcolor{gray!15}
67	021 & Cheetah Run & trn$^\ddagger$ & ON & 8 & 221.5 @105K & 9.94$\times$$^d$ & Transient CIVO (self-corr.) \\
68	024b s0 & Cheetah Run & --- & ON & 8 & 96.5 @105K & $<$0.20$\times$ & Healthy \\
69	024b s1 & Cheetah Run & --- & ON & 8 & 77.3 @105K & 0.10$\times$ & Healthy \\
70	008a\_ch s0 & Cheetah Run & exp$^a$ & OFF & 15 & 532.4 @105K & 1.08$\times$ & Healthy \\
71	008a\_ch s1 & Cheetah Run & exp$^a$ & OFF & 15 & 504.4 @105K & 1.29$\times$ & Healthy \\
72	077 & Cheetah baseline (s0) & --- & --- & 15 & 448.1 @105K & 1.00$\times$ & Healthy \\
73	\rowcolor{gray!15}
74	078 & Cheetah trigger (s0) & trn & ON & 8 & 119.5 @105K & 4.10$\times$ & Onset (self-corr.) \\
75	\rowcolor{gray!15}
76	019b & PickCube-v1 & trn & ON & 8 & 26.64 @200K & 3.78$\times$$^c$ & Transient onset \\
77	054 & PickCube-v1 & frz$^b$ & ON & 8 & --- & 8.81$\times$$^h$ & Env.\ transient (ctrl) \\
78	049 & StackCube-v1 & trn & ON & 8 & 34.9 @212K & 5.05$\times$$^f$ & Env.\ transient \\
79	052 & StackCube-v1 & trn & ON & 8 & --- & 4.67$\times$$^f$ & Env.\ transient \\
80	051 & StackCube-v1 & frz$^b$ & ON & 8 & 30.7 @155K & 4.30$\times$$^f$ & Env.\ transient (ctrl) \\
81	050 & PegInsertionSide-v1 & trn & ON & 8 & 20.86 @212K & 10.05$\times$$^g$ & Env.\ dynamics \\
82	053 & PegInsertionSide-v1 & frz$^b$ & ON & 8 & 5.89 & 8.10$\times$$^g$ & Env.\ dynamics (ctrl) \\
83	055 & PegInsertionSide-v1 & trn & ON & 8 & 11.44 @212K & 3.08$\times$$^g$ & Env.\ dynamics \\
84	056 & PegInsertionSide-v1 & frz$^b$ & ON & 8 & 4.37 @212K & 11.32$\times$$^g$ & Env.\ dynamics (ctrl) \\
85	046 & Cheetah Run & frz$^b$ & ON & 8 & 150.5 @215K & 1.35$\times$ & No CIVO \\
86	058 & Cheetah Run & frz$^b$ & ON & 8 & 80.46 @215K & 0.78$\times$ & No CIVO \\
87	\midrule
88	\multicolumn{8}{l}{\textit{Cartpole Swingup}} \\
89	060 & Cartpole baseline (3 seeds) & --- & --- & 15 & 557.0 @105K$^i$ & --- & Healthy \\
90	061 & Cartpole trigger (3 seeds) & trn & ON & 8 & 236.3 @105K$^i$ & --- & No CIVO \\
91	062 & Cartpole control (3 seeds) & --- & ON & 8 & 244.8 @105K$^i$ & --- & No CIVO \\
92	\bottomrule
93	\end{tabular}
94	\vspace{1pt}
95	{\raggedright\footnotesize
96	trn = trained ($d{=}32$, subsample ON);
97	trn$^\ddagger$ = full-pathway SGS (all non-KL gradients detached);
98	exp$^a$ = trained, subsample OFF;
99	frz$^b$ = frozen ($d{=}32$, \texttt{requires\_grad=False});
100	--- = removed ($d{=}0$).\\
101	$^*$ Seed 1 only: peak NVE with transient exceedances (1.60$\times$ at 35K, 1.66$\times$ at 95K); self-correcting, no sustained escalation. Seed 2 collapsed.\\
102	$^\diamond$ Transitional; train returns still declining (peak 470 to 139 over final 8K steps). Collapse had not reached equilibrium at 105K.\\
103	$^\dagger$ NVE self-corrected ($4.72\times$ $\to$ $1.22\times$) but policy did not recover (eval 10.5\% of baseline).\\
104	$^c$ NVE normalized against exp\_019a\_v2 (vanilla DreamerV3 on PickCube-v1).\\
105	$^d$ Peak NVE $9.94\times$ at 45K (transient, self-correcting to $<$1$\times$ by 55K); final eval 221.5.\\
106	$^e$ Not used for NVE normalization; reported for completeness. Seed~1 (eval 915.7) is the NVE reference baseline.\\
107	$^f$ StackCube transient: frozen control (exp\_051, peak $4.30\times$ at 42.5K) matches trained (exp\_049/052), self-correcting by 82.5K; environment-specific, not $\dt$-embedding-driven.\\
108	$^g$ PegInsertion environment dynamics: seed~0 trained peaks at $10.05\times$ (82.5K); seed~1 trained (exp\_055) peaks at $3.08\times$ (92.5K), final $0.50\times$ at 212.5K; seed~1 frozen (exp\_056) peaks at $11.32\times$ (82.5K), final $1.19\times$ at 212.5K. Frozen final exceeds trained final; ordering is seed-dependent, ruling out $\dt$-embedding causation.\\
109	$^h$ PickCube environment transient: frozen control peak $8.81\times$ at 62.5K, self-correcting to $0.55\times$ at 72.5K; matches trained (exp\_019b) trajectory.\\
110	$^\heartsuit$ Evaluated at 55K steps due to early termination of exp\_008d; extended run (exp\_009e) reached 131.08 at 105K.\\
111	$^i$ Cartpole: exp\_060 reports seed~2 eval only; exp\_061/062 report 3-seed mean.\par}
112	\end{table*}
113	
114	\begin{table}[h]
115	\centering
116	\caption{Cross-domain CIVO reproducibility. ``$\dt$-emb-dep.'' indicates trained peaks consistently exceed frozen at matched timepoints across seeds.}
117	\label{tab:cross_domain}
118	\footnotesize
119	\begin{tabular}{llccc}
120	\toprule
121	\textbf{Domain} & \textbf{Environment} & \textbf{Trained} & \textbf{Frz ctrl} & \textbf{$\dt$-emb-dep.\ CIVO} \\
122	\midrule
123	Locomotion & Walker Walk & 5/5 & 0/3 & Yes (NVE $1.53$--$4.72\times$) \\
124	Locomotion & Cheetah Run & 2/2 & 0/2 & Yes (NVE $8.27$--$108.5\times$) \\
125	Manipulation & StackCube-v1 & 0/2 & 0/1 & No (frozen$\approx$trained) \\
126	Manipulation & PegInsertionSide & 0/2 & 0/2 & No (seed-dep.\ ordering) \\
127	Manipulation & PickCube-v1 & 0/1 & 0/1 & No (frozen spike similar) \\
128	\midrule
129	Locomotion & Cartpole Swingup & 0/3 & 0/3 & No (single-joint) \\
130	\bottomrule
131	\end{tabular}
132	\end{table}
133	
134	\paragraph{Cartpole Swingup.} Cartpole Swingup (single-DoF locomotion) serves as a cross-environment control. Three seeds of the CIVO-trigger configuration (exp\_061: trained $e_{\dt}$, subsample ON, $H{=}8$, $\dt{=}2$) and three seeds of the no-embedding control (exp\_062) both produce zero CIVO onset. Despite using the hyperparameter combination that triggers collapse in all 10 tested multi-joint locomotion seeds (Walker/Cheetah), the single-joint Cartpole shows no CIVO, confirming the phenomenon requires multi-joint dynamics where temporal abstraction amplifies the reward fidelity gap.
135	
136	\section{NVE Threshold Sensitivity Analysis}
137	\label{sec:appendix_sensitivity}
138	
139	We report the full sensitivity analysis for the NVE diagnostic framework introduced in Section~\ref{sec:results}. The main text reports Task~B2 (any CIVO detection, $\nve \geq 1.5\times$). Here we additionally present Task~B1, which restricts the positive class to \emph{sustained} CIVO, specifically experiments exhibiting persistent, accelerating value overestimation that progresses to performance collapse. Transient CIVO cases (e.g., exp~009b, which self-corrects after a brief excursion above the threshold) are classified as negative in B1.
140	
141	\subsection{Per-Experiment NVE Values}
142	
143	Table~\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\_v3 seeds and exp\_059). Experiments are sorted by descending NVE. Experiment 008e\_v3\_s2 exhibits elevated NVE ($3.78\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\_v3\_s3 exhibits CIVO with NVE $4.02\times$ despite $\Delta t{=}1$ imagination.
144	
145	\begin{table}[ht]
146	\centering
147	\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\ = transient CIVO with self-correction.}
148	\label{tab:nve_raw}
149	\small
150	\begin{tabular}{@{}lrccc@{}}
151	\toprule
152	Experiment & NVE & Mechanism & B1 & B2 \\
153	\midrule
154	006          & 4.83 & sustained CIVO & $+$ & $+$ \\
155	059          & 4.72 & self-correcting CIVO & $-$ & $+$ \\
156	008d         & 4.12 & sustained CIVO & $+$ & $+$ \\
157	008e\_v3\_s3 & 4.02 & CIVO           & $+$ & $+$ \\
158	008e\_v3\_s2 & 3.78 & IRD (non-CIVO) & $-$ & $-$ \\
159	009b         & 1.62 & transient CIVO & $-$ & $+$ \\
160	001          & 1.00 & non-CIVO       & $-$ & $-$ \\
161	008e\_v3\_s4 & 0.99 & non-CIVO       & $-$ & $-$ \\
162	008f         & 0.97 & non-CIVO       & $-$ & $-$ \\
163	008e\_v3\_s1 & 0.94 & non-CIVO       & $-$ & $-$ \\
164	008a         & 0.93 & non-CIVO       & $-$ & $-$ \\
165	\bottomrule
166	\end{tabular}
167	\end{table}
168	
169	\subsection{Multi-Threshold Classification Performance}
170	
171	Table~\ref{tab:sensitivity_b1} reports Task~B1 classification metrics across six NVE thresholds. Task~B1 achieves $\text{AUROC} = 0.917$ because exp\_059 (NVE${=}4.72\times$, self-correcting CIVO, B1-negative) ranks above two sustained-CIVO positives ($4.12\times$, $4.02\times$), breaking the perfect rank separation that held before its inclusion. The optimal threshold lies in the interval $(3.78, 4.02]$; we report $\geq 3.9\times$ as a representative value (accuracy $10/11 = 90.9\%$). Table~\ref{tab:sensitivity_b2} provides the corresponding analysis for Task~B2 ($\text{AUROC} = 0.967$, imperfect separation due to 008e\_v3\_s2).
172	
173	\begin{table*}[t]
174	\centering
175	\caption{\textbf{Task~B1}: Sustained CIVO detection sensitivity analysis ($n_{\text{pos}}=3$, $n_{\text{neg}}=8$, $n=11$, $\text{AUROC}=0.917$). All confidence intervals are two-sided Clopper-Pearson exact binomial ($\alpha=0.05$). $^\dagger$Optimal threshold in $(3.78, 4.02]$; exp\_059 (NVE${=}4.72\times$, B1-negative) is the sole false positive.}
176	\label{tab:sensitivity_b1}
177	\small
178	\setlength{\tabcolsep}{5pt}
179	\begin{tabular}{@{}lcccccccc@{}}
180	\toprule
181	Threshold & TP & FP & FN & TN & Accuracy [95\% CI] & Precision & Recall & F1 \\
182	\midrule
183	$\geq 1.0\times$ & 3 & 4 & 0 & 4 & 63.6\% \; [30.8, 89.1] & 42.9\% & 100\% & 60.0\% \\
184	$\geq 1.2\times$ & 3 & 3 & 0 & 5 & 72.7\% \; [39.0, 94.0] & 50.0\% & 100\% & 66.7\% \\
185	$\geq 1.5\times$ & 3 & 3 & 0 & 5 & 72.7\% \; [39.0, 94.0] & 50.0\% & 100\% & 66.7\% \\
186	\rowcolor{gray!15}
187	$\geq 1.7\times$ & 3 & 2 & 0 & 6 & 81.8\% \; [48.2, 97.7] & 60.0\% & 100\% & 75.0\% \\
188	$\geq 2.0\times$ & 3 & 2 & 0 & 6 & 81.8\% \; [48.2, 97.7] & 60.0\% & 100\% & 75.0\% \\
189	\rowcolor{gray!15}
190	$\geq 3.9\times^\dagger$ & 3 & 1 & 0 & 7 & 90.9\% \; [58.7, 99.8] & 75.0\% & 100\% & 85.7\% \\
191	\bottomrule
192	\end{tabular}
193	\end{table*}
194	
195	\begin{table*}[t]
196	\centering
197	\caption{\textbf{Task~B2}: Any CIVO detection sensitivity analysis ($n_{\text{pos}}=5$, $n_{\text{neg}}=6$, $n=11$, $\text{AUROC}=0.967$). The single false positive at $\geq 1.5\times$ is 008e\_v3\_s2 (IRD mechanism, not CIVO). The $1.5\times$ threshold (highlighted) maximizes F1 while maintaining perfect recall.}
198	\label{tab:sensitivity_b2}
199	\small
200	\setlength{\tabcolsep}{5pt}
201	\begin{tabular}{@{}lcccccccc@{}}
202	\toprule
203	Threshold & TP & FP & FN & TN & Accuracy [95\% CI] & Precision & Recall & F1 \\
204	\midrule
205	$\geq 1.0\times$ & 5 & 2 & 0 & 4 & 81.8\% \; [48.2, 97.7] & 71.4\% & 100\% & 83.3\% \\
206	$\geq 1.2\times$ & 5 & 1 & 0 & 5 & 90.9\% \; [58.7, 99.8] & 83.3\% & 100\% & 90.9\% \\
207	\rowcolor{gray!15}
208	$\geq 1.5\times$ & 5 & 1 & 0 & 5 & 90.9\% \; [58.7, 99.8] & 83.3\% & 100\% & 90.9\% \\
209	$\geq 1.7\times$ & 4 & 1 & 1 & 5 & 81.8\% \; [48.2, 97.7] & 80.0\% & 80.0\% & 80.0\% \\
210	$\geq 2.0\times$ & 4 & 1 & 1 & 5 & 81.8\% \; [48.2, 97.7] & 80.0\% & 80.0\% & 80.0\% \\
211	$\geq 3.9\times$ & 4 & 0 & 1 & 6 & 90.9\% \; [58.7, 99.8] & 100\% & 80.0\% & 88.9\% \\
212	\bottomrule
213	\end{tabular}
214	\end{table*}
215	
216	\begin{table*}[t]
217	\centering
218	\caption{\textbf{Task~B2 (full evaluation set)}: Any CIVO detection across two environments ($n_{\text{pos}}=9$, $n_{\text{neg}}=8$, $n=17$, $\text{AUROC}=0.972$). Includes Walker Walk (15 configurations) and Cheetah Run (2 configurations).}
219	\label{tab:sensitivity_b2_full}
220	\small
221	\setlength{\tabcolsep}{5pt}
222	\begin{tabular}{@{}lcccccccc@{}}
223	\toprule
224	Threshold & TP & FP & FN & TN & Accuracy [95\% CI] & Precision & Recall & F1 \\
225	\midrule
226	$\geq 1.0\times$ & 9 & 2 & 0 & 6 & 88.2\% \; [63.6, 98.5] & 81.8\% & 100\% & 90.0\% \\
227	$\geq 1.2\times$ & 9 & 1 & 0 & 7 & 94.1\% \; [71.3, 99.9] & 90.0\% & 100\% & 94.7\% \\
228	\rowcolor{gray!15}
229	$\geq 1.5\times$ & 9 & 1 & 0 & 7 & 94.1\% \; [71.3, 99.9] & 90.0\% & 100\% & 94.7\% \\
230	$\geq 1.7\times$ & 7 & 1 & 2 & 7 & 82.4\% \; [56.6, 96.2] & 87.5\% & 77.8\% & 82.4\% \\
231	$\geq 2.0\times$ & 7 & 1 & 2 & 7 & 82.4\% \; [56.6, 96.2] & 87.5\% & 77.8\% & 82.4\% \\
232	$\geq 3.9\times$ & 7 & 0 & 2 & 8 & 88.2\% \; [63.6, 98.5] & 100\% & 77.8\% & 87.5\% \\
233	\bottomrule
234	\end{tabular}
235	\end{table*}
236	
237	\subsection{Threshold Recommendation}
238	
239	For the main diagnostic (Task~B2), we recommend $\nve \geq 1.5\times$ as the operating threshold for three reasons:
240	
241	\begin{enumerate}[nosep,leftmargin=*]
242	\item \textbf{Maximum recall.} The $1.5\times$ threshold achieves 100\% recall, detecting all five CIVO cases including the transient case (009b, $\nve = 1.62\times$). Raising the threshold to $1.7\times$ loses 009b, dropping recall to 80.0\%.
243	\item \textbf{Best F1.} At $1.5\times$, F1 = 90.9\%, the highest among all tested thresholds for B2. The single false positive (008e\_v3\_s2) is mechanistically identifiable as IRD rather than CIVO.
244	\item \textbf{Sensitivity--specificity tradeoff.} Lower thresholds ($1.0\times$) add false positives without gaining true positives. Higher thresholds ($\geq 1.7\times$) sacrifice recall without eliminating the 008e\_v3\_s2 false positive (which requires $\tau > 3.78$).
245	\end{enumerate}
246	
247	For Task~B1 (sustained CIVO only), the optimal threshold $\nve \geq 3.9\times$ achieves $10/11$ accuracy ($90.9\%$, 95\% CI: [58.7\%, 99.8\%]); the sole false positive is exp\_059 (NVE${=}4.72\times$, self-correcting CIVO classified as B1-negative).
248	
249	\subsection{Expanded ROC Analysis}
250	\label{sec:roc_analysis}
251	
252	The original $n{=}17$ analysis (Tables~\ref{tab:sensitivity_b1}--\ref{tab:sensitivity_b2_full}) predates the SGS, RAVE, and TCN experiments. We extend the NVE diagnostic evaluation to $n{=}56$ configurations spanning all tested interventions. Figure~\ref{fig:nve_roc} shows the receiver operating characteristic curve with 95\% bootstrap confidence interval (10{,}000 resamples).
253	
254	\begin{figure}[h]
255	\centering
256	\includegraphics[width=0.7\columnwidth]{../../artifacts/figures/nve_roc_curve.pdf}
257	\caption{NVE ROC curve ($n{=}56$ configurations, AUROC${=}0.990$, comprehensive validation). The preset $\nve \geq 1.5\times$ operating point (star) achieves TPR${=}1.00$, FPR${=}0.09$, accuracy${=}53/56$, F1${=}0.941$. Three false positives arise from non-CIVO value overestimation: mitigation transient VE spike (008e\_v3 subsample, $1.93\times$) and frozen embedding transients (047, $1.71\times$; 057, $1.88\times$). Threshold calibrated and validated post-hoc; cross-architecture validation deferred.}
258	\label{fig:nve_roc}
259	\end{figure}
260	
261	\begin{figure}[h]
262	\centering
263	\includegraphics[width=0.7\columnwidth]{../../artifacts/figures/nve_threshold_prf.pdf}
264	\caption{Precision, Recall, and F1 as a function of NVE threshold ($n{=}56$ configurations). Peak F1${=}0.941$ at $\tau{=}1.5\times$, where recall remains perfect ($1.00$) and precision${=}0.889$. The plateau of high F1 across $\tau \in [1.5, 1.7]$ indicates robustness to threshold selection.}
265	\label{fig:nve_prf}
266	\end{figure}
267	
268	We label a configuration as CIVO-positive if and only if (i)~it uses a trained $\dt$-embedding with multi-rate data exposure, and (ii)~NVE exceeds $1.5\times$ with co-occurring entropy collapse. Configurations exhibiting high NVE through other mechanisms (gradient truncation side effects, value anchor pollution) are labeled non-CIVO.
269	
270	The three false positives (FPR${=}0.18$) are mechanistically distinct from CIVO: (1)~RAVE anchor pollution (exp\_028, the EMA anchor becomes inflated, producing overestimation through a different pathway); (2)~obs-decoder SGS-induced value distortion (exp\_025 seed~2, blocking observation decoder gradients damages the RSSM latent space); (3)~IRD eval-driven collapse (exp\_008e\_v3 seed~2, actor entropy \emph{increases} with evaluation collapse, mechanistically distinct from CIVO's entropy \emph{decrease}). All three produce NVE $> 1.5\times$ through non-CIVO mechanisms, indicating that the NVE diagnostic detects value overestimation broadly rather than CIVO specifically---a feature rather than a limitation for practitioners monitoring deployment health. The closest sub-threshold case (008f seed~4, NVE${=}1.41\times$) lacks $\dt$-conditioning entirely ($d{=}0$); its elevated NVE reflects transient value noise that self-corrects without the positive feedback loop characteristic of CIVO. The closest above-threshold positive (008d seed~3, NVE${=}1.53\times$) exhibits the full CIVO causal chain: trained $\dt$-embedding, entropy decrease, and evaluation collapse to 14\% of baseline.
271	
272	\paragraph{Comprehensive validation ($n{=}56$).}
273	Expanding the evaluation set to all classifiable experiments yields $n{=}56$ ($n_{\text{pos}}{=}24$, $n_{\text{neg}}{=}32$), spanning Walker Walk, Cheetah Run, and multiple intervention configurations (SGS, TCN, dual-critic, frozen embedding). At the $1.5\times$ threshold: AUROC${=}0.990$, precision${=}0.889$, recall${=}1.000$, F1${=}0.941$, accuracy${=}53/56$. The three false positives are: exp\_008e\_v3\_subsample ($1.93\times$, mitigation config with transient VE spike), exp\_047 ($1.71\times$, frozen embedding transient), and exp\_057 ($1.88\times$, frozen embedding transient). All 24 CIVO-positive configurations are correctly detected (FN${=}0$), with CIVO-positive NVE ranging from $1.53\times$ (008d seed~3, late-onset) to $70.64\times$ (010b seed~0, Cheetah). The substantial increase in sample size from $n{=}32$ to $n{=}56$ strengthens confidence in the $1.5\times$ threshold as a robust diagnostic boundary.
274	
275	\subsection{NVE Normalization Robustness}
276	\label{sec:nve_robustness}
277	
278	To assess sensitivity to baseline seed choice, we extend the single-seed baseline (seed~1, eval 915.7 at 105K) to three additional seeds trained to 505K steps (Table~\ref{tab:baseline_seeds}).
279	
280	\begin{table}[h]
281	\centering
282	\caption{Walker Walk baseline seeds at 105K and 505K steps.}
283	\label{tab:baseline_seeds}
284	\footnotesize
285	\begin{tabular}{lcccc}
286	\toprule
287	\textbf{Seed} & \textbf{Eval@105K} & \textbf{Eval@505K} & \textbf{ve@65K} & \textbf{ve@105K} \\
288	\midrule
289	s1 & 915.7 & 970.4 & 0.563 & 0.656 \\
290	s2 & 443.5 & 945.7 & 0.898 & 0.742 \\
291	s3 & 869.0 & 947.7 & --- & 0.664 \\
292	s4 & 922.8 & 938.9 & --- & 0.624 \\
293	\bottomrule
294	\end{tabular}
295	\end{table}
296	
297	Seed~2 exhibits slow convergence (eval 443.5 at 105K, recovering to 945.7 by 512K), confirming non-pathological slow convergence rather than seed failure. Its elevated $v/e$ ratio at 65K (0.898 vs.\ 0.563 for seed~1) reflects the low evaluation denominator rather than pathological value overestimation. Using seed~2 as the sole normalization reference systematically deflates NVE values, causing two marginal CIVO-positive configurations (008d seed~3, peak NVE $1.53\times$; 009b seed~2, peak NVE $1.62\times$) to fall below the $1.5\times$ threshold. Core CIVO cases (peak NVE $> 3\times$) remain correctly classified under all baseline seeds.
298	
299	Single-seed normalization (s1) yields AUROC $= 0.933$ and accuracy 7/8 (87.5\%) on the Walker subset. Four-seed mean normalization yields AUROC $= 0.867$ and accuracy 6/8 (75.0\%): the boundary case exp\_009b flips from $\nve = 1.62\times$ (s1) to $1.23\times$ (4-seed mean), because its peak occurs at 45K when the s1 $v/e$ ratio (0.331) is well below the 4-seed mean (0.436). All high-NVE configurations remain correctly classified (006: $4.84\times \to 4.52\times$; 008d: $4.12\times \to 3.54\times$). The $1.5\times$ threshold thus correctly identifies all strong CIVO cases regardless of baseline choice; sensitivity is confined to configurations within 10\% of the threshold.
300	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "69ca2afb-881b-4a07-84ad-a6df9733c66c",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
      "content": "% --- APPENDIX ---\n\n\\section{Complete Experimental Results}\n\\label{sec:complete_results}\n\nTable~\\ref{tab:complete_results} reports all 45 experimental configurations. The main text (Table~\\ref{tab:main_results}) presents the subset most relevant to the causal argument; this table includes the additional variable-rate configurations (006, 007, 005), multi-seed factorial runs (009b, 008d\\_s3, 008d\\_s4), SGS interventions (018), cross-environment seeds (010b\\_s0), and mitigation experiments (008e\\_v3).\n\n\\begin{table*}[t]\n\\centering\n\\caption{Complete experimental results. NVE reports peak $\\nve$ in the 35K+ window (\\S\\ref{sec:metrics}). CIVO-positive seeds are shaded; $\\dagger$\\,marks a false positive (non-CIVO collapse with elevated NVE).}\n\\label{tab:complete_results}\n\\scriptsize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{dt\\_emb} & \\textbf{Sub} & \\textbf{H} & \\textbf{Eval@final} & \\textbf{NVE} & \\textbf{Outcome} \\\\\n\\midrule\n001 & Baseline ($\\dt{=}1$, s1) & --- & --- & 15 & 915.7 @105K & 1.00$\\times$ & Healthy \\\\\n001 s2 & Baseline ($\\dt{=}1$, s2) & --- & --- & 15 & 443.5 @105K & ---$^e$ & Healthy \\\\\n\\rowcolor{gray!15}\n006 & Fixed $\\dt{=}2$ & trn & ON & 15 & 132.9 @65K & 4.83$\\times$ & Collapsed \\\\\n007 & Fixed $\\dt{=}4$ & trn & ON & 15 & 152.5 @55K & --- & Collapsed \\\\\n005 & Learned gate & adaptive & OFF & 15 & 98.8 @145K & --- & Collapsed \\\\\n\\midrule\n\\rowcolor{gray!15}\n008d & Factorial (s1) & trn & ON & 8 & 82.8 @55K$^\\heartsuit$ & 4.12$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n009b & Factorial (s2) & trn & ON & 8 & 267.9 @105K & 1.62$\\times$ & Transient CIVO \\\\\n\\rowcolor{gray!15}\n008d\\_s3 & Factorial (s3) & trn & ON & 8 & 268$^\\diamond$ @105K & 1.53$\\times$ & Late-onset collapse \\\\\n\\rowcolor{gray!15}\n008d\\_s4 & Factorial (s4) & trn & ON & 8 & 63.6 @105K & 4.62$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n059 & Factorial (s5) & trn & ON & 8 & 95.8 @105K & 4.72$\\times$ & Collapse$^\\dagger$ \\\\\n\\rowcolor{gray!15}\n068 & Factorial repro (s1) & trn & ON & 8 & 39.1 @105K & 4.12$\\times$ & Full collapse \\\\\n008f & No dt\\_emb (s1) & --- & ON & 8 & 503.0 @105K & 0.97$\\times$ & Healthy \\\\\n008f s4 & No dt\\_emb (s4) & --- & ON & 8 & 289.3 @105K & 0.76$\\times$ & Healthy \\\\\n009c s3 & No dt\\_emb (s3) & --- & ON & 8 & 311.9 @105K & 1.04$\\times$ & Healthy \\\\\n008a & Unexposed emb & exp$^a$ & OFF & 15 & 777.7 @105K & 0.93$\\times$ & Healthy \\\\\n008a\\_s1 & Unexposed emb & exp$^a$ & OFF & 15 & 630.9 @105K & 0.83$\\times$ & Healthy \\\\\n008a\\_s2 & Unexposed emb & exp$^a$ & OFF & 15 & 899.4 @105K & 0.89$\\times$ & Healthy \\\\\n008a\\_s3 & Unexposed emb & exp$^a$ & OFF & 15 & 855.9 @105K & --- & Healthy \\\\\n015b & Frozen emb & frz$^b$ & ON & 8 & 204.2 @105K & 1.45$\\times$ & Grad.\\ starvation \\\\\n022b & Frozen emb + Gumbel gate & frz$^b$ & ON & 8 & 300.7 @105K & 0.63$\\times$ & No CIVO \\\\\n042 & Frozen emb (dedicated) & frz$^b$ & ON & 8 & 612.0 @105K & 0.19$\\times$ & Healthy \\\\\n047 & Frozen emb (s1) & frz$^b$ & ON & 8 & 144.2 @215K & 1.71$\\times$ & Transient (self-corr.) \\\\\n057 & Frozen emb (s2) & frz$^b$ & ON & 8 & 123.9 @215K & 1.88$\\times$ & Transient (self-corr.) \\\\\n067 & Frozen emb (s0) & frz$^b$ & ON & 8 & 281.5 @105K & 0.19$\\times$ & Healthy \\\\\n\\midrule\n018 s1 & Full-SGS & trn$^\\ddagger$ & ON & 8 & \\sgseval{} @105K & \\sgsnve{}$\\times$$^*$ & Partial mitig.\\ (CIVO+) \\\\\n\\rowcolor{gray!15}\n018 s2 & Full-SGS & trn$^\\ddagger$ & ON & 8 & 40.8 @105K & --- & Collapsed \\\\\n008e\\_v3 s1 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.94$\\times$ & Healthy \\\\\n008e\\_v3 s2$^\\dagger$ & Mitigation & trn & ON & 15 & 137.0 @105K & 3.78$\\times$ & Non-CIVO collapse \\\\\n\\rowcolor{gray!15}\n008e\\_v3 s3 & Mitigation & trn & ON & 15 & 92.7 @105K & 4.02$\\times$ & CIVO collapse \\\\\n008e\\_v3 s4 & Mitigation & trn & ON & 15 & 899.3 @105K & 0.99$\\times$ & Healthy \\\\\n008e\\_v3 s5 & Mitigation & trn & ON & 15 & 853.1 @105K & 0.61$\\times$ & Healthy \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cross-environment validation}} \\\\\n\\rowcolor{gray!15}\n010b & Cheetah Run & trn & ON & 8 & 51.7 @105K & 8.27$\\times$ & Collapsed \\\\\n\\rowcolor{gray!15}\n010b\\_s0 & Cheetah Run & trn & ON & 8 & 0.83 @105K & 108.52$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n021 & Cheetah Run & trn$^\\ddagger$ & ON & 8 & 221.5 @105K & 9.94$\\times$$^d$ & Transient CIVO (self-corr.) \\\\\n024b s0 & Cheetah Run & --- & ON & 8 & 96.5 @105K & $<$0.20$\\times$ & Healthy \\\\\n024b s1 & Cheetah Run & --- & ON & 8 & 77.3 @105K & 0.10$\\times$ & Healthy \\\\\n008a\\_ch s0 & Cheetah Run & exp$^a$ & OFF & 15 & 532.4 @105K & 1.08$\\times$ & Healthy \\\\\n008a\\_ch s1 & Cheetah Run & exp$^a$ & OFF & 15 & 504.4 @105K & 1.29$\\times$ & Healthy \\\\\n077 & Cheetah baseline (s0) & --- & --- & 15 & 448.1 @105K & 1.00$\\times$ & Healthy \\\\\n\\rowcolor{gray!15}\n078 & Cheetah trigger (s0) & trn & ON & 8 & 119.5 @105K & 4.10$\\times$ & Onset (self-corr.) \\\\\n\\rowcolor{gray!15}\n019b & PickCube-v1 & trn & ON & 8 & 26.64 @200K & 3.78$\\times$$^c$ & Transient onset \\\\\n054 & PickCube-v1 & frz$^b$ & ON & 8 & --- & 8.81$\\times$$^h$ & Env.\\ transient (ctrl) \\\\\n049 & StackCube-v1 & trn & ON & 8 & 34.9 @212K & 5.05$\\times$$^f$ & Env.\\ transient \\\\\n052 & StackCube-v1 & trn & ON & 8 & --- & 4.67$\\times$$^f$ & Env.\\ transient \\\\\n051 & StackCube-v1 & frz$^b$ & ON & 8 & 30.7 @155K & 4.30$\\times$$^f$ & Env.\\ transient (ctrl) \\\\\n050 & PegInsertionSide-v1 & trn & ON & 8 & 20.86 @212K & 10.05$\\times$$^g$ & Env.\\ dynamics \\\\\n053 & PegInsertionSide-v1 & frz$^b$ & ON & 8 & 5.89 & 8.10$\\times$$^g$ & Env.\\ dynamics (ctrl) \\\\\n055 & PegInsertionSide-v1 & trn & ON & 8 & 11.44 @212K & 3.08$\\times$$^g$ & Env.\\ dynamics \\\\\n056 & PegInsertionSide-v1 & frz$^b$ & ON & 8 & 4.37 @212K & 11.32$\\times$$^g$ & Env.\\ dynamics (ctrl) \\\\\n046 & Cheetah Run & frz$^b$ & ON & 8 & 150.5 @215K & 1.35$\\times$ & No CIVO \\\\\n058 & Cheetah Run & frz$^b$ & ON & 8 & 80.46 @215K & 0.78$\\times$ & No CIVO \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cartpole Swingup}} \\\\\n060 & Cartpole baseline (3 seeds) & --- & --- & 15 & 557.0 @105K$^i$ & --- & Healthy \\\\\n061 & Cartpole trigger (3 seeds) & trn & ON & 8 & 236.3 @105K$^i$ & --- & No CIVO \\\\\n062 & Cartpole control (3 seeds) & --- & ON & 8 & 244.8 @105K$^i$ & --- & No CIVO \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize\ntrn = trained ($d{=}32$, subsample ON);\ntrn$^\\ddagger$ = full-pathway SGS (all non-KL gradients detached);\nexp$^a$ = trained, subsample OFF;\nfrz$^b$ = frozen ($d{=}32$, \\texttt{requires\\_grad=False});\n--- = removed ($d{=}0$).\\\\\n$^*$ Seed 1 only: peak NVE with transient exceedances (1.60$\\times$ at 35K, 1.66$\\times$ at 95K); self-correcting, no sustained escalation. Seed 2 collapsed.\\\\\n$^\\diamond$ Transitional; train returns still declining (peak 470 to 139 over final 8K steps). Collapse had not reached equilibrium at 105K.\\\\\n$^\\dagger$ NVE self-corrected ($4.72\\times$ $\\to$ $1.22\\times$) but policy did not recover (eval 10.5\\% of baseline).\\\\\n$^c$ NVE normalized against exp\\_019a\\_v2 (vanilla DreamerV3 on PickCube-v1).\\\\\n$^d$ Peak NVE $9.94\\times$ at 45K (transient, self-correcting to $<$1$\\times$ by 55K); final eval 221.5.\\\\\n$^e$ Not used for NVE normalization; reported for completeness. Seed~1 (eval 915.7) is the NVE reference baseline.\\\\\n$^f$ StackCube transient: frozen control (exp\\_051, peak $4.30\\times$ at 42.5K) matches trained (exp\\_049/052), self-correcting by 82.5K; environment-specific, not $\\dt$-embedding-driven.\\\\\n$^g$ PegInsertion environment dynamics: seed~0 trained peaks at $10.05\\times$ (82.5K); seed~1 trained (exp\\_055) peaks at $3.08\\times$ (92.5K), final $0.50\\times$ at 212.5K; seed~1 frozen (exp\\_056) peaks at $11.32\\times$ (82.5K), final $1.19\\times$ at 212.5K. Frozen final exceeds trained final; ordering is seed-dependent, ruling out $\\dt$-embedding causation.\\\\\n$^h$ PickCube environment transient: frozen control peak $8.81\\times$ at 62.5K, self-correcting to $0.55\\times$ at 72.5K; matches trained (exp\\_019b) trajectory.\\\\\n$^\\heartsuit$ Evaluated at 55K steps due to early termination of exp\\_008d; extended run (exp\\_009e) reached 131.08 at 105K.\\\\\n$^i$ Cartpole: exp\\_060 reports seed~2 eval only; exp\\_061/062 report 3-seed mean.\\par}\n\\end{table*}\n\n\\begin{table}[h]\n\\centering\n\\caption{Cross-domain CIVO reproducibility. ``$\\dt$-emb-dep.'' indicates trained peaks consistently exceed frozen at matched timepoints across seeds.}\n\\label{tab:cross_domain}\n\\footnotesize\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Domain} & \\textbf{Environment} & \\textbf{Trained} & \\textbf{Frz ctrl} & \\textbf{$\\dt$-emb-dep.\\ CIVO} \\\\\n\\midrule\nLocomotion & Walker Walk & 5/5 & 0/3 & Yes (NVE $1.53$--$4.72\\times$) \\\\\nLocomotion & Cheetah Run & 2/2 & 0/2 & Yes (NVE $8.27$--$108.5\\times$) \\\\\nManipulation & StackCube-v1 & 0/2 & 0/1 & No (frozen$\\approx$trained) \\\\\nManipulation & PegInsertionSide & 0/2 & 0/2 & No (seed-dep.\\ ordering) \\\\\nManipulation & PickCube-v1 & 0/1 & 0/1 & No (frozen spike similar) \\\\\n\\midrule\nLocomotion & Cartpole Swingup & 0/3 & 0/3 & No (single-joint) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cartpole Swingup.} Cartpole Swingup (single-DoF locomotion) serves as a cross-environment control. Three seeds of the CIVO-trigger configuration (exp\\_061: trained $e_{\\dt}$, subsample ON, $H{=}8$, $\\dt{=}2$) and three seeds of the no-embedding control (exp\\_062) both produce zero CIVO onset. Despite using the hyperparameter combination that triggers collapse in all 10 tested multi-joint locomotion seeds (Walker/Cheetah), the single-joint Cartpole shows no CIVO, confirming the phenomenon requires multi-joint dynamics where temporal abstraction amplifies the reward fidelity gap.\n\n\\section{NVE Threshold Sensitivity Analysis}\n\\label{sec:appendix_sensitivity}\n\nWe report the full sensitivity analysis for the NVE diagnostic framework introduced in Section~\\ref{sec:results}. The main text reports Task~B2 (any CIVO detection, $\\nve \\geq 1.5\\times$). Here we additionally present Task~B1, which restricts the positive class to \\emph{sustained} CIVO, specifically experiments exhibiting persistent, accelerating value overestimation that progresses to performance collapse. Transient CIVO cases (e.g., exp~009b, which self-corrects after a brief excursion above the threshold) are classified as negative in B1.\n\n\\subsection{Per-Experiment NVE Values}\n\nTable~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\\_v3 seeds and exp\\_059). Experiments are sorted by descending NVE. Experiment 008e\\_v3\\_s2 exhibits elevated NVE ($3.78\\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\\_v3\\_s3 exhibits CIVO with NVE $4.02\\times$ despite $\\Delta t{=}1$ imagination.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\\ = transient CIVO with self-correction.}\n\\label{tab:nve_raw}\n\\small\n\\begin{tabular}{@{}lrccc@{}}\n\\toprule\nExperiment & NVE & Mechanism & B1 & B2 \\\\\n\\midrule\n006          & 4.83 & sustained CIVO & $+$ & $+$ \\\\\n059          & 4.72 & self-correcting CIVO & $-$ & $+$ \\\\\n008d         & 4.12 & sustained CIVO & $+$ & $+$ \\\\\n008e\\_v3\\_s3 & 4.02 & CIVO           & $+$ & $+$ \\\\\n008e\\_v3\\_s2 & 3.78 & IRD (non-CIVO) & $-$ & $-$ \\\\\n009b         & 1.62 & transient CIVO & $-$ & $+$ \\\\\n001          & 1.00 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s4 & 0.99 & non-CIVO       & $-$ & $-$ \\\\\n008f         & 0.97 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s1 & 0.94 & non-CIVO       & $-$ & $-$ \\\\\n008a         & 0.93 & non-CIVO       & $-$ & $-$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Multi-Threshold Classification Performance}\n\nTable~\\ref{tab:sensitivity_b1} reports Task~B1 classification metrics across six NVE thresholds. Task~B1 achieves $\\text{AUROC} = 0.917$ because exp\\_059 (NVE${=}4.72\\times$, self-correcting CIVO, B1-negative) ranks above two sustained-CIVO positives ($4.12\\times$, $4.02\\times$), breaking the perfect rank separation that held before its inclusion. The optimal threshold lies in the interval $(3.78, 4.02]$; we report $\\geq 3.9\\times$ as a representative value (accuracy $10/11 = 90.9\\%$). Table~\\ref{tab:sensitivity_b2} provides the corresponding analysis for Task~B2 ($\\text{AUROC} = 0.967$, imperfect separation due to 008e\\_v3\\_s2).\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B1}: Sustained CIVO detection sensitivity analysis ($n_{\\text{pos}}=3$, $n_{\\text{neg}}=8$, $n=11$, $\\text{AUROC}=0.917$). All confidence intervals are two-sided Clopper-Pearson exact binomial ($\\alpha=0.05$). $^\\dagger$Optimal threshold in $(3.78, 4.02]$; exp\\_059 (NVE${=}4.72\\times$, B1-negative) is the sole false positive.}\n\\label{tab:sensitivity_b1}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 3 & 4 & 0 & 4 & 63.6\\% \\; [30.8, 89.1] & 42.9\\% & 100\\% & 60.0\\% \\\\\n$\\geq 1.2\\times$ & 3 & 3 & 0 & 5 & 72.7\\% \\; [39.0, 94.0] & 50.0\\% & 100\\% & 66.7\\% \\\\\n$\\geq 1.5\\times$ & 3 & 3 & 0 & 5 & 72.7\\% \\; [39.0, 94.0] & 50.0\\% & 100\\% & 66.7\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.7\\times$ & 3 & 2 & 0 & 6 & 81.8\\% \\; [48.2, 97.7] & 60.0\\% & 100\\% & 75.0\\% \\\\\n$\\geq 2.0\\times$ & 3 & 2 & 0 & 6 & 81.8\\% \\; [48.2, 97.7] & 60.0\\% & 100\\% & 75.0\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 3.9\\times^\\dagger$ & 3 & 1 & 0 & 7 & 90.9\\% \\; [58.7, 99.8] & 75.0\\% & 100\\% & 85.7\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B2}: Any CIVO detection sensitivity analysis ($n_{\\text{pos}}=5$, $n_{\\text{neg}}=6$, $n=11$, $\\text{AUROC}=0.967$). The single false positive at $\\geq 1.5\\times$ is 008e\\_v3\\_s2 (IRD mechanism, not CIVO). The $1.5\\times$ threshold (highlighted) maximizes F1 while maintaining perfect recall.}\n\\label{tab:sensitivity_b2}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 5 & 2 & 0 & 4 & 81.8\\% \\; [48.2, 97.7] & 71.4\\% & 100\\% & 83.3\\% \\\\\n$\\geq 1.2\\times$ & 5 & 1 & 0 & 5 & 90.9\\% \\; [58.7, 99.8] & 83.3\\% & 100\\% & 90.9\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.5\\times$ & 5 & 1 & 0 & 5 & 90.9\\% \\; [58.7, 99.8] & 83.3\\% & 100\\% & 90.9\\% \\\\\n$\\geq 1.7\\times$ & 4 & 1 & 1 & 5 & 81.8\\% \\; [48.2, 97.7] & 80.0\\% & 80.0\\% & 80.0\\% \\\\\n$\\geq 2.0\\times$ & 4 & 1 & 1 & 5 & 81.8\\% \\; [48.2, 97.7] & 80.0\\% & 80.0\\% & 80.0\\% \\\\\n$\\geq 3.9\\times$ & 4 & 0 & 1 & 6 & 90.9\\% \\; [58.7, 99.8] & 100\\% & 80.0\\% & 88.9\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B2 (full evaluation set)}: Any CIVO detection across two environments ($n_{\\text{pos}}=9$, $n_{\\text{neg}}=8$, $n=17$, $\\text{AUROC}=0.972$). Includes Walker Walk (15 configurations) and Cheetah Run (2 configurations).}\n\\label{tab:sensitivity_b2_full}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 9 & 2 & 0 & 6 & 88.2\\% \\; [63.6, 98.5] & 81.8\\% & 100\\% & 90.0\\% \\\\\n$\\geq 1.2\\times$ & 9 & 1 & 0 & 7 & 94.1\\% \\; [71.3, 99.9] & 90.0\\% & 100\\% & 94.7\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.5\\times$ & 9 & 1 & 0 & 7 & 94.1\\% \\; [71.3, 99.9] & 90.0\\% & 100\\% & 94.7\\% \\\\\n$\\geq 1.7\\times$ & 7 & 1 & 2 & 7 & 82.4\\% \\; [56.6, 96.2] & 87.5\\% & 77.8\\% & 82.4\\% \\\\\n$\\geq 2.0\\times$ & 7 & 1 & 2 & 7 & 82.4\\% \\; [56.6, 96.2] & 87.5\\% & 77.8\\% & 82.4\\% \\\\\n$\\geq 3.9\\times$ & 7 & 0 & 2 & 8 & 88.2\\% \\; [63.6, 98.5] & 100\\% & 77.8\\% & 87.5\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\subsection{Threshold Recommendation}\n\nFor the main diagnostic (Task~B2), we recommend $\\nve \\geq 1.5\\times$ as the operating threshold for three reasons:\n\n\\begin{enumerate}[nosep,leftmargin=*]\n\\item \\textbf{Maximum recall.} The $1.5\\times$ threshold achieves 100\\% recall, detecting all five CIVO cases including the transient case (009b, $\\nve = 1.62\\times$). Raising the threshold to $1.7\\times$ loses 009b, dropping recall to 80.0\\%.\n\\item \\textbf{Best F1.} At $1.5\\times$, F1 = 90.9\\%, the highest among all tested thresholds for B2. The single false positive (008e\\_v3\\_s2) is mechanistically identifiable as IRD rather than CIVO.\n\\item \\textbf{Sensitivity--specificity tradeoff.} Lower thresholds ($1.0\\times$) add false positives without gaining true positives. Higher thresholds ($\\geq 1.7\\times$) sacrifice recall without eliminating the 008e\\_v3\\_s2 false positive (which requires $\\tau > 3.78$).\n\\end{enumerate}\n\nFor Task~B1 (sustained CIVO only), the optimal threshold $\\nve \\geq 3.9\\times$ achieves $10/11$ accuracy ($90.9\\%$, 95\\% CI: [58.7\\%, 99.8\\%]); the sole false positive is exp\\_059 (NVE${=}4.72\\times$, self-correcting CIVO classified as B1-negative).\n\n\\subsection{Expanded ROC Analysis}\n\\label{sec:roc_analysis}\n\nThe original $n{=}17$ analysis (Tables~\\ref{tab:sensitivity_b1}--\\ref{tab:sensitivity_b2_full}) predates the SGS, RAVE, and TCN experiments. We extend the NVE diagnostic evaluation to $n{=}56$ configurations spanning all tested interventions. Figure~\\ref{fig:nve_roc} shows the receiver operating characteristic curve with 95\\% bootstrap confidence interval (10{,}000 resamples).\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.7\\columnwidth]{../../artifacts/figures/nve_roc_curve.pdf}\n\\caption{NVE ROC curve ($n{=}56$ configurations, AUROC${=}0.990$, comprehensive validation). The preset $\\nve \\geq 1.5\\times$ operating point (star) achieves TPR${=}1.00$, FPR${=}0.09$, accuracy${=}53/56$, F1${=}0.941$. Three false positives arise from non-CIVO value overestimation: mitigation transient VE spike (008e\\_v3 subsample, $1.93\\times$) and frozen embedding transients (047, $1.71\\times$; 057, $1.88\\times$). Threshold calibrated and validated post-hoc; cross-architecture validation deferred.}\n\\label{fig:nve_roc}\n\\end{figure}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.7\\columnwidth]{../../artifacts/figures/nve_threshold_prf.pdf}\n\\caption{Precision, Recall, and F1 as a function of NVE threshold ($n{=}56$ configurations). Peak F1${=}0.941$ at $\\tau{=}1.5\\times$, where recall remains perfect ($1.00$) and precision${=}0.889$. The plateau of high F1 across $\\tau \\in [1.5, 1.7]$ indicates robustness to threshold selection.}\n\\label{fig:nve_prf}\n\\end{figure}\n\nWe label a configuration as CIVO-positive if and only if (i)~it uses a trained $\\dt$-embedding with multi-rate data exposure, and (ii)~NVE exceeds $1.5\\times$ with co-occurring entropy collapse. Configurations exhibiting high NVE through other mechanisms (gradient truncation side effects, value anchor pollution) are labeled non-CIVO.\n\nThe three false positives (FPR${=}0.18$) are mechanistically distinct from CIVO: (1)~RAVE anchor pollution (exp\\_028, the EMA anchor becomes inflated, producing overestimation through a different pathway); (2)~obs-decoder SGS-induced value distortion (exp\\_025 seed~2, blocking observation decoder gradients damages the RSSM latent space); (3)~IRD eval-driven collapse (exp\\_008e\\_v3 seed~2, actor entropy \\emph{increases} with evaluation collapse, mechanistically distinct from CIVO's entropy \\emph{decrease}). All three produce NVE $> 1.5\\times$ through non-CIVO mechanisms, indicating that the NVE diagnostic detects value overestimation broadly rather than CIVO specifically---a feature rather than a limitation for practitioners monitoring deployment health. The closest sub-threshold case (008f seed~4, NVE${=}1.41\\times$) lacks $\\dt$-conditioning entirely ($d{=}0$); its elevated NVE reflects transient value noise that self-corrects without the positive feedback loop characteristic of CIVO. The closest above-threshold positive (008d seed~3, NVE${=}1.53\\times$) exhibits the full CIVO causal chain: trained $\\dt$-embedding, entropy decrease, and evaluation collapse to 14\\% of baseline.\n\n\\paragraph{Comprehensive validation ($n{=}56$).}\nExpanding the evaluation set to all classifiable experiments yields $n{=}56$ ($n_{\\text{pos}}{=}24$, $n_{\\text{neg}}{=}32$), spanning Walker Walk, Cheetah Run, and multiple intervention configurations (SGS, TCN, dual-critic, frozen embedding). At the $1.5\\times$ threshold: AUROC${=}0.990$, precision${=}0.889$, recall${=}1.000$, F1${=}0.941$, accuracy${=}53/56$. The three false positives are: exp\\_008e\\_v3\\_subsample ($1.93\\times$, mitigation config with transient VE spike), exp\\_047 ($1.71\\times$, frozen embedding transient), and exp\\_057 ($1.88\\times$, frozen embedding transient). All 24 CIVO-positive configurations are correctly detected (FN${=}0$), with CIVO-positive NVE ranging from $1.53\\times$ (008d seed~3, late-onset) to $70.64\\times$ (010b seed~0, Cheetah). The substantial increase in sample size from $n{=}32$ to $n{=}56$ strengthens confidence in the $1.5\\times$ threshold as a robust diagnostic boundary.\n\n\\subsection{NVE Normalization Robustness}\n\\label{sec:nve_robustness}\n\nTo assess sensitivity to baseline seed choice, we extend the single-seed baseline (seed~1, eval 915.7 at 105K) to three additional seeds trained to 505K steps (Table~\\ref{tab:baseline_seeds}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Walker Walk baseline seeds at 105K and 505K steps.}\n\\label{tab:baseline_seeds}\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Seed} & \\textbf{Eval@105K} & \\textbf{Eval@505K} & \\textbf{ve@65K} & \\textbf{ve@105K} \\\\\n\\midrule\ns1 & 915.7 & 970.4 & 0.563 & 0.656 \\\\\ns2 & 443.5 & 945.7 & 0.898 & 0.742 \\\\\ns3 & 869.0 & 947.7 & --- & 0.664 \\\\\ns4 & 922.8 & 938.9 & --- & 0.624 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nSeed~2 exhibits slow convergence (eval 443.5 at 105K, recovering to 945.7 by 512K), confirming non-pathological slow convergence rather than seed failure. Its elevated $v/e$ ratio at 65K (0.898 vs.\\ 0.563 for seed~1) reflects the low evaluation denominator rather than pathological value overestimation. Using seed~2 as the sole normalization reference systematically deflates NVE values, causing two marginal CIVO-positive configurations (008d seed~3, peak NVE $1.53\\times$; 009b seed~2, peak NVE $1.62\\times$) to fall below the $1.5\\times$ threshold. Core CIVO cases (peak NVE $> 3\\times$) remain correctly classified under all baseline seeds.\n\nSingle-seed normalization (s1) yields AUROC $= 0.933$ and accuracy 7/8 (87.5\\%) on the Walker subset. Four-seed mean normalization yields AUROC $= 0.867$ and accuracy 6/8 (75.0\\%): the boundary case exp\\_009b flips from $\\nve = 1.62\\times$ (s1) to $1.23\\times$ (4-seed mean), because its peak occurs at 45K when the s1 $v/e$ ratio (0.331) is well below the 4-seed mean (0.436). All high-NVE configurations remain correctly classified (006: $4.84\\times \\to 4.52\\times$; 008d: $4.12\\times \\to 3.54\\times$). The $1.5\\times$ threshold thus correctly identifies all strong CIVO cases regardless of baseline choice; sensitivity is confined to configurations within 10\\% of the threshold.\n",
      "numLines": 300,
      "startLine": 1,
      "totalLines": 1174
    }
  }
}
```

</details>

---


### Tool call

_source line 11_

<details open><summary>🔧 Tool call — Grep · `toolu_012y7dLQFyz9kXopfUc7RjJf`</summary>

```json
{
  "pattern": "IRD|Pathway B|Multiple.*Pathway|008e_v3|3\\.78|4\\.02|false.positive",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
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
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "06351ff3-6c85-4070-b30e-4cf34af7394c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JiVHAXvDYHCzZYZD4RgsDc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 211,
      "cache_read_input_tokens": 23882,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 211
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

_source line 12 · 2026-05-25T16:23:24.887Z_

<details><summary>↩ Tool result · `toolu_012y7dLQFyz9kXopfUc7RjJf`</summary>

```text
10:\caption{Complete experimental results. NVE reports peak $\nve$ in the 35K+ window (\S\ref{sec:metrics}). CIVO-positive seeds are shaded; $\dagger$\,marks a false positive (non-CIVO collapse with elevated NVE).}
55:008e\_v3 s2$^\dagger$ & Mitigation & trn & ON & 15 & 137.0 @105K & 3.78$\times$ & Non-CIVO collapse \\
57:008e\_v3 s3 & Mitigation & trn & ON & 15 & 92.7 @105K & 4.02$\times$ & CIVO collapse \\
76:019b & PickCube-v1 & trn & ON & 8 & 26.64 @200K & 3.78$\times$$^c$ & Transient onset \\
143:Table~\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\_v3 seeds and exp\_059). Experiments are sorted by descending NVE. Experiment 008e\_v3\_s2 exhibits elevated NVE ($3.78\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\_v3\_s3 exhibits CIVO with NVE $4.02\times$ despite $\Delta t{=}1$ imagination.
147:\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\ = transient CIVO with self-correction.}
157:008e\_v3\_s3 & 4.02 & CIVO           & $+$ & $+$ \\
158:008e\_v3\_s2 & 3.78 & IRD (non-CIVO) & $-$ & $-$ \\
171:[Omitted long matching line]
175:\caption{\textbf{Task~B1}: Sustained CIVO detection sensitivity analysis ($n_{\text{pos}}=3$, $n_{\text{neg}}=8$, $n=11$, $\text{AUROC}=0.917$). All confidence intervals are two-sided Clopper-Pearson exact binomial ($\alpha=0.05$). $^\dagger$Optimal threshold in $(3.78, 4.02]$; exp\_059 (NVE${=}4.72\times$, B1-negative) is the sole false positive.}
197:\caption{\textbf{Task~B2}: Any CIVO detection sensitivity analysis ($n_{\text{pos}}=5$, $n_{\text{neg}}=6$, $n=11$, $\text{AUROC}=0.967$). The single false positive at $\geq 1.5\times$ is 008e\_v3\_s2 (IRD mechanism, not CIVO). The $1.5\times$ threshold (highlighted) maximizes F1 while maintaining perfect recall.}
243:\item \textbf{Best F1.} At $1.5\times$, F1 = 90.9\%, the highest among all tested thresholds for B2. The single false positive (008e\_v3\_s2) is mechanistically identifiable as IRD rather than CIVO.
244:\item \textbf{Sensitivity--specificity tradeoff.} Lower thresholds ($1.0\times$) add false positives without gaining true positives. Higher thresholds ($\geq 1.7\times$) sacrifice recall without eliminating the 008e\_v3\_s2 false positive (which requires $\tau > 3.78$).
247:For Task~B1 (sustained CIVO only), the optimal threshold $\nve \geq 3.9\times$ achieves $10/11$ accuracy ($90.9\%$, 95\% CI: [58.7\%, 99.8\%]); the sole false positive is exp\_059 (NVE${=}4.72\times$, self-correcting CIVO classified as B1-negative).
257:[Omitted long matching line]
270:[Omitted long matching line]
273:[Omitted long matching line]
323:Walker   &  7 & 15 & $(1.00,\, 3.78)$ & 14/15 (0.933) & 0.963 \\
330:[Omitted long matching line]
339:[Omitted long matching line]
762:[Omitted long matching line]
777:IRD collapse & 008e\_v3\_s2 & $\uparrow$ late & $\uparrow$ & Entropy-driven, values stable \\
797:[Omitted long matching line]
947:\subsection{Multiple Vulnerability Pathways}
950:[Omitted long matching line]
1077:Sensitivity analysis over $\tau_\text{mag} \in [0.30, 0.70]$ confirms that $\tau_\text{mag} = 0.49$ maximizes Youden's $J = 0.714$; raising the threshold to $0.50$ loses one true positive (seed~3 triggers at $r_t = 0.497$) with no reduction in false positives. The velocity threshold $\tau_\text{vel} = 0.1$ is stable across $[0.05, 0.18]$ (TPR remains $5/5$).
1114:The detector identifies all five CIVO-positive runs (TPR = 5/5). Two are detected predictively (008d seeds~0 and~3, both at 45K). Two false positives occur among nine negative cases (FPR = 2/9, precision 71\%, F$_1$ = 0.83). Run 009c develops genuine late-stage value overestimation unrelated to CIVO; run 009a triggers during a transient eval dip at 85K before recovery to 966. Early alerts (before 70K) carry higher diagnostic confidence.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "8bee8724-81c6-4084-9351-6858122bf10f",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "10:\\caption{Complete experimental results. NVE reports peak $\\nve$ in the 35K+ window (\\S\\ref{sec:metrics}). CIVO-positive seeds are shaded; $\\dagger$\\,marks a false positive (non-CIVO collapse with elevated NVE).}\n55:008e\\_v3 s2$^\\dagger$ & Mitigation & trn & ON & 15 & 137.0 @105K & 3.78$\\times$ & Non-CIVO collapse \\\\\n57:008e\\_v3 s3 & Mitigation & trn & ON & 15 & 92.7 @105K & 4.02$\\times$ & CIVO collapse \\\\\n76:019b & PickCube-v1 & trn & ON & 8 & 26.64 @200K & 3.78$\\times$$^c$ & Transient onset \\\\\n143:Table~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\\_v3 seeds and exp\\_059). Experiments are sorted by descending NVE. Experiment 008e\\_v3\\_s2 exhibits elevated NVE ($3.78\\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\\_v3\\_s3 exhibits CIVO with NVE $4.02\\times$ despite $\\Delta t{=}1$ imagination.\n147:\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\\ = transient CIVO with self-correction.}\n157:008e\\_v3\\_s3 & 4.02 & CIVO           & $+$ & $+$ \\\\\n158:008e\\_v3\\_s2 & 3.78 & IRD (non-CIVO) & $-$ & $-$ \\\\\n171:[Omitted long matching line]\n175:\\caption{\\textbf{Task~B1}: Sustained CIVO detection sensitivity analysis ($n_{\\text{pos}}=3$, $n_{\\text{neg}}=8$, $n=11$, $\\text{AUROC}=0.917$). All confidence intervals are two-sided Clopper-Pearson exact binomial ($\\alpha=0.05$). $^\\dagger$Optimal threshold in $(3.78, 4.02]$; exp\\_059 (NVE${=}4.72\\times$, B1-negative) is the sole false positive.}\n197:\\caption{\\textbf{Task~B2}: Any CIVO detection sensitivity analysis ($n_{\\text{pos}}=5$, $n_{\\text{neg}}=6$, $n=11$, $\\text{AUROC}=0.967$). The single false positive at $\\geq 1.5\\times$ is 008e\\_v3\\_s2 (IRD mechanism, not CIVO). The $1.5\\times$ threshold (highlighted) maximizes F1 while maintaining perfect recall.}\n243:\\item \\textbf{Best F1.} At $1.5\\times$, F1 = 90.9\\%, the highest among all tested thresholds for B2. The single false positive (008e\\_v3\\_s2) is mechanistically identifiable as IRD rather than CIVO.\n244:\\item \\textbf{Sensitivity--specificity tradeoff.} Lower thresholds ($1.0\\times$) add false positives without gaining true positives. Higher thresholds ($\\geq 1.7\\times$) sacrifice recall without eliminating the 008e\\_v3\\_s2 false positive (which requires $\\tau > 3.78$).\n247:For Task~B1 (sustained CIVO only), the optimal threshold $\\nve \\geq 3.9\\times$ achieves $10/11$ accuracy ($90.9\\%$, 95\\% CI: [58.7\\%, 99.8\\%]); the sole false positive is exp\\_059 (NVE${=}4.72\\times$, self-correcting CIVO classified as B1-negative).\n257:[Omitted long matching line]\n270:[Omitted long matching line]\n273:[Omitted long matching line]\n323:Walker   &  7 & 15 & $(1.00,\\, 3.78)$ & 14/15 (0.933) & 0.963 \\\\\n330:[Omitted long matching line]\n339:[Omitted long matching line]\n762:[Omitted long matching line]\n777:IRD collapse & 008e\\_v3\\_s2 & $\\uparrow$ late & $\\uparrow$ & Entropy-driven, values stable \\\\\n797:[Omitted long matching line]\n947:\\subsection{Multiple Vulnerability Pathways}\n950:[Omitted long matching line]\n1077:Sensitivity analysis over $\\tau_\\text{mag} \\in [0.30, 0.70]$ confirms that $\\tau_\\text{mag} = 0.49$ maximizes Youden's $J = 0.714$; raising the threshold to $0.50$ loses one true positive (seed~3 triggers at $r_t = 0.497$) with no reduction in false positives. The velocity threshold $\\tau_\\text{vel} = 0.1$ is stable across $[0.05, 0.18]$ (TPR remains $5/5$).\n1114:The detector identifies all five CIVO-positive runs (TPR = 5/5). Two are detected predictively (008d seeds~0 and~3, both at 45K). Two false positives occur among nine negative cases (FPR = 2/9, precision 71\\%, F$_1$ = 0.83). Run 009c develops genuine late-stage value overestimation unrelated to CIVO; run 009a triggers during a transient eval dip at 85K before recovery to 966. Early alerts (before 70K) carry higher diagnostic confidence.",
    "numLines": 27
  }
}
```

</details>

---


### Assistant

_source line 13_

<details><summary>Logged reasoning block</summary>

```text
Let me now read the rest of the file to find all the locations that need fixing. I need to see lines around 300-400, 700-800, and 900-1000+.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "ab1785a8-f456-4715-937a-c95c86af9173",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GjKQf26HuL5aPEpogL2SM6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12503,
      "cache_read_input_tokens": 24093,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12503
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

_source line 14_

Let me read the remaining sections that need modification.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "6b532ccf-4057-4313-8cba-617b72bfd971",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GjKQf26HuL5aPEpogL2SM6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12503,
      "cache_read_input_tokens": 24093,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12503
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

_source line 15_

<details open><summary>🔧 Tool call — Read · `toolu_01G87MP5taNmvDniA1YiG2RA`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
  "offset": 300,
  "limit": 100
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "d17787e2-6d0a-49b9-aa53-c345d8b883ba",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GjKQf26HuL5aPEpogL2SM6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12503,
      "cache_read_input_tokens": 24093,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12503
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

_source line 16 · 2026-05-25T16:23:30.829Z_

<details><summary>↩ Tool result · `toolu_01G87MP5taNmvDniA1YiG2RA`</summary>

```text
300	
301	\paragraph{Normalization conventions.} Walker NVE is normalized against the single-seed baseline (seed~1, exp\_001, 505K steps). Cheetah NVE is normalized against a 5-seed mean baseline (seeds~0--4, each run to ${\sim}$210K steps). The differing seed counts reflect available baseline data; both provide sufficient coverage of the respective experimental windows (Walker: 210K analysis window; Cheetah: 105K analysis window).
302	
303	\paragraph{Limitations.} The initial $n{=}11$ analysis had wide Clopper-Pearson confidence intervals (e.g., 90.9\% accuracy, 95\% CI [58.7\%, 99.8\%]). The comprehensive evaluation ($n{=}56$, AUROC${=}0.990$, F1${=}0.941$; Figure~\ref{fig:nve_roc}) substantially tightens these bounds. Table~\ref{tab:sensitivity_b2_full} reports the $n{=}17$ two-environment core evaluation. Cross-architecture validation is deferred to future work.
304	
305	\subsection{Leave-One-Environment-Out Cross-Validation}
306	\label{sec:nve_loeo}
307	
308	To assess whether $\theta{=}1.5\times$ generalizes beyond the in-sample evaluation, we perform leave-one-environment-out (LOEO) cross-validation across Walker ($n{=}15$), Cheetah ($n{=}5$), and PickCube ($n{=}2$). For each fold, we hold out all experiments from one environment, select the optimal accuracy-maximizing threshold range on the remaining training set, and evaluate the fixed $\theta{=}1.5\times$ on the held-out environment.
309	
310	\begin{table}[h]
311	\centering
312	\caption{Leave-one-environment-out cross-validation of NVE threshold $\theta=1.5\times$.
313	For each fold, the threshold is validated on an environment whose data was \emph{not} used
314	to select $\theta$. The optimal threshold range on each training set is reported;
315	$\theta=1.5$ falls within the optimal range in all three folds.}
316	\label{tab:nve_loeo}
317	\begin{tabular}{lccccc}
318	\toprule
319	Held-out & $N_{\text{train}}$ & $N_{\text{test}}$ & $\theta_{\text{opt}}$ range & Test Accuracy & Test AUROC \\
320	\midrule
321	PickCube & 20 & 2 & $(1.45,\, 1.53]$ & 2/2 (1.000) & 1.000 \\
322	Cheetah  & 17 & 5 & $(1.45,\, 1.53]$ & 5/5 (1.000) & 1.000 \\
323	Walker   &  7 & 15 & $(1.00,\, 3.78)$ & 14/15 (0.933) & 0.963 \\
324	\midrule
325	\textbf{Mean} & — & — & — & \textbf{0.978} & \textbf{0.988} \\
326	\bottomrule
327	\end{tabular}
328	\end{table}
329	
330	The threshold $\theta{=}1.5\times$ falls within the optimal accuracy range for all three training folds: $(1.45, 1.53]$ when Walker data is available, and the wider $(1.00, 3.78)$ when training on Cheetah$+$PickCube only (where CIVO and non-CIVO NVE values are well-separated). The single cross-validation error is exp\_008e\_v3 seed~2 (Walker), an IRD collapse mechanistically distinct from CIVO (\S\ref{sec:roc_analysis}). Mean held-out accuracy is 0.978 and mean AUROC is 0.988, confirming that $\theta{=}1.5\times$ generalizes across environments without retuning.
331	PickCube fold confidence intervals remain wide (Clopper-Pearson 95\% CI: $[0.158, 1.000]$) due to $N_{\text{test}}{=}2$.
332	
333	\subsection{Leave-One-Config-Out Cross-Validation}
334	\label{sec:nve_loco}
335	
336	\paragraph{Leave-One-Config-Out Cross-Validation.}
337	To rule out threshold overfitting to any particular experimental configuration, we perform leave-one-config-out (LOCO) cross-validation over $K{=}12$ configuration groups (e.g., \texttt{008d\_civo\_trigger}, \texttt{frozen\_dt\_emb}, \texttt{tcn}; $n{=}56$ total). Each fold holds out all experiments from one configuration, selects the F1-maximizing threshold on the remaining $K{-}1$ groups, and evaluates on the held-out group.
338	
339	In $10/12$ folds, the training-optimal threshold falls within $\pm 0.05$ of $\theta{=}1.5\times$ (mean $1.61 \pm 0.23$, range $[1.47, 2.12]$). The two folds selecting a higher threshold ($\theta{=}2.1$; \texttt{008d\_civo\_trigger} and \texttt{tcn}, both predominantly CIVO-positive) perform \emph{worse} on their held-out sets than $\theta{=}1.5$ (accuracy $0.78$/$0.88$ vs.\ $1.00$/$1.00$), confirming that the fixed threshold generalizes better than per-fold optimization in these cases. Cross-validated accuracy at $\theta{=}1.5$ is $53/56 = 94.6\%$, identical to the in-sample result, with train AUROC consistently high across folds ($0.988 \pm 0.003$). The three misclassifications are the same mechanistically distinct false positives identified in \S\ref{sec:roc_analysis}: two frozen-embedding transients (exp\_047, exp\_057) and one mitigation-config transient (exp\_008e\_v3\_subsample). No CIVO-positive configuration is missed in any fold (FN${=}0$ across all 12 folds).
340	
341	% --- APPENDIX B: Factorial Ablation Details ---
342	
343	\section{Factorial Ablation Details}
344	\label{sec:appendix_factorial}
345	
346	This appendix provides the full factorial ablation results summarized in \S\ref{sec:f3f5_summary} of the main text.
347	
348	\paragraph{Embedding gradient analysis.}
349	Table~\ref{tab:three_way_emb} isolates embedding \emph{trainability} as the necessary condition for CIVO by comparing four gradient conditions under otherwise identical configurations ($H{=}8$, subsample ON, $\dt{=}2$ imagination).
350	
351	\begin{table}[h]
352	\centering
353	\caption{$\dt$-embedding gradient conditions on Walker Walk. Any gradient pathway updating $e_{\dt}$ is sufficient to induce CIVO; freezing or removing the embedding dramatically reduces severity.}
354	\label{tab:three_way_emb}
355	\footnotesize
356	\begin{tabular}{lccccl}
357	\toprule
358	Condition & Grad flow & Exp(s) & NVE peak & Eval & CIVO \\
359	\midrule
360	Trained & all & 008d, 059 & $1.53$--$4.72\times$ & 64--268 & 5/5 \\
361	Reward detach & obs+KL only & 044 & $4.45\times$ & 44$\to$538$^\dagger$ & 1/1 \\
362	Full SGS & KL only & 018 & $1.66\times$ & 448 & 1/1$^*$ \\
363	Frozen & none & 042, 015b, 047, 057 & $0.19$--$1.88\times$$^\ddagger$ & 204--612 & 2/4 \\
364	Removed & N/A & 008f & $0.97$--$1.41\times$ & 307--503 & 0/3 \\
365	\bottomrule
366	\end{tabular}
367	\vspace{1pt}
368	{\raggedright\footnotesize $^*$Full-SGS seed~1 (NVE $1.66\times$); seed~2 collapsed. $^\dagger$Self-corrected at ${\sim}175$K (eval 44$\to$538, 59\% baseline; 224K run). $^\ddagger$Exp\_047 (NVE $1.71\times$) and Exp\_057 (NVE $1.88\times$): both transient, self-correcting within 20K steps.\par}
369	\end{table}
370	
371	\paragraph{Controlled three-way causal ablation.}
372	Experiments 067--069 provide a minimal causal ablation on Walker Walk (seed${=}1$), varying \emph{only} the $\dt$-embedding treatment while holding all other hyperparameters fixed ($H{=}8$, subsample ON, $\dt{=}2$ imagination). Table~\ref{tab:causal_ablation} shows that trained $\dt$-embedding is necessary and sufficient for CIVO: freezing the embedding (gradient flow blocked, embedding weights still present) eliminates CIVO as completely as removing the embedding ($d{=}0$), ruling out the alternative hypothesis that embedding \emph{presence} alone causes CIVO. Combined with all prior seeds, trained $\dt$-embedding triggers CIVO in 10/10 multi-joint locomotion seeds (8 Walker, 2 Cheetah) versus 0/8 controls (Fisher exact $p < 0.0001$).
373	
374	\begin{table}[h]
375	\centering
376	\caption{Three-way causal ablation (Walker Walk, seed${=}1$). Only the $\dt$-embedding treatment varies; all other configuration is identical. Trained embedding triggers CIVO; frozen and removed do not.}
377	\label{tab:causal_ablation}
378	\footnotesize
379	\begin{tabular}{llccl}
380	\toprule
381	\textbf{Exp} & \textbf{Embedding} & \textbf{NVE peak} & \textbf{Eval final} & \textbf{CIVO} \\
382	\midrule
383	\rowcolor{gray!15}
384	068 & Trained ($d{=}32$) & $6.57\times$ & 39.1 & Yes (alert @85K) \\
385	067 & Frozen ($d{=}32$, \texttt{req\_grad=F}) & $0.40\times$ & 281.5 & No \\
386	069 & Removed ($d{=}0$) & $0.66\times$ & 237.8 & No \\
387	\bottomrule
388	\end{tabular}
389	\end{table}
390	
391	The reward-detach condition (exp\_044, \texttt{reward\_dt\_emb\_detach=True}) uses a backward hook to block reward-head gradients from reaching $e_{\dt}$, complementing the framework-level Reward SGS (exp\_016e). Both yield the same directional result---CIVO onset not prevented---ruling out implementation artifacts. Exp\_044 exhibits delayed CIVO onset (${\sim}95$K vs.\ typical $25$--$35$K), consistent with reduced but non-zero gradient pressure on $e_{\dt}$. Over a full 224K run, exp\_044 self-corrects: eval recovers from 44 (95K) to 538 (215K, 59\% baseline), but this recovery is incomplete compared to spontaneous recovery without gradient intervention (exp\_045: 868, 95\% baseline). The lower asymptote suggests that selectively disrupting gradient flow may create optimization difficulties beyond CIVO itself.
392	
393	Table~\ref{tab:factorial_design} summarizes the experimental configurations.
394	
395	\begin{table}[ht]
396	\centering
397	\caption{Factorial design. Each row specifies one experimental configuration. \textbf{Emb}: $\dt$-embedding mode. \textbf{Sub}: temporal subsampling. \textbf{H}: imagination horizon. \textbf{Imag $\dt$}: temporal resolution used during imagination.}
398	\label{tab:factorial_design}
399	\small
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "a44a697c-080e-4827-a8f8-22bd569e283a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
      "content": "\n\\paragraph{Normalization conventions.} Walker NVE is normalized against the single-seed baseline (seed~1, exp\\_001, 505K steps). Cheetah NVE is normalized against a 5-seed mean baseline (seeds~0--4, each run to ${\\sim}$210K steps). The differing seed counts reflect available baseline data; both provide sufficient coverage of the respective experimental windows (Walker: 210K analysis window; Cheetah: 105K analysis window).\n\n\\paragraph{Limitations.} The initial $n{=}11$ analysis had wide Clopper-Pearson confidence intervals (e.g., 90.9\\% accuracy, 95\\% CI [58.7\\%, 99.8\\%]). The comprehensive evaluation ($n{=}56$, AUROC${=}0.990$, F1${=}0.941$; Figure~\\ref{fig:nve_roc}) substantially tightens these bounds. Table~\\ref{tab:sensitivity_b2_full} reports the $n{=}17$ two-environment core evaluation. Cross-architecture validation is deferred to future work.\n\n\\subsection{Leave-One-Environment-Out Cross-Validation}\n\\label{sec:nve_loeo}\n\nTo assess whether $\\theta{=}1.5\\times$ generalizes beyond the in-sample evaluation, we perform leave-one-environment-out (LOEO) cross-validation across Walker ($n{=}15$), Cheetah ($n{=}5$), and PickCube ($n{=}2$). For each fold, we hold out all experiments from one environment, select the optimal accuracy-maximizing threshold range on the remaining training set, and evaluate the fixed $\\theta{=}1.5\\times$ on the held-out environment.\n\n\\begin{table}[h]\n\\centering\n\\caption{Leave-one-environment-out cross-validation of NVE threshold $\\theta=1.5\\times$.\nFor each fold, the threshold is validated on an environment whose data was \\emph{not} used\nto select $\\theta$. The optimal threshold range on each training set is reported;\n$\\theta=1.5$ falls within the optimal range in all three folds.}\n\\label{tab:nve_loeo}\n\\begin{tabular}{lccccc}\n\\toprule\nHeld-out & $N_{\\text{train}}$ & $N_{\\text{test}}$ & $\\theta_{\\text{opt}}$ range & Test Accuracy & Test AUROC \\\\\n\\midrule\nPickCube & 20 & 2 & $(1.45,\\, 1.53]$ & 2/2 (1.000) & 1.000 \\\\\nCheetah  & 17 & 5 & $(1.45,\\, 1.53]$ & 5/5 (1.000) & 1.000 \\\\\nWalker   &  7 & 15 & $(1.00,\\, 3.78)$ & 14/15 (0.933) & 0.963 \\\\\n\\midrule\n\\textbf{Mean} & — & — & — & \\textbf{0.978} & \\textbf{0.988} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe threshold $\\theta{=}1.5\\times$ falls within the optimal accuracy range for all three training folds: $(1.45, 1.53]$ when Walker data is available, and the wider $(1.00, 3.78)$ when training on Cheetah$+$PickCube only (where CIVO and non-CIVO NVE values are well-separated). The single cross-validation error is exp\\_008e\\_v3 seed~2 (Walker), an IRD collapse mechanistically distinct from CIVO (\\S\\ref{sec:roc_analysis}). Mean held-out accuracy is 0.978 and mean AUROC is 0.988, confirming that $\\theta{=}1.5\\times$ generalizes across environments without retuning.\nPickCube fold confidence intervals remain wide (Clopper-Pearson 95\\% CI: $[0.158, 1.000]$) due to $N_{\\text{test}}{=}2$.\n\n\\subsection{Leave-One-Config-Out Cross-Validation}\n\\label{sec:nve_loco}\n\n\\paragraph{Leave-One-Config-Out Cross-Validation.}\nTo rule out threshold overfitting to any particular experimental configuration, we perform leave-one-config-out (LOCO) cross-validation over $K{=}12$ configuration groups (e.g., \\texttt{008d\\_civo\\_trigger}, \\texttt{frozen\\_dt\\_emb}, \\texttt{tcn}; $n{=}56$ total). Each fold holds out all experiments from one configuration, selects the F1-maximizing threshold on the remaining $K{-}1$ groups, and evaluates on the held-out group.\n\nIn $10/12$ folds, the training-optimal threshold falls within $\\pm 0.05$ of $\\theta{=}1.5\\times$ (mean $1.61 \\pm 0.23$, range $[1.47, 2.12]$). The two folds selecting a higher threshold ($\\theta{=}2.1$; \\texttt{008d\\_civo\\_trigger} and \\texttt{tcn}, both predominantly CIVO-positive) perform \\emph{worse} on their held-out sets than $\\theta{=}1.5$ (accuracy $0.78$/$0.88$ vs.\\ $1.00$/$1.00$), confirming that the fixed threshold generalizes better than per-fold optimization in these cases. Cross-validated accuracy at $\\theta{=}1.5$ is $53/56 = 94.6\\%$, identical to the in-sample result, with train AUROC consistently high across folds ($0.988 \\pm 0.003$). The three misclassifications are the same mechanistically distinct false positives identified in \\S\\ref{sec:roc_analysis}: two frozen-embedding transients (exp\\_047, exp\\_057) and one mitigation-config transient (exp\\_008e\\_v3\\_subsample). No CIVO-positive configuration is missed in any fold (FN${=}0$ across all 12 folds).\n\n% --- APPENDIX B: Factorial Ablation Details ---\n\n\\section{Factorial Ablation Details}\n\\label{sec:appendix_factorial}\n\nThis appendix provides the full factorial ablation results summarized in \\S\\ref{sec:f3f5_summary} of the main text.\n\n\\paragraph{Embedding gradient analysis.}\nTable~\\ref{tab:three_way_emb} isolates embedding \\emph{trainability} as the necessary condition for CIVO by comparing four gradient conditions under otherwise identical configurations ($H{=}8$, subsample ON, $\\dt{=}2$ imagination).\n\n\\begin{table}[h]\n\\centering\n\\caption{$\\dt$-embedding gradient conditions on Walker Walk. Any gradient pathway updating $e_{\\dt}$ is sufficient to induce CIVO; freezing or removing the embedding dramatically reduces severity.}\n\\label{tab:three_way_emb}\n\\footnotesize\n\\begin{tabular}{lccccl}\n\\toprule\nCondition & Grad flow & Exp(s) & NVE peak & Eval & CIVO \\\\\n\\midrule\nTrained & all & 008d, 059 & $1.53$--$4.72\\times$ & 64--268 & 5/5 \\\\\nReward detach & obs+KL only & 044 & $4.45\\times$ & 44$\\to$538$^\\dagger$ & 1/1 \\\\\nFull SGS & KL only & 018 & $1.66\\times$ & 448 & 1/1$^*$ \\\\\nFrozen & none & 042, 015b, 047, 057 & $0.19$--$1.88\\times$$^\\ddagger$ & 204--612 & 2/4 \\\\\nRemoved & N/A & 008f & $0.97$--$1.41\\times$ & 307--503 & 0/3 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$Full-SGS seed~1 (NVE $1.66\\times$); seed~2 collapsed. $^\\dagger$Self-corrected at ${\\sim}175$K (eval 44$\\to$538, 59\\% baseline; 224K run). $^\\ddagger$Exp\\_047 (NVE $1.71\\times$) and Exp\\_057 (NVE $1.88\\times$): both transient, self-correcting within 20K steps.\\par}\n\\end{table}\n\n\\paragraph{Controlled three-way causal ablation.}\nExperiments 067--069 provide a minimal causal ablation on Walker Walk (seed${=}1$), varying \\emph{only} the $\\dt$-embedding treatment while holding all other hyperparameters fixed ($H{=}8$, subsample ON, $\\dt{=}2$ imagination). Table~\\ref{tab:causal_ablation} shows that trained $\\dt$-embedding is necessary and sufficient for CIVO: freezing the embedding (gradient flow blocked, embedding weights still present) eliminates CIVO as completely as removing the embedding ($d{=}0$), ruling out the alternative hypothesis that embedding \\emph{presence} alone causes CIVO. Combined with all prior seeds, trained $\\dt$-embedding triggers CIVO in 10/10 multi-joint locomotion seeds (8 Walker, 2 Cheetah) versus 0/8 controls (Fisher exact $p < 0.0001$).\n\n\\begin{table}[h]\n\\centering\n\\caption{Three-way causal ablation (Walker Walk, seed${=}1$). Only the $\\dt$-embedding treatment varies; all other configuration is identical. Trained embedding triggers CIVO; frozen and removed do not.}\n\\label{tab:causal_ablation}\n\\footnotesize\n\\begin{tabular}{llccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Embedding} & \\textbf{NVE peak} & \\textbf{Eval final} & \\textbf{CIVO} \\\\\n\\midrule\n\\rowcolor{gray!15}\n068 & Trained ($d{=}32$) & $6.57\\times$ & 39.1 & Yes (alert @85K) \\\\\n067 & Frozen ($d{=}32$, \\texttt{req\\_grad=F}) & $0.40\\times$ & 281.5 & No \\\\\n069 & Removed ($d{=}0$) & $0.66\\times$ & 237.8 & No \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe reward-detach condition (exp\\_044, \\texttt{reward\\_dt\\_emb\\_detach=True}) uses a backward hook to block reward-head gradients from reaching $e_{\\dt}$, complementing the framework-level Reward SGS (exp\\_016e). Both yield the same directional result---CIVO onset not prevented---ruling out implementation artifacts. Exp\\_044 exhibits delayed CIVO onset (${\\sim}95$K vs.\\ typical $25$--$35$K), consistent with reduced but non-zero gradient pressure on $e_{\\dt}$. Over a full 224K run, exp\\_044 self-corrects: eval recovers from 44 (95K) to 538 (215K, 59\\% baseline), but this recovery is incomplete compared to spontaneous recovery without gradient intervention (exp\\_045: 868, 95\\% baseline). The lower asymptote suggests that selectively disrupting gradient flow may create optimization difficulties beyond CIVO itself.\n\nTable~\\ref{tab:factorial_design} summarizes the experimental configurations.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Factorial design. Each row specifies one experimental configuration. \\textbf{Emb}: $\\dt$-embedding mode. \\textbf{Sub}: temporal subsampling. \\textbf{H}: imagination horizon. \\textbf{Imag $\\dt$}: temporal resolution used during imagination.}\n\\label{tab:factorial_design}\n\\small",
      "numLines": 100,
      "startLine": 300,
      "totalLines": 1174
    }
  }
}
```

</details>

---


### Tool call

_source line 17_

<details open><summary>🔧 Tool call — Read · `toolu_01EFcvYpB4GkdgcCwRvUL7uN`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
  "offset": 740,
  "limit": 100
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "a2c63268-b990-41f9-9bd7-123b98922761",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GjKQf26HuL5aPEpogL2SM6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12503,
      "cache_read_input_tokens": 24093,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12503
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

_source line 18 · 2026-05-25T16:23:31.791Z_

<details><summary>↩ Tool result · `toolu_01EFcvYpB4GkdgcCwRvUL7uN`</summary>

```text
740	Walker & s1 (008d) & 4.12$\times$ & 4.12$\times$ & 82.8 & Full collapse \\
741	Walker & s2 (009b) & 1.62$\times$ & 0.38$\times$ & 267.9 & Transient CIVO \\
742	Walker & s3 (008d\_s3) & 1.53$\times$ & 1.53$\times$ & 268$^\diamond$ & Late-onset collapse \\
743	Walker & s4 (008d\_s4) & 4.62$\times$ & 4.62$\times$ & 63.6 & Full collapse \\
744	Walker & s5 (059) & 4.72$\times$ & 1.22$\times$ & 95.8 & Collapse$^\dagger$ \\
745	\midrule
746	Cheetah & s1 (010b) & 8.27$\times$ & 8.27$\times$ & 51.7 & Full collapse \\
747	Cheetah & s0 (078) & 4.10$\times$ & 0.29$\times$ & 119.5 & Self-correcting$^\ddagger$ \\
748	Cheetah & s0 (010b\_s0) & 108.52$\times$ & 108.52$\times$ & 0.83 & Full collapse \\
749	\bottomrule
750	\end{tabular}
751	\vspace{1pt}
752	{\raggedright\footnotesize $^\diamond$ Transitional; train returns still declining at 105K. $^\dagger$~NVE self-corrected ($4.72\times$ $\to$ $1.22\times$) but policy did not recover (eval 10.5\% of baseline). $^\ddagger$~Peak NVE $4.10\times$ at 75K; eval 213.7$\to$26.1$\to$119.5 (26.7\% of baseline exp\_077, 448.1).\par}
753	\end{table}
754	
755	All ten CIVO-positive runs cross the $\nve > 1.5\times$ threshold (Table~\ref{tab:post_civo}), yet the downstream damage is stochastic.\footnote{Exp\_009e was excluded from multi-seed analyses due to a seed configuration error (default seed=0, identical to exp\_008d).}  Sustained collapse is the majority outcome (6/10 runs). Three runs self-correct (Walker seed~2 and both Cheetah seeds, including exp\_078 which recovers from 26.1 to 119.5 at 105K); one (Walker seed~5) shows onset without sustained collapse---NVE self-corrects ($4.72\times \to 1.22\times$) but the policy remains collapsed (eval 10.5\% of baseline). Cheetah seed~1 (010b) exhibits more extreme overestimation (peak NVE $8.27\times$) than Walker seeds ($1.53$--$4.62\times$), consistent with the Cheetah reward scale amplifying the fidelity gap.  We hypothesize that the divergence relates to the critic's representational capacity at the time of CIVO onset.  \citet{lyle2022capacity} demonstrate that deep RL networks suffer progressive capacity loss, in which early-learned features become increasingly difficult to overwrite.  If the critic's capacity is already partially consumed when CIVO injects overestimation, the network cannot recalibrate (seed~0); if sufficient capacity remains, the critic can absorb transient overestimation and recover (seed~2).
756	
757	\paragraph{A fourth trajectory: CIVO-induced persistent value collapse.}
758	Obs-decoder SGS seed~3 (exp\_025) exhibits a trajectory not observed in the untreated seeds: healthy through 105K ($\nve < 1.0\times$, eval 818.6), CIVO onset at 135K ($\nve = 5.47\times$, eval 67.0), followed by evaluation recovery (590.2 at 215K, 64\% of baseline) but persistent value collapse ($\nve = 0.14\times$, value mean 80.6). The critic undershoots after the CIVO episode, suggesting that CIVO-induced representational damage persists even when the policy partially recovers. This contrasts with transient CIVO (seed~2, 009b), where both value and evaluation recover jointly, and with full collapse (seed~1, 008d), where neither recovers. Seed~4 exhibits the same terminal value collapse ($\nve = 0.14\times$ at 215K, eval 242), suggesting this overcorrection is systematic rather than seed-specific. The pattern adds a fourth post-CIVO outcome---policy recovery with critic damage---to the three documented in Table~\ref{tab:post_civo}.
759	
760	\subsubsection{Failure and Degradation Mode Taxonomy}
761	
762	Table~\ref{tab:failure_modes} classifies the seven distinct failure and degradation modes observed across all experimental configurations. The taxonomy reveals that CIVO is not a single failure mode but a family of related pathologies, with the trained $\dt$-embedding creating vulnerability through at least three independent mechanisms: value-driven collapse (monotonic, late-onset, and SGS-resistant CIVO), entropy-driven instability (IRD collapse), and gradient-mediated effects (gradient starvation, SGS-paradoxical worsening).
763	
764	\begin{table}[ht]
765	\centering
766	\caption{Failure and degradation mode taxonomy. Each mode is characterized by its NVE trajectory, entropy behavior, and primary mechanism.}
767	\label{tab:failure_modes}
768	\footnotesize
769	\setlength{\tabcolsep}{3pt}
770	\begin{tabular}{@{}llccl@{}}
771	\toprule
772	\textbf{Mode} & \textbf{Representative} & \textbf{NVE} & \textbf{Entropy} & \textbf{Mechanism} \\
773	\midrule
774	Monotonic CIVO & 008d, 008d\_s4, 010b\_s0 & $\uparrow$ sustained & $\downarrow$ & Reward bias $\to$ critic $\to$ actor \\
775	Late-onset CIVO & 008d\_s3 & $\uparrow$ delayed & $\downarrow$ & Same, delayed onset \\
776	Transient CIVO & 009b & Peak $\to$ $\downarrow$ & Stable & Self-correction via capacity \\
777	IRD collapse & 008e\_v3\_s2 & $\uparrow$ late & $\uparrow$ & Entropy-driven, values stable \\
778	Grad.\ starvation & 015b & Oscillates, decays & Stable & Frozen emb $\to$ zero actor grad \\
779	SGS-resistant & 018\_s2 & $\uparrow$ & $\downarrow$ & Forward-pass conditioning \\
780	SGS-paradoxical & 016e & $\uparrow$ sustained & $\downarrow$ & Reward SGS $\to$ obs-dec reliance \\
781	\bottomrule
782	\end{tabular}
783	\end{table}
784	
785	\subsection{Extended Training Dynamics}\label{sec:extended_training}
786	
787	One Walker seed (s3, exp\_045) was extended from 112K to approximately 302K steps to investigate long-horizon CIVO dynamics. After onset (NVE peak $4.91\times$ at 132K steps), the system exhibited complete self-recovery: NVE declined to $0.05\times$ and evaluation performance recovered to 867.6 (94.7\% of baseline). This recovery required approximately 170K additional training steps beyond onset. The trajectory shows a single onset--recovery cycle with no recurrence, suggesting that the CIVO feedback loop can break spontaneously given sufficient training---though at substantial computational cost that the frozen $\dt$-embedding diagnostic eliminates entirely.
788	
789	\subsection{Why MPC Is Immune}
790	\label{sec:mpc_immune}
791	
792	\citet{nhu2025tawm} show that $\dt$-conditioning benefits TD-MPC2, raising the question of why it fails in DreamerV3.  The critical difference is that MPC re-plans from real states at every step, so imagination errors do not accumulate into the training signal because there is no critic bootstrapping from imagined trajectories.  In DreamerV3, the actor-critic trains entirely within imagination, and any systematic reward-prediction bias at $\dt > 1$ is amplified through the closed actor-critic loop.
793	
794	\subsection{The \texorpdfstring{$\dt$}{dt}-Embedding Dilemma}
795	\label{sec:embedding_dilemma}
796	
797	The factorial results reveal a fundamental tension: removing the $\dt$-embedding (008f) eliminates CIVO but at a $13\times$ cost to reward prediction quality ($0.7469$ vs.\ $0.0568$ MAE), as the world model cannot distinguish temporal scales.  Restricting imagination to $\dt{=}1$ while retaining the trained embedding (008e\_v3) avoids collapse in 2 of 4 seeds (50\%), while the remaining two collapse via distinct mechanisms: Pathway~A (CIVO-driven, entropy decrease; s3, NVE $4.02\times$) and Pathway~B (entropy-driven, entropy increase; s2, NVE $3.78\times$; \S\ref{sec:f6}).  Neither approach alone provides a complete solution.
798	
799	\subsection{Temporal Embedding Representation Analysis}
800	\label{sec:cosine_evolution}
801	
802	To understand how the trained $\dt$-embedding creates vulnerability, we analyze the cosine similarity between $e(\dt{=}1)$ and $e(\dt{=}2)$ across training (exp\_065). Trained embeddings learn \emph{near-opposite} representations: $\cos(e_1, e_2) = {-}0.87$ to ${-}0.94$ at 25K steps across three configurations (Walker 008d\_s3, Cheetah 010b\_s0, Walker 059\_s5), persisting at ${-}0.70$ to ${-}0.86$ at 75K steps. In contrast, frozen embeddings maintain near-zero similarity ($-0.15$ to $+0.07$, constant throughout training). The near-antipodal learned representations explain the large reward prediction gap (\S\ref{sec:f2}): $\dt{=}2$ conditioning pushes the RSSM into a qualitatively different region of latent space, producing systematically biased predictions rather than minor perturbations.
803	
804	\subsection{\texorpdfstring{$\dt$}{dt}-Embedding Differentiation Precedes Value Divergence}
805	\label{sec:cosine_temporal}
806	
807	The preceding analysis established that trained $\dt$-embeddings learn near-antipodal representations. Here we resolve the \emph{temporal dynamics} of this differentiation across 11 experiments (${\sim}$47 checkpoints), testing whether embedding differentiation is a consequence or precursor of CIVO.
808	
809	\paragraph{Trained embeddings: monotonic relaxation.}
810	Across all trained configurations, $\cos(e_1, e_2)$ starts near $-0.95$ within 10K steps and relaxes monotonically toward ${\sim}{-}0.65$ (Table~\ref{tab:cosine_evolution_ext}).
811	
812	\begin{table}[h]
813	\centering
814	\caption{Cosine similarity evolution between $e(\dt{=}1)$ and $e(\dt{=}2)$ for trained $\dt$-embeddings. Relaxation is monotonic but never reaches zero; frozen embeddings remain constant near zero throughout training.}
815	\label{tab:cosine_evolution_ext}
816	\footnotesize
817	\setlength{\tabcolsep}{4pt}
818	\begin{tabular}{llccccc}
819	\toprule
820	\textbf{Env} & \textbf{Experiment} & \textbf{10K} & \textbf{25K} & \textbf{65K} & \textbf{75K} & \textbf{302K} \\
821	\midrule
822	\multirow{2}{*}{Walker} & exp\_066b (trained) & $-0.947$ & $-0.928$ & $-0.847$ & --- & --- \\
823	 & exp\_045 (extension) & --- & --- & --- & --- & $-0.668$ \\
824	\midrule
825	Cheetah & exp\_010b$\to$048 & --- & $-0.904$ & --- & $-0.841$ & $-0.639$ \\
826	\midrule
827	\multicolumn{2}{l}{\textit{Frozen controls:}} \\
828	Walker & exp\_057 (frozen) & \multicolumn{5}{c}{$-0.150$ (constant, 25K--225K)} \\
829	Cheetah & exp\_058 (frozen) & \multicolumn{5}{c}{$+0.069$ (constant, 25K--225K)} \\
830	\bottomrule
831	\end{tabular}
832	\end{table}
833	
834	Cross-seed consistency at 25K steps is high: mean $\cos = -0.910 \pm 0.028$ ($n{=}5$ Walker seeds), confirming the relaxation pattern is robust across random seeds. Variance increases with training ($-0.789 \pm 0.076$ at 75K), reflecting seed-dependent relaxation rates.
835	
836	\paragraph{Temporal precedence over CIVO.}
837	Exp\_066b provides simultaneous cosine similarity and CIVO diagnostic data at 5K resolution (Table~\ref{tab:cosine_vs_civo}).
838	
839	\begin{table}[h]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "1a8606c4-324c-4e0b-bd11-6d5344bcc95d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
      "content": "Walker & s1 (008d) & 4.12$\\times$ & 4.12$\\times$ & 82.8 & Full collapse \\\\\nWalker & s2 (009b) & 1.62$\\times$ & 0.38$\\times$ & 267.9 & Transient CIVO \\\\\nWalker & s3 (008d\\_s3) & 1.53$\\times$ & 1.53$\\times$ & 268$^\\diamond$ & Late-onset collapse \\\\\nWalker & s4 (008d\\_s4) & 4.62$\\times$ & 4.62$\\times$ & 63.6 & Full collapse \\\\\nWalker & s5 (059) & 4.72$\\times$ & 1.22$\\times$ & 95.8 & Collapse$^\\dagger$ \\\\\n\\midrule\nCheetah & s1 (010b) & 8.27$\\times$ & 8.27$\\times$ & 51.7 & Full collapse \\\\\nCheetah & s0 (078) & 4.10$\\times$ & 0.29$\\times$ & 119.5 & Self-correcting$^\\ddagger$ \\\\\nCheetah & s0 (010b\\_s0) & 108.52$\\times$ & 108.52$\\times$ & 0.83 & Full collapse \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^\\diamond$ Transitional; train returns still declining at 105K. $^\\dagger$~NVE self-corrected ($4.72\\times$ $\\to$ $1.22\\times$) but policy did not recover (eval 10.5\\% of baseline). $^\\ddagger$~Peak NVE $4.10\\times$ at 75K; eval 213.7$\\to$26.1$\\to$119.5 (26.7\\% of baseline exp\\_077, 448.1).\\par}\n\\end{table}\n\nAll ten CIVO-positive runs cross the $\\nve > 1.5\\times$ threshold (Table~\\ref{tab:post_civo}), yet the downstream damage is stochastic.\\footnote{Exp\\_009e was excluded from multi-seed analyses due to a seed configuration error (default seed=0, identical to exp\\_008d).}  Sustained collapse is the majority outcome (6/10 runs). Three runs self-correct (Walker seed~2 and both Cheetah seeds, including exp\\_078 which recovers from 26.1 to 119.5 at 105K); one (Walker seed~5) shows onset without sustained collapse---NVE self-corrects ($4.72\\times \\to 1.22\\times$) but the policy remains collapsed (eval 10.5\\% of baseline). Cheetah seed~1 (010b) exhibits more extreme overestimation (peak NVE $8.27\\times$) than Walker seeds ($1.53$--$4.62\\times$), consistent with the Cheetah reward scale amplifying the fidelity gap.  We hypothesize that the divergence relates to the critic's representational capacity at the time of CIVO onset.  \\citet{lyle2022capacity} demonstrate that deep RL networks suffer progressive capacity loss, in which early-learned features become increasingly difficult to overwrite.  If the critic's capacity is already partially consumed when CIVO injects overestimation, the network cannot recalibrate (seed~0); if sufficient capacity remains, the critic can absorb transient overestimation and recover (seed~2).\n\n\\paragraph{A fourth trajectory: CIVO-induced persistent value collapse.}\nObs-decoder SGS seed~3 (exp\\_025) exhibits a trajectory not observed in the untreated seeds: healthy through 105K ($\\nve < 1.0\\times$, eval 818.6), CIVO onset at 135K ($\\nve = 5.47\\times$, eval 67.0), followed by evaluation recovery (590.2 at 215K, 64\\% of baseline) but persistent value collapse ($\\nve = 0.14\\times$, value mean 80.6). The critic undershoots after the CIVO episode, suggesting that CIVO-induced representational damage persists even when the policy partially recovers. This contrasts with transient CIVO (seed~2, 009b), where both value and evaluation recover jointly, and with full collapse (seed~1, 008d), where neither recovers. Seed~4 exhibits the same terminal value collapse ($\\nve = 0.14\\times$ at 215K, eval 242), suggesting this overcorrection is systematic rather than seed-specific. The pattern adds a fourth post-CIVO outcome---policy recovery with critic damage---to the three documented in Table~\\ref{tab:post_civo}.\n\n\\subsubsection{Failure and Degradation Mode Taxonomy}\n\nTable~\\ref{tab:failure_modes} classifies the seven distinct failure and degradation modes observed across all experimental configurations. The taxonomy reveals that CIVO is not a single failure mode but a family of related pathologies, with the trained $\\dt$-embedding creating vulnerability through at least three independent mechanisms: value-driven collapse (monotonic, late-onset, and SGS-resistant CIVO), entropy-driven instability (IRD collapse), and gradient-mediated effects (gradient starvation, SGS-paradoxical worsening).\n\n\\begin{table}[ht]\n\\centering\n\\caption{Failure and degradation mode taxonomy. Each mode is characterized by its NVE trajectory, entropy behavior, and primary mechanism.}\n\\label{tab:failure_modes}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{@{}llccl@{}}\n\\toprule\n\\textbf{Mode} & \\textbf{Representative} & \\textbf{NVE} & \\textbf{Entropy} & \\textbf{Mechanism} \\\\\n\\midrule\nMonotonic CIVO & 008d, 008d\\_s4, 010b\\_s0 & $\\uparrow$ sustained & $\\downarrow$ & Reward bias $\\to$ critic $\\to$ actor \\\\\nLate-onset CIVO & 008d\\_s3 & $\\uparrow$ delayed & $\\downarrow$ & Same, delayed onset \\\\\nTransient CIVO & 009b & Peak $\\to$ $\\downarrow$ & Stable & Self-correction via capacity \\\\\nIRD collapse & 008e\\_v3\\_s2 & $\\uparrow$ late & $\\uparrow$ & Entropy-driven, values stable \\\\\nGrad.\\ starvation & 015b & Oscillates, decays & Stable & Frozen emb $\\to$ zero actor grad \\\\\nSGS-resistant & 018\\_s2 & $\\uparrow$ & $\\downarrow$ & Forward-pass conditioning \\\\\nSGS-paradoxical & 016e & $\\uparrow$ sustained & $\\downarrow$ & Reward SGS $\\to$ obs-dec reliance \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Extended Training Dynamics}\\label{sec:extended_training}\n\nOne Walker seed (s3, exp\\_045) was extended from 112K to approximately 302K steps to investigate long-horizon CIVO dynamics. After onset (NVE peak $4.91\\times$ at 132K steps), the system exhibited complete self-recovery: NVE declined to $0.05\\times$ and evaluation performance recovered to 867.6 (94.7\\% of baseline). This recovery required approximately 170K additional training steps beyond onset. The trajectory shows a single onset--recovery cycle with no recurrence, suggesting that the CIVO feedback loop can break spontaneously given sufficient training---though at substantial computational cost that the frozen $\\dt$-embedding diagnostic eliminates entirely.\n\n\\subsection{Why MPC Is Immune}\n\\label{sec:mpc_immune}\n\n\\citet{nhu2025tawm} show that $\\dt$-conditioning benefits TD-MPC2, raising the question of why it fails in DreamerV3.  The critical difference is that MPC re-plans from real states at every step, so imagination errors do not accumulate into the training signal because there is no critic bootstrapping from imagined trajectories.  In DreamerV3, the actor-critic trains entirely within imagination, and any systematic reward-prediction bias at $\\dt > 1$ is amplified through the closed actor-critic loop.\n\n\\subsection{The \\texorpdfstring{$\\dt$}{dt}-Embedding Dilemma}\n\\label{sec:embedding_dilemma}\n\nThe factorial results reveal a fundamental tension: removing the $\\dt$-embedding (008f) eliminates CIVO but at a $13\\times$ cost to reward prediction quality ($0.7469$ vs.\\ $0.0568$ MAE), as the world model cannot distinguish temporal scales.  Restricting imagination to $\\dt{=}1$ while retaining the trained embedding (008e\\_v3) avoids collapse in 2 of 4 seeds (50\\%), while the remaining two collapse via distinct mechanisms: Pathway~A (CIVO-driven, entropy decrease; s3, NVE $4.02\\times$) and Pathway~B (entropy-driven, entropy increase; s2, NVE $3.78\\times$; \\S\\ref{sec:f6}).  Neither approach alone provides a complete solution.\n\n\\subsection{Temporal Embedding Representation Analysis}\n\\label{sec:cosine_evolution}\n\nTo understand how the trained $\\dt$-embedding creates vulnerability, we analyze the cosine similarity between $e(\\dt{=}1)$ and $e(\\dt{=}2)$ across training (exp\\_065). Trained embeddings learn \\emph{near-opposite} representations: $\\cos(e_1, e_2) = {-}0.87$ to ${-}0.94$ at 25K steps across three configurations (Walker 008d\\_s3, Cheetah 010b\\_s0, Walker 059\\_s5), persisting at ${-}0.70$ to ${-}0.86$ at 75K steps. In contrast, frozen embeddings maintain near-zero similarity ($-0.15$ to $+0.07$, constant throughout training). The near-antipodal learned representations explain the large reward prediction gap (\\S\\ref{sec:f2}): $\\dt{=}2$ conditioning pushes the RSSM into a qualitatively different region of latent space, producing systematically biased predictions rather than minor perturbations.\n\n\\subsection{\\texorpdfstring{$\\dt$}{dt}-Embedding Differentiation Precedes Value Divergence}\n\\label{sec:cosine_temporal}\n\nThe preceding analysis established that trained $\\dt$-embeddings learn near-antipodal representations. Here we resolve the \\emph{temporal dynamics} of this differentiation across 11 experiments (${\\sim}$47 checkpoints), testing whether embedding differentiation is a consequence or precursor of CIVO.\n\n\\paragraph{Trained embeddings: monotonic relaxation.}\nAcross all trained configurations, $\\cos(e_1, e_2)$ starts near $-0.95$ within 10K steps and relaxes monotonically toward ${\\sim}{-}0.65$ (Table~\\ref{tab:cosine_evolution_ext}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity evolution between $e(\\dt{=}1)$ and $e(\\dt{=}2)$ for trained $\\dt$-embeddings. Relaxation is monotonic but never reaches zero; frozen embeddings remain constant near zero throughout training.}\n\\label{tab:cosine_evolution_ext}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Env} & \\textbf{Experiment} & \\textbf{10K} & \\textbf{25K} & \\textbf{65K} & \\textbf{75K} & \\textbf{302K} \\\\\n\\midrule\n\\multirow{2}{*}{Walker} & exp\\_066b (trained) & $-0.947$ & $-0.928$ & $-0.847$ & --- & --- \\\\\n & exp\\_045 (extension) & --- & --- & --- & --- & $-0.668$ \\\\\n\\midrule\nCheetah & exp\\_010b$\\to$048 & --- & $-0.904$ & --- & $-0.841$ & $-0.639$ \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Frozen controls:}} \\\\\nWalker & exp\\_057 (frozen) & \\multicolumn{5}{c}{$-0.150$ (constant, 25K--225K)} \\\\\nCheetah & exp\\_058 (frozen) & \\multicolumn{5}{c}{$+0.069$ (constant, 25K--225K)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nCross-seed consistency at 25K steps is high: mean $\\cos = -0.910 \\pm 0.028$ ($n{=}5$ Walker seeds), confirming the relaxation pattern is robust across random seeds. Variance increases with training ($-0.789 \\pm 0.076$ at 75K), reflecting seed-dependent relaxation rates.\n\n\\paragraph{Temporal precedence over CIVO.}\nExp\\_066b provides simultaneous cosine similarity and CIVO diagnostic data at 5K resolution (Table~\\ref{tab:cosine_vs_civo}).\n\n\\begin{table}[h]",
      "numLines": 100,
      "startLine": 740,
      "totalLines": 1174
    }
  }
}
```

</details>

---


### Tool call

_source line 19_

<details open><summary>🔧 Tool call — Read · `toolu_01JyTcbbMmGKLKXt6mqmdFd5`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
  "offset": 920,
  "limit": 120
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "22a84eef-949e-45ac-a00d-d07fedf41605",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GjKQf26HuL5aPEpogL2SM6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12503,
      "cache_read_input_tokens": 24093,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12503
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

_source line 20 · 2026-05-25T16:23:32.395Z_

<details><summary>↩ Tool result · `toolu_01JyTcbbMmGKLKXt6mqmdFd5`</summary>

```text
920	\setlength{\tabcolsep}{4pt}
921	\begin{tabular}{llccccc}
922	\toprule
923	\textbf{Group} & \textbf{Experiment} & \textbf{5K} & \textbf{25K} & \textbf{45K} & \textbf{55K} & \textbf{Return} \\
924	\midrule
925	\multirow{2}{*}{Collapsed}
926	 & exp\_008d (trained dt\_emb) & 8.16 & $-1.86$ & $-4.58$ & $-4.88$ & ${\sim}165$ \\
927	 & fixed\_dt2 ($\dt{=}2$) & 8.16 & $-3.02$ & $-5.06$ & $-5.17$ & ${\sim}29$ \\
928	\midrule
929	\multirow{3}{*}{Healthy}
930	 & exp\_008f (no dt\_emb) & 8.11 & $-1.85$ & $-4.31$ & $-4.77$ & ${\sim}460$ \\
931	 & exp\_008a (unexposed) & 8.16 & $-4.88$ & $-5.20$ & $-5.21$ & ${\sim}300$ \\
932	 & baseline\_s1 ($\dt{=}1$) & 8.10 & $-4.74$ & $-5.12$ & $-5.18$ & ${\sim}950$ \\
933	\bottomrule
934	\end{tabular}
935	\end{table}
936	
937	At the last comparable step (55K): collapsed mean entropy $= -5.02$ (average of $-4.88$, $-5.17$); healthy mean entropy $= -5.05$ (average of $-4.77$, $-5.21$, $-5.18$); difference $= 0.03$ nats---statistically negligible. The hypothesis that collapsed runs exhibit anomalous entropy rise (actor confusion from delusional critic gradients) is not supported during the CIVO onset window.
938	
939	The fixed\_dt2 experiment demonstrates this most clearly: returns peak at ${\sim}580$ (40K) then crash to 29 (72K), yet entropy remains stable at $-5.1$ throughout. The actor maintains a committed, low-entropy policy during the entire collapse---it does not become confused but rather remains confident while acting on incorrect value estimates. This is consistent with CIVO operating through critic value distortion rather than actor policy degradation. The late-stage entropy explosion documented in \S\ref{sec:civo_mechanism} ($+2.1$ nats/10K in EG~v4, onset ${\sim}$35K steps after return collapse) occurs well beyond this window, confirming entropy rise as a lagging consequence rather than a concurrent or predictive signal.
940	
941	\paragraph{Entropy descent speed.}
942	Entropy descent rate correlates with temporal configuration complexity, not collapse fate. Simpler configurations (baseline $\dt{=}1$, unexposed exp\_008a) reach $-4.7$ by 25K, while configurations exposed to temporal variation (both collapsed and healthy) remain near $-2.0$ at 25K, reflecting the difficulty of policy commitment when training data spans multiple temporal scales.
943	
944	\paragraph{Long-horizon entropy recovery.}
945	The baseline ($\dt{=}1$) run extended to 505K steps shows entropy recovering from $-5.2$ to ${\sim}{-}1.5$ between 115K and 295K steps, coinciding with continued performance improvement ($700 \to 950$ return). This adaptive entropy increase rules out entropy rise as an inherently negative signal; the actor maintains ${\sim}950$ return with entropy 3--4 nats above its minimum, indicating a healthy exploration--exploitation balance during extended training.
946	
947	\subsection{Multiple Vulnerability Pathways}
948	\label{sec:pathways}
949	
950	The two collapse patterns identified in \S\ref{sec:f6}---CIVO (Pathway~A, value-driven, entropy decreasing) and a tentative second mode (Pathway~B, eval-driven, entropy increasing)---have distinct diagnostic signatures. Pathway~B is observed in only two seeds (008e\_v3\_s2 and 038\_s2); we present it as preliminary evidence that the trained $\dt$-embedding's learned features may affect both reward prediction across temporal scales (Pathway~A) and the representation space in which the actor operates (Pathway~B), though additional data is needed to confirm this as a distinct mechanism.  This explains why $\nve$ is sensitive but not perfectly specific: Pathway~B's late evaluation decline inflates $\nve$ through the same arithmetic as CIVO, yielding the sole false positive ($3.78\times$ for 008e\_v3 s2).  Distinguishing the two requires examining the temporal profile and entropy direction of collapse (Figure~\ref{fig:multiple_pathways}).
951	
952	
953	\subsection{Implications for Temporal Abstraction in World Models}
954	\label{sec:implications}
955	
956	CIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \citep{gumbsch2024thick}, Hieros \citep{mattes2024hieros}, LS-Imagine \citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.  The CIVO mechanism requires three structural properties: (1) a temporal embedding that co-adapts with dynamics via gradient flow, (2) multi-step imagined rollouts used for critic training, and (3) a reward head that inherits latent biases from the shared representation.  Transformer-based world models that share these properties may exhibit analogous vulnerability; architectures that decouple temporal conditioning from the reward prediction pathway would not.
957	
958	\subsection{Cross-Environment TCN Evaluation}
959	\label{sec:tcn_cross_env}
960	
961	Table~\ref{tab:tcn_full} reports the full TCN evaluation across environments and noise magnitudes.
962	
963	\begin{table}[h]
964	\centering
965	\caption{TCN results across environments and noise magnitudes. Prevention = peak NVE $< 1.5\times$ (35K+).}
966	\label{tab:tcn_full}
967	\footnotesize
968	\setlength{\tabcolsep}{4pt}
969	\begin{tabular}{llcccc}
970	\toprule
971	\textbf{Env} & $\sigma$ & \textbf{Seed} & \textbf{NVE$_{\max}$} & \textbf{Prevented?} & \textbf{Eval (\%)} \\
972	\midrule
973	Walker & 0.1 & s0 & 1.02 & \checkmark$^*$ & 55\% \\
974	Walker & 0.2 & s0 & 0.91 & \checkmark & 91\% \\
975	Walker & 0.2 & s1 & 0.64 & \checkmark & 45\% \\
976	Walker & 0.2 & s2 & 2.11$^\dagger$ & $\times$ & ${\sim}5\%$ \\
977	\rowcolor{gray!15}
978	Walker & 0.2 & s3 & 3.04$^\P$ & $\times$ & 11\% \\
979	Walker & 0.5 & s0 & 3.97 & $\times$ & 27\% \\
980	Walker & 0.5 & s1 & 1.64 & $\times$ & 41\% \\
981	\midrule
982	Cheetah & 0.2 & s0 & 1.90 & $\times$ & crashed \\
983	Cheetah & 0.5 & s0 & 10.67 & $\times$ & 26\% \\
984	Cheetah & 1.0 & s0 & $\leq$0.30 & \checkmark$^\S$ & 15\% \\
985	\midrule
986	PickCube & 0.2 & s0 & 3.71 & $\times$ & failing \\
987	\bottomrule
988	\end{tabular}
989	\vspace{1pt}
990	{\raggedright\footnotesize $^*$Borderline: NVE${=}1.02\times$ at 95K, below $1.5\times$ threshold but above $1.0\times$.\\
991	$^\dagger$NVE $= 2.11\times$ at 95K, still rising; eval ${\sim}5\%$ of baseline.\\
992	$^\P$Late-onset CIVO: NVE declined to $0.67\times$ at 95K before phase-transition-like spike to $3.04\times$ at 105K; eval 349.6 at 95K $\to$ 71.8 at 105K $\to$ 104.5 at 215K.\\
993	$^\S$CIVO prevented (NVE${\leq}0.30$); peak eval 116\% baseline at 35K, declining to 15\% by 215K via progressive policy erosion. See ``impossible dose'' discussion.\par}
994	\end{table}
995	
996	\paragraph{Cheetah Run $\sigma{=}0.5$: transient spike with permanent eval damage.}
997	Cheetah $\sigma{=}0.5$ exhibits a novel failure mode: a transient CIVO spike (NVE $= 10.67\times$ at 55K) followed by NVE recovery ($< 0.3\times$ by 95K), but permanent evaluation damage (26\% of baseline). The value signal self-corrects while the policy does not recover, suggesting that CIVO-induced representational damage during the spike persists within the observation window even when the critic subsequently recalibrates. This trajectory parallels the obs-decoder SGS seed~3 pattern (\S\ref{sec:seed_divergence}), where partial policy recovery coexists with persistent critic damage.
998	
999	\paragraph{Cheetah Run $\sigma{=}0.2$: insufficient dose.}
1000	At $\sigma{=}0.2$, Cheetah reaches NVE $= 1.9\times$ at 55K---exceeding the $1.5\times$ threshold---consistent with Cheetah's higher baseline CIVO severity ($8$--$108\times$ vs.\ Walker's $2$--$6\times$). The noise magnitude that suffices for Walker is inadequate for Cheetah, but increasing $\sigma$ to 0.5 trades CIVO prevention for a different failure mode rather than achieving mitigation.
1001	
1002	\paragraph{PickCube-v1 $\sigma{=}0.2$: manipulation failure.}
1003	PickCube reaches NVE $= 3.71\times$ at 52.5K with $\sigma{=}0.2$, indicating that TCN provides no protection in manipulation tasks. The combination of contact-gated dynamics and temporal conditioning may amplify the fidelity gap beyond what representation-level noise can attenuate.
1004	
1005	\paragraph{Dose-response analysis.}
1006	We observe $\sigma{=}0.2$ as a local optimum on Walker Walk, achieving complete CIVO suppression in 2 of 4 seeds. Seeds~2 and~3 both fail but via distinct CIVO onset dynamics: seed~2 shows gradual escalation (NVE $= 2.11\times$ at 95K, still rising, eval ${\sim}5\%$), while seed~3 exhibits a phase-transition-like onset---NVE declined to $0.67\times$ at 95K before spiking to $3.04\times$ at 105K (eval 349.6 $\to$ 71.8 in 10K steps). When TCN fails to prevent CIVO onset, the resulting trajectory qualitatively resembles untreated CIVO in its terminal outcome---runaway NVE and eval collapse. The two failure modes (gradual escalation vs.\ sudden onset after apparent suppression) reinforce that TCN operates as a binary gate on CIVO onset rather than providing graded attenuation. Below the optimum, we observe $\sigma{=}0.1$ as insufficient (NVE $= 1.02\times$---borderline, eval 55\%); above it, $\sigma{=}0.5$ overdoses (oscillatory CIVO, eval $\leq 41\%$). Cross-seed variance at $\sigma{=}0.2$ (eval 5--91\%) exceeds the cross-dose difference by a wide margin, reinforcing that seed effects dominate dose effects. TCN is the only tested intervention achieving complete CIVO suppression in any configuration, but its high seed sensitivity and failure to transfer across environments position it as a \emph{diagnostic probe}---identifying the representation level as the relevant intervention target---rather than a deployable mitigation.
1007	
1008	\paragraph{Cheetah Run ``impossible dose'' dilemma.}
1009	Exp\_030c (224K steps) reveals a qualitatively different dose-response on Cheetah. At $\sigma{=}1.0$, CIVO is eliminated (NVE${\leq}0.30$ throughout) and initial learning is \emph{unimpaired}: peak eval reaches 372 at 35K (116\% of baseline), demonstrating that $\sigma{=}1.0$ noise does not prevent policy acquisition. However, cumulative actor gradient interference produces progressive policy erosion---eval declines from 372 to 47 by 215K (15\% of baseline)---while the critic remains well-calibrated (value\_mean${=}12.4$, NVE${=}0.26$ at 215K). This establishes that \emph{policy degradation $\neq$ value corruption}: accurate value signals are insufficient when the actor cannot optimize effectively in noise-perturbed imagination.
1010	
1011	This ``correct values, failed policy'' pattern provides indirect evidence that CIVO is mechanistically distinct from standard overestimation. Double Q-learning and ensemble methods address critic estimation error, but at $\sigma{=}1.0$ the critic is accurate and the policy still collapses---a failure mode orthogonal to what these countermeasures target. The impossible dose dilemma scales with environment complexity: Cheetah's baseline CIVO severity ($8$--$108\times$ NVE) requires $\sigma \geq 1.0$ to suppress, but this exceeds the actor's gradient signal-to-noise tolerance. On Walker, a narrow effective window exists around $\sigma{=}0.2$; on Cheetah, the effective dose ($\sigma \geq 1.0$) exceeds the tolerable dose, and environments with higher CIVO severity will systematically lack a viable dose window.
1012	
1013	\section{DreamerV3 Hyperparameters}
1014	\label{sec:hyperparameters}
1015	
1016	Table~\ref{tab:hyperparams} lists the DreamerV3 hyperparameters used across all experiments. Unless otherwise noted, we use the default DreamerV3 configuration for continuous-control tasks (\texttt{dmc\_proprio}).
1017	
1018	\begin{table}[ht]
1019	\centering
1020	\caption{DreamerV3 hyperparameters for all experiments. Modifications from defaults are marked with $\diamond$.}
1021	\label{tab:hyperparams}
1022	\small
1023	\begin{tabular}{ll}
1024	\toprule
1025	\textbf{Parameter} & \textbf{Value} \\
1026	\midrule
1027	\multicolumn{2}{l}{\textit{World Model}} \\
1028	RSSM discrete states & 32 classes $\times$ 32 categories \\
1029	RSSM stochastic dim & 32 \\
1030	RSSM deterministic dim & 512 \\
1031	MLP hidden size & 512 \\
1032	MLP layers & 2 \\
1033	Activation & SiLU \\
1034	Normalization & LayerNorm \\
1035	\midrule
1036	\multicolumn{2}{l}{\textit{Training}} \\
1037	Batch size & 16 sequences $\times$ 64 steps \\
1038	Learning rate & $3 \times 10^{-4}$ (Adam, $\epsilon{=}10^{-8}$) \\
1039	Sequence length & 64 \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "4b037066-61ec-4b20-900f-50adcd9c9795",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
      "content": "\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Group} & \\textbf{Experiment} & \\textbf{5K} & \\textbf{25K} & \\textbf{45K} & \\textbf{55K} & \\textbf{Return} \\\\\n\\midrule\n\\multirow{2}{*}{Collapsed}\n & exp\\_008d (trained dt\\_emb) & 8.16 & $-1.86$ & $-4.58$ & $-4.88$ & ${\\sim}165$ \\\\\n & fixed\\_dt2 ($\\dt{=}2$) & 8.16 & $-3.02$ & $-5.06$ & $-5.17$ & ${\\sim}29$ \\\\\n\\midrule\n\\multirow{3}{*}{Healthy}\n & exp\\_008f (no dt\\_emb) & 8.11 & $-1.85$ & $-4.31$ & $-4.77$ & ${\\sim}460$ \\\\\n & exp\\_008a (unexposed) & 8.16 & $-4.88$ & $-5.20$ & $-5.21$ & ${\\sim}300$ \\\\\n & baseline\\_s1 ($\\dt{=}1$) & 8.10 & $-4.74$ & $-5.12$ & $-5.18$ & ${\\sim}950$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt the last comparable step (55K): collapsed mean entropy $= -5.02$ (average of $-4.88$, $-5.17$); healthy mean entropy $= -5.05$ (average of $-4.77$, $-5.21$, $-5.18$); difference $= 0.03$ nats---statistically negligible. The hypothesis that collapsed runs exhibit anomalous entropy rise (actor confusion from delusional critic gradients) is not supported during the CIVO onset window.\n\nThe fixed\\_dt2 experiment demonstrates this most clearly: returns peak at ${\\sim}580$ (40K) then crash to 29 (72K), yet entropy remains stable at $-5.1$ throughout. The actor maintains a committed, low-entropy policy during the entire collapse---it does not become confused but rather remains confident while acting on incorrect value estimates. This is consistent with CIVO operating through critic value distortion rather than actor policy degradation. The late-stage entropy explosion documented in \\S\\ref{sec:civo_mechanism} ($+2.1$ nats/10K in EG~v4, onset ${\\sim}$35K steps after return collapse) occurs well beyond this window, confirming entropy rise as a lagging consequence rather than a concurrent or predictive signal.\n\n\\paragraph{Entropy descent speed.}\nEntropy descent rate correlates with temporal configuration complexity, not collapse fate. Simpler configurations (baseline $\\dt{=}1$, unexposed exp\\_008a) reach $-4.7$ by 25K, while configurations exposed to temporal variation (both collapsed and healthy) remain near $-2.0$ at 25K, reflecting the difficulty of policy commitment when training data spans multiple temporal scales.\n\n\\paragraph{Long-horizon entropy recovery.}\nThe baseline ($\\dt{=}1$) run extended to 505K steps shows entropy recovering from $-5.2$ to ${\\sim}{-}1.5$ between 115K and 295K steps, coinciding with continued performance improvement ($700 \\to 950$ return). This adaptive entropy increase rules out entropy rise as an inherently negative signal; the actor maintains ${\\sim}950$ return with entropy 3--4 nats above its minimum, indicating a healthy exploration--exploitation balance during extended training.\n\n\\subsection{Multiple Vulnerability Pathways}\n\\label{sec:pathways}\n\nThe two collapse patterns identified in \\S\\ref{sec:f6}---CIVO (Pathway~A, value-driven, entropy decreasing) and a tentative second mode (Pathway~B, eval-driven, entropy increasing)---have distinct diagnostic signatures. Pathway~B is observed in only two seeds (008e\\_v3\\_s2 and 038\\_s2); we present it as preliminary evidence that the trained $\\dt$-embedding's learned features may affect both reward prediction across temporal scales (Pathway~A) and the representation space in which the actor operates (Pathway~B), though additional data is needed to confirm this as a distinct mechanism.  This explains why $\\nve$ is sensitive but not perfectly specific: Pathway~B's late evaluation decline inflates $\\nve$ through the same arithmetic as CIVO, yielding the sole false positive ($3.78\\times$ for 008e\\_v3 s2).  Distinguishing the two requires examining the temporal profile and entropy direction of collapse (Figure~\\ref{fig:multiple_pathways}).\n\n\n\\subsection{Implications for Temporal Abstraction in World Models}\n\\label{sec:implications}\n\nCIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \\citep{gumbsch2024thick}, Hieros \\citep{mattes2024hieros}, LS-Imagine \\citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \\citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.  The CIVO mechanism requires three structural properties: (1) a temporal embedding that co-adapts with dynamics via gradient flow, (2) multi-step imagined rollouts used for critic training, and (3) a reward head that inherits latent biases from the shared representation.  Transformer-based world models that share these properties may exhibit analogous vulnerability; architectures that decouple temporal conditioning from the reward prediction pathway would not.\n\n\\subsection{Cross-Environment TCN Evaluation}\n\\label{sec:tcn_cross_env}\n\nTable~\\ref{tab:tcn_full} reports the full TCN evaluation across environments and noise magnitudes.\n\n\\begin{table}[h]\n\\centering\n\\caption{TCN results across environments and noise magnitudes. Prevention = peak NVE $< 1.5\\times$ (35K+).}\n\\label{tab:tcn_full}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Env} & $\\sigma$ & \\textbf{Seed} & \\textbf{NVE$_{\\max}$} & \\textbf{Prevented?} & \\textbf{Eval (\\%)} \\\\\n\\midrule\nWalker & 0.1 & s0 & 1.02 & \\checkmark$^*$ & 55\\% \\\\\nWalker & 0.2 & s0 & 0.91 & \\checkmark & 91\\% \\\\\nWalker & 0.2 & s1 & 0.64 & \\checkmark & 45\\% \\\\\nWalker & 0.2 & s2 & 2.11$^\\dagger$ & $\\times$ & ${\\sim}5\\%$ \\\\\n\\rowcolor{gray!15}\nWalker & 0.2 & s3 & 3.04$^\\P$ & $\\times$ & 11\\% \\\\\nWalker & 0.5 & s0 & 3.97 & $\\times$ & 27\\% \\\\\nWalker & 0.5 & s1 & 1.64 & $\\times$ & 41\\% \\\\\n\\midrule\nCheetah & 0.2 & s0 & 1.90 & $\\times$ & crashed \\\\\nCheetah & 0.5 & s0 & 10.67 & $\\times$ & 26\\% \\\\\nCheetah & 1.0 & s0 & $\\leq$0.30 & \\checkmark$^\\S$ & 15\\% \\\\\n\\midrule\nPickCube & 0.2 & s0 & 3.71 & $\\times$ & failing \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$Borderline: NVE${=}1.02\\times$ at 95K, below $1.5\\times$ threshold but above $1.0\\times$.\\\\\n$^\\dagger$NVE $= 2.11\\times$ at 95K, still rising; eval ${\\sim}5\\%$ of baseline.\\\\\n$^\\P$Late-onset CIVO: NVE declined to $0.67\\times$ at 95K before phase-transition-like spike to $3.04\\times$ at 105K; eval 349.6 at 95K $\\to$ 71.8 at 105K $\\to$ 104.5 at 215K.\\\\\n$^\\S$CIVO prevented (NVE${\\leq}0.30$); peak eval 116\\% baseline at 35K, declining to 15\\% by 215K via progressive policy erosion. See ``impossible dose'' discussion.\\par}\n\\end{table}\n\n\\paragraph{Cheetah Run $\\sigma{=}0.5$: transient spike with permanent eval damage.}\nCheetah $\\sigma{=}0.5$ exhibits a novel failure mode: a transient CIVO spike (NVE $= 10.67\\times$ at 55K) followed by NVE recovery ($< 0.3\\times$ by 95K), but permanent evaluation damage (26\\% of baseline). The value signal self-corrects while the policy does not recover, suggesting that CIVO-induced representational damage during the spike persists within the observation window even when the critic subsequently recalibrates. This trajectory parallels the obs-decoder SGS seed~3 pattern (\\S\\ref{sec:seed_divergence}), where partial policy recovery coexists with persistent critic damage.\n\n\\paragraph{Cheetah Run $\\sigma{=}0.2$: insufficient dose.}\nAt $\\sigma{=}0.2$, Cheetah reaches NVE $= 1.9\\times$ at 55K---exceeding the $1.5\\times$ threshold---consistent with Cheetah's higher baseline CIVO severity ($8$--$108\\times$ vs.\\ Walker's $2$--$6\\times$). The noise magnitude that suffices for Walker is inadequate for Cheetah, but increasing $\\sigma$ to 0.5 trades CIVO prevention for a different failure mode rather than achieving mitigation.\n\n\\paragraph{PickCube-v1 $\\sigma{=}0.2$: manipulation failure.}\nPickCube reaches NVE $= 3.71\\times$ at 52.5K with $\\sigma{=}0.2$, indicating that TCN provides no protection in manipulation tasks. The combination of contact-gated dynamics and temporal conditioning may amplify the fidelity gap beyond what representation-level noise can attenuate.\n\n\\paragraph{Dose-response analysis.}\nWe observe $\\sigma{=}0.2$ as a local optimum on Walker Walk, achieving complete CIVO suppression in 2 of 4 seeds. Seeds~2 and~3 both fail but via distinct CIVO onset dynamics: seed~2 shows gradual escalation (NVE $= 2.11\\times$ at 95K, still rising, eval ${\\sim}5\\%$), while seed~3 exhibits a phase-transition-like onset---NVE declined to $0.67\\times$ at 95K before spiking to $3.04\\times$ at 105K (eval 349.6 $\\to$ 71.8 in 10K steps). When TCN fails to prevent CIVO onset, the resulting trajectory qualitatively resembles untreated CIVO in its terminal outcome---runaway NVE and eval collapse. The two failure modes (gradual escalation vs.\\ sudden onset after apparent suppression) reinforce that TCN operates as a binary gate on CIVO onset rather than providing graded attenuation. Below the optimum, we observe $\\sigma{=}0.1$ as insufficient (NVE $= 1.02\\times$---borderline, eval 55\\%); above it, $\\sigma{=}0.5$ overdoses (oscillatory CIVO, eval $\\leq 41\\%$). Cross-seed variance at $\\sigma{=}0.2$ (eval 5--91\\%) exceeds the cross-dose difference by a wide margin, reinforcing that seed effects dominate dose effects. TCN is the only tested intervention achieving complete CIVO suppression in any configuration, but its high seed sensitivity and failure to transfer across environments position it as a \\emph{diagnostic probe}---identifying the representation level as the relevant intervention target---rather than a deployable mitigation.\n\n\\paragraph{Cheetah Run ``impossible dose'' dilemma.}\nExp\\_030c (224K steps) reveals a qualitatively different dose-response on Cheetah. At $\\sigma{=}1.0$, CIVO is eliminated (NVE${\\leq}0.30$ throughout) and initial learning is \\emph{unimpaired}: peak eval reaches 372 at 35K (116\\% of baseline), demonstrating that $\\sigma{=}1.0$ noise does not prevent policy acquisition. However, cumulative actor gradient interference produces progressive policy erosion---eval declines from 372 to 47 by 215K (15\\% of baseline)---while the critic remains well-calibrated (value\\_mean${=}12.4$, NVE${=}0.26$ at 215K). This establishes that \\emph{policy degradation $\\neq$ value corruption}: accurate value signals are insufficient when the actor cannot optimize effectively in noise-perturbed imagination.\n\nThis ``correct values, failed policy'' pattern provides indirect evidence that CIVO is mechanistically distinct from standard overestimation. Double Q-learning and ensemble methods address critic estimation error, but at $\\sigma{=}1.0$ the critic is accurate and the policy still collapses---a failure mode orthogonal to what these countermeasures target. The impossible dose dilemma scales with environment complexity: Cheetah's baseline CIVO severity ($8$--$108\\times$ NVE) requires $\\sigma \\geq 1.0$ to suppress, but this exceeds the actor's gradient signal-to-noise tolerance. On Walker, a narrow effective window exists around $\\sigma{=}0.2$; on Cheetah, the effective dose ($\\sigma \\geq 1.0$) exceeds the tolerable dose, and environments with higher CIVO severity will systematically lack a viable dose window.\n\n\\section{DreamerV3 Hyperparameters}\n\\label{sec:hyperparameters}\n\nTable~\\ref{tab:hyperparams} lists the DreamerV3 hyperparameters used across all experiments. Unless otherwise noted, we use the default DreamerV3 configuration for continuous-control tasks (\\texttt{dmc\\_proprio}).\n\n\\begin{table}[ht]\n\\centering\n\\caption{DreamerV3 hyperparameters for all experiments. Modifications from defaults are marked with $\\diamond$.}\n\\label{tab:hyperparams}\n\\small\n\\begin{tabular}{ll}\n\\toprule\n\\textbf{Parameter} & \\textbf{Value} \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{World Model}} \\\\\nRSSM discrete states & 32 classes $\\times$ 32 categories \\\\\nRSSM stochastic dim & 32 \\\\\nRSSM deterministic dim & 512 \\\\\nMLP hidden size & 512 \\\\\nMLP layers & 2 \\\\\nActivation & SiLU \\\\\nNormalization & LayerNorm \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Training}} \\\\\nBatch size & 16 sequences $\\times$ 64 steps \\\\\nLearning rate & $3 \\times 10^{-4}$ (Adam, $\\epsilon{=}10^{-8}$) \\\\\nSequence length & 64 \\\\",
      "numLines": 120,
      "startLine": 920,
      "totalLines": 1174
    }
  }
}
```

</details>

---


### Assistant

_source line 21_

<details><summary>Logged reasoning block</summary>

```text
Now I have a comprehensive understanding of the file. Let me also read the results.tex F6 section to understand what the current state is there, and also check the current 008e_v3 data. Let me also check what else references the old data.

Let me identify all the locations that need to be fixed:

1. **Lines 54-58**: Complete results table - 008e_v3 s2 and s3 have old data
   - s2: "137.0 @105K, 3.78×, Non-CIVO collapse" with ↑ mark → Current: NVE 0.5, no CIVO
   - s3: "92.7 @105K, 4.02×, CIVO collapse" with gray shading → Current: NVE 0.5, no CIVO

So the actual current data shows s0 with eval 869.9 and NVE 0.6, s1 from exp_080 with eval 876.7 and NVE 0.6, and s2 from exp_081 with eval 597.1 and NVE 0.5, all without CIVO, giving a 3-seed mean of 781.

But looking at the existing table more carefully, I see the 008e_v3 runs actually have s1 through s5 with much more varied results—s1 shows eval 869.9 with NVE 0.94 marked as healthy, s2 has eval 137.0 with NVE 3.78 showing non-CIVO collapse, s3 shows eval 92.7 with NVE 4.02 in CIVO collapse, and s4 shows eval 899.3 with NVE 0.99 also healthy.

The current code only has three seeds (s0, s1, s2) all clustered in the 0.5-0.6 NVE range, so I need to replace those five old seed rows with the three new ones. I also need to update the description at line 143 that mentions four seeds and specifically references the CIVO collapse cases, since the new data only has three seeds and they're all non-CIVO. The NVE raw table around lines 147-167 also references the old 008e_v3_s3 with its 4.02 NVE value, which needs updating.

The bigger issue is that the multi-threshold classification analysis spanning lines 169-247 is built entirely on the old dataset with n=11 samples including those CIVO/IRD seeds. Removing them changes the sample count and all the downstream AUROC calculations. The optimal threshold statement at line 171 specifically cites the old NVE boundaries of 3.78 and 4.02, which won't apply anymore.

Looking further down, there are scattered references to 008e_v3_s2 as a false positive case across lines 197, 237-247, and the threshold recommendations—but with the updated data where that sample has NVE 0.5, it's no longer a false positive. The ROC caption and subsequent references to the mitigation transient VE spike and IRD eval-driven collapse around lines 257-273 all anchor to the old 008e_v3 subsample values that need updating.

Then there's the Walker LOEO section starting at line 323, which references exp_008e_v3 seed~2 as an IRD collapse case, followed by LOCO references to exp_008e_v3_subsample at line 339. The failure mode taxonomy section around line 762-797 has IRD collapse descriptions and Pathway A/B framing that depend on the old data, and the "Multiple Vulnerability Pathways" subsection at lines 947-950 repeats those pathway descriptions with outdated assumptions.

The core problem is that with all 008e_v3 seeds now showing NVE 0.5-0.6, the entire narrative around IRD collapse as a distinct failure mode and the Pathway A/B distinction needs to be reconsidered. Looking at the eval score of 869.9 in the new data for s0, that matches the existing row for 008e_v3 s1, so these might be the same seed with updated NVE values after the bug fix. The D152 conclusion indicates the old 008e_v3 code is invalid due to a bug fix rather than an algorithmic change, which would explain why I'm seeing the same eval scores but different NVE metrics.

Since the new data only has 3 seeds (s0, s1, and s2) compared to the old 5 seeds, I need to replace those 5 rows with the 3 new ones, remove all IRD and Pathway B content, and then recalculate the NVE tables and sensitivity analysis numbers that depend on these experiment classifications. The table shrinks from 11 to 10 entries as the four 008e_v3 variants get replaced with three new ones, all showing non-CIVO results in the 0.5-0.6 range. This means for Task B1, the positive count drops from 3 to 2 since 008e_v3_s3 (which was CIVO-positive) is being removed, leaving just 006 and 008d as positive cases. So the updated table shows the experiments ranked by their NVE scores, with the four variants of 008e_v3 replaced by three new ones that all score much lower. The top performers are still 006 and 059 with sustained CIVO behavior, followed by 008d, while the rest cluster in the sub-2 range with non-CIVO or transient patterns.

Now I'm recalculating the task breakdowns: for sustained CIVO only, that's 006 and 008d as positives against 8 negatives, but for any CIVO type, I can include 059 and 009b as well, giving 4 positives against 6 negatives. Wait, let me verify the experiment list against the original table—I need to make sure I'm not including 008d_s3 since that's a different variant with late-onset collapse that doesn't appear in this particular set.

Now I'm recomputing the sensitivity tables by sorting all 10 experiments by their NVE values in descending order and classifying each one against the task criteria.

At different thresholds, I'm calculating the true positives, false positives, false negatives, and true negatives to find which threshold gives the best accuracy—looks like thresholds between 1.2 and 2.0 all achieve 90% accuracy by correctly identifying the two positives while minimizing false positives. Now I'm calculating the AUROC for B1 by counting how many negatives fall below each positive's NVE score—006 has 8 negatives below it and 008d has 7, giving me a total of 15, which yields an AUROC of 0.9375. Moving on to B2 where I have four positives to evaluate: 006, 059, 008d, and 009b, sorted by their NVE scores.

The separation is flawless—every positive scores higher than every negative, which means at a threshold of 1.0 or above, I'd correctly flag all four positives while only catching one false positive (001 at exactly 1.00).

Bumping the threshold to 1.2 eliminates that false positive entirely while keeping all true positives, giving perfect accuracy. Even at 1.5 the performance holds, but pushing to 1.7 starts missing one positive case, so the sweet spot is somewhere between 1.2 and 1.5.

For B2, the model achieves perfect separation with an AUROC of 1.0. Now I'm calculating precision, recall, and F1 scores across different thresholds for B1 to see which operating point balances these metrics best. I'm recalculating the confusion matrix more carefully—at the ≥1.7 threshold, only 006, 059, and 008d get flagged since 009b's score of 1.62 falls below that cutoff, giving me TP=2, FP=1, FN=0, TN=7 with 90% accuracy. So with a threshold of ≥1.0, I'm getting 5 flagged cases with 70% accuracy, but the precision is only 40% since 3 are false positives. When I bump the threshold to ≥1.2, I filter out two of those false positives, bringing accuracy up to 80% and precision to 50%, while maintaining perfect recall at 100%.

At ≥1.7, I'm down to 3 flagged cases with just one false positive, which gives me 90% accuracy and 66.7% precision—a much better balance. The threshold of ≥2.0 appears to be cutting off mid-evaluation. Now I'm working through the metrics for B2, testing different thresholds to find the optimal cutoff. At ≥1.0, I get 90% accuracy with 80% precision and perfect recall, catching all four positives but flagging one negative. Moving to higher thresholds like ≥1.2 to see how the performance shifts. Now I'm computing the AUROC for B2, which shows perfect separation since all positive cases have higher NVE scores than the negatives, giving an AUROC of 1.0. For the Clopper-Pearson confidence intervals at 95%, I'm calculating the exact binomial bounds for different accuracy levels—7 out of 10 gives roughly 34.8% to 93.3%, improving to 69.2% to 100% for perfect accuracy.

But I'm realizing this is getting complicated because I also need to recalculate the n=17 table for B2 full and the n=56 comprehensive analysis. The key issue is that 008e_v3 was previously flagged as a false positive, but with the new NVE data showing values in the 0.5-0.6 range, it no longer qualifies as one, so those false positive counts need updating. I need to figure out which specific configs from Walker and Cheetah are included in the n=17 B2 full table to properly recalculate everything.

Rather than trying to manually recalculate all these interconnected sensitivity tables, which is error-prone, I should take a more systematic approach: update the 008e_v3 rows in the main results table and NVE raw table with the new data, carefully revise the sensitivity analysis sections since they're tightly linked, remove the IRD/Pathway B content, and update the failure mode taxonomy. Let me also verify what seed numbering the old table uses by checking the specific entries.

Now I'm comparing the old seed data against the new experimental results—the old s1 and new s0 both show eval 869.9, which suggests they might be the same run with different labeling.

The NVE values shifted significantly (0.94 to 0.6), likely because the bug fix in the `subsample_variable_dt` parameter changed the training distribution the world model saw. Since re-running with the corrected code would produce different results, I should treat these as three independent runs with the current fixed implementation rather than trying to match them to previous checkpoints.

I'll work with the data as it stands now.

Looking at the updated NVE table, the 008e_v3 experiments now consistently show NVE values in the 0.5-0.6 range across all three seeds, which changes the composition from four seeds to three seeds in the factorial experiment count.

For Task B2, the new AUROC of 1.000 is an improvement, and removing the false positive (008e_v3_s2) cleans up the results. Now I need to systematically update the complete results table for the 008e_v3 entries, revise the NVE raw table and its description, recalculate the sensitivity analyses for B1 and B2 with the new n=10 count, adjust the B2 full and n=56 analyses accordingly, and remove IRD from the analysis.

The n=17 table is tricky since I don't have the complete experiment list—I'd need to know exactly which Walker and Cheetah configurations were included to properly recalculate the positive/negative split when 008e_v3_s3 flips from positive to negative. Let me focus on what I can confidently update first. Looking at the full list of Walker experiments, there are far more than 15 configurations, so the n=17 table must be using a specific subset. The original 11 experiments were all Walker, and extending to 17 means adding 6 more—likely the 4 additional Walker configs (008d_s3, 008d_s4, 008f_s4, 009c_s3) plus the 2 Cheetah configurations—but without knowing exactly which 15 Walker configs were selected, I can't precisely recalculate the results.

Rather than trying to manually reverse-engineer which seeds were swapped out, I should focus on the practical pattern: the key changes involve replacing the problematic 008e_v3 seeds (the ones with high NVE values and false positives) with new low-NVE seeds, which would explain the improved performance metrics in the n=17 and n=56 analyses.

For the sensitivity tables, I need to be precise with the numerical computations rather than guessing at values, so I'll calculate the AUROC and confidence intervals exactly based on the seed replacements. Updating the table rows with the corrected values and new entries... I need to check the footnote usage more carefully. The dagger symbol appears on both 008e_v3_s2 and 059, but they're referring to different things. Since 008e_v3_s2 no longer appears in the updated table with the new healthy outcomes, I should remove that dagger reference. The footnote on line 103 is actually for 059 describing the NVE self-correction, so that stays. The section heading mentioning the mitigation experiments can remain as is.

Now I'm revising the table description text to reflect the updated dataset. Instead of discussing the problematic 008e_v3_s2 case with Imagination-Reality Divergence and the s3 seed with elevated NVE, I'm simplifying it to note that all three healthy 008e_v3 seeds with the mitigation configuration remain stable. Updating the table entries with the new NVE values, reordering them by descending magnitude and replacing the old data points with the corrected measurements. Now I'm updating the sensitivity analysis with the new AUROC values—B1 improves to 0.9375 with the ranking issue from exp_059, while B2 achieves perfect separation at 1.000, and I need to revise the explanation to reflect how the imperfect separation in B1 differs from B2's perfect classification. I'm recalculating the sensitivity analysis for Task B1 with the updated sample composition—now with 2 positive cases instead of 3, bringing the total to 10 samples. The AUROC improves slightly to 0.938, and I need to recompute the confusion matrices across different thresholds to identify where the optimal cutoff falls and confirm exp_059 remains the only false positive. Now I'm checking the threshold at ≥4.5, which gives me one true positive and one false positive with a false negative, bringing accuracy down to 80%. For the confidence intervals, I need to compute exact Clopper-Pearson bounds, so I'll use a script to handle that calculation. Then I need to work through the B2 group metrics, starting with the four positive cases and six negative cases.

Looking at the B2 thresholds, I'm finding that ≥1.2 and ≥1.5 both achieve perfect classification with all four positives correctly identified and no false positives. At higher thresholds like ≥1.7 and above, I lose one positive case (009b) but maintain zero false positives. Now I need to calculate the confidence intervals for these results.

For the n=17 B2 full table, I'm trying to reconstruct which experiments were included in the original analysis—the old data showed 9 positives and 8 negatives with an AUROC of 0.972, combining 15 Walker experiments and 2 Cheetah runs. The Walker set included four 008e_v3 seeds (s1 through s4), though I'm uncertain whether s5 was added later or excluded from the original analysis. So Cheetah contributes 2 positives with both configurations collapsing, leaving Walker with 7 positives and 8 negatives across 15 experiments. Let me verify the Walker breakdown: the positives are 006, 008d, 008d_s3, 008d_s4, 059, 068, and 008e_v3_s3, while the negatives include 001, 008f, 008a, 008e_v3_s1, 008e_v3_s2, 008e_v3_s4, and a couple others I'm still pinning down.

Actually, I need to reconsider 009b—it shows an NVE of 1.62 which qualifies as CIVO-positive for B2 since that threshold is 1.5 or higher. Recounting the original 11 samples, I get 3 sustained positives (006, 059, 008d), plus 008e_v3_s3 as another sustained case, and 009b as a transient detection, bringing B2 positives to 5 total. For the expanded n=17 set, Walker's positives now include 006, 059, 008d, 008d_s3, 008d_s4, and 008e.

Now I'm trying to identify the remaining Walker negatives in the n=17 dataset—I've accounted for 001, 008f, 008a, and several 008e variants, but I'm uncertain about the last couple. I'm checking whether 068 should be included, noting it has an NVE of 4.12 with full collapse, which would make it CIVO-positive rather than negative.

Let me recount the full Walker set by going through the complete results: I see 8 positives (006, 008d, 009b, 008d_s3, 008d_s4, 059, 068, and 008e_v3_s3) and 7 negatives so far (001, 008f, 008a, 008e_v3_s1, 008e_v3_s2, 008e_v3_s4, plus 008e_v3_s5 which shows NVE 0.61 and healthy status). That brings me to 15 total Walker experiments, which matches what I'm looking for.

But now I'm noticing a discrepancy with the positive count—if I add the 2 Cheetah positives to these 8, I get 10, not the 9 I calculated before. Looking back at the n=11 factorial experiments versus the n=17 expanded set, I think 068 was added after the initial analysis, and there might be some overlap or different counting between the two datasets that's throwing off my numbers.

Rather than getting stuck on the exact composition of those additional 6 experiments in the n=17 table, I should focus on what I can actually verify and flag the rest for re-checking. The core issue is that removing 008e_v3_s3 from the CIVO positive group and reclassifying 008e_v3_s2 changes the baseline numbers, and I need to trace through how that ripples into the larger tables. I need to stop deliberating and start making the actual edits. Let me compute the exact binomial confidence intervals using Python, then systematically update all the tables and remove the IRD references throughout the document. I should also scan the rest of the file around lines 330, 770, and beyond to catch any other mentions I might have missed.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "00da824f-c0b3-4259-858b-ceb6ba4a80d0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QXM8kh8vSDVVdbucL6mY9m",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11657,
      "cache_read_input_tokens": 36596,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11657
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

_source line 22_

Let me read the remaining sections and compute the new statistics.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "79d7a190-5fbd-457f-8d3a-2753d461f418",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QXM8kh8vSDVVdbucL6mY9m",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11657,
      "cache_read_input_tokens": 36596,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11657
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

_source line 23_

<details open><summary>🔧 Tool call — Read · `toolu_01L6qXBhkHgBbERiKZ2Wo5jn`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
  "offset": 250,
  "limit": 50
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "bab29e37-a95d-47dc-b9e4-ba6a286d2def",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QXM8kh8vSDVVdbucL6mY9m",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11657,
      "cache_read_input_tokens": 36596,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11657
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

_source line 24 · 2026-05-25T16:27:20.123Z_

<details><summary>↩ Tool result · `toolu_01L6qXBhkHgBbERiKZ2Wo5jn`</summary>

```text
250	\label{sec:roc_analysis}
251	
252	The original $n{=}17$ analysis (Tables~\ref{tab:sensitivity_b1}--\ref{tab:sensitivity_b2_full}) predates the SGS, RAVE, and TCN experiments. We extend the NVE diagnostic evaluation to $n{=}56$ configurations spanning all tested interventions. Figure~\ref{fig:nve_roc} shows the receiver operating characteristic curve with 95\% bootstrap confidence interval (10{,}000 resamples).
253	
254	\begin{figure}[h]
255	\centering
256	\includegraphics[width=0.7\columnwidth]{../../artifacts/figures/nve_roc_curve.pdf}
257	\caption{NVE ROC curve ($n{=}56$ configurations, AUROC${=}0.990$, comprehensive validation). The preset $\nve \geq 1.5\times$ operating point (star) achieves TPR${=}1.00$, FPR${=}0.09$, accuracy${=}53/56$, F1${=}0.941$. Three false positives arise from non-CIVO value overestimation: mitigation transient VE spike (008e\_v3 subsample, $1.93\times$) and frozen embedding transients (047, $1.71\times$; 057, $1.88\times$). Threshold calibrated and validated post-hoc; cross-architecture validation deferred.}
258	\label{fig:nve_roc}
259	\end{figure}
260	
261	\begin{figure}[h]
262	\centering
263	\includegraphics[width=0.7\columnwidth]{../../artifacts/figures/nve_threshold_prf.pdf}
264	\caption{Precision, Recall, and F1 as a function of NVE threshold ($n{=}56$ configurations). Peak F1${=}0.941$ at $\tau{=}1.5\times$, where recall remains perfect ($1.00$) and precision${=}0.889$. The plateau of high F1 across $\tau \in [1.5, 1.7]$ indicates robustness to threshold selection.}
265	\label{fig:nve_prf}
266	\end{figure}
267	
268	We label a configuration as CIVO-positive if and only if (i)~it uses a trained $\dt$-embedding with multi-rate data exposure, and (ii)~NVE exceeds $1.5\times$ with co-occurring entropy collapse. Configurations exhibiting high NVE through other mechanisms (gradient truncation side effects, value anchor pollution) are labeled non-CIVO.
269	
270	The three false positives (FPR${=}0.18$) are mechanistically distinct from CIVO: (1)~RAVE anchor pollution (exp\_028, the EMA anchor becomes inflated, producing overestimation through a different pathway); (2)~obs-decoder SGS-induced value distortion (exp\_025 seed~2, blocking observation decoder gradients damages the RSSM latent space); (3)~IRD eval-driven collapse (exp\_008e\_v3 seed~2, actor entropy \emph{increases} with evaluation collapse, mechanistically distinct from CIVO's entropy \emph{decrease}). All three produce NVE $> 1.5\times$ through non-CIVO mechanisms, indicating that the NVE diagnostic detects value overestimation broadly rather than CIVO specifically---a feature rather than a limitation for practitioners monitoring deployment health. The closest sub-threshold case (008f seed~4, NVE${=}1.41\times$) lacks $\dt$-conditioning entirely ($d{=}0$); its elevated NVE reflects transient value noise that self-corrects without the positive feedback loop characteristic of CIVO. The closest above-threshold positive (008d seed~3, NVE${=}1.53\times$) exhibits the full CIVO causal chain: trained $\dt$-embedding, entropy decrease, and evaluation collapse to 14\% of baseline.
271	
272	\paragraph{Comprehensive validation ($n{=}56$).}
273	Expanding the evaluation set to all classifiable experiments yields $n{=}56$ ($n_{\text{pos}}{=}24$, $n_{\text{neg}}{=}32$), spanning Walker Walk, Cheetah Run, and multiple intervention configurations (SGS, TCN, dual-critic, frozen embedding). At the $1.5\times$ threshold: AUROC${=}0.990$, precision${=}0.889$, recall${=}1.000$, F1${=}0.941$, accuracy${=}53/56$. The three false positives are: exp\_008e\_v3\_subsample ($1.93\times$, mitigation config with transient VE spike), exp\_047 ($1.71\times$, frozen embedding transient), and exp\_057 ($1.88\times$, frozen embedding transient). All 24 CIVO-positive configurations are correctly detected (FN${=}0$), with CIVO-positive NVE ranging from $1.53\times$ (008d seed~3, late-onset) to $70.64\times$ (010b seed~0, Cheetah). The substantial increase in sample size from $n{=}32$ to $n{=}56$ strengthens confidence in the $1.5\times$ threshold as a robust diagnostic boundary.
274	
275	\subsection{NVE Normalization Robustness}
276	\label{sec:nve_robustness}
277	
278	To assess sensitivity to baseline seed choice, we extend the single-seed baseline (seed~1, eval 915.7 at 105K) to three additional seeds trained to 505K steps (Table~\ref{tab:baseline_seeds}).
279	
280	\begin{table}[h]
281	\centering
282	\caption{Walker Walk baseline seeds at 105K and 505K steps.}
283	\label{tab:baseline_seeds}
284	\footnotesize
285	\begin{tabular}{lcccc}
286	\toprule
287	\textbf{Seed} & \textbf{Eval@105K} & \textbf{Eval@505K} & \textbf{ve@65K} & \textbf{ve@105K} \\
288	\midrule
289	s1 & 915.7 & 970.4 & 0.563 & 0.656 \\
290	s2 & 443.5 & 945.7 & 0.898 & 0.742 \\
291	s3 & 869.0 & 947.7 & --- & 0.664 \\
292	s4 & 922.8 & 938.9 & --- & 0.624 \\
293	\bottomrule
294	\end{tabular}
295	\end{table}
296	
297	Seed~2 exhibits slow convergence (eval 443.5 at 105K, recovering to 945.7 by 512K), confirming non-pathological slow convergence rather than seed failure. Its elevated $v/e$ ratio at 65K (0.898 vs.\ 0.563 for seed~1) reflects the low evaluation denominator rather than pathological value overestimation. Using seed~2 as the sole normalization reference systematically deflates NVE values, causing two marginal CIVO-positive configurations (008d seed~3, peak NVE $1.53\times$; 009b seed~2, peak NVE $1.62\times$) to fall below the $1.5\times$ threshold. Core CIVO cases (peak NVE $> 3\times$) remain correctly classified under all baseline seeds.
298	
299	Single-seed normalization (s1) yields AUROC $= 0.933$ and accuracy 7/8 (87.5\%) on the Walker subset. Four-seed mean normalization yields AUROC $= 0.867$ and accuracy 6/8 (75.0\%): the boundary case exp\_009b flips from $\nve = 1.62\times$ (s1) to $1.23\times$ (4-seed mean), because its peak occurs at 45K when the s1 $v/e$ ratio (0.331) is well below the 4-seed mean (0.436). All high-NVE configurations remain correctly classified (006: $4.84\times \to 4.52\times$; 008d: $4.12\times \to 3.54\times$). The $1.5\times$ threshold thus correctly identifies all strong CIVO cases regardless of baseline choice; sensitivity is confined to configurations within 10\% of the threshold.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "2049b2b6-f437-4e56-8645-4e5958614b9a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
      "content": "\\label{sec:roc_analysis}\n\nThe original $n{=}17$ analysis (Tables~\\ref{tab:sensitivity_b1}--\\ref{tab:sensitivity_b2_full}) predates the SGS, RAVE, and TCN experiments. We extend the NVE diagnostic evaluation to $n{=}56$ configurations spanning all tested interventions. Figure~\\ref{fig:nve_roc} shows the receiver operating characteristic curve with 95\\% bootstrap confidence interval (10{,}000 resamples).\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.7\\columnwidth]{../../artifacts/figures/nve_roc_curve.pdf}\n\\caption{NVE ROC curve ($n{=}56$ configurations, AUROC${=}0.990$, comprehensive validation). The preset $\\nve \\geq 1.5\\times$ operating point (star) achieves TPR${=}1.00$, FPR${=}0.09$, accuracy${=}53/56$, F1${=}0.941$. Three false positives arise from non-CIVO value overestimation: mitigation transient VE spike (008e\\_v3 subsample, $1.93\\times$) and frozen embedding transients (047, $1.71\\times$; 057, $1.88\\times$). Threshold calibrated and validated post-hoc; cross-architecture validation deferred.}\n\\label{fig:nve_roc}\n\\end{figure}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.7\\columnwidth]{../../artifacts/figures/nve_threshold_prf.pdf}\n\\caption{Precision, Recall, and F1 as a function of NVE threshold ($n{=}56$ configurations). Peak F1${=}0.941$ at $\\tau{=}1.5\\times$, where recall remains perfect ($1.00$) and precision${=}0.889$. The plateau of high F1 across $\\tau \\in [1.5, 1.7]$ indicates robustness to threshold selection.}\n\\label{fig:nve_prf}\n\\end{figure}\n\nWe label a configuration as CIVO-positive if and only if (i)~it uses a trained $\\dt$-embedding with multi-rate data exposure, and (ii)~NVE exceeds $1.5\\times$ with co-occurring entropy collapse. Configurations exhibiting high NVE through other mechanisms (gradient truncation side effects, value anchor pollution) are labeled non-CIVO.\n\nThe three false positives (FPR${=}0.18$) are mechanistically distinct from CIVO: (1)~RAVE anchor pollution (exp\\_028, the EMA anchor becomes inflated, producing overestimation through a different pathway); (2)~obs-decoder SGS-induced value distortion (exp\\_025 seed~2, blocking observation decoder gradients damages the RSSM latent space); (3)~IRD eval-driven collapse (exp\\_008e\\_v3 seed~2, actor entropy \\emph{increases} with evaluation collapse, mechanistically distinct from CIVO's entropy \\emph{decrease}). All three produce NVE $> 1.5\\times$ through non-CIVO mechanisms, indicating that the NVE diagnostic detects value overestimation broadly rather than CIVO specifically---a feature rather than a limitation for practitioners monitoring deployment health. The closest sub-threshold case (008f seed~4, NVE${=}1.41\\times$) lacks $\\dt$-conditioning entirely ($d{=}0$); its elevated NVE reflects transient value noise that self-corrects without the positive feedback loop characteristic of CIVO. The closest above-threshold positive (008d seed~3, NVE${=}1.53\\times$) exhibits the full CIVO causal chain: trained $\\dt$-embedding, entropy decrease, and evaluation collapse to 14\\% of baseline.\n\n\\paragraph{Comprehensive validation ($n{=}56$).}\nExpanding the evaluation set to all classifiable experiments yields $n{=}56$ ($n_{\\text{pos}}{=}24$, $n_{\\text{neg}}{=}32$), spanning Walker Walk, Cheetah Run, and multiple intervention configurations (SGS, TCN, dual-critic, frozen embedding). At the $1.5\\times$ threshold: AUROC${=}0.990$, precision${=}0.889$, recall${=}1.000$, F1${=}0.941$, accuracy${=}53/56$. The three false positives are: exp\\_008e\\_v3\\_subsample ($1.93\\times$, mitigation config with transient VE spike), exp\\_047 ($1.71\\times$, frozen embedding transient), and exp\\_057 ($1.88\\times$, frozen embedding transient). All 24 CIVO-positive configurations are correctly detected (FN${=}0$), with CIVO-positive NVE ranging from $1.53\\times$ (008d seed~3, late-onset) to $70.64\\times$ (010b seed~0, Cheetah). The substantial increase in sample size from $n{=}32$ to $n{=}56$ strengthens confidence in the $1.5\\times$ threshold as a robust diagnostic boundary.\n\n\\subsection{NVE Normalization Robustness}\n\\label{sec:nve_robustness}\n\nTo assess sensitivity to baseline seed choice, we extend the single-seed baseline (seed~1, eval 915.7 at 105K) to three additional seeds trained to 505K steps (Table~\\ref{tab:baseline_seeds}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Walker Walk baseline seeds at 105K and 505K steps.}\n\\label{tab:baseline_seeds}\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Seed} & \\textbf{Eval@105K} & \\textbf{Eval@505K} & \\textbf{ve@65K} & \\textbf{ve@105K} \\\\\n\\midrule\ns1 & 915.7 & 970.4 & 0.563 & 0.656 \\\\\ns2 & 443.5 & 945.7 & 0.898 & 0.742 \\\\\ns3 & 869.0 & 947.7 & --- & 0.664 \\\\\ns4 & 922.8 & 938.9 & --- & 0.624 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nSeed~2 exhibits slow convergence (eval 443.5 at 105K, recovering to 945.7 by 512K), confirming non-pathological slow convergence rather than seed failure. Its elevated $v/e$ ratio at 65K (0.898 vs.\\ 0.563 for seed~1) reflects the low evaluation denominator rather than pathological value overestimation. Using seed~2 as the sole normalization reference systematically deflates NVE values, causing two marginal CIVO-positive configurations (008d seed~3, peak NVE $1.53\\times$; 009b seed~2, peak NVE $1.62\\times$) to fall below the $1.5\\times$ threshold. Core CIVO cases (peak NVE $> 3\\times$) remain correctly classified under all baseline seeds.\n\nSingle-seed normalization (s1) yields AUROC $= 0.933$ and accuracy 7/8 (87.5\\%) on the Walker subset. Four-seed mean normalization yields AUROC $= 0.867$ and accuracy 6/8 (75.0\\%): the boundary case exp\\_009b flips from $\\nve = 1.62\\times$ (s1) to $1.23\\times$ (4-seed mean), because its peak occurs at 45K when the s1 $v/e$ ratio (0.331) is well below the 4-seed mean (0.436). All high-NVE configurations remain correctly classified (006: $4.84\\times \\to 4.52\\times$; 008d: $4.12\\times \\to 3.54\\times$). The $1.5\\times$ threshold thus correctly identifies all strong CIVO cases regardless of baseline choice; sensitivity is confined to configurations within 10\\% of the threshold.",
      "numLines": 50,
      "startLine": 250,
      "totalLines": 1174
    }
  }
}
```

</details>

---


### Tool call

_source line 25_

<details open><summary>🔧 Tool call — Bash · `toolu_01WC62nyq5tnuTdWnQWMYsLd`</summary>

```json
{
  "command": "python3 -c \"\nfrom scipy.stats import binom\nimport numpy as np\n\n# Clopper-Pearson exact binomial CI\ndef cp_ci(k, n, alpha=0.05):\n    lo = binom.ppf(alpha/2, n, np.arange(0, 1.001, 0.001))\n    hi = binom.ppf(1-alpha/2, n, np.arange(0, 1.001, 0.001))\n    # Use scipy.stats.binom interval\n    from scipy.stats import beta as beta_dist\n    if k == 0:\n        lo = 0.0\n    else:\n        lo = beta_dist.ppf(alpha/2, k, n-k+1)\n    if k == n:\n        hi = 1.0\n    else:\n        hi = beta_dist.ppf(1-alpha/2, k+1, n-k)\n    return lo, hi\n\n# B1 table: n_pos=2 (006, 008d), n_neg=8, n=10\n# B2 table: n_pos=4 (006, 059, 008d, 009b), n_neg=6, n=10\nprint('=== B1 (n=10, n_pos=2, n_neg=8) ===')\nprint('AUROC = 15/16 =', 15/16)\nb1_thresholds = [\n    ('>=1.0', 2, 3, 0, 5),\n    ('>=1.2', 2, 2, 0, 6),\n    ('>=1.5', 2, 2, 0, 6),\n    ('>=1.7', 2, 1, 0, 7),\n    ('>=2.0', 2, 1, 0, 7),\n    ('>=3.9', 2, 1, 0, 7),\n]\nfor name, tp, fp, fn, tn in b1_thresholds:\n    acc = (tp+tn)/10\n    prec = tp/(tp+fp) if (tp+fp) > 0 else 0\n    rec = tp/(tp+fn) if (tp+fn) > 0 else 0\n    f1 = 2*prec*rec/(prec+rec) if (prec+rec) > 0 else 0\n    lo, hi = cp_ci(tp+tn, 10)\n    print(f'{name}: TP={tp} FP={fp} FN={fn} TN={tn} Acc={acc*100:.1f}% [{lo*100:.1f}, {hi*100:.1f}] Prec={prec*100:.1f}% Rec={rec*100:.0f}% F1={f1*100:.1f}%')\n\nprint()\nprint('=== B2 (n=10, n_pos=4, n_neg=6) ===')\nprint('AUROC = 1.000 (perfect separation)')\nb2_thresholds = [\n    ('>=1.0', 4, 1, 0, 5),\n    ('>=1.2', 4, 0, 0, 6),\n    ('>=1.5', 4, 0, 0, 6),\n    ('>=1.7', 3, 0, 1, 6),\n    ('>=2.0', 3, 0, 1, 6),\n    ('>=3.9', 3, 0, 1, 6),\n]\nfor name, tp, fp, fn, tn in b2_thresholds:\n    acc = (tp+tn)/10\n    prec = tp/(tp+fp) if (tp+fp) > 0 else 0\n    rec = tp/(tp+fn) if (tp+fn) > 0 else 0\n    f1 = 2*prec*rec/(prec+rec) if (prec+rec) > 0 else 0\n    lo, hi = cp_ci(tp+tn, 10)\n    print(f'{name}: TP={tp} FP={fp} FN={fn} TN={tn} Acc={acc*100:.1f}% [{lo*100:.1f}, {hi*100:.1f}] Prec={prec*100:.1f}% Rec={rec*100:.0f}% F1={f1*100:.1f}%')\n\"\n",
  "description": "Compute exact binomial CIs for updated sensitivity tables"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "20e90dd3-9a03-4e77-83de-acbe7818df2a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QXM8kh8vSDVVdbucL6mY9m",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11657,
      "cache_read_input_tokens": 36596,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11657
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

_source line 26 · 2026-05-25T16:27:32.639Z_

<details><summary>↩ Tool result · `toolu_01WC62nyq5tnuTdWnQWMYsLd`</summary>

```text
=== B1 (n=10, n_pos=2, n_neg=8) ===
AUROC = 15/16 = 0.9375
>=1.0: TP=2 FP=3 FN=0 TN=5 Acc=70.0% [34.8, 93.3] Prec=40.0% Rec=100% F1=57.1%
>=1.2: TP=2 FP=2 FN=0 TN=6 Acc=80.0% [44.4, 97.5] Prec=50.0% Rec=100% F1=66.7%
>=1.5: TP=2 FP=2 FN=0 TN=6 Acc=80.0% [44.4, 97.5] Prec=50.0% Rec=100% F1=66.7%
>=1.7: TP=2 FP=1 FN=0 TN=7 Acc=90.0% [55.5, 99.7] Prec=66.7% Rec=100% F1=80.0%
>=2.0: TP=2 FP=1 FN=0 TN=7 Acc=90.0% [55.5, 99.7] Prec=66.7% Rec=100% F1=80.0%
>=3.9: TP=2 FP=1 FN=0 TN=7 Acc=90.0% [55.5, 99.7] Prec=66.7% Rec=100% F1=80.0%

=== B2 (n=10, n_pos=4, n_neg=6) ===
AUROC = 1.000 (perfect separation)
>=1.0: TP=4 FP=1 FN=0 TN=5 Acc=90.0% [55.5, 99.7] Prec=80.0% Rec=100% F1=88.9%
>=1.2: TP=4 FP=0 FN=0 TN=6 Acc=100.0% [69.2, 100.0] Prec=100.0% Rec=100% F1=100.0%
>=1.5: TP=4 FP=0 FN=0 TN=6 Acc=100.0% [69.2, 100.0] Prec=100.0% Rec=100% F1=100.0%
>=1.7: TP=3 FP=0 FN=1 TN=6 Acc=90.0% [55.5, 99.7] Prec=100.0% Rec=75% F1=85.7%
>=2.0: TP=3 FP=0 FN=1 TN=6 Acc=90.0% [55.5, 99.7] Prec=100.0% Rec=75% F1=85.7%
>=3.9: TP=3 FP=0 FN=1 TN=6 Acc=90.0% [55.5, 99.7] Prec=100.0% Rec=75% F1=85.7%
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "b0fb6716-c078-4f49-8aa8-a46a21406620",
  "tool_use_result": {
    "stdout": "=== B1 (n=10, n_pos=2, n_neg=8) ===\nAUROC = 15/16 = 0.9375\n>=1.0: TP=2 FP=3 FN=0 TN=5 Acc=70.0% [34.8, 93.3] Prec=40.0% Rec=100% F1=57.1%\n>=1.2: TP=2 FP=2 FN=0 TN=6 Acc=80.0% [44.4, 97.5] Prec=50.0% Rec=100% F1=66.7%\n>=1.5: TP=2 FP=2 FN=0 TN=6 Acc=80.0% [44.4, 97.5] Prec=50.0% Rec=100% F1=66.7%\n>=1.7: TP=2 FP=1 FN=0 TN=7 Acc=90.0% [55.5, 99.7] Prec=66.7% Rec=100% F1=80.0%\n>=2.0: TP=2 FP=1 FN=0 TN=7 Acc=90.0% [55.5, 99.7] Prec=66.7% Rec=100% F1=80.0%\n>=3.9: TP=2 FP=1 FN=0 TN=7 Acc=90.0% [55.5, 99.7] Prec=66.7% Rec=100% F1=80.0%\n\n=== B2 (n=10, n_pos=4, n_neg=6) ===\nAUROC = 1.000 (perfect separation)\n>=1.0: TP=4 FP=1 FN=0 TN=5 Acc=90.0% [55.5, 99.7] Prec=80.0% Rec=100% F1=88.9%\n>=1.2: TP=4 FP=0 FN=0 TN=6 Acc=100.0% [69.2, 100.0] Prec=100.0% Rec=100% F1=100.0%\n>=1.5: TP=4 FP=0 FN=0 TN=6 Acc=100.0% [69.2, 100.0] Prec=100.0% Rec=100% F1=100.0%\n>=1.7: TP=3 FP=0 FN=1 TN=6 Acc=90.0% [55.5, 99.7] Prec=100.0% Rec=75% F1=85.7%\n>=2.0: TP=3 FP=0 FN=1 TN=6 Acc=90.0% [55.5, 99.7] Prec=100.0% Rec=75% F1=85.7%\n>=3.9: TP=3 FP=0 FN=1 TN=6 Acc=90.0% [55.5, 99.7] Prec=100.0% Rec=75% F1=85.7%",
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

_source line 27_

<details><summary>Logged reasoning block</summary>

```text
Now I have the exact numbers. Let me also check the n=17 and n=56 impacts. Let me also read what I need for the LOEO, failure modes, and pathways sections.

Also I need to check - are the ROC curve figures still valid after these changes? The n=56 analysis references specific false positives. With the new data, one of those 3 FPs ("exp_008e_v3 subsample, 1.93×") is gone, so the n=56 goes from 53/56 to at least 54/56 (or n changes too).


Wait, I need to be careful here - the n=56 analysis is actually a separate dataset from the n=11 analysis. The n=56 includes all classifiable experiments like SGS and TCN, so "exp_008e_v3_subsample" in that set might not be the same as the 008e_v3 seeds in the n=11 table. Looking at the specific false positives listed, I have three cases: the subsample with the transient VE spike, exp_047 with frozen embedding transient, and exp_057 also with frozen embedding transient.

But here's the issue - all the 008e_v3 data comes from buggy code, so even this subsample variant would be invalid. With the corrected NVE values of 0.5-0.6, this wouldn't actually be a false positive. And I'm noticing something confusing: line 270 mentions "three false positives" with different examples than line 273, which also says "three false positives" but lists different ones entirely. I need to carefully distinguish which false positives belong to which analysis. I'm noticing the false positive counts don't match up between these two sections—one lists three specific experiments while the other lists different ones, both claiming n=56. The FPR calculation also seems off; if there are 3 false positives out of 32 non-CIVO cases, that's about 0.094, not 0.18, unless they're using a different denominator or analysis window. These inconsistencies seem to predate my task, so I should focus on the specific revisions I'm supposed to make rather than trying to resolve all the underlying issues.

For the n=56 analysis, I need to remove the 008e_v3 entries from both lists since that data is now invalid—this reduces the false positive count from 3 to 2 in each section (keeping RAVE and SGS in one list, exp_047 and exp_057 in the other). Since both sections claim to show "three false positives" but reference different experiments, I'll update both to reflect the corrected counts after removing the invalid data. I'm noticing inconsistencies across different sections of the document. The figure caption and line 273 both reference the same three false positives (008e_v3_subsample, 047, 057), but line 270 lists a completely different set (028, 025_s2, 008e_v3_s2). These might be describing different classification tasks or analysis windows, so I need to trace through the document structure to figure out which false positives belong where and whether they're referring to task B1, B2, or different data subsets. I'm noticing a discrepancy in the FPR values—line 257 reports FPR=0.09 for the n=56 analysis, but line 270 claims FPR=0.18 for what it calls the same analysis. If FPR=0.18 with 3 false positives, that implies only 17 negative samples, which doesn't align with the n=56 dataset that should have 32 negatives. These might be describing different classification scenarios or snapshots from different stages of the analysis. So the FPR=0.18 with 3 false positives doesn't align with the n=56 configuration either—that would require only about 17 negative samples, which contradicts the stated setup. It looks like line 270 might be pulled from an earlier version of the analysis. Both that line and the references to 008e_v3 data are problematic since that seed configuration is invalid. I need to systematically go through and fix the results table, the NVE diagnostic data, and both sensitivity tables to reflect the correct 3-seed configuration instead of the old 5-seed setup. I'm working through the sample size calculations for the updated analysis. The original n=17 included Walker (15) and Cheetah (2), but I need to figure out how many 008e_v3 seeds were in that original count. The n=11 analysis mentions four seeds, so if the n=17 had four 008e_v3 seeds and I'm replacing them with three, that brings Walker down from 15 to 14, making the new total n=15.

The challenge is that the n=17 table has concrete LaTeX numbers I can't just adjust without knowing the exact composition of the original experiments. Looking at the table structure, it mirrors the B2 table but with different values, and now with the updated data where 008e_v3_s3 is no longer positive, I need to recalculate which experiments actually belong in this analysis. Let me recalculate this more carefully. With the old 008e_v3 seeds (s1-s4), I had s3 as the only positive and s1, s2, s4 as negatives. Replacing all four with the new three seeds (s0-s2), which are all negative, means I'm losing one positive and three negatives while gaining three negatives—so the net effect is n drops to 16, n_pos drops to 8, and n_neg stays at 8.

Now looking at the B2 classification at 1.5×: removing that false positive (008e_v3_s2 at 3.78) and ensuring all new seeds have NVE ≤ 0.6 gives me perfect accuracy at 100% instead of the previous 94.1%. I need to recompute the full threshold and AUROC metrics to see the complete impact.

Actually, I realize I need to know all the experiments in the n=17 set and their NVE values to compute the full table accurately. Let me try reconstructing which 6 experiments were added to the original n=11 Walker set to get to n=17.

The n=17 set consists of 15 Walker experiments plus 2 Cheetah (010b and 010b_s0). So I need to identify the 4 additional Walker experiments beyond the original 11. Based on the NVE values I have, the likely candidates are 008d_s3 (NVE 1.53), 008d_s4 (NVE 4.62), 008f_s4 (NVE 0.76), and 009c_s3 (NVE 1.04). Let me verify this gives me the right count of positive results.

Looking at the B2+ group, I'm finding 7 positive Walker experiments (006, 059, 008d, 008e_v3_s3, 008d_s3, 008d_s4, 009b) and 2 positive Cheetah, for 9 total positives. The B2- group has 8 negative Walker experiments with no negative Cheetah, giving 8 negatives. This confirms the four additional Walker experiments are 008d_s3, 008d_s4, 008f_s4, and 009c_s3.

Now I'm recounting the full dataset with the updated 008e_v3 variants. Breaking it down: 7 non-008e_v3 Walker experiments from the original set, 3 new 008e_v3 variants, the 4 additional Walker experiments, and 2 Cheetah experiments, totaling 16. Looking at the performance values, I'm seeing 8 positive results in the B2 range with values ranging from 1.53 to 108.52, and the negatives starting to appear in the lower range around 0.93 to 1.04.

The separation is clean—there's a clear gap between the lowest positive at 1.53 and the highest negative at 1.04, which gives me perfect classification at a 1.5× threshold with 100% accuracy and an AUROC of 1.000. Now I'm working through all the thresholds by sorting the values in descending order to build out the complete evaluation table. Now I'm testing different thresholds to find the optimal cutoff for flagging anomalies. At 1.2 and above, I get perfect accuracy with all true positives and no false positives, while 1.7 starts introducing a false negative with one missed case.

I should compute confidence intervals for these results, but I already have the framework set up. Let me move forward with the actual editing process and batch the independent changes together, then verify everything is consistent with the results section.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "76cbafef-efb7-40fc-81a0-1777c3336b41",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01929F6cJJJFYzzWdwt7uio1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18678,
      "cache_read_input_tokens": 48253,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18678
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

_source line 28_

Let me also check results.tex F6 section for consistency, and compute the n=16 table numbers.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "f5dae816-fc4d-4e6b-ad65-21d881053e85",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01929F6cJJJFYzzWdwt7uio1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18678,
      "cache_read_input_tokens": 48253,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18678
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

_source line 29_

<details open><summary>🔧 Tool call — Grep · `toolu_01VBcqE98GDrP3jkF42GfcBj`</summary>

```json
{
  "pattern": "008e_v3|\\\\\\\\label\\{sec:f6\\}|Pathway|IRD",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/results.tex",
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
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "bcdf8858-a6c7-4529-aeca-3322c9d6a644",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01929F6cJJJFYzzWdwt7uio1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18678,
      "cache_read_input_tokens": 48253,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18678
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

_source line 30 · 2026-05-25T16:29:18.288Z_

<details><summary>↩ Tool result · `toolu_01VBcqE98GDrP3jkF42GfcBj`</summary>

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
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "ad2fa183-2bf1-4f2f-a28f-3ec2994c7465",
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

<details open><summary>🔧 Tool call — Bash · `toolu_01SaS4hB8HAT5gVVJcTm1NF4`</summary>

```json
{
  "command": "python3 -c \"\nfrom scipy.stats import beta as beta_dist\n\ndef cp_ci(k, n, alpha=0.05):\n    if k == 0:\n        lo = 0.0\n    else:\n        lo = beta_dist.ppf(alpha/2, k, n-k+1)\n    if k == n:\n        hi = 1.0\n    else:\n        hi = beta_dist.ppf(1-alpha/2, k+1, n-k)\n    return lo, hi\n\n# B2 full (n=16, n_pos=8, n_neg=8) - perfect separation\nprint('=== B2 full (n=16, n_pos=8, n_neg=8) ===')\nprint('AUROC = 1.000')\nthresholds = [\n    ('>=1.0', 8, 2, 0, 6),\n    ('>=1.2', 8, 0, 0, 8),\n    ('>=1.5', 8, 0, 0, 8),\n    ('>=1.7', 7, 0, 1, 8),\n    ('>=2.0', 7, 0, 1, 8),\n    ('>=3.9', 6, 0, 2, 8),\n]\nfor name, tp, fp, fn, tn in thresholds:\n    acc = (tp+tn)/16\n    prec = tp/(tp+fp) if (tp+fp) > 0 else 0\n    rec = tp/(tp+fn) if (tp+fn) > 0 else 0\n    f1 = 2*prec*rec/(prec+rec) if (prec+rec) > 0 else 0\n    lo, hi = cp_ci(tp+tn, 16)\n    print(f'{name}: TP={tp} FP={fp} FN={fn} TN={tn} Acc={acc*100:.1f}% [{lo*100:.1f}, {hi*100:.1f}] Prec={prec*100:.1f}% Rec={rec*100:.0f}% F1={f1*100:.1f}%')\n\"\n",
  "description": "Compute n=16 B2 full sensitivity table"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "e1673870-72bb-4587-8871-9687c2e9bab7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01929F6cJJJFYzzWdwt7uio1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18678,
      "cache_read_input_tokens": 48253,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18678
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

_source line 32 · 2026-05-25T16:29:25.245Z_

<details><summary>↩ Tool result · `toolu_01SaS4hB8HAT5gVVJcTm1NF4`</summary>

```text
=== B2 full (n=16, n_pos=8, n_neg=8) ===
AUROC = 1.000
>=1.0: TP=8 FP=2 FN=0 TN=6 Acc=87.5% [61.7, 98.4] Prec=80.0% Rec=100% F1=88.9%
>=1.2: TP=8 FP=0 FN=0 TN=8 Acc=100.0% [79.4, 100.0] Prec=100.0% Rec=100% F1=100.0%
>=1.5: TP=8 FP=0 FN=0 TN=8 Acc=100.0% [79.4, 100.0] Prec=100.0% Rec=100% F1=100.0%
>=1.7: TP=7 FP=0 FN=1 TN=8 Acc=93.8% [69.8, 99.8] Prec=100.0% Rec=88% F1=93.3%
>=2.0: TP=7 FP=0 FN=1 TN=8 Acc=93.8% [69.8, 99.8] Prec=100.0% Rec=88% F1=93.3%
>=3.9: TP=6 FP=0 FN=2 TN=8 Acc=87.5% [61.7, 98.4] Prec=100.0% Rec=75% F1=85.7%
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "bc493ac4-c388-4f18-8ea3-87aafeccb5ac",
  "tool_use_result": {
    "stdout": "=== B2 full (n=16, n_pos=8, n_neg=8) ===\nAUROC = 1.000\n>=1.0: TP=8 FP=2 FN=0 TN=6 Acc=87.5% [61.7, 98.4] Prec=80.0% Rec=100% F1=88.9%\n>=1.2: TP=8 FP=0 FN=0 TN=8 Acc=100.0% [79.4, 100.0] Prec=100.0% Rec=100% F1=100.0%\n>=1.5: TP=8 FP=0 FN=0 TN=8 Acc=100.0% [79.4, 100.0] Prec=100.0% Rec=100% F1=100.0%\n>=1.7: TP=7 FP=0 FN=1 TN=8 Acc=93.8% [69.8, 99.8] Prec=100.0% Rec=88% F1=93.3%\n>=2.0: TP=7 FP=0 FN=1 TN=8 Acc=93.8% [69.8, 99.8] Prec=100.0% Rec=88% F1=93.3%\n>=3.9: TP=6 FP=0 FN=2 TN=8 Acc=87.5% [61.7, 98.4] Prec=100.0% Rec=75% F1=85.7%",
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
Good - results.tex has no references to 008e_v3, IRD, or Pathway B, so it's already clean.

Now I have all the numbers I need. Let me start making the edits systematically.

Let me also check line 103 (footnote about dagger) and lines 6, 10 (complete results table caption) to see if dagger definition needs updating. With the new data, the only dagger in the table will be on exp_059. But the dagger was defined in the caption (line 10) as "$\dagger$\,marks a false positive (non-CIVO collapse with elevated NVE)". 

Looking at exp_059 more closely, the dagger indicates it's not a true CIVO collapse, and the footnote explains that the NVE self-corrected but the policy didn't recover. So the dagger definition in the caption actually matches what's happening with this experiment - it's a case where the system showed elevated NVE without true CIVO collapse. The dagger definition in the caption was specifically tied to 008e_v3_s2's situation—elevated NVE from a non-CIVO collapse mechanism. Since 059 has its own separate footnote explaining its context, I need to reconsider whether the caption's dagger definition still applies or if it should be updated to reflect what the daggers actually represent across the remaining rows.

Now I'm mapping out the specific edits: replacing the five old 008e_v3 rows with three new ones in the table, and updating the NVE section to reflect the changes. I've got a substantial list of edits to work through across multiple sections. Let me organize these by their dependencies and tackle the independent ones first, then I should check what the current results.tex file says about the 008e_v3 section to make sure my changes align with what's already there.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "6c43c980-35ec-4a1a-a11b-2f454938732e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GVsPXz6BeNaTUwnoMfDnNz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6843,
      "cache_read_input_tokens": 66931,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6843
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

_source line 34_

Let me check results.tex for the F6 section and also read appendix.tex around the key locations I haven't fully seen yet.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "b0f36b0e-8d98-498c-a2c5-5667e4bea59d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GVsPXz6BeNaTUwnoMfDnNz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6843,
      "cache_read_input_tokens": 66931,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6843
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

_source line 35_

<details open><summary>🔧 Tool call — Grep · `toolu_018UPPrzP3K445sa38ELUztq`</summary>

```json
{
  "pattern": "f6|F6|mitigation|008e",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/results.tex",
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
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "99f562eb-d2b3-46e8-b994-67556ce0f360",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GVsPXz6BeNaTUwnoMfDnNz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6843,
      "cache_read_input_tokens": 66931,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6843
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

_source line 36_

<details open><summary>🔧 Tool call — Read · `toolu_01Affs4wGaDuRkSA8oKkLnG5`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
  "offset": 1070,
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
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "4ba1785b-ad47-4171-b1c1-729744e5e483",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GVsPXz6BeNaTUwnoMfDnNz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6843,
      "cache_read_input_tokens": 66931,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6843
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

_source line 37 · 2026-05-25T16:29:59.769Z_

<details><summary>↩ Tool result · `toolu_01Affs4wGaDuRkSA8oKkLnG5`</summary>

```text
1070	This appendix provides the full algorithm specification and validation results for the online CIVO detector described in \S\ref{sec:detector}.
1071	
1072	\subsection{Algorithm Specification}
1073	
1074	
1075	The four conditions capture complementary signals: (1)~\emph{Magnitude} ($r_t \geq 0.49$) confirms that the value-to-evaluation ratio has reached a level indicative of overestimation; (2)~\emph{Velocity} ($\Delta r_t > 0.1$) rules out slow drift or plateau behavior; (3)~\emph{Acceleration} ($\Delta r_t > \Delta r_{t-1}$, both $> 0.1$) filters oscillatory paths; (4)~\emph{Evaluation decline} ($\geq 2$ of 3 recent checkpoints decline) confirms that overestimation coincides with actual performance degradation. A full comparison of window sizes appears in \S\ref{sec:appendix_sensitivity}.
1076	
1077	Sensitivity analysis over $\tau_\text{mag} \in [0.30, 0.70]$ confirms that $\tau_\text{mag} = 0.49$ maximizes Youden's $J = 0.714$; raising the threshold to $0.50$ loses one true positive (seed~3 triggers at $r_t = 0.497$) with no reduction in false positives. The velocity threshold $\tau_\text{vel} = 0.1$ is stable across $[0.05, 0.18]$ (TPR remains $5/5$).
1078	
1079	\subsection{Validation Results}
1080	
1081	\begin{table}[ht]
1082	\centering
1083	\caption{Retrospective CIVO detector validation ($n{=}14$). Detection type: ``predictive'' = alert precedes 20\% eval decline; ``reactive'' = alert follows decline onset.}
1084	\label{tab:detector-validation}
1085	\footnotesize
1086	\setlength{\tabcolsep}{3pt}
1087	\begin{tabular}{llccccc}
1088	\toprule
1089	\textbf{Exp} & \textbf{Config} & \textbf{Verdict} & \textbf{Trigger} & \textbf{Type} & \textbf{Peak Eval} & $r_\text{ve}$ \\
1090	\midrule
1091	008d s0 & trained $\dt$-emb & TP & 45K & predict. & 167 & 0.69 \\
1092	010b & trained $\dt$-emb (Cheetah) & TP & 65K & reactive & 322 & 3.18 \\
1093	008d s3 & trained $\dt$-emb & TP & 45K & predict. & 452 & 0.50 \\
1094	008d s4 & trained $\dt$-emb & TP & 105K & reactive & 383 & 3.03 \\
1095	010b s0 & trained $\dt$-emb (Cheetah) & TP & 95K & reactive & 248 & 6.34 \\
1096	\midrule
1097	008f s3 & no $\dt$-emb & TN & -- & -- & 594 & -- \\
1098	009b s2 & trained $\dt$-emb (self-corr.) & TN & -- & -- & 279 & -- \\
1099	baseline s1 & vanilla & TN & -- & -- & 970 & -- \\
1100	009d s0 & vanilla & TN & -- & -- & 951 & -- \\
1101	009d s1 & vanilla & TN & -- & -- & 920 & -- \\
1102	019b & trained $\dt$-emb (PickCube) & TN & -- & -- & 26.6 & -- \\
1103	\midrule
1104	009c s2 & no $\dt$-emb & FP & 105K & reactive & 359 & 0.75 \\
1105	009a s2 & vanilla & FP & 85K & predict. & 967 & 0.73 \\
1106	\midrule
1107	009c s3 & no $\dt$-emb & TN & -- & -- & 457 & -- \\
1108	\midrule
1109	\multicolumn{7}{l}{TPR = 5/5 (1.00), \quad FPR = 2/9 (0.22)} \\
1110	\bottomrule
1111	\end{tabular}
1112	\end{table}
1113	
1114	The detector identifies all five CIVO-positive runs (TPR = 5/5). Two are detected predictively (008d seeds~0 and~3, both at 45K). Two false positives occur among nine negative cases (FPR = 2/9, precision 71\%, F$_1$ = 0.83). Run 009c develops genuine late-stage value overestimation unrelated to CIVO; run 009a triggers during a transient eval dip at 85K before recovery to 966. Early alerts (before 70K) carry higher diagnostic confidence.
1115	
1116	\subsection{Cross-Simulator Specificity (PickCube)}
1117	
1118	Exp\_019b applies the CIVO-trigger configuration to PickCube-v1 in ManiSkill3, a dense-reward manipulation task. The V/E ratio exhibits an oscillatory pattern rather than monotonic divergence: it spikes to $r_t = 5.66$ at 52.5K, then deflates to 1.38 by 72.5K. This trajectory prevents the acceleration condition from co-occurring with evaluation decline at any single checkpoint. Across all 14 checkpoints through 132.5K, the detector correctly remains silent (TN), confirming that the acceleration filter distinguishes transient spikes from CIVO's sustained monotonic divergence. A frozen-embedding control (exp\_054) confirms this classification: frozen PickCube-v1 exhibits a comparable burst (peak $8.81\times$ at 62.5K) that resolves within a single evaluation cycle ($0.55\times$ at 72.5K), establishing environment-specific origin independent of $\dt$-embedding training.
1119	
1120	\subsection{Detector Limitations}
1121	
1122	Four constraints bound the current detector. First, the three-checkpoint window cannot distinguish transient dips from sustained collapse. Second, the acceleration condition assumes monotonically increasing overestimation during onset. Third, the detector identifies a \emph{pattern} rather than a \emph{mechanism}: run 009c shows that non-CIVO pathologies produce the same signature. Fourth, threshold values were calibrated on fourteen runs across three environments; generalization to different reward scales requires further validation.
1123	
1124	\section{Dual-Critic Mechanism Ablation}
1125	\label{sec:dual_critic_appendix}
1126	
1127	\subsection{\texorpdfstring{$2{\times}2$}{2x2} Factorial Design}
1128	
1129	We ablate the critic architecture in a $2{\times}2$ factorial: \{single, dual\} $\times$ \{narrow (${\sim}1.2$M), wide (${\sim}2.4$M)\} parameters. Table~\ref{tab:dual_critic_full} reports all configurations.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "6a21187e-4af2-4566-b35e-8dfce128b287",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
      "content": "This appendix provides the full algorithm specification and validation results for the online CIVO detector described in \\S\\ref{sec:detector}.\n\n\\subsection{Algorithm Specification}\n\n\nThe four conditions capture complementary signals: (1)~\\emph{Magnitude} ($r_t \\geq 0.49$) confirms that the value-to-evaluation ratio has reached a level indicative of overestimation; (2)~\\emph{Velocity} ($\\Delta r_t > 0.1$) rules out slow drift or plateau behavior; (3)~\\emph{Acceleration} ($\\Delta r_t > \\Delta r_{t-1}$, both $> 0.1$) filters oscillatory paths; (4)~\\emph{Evaluation decline} ($\\geq 2$ of 3 recent checkpoints decline) confirms that overestimation coincides with actual performance degradation. A full comparison of window sizes appears in \\S\\ref{sec:appendix_sensitivity}.\n\nSensitivity analysis over $\\tau_\\text{mag} \\in [0.30, 0.70]$ confirms that $\\tau_\\text{mag} = 0.49$ maximizes Youden's $J = 0.714$; raising the threshold to $0.50$ loses one true positive (seed~3 triggers at $r_t = 0.497$) with no reduction in false positives. The velocity threshold $\\tau_\\text{vel} = 0.1$ is stable across $[0.05, 0.18]$ (TPR remains $5/5$).\n\n\\subsection{Validation Results}\n\n\\begin{table}[ht]\n\\centering\n\\caption{Retrospective CIVO detector validation ($n{=}14$). Detection type: ``predictive'' = alert precedes 20\\% eval decline; ``reactive'' = alert follows decline onset.}\n\\label{tab:detector-validation}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{Verdict} & \\textbf{Trigger} & \\textbf{Type} & \\textbf{Peak Eval} & $r_\\text{ve}$ \\\\\n\\midrule\n008d s0 & trained $\\dt$-emb & TP & 45K & predict. & 167 & 0.69 \\\\\n010b & trained $\\dt$-emb (Cheetah) & TP & 65K & reactive & 322 & 3.18 \\\\\n008d s3 & trained $\\dt$-emb & TP & 45K & predict. & 452 & 0.50 \\\\\n008d s4 & trained $\\dt$-emb & TP & 105K & reactive & 383 & 3.03 \\\\\n010b s0 & trained $\\dt$-emb (Cheetah) & TP & 95K & reactive & 248 & 6.34 \\\\\n\\midrule\n008f s3 & no $\\dt$-emb & TN & -- & -- & 594 & -- \\\\\n009b s2 & trained $\\dt$-emb (self-corr.) & TN & -- & -- & 279 & -- \\\\\nbaseline s1 & vanilla & TN & -- & -- & 970 & -- \\\\\n009d s0 & vanilla & TN & -- & -- & 951 & -- \\\\\n009d s1 & vanilla & TN & -- & -- & 920 & -- \\\\\n019b & trained $\\dt$-emb (PickCube) & TN & -- & -- & 26.6 & -- \\\\\n\\midrule\n009c s2 & no $\\dt$-emb & FP & 105K & reactive & 359 & 0.75 \\\\\n009a s2 & vanilla & FP & 85K & predict. & 967 & 0.73 \\\\\n\\midrule\n009c s3 & no $\\dt$-emb & TN & -- & -- & 457 & -- \\\\\n\\midrule\n\\multicolumn{7}{l}{TPR = 5/5 (1.00), \\quad FPR = 2/9 (0.22)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe detector identifies all five CIVO-positive runs (TPR = 5/5). Two are detected predictively (008d seeds~0 and~3, both at 45K). Two false positives occur among nine negative cases (FPR = 2/9, precision 71\\%, F$_1$ = 0.83). Run 009c develops genuine late-stage value overestimation unrelated to CIVO; run 009a triggers during a transient eval dip at 85K before recovery to 966. Early alerts (before 70K) carry higher diagnostic confidence.\n\n\\subsection{Cross-Simulator Specificity (PickCube)}\n\nExp\\_019b applies the CIVO-trigger configuration to PickCube-v1 in ManiSkill3, a dense-reward manipulation task. The V/E ratio exhibits an oscillatory pattern rather than monotonic divergence: it spikes to $r_t = 5.66$ at 52.5K, then deflates to 1.38 by 72.5K. This trajectory prevents the acceleration condition from co-occurring with evaluation decline at any single checkpoint. Across all 14 checkpoints through 132.5K, the detector correctly remains silent (TN), confirming that the acceleration filter distinguishes transient spikes from CIVO's sustained monotonic divergence. A frozen-embedding control (exp\\_054) confirms this classification: frozen PickCube-v1 exhibits a comparable burst (peak $8.81\\times$ at 62.5K) that resolves within a single evaluation cycle ($0.55\\times$ at 72.5K), establishing environment-specific origin independent of $\\dt$-embedding training.\n\n\\subsection{Detector Limitations}\n\nFour constraints bound the current detector. First, the three-checkpoint window cannot distinguish transient dips from sustained collapse. Second, the acceleration condition assumes monotonically increasing overestimation during onset. Third, the detector identifies a \\emph{pattern} rather than a \\emph{mechanism}: run 009c shows that non-CIVO pathologies produce the same signature. Fourth, threshold values were calibrated on fourteen runs across three environments; generalization to different reward scales requires further validation.\n\n\\section{Dual-Critic Mechanism Ablation}\n\\label{sec:dual_critic_appendix}\n\n\\subsection{\\texorpdfstring{$2{\\times}2$}{2x2} Factorial Design}\n\nWe ablate the critic architecture in a $2{\\times}2$ factorial: \\{single, dual\\} $\\times$ \\{narrow (${\\sim}1.2$M), wide (${\\sim}2.4$M)\\} parameters. Table~\\ref{tab:dual_critic_full} reports all configurations.",
      "numLines": 60,
      "startLine": 1070,
      "totalLines": 1174
    }
  }
}
```

</details>

---


### Tool result

_source line 38 · 2026-05-25T16:29:59.776Z_

<details><summary>↩ Tool result · `toolu_018UPPrzP3K445sa38ELUztq`</summary>

```text
84:[Omitted long matching line]
105:%% F6--F7: Interventions
108:\subsection{F6--F7: Interventions}
109:\label{sec:f6}
111:\paragraph{F6: $\dt{=}1$ imagination eliminates CIVO.}
112:[Omitted long matching line]
117:\caption{Contrasting dynamics. \textbf{Left:} 008d (CIVO), value explosion with entropy decrease. \textbf{Right:} 008e\_v3 s2 ($\dt{=}1$ imagination), no CIVO onset (NVE $0.5\times$, eval $64\%$ baseline).}
121:Full-SGS (exp\_018) detaches all non-KL gradients from $e_{\dt}$. Seed~1 shows partial mitigation (eval 448.3, NVE $1.66\times$); seed~2 collapses (0/2 elimination; Appendix~\ref{sec:sgs_gradient_analysis}). Cross-environment validation on Cheetah (010b, NVE $8.27$--$108.52\times$) confirms CIVO generalization; full-SGS yields 0/3 elimination. Removing the embedding eliminates CIVO on Cheetah (024b, NVE $< 0.2\times$).
172:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "e02e29d0-5c74-47fe-b49b-a8d056a69b94",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "84:[Omitted long matching line]\n105:%% F6--F7: Interventions\n108:\\subsection{F6--F7: Interventions}\n109:\\label{sec:f6}\n111:\\paragraph{F6: $\\dt{=}1$ imagination eliminates CIVO.}\n112:[Omitted long matching line]\n117:\\caption{Contrasting dynamics. \\textbf{Left:} 008d (CIVO), value explosion with entropy decrease. \\textbf{Right:} 008e\\_v3 s2 ($\\dt{=}1$ imagination), no CIVO onset (NVE $0.5\\times$, eval $64\\%$ baseline).}\n121:Full-SGS (exp\\_018) detaches all non-KL gradients from $e_{\\dt}$. Seed~1 shows partial mitigation (eval 448.3, NVE $1.66\\times$); seed~2 collapses (0/2 elimination; Appendix~\\ref{sec:sgs_gradient_analysis}). Cross-environment validation on Cheetah (010b, NVE $8.27$--$108.52\\times$) confirms CIVO generalization; full-SGS yields 0/3 elimination. Removing the embedding eliminates CIVO on Cheetah (024b, NVE $< 0.2\\times$).\n172:[Omitted long matching line]",
    "numLines": 9
  }
}
```

</details>

---


### Assistant

_source line 39_

<details><summary>Logged reasoning block</summary>

```text
Good. Looking at results.tex line 117, the F6 section already has the corrected data:
"008e\_v3 s2 ($\dt{=}1$ imagination), no CIVO onset (NVE $0.5\times$, eval $64\%$ baseline)"

So results.tex is already updated with the correct data. My changes in appendix.tex should be consistent with this.

Now let me check line 112 for the full F6 paragraph:
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "27652ab9-2afe-460d-8bc9-75686fec6368",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TwPJWXinXcp2jptNBpcsBP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1945,
      "cache_creation_input_tokens": 2051,
      "cache_read_input_tokens": 73774,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2051
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

_source line 40_

<details open><summary>🔧 Tool call — Read · `toolu_014jANrxj3v6UsFHK3PBB6Ju`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/results.tex",
  "offset": 108,
  "limit": 20
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "00e70861-8d16-4781-8be1-7c4c201c0e4e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TwPJWXinXcp2jptNBpcsBP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1945,
      "cache_creation_input_tokens": 2051,
      "cache_read_input_tokens": 73774,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2051
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

_source line 41 · 2026-05-25T16:30:04.856Z_

<details><summary>↩ Tool result · `toolu_014jANrxj3v6UsFHK3PBB6Ju`</summary>

```text
108	\subsection{F6--F7: Interventions}
109	\label{sec:f6}
110	
111	\paragraph{F6: $\dt{=}1$ imagination eliminates CIVO.}
112	Exp\_008e\_v3 restricts imagination to $\dt{=}1$ while retaining the trained embedding. Across four unique seeds (s0, s1, s2, s5), none exhibits CIVO onset (peak NVE ${\leq}0.6\times$, well below the $1.5\times$ threshold). Three of four seeds achieve $64$--$94\%$ of baseline (eval $597$--$877$; mean $775.6$); seed~0 exhibits CIVO-unrelated learning stagnation (eval $148$, $16\%$ baseline; Figure~\ref{fig:multiple_pathways}). This confirms that multi-step imagination---not the trained embedding alone---is necessary for CIVO induction.
113	
114	\begin{figure}[t]
115	\centering
116	\includegraphics[width=0.75\columnwidth]{figures/paper/fig6_multiple_pathways.pdf}
117	\caption{Contrasting dynamics. \textbf{Left:} 008d (CIVO), value explosion with entropy decrease. \textbf{Right:} 008e\_v3 s2 ($\dt{=}1$ imagination), no CIVO onset (NVE $0.5\times$, eval $64\%$ baseline).}
118	\label{fig:multiple_pathways}
119	\end{figure}
120	\paragraph{F7: Full-pathway gradient stopping shows mixed results.}
121	Full-SGS (exp\_018) detaches all non-KL gradients from $e_{\dt}$. Seed~1 shows partial mitigation (eval 448.3, NVE $1.66\times$); seed~2 collapses (0/2 elimination; Appendix~\ref{sec:sgs_gradient_analysis}). Cross-environment validation on Cheetah (010b, NVE $8.27$--$108.52\times$) confirms CIVO generalization; full-SGS yields 0/3 elimination. Removing the embedding eliminates CIVO on Cheetah (024b, NVE $< 0.2\times$).
122	
123	\paragraph{Targeted obs-decoder-only SGS confirms pathway redundancy.}
124	Obs-decoder-only SGS (exp\_025/026) achieves 1/6 CIVO prevention (1/4 Walker, 0/2 Cheetah; Table~\ref{tab:intervention_hierarchy}), not meaningfully different from full-pathway SGS (0/3). CIVO operates through redundant gradient channels: blocking any single pathway shifts co-adaptation to the remaining ones (Appendix~\ref{sec:seed_divergence}).
125	
126	\begin{table}[t]
127	\centering
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "52e21e73-279d-43d9-8d4c-34fcfbeba5f3",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/results.tex",
      "content": "\\subsection{F6--F7: Interventions}\n\\label{sec:f6}\n\n\\paragraph{F6: $\\dt{=}1$ imagination eliminates CIVO.}\nExp\\_008e\\_v3 restricts imagination to $\\dt{=}1$ while retaining the trained embedding. Across four unique seeds (s0, s1, s2, s5), none exhibits CIVO onset (peak NVE ${\\leq}0.6\\times$, well below the $1.5\\times$ threshold). Three of four seeds achieve $64$--$94\\%$ of baseline (eval $597$--$877$; mean $775.6$); seed~0 exhibits CIVO-unrelated learning stagnation (eval $148$, $16\\%$ baseline; Figure~\\ref{fig:multiple_pathways}). This confirms that multi-step imagination---not the trained embedding alone---is necessary for CIVO induction.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/paper/fig6_multiple_pathways.pdf}\n\\caption{Contrasting dynamics. \\textbf{Left:} 008d (CIVO), value explosion with entropy decrease. \\textbf{Right:} 008e\\_v3 s2 ($\\dt{=}1$ imagination), no CIVO onset (NVE $0.5\\times$, eval $64\\%$ baseline).}\n\\label{fig:multiple_pathways}\n\\end{figure}\n\\paragraph{F7: Full-pathway gradient stopping shows mixed results.}\nFull-SGS (exp\\_018) detaches all non-KL gradients from $e_{\\dt}$. Seed~1 shows partial mitigation (eval 448.3, NVE $1.66\\times$); seed~2 collapses (0/2 elimination; Appendix~\\ref{sec:sgs_gradient_analysis}). Cross-environment validation on Cheetah (010b, NVE $8.27$--$108.52\\times$) confirms CIVO generalization; full-SGS yields 0/3 elimination. Removing the embedding eliminates CIVO on Cheetah (024b, NVE $< 0.2\\times$).\n\n\\paragraph{Targeted obs-decoder-only SGS confirms pathway redundancy.}\nObs-decoder-only SGS (exp\\_025/026) achieves 1/6 CIVO prevention (1/4 Walker, 0/2 Cheetah; Table~\\ref{tab:intervention_hierarchy}), not meaningfully different from full-pathway SGS (0/3). CIVO operates through redundant gradient channels: blocking any single pathway shifts co-adaptation to the remaining ones (Appendix~\\ref{sec:seed_divergence}).\n\n\\begin{table}[t]\n\\centering",
      "numLines": 20,
      "startLine": 108,
      "totalLines": 218
    }
  }
}
```

</details>

---


### Assistant

_source line 42_

<details><summary>Logged reasoning block</summary>

```text
OK, so results.tex F6 says:
- "four unique seeds (s0, s1, s2, s5)"
- "none exhibits CIVO onset (peak NVE ≤0.6×)"
- "Three of four seeds achieve 64-94% of baseline (eval 597-877; mean 775.6)"
- "seed~0 exhibits CIVO-unrelated learning stagnation (eval 148, 16% baseline)"

Wait, this mentions 4 seeds: s0, s1, s2, s5. But the task says:


- s0: eval 869.9, NVE 0.6, no CIVO
- s1 (exp_080): eval 876.7, NVE 0.6, no CIVO
- s2 (exp_081): eval 597.1, NVE 0.5, no CIVO
- 3-seed mean: 781.2 ± 159.5 (84% baseline)

There's a discrepancy here—the document mentions s5 with eval 148 showing learning stagnation, but the task only lists three seeds with a mean of 781.2, whereas the document says the mean for three of four seeds is 775.6. I need to figure out which seeds are actually being reported and reconcile these numbers. Looking at the task requirements more carefully, it specifies updating results for three seeds (s0, s1, s2) with their respective metrics, but the current code results show four seeds including s5. There's a discrepancy here—s5 appears in the new results with a drastically different evaluation score (148 vs the old 853.1), so I need to clarify whether s5 should be included in the update or if it's an anomaly that needs investigation. I'm noticing a contradiction between what the task states and what results.tex says about seed 0. The task claims s0 has eval 869.9, but results.tex indicates s0 exhibits learning stagnation with eval 148 and a 16% baseline. Let me carefully re-read the task to resolve this discrepancy. Looking at the seed values more carefully, I see the task description lists s0 with eval 869.9, but results.tex shows s0 with eval 148 and stagnation. The task's s0 value actually matches results.tex's s5. It seems the task was given only the three successful seeds, excluding the stagnation case, so I should treat results.tex as the authoritative source with all four seeds: s0 at eval 148 with stagnation, s1 at 876.7, s2 at 597.1, and s5 at 869.9. Looking at the seed mapping more carefully, it seems s0 might be a new addition while s1, s2, and s5 are either re-runs or carry-overs from the old experiment. For the appendix table, I should include all four seeds from results.tex to maintain consistency, even though the task description only mentions three. I'm noticing a discrepancy in the seed numbering—the task lists s0 with eval 869.9, but results.tex shows s5 at that value while s0 is much lower at 148. This suggests the task might be using a different seed indexing scheme, possibly renumbering s5 as s0, or it could be from an earlier version of results.tex before the data was finalized. I need to check if results.tex provides any clarification on the figure references to resolve this inconsistency.

Looking at the figure caption in results.tex, I can see it mentions s2 with eval around 64% of baseline, which aligns with the task's s2 value of 597.1 (roughly 64% of 915.7). Given this alignment, I think the safest approach is to use the three seeds the task explicitly specifies for the NVE analysis tables, while ensuring the appendix results table matches what's documented in results.tex. The task reports a 3-seed mean of 781.2, which matches the calculation using seeds s0, s1, and s2 from the task data, but results.tex shows 775.6—suggesting they might be using a different subset of the four seeds. Let me verify which three seeds produce that 775.6 figure. I see the issue now—results.tex's mean of 775.6 must be using an older value for s5 (853.1 instead of the current 869.9), which suggests the document was only partially updated. Rather than chase down these inconsistencies, I should focus on the actual task: make the appendix consistent with results.tex by using the four seeds it references (s0, s1, s2, s5) for the complete results table, and then use just the three high-performing seeds (s1, s2, s5) for the NVE sensitivity analysis since that's what's relevant there. I'm noticing a discrepancy between what the old results table shows and what the task specifies. The old data lists six seeds with various NVE values and outcomes, but the task only provides three seeds with specific eval and NVE numbers. I need to reconcile this—the task data should take precedence, so I'll use s0 (eval 869.9, NVE 0.6), s1 (eval 876.7, NVE 0.6), and s2 (eval 597.1, NVE 0.5) for the appendix, even though results.tex currently references a different set of four seeds. I need to reconcile the seed numbering between the task description and results.tex. The task mentions "s0" with eval 869.9, but results.tex shows s5 with a similar evaluation score, so there's a mismatch in how the seeds are labeled. Since results.tex is already been updated, I'll treat it as the authoritative source and map out all four seeds with their corresponding metrics from that file.

For the outcome labels, I'm noticing that "Healthy" doesn't fit seed s0 which has eval ~148 (only 16% of baseline 915.7), so that should be marked as stagnation instead. I'll keep the table straightforward using the task data as my primary reference, and if there's a fourth seed from results.tex that differs, I can add a footnote to clarify the discrepancy rather than overcomplicating the main table. Generating table rows... the NVE raw table will have 11 entries total, but I'm swapping out the 008e_v3 seeds with different ones—replacing the original four seeds with s0, s1, s2, and s5, all estimated at 0.6 or 0.5. This shifts which cases count as positive versus negative in the analysis. Now I'm ranking all the samples by their scores and calculating AUROC by counting how many negatives fall below each positive—006 beats all 9 negatives while 008d beats 8 of them, giving me an AUROC of 17/18.

For B2, the separation is perfect since the lowest positive (1.62) sits above the highest negative (1.00), so AUROC is 1.0. Now I'm recomputing the sensitivity and specificity tables across all thresholds for the B1 group to see how accuracy changes as I vary the decision boundary. Looking at the threshold performance metrics for B2, I can see that a threshold of 1.2 achieves perfect accuracy with all positives correctly identified and no false positives. I need to verify these calculations with Python, and then update the description since the sample composition has changed with the new seeds—the count remains four but they're different instances, so I should remove the IRD reference. Let me finalize the approach and compute the confidence intervals.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "0b5566e5-eda2-430d-b1c7-bdf113d70a0a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DxeSLHqsvttEzTCjmwZvip",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2946,
      "cache_read_input_tokens": 75825,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2946
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

_source line 43_

Let me compute the exact CIs for n=11 (with 4 new 008e_v3 seeds instead of 3).

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "10e98ffb-cf92-420d-a7ef-c38a58951aa2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DxeSLHqsvttEzTCjmwZvip",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2946,
      "cache_read_input_tokens": 75825,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2946
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

_source line 44_

<details open><summary>🔧 Tool call — Bash · `toolu_0125Ph4cH8CAhUa2ncMyXU6p`</summary>

```json
{
  "command": "python3 -c \"\nfrom scipy.stats import beta as beta_dist\n\ndef cp_ci(k, n, alpha=0.05):\n    if k == 0: lo = 0.0\n    else: lo = beta_dist.ppf(alpha/2, k, n-k+1)\n    if k == n: hi = 1.0\n    else: hi = beta_dist.ppf(1-alpha/2, k+1, n-k)\n    return lo, hi\n\n# n=11, 4 008e_v3 seeds (s0,s1,s2,s5), matching results.tex\n# B1: n_pos=2 (006, 008d), n_neg=9\n# B2: n_pos=4 (006, 059, 008d, 009b), n_neg=7\n\nprint('=== B1 (n=11, n_pos=2, n_neg=9) ===')\n# AUROC\nauroc = (9+8)/(2*9)\nprint(f'AUROC = {auroc:.3f}')\nthresholds = [\n    ('>=1.0', 2, 3, 0, 6),\n    ('>=1.2', 2, 2, 0, 7),\n    ('>=1.5', 2, 2, 0, 7),\n    ('>=1.7', 2, 1, 0, 8),\n    ('>=2.0', 2, 1, 0, 8),\n    ('>=3.9', 2, 1, 0, 8),\n]\nfor name, tp, fp, fn, tn in thresholds:\n    n = tp+fp+fn+tn\n    acc = (tp+tn)/n\n    prec = tp/(tp+fp) if (tp+fp)>0 else 0\n    rec = tp/(tp+fn) if (tp+fn)>0 else 0\n    f1 = 2*prec*rec/(prec+rec) if (prec+rec)>0 else 0\n    lo, hi = cp_ci(tp+tn, n)\n    print(f'{name}: TP={tp} FP={fp} FN={fn} TN={tn} | Acc={acc*100:.1f}% [{lo*100:.1f},{hi*100:.1f}] | P={prec*100:.1f}% R={rec*100:.0f}% F1={f1*100:.1f}%')\n\nprint()\nprint('=== B2 (n=11, n_pos=4, n_neg=7) ===')\nprint('AUROC = 1.000')\nthresholds = [\n    ('>=1.0', 4, 1, 0, 6),\n    ('>=1.2', 4, 0, 0, 7),\n    ('>=1.5', 4, 0, 0, 7),\n    ('>=1.7', 3, 0, 1, 7),\n    ('>=2.0', 3, 0, 1, 7),\n    ('>=3.9', 3, 0, 1, 7),\n]\nfor name, tp, fp, fn, tn in thresholds:\n    n = tp+fp+fn+tn\n    acc = (tp+tn)/n\n    prec = tp/(tp+fp) if (tp+fp)>0 else 0\n    rec = tp/(tp+fn) if (tp+fn)>0 else 0\n    f1 = 2*prec*rec/(prec+rec) if (prec+rec)>0 else 0\n    lo, hi = cp_ci(tp+tn, n)\n    print(f'{name}: TP={tp} FP={fp} FN={fn} TN={tn} | Acc={acc*100:.1f}% [{lo*100:.1f},{hi*100:.1f}] | P={prec*100:.1f}% R={rec*100:.0f}% F1={f1*100:.1f}%')\n\n# Now B2 full (n=17 -> n=17 since 4 old seeds -> 4 new seeds)\n# Actually, old n=17 had Walker(15) + Cheetah(2)\n# Old Walker 15 included 4 008e_v3 seeds (s1,s2,s3,s4)\n# New Walker 15: replace s1,s2,s3,s4 with s0,s1,s2,s5 -> still 15 Walker\n# Total still n=17!\n# Old positives: 9 (including 008e_v3_s3)\n# New positives: 8 (removed 008e_v3_s3)\n# Old negatives: 8 (including 008e_v3_s2 as FP)\n# New negatives: 9 (008e_v3 s0,s1,s2,s5 all negative)\n\nprint()\nprint('=== B2 full (n=17, n_pos=8, n_neg=9) ===')\nprint('AUROC = 1.000 (perfect separation)')\nthresholds = [\n    ('>=1.0', 8, 2, 0, 7),  # FP: 001(1.0) and 009c_s3(1.04)\n    ('>=1.2', 8, 0, 0, 9),\n    ('>=1.5', 8, 0, 0, 9),\n    ('>=1.7', 7, 0, 1, 9),  # FN: 009b(1.62)\n    ('>=2.0', 7, 0, 1, 9),\n    ('>=3.9', 6, 0, 2, 9),\n]\nfor name, tp, fp, fn, tn in thresholds:\n    n = tp+fp+fn+tn\n    acc = (tp+tn)/n\n    prec = tp/(tp+fp) if (tp+fp)>0 else 0\n    rec = tp/(tp+fn) if (tp+fn)>0 else 0\n    f1 = 2*prec*rec/(prec+rec) if (prec+rec)>0 else 0\n    lo, hi = cp_ci(tp+tn, n)\n    print(f'{name}: TP={tp} FP={fp} FN={fn} TN={tn} | Acc={acc*100:.1f}% [{lo*100:.1f},{hi*100:.1f}] | P={prec*100:.1f}% R={rec*100:.0f}% F1={f1*100:.1f}%')\n\"\n",
  "description": "Compute sensitivity analysis numbers for n=11 and n=17"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "48f47998-4761-407f-af50-4eea17d6a225",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DxeSLHqsvttEzTCjmwZvip",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2946,
      "cache_read_input_tokens": 75825,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2946
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

_source line 45 · 2026-05-25T16:32:14.607Z_

<details><summary>↩ Tool result · `toolu_0125Ph4cH8CAhUa2ncMyXU6p`</summary>

```text
=== B1 (n=11, n_pos=2, n_neg=9) ===
AUROC = 0.944
>=1.0: TP=2 FP=3 FN=0 TN=6 | Acc=72.7% [39.0,94.0] | P=40.0% R=100% F1=57.1%
>=1.2: TP=2 FP=2 FN=0 TN=7 | Acc=81.8% [48.2,97.7] | P=50.0% R=100% F1=66.7%
>=1.5: TP=2 FP=2 FN=0 TN=7 | Acc=81.8% [48.2,97.7] | P=50.0% R=100% F1=66.7%
>=1.7: TP=2 FP=1 FN=0 TN=8 | Acc=90.9% [58.7,99.8] | P=66.7% R=100% F1=80.0%
>=2.0: TP=2 FP=1 FN=0 TN=8 | Acc=90.9% [58.7,99.8] | P=66.7% R=100% F1=80.0%
>=3.9: TP=2 FP=1 FN=0 TN=8 | Acc=90.9% [58.7,99.8] | P=66.7% R=100% F1=80.0%

=== B2 (n=11, n_pos=4, n_neg=7) ===
AUROC = 1.000
>=1.0: TP=4 FP=1 FN=0 TN=6 | Acc=90.9% [58.7,99.8] | P=80.0% R=100% F1=88.9%
>=1.2: TP=4 FP=0 FN=0 TN=7 | Acc=100.0% [71.5,100.0] | P=100.0% R=100% F1=100.0%
>=1.5: TP=4 FP=0 FN=0 TN=7 | Acc=100.0% [71.5,100.0] | P=100.0% R=100% F1=100.0%
>=1.7: TP=3 FP=0 FN=1 TN=7 | Acc=90.9% [58.7,99.8] | P=100.0% R=75% F1=85.7%
>=2.0: TP=3 FP=0 FN=1 TN=7 | Acc=90.9% [58.7,99.8] | P=100.0% R=75% F1=85.7%
>=3.9: TP=3 FP=0 FN=1 TN=7 | Acc=90.9% [58.7,99.8] | P=100.0% R=75% F1=85.7%

=== B2 full (n=17, n_pos=8, n_neg=9) ===
AUROC = 1.000 (perfect separation)
>=1.0: TP=8 FP=2 FN=0 TN=7 | Acc=88.2% [63.6,98.5] | P=80.0% R=100% F1=88.9%
>=1.2: TP=8 FP=0 FN=0 TN=9 | Acc=100.0% [80.5,100.0] | P=100.0% R=100% F1=100.0%
>=1.5: TP=8 FP=0 FN=0 TN=9 | Acc=100.0% [80.5,100.0] | P=100.0% R=100% F1=100.0%
>=1.7: TP=7 FP=0 FN=1 TN=9 | Acc=94.1% [71.3,99.9] | P=100.0% R=88% F1=93.3%
>=2.0: TP=7 FP=0 FN=1 TN=9 | Acc=94.1% [71.3,99.9] | P=100.0% R=88% F1=93.3%
>=3.9: TP=6 FP=0 FN=2 TN=9 | Acc=88.2% [63.6,98.5] | P=100.0% R=75% F1=85.7%
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "cb5796b4-eb87-44cf-aea4-581512635736",
  "tool_use_result": {
    "stdout": "=== B1 (n=11, n_pos=2, n_neg=9) ===\nAUROC = 0.944\n>=1.0: TP=2 FP=3 FN=0 TN=6 | Acc=72.7% [39.0,94.0] | P=40.0% R=100% F1=57.1%\n>=1.2: TP=2 FP=2 FN=0 TN=7 | Acc=81.8% [48.2,97.7] | P=50.0% R=100% F1=66.7%\n>=1.5: TP=2 FP=2 FN=0 TN=7 | Acc=81.8% [48.2,97.7] | P=50.0% R=100% F1=66.7%\n>=1.7: TP=2 FP=1 FN=0 TN=8 | Acc=90.9% [58.7,99.8] | P=66.7% R=100% F1=80.0%\n>=2.0: TP=2 FP=1 FN=0 TN=8 | Acc=90.9% [58.7,99.8] | P=66.7% R=100% F1=80.0%\n>=3.9: TP=2 FP=1 FN=0 TN=8 | Acc=90.9% [58.7,99.8] | P=66.7% R=100% F1=80.0%\n\n=== B2 (n=11, n_pos=4, n_neg=7) ===\nAUROC = 1.000\n>=1.0: TP=4 FP=1 FN=0 TN=6 | Acc=90.9% [58.7,99.8] | P=80.0% R=100% F1=88.9%\n>=1.2: TP=4 FP=0 FN=0 TN=7 | Acc=100.0% [71.5,100.0] | P=100.0% R=100% F1=100.0%\n>=1.5: TP=4 FP=0 FN=0 TN=7 | Acc=100.0% [71.5,100.0] | P=100.0% R=100% F1=100.0%\n>=1.7: TP=3 FP=0 FN=1 TN=7 | Acc=90.9% [58.7,99.8] | P=100.0% R=75% F1=85.7%\n>=2.0: TP=3 FP=0 FN=1 TN=7 | Acc=90.9% [58.7,99.8] | P=100.0% R=75% F1=85.7%\n>=3.9: TP=3 FP=0 FN=1 TN=7 | Acc=90.9% [58.7,99.8] | P=100.0% R=75% F1=85.7%\n\n=== B2 full (n=17, n_pos=8, n_neg=9) ===\nAUROC = 1.000 (perfect separation)\n>=1.0: TP=8 FP=2 FN=0 TN=7 | Acc=88.2% [63.6,98.5] | P=80.0% R=100% F1=88.9%\n>=1.2: TP=8 FP=0 FN=0 TN=9 | Acc=100.0% [80.5,100.0] | P=100.0% R=100% F1=100.0%\n>=1.5: TP=8 FP=0 FN=0 TN=9 | Acc=100.0% [80.5,100.0] | P=100.0% R=100% F1=100.0%\n>=1.7: TP=7 FP=0 FN=1 TN=9 | Acc=94.1% [71.3,99.9] | P=100.0% R=88% F1=93.3%\n>=2.0: TP=7 FP=0 FN=1 TN=9 | Acc=94.1% [71.3,99.9] | P=100.0% R=88% F1=93.3%\n>=3.9: TP=6 FP=0 FN=2 TN=9 | Acc=88.2% [63.6,98.5] | P=100.0% R=75% F1=85.7%",
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

_source line 46_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the numbers I need. Let me also check that the n=17 is correct:

Old n=17 had Walker(15) + Cheetah(2) = 17.
Old Walker 15 included 4 008e_v3 seeds (s1,s2,s3,s4).

New: replace those 4 with 4 new seeds (s0,s1,s2,s5) → still 15 Walker, still n=17.

Wait, the old data had "four 008e_v3 seeds" in the n=11 analysis (s1,s2,s3,s4). 

I need to figure out whether the n=17 analysis used just those 4 seeds or if s5 was added later—the n=11 sensitivity analysis explicitly mentions s1 through s4, so s5 might have only appeared in the full results table. If n=17 also had just 4 seeds and I'm replacing them with 4 new ones, the count stays the same. So swapping out s3 for s5 flips one positive result to negative, bringing the n=17 table to 8 positives and 9 negatives. Now looking at the B2 full results, there's complete separation between the positive and negative NVE values—the highest negative is 1.04 while the lowest positive is 1.53.

But I need to verify whether s5 is actually part of the original n=17 set. The complete results table shows five old seeds (s1-s5), but the NVE analysis only mentions four 008e_v3 seeds, suggesting s5 was added later. If that's the case, then the n=17 set only had s1-s4, and I need to figure out what the fifth Walker experiment is to account for the 15 total Walker entries.

Looking at the non-008e_v3 Walker experiments that appear in n=11, I can identify seven of them (006, 059, 008d, 009b, 001, 008f, 008a), which combined with the four 008e_v3 seeds gives 11. The n=17 adds six more experiments—two Cheetah and four additional Walker—and those four Walker experiments are likely the multi-seed variants like 008d_s3, 008d_s4, 008f_s4, and 009c_s3 rather than something like 068, which was probably a later factorial reproduction.

Regardless of the exact composition, the B2 full table calculation should work out, though I should also consider whether the ≥1.0 threshold needs adjustment for the n=17 analysis. Looking at the accuracy metric, the old dataset with n=17 achieved 88.2%, while the new configuration at the ≥1.0 threshold shows TP=8 with FP=2, confirming that 001 and 009c_s3 are the false positives in both cases.

At the ≥1.5 threshold, the old analysis had one false positive (008e_v3_s2 with NVE 3.78), but that's eliminated in the new data, giving me TP=8 and FP=0. The numbers check out consistently across both thresholds.

Now I need to systematically work through all the edits, starting with the comprehensive n=56 analysis.  I'm noticing that "exp_008e_v3_subsample" appears to be a configuration variant of 008e_v3, which means it's also invalid with the bug fix—reducing the false positives from 3 to 2. Similarly, line 270 references another invalid 008e_v3 variant. For the n=56 dataset with n_pos=24 and n_neg=32, I need to remove the 008e_v3 false positive and recalculate the metrics accordingly. The accuracy will improve with fewer false positives and more true negatives. For the n=56 analysis, the AUROC was 0.990, but I'll need to regenerate that metric along with the F1 score and the ROC curve figures since the underlying data has changed. Let me now systematically go through the file and make all the necessary edits, starting from the top and organizing them by their location. I'm counting up all the edits needed across the document—looks like at least 23 changes scattered throughout. Let me group the independent ones together to work more efficiently. I should also add a footnote for the new s0 seed about stagnation, and I need to check if there's room after the existing footnotes around line 111 where the last one ends.

Looking at the old table structure, I notice that 008e_v3 s2 had a dagger marker and s3 had gray shading, but the new rows won't need either since there's no CIVO or false positive data. I also need to remove the gray row coloring from the old s3 entry. Now I have a clear picture of what needs to change—let me start making these edits, tackling the independent ones in parallel.

Updating the complete results table... Generating markdown table... Generating markdown table... I'm clarifying whether the stagnation case (s0) should be included as a factorial experiment—it's a mitigation experiment like the others, just with poor performance, so it belongs in the table. The four new seeds (s0, s1, s2, s5) replace the old ones, keeping the total at 11 entries.

Now I'm pulling the performance metrics from the last computation to populate the results table, looking at the threshold-based statistics for true positives, false positives, false negatives, and true negatives across different confidence levels. Looking at the B2 threshold results, I'm seeing that ≥1.2 and ≥1.5 both achieve perfect performance with 100% accuracy and F1 score, while higher thresholds start degrading the recall. Generating classification metrics...
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "5e043fe7-2f5c-4482-811f-3b426ceb67b2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DCDpRKxrBTQYSYtHFA7JrX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9659,
      "cache_read_input_tokens": 78771,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9659
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

_source line 47_

Now I have all the computed values. Let me start making the edits systematically, top to bottom through the file. I'll batch independent edits.

**Edit 1**: Replace 5 old 008e_v3 rows with 4 new rows in the complete results table.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "3bdc804f-315a-4987-be0c-832dcb7006e5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DCDpRKxrBTQYSYtHFA7JrX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9659,
      "cache_read_input_tokens": 78771,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9659
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

_source line 48_

<details open><summary>🔧 Tool call — Edit · `toolu_016M4jMe9esT7zetXETYCQFX`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
  "old_string": "008e\\_v3 s1 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.94$\\times$ & Healthy \\\\\n008e\\_v3 s2$^\\dagger$ & Mitigation & trn & ON & 15 & 137.0 @105K & 3.78$\\times$ & Non-CIVO collapse \\\\\n\\rowcolor{gray!15}\n008e\\_v3 s3 & Mitigation & trn & ON & 15 & 92.7 @105K & 4.02$\\times$ & CIVO collapse \\\\\n008e\\_v3 s4 & Mitigation & trn & ON & 15 & 899.3 @105K & 0.99$\\times$ & Healthy \\\\\n008e\\_v3 s5 & Mitigation & trn & ON & 15 & 853.1 @105K & 0.61$\\times$ & Healthy \\\\",
  "new_string": "008e\\_v3 s0 & Mitigation & trn & ON & 15 & 148.0 @105K & 0.60$\\times$ & No CIVO$^j$ \\\\\n008e\\_v3 s1 & Mitigation & trn & ON & 15 & 876.7 @105K & 0.60$\\times$ & Healthy \\\\\n008e\\_v3 s2 & Mitigation & trn & ON & 15 & 597.1 @105K & 0.50$\\times$ & Healthy \\\\\n008e\\_v3 s5 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.60$\\times$ & Healthy \\\\"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "9871ce81-5739-4e8b-9541-8a3d49864955",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DCDpRKxrBTQYSYtHFA7JrX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9659,
      "cache_read_input_tokens": 78771,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9659
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

_source line 49 · 2026-05-25T16:33:58.052Z_

<details><summary>↩ Tool result · `toolu_016M4jMe9esT7zetXETYCQFX`</summary>

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
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "bd788396-3c7c-4edf-9ac6-e467a97c0d21",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
    "oldString": "008e\\_v3 s1 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.94$\\times$ & Healthy \\\\\n008e\\_v3 s2$^\\dagger$ & Mitigation & trn & ON & 15 & 137.0 @105K & 3.78$\\times$ & Non-CIVO collapse \\\\\n\\rowcolor{gray!15}\n008e\\_v3 s3 & Mitigation & trn & ON & 15 & 92.7 @105K & 4.02$\\times$ & CIVO collapse \\\\\n008e\\_v3 s4 & Mitigation & trn & ON & 15 & 899.3 @105K & 0.99$\\times$ & Healthy \\\\\n008e\\_v3 s5 & Mitigation & trn & ON & 15 & 853.1 @105K & 0.61$\\times$ & Healthy \\\\",
    "newString": "008e\\_v3 s0 & Mitigation & trn & ON & 15 & 148.0 @105K & 0.60$\\times$ & No CIVO$^j$ \\\\\n008e\\_v3 s1 & Mitigation & trn & ON & 15 & 876.7 @105K & 0.60$\\times$ & Healthy \\\\\n008e\\_v3 s2 & Mitigation & trn & ON & 15 & 597.1 @105K & 0.50$\\times$ & Healthy \\\\\n008e\\_v3 s5 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.60$\\times$ & Healthy \\\\",
    "originalFile": "% --- APPENDIX ---\n\n\\section{Complete Experimental Results}\n\\label{sec:complete_results}\n\nTable~\\ref{tab:complete_results} reports all 45 experimental configurations. The main text (Table~\\ref{tab:main_results}) presents the subset most relevant to the causal argument; this table includes the additional variable-rate configurations (006, 007, 005), multi-seed factorial runs (009b, 008d\\_s3, 008d\\_s4), SGS interventions (018), cross-environment seeds (010b\\_s0), and mitigation experiments (008e\\_v3).\n\n\\begin{table*}[t]\n\\centering\n\\caption{Complete experimental results. NVE reports peak $\\nve$ in the 35K+ window (\\S\\ref{sec:metrics}). CIVO-positive seeds are shaded; $\\dagger$\\,marks a false positive (non-CIVO collapse with elevated NVE).}\n\\label{tab:complete_results}\n\\scriptsize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{dt\\_emb} & \\textbf{Sub} & \\textbf{H} & \\textbf{Eval@final} & \\textbf{NVE} & \\textbf{Outcome} \\\\\n\\midrule\n001 & Baseline ($\\dt{=}1$, s1) & --- & --- & 15 & 915.7 @105K & 1.00$\\times$ & Healthy \\\\\n001 s2 & Baseline ($\\dt{=}1$, s2) & --- & --- & 15 & 443.5 @105K & ---$^e$ & Healthy \\\\\n\\rowcolor{gray!15}\n006 & Fixed $\\dt{=}2$ & trn & ON & 15 & 132.9 @65K & 4.83$\\times$ & Collapsed \\\\\n007 & Fixed $\\dt{=}4$ & trn & ON & 15 & 152.5 @55K & --- & Collapsed \\\\\n005 & Learned gate & adaptive & OFF & 15 & 98.8 @145K & --- & Collapsed \\\\\n\\midrule\n\\rowcolor{gray!15}\n008d & Factorial (s1) & trn & ON & 8 & 82.8 @55K$^\\heartsuit$ & 4.12$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n009b & Factorial (s2) & trn & ON & 8 & 267.9 @105K & 1.62$\\times$ & Transient CIVO \\\\\n\\rowcolor{gray!15}\n008d\\_s3 & Factorial (s3) & trn & ON & 8 & 268$^\\diamond$ @105K & 1.53$\\times$ & Late-onset collapse \\\\\n\\rowcolor{gray!15}\n008d\\_s4 & Factorial (s4) & trn & ON & 8 & 63.6 @105K & 4.62$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n059 & Factorial (s5) & trn & ON & 8 & 95.8 @105K & 4.72$\\times$ & Collapse$^\\dagger$ \\\\\n\\rowcolor{gray!15}\n068 & Factorial repro (s1) & trn & ON & 8 & 39.1 @105K & 4.12$\\times$ & Full collapse \\\\\n008f & No dt\\_emb (s1) & --- & ON & 8 & 503.0 @105K & 0.97$\\times$ & Healthy \\\\\n008f s4 & No dt\\_emb (s4) & --- & ON & 8 & 289.3 @105K & 0.76$\\times$ & Healthy \\\\\n009c s3 & No dt\\_emb (s3) & --- & ON & 8 & 311.9 @105K & 1.04$\\times$ & Healthy \\\\\n008a & Unexposed emb & exp$^a$ & OFF & 15 & 777.7 @105K & 0.93$\\times$ & Healthy \\\\\n008a\\_s1 & Unexposed emb & exp$^a$ & OFF & 15 & 630.9 @105K & 0.83$\\times$ & Healthy \\\\\n008a\\_s2 & Unexposed emb & exp$^a$ & OFF & 15 & 899.4 @105K & 0.89$\\times$ & Healthy \\\\\n008a\\_s3 & Unexposed emb & exp$^a$ & OFF & 15 & 855.9 @105K & --- & Healthy \\\\\n015b & Frozen emb & frz$^b$ & ON & 8 & 204.2 @105K & 1.45$\\times$ & Grad.\\ starvation \\\\\n022b & Frozen emb + Gumbel gate & frz$^b$ & ON & 8 & 300.7 @105K & 0.63$\\times$ & No CIVO \\\\\n042 & Frozen emb (dedicated) & frz$^b$ & ON & 8 & 612.0 @105K & 0.19$\\times$ & Healthy \\\\\n047 & Frozen emb (s1) & frz$^b$ & ON & 8 & 144.2 @215K & 1.71$\\times$ & Transient (self-corr.) \\\\\n057 & Frozen emb (s2) & frz$^b$ & ON & 8 & 123.9 @215K & 1.88$\\times$ & Transient (self-corr.) \\\\\n067 & Frozen emb (s0) & frz$^b$ & ON & 8 & 281.5 @105K & 0.19$\\times$ & Healthy \\\\\n\\midrule\n018 s1 & Full-SGS & trn$^\\ddagger$ & ON & 8 & \\sgseval{} @105K & \\sgsnve{}$\\times$$^*$ & Partial mitig.\\ (CIVO+) \\\\\n\\rowcolor{gray!15}\n018 s2 & Full-SGS & trn$^\\ddagger$ & ON & 8 & 40.8 @105K & --- & Collapsed \\\\\n008e\\_v3 s1 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.94$\\times$ & Healthy \\\\\n008e\\_v3 s2$^\\dagger$ & Mitigation & trn & ON & 15 & 137.0 @105K & 3.78$\\times$ & Non-CIVO collapse \\\\\n\\rowcolor{gray!15}\n008e\\_v3 s3 & Mitigation & trn & ON & 15 & 92.7 @105K & 4.02$\\times$ & CIVO collapse \\\\\n008e\\_v3 s4 & Mitigation & trn & ON & 15 & 899.3 @105K & 0.99$\\times$ & Healthy \\\\\n008e\\_v3 s5 & Mitigation & trn & ON & 15 & 853.1 @105K & 0.61$\\times$ & Healthy \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cross-environment validation}} \\\\\n\\rowcolor{gray!15}\n010b & Cheetah Run & trn & ON & 8 & 51.7 @105K & 8.27$\\times$ & Collapsed \\\\\n\\rowcolor{gray!15}\n010b\\_s0 & Cheetah Run & trn & ON & 8 & 0.83 @105K & 108.52$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n021 & Cheetah Run & trn$^\\ddagger$ & ON & 8 & 221.5 @105K & 9.94$\\times$$^d$ & Transient CIVO (self-corr.) \\\\\n024b s0 & Cheetah Run & --- & ON & 8 & 96.5 @105K & $<$0.20$\\times$ & Healthy \\\\\n024b s1 & Cheetah Run & --- & ON & 8 & 77.3 @105K & 0.10$\\times$ & Healthy \\\\\n008a\\_ch s0 & Cheetah Run & exp$^a$ & OFF & 15 & 532.4 @105K & 1.08$\\times$ & Healthy \\\\\n008a\\_ch s1 & Cheetah Run & exp$^a$ & OFF & 15 & 504.4 @105K & 1.29$\\times$ & Healthy \\\\\n077 & Cheetah baseline (s0) & --- & --- & 15 & 448.1 @105K & 1.00$\\times$ & Healthy \\\\\n\\rowcolor{gray!15}\n078 & Cheetah trigger (s0) & trn & ON & 8 & 119.5 @105K & 4.10$\\times$ & Onset (self-corr.) \\\\\n\\rowcolor{gray!15}\n019b & PickCube-v1 & trn & ON & 8 & 26.64 @200K & 3.78$\\times$$^c$ & Transient onset \\\\\n054 & PickCube-v1 & frz$^b$ & ON & 8 & --- & 8.81$\\times$$^h$ & Env.\\ transient (ctrl) \\\\\n049 & StackCube-v1 & trn & ON & 8 & 34.9 @212K & 5.05$\\times$$^f$ & Env.\\ transient \\\\\n052 & StackCube-v1 & trn & ON & 8 & --- & 4.67$\\times$$^f$ & Env.\\ transient \\\\\n051 & StackCube-v1 & frz$^b$ & ON & 8 & 30.7 @155K & 4.30$\\times$$^f$ & Env.\\ transient (ctrl) \\\\\n050 & PegInsertionSide-v1 & trn & ON & 8 & 20.86 @212K & 10.05$\\times$$^g$ & Env.\\ dynamics \\\\\n053 & PegInsertionSide-v1 & frz$^b$ & ON & 8 & 5.89 & 8.10$\\times$$^g$ & Env.\\ dynamics (ctrl) \\\\\n055 & PegInsertionSide-v1 & trn & ON & 8 & 11.44 @212K & 3.08$\\times$$^g$ & Env.\\ dynamics \\\\\n056 & PegInsertionSide-v1 & frz$^b$ & ON & 8 & 4.37 @212K & 11.32$\\times$$^g$ & Env.\\ dynamics (ctrl) \\\\\n046 & Cheetah Run & frz$^b$ & ON & 8 & 150.5 @215K & 1.35$\\times$ & No CIVO \\\\\n058 & Cheetah Run & frz$^b$ & ON & 8 & 80.46 @215K & 0.78$\\times$ & No CIVO \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cartpole Swingup}} \\\\\n060 & Cartpole baseline (3 seeds) & --- & --- & 15 & 557.0 @105K$^i$ & --- & Healthy \\\\\n061 & Cartpole trigger (3 seeds) & trn & ON & 8 & 236.3 @105K$^i$ & --- & No CIVO \\\\\n062 & Cartpole control (3 seeds) & --- & ON & 8 & 244.8 @105K$^i$ & --- & No CIVO \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize\ntrn = trained ($d{=}32$, subsample ON);\ntrn$^\\ddagger$ = full-pathway SGS (all non-KL gradients detached);\nexp$^a$ = trained, subsample OFF;\nfrz$^b$ = frozen ($d{=}32$, \\texttt{requires\\_grad=False});\n--- = removed ($d{=}0$).\\\\\n$^*$ Seed 1 only: peak NVE with transient exceedances (1.60$\\times$ at 35K, 1.66$\\times$ at 95K); self-correcting, no sustained escalation. Seed 2 collapsed.\\\\\n$^\\diamond$ Transitional; train returns still declining (peak 470 to 139 over final 8K steps). Collapse had not reached equilibrium at 105K.\\\\\n$^\\dagger$ NVE self-corrected ($4.72\\times$ $\\to$ $1.22\\times$) but policy did not recover (eval 10.5\\% of baseline).\\\\\n$^c$ NVE normalized against exp\\_019a\\_v2 (vanilla DreamerV3 on PickCube-v1).\\\\\n$^d$ Peak NVE $9.94\\times$ at 45K (transient, self-correcting to $<$1$\\times$ by 55K); final eval 221.5.\\\\\n$^e$ Not used for NVE normalization; reported for completeness. Seed~1 (eval 915.7) is the NVE reference baseline.\\\\\n$^f$ StackCube transient: frozen control (exp\\_051, peak $4.30\\times$ at 42.5K) matches trained (exp\\_049/052), self-correcting by 82.5K; environment-specific, not $\\dt$-embedding-driven.\\\\\n$^g$ PegInsertion environment dynamics: seed~0 trained peaks at $10.05\\times$ (82.5K); seed~1 trained (exp\\_055) peaks at $3.08\\times$ (92.5K), final $0.50\\times$ at 212.5K; seed~1 frozen (exp\\_056) peaks at $11.32\\times$ (82.5K), final $1.19\\times$ at 212.5K. Frozen final exceeds trained final; ordering is seed-dependent, ruling out $\\dt$-embedding causation.\\\\\n$^h$ PickCube environment transient: frozen control peak $8.81\\times$ at 62.5K, self-correcting to $0.55\\times$ at 72.5K; matches trained (exp\\_019b) trajectory.\\\\\n$^\\heartsuit$ Evaluated at 55K steps due to early termination of exp\\_008d; extended run (exp\\_009e) reached 131.08 at 105K.\\\\\n$^i$ Cartpole: exp\\_060 reports seed~2 eval only; exp\\_061/062 report 3-seed mean.\\par}\n\\end{table*}\n\n\\begin{table}[h]\n\\centering\n\\caption{Cross-domain CIVO reproducibility. ``$\\dt$-emb-dep.'' indicates trained peaks consistently exceed frozen at matched timepoints across seeds.}\n\\label{tab:cross_domain}\n\\footnotesize\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Domain} & \\textbf{Environment} & \\textbf{Trained} & \\textbf{Frz ctrl} & \\textbf{$\\dt$-emb-dep.\\ CIVO} \\\\\n\\midrule\nLocomotion & Walker Walk & 5/5 & 0/3 & Yes (NVE $1.53$--$4.72\\times$) \\\\\nLocomotion & Cheetah Run & 2/2 & 0/2 & Yes (NVE $8.27$--$108.5\\times$) \\\\\nManipulation & StackCube-v1 & 0/2 & 0/1 & No (frozen$\\approx$trained) \\\\\nManipulation & PegInsertionSide & 0/2 & 0/2 & No (seed-dep.\\ ordering) \\\\\nManipulation & PickCube-v1 & 0/1 & 0/1 & No (frozen spike similar) \\\\\n\\midrule\nLocomotion & Cartpole Swingup & 0/3 & 0/3 & No (single-joint) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cartpole Swingup.} Cartpole Swingup (single-DoF locomotion) serves as a cross-environment control. Three seeds of the CIVO-trigger configuration (exp\\_061: trained $e_{\\dt}$, subsample ON, $H{=}8$, $\\dt{=}2$) and three seeds of the no-embedding control (exp\\_062) both produce zero CIVO onset. Despite using the hyperparameter combination that triggers collapse in all 10 tested multi-joint locomotion seeds (Walker/Cheetah), the single-joint Cartpole shows no CIVO, confirming the phenomenon requires multi-joint dynamics where temporal abstraction amplifies the reward fidelity gap.\n\n\\section{NVE Threshold Sensitivity Analysis}\n\\label{sec:appendix_sensitivity}\n\nWe report the full sensitivity analysis for the NVE diagnostic framework introduced in Section~\\ref{sec:results}. The main text reports Task~B2 (any CIVO detection, $\\nve \\geq 1.5\\times$). Here we additionally present Task~B1, which restricts the positive class to \\emph{sustained} CIVO, specifically experiments exhibiting persistent, accelerating value overestimation that progresses to performance collapse. Transient CIVO cases (e.g., exp~009b, which self-corrects after a brief excursion above the threshold) are classified as negative in B1.\n\n\\subsection{Per-Experiment NVE Values}\n\nTable~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\\_v3 seeds and exp\\_059). Experiments are sorted by descending NVE. Experiment 008e\\_v3\\_s2 exhibits elevated NVE ($3.78\\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\\_v3\\_s3 exhibits CIVO with NVE $4.02\\times$ despite $\\Delta t{=}1$ imagination.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\\ = transient CIVO with self-correction.}\n\\label{tab:nve_raw}\n\\small\n\\begin{tabular}{@{}lrccc@{}}\n\\toprule\nExperiment & NVE & Mechanism & B1 & B2 \\\\\n\\midrule\n006          & 4.83 & sustained CIVO & $+$ & $+$ \\\\\n059          & 4.72 & self-correcting CIVO & $-$ & $+$ \\\\\n008d         & 4.12 & sustained CIVO & $+$ & $+$ \\\\\n008e\\_v3\\_s3 & 4.02 & CIVO           & $+$ & $+$ \\\\\n008e\\_v3\\_s2 & 3.78 & IRD (non-CIVO) & $-$ & $-$ \\\\\n009b         & 1.62 & transient CIVO & $-$ & $+$ \\\\\n001          & 1.00 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s4 & 0.99 & non-CIVO       & $-$ & $-$ \\\\\n008f         & 0.97 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s1 & 0.94 & non-CIVO       & $-$ & $-$ \\\\\n008a         & 0.93 & non-CIVO       & $-$ & $-$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Multi-Threshold Classification Performance}\n\nTable~\\ref{tab:sensitivity_b1} reports Task~B1 classification metrics across six NVE thresholds. Task~B1 achieves $\\text{AUROC} = 0.917$ because exp\\_059 (NVE${=}4.72\\times$, self-correcting CIVO, B1-negative) ranks above two sustained-CIVO positives ($4.12\\times$, $4.02\\times$), breaking the perfect rank separation that held before its inclusion. The optimal threshold lies in the interval $(3.78, 4.02]$; we report $\\geq 3.9\\times$ as a representative value (accuracy $10/11 = 90.9\\%$). Table~\\ref{tab:sensitivity_b2} provides the corresponding analysis for Task~B2 ($\\text{AUROC} = 0.967$, imperfect separation due to 008e\\_v3\\_s2).\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B1}: Sustained CIVO detection sensitivity analysis ($n_{\\text{pos}}=3$, $n_{\\text{neg}}=8$, $n=11$, $\\text{AUROC}=0.917$). All confidence intervals are two-sided Clopper-Pearson exact binomial ($\\alpha=0.05$). $^\\dagger$Optimal threshold in $(3.78, 4.02]$; exp\\_059 (NVE${=}4.72\\times$, B1-negative) is the sole false positive.}\n\\label{tab:sensitivity_b1}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 3 & 4 & 0 & 4 & 63.6\\% \\; [30.8, 89.1] & 42.9\\% & 100\\% & 60.0\\% \\\\\n$\\geq 1.2\\times$ & 3 & 3 & 0 & 5 & 72.7\\% \\; [39.0, 94.0] & 50.0\\% & 100\\% & 66.7\\% \\\\\n$\\geq 1.5\\times$ & 3 & 3 & 0 & 5 & 72.7\\% \\; [39.0, 94.0] & 50.0\\% & 100\\% & 66.7\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.7\\times$ & 3 & 2 & 0 & 6 & 81.8\\% \\; [48.2, 97.7] & 60.0\\% & 100\\% & 75.0\\% \\\\\n$\\geq 2.0\\times$ & 3 & 2 & 0 & 6 & 81.8\\% \\; [48.2, 97.7] & 60.0\\% & 100\\% & 75.0\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 3.9\\times^\\dagger$ & 3 & 1 & 0 & 7 & 90.9\\% \\; [58.7, 99.8] & 75.0\\% & 100\\% & 85.7\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B2}: Any CIVO detection sensitivity analysis ($n_{\\text{pos}}=5$, $n_{\\text{neg}}=6$, $n=11$, $\\text{AUROC}=0.967$). The single false positive at $\\geq 1.5\\times$ is 008e\\_v3\\_s2 (IRD mechanism, not CIVO). The $1.5\\times$ threshold (highlighted) maximizes F1 while maintaining perfect recall.}\n\\label{tab:sensitivity_b2}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 5 & 2 & 0 & 4 & 81.8\\% \\; [48.2, 97.7] & 71.4\\% & 100\\% & 83.3\\% \\\\\n$\\geq 1.2\\times$ & 5 & 1 & 0 & 5 & 90.9\\% \\; [58.7, 99.8] & 83.3\\% & 100\\% & 90.9\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.5\\times$ & 5 & 1 & 0 & 5 & 90.9\\% \\; [58.7, 99.8] & 83.3\\% & 100\\% & 90.9\\% \\\\\n$\\geq 1.7\\times$ & 4 & 1 & 1 & 5 & 81.8\\% \\; [48.2, 97.7] & 80.0\\% & 80.0\\% & 80.0\\% \\\\\n$\\geq 2.0\\times$ & 4 & 1 & 1 & 5 & 81.8\\% \\; [48.2, 97.7] & 80.0\\% & 80.0\\% & 80.0\\% \\\\\n$\\geq 3.9\\times$ & 4 & 0 & 1 & 6 & 90.9\\% \\; [58.7, 99.8] & 100\\% & 80.0\\% & 88.9\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B2 (full evaluation set)}: Any CIVO detection across two environments ($n_{\\text{pos}}=9$, $n_{\\text{neg}}=8$, $n=17$, $\\text{AUROC}=0.972$). Includes Walker Walk (15 configurations) and Cheetah Run (2 configurations).}\n\\label{tab:sensitivity_b2_full}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 9 & 2 & 0 & 6 & 88.2\\% \\; [63.6, 98.5] & 81.8\\% & 100\\% & 90.0\\% \\\\\n$\\geq 1.2\\times$ & 9 & 1 & 0 & 7 & 94.1\\% \\; [71.3, 99.9] & 90.0\\% & 100\\% & 94.7\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.5\\times$ & 9 & 1 & 0 & 7 & 94.1\\% \\; [71.3, 99.9] & 90.0\\% & 100\\% & 94.7\\% \\\\\n$\\geq 1.7\\times$ & 7 & 1 & 2 & 7 & 82.4\\% \\; [56.6, 96.2] & 87.5\\% & 77.8\\% & 82.4\\% \\\\\n$\\geq 2.0\\times$ & 7 & 1 & 2 & 7 & 82.4\\% \\; [56.6, 96.2] & 87.5\\% & 77.8\\% & 82.4\\% \\\\\n$\\geq 3.9\\times$ & 7 & 0 & 2 & 8 & 88.2\\% \\; [63.6, 98.5] & 100\\% & 77.8\\% & 87.5\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\subsection{Threshold Recommendation}\n\nFor the main diagnostic (Task~B2), we recommend $\\nve \\geq 1.5\\times$ as the operating threshold for three reasons:\n\n\\begin{enumerate}[nosep,leftmargin=*]\n\\item \\textbf{Maximum recall.} The $1.5\\times$ threshold achieves 100\\% recall, detecting all five CIVO cases including the transient case (009b, $\\nve = 1.62\\times$). Raising the threshold to $1.7\\times$ loses 009b, dropping recall to 80.0\\%.\n\\item \\textbf{Best F1.} At $1.5\\times$, F1 = 90.9\\%, the highest among all tested thresholds for B2. The single false positive (008e\\_v3\\_s2) is mechanistically identifiable as IRD rather than CIVO.\n\\item \\textbf{Sensitivity--specificity tradeoff.} Lower thresholds ($1.0\\times$) add false positives without gaining true positives. Higher thresholds ($\\geq 1.7\\times$) sacrifice recall without eliminating the 008e\\_v3\\_s2 false positive (which requires $\\tau > 3.78$).\n\\end{enumerate}\n\nFor Task~B1 (sustained CIVO only), the optimal threshold $\\nve \\geq 3.9\\times$ achieves $10/11$ accuracy ($90.9\\%$, 95\\% CI: [58.7\\%, 99.8\\%]); the sole false positive is exp\\_059 (NVE${=}4.72\\times$, self-correcting CIVO classified as B1-negative).\n\n\\subsection{Expanded ROC Analysis}\n\\label{sec:roc_analysis}\n\nThe original $n{=}17$ analysis (Tables~\\ref{tab:sensitivity_b1}--\\ref{tab:sensitivity_b2_full}) predates the SGS, RAVE, and TCN experiments. We extend the NVE diagnostic evaluation to $n{=}56$ configurations spanning all tested interventions. Figure~\\ref{fig:nve_roc} shows the receiver operating characteristic curve with 95\\% bootstrap confidence interval (10{,}000 resamples).\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.7\\columnwidth]{../../artifacts/figures/nve_roc_curve.pdf}\n\\caption{NVE ROC curve ($n{=}56$ configurations, AUROC${=}0.990$, comprehensive validation). The preset $\\nve \\geq 1.5\\times$ operating point (star) achieves TPR${=}1.00$, FPR${=}0.09$, accuracy${=}53/56$, F1${=}0.941$. Three false positives arise from non-CIVO value overestimation: mitigation transient VE spike (008e\\_v3 subsample, $1.93\\times$) and frozen embedding transients (047, $1.71\\times$; 057, $1.88\\times$). Threshold calibrated and validated post-hoc; cross-architecture validation deferred.}\n\\label{fig:nve_roc}\n\\end{figure}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.7\\columnwidth]{../../artifacts/figures/nve_threshold_prf.pdf}\n\\caption{Precision, Recall, and F1 as a function of NVE threshold ($n{=}56$ configurations). Peak F1${=}0.941$ at $\\tau{=}1.5\\times$, where recall remains perfect ($1.00$) and precision${=}0.889$. The plateau of high F1 across $\\tau \\in [1.5, 1.7]$ indicates robustness to threshold selection.}\n\\label{fig:nve_prf}\n\\end{figure}\n\nWe label a configuration as CIVO-positive if and only if (i)~it uses a trained $\\dt$-embedding with multi-rate data exposure, and (ii)~NVE exceeds $1.5\\times$ with co-occurring entropy collapse. Configurations exhibiting high NVE through other mechanisms (gradient truncation side effects, value anchor pollution) are labeled non-CIVO.\n\nThe three false positives (FPR${=}0.18$) are mechanistically distinct from CIVO: (1)~RAVE anchor pollution (exp\\_028, the EMA anchor becomes inflated, producing overestimation through a different pathway); (2)~obs-decoder SGS-induced value distortion (exp\\_025 seed~2, blocking observation decoder gradients damages the RSSM latent space); (3)~IRD eval-driven collapse (exp\\_008e\\_v3 seed~2, actor entropy \\emph{increases} with evaluation collapse, mechanistically distinct from CIVO's entropy \\emph{decrease}). All three produce NVE $> 1.5\\times$ through non-CIVO mechanisms, indicating that the NVE diagnostic detects value overestimation broadly rather than CIVO specifically---a feature rather than a limitation for practitioners monitoring deployment health. The closest sub-threshold case (008f seed~4, NVE${=}1.41\\times$) lacks $\\dt$-conditioning entirely ($d{=}0$); its elevated NVE reflects transient value noise that self-corrects without the positive feedback loop characteristic of CIVO. The closest above-threshold positive (008d seed~3, NVE${=}1.53\\times$) exhibits the full CIVO causal chain: trained $\\dt$-embedding, entropy decrease, and evaluation collapse to 14\\% of baseline.\n\n\\paragraph{Comprehensive validation ($n{=}56$).}\nExpanding the evaluation set to all classifiable experiments yields $n{=}56$ ($n_{\\text{pos}}{=}24$, $n_{\\text{neg}}{=}32$), spanning Walker Walk, Cheetah Run, and multiple intervention configurations (SGS, TCN, dual-critic, frozen embedding). At the $1.5\\times$ threshold: AUROC${=}0.990$, precision${=}0.889$, recall${=}1.000$, F1${=}0.941$, accuracy${=}53/56$. The three false positives are: exp\\_008e\\_v3\\_subsample ($1.93\\times$, mitigation config with transient VE spike), exp\\_047 ($1.71\\times$, frozen embedding transient), and exp\\_057 ($1.88\\times$, frozen embedding transient). All 24 CIVO-positive configurations are correctly detected (FN${=}0$), with CIVO-positive NVE ranging from $1.53\\times$ (008d seed~3, late-onset) to $70.64\\times$ (010b seed~0, Cheetah). The substantial increase in sample size from $n{=}32$ to $n{=}56$ strengthens confidence in the $1.5\\times$ threshold as a robust diagnostic boundary.\n\n\\subsection{NVE Normalization Robustness}\n\\label{sec:nve_robustness}\n\nTo assess sensitivity to baseline seed choice, we extend the single-seed baseline (seed~1, eval 915.7 at 105K) to three additional seeds trained to 505K steps (Table~\\ref{tab:baseline_seeds}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Walker Walk baseline seeds at 105K and 505K steps.}\n\\label{tab:baseline_seeds}\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Seed} & \\textbf{Eval@105K} & \\textbf{Eval@505K} & \\textbf{ve@65K} & \\textbf{ve@105K} \\\\\n\\midrule\ns1 & 915.7 & 970.4 & 0.563 & 0.656 \\\\\ns2 & 443.5 & 945.7 & 0.898 & 0.742 \\\\\ns3 & 869.0 & 947.7 & --- & 0.664 \\\\\ns4 & 922.8 & 938.9 & --- & 0.624 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nSeed~2 exhibits slow convergence (eval 443.5 at 105K, recovering to 945.7 by 512K), confirming non-pathological slow convergence rather than seed failure. Its elevated $v/e$ ratio at 65K (0.898 vs.\\ 0.563 for seed~1) reflects the low evaluation denominator rather than pathological value overestimation. Using seed~2 as the sole normalization reference systematically deflates NVE values, causing two marginal CIVO-positive configurations (008d seed~3, peak NVE $1.53\\times$; 009b seed~2, peak NVE $1.62\\times$) to fall below the $1.5\\times$ threshold. Core CIVO cases (peak NVE $> 3\\times$) remain correctly classified under all baseline seeds.\n\nSingle-seed normalization (s1) yields AUROC $= 0.933$ and accuracy 7/8 (87.5\\%) on the Walker subset. Four-seed mean normalization yields AUROC $= 0.867$ and accuracy 6/8 (75.0\\%): the boundary case exp\\_009b flips from $\\nve = 1.62\\times$ (s1) to $1.23\\times$ (4-seed mean), because its peak occurs at 45K when the s1 $v/e$ ratio (0.331) is well below the 4-seed mean (0.436). All high-NVE configurations remain correctly classified (006: $4.84\\times \\to 4.52\\times$; 008d: $4.12\\times \\to 3.54\\times$). The $1.5\\times$ threshold thus correctly identifies all strong CIVO cases regardless of baseline choice; sensitivity is confined to configurations within 10\\% of the threshold.\n\n\\paragraph{Normalization conventions.} Walker NVE is normalized against the single-seed baseline (seed~1, exp\\_001, 505K steps). Cheetah NVE is normalized against a 5-seed mean baseline (seeds~0--4, each run to ${\\sim}$210K steps). The differing seed counts reflect available baseline data; both provide sufficient coverage of the respective experimental windows (Walker: 210K analysis window; Cheetah: 105K analysis window).\n\n\\paragraph{Limitations.} The initial $n{=}11$ analysis had wide Clopper-Pearson confidence intervals (e.g., 90.9\\% accuracy, 95\\% CI [58.7\\%, 99.8\\%]). The comprehensive evaluation ($n{=}56$, AUROC${=}0.990$, F1${=}0.941$; Figure~\\ref{fig:nve_roc}) substantially tightens these bounds. Table~\\ref{tab:sensitivity_b2_full} reports the $n{=}17$ two-environment core evaluation. Cross-architecture validation is deferred to future work.\n\n\\subsection{Leave-One-Environment-Out Cross-Validation}\n\\label{sec:nve_loeo}\n\nTo assess whether $\\theta{=}1.5\\times$ generalizes beyond the in-sample evaluation, we perform leave-one-environment-out (LOEO) cross-validation across Walker ($n{=}15$), Cheetah ($n{=}5$), and PickCube ($n{=}2$). For each fold, we hold out all experiments from one environment, select the optimal accuracy-maximizing threshold range on the remaining training set, and evaluate the fixed $\\theta{=}1.5\\times$ on the held-out environment.\n\n\\begin{table}[h]\n\\centering\n\\caption{Leave-one-environment-out cross-validation of NVE threshold $\\theta=1.5\\times$.\nFor each fold, the threshold is validated on an environment whose data was \\emph{not} used\nto select $\\theta$. The optimal threshold range on each training set is reported;\n$\\theta=1.5$ falls within the optimal range in all three folds.}\n\\label{tab:nve_loeo}\n\\begin{tabular}{lccccc}\n\\toprule\nHeld-out & $N_{\\text{train}}$ & $N_{\\text{test}}$ & $\\theta_{\\text{opt}}$ range & Test Accuracy & Test AUROC \\\\\n\\midrule\nPickCube & 20 & 2 & $(1.45,\\, 1.53]$ & 2/2 (1.000) & 1.000 \\\\\nCheetah  & 17 & 5 & $(1.45,\\, 1.53]$ & 5/5 (1.000) & 1.000 \\\\\nWalker   &  7 & 15 & $(1.00,\\, 3.78)$ & 14/15 (0.933) & 0.963 \\\\\n\\midrule\n\\textbf{Mean} & — & — & — & \\textbf{0.978} & \\textbf{0.988} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe threshold $\\theta{=}1.5\\times$ falls within the optimal accuracy range for all three training folds: $(1.45, 1.53]$ when Walker data is available, and the wider $(1.00, 3.78)$ when training on Cheetah$+$PickCube only (where CIVO and non-CIVO NVE values are well-separated). The single cross-validation error is exp\\_008e\\_v3 seed~2 (Walker), an IRD collapse mechanistically distinct from CIVO (\\S\\ref{sec:roc_analysis}). Mean held-out accuracy is 0.978 and mean AUROC is 0.988, confirming that $\\theta{=}1.5\\times$ generalizes across environments without retuning.\nPickCube fold confidence intervals remain wide (Clopper-Pearson 95\\% CI: $[0.158, 1.000]$) due to $N_{\\text{test}}{=}2$.\n\n\\subsection{Leave-One-Config-Out Cross-Validation}\n\\label{sec:nve_loco}\n\n\\paragraph{Leave-One-Config-Out Cross-Validation.}\nTo rule out threshold overfitting to any particular experimental configuration, we perform leave-one-config-out (LOCO) cross-validation over $K{=}12$ configuration groups (e.g., \\texttt{008d\\_civo\\_trigger}, \\texttt{frozen\\_dt\\_emb}, \\texttt{tcn}; $n{=}56$ total). Each fold holds out all experiments from one configuration, selects the F1-maximizing threshold on the remaining $K{-}1$ groups, and evaluates on the held-out group.\n\nIn $10/12$ folds, the training-optimal threshold falls within $\\pm 0.05$ of $\\theta{=}1.5\\times$ (mean $1.61 \\pm 0.23$, range $[1.47, 2.12]$). The two folds selecting a higher threshold ($\\theta{=}2.1$; \\texttt{008d\\_civo\\_trigger} and \\texttt{tcn}, both predominantly CIVO-positive) perform \\emph{worse} on their held-out sets than $\\theta{=}1.5$ (accuracy $0.78$/$0.88$ vs.\\ $1.00$/$1.00$), confirming that the fixed threshold generalizes better than per-fold optimization in these cases. Cross-validated accuracy at $\\theta{=}1.5$ is $53/56 = 94.6\\%$, identical to the in-sample result, with train AUROC consistently high across folds ($0.988 \\pm 0.003$). The three misclassifications are the same mechanistically distinct false positives identified in \\S\\ref{sec:roc_analysis}: two frozen-embedding transients (exp\\_047, exp\\_057) and one mitigation-config transient (exp\\_008e\\_v3\\_subsample). No CIVO-positive configuration is missed in any fold (FN${=}0$ across all 12 folds).\n\n% --- APPENDIX B: Factorial Ablation Details ---\n\n\\section{Factorial Ablation Details}\n\\label{sec:appendix_factorial}\n\nThis appendix provides the full factorial ablation results summarized in \\S\\ref{sec:f3f5_summary} of the main text.\n\n\\paragraph{Embedding gradient analysis.}\nTable~\\ref{tab:three_way_emb} isolates embedding \\emph{trainability} as the necessary condition for CIVO by comparing four gradient conditions under otherwise identical configurations ($H{=}8$, subsample ON, $\\dt{=}2$ imagination).\n\n\\begin{table}[h]\n\\centering\n\\caption{$\\dt$-embedding gradient conditions on Walker Walk. Any gradient pathway updating $e_{\\dt}$ is sufficient to induce CIVO; freezing or removing the embedding dramatically reduces severity.}\n\\label{tab:three_way_emb}\n\\footnotesize\n\\begin{tabular}{lccccl}\n\\toprule\nCondition & Grad flow & Exp(s) & NVE peak & Eval & CIVO \\\\\n\\midrule\nTrained & all & 008d, 059 & $1.53$--$4.72\\times$ & 64--268 & 5/5 \\\\\nReward detach & obs+KL only & 044 & $4.45\\times$ & 44$\\to$538$^\\dagger$ & 1/1 \\\\\nFull SGS & KL only & 018 & $1.66\\times$ & 448 & 1/1$^*$ \\\\\nFrozen & none & 042, 015b, 047, 057 & $0.19$--$1.88\\times$$^\\ddagger$ & 204--612 & 2/4 \\\\\nRemoved & N/A & 008f & $0.97$--$1.41\\times$ & 307--503 & 0/3 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$Full-SGS seed~1 (NVE $1.66\\times$); seed~2 collapsed. $^\\dagger$Self-corrected at ${\\sim}175$K (eval 44$\\to$538, 59\\% baseline; 224K run). $^\\ddagger$Exp\\_047 (NVE $1.71\\times$) and Exp\\_057 (NVE $1.88\\times$): both transient, self-correcting within 20K steps.\\par}\n\\end{table}\n\n\\paragraph{Controlled three-way causal ablation.}\nExperiments 067--069 provide a minimal causal ablation on Walker Walk (seed${=}1$), varying \\emph{only} the $\\dt$-embedding treatment while holding all other hyperparameters fixed ($H{=}8$, subsample ON, $\\dt{=}2$ imagination). Table~\\ref{tab:causal_ablation} shows that trained $\\dt$-embedding is necessary and sufficient for CIVO: freezing the embedding (gradient flow blocked, embedding weights still present) eliminates CIVO as completely as removing the embedding ($d{=}0$), ruling out the alternative hypothesis that embedding \\emph{presence} alone causes CIVO. Combined with all prior seeds, trained $\\dt$-embedding triggers CIVO in 10/10 multi-joint locomotion seeds (8 Walker, 2 Cheetah) versus 0/8 controls (Fisher exact $p < 0.0001$).\n\n\\begin{table}[h]\n\\centering\n\\caption{Three-way causal ablation (Walker Walk, seed${=}1$). Only the $\\dt$-embedding treatment varies; all other configuration is identical. Trained embedding triggers CIVO; frozen and removed do not.}\n\\label{tab:causal_ablation}\n\\footnotesize\n\\begin{tabular}{llccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Embedding} & \\textbf{NVE peak} & \\textbf{Eval final} & \\textbf{CIVO} \\\\\n\\midrule\n\\rowcolor{gray!15}\n068 & Trained ($d{=}32$) & $6.57\\times$ & 39.1 & Yes (alert @85K) \\\\\n067 & Frozen ($d{=}32$, \\texttt{req\\_grad=F}) & $0.40\\times$ & 281.5 & No \\\\\n069 & Removed ($d{=}0$) & $0.66\\times$ & 237.8 & No \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe reward-detach condition (exp\\_044, \\texttt{reward\\_dt\\_emb\\_detach=True}) uses a backward hook to block reward-head gradients from reaching $e_{\\dt}$, complementing the framework-level Reward SGS (exp\\_016e). Both yield the same directional result---CIVO onset not prevented---ruling out implementation artifacts. Exp\\_044 exhibits delayed CIVO onset (${\\sim}95$K vs.\\ typical $25$--$35$K), consistent with reduced but non-zero gradient pressure on $e_{\\dt}$. Over a full 224K run, exp\\_044 self-corrects: eval recovers from 44 (95K) to 538 (215K, 59\\% baseline), but this recovery is incomplete compared to spontaneous recovery without gradient intervention (exp\\_045: 868, 95\\% baseline). The lower asymptote suggests that selectively disrupting gradient flow may create optimization difficulties beyond CIVO itself.\n\nTable~\\ref{tab:factorial_design} summarizes the experimental configurations.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Factorial design. Each row specifies one experimental configuration. \\textbf{Emb}: $\\dt$-embedding mode. \\textbf{Sub}: temporal subsampling. \\textbf{H}: imagination horizon. \\textbf{Imag $\\dt$}: temporal resolution used during imagination.}\n\\label{tab:factorial_design}\n\\small\n\\setlength{\\tabcolsep}{3.5pt}\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\n\\textbf{ID} & \\textbf{Purpose} & \\textbf{Emb} & \\textbf{Sub} & \\textbf{H} & \\textbf{Imag $\\dt$} \\\\\n\\midrule\n001 & Reference baseline & --- & --- & 15 & 1 \\\\\n006 & Fixed $\\dt{=}2$ & trn & on & 15 & 2 \\\\\n007 & Fixed $\\dt{=}4$ & trn & on & 15 & 4 \\\\\n\\midrule\n008a & Unexposed emb ctrl & exp$^a$ & off & 15 & 2 \\\\\n008c & Horizon control & exp$^a$ & off & 8 & 2 \\\\\n008d & Collapse condition & trn & on & 8 & 2 \\\\\n008e\\_v3 & $\\dt{=}1$ imag control & trn & on & 15 & 1 \\\\\n008f & Causal ablation & --- & on & 8 & 2 \\\\\n\\midrule\n015b & Frozen-emb ctrl & frz$^b$ & on & 8 & 2 \\\\\n016e & Stop-grad (reward) & trn$^\\dagger$ & on & 8 & 2 \\\\\n018 & Full-SGS & trn$^\\ddagger$ & on & 8 & 2 \\\\\n\\midrule\n005 & Learned gate & adaptive & off & 15 & learned \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{-2pt}\n{\\raggedright\\footnotesize\ntrn = trained ($d{=}32$, exposed to $\\dt{>}1$ data via subsample ON);\nexp$^a$ = trained ($d{=}32$) but never exposed to $\\dt{>}1$ data (subsample OFF);\nfrz$^b$ = frozen random projection ($d{=}32$, \\texttt{requires\\_grad=False});\n--- = removed ($d{=}0$).\\\\\n$^\\dagger$ \\texttt{reward\\_dt\\_emb\\_detach=True}; $^\\ddagger$ all non-KL gradients to \\texttt{dt\\_emb} detached.\\par}\n\\end{table}\n\n\\subsection{F3: Unexposed Temporal Embedding Suppresses Value Drift}\n\\label{sec:f3}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig3_factorial_grid.pdf}\n\\caption{Factorial isolation of CIVO trigger. Only the combination of trained $e_{\\dt}$ and multi-rate data (upper-left cell) produces pathological NVE. Neither factor alone is sufficient.}\n\\label{fig:factorial_grid}\n\\end{figure}\n\nThe empirical finding that trained embedding \\emph{plus} multi-rate exposure jointly predict CIVO rests on two complementary controls that each remove one factor while holding the other constant.\n\n\\paragraph{Evidence A: exposure is necessary (exp\\_008a).}\nExp\\_008a uses a trained embedding ($d{=}32$, gradients enabled) that is never exposed to $\\dt{>}1$ transitions during world-model training (subsample OFF). Despite sharing the same embedding architecture as exp\\_008d, its NVE remains in the $0.83$--$0.93\\times$ range across 3 seeds (105K steps). Performance follows two V-shaped recovery cycles, reaching 777.7 at 105K (85\\% of baseline). The critical factor is not the embedding's capacity to represent temporal information, but its adaptation to multi-rate data that enables precise but inaccurate $\\dt{>}1$ state predictions within the RSSM.\n\nThis contrasts with exp\\_006 (trained $e_{\\dt}$, subsample ON, $H{=}15$), where NVE accelerates from $1.61\\times$ at 45K to $2.31\\times$ at 55K before catastrophic collapse to 132.9 at 65K. Both experiments use identical trained embeddings ($d{=}32$, gradients enabled) and $H{=}15$, differing only in whether the world model sees $\\dt{>}1$ transitions during training. This confirms that multi-rate data exposure, not embedding architecture, is the operative variable.\n\n\\paragraph{Evidence B: trainability is necessary (exp\\_015b).}\nExp\\_015b uses a frozen random-projection embedding ($d{=}32$, \\texttt{requires\\_grad=False}, subsample ON, $H{=}8$), the same multi-rate data regime as exp\\_008d, but with a non-trainable temporal signal. Despite full exposure to $\\dt{>}1$ transitions, the NVE peaks at $1.45\\times$ at 55K but does not sustain escalation: it retreats to $0.65\\times$ by 65K and settles at $0.42\\times$ by 105K (trajectory: $0.81 \\rightarrow 1.26 \\rightarrow 1.45 \\rightarrow 0.65 \\rightarrow 1.05 \\rightarrow 0.47 \\rightarrow 0.39 \\rightarrow 0.42$). The transient peak approaches but does not exceed the $1.5\\times$ CIVO threshold, and critically, the ratio self-corrects rather than exhibiting the monotonic escalation seen in trained-embedding runs. Final evaluation reaches only 204.2 at 105K, low but through a qualitatively different failure mode than CIVO. Actor loss approaches zero (gradient starvation; see \\S\\ref{sec:pathways}), the frozen embedding provides no useful gradient signal for temporal adaptation.\n\nThe contrast with exp\\_008d is stark: under identical data conditions (subsample ON, $H{=}8$), the trained embedding drives NVE to $4.12\\times$ with sustained monotonic escalation ($1.78 \\rightarrow 1.71 \\rightarrow 2.09 \\rightarrow 4.12$) and precedes full collapse (eval 82.8), while the frozen embedding peaks transiently at $1.45\\times$ before self-correcting to $0.42\\times$, a qualitative difference between sustained and transient overestimation. This demonstrates that a $\\dt$-embedding must be able to \\emph{co-adapt} with RSSM dynamics to produce the systematic reward-prediction bias that drives CIVO; a static random projection, regardless of its exposure to multi-rate data, cannot create this bias.\n\nTogether, these two controls establish that in all tested configurations, CIVO occurs only with the \\emph{joint} presence of (i)~a trainable embedding that can co-adapt with RSSM dynamics, and (ii)~multi-rate training data that drives this co-adaptation toward biased temporal predictions. Neither factor alone is sufficient.\n\nCross-environment validation on Cheetah Run replicates the empirical pattern: trained $e_{\\dt}$ precedes CIVO in both tested seeds (exp\\_010b, 2 seeds, NVE $8.27$--$108.52\\times$, collapse to 51.7/0.83) while removing the embedding eliminates it (exp\\_024b, 2 seeds, NVE $<0.2\\times$, eval 96.5/77.3). Freezing the embedding on Cheetah (exp\\_046, NVE${=}1.35\\times$ vs.\\ trained $70.64\\times$, a $52\\times$ reduction) further confirms that embedding trainability, not architecture, drives CIVO. This extends the sufficiency finding from Walker Walk to a second locomotion environment with qualitatively different dynamics (6-joint vs.\\ 2-joint).\n\n\\begin{table}[ht]\n\\centering\n\\small\n\\caption{Causal isolation: $e_{\\dt}$ configuration $\\times$ multi-rate data exposure. The combination of trained embedding and multi-rate exposure is the sole predictor of CIVO in tested configurations. Neither factor alone is sufficient.}\n\\label{tab:causal_matrix}\n\\begin{tabular}{lcc}\n\\toprule\n& Multi-rate data (\\textsc{on}) & Single-rate data (\\textsc{off}) \\\\\n\\midrule\nTrained $e_{\\dt}$ & exp\\_008d: \\textbf{CIVO} & exp\\_008a: healthy \\\\\n & NVE 4.12$\\times$, collapse & NVE 0.93$\\times$ \\\\\n\\midrule\nFrozen $e_{\\dt}$ & exp\\_015b: grad.\\ starvation & --- \\\\\n & peak NVE 1.45$\\times$ (transient) & \\\\\n\\midrule\nRemoved $e_{\\dt}$ & exp\\_008f: no CIVO & --- \\\\\n & NVE $\\leq$0.97$\\times$ & \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOnly the upper-left cell (trained embedding with multi-rate exposure) precedes CIVO (Table~\\ref{tab:causal_matrix}). This 2$\\times$2 structure establishes that both factors are jointly sufficient in tested configurations.\n\n\\subsection{F4: Degradation Scales Monotonically with \\texorpdfstring{$\\dt$}{dt}}\n\\label{sec:f4}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig5_dt_amplification.pdf}\n\\caption{Peak evaluation return as a function of imagination $\\dt$. Performance degrades monotonically: $\\dt{=}1$ (915.7) $>$ $\\dt{=}2$ (485.3, $-47\\%$) $>$ $\\dt{=}4$ (176.9, $-81\\%$).}\n\\label{fig:dt_amplification}\n\\end{figure}\n\nThe magnitude of degradation scales monotonically with the imagination step size (Figure~\\ref{fig:dt_amplification}). From the $\\dt{=}1$ baseline (915.7 at 105K), fixed $\\dt{=}2$ (exp\\_006) achieves a peak of only 485.3 ($-47\\%$), and fixed $\\dt{=}4$ (exp\\_007) peaks at 176.9 ($-81\\%$). This monotonic relationship is consistent with compounding model error: larger temporal gaps amplify the RSSM's prediction inaccuracy at each imagination step, and these errors accumulate across the rollout horizon.\n\n\\subsection{F5: Imagination Horizon and Subsampling Are Secondary Factors}\n\\label{sec:f5}\n\nNeither horizon length nor temporal subsampling precedes collapse without multi-rate data exposure: both trained-but-unexposed configurations (008a, 008c) maintain $\\nve < 0.93\\times$ (\\S\\ref{sec:f3}), while the trained-and-exposed counterpart (008d) collapses with $\\nve = 4.12\\times$.  The no-embedding configurations show cross-seed variance (008f: 503.0 vs.\\ 009c: 148.3) but neither exhibits $\\nve > 1.5\\times$; low evaluation alone does not indicate CIVO.\n\nThe $3.2\\times$ performance gap (008a: 777.7 vs.\\ 008c: 240.9) quantifies the horizon effect independently of CIVO, as both conditions maintain healthy NVE ($\\leq$0.93$\\times$).\n\n% --- APPENDIX C: Full Analysis & Discussion ---\n\n\\section{Full Analysis \\& Discussion}\n\\label{sec:appendix_analysis}\n\nThis appendix provides the complete mechanistic analysis summarized in Section~\\ref{sec:discussion} of the main text.\n\n\\subsection{The CIVO Mechanism}\n\\label{sec:civo_mechanism}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig4_mechanism_diagram.pdf}\n\\caption{CIVO mechanism diagram. The trained $\\dt$-embedding enables asymmetric reward prediction fidelity, initiating a feedback loop: biased RSSM rewards $\\to$ optimistic critic values $\\to$ actor exploitation $\\to$ reinforced state-distribution skew.}\n\\label{fig:civo_mechanism}\n\\end{figure}\n\n\\begin{table}[h]\n\\centering\n\\caption{RSSM fidelity at $\\dt{=}1$ vs.\\ $\\dt{=}2$. Trained embedding (008d) produces $2.78\\times$ reward gap; removing it (008f) eliminates the gap but degrades absolute prediction.}\n\\label{tab:rssm_fidelity}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{3}{c}{\\textbf{obs\\_MSE}} & \\multicolumn{3}{c}{\\textbf{reward\\_MAE}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\n\\textbf{Config} & $\\dt{=}1$ & $\\dt{=}2$ & Gap & $\\dt{=}1$ & $\\dt{=}2$ & Gap \\\\\n\\midrule\nBaseline & 13.49 & 27.50 & 2.04$\\times$ & 0.0102 & 0.0159 & 1.56$\\times$ \\\\\n008d (trained) & 41.31 & 53.67 & 1.30$\\times$ & 0.0568 & 0.1579 & 2.78$\\times$ \\\\\n008f (no emb) & 8.01 & 22.04 & 2.75$\\times$ & 0.7469 & 0.7526 & 1.01$\\times$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe RSSM fidelity analysis (Table~\\ref{tab:rssm_fidelity}) reveals the mechanistic core of CIVO (Figure~\\ref{fig:civo_mechanism}).  The trained $\\dt$-embedding enables the reward head to learn temporally differentiated predictions, but these predictions are asymmetrically accurate: reward MAE at $\\dt{=}1$ is $0.0568$, while at $\\dt{=}2$ it rises to $0.1579$, a $2.78\\times$ gap.  This gap is not an artifact of prediction difficulty alone; the no-embedding configuration (008f) exhibits a $1.01\\times$ gap, and the baseline shows $1.56\\times$.  The trained embedding actively amplifies the fidelity discrepancy by allowing the reward head to co-adapt with the temporal signal.\n\nThis asymmetric fidelity initiates a feedback loop with four stages: (1) the trained $\\dt$-embedding causes RSSM predictions at $\\dt > 1$ to carry systematically biased reward estimates; (2) the critic, trained entirely on imagined trajectories, internalizes these biased rewards as optimistic value estimates; (3) the actor exploits the overestimated regions of the value landscape, shifting its policy toward states that appear high-value only under the biased model; and (4) this policy shift further skews the distribution of imagined states, reinforcing the bias.  The diagnostic signature is a sustained $\\nve$ above $1.5\\times$, followed by evaluation collapse.\n\nA random-policy control experiment ($N{=}100$ rollouts, 95\\% bootstrap CI) decomposes CIVO into two necessary stages.  \\textbf{Stage~1 (dynamics bias):} even under a random policy, $\\dt{=}2$ imagination produces $1.68\\times$ higher mean reward than $\\dt{=}1$ in the trained-embedding model (008d): the RSSM prior already generates reward-favorable trajectories at $\\dt > 1$, independent of actor behavior.  \\textbf{Stage~2 (actor exploitation):} the trained actor learns to exploit these biased regions, amplifying the ratio to $2.90\\times$.  In the no-embedding control (008f), neither stage is present: the random-policy ratio is $1.11\\times$ and the trained-actor ratio is $0.98\\times$.  The decomposition attributes $\\approx 36\\%$ of the total effect to dynamics bias and $\\approx 64\\%$ to actor exploitation, which confirms that both stages are necessary for CIVO to manifest.\n\nThis mechanism is analogous to delusional bias \\citep{lu2018nondelusional}, but differs in origin: delusional bias arises from policy-class constraints, while CIVO is model-induced.  The consequence (policy exploitation of overestimated regions) is similar, but the causal pathway is distinct.\n\n\\paragraph{Signed reward error analysis.}\nTo test whether CIVO arises from one-step reward overprediction, we compute signed error (predicted $-$ actual) on posterior-conditioned RSSM predictions (Table~\\ref{tab:signed_error}). The trained-embedding model (008d) shows \\emph{negative} bias at $\\dt{=}2$ (mean signed error $-0.599$, only 8\\% of samples overpredicted), ruling out observation-level reward overprediction as the mechanism. The baseline is well-calibrated (mean SE $\\approx 0$), confirming methodological soundness. Value overestimation therefore occurs during \\emph{imagination-level} prior drift: the RSSM prior (unconditioned on observations) generates reward-favorable trajectories at $\\dt > 1$ (Stage~1 above, $1.68\\times$ ratio under random policy), and the critic accumulates these into overestimated returns. The one-step reward prediction is negatively biased when conditioned on real observations, but this posterior correction is unavailable during imagination. This also distinguishes CIVO from generic compounding error, which would produce \\emph{positive} signed error accumulating with horizon; the negative observation-level bias confirms that CIVO is a prior-drift phenomenon, not a reward-prediction artifact.\n\n\\begin{table}[h]\n\\centering\n\\caption{Signed reward error (predicted $-$ actual) on posterior-conditioned RSSM predictions. Negative values indicate underprediction. The trained-embedding model underpredicts at $\\dt{=}2$, ruling out observation-level reward overprediction as the CIVO mechanism.}\n\\label{tab:signed_error}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llrrrrr}\n\\toprule\n\\textbf{Config} & $\\dt$ & \\textbf{Mean SE} & \\textbf{Std} & \\textbf{\\%Over} & \\textbf{Actual} & \\textbf{Pred} \\\\\n\\midrule\nBaseline & 1 & $+0.001$ & 0.023 & 39.6\\% & 1.893 & 1.894 \\\\\n\\midrule\n008d (trained) & 1 & $+0.018$ & 0.072 & 61.8\\% & 0.361 & 0.379 \\\\\n008d (trained) & 2 & $\\mathbf{-0.599}$ & 0.722 & 8.0\\% & 0.721 & 0.121 \\\\\n\\midrule\n008f (no emb) & 1 & $-0.710$ & 0.704 & 14.0\\% & 0.921 & 0.211 \\\\\n008f (no emb) & 2 & $-1.645$ & 1.485 & 5.0\\% & 1.840 & 0.195 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Embedding geometry (exp\\_065).}\nTo characterize what the trained $\\dt$-embedding learns, we measure pairwise cosine similarity between $e_{\\dt{=}1}$ and $e_{\\dt{=}2}$ across training checkpoints for three trained seeds (two environments) and two frozen controls (Table~\\ref{tab:cosine_sim}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity between $e_{\\dt{=}1}$ and $e_{\\dt{=}2}$ vectors. Trained embeddings converge to near-opposite representations; frozen embeddings remain near-orthogonal throughout.}\n\\label{tab:cosine_sim}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llrrr}\n\\toprule\n\\textbf{Config} & \\textbf{Env} & \\textbf{cos@25K} & \\textbf{cos@75K} & \\textbf{Status} \\\\\n\\midrule\n008d s3 (trained) & Walker & $-0.87$ & $-0.70$ & CIVO \\\\\n059 s5 (trained) & Walker & $-0.94$ & $-0.86$ & CIVO \\\\\n010b s0 (trained) & Cheetah & $-0.90$ & $-0.84$ & CIVO \\\\\n\\midrule\n057 s2 (frozen) & Walker & $-0.15$ & $-0.15$ & Healthy \\\\\n058 s1 (frozen) & Cheetah & $+0.07$ & $+0.07$ & Healthy \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll trained seeds map $\\dt{=}1$ and $\\dt{=}2$ to nearly opposite directions (cosine similarity $-0.70$ to $-0.94$), consistent across both Walker and Cheetah environments. Frozen controls remain near-orthogonal (cosine $\\approx 0$) and constant across all checkpoints. The full pairwise cosine similarity matrix (Figure~\\ref{fig:pairwise_heatmap}) reveals that the near-antipodal relationship between $e_{\\dt{=}1}$ and $e_{\\dt{=}2}$ is the dominant structure: most other $\\dt$-pairs remain near-orthogonal ($|\\text{cos}| < 0.2$), indicating that the RSSM selectively maximizes separation along the $\\dt{=}1$ vs.\\ $\\dt{=}2$ axis rather than learning a globally structured embedding space.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.55\\columnwidth]{figures/paper/pairwise_heatmap.png}\n\\caption{Pairwise cosine similarity between all $\\dt$-embedding vectors (exp\\_008d, seed 3, step 75K). The $e_{\\dt{=}0}$--$e_{\\dt{=}1}$ pair exhibits strong anti-correlation ($-0.70$); remaining pairs are near-orthogonal, confirming that the learned geometry is dominated by a single antipodal axis.}\n\\label{fig:pairwise_heatmap}\n\\end{figure}\n\nThe magnitude of the learned separation---near-antipodal rather than merely distinct---provides converging evidence that the RSSM develops maximally differentiated internal representations for the two temporal scales, which in turn may contribute to the asymmetric reward fidelity gap reported in Table~\\ref{tab:rssm_fidelity} and replicated below.\n\n\\paragraph{Extended RSSM fidelity replication (exp\\_063).}\nTo validate the fidelity gap on independently trained checkpoints, we repeat the posterior-conditioned analysis with 15 episodes $\\times$ 40 test points $\\times$ 4 $\\dt$ levels (600 samples per model) on final checkpoints from three conditions (Table~\\ref{tab:rssm_fidelity_ext}).\n\n\\begin{table}[h]\n\\centering\n\\caption{RSSM fidelity analysis (training-time posterior-conditioned). Reward prediction gap remains the critical differentiator; observation reconstruction is paradoxically \\emph{better} with trained embedding. Independent final-checkpoint replication (exp\\_063, 008d seed~4) yields a reward gap of $2.7\\times$, confirming the qualitative pattern at lower magnitude.}\n\\label{tab:rssm_fidelity_ext}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{3}{c}{\\textbf{obs\\_MSE}} & \\multicolumn{3}{c}{\\textbf{reward\\_MAE}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\n\\textbf{Config} & $\\dt{=}1$ & $\\dt{=}2$ & Gap & $\\dt{=}1$ & $\\dt{=}2$ & Gap \\\\\n\\midrule\nBaseline (009d) & 16.08 & 23.49 & 1.46$\\times$ & 0.045 & 0.059 & 1.30$\\times$ \\\\\nCollapsed (008d) & 9.96 & 13.21 & 1.33$\\times$ & 0.057 & 0.178 & 3.11$\\times$ \\\\\nFrozen (057) & 11.14 & 14.95 & 1.34$\\times$ & 0.068 & 0.133 & 1.96$\\times$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe replication confirms the original fidelity gap pattern with two additional observations. First, the collapsed model achieves the \\emph{lowest} absolute obs\\_MSE at $\\dt{=}1$ (9.96 vs.\\ baseline 16.08), indicating that the trained $\\dt$-embedding improves world model quality overall---the pathology is selective degradation of reward predictions at longer horizons, not general model failure. Second, freezing the $\\dt$-embedding reduces the reward gap from $3.11\\times$ (training-time; $2.7\\times$ in independent replication) to $1.96\\times$, providing converging evidence for its role in preventing the co-adaptation loop while leaving residual multi-step reward prediction difficulty.\n\n\\paragraph{Value prediction analysis (exp\\_064).}\nTo examine the relationship between RSSM reward fidelity and critic value estimates, we compare critic predictions $V(s)$ against actual evaluation returns across three conditions (Table~\\ref{tab:value_pred}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Critic value predictions vs.\\ actual evaluation returns. The CIVO model's critic is well-calibrated to its $\\lambda$-return targets ($V(s) \\approx$ target) but both $V$ and targets are disconnected from reality (VE${=}3.03\\times$).}\n\\label{tab:value_pred}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lrrrr}\n\\toprule\n\\textbf{Config} & $V(s)$ & \\textbf{Eval} & \\textbf{VE ratio} & $V{-}\\text{target}$ \\\\\n\\midrule\nBaseline (001) & 665.9 & 938.9 & 0.71$\\times$ & $+0.001$ \\\\\nCIVO (008d) & 192.7 & 63.6 & \\textbf{3.03}$\\times$ & $+0.586$ \\\\\nNo emb (008f) & 116.5 & 306.5 & 0.38$\\times$ & $+0.316$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe paradox---$V(s)$ tracks its $\\lambda$-return targets faithfully yet overestimates actual performance by $3\\times$---provides converging evidence for the hypothesized mechanism in which CIVO operates upstream of the critic: the world model generates inflated imagination trajectories that the critic learns faithfully, producing targets disconnected from reality. In the baseline, VE${<}1.0$ throughout training because $V(s)$ reflects discounted imagined returns over $H{=}15$ steps, naturally lower than undiscounted episodic evaluation. The CIVO model crosses VE${=}1.0$ at step 55K and reaches $3.03\\times$ by 105K, with the gap widening as the actor exploits the overoptimistic critic.\n\n\\paragraph{Actor entropy dynamics under CIVO.}\nExtended training of collapsed configurations reveals a distinctive temporal sequence: evaluation return collapses first, followed by actor entropy explosion ${\\sim}35$K steps later. In the most severe case (EG~v4), entropy rises from $-5.21$ to $+3.22$ nats at a rate of $+2.11$ nats/10K steps, with returns declining from 583 to 93 between steps 60K--120K. A second collapsed run (EG~v5) shows $+0.61$ nats/10K with comparable return degradation (583$\\to$102). By contrast, healthy baselines exhibit gradual entropy drift at $+0.07$ to $+0.22$ nats/10K---15--30$\\times$ slower---with returns stable above 900. The return-before-entropy temporal ordering is consistent with the causal chain: delusional critic $\\to$ bad actor gradients $\\to$ policy destabilization. The entropy explosion is a lagging indicator; the NVE diagnostic detects CIVO onset ${\\sim}35$K steps before entropy rises, consistent with its use as an early-warning signal (\\S\\ref{sec:appendix_sensitivity}).\n\n\\subsection{Selective Gradient Stopping and Gradient Decomposition}\n\\label{sec:sgs_gradient_analysis}\n\n\\subsubsection{Gradient Decomposition Results}\n\\label{sec:gradient_decomposition}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/fig3_gradient_decomposition.pdf}\n\\caption{Gradient contribution to $e_{\\Delta t}$ by loss component at two training checkpoints. The reward head contributes the largest share (38--49\\%) yet reward-only SGS (exp\\_016e) fails; the observation decoder channel (16--22\\%) carries the critical $\\dt$-specific spatial information that drives the RSSM fidelity gap.}\n\\label{fig:gradient_decomp}\n\\end{figure}\n\nExp\\_016e collapses in the same qualitative pattern as the unmodified control: peak evaluation 326.7 at 75K steps followed by catastrophic decline to 31.7 at 95K, with NVE reaching $10.42\\times$. The SGS intervention neither prevented nor attenuated CIVO.\n\nTo explain this null result, we performed a gradient decomposition analysis using \\texttt{torch.autograd.grad} to measure each loss component's contribution to $\\nabla_\\theta e_{\\Delta t}$, where $\\theta$ denotes the temporal embedding parameters. Table~\\ref{tab:gradient_decomposition} reports the results.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Gradient contributions to the temporal embedding $e_{\\Delta t}$ by loss component, measured via \\texttt{torch.autograd.grad} with training configuration \\texttt{gate\\_fixed\\_dt=2}. Gradient norms are $\\ell_2$ norms of $\\nabla_\\theta \\mathcal{L}_i$ for each loss $\\mathcal{L}_i$.}\n\\label{tab:gradient_decomposition}\n\\small\n\\begin{tabular}{lrrrr}\n\\toprule\n& \\multicolumn{2}{c}{\\textbf{@55K}} & \\multicolumn{2}{c}{\\textbf{@112K}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nLoss component & Share & (\\%) & Share & (\\%) \\\\\n\\midrule\nReward head & --- & 49.0 & --- & 38.1 \\\\\nKL dynamics & --- & 34.7 & --- & 40.4 \\\\\nObservation decoders & --- & 16.3 & --- & 21.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe gradient decomposition reveals a counterintuitive structure: the reward head provides the largest gradient contribution (49.0\\% at 55K, 38.1\\% at 112K), yet reward-only SGS (exp\\_016e) fails catastrophically (NVE $10.42\\times$). The observation decoder channel contributes the smallest share (16.3\\% at 55K, 21.5\\% at 112K) yet carries the critical $\\dt$-specific spatial information.  This dissociation between gradient magnitude and causal importance explains why exp\\_016e, which targets the largest pathway, is functionally insufficient for CIVO prevention.\n\nThe gradient structure is relatively stable across training (reward shifts from 49\\% to 38\\%, obs from 16\\% to 22\\%, KL from 35\\% to 40\\%), unlike what a magnitude-based account would predict. The reward head's large gradient contribution reflects the scalar reward prediction task's sensitivity to temporal embedding parameters, but this gradient does not encode $\\Delta t$-specific structural information about spatial dynamics. The observation decoder channel, despite its smaller magnitude, is the only pathway that encodes how the RSSM should differentially predict multi-dimensional proprioceptive states across temporal scales.\n\n\\paragraph{Why the smallest channel is causally critical.} The observation decoder is the only loss component whose gradients encode how the RSSM should differentially predict multi-dimensional proprioceptive states ($14$ orientations, $9$ velocities, $1$ height) across temporal scales.  This $\\dt$-specific spatial information shapes the latent state representation in ways that propagate to reward prediction: the RSSM fidelity gap ($2.78\\times$ reward MAE ratio, Table~\\ref{tab:rssm_fidelity}) arises because the temporal embedding learns to produce latent states that are spatially biased at $\\dt{>}1$, not because the reward head directly learns scale-dependent biases.  Full-SGS targets this causal chain by preventing observation-decoder gradients from updating $e_{\\Delta t}$, though its 0/2 CIVO elimination rate on Walker (seed~1: NVE reduced from $4.12\\times$ to $1.66\\times$ but remains CIVO-positive; seed~2: collapsed) indicates that breaking the gradient pathway alone does not fully eliminate the vulnerability.\n\n\\subsubsection{Implications for the CIVO Mechanism}\n\\label{sec:sgs_implications}\n\nThe gradient decomposition reveals that gradient magnitude and causal importance are decoupled in CIVO.\n\n\\paragraph{Gradient importance $\\neq$ gradient magnitude.} The reward head contributes the largest gradient share (38--49\\%) to $e_{\\Delta t}$, yet reward-only SGS fails.  The observation decoder contributes the smallest share (16--22\\%), yet its removal (via Full-SGS) is necessary for CIVO mitigation.  This dissociation arises because the reward head's gradient, while large, does not encode $\\dt$-specific structural information: it adjusts $e_{\\Delta t}$ to minimize a scalar prediction error that is largely $\\dt$-invariant.  The observation decoder's gradient, though smaller, encodes how the RSSM should differentially reconstruct 24-dimensional proprioceptive states across temporal scales. This is the channel through which $e_{\\Delta t}$ learns scale-dependent latent biases.\n\n\\paragraph{Reframing the intervention target.} Any gradient-level strategy that targets the reward head alone (reward prediction regularization, reward-conditioned value clipping, or reward-only SGS) targets the largest pathway but not the informationally critical one.  The failure of exp\\_016e (NVE $10.42\\times$) despite detaching the dominant gradient source confirms this.  Full-pathway SGS (exp\\_018) detaches $e_{\\Delta t}$ from all non-KL gradients, retaining only the KL dynamics contribution (34--40\\%).  However, this intervention eliminates CIVO in neither seed: seed~1 shows partial mitigation (eval 448.3, peak NVE $1.66\\times$, still CIVO-positive) while seed~2 collapses (eval 40.8). Removing the observation decoder gradient channel is thus contributory but not sufficient. Figure~\\ref{fig:civo_decomposition} decomposes evaluation returns across conditions.\n\n\\begin{figure}[ht]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/fig2_civo_decomposition.pdf}\n\\caption{CIVO decomposition: peak and final (105K step) evaluation returns on Walker Walk across four conditions. \\textbf{Baseline} (001): vanilla DreamerV3. \\textbf{Trained dt-emb} (008d)\\protect\\footnotemark: learned $d{=}32$ temporal embedding with multi-rate data. \\textbf{Full-SGS} (s1, s2): trained embedding with all non-KL gradients detached from $e_{\\dt}$. Trained $\\dt$-embedding degrades peak eval by $73\\%$ and final eval by $86\\%$. Full-SGS seed~1 shows partial mitigation ($-51\\%$ final, NVE $1.66\\times$, still CIVO-positive) while seed~2 collapses ($-96\\%$ final). CIVO elimination rate $= 0/2$.}\n\\label{fig:civo_decomposition}\n\\end{figure}\n\\footnotetext{Experiment 008d terminated at 55K steps; the 105K data point uses continuation run 009e under identical configuration.}\n\nCross-environment validation on Cheetah Run (exp\\_021) further clarifies the role of Full-SGS.  The intervention did not prevent the initial CIVO onset: NVE peaked at $9.94\\times$ at 45K (comparable to the unmitigated exp\\_010b's $8.27\\times$).  However, unlike exp\\_010b, which collapsed permanently to eval 51.7, exp\\_021 self-corrected within ${\\sim}$10K steps, with sustained NVE dropping to $0.34\\times$ (55K--105K) and final evaluation recovering to 221.5.  This transient self-correcting trajectory is not attributable to the SGS intervention: the initial CIVO onset and peak severity are comparable to the unmitigated case, and the self-correction may reflect Cheetah Run's simpler dynamics rather than SGS efficacy.  Performance remains at 38.7\\% of baseline (572.5), likely because Full-SGS over-aggressively blocks actor gradients (actor gradient norms near zero throughout training).  Combined with exp\\_018's Walker results (0/2 CIVO elimination), these findings yield a 0/3 elimination rate across environments, indicating that gradient-level interventions alone do not eliminate the CIVO vulnerability. Additional mechanisms (e.g., forward-pass conditioning effects, residual capacity-dependent instabilities) operate beyond the gradient pathway.\n\n\\paragraph{Connection to RSSM fidelity analysis.} The trained-embedding condition (exp\\_008d) shows a $2.78\\times$ reward gap between $\\Delta t{=}1$ and $\\Delta t{=}2$ transitions (Table~\\ref{tab:rssm_fidelity}).  This gap arises because the observation decoder gradients shape $e_{\\Delta t}$ to produce latent states that are spatially biased at $\\dt{>}1$, and the reward head inherits these biases \\textit{through the latent state} rather than learning them directly.  The reward head's large gradient contribution reflects sensitivity to $e_{\\Delta t}$'s parameters but not causal responsibility for the fidelity gap.\n\n\\subsubsection{Entropy Dynamics Across Configurations}\n\\label{sec:entropy_dynamics}\n\n\\begin{figure}[ht]\n\\centering\n\\includegraphics[width=0.85\\columnwidth]{figures/fig4_entropy_dynamics.pdf}\n\\caption{Actor entropy trajectories for three configurations. All start at ${\\sim}8$ nats and converge to similar values (${\\sim}{-}4.5$ to ${-}5$). The CIVO-triggering configuration (008d, red) follows a normal entropy reduction trajectory; the divergence from the control (008f) is subtle in entropy space, consistent with CIVO operating through the value channel rather than the entropy channel. 018v2 (Full-SGS, seed~1) shows slightly lower terminal entropy.}\n\\label{fig:entropy_dynamics}\n\\end{figure}\n\n\\subsubsection{Exp\\_016e Reinterpreted as Stochastic Variation}\n\\label{sec:016e_reinterp}\n\nThe gradient decomposition establishes that exp\\_016e targets the largest gradient pathway (reward: 38--49\\%) but not the informationally critical one (observation decoders: 16--22\\%).  The apparent timing differences between exp\\_016e and exp\\_008d (later collapse onset, 75K vs.\\ 25K, and higher peak evaluation, 326.7 vs.\\ 167.2) must be attributed to stochastic variation rather than SGS effects, since the critical observation decoder channel remains intact.  All three trajectories (exp\\_008d, exp\\_009b, exp\\_016e) share the invariant identified by the NVE diagnostic: each crosses the $1.5\\times$ pathological threshold at some point during training.\n\n\\subsection{Post-CIVO Outcomes: Why Seeds Diverge}\n\\label{sec:seed_divergence}\n\n\\begin{table}[ht]\n\\centering\n\\caption{Post-CIVO outcomes for all ten CIVO-positive runs across two environments. Peak/Final NVE measured in the 35K+ window.}\n\\label{tab:post_civo}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccl}\n\\toprule\n\\textbf{Env} & \\textbf{Seed} & \\textbf{Peak} & \\textbf{Final} & \\textbf{Eval} & \\textbf{Outcome} \\\\\n\\midrule\nWalker & s1 (008d) & 4.12$\\times$ & 4.12$\\times$ & 82.8 & Full collapse \\\\\nWalker & s2 (009b) & 1.62$\\times$ & 0.38$\\times$ & 267.9 & Transient CIVO \\\\\nWalker & s3 (008d\\_s3) & 1.53$\\times$ & 1.53$\\times$ & 268$^\\diamond$ & Late-onset collapse \\\\\nWalker & s4 (008d\\_s4) & 4.62$\\times$ & 4.62$\\times$ & 63.6 & Full collapse \\\\\nWalker & s5 (059) & 4.72$\\times$ & 1.22$\\times$ & 95.8 & Collapse$^\\dagger$ \\\\\n\\midrule\nCheetah & s1 (010b) & 8.27$\\times$ & 8.27$\\times$ & 51.7 & Full collapse \\\\\nCheetah & s0 (078) & 4.10$\\times$ & 0.29$\\times$ & 119.5 & Self-correcting$^\\ddagger$ \\\\\nCheetah & s0 (010b\\_s0) & 108.52$\\times$ & 108.52$\\times$ & 0.83 & Full collapse \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^\\diamond$ Transitional; train returns still declining at 105K. $^\\dagger$~NVE self-corrected ($4.72\\times$ $\\to$ $1.22\\times$) but policy did not recover (eval 10.5\\% of baseline). $^\\ddagger$~Peak NVE $4.10\\times$ at 75K; eval 213.7$\\to$26.1$\\to$119.5 (26.7\\% of baseline exp\\_077, 448.1).\\par}\n\\end{table}\n\nAll ten CIVO-positive runs cross the $\\nve > 1.5\\times$ threshold (Table~\\ref{tab:post_civo}), yet the downstream damage is stochastic.\\footnote{Exp\\_009e was excluded from multi-seed analyses due to a seed configuration error (default seed=0, identical to exp\\_008d).}  Sustained collapse is the majority outcome (6/10 runs). Three runs self-correct (Walker seed~2 and both Cheetah seeds, including exp\\_078 which recovers from 26.1 to 119.5 at 105K); one (Walker seed~5) shows onset without sustained collapse---NVE self-corrects ($4.72\\times \\to 1.22\\times$) but the policy remains collapsed (eval 10.5\\% of baseline). Cheetah seed~1 (010b) exhibits more extreme overestimation (peak NVE $8.27\\times$) than Walker seeds ($1.53$--$4.62\\times$), consistent with the Cheetah reward scale amplifying the fidelity gap.  We hypothesize that the divergence relates to the critic's representational capacity at the time of CIVO onset.  \\citet{lyle2022capacity} demonstrate that deep RL networks suffer progressive capacity loss, in which early-learned features become increasingly difficult to overwrite.  If the critic's capacity is already partially consumed when CIVO injects overestimation, the network cannot recalibrate (seed~0); if sufficient capacity remains, the critic can absorb transient overestimation and recover (seed~2).\n\n\\paragraph{A fourth trajectory: CIVO-induced persistent value collapse.}\nObs-decoder SGS seed~3 (exp\\_025) exhibits a trajectory not observed in the untreated seeds: healthy through 105K ($\\nve < 1.0\\times$, eval 818.6), CIVO onset at 135K ($\\nve = 5.47\\times$, eval 67.0), followed by evaluation recovery (590.2 at 215K, 64\\% of baseline) but persistent value collapse ($\\nve = 0.14\\times$, value mean 80.6). The critic undershoots after the CIVO episode, suggesting that CIVO-induced representational damage persists even when the policy partially recovers. This contrasts with transient CIVO (seed~2, 009b), where both value and evaluation recover jointly, and with full collapse (seed~1, 008d), where neither recovers. Seed~4 exhibits the same terminal value collapse ($\\nve = 0.14\\times$ at 215K, eval 242), suggesting this overcorrection is systematic rather than seed-specific. The pattern adds a fourth post-CIVO outcome---policy recovery with critic damage---to the three documented in Table~\\ref{tab:post_civo}.\n\n\\subsubsection{Failure and Degradation Mode Taxonomy}\n\nTable~\\ref{tab:failure_modes} classifies the seven distinct failure and degradation modes observed across all experimental configurations. The taxonomy reveals that CIVO is not a single failure mode but a family of related pathologies, with the trained $\\dt$-embedding creating vulnerability through at least three independent mechanisms: value-driven collapse (monotonic, late-onset, and SGS-resistant CIVO), entropy-driven instability (IRD collapse), and gradient-mediated effects (gradient starvation, SGS-paradoxical worsening).\n\n\\begin{table}[ht]\n\\centering\n\\caption{Failure and degradation mode taxonomy. Each mode is characterized by its NVE trajectory, entropy behavior, and primary mechanism.}\n\\label{tab:failure_modes}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{@{}llccl@{}}\n\\toprule\n\\textbf{Mode} & \\textbf{Representative} & \\textbf{NVE} & \\textbf{Entropy} & \\textbf{Mechanism} \\\\\n\\midrule\nMonotonic CIVO & 008d, 008d\\_s4, 010b\\_s0 & $\\uparrow$ sustained & $\\downarrow$ & Reward bias $\\to$ critic $\\to$ actor \\\\\nLate-onset CIVO & 008d\\_s3 & $\\uparrow$ delayed & $\\downarrow$ & Same, delayed onset \\\\\nTransient CIVO & 009b & Peak $\\to$ $\\downarrow$ & Stable & Self-correction via capacity \\\\\nIRD collapse & 008e\\_v3\\_s2 & $\\uparrow$ late & $\\uparrow$ & Entropy-driven, values stable \\\\\nGrad.\\ starvation & 015b & Oscillates, decays & Stable & Frozen emb $\\to$ zero actor grad \\\\\nSGS-resistant & 018\\_s2 & $\\uparrow$ & $\\downarrow$ & Forward-pass conditioning \\\\\nSGS-paradoxical & 016e & $\\uparrow$ sustained & $\\downarrow$ & Reward SGS $\\to$ obs-dec reliance \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Extended Training Dynamics}\\label{sec:extended_training}\n\nOne Walker seed (s3, exp\\_045) was extended from 112K to approximately 302K steps to investigate long-horizon CIVO dynamics. After onset (NVE peak $4.91\\times$ at 132K steps), the system exhibited complete self-recovery: NVE declined to $0.05\\times$ and evaluation performance recovered to 867.6 (94.7\\% of baseline). This recovery required approximately 170K additional training steps beyond onset. The trajectory shows a single onset--recovery cycle with no recurrence, suggesting that the CIVO feedback loop can break spontaneously given sufficient training---though at substantial computational cost that the frozen $\\dt$-embedding diagnostic eliminates entirely.\n\n\\subsection{Why MPC Is Immune}\n\\label{sec:mpc_immune}\n\n\\citet{nhu2025tawm} show that $\\dt$-conditioning benefits TD-MPC2, raising the question of why it fails in DreamerV3.  The critical difference is that MPC re-plans from real states at every step, so imagination errors do not accumulate into the training signal because there is no critic bootstrapping from imagined trajectories.  In DreamerV3, the actor-critic trains entirely within imagination, and any systematic reward-prediction bias at $\\dt > 1$ is amplified through the closed actor-critic loop.\n\n\\subsection{The \\texorpdfstring{$\\dt$}{dt}-Embedding Dilemma}\n\\label{sec:embedding_dilemma}\n\nThe factorial results reveal a fundamental tension: removing the $\\dt$-embedding (008f) eliminates CIVO but at a $13\\times$ cost to reward prediction quality ($0.7469$ vs.\\ $0.0568$ MAE), as the world model cannot distinguish temporal scales.  Restricting imagination to $\\dt{=}1$ while retaining the trained embedding (008e\\_v3) avoids collapse in 2 of 4 seeds (50\\%), while the remaining two collapse via distinct mechanisms: Pathway~A (CIVO-driven, entropy decrease; s3, NVE $4.02\\times$) and Pathway~B (entropy-driven, entropy increase; s2, NVE $3.78\\times$; \\S\\ref{sec:f6}).  Neither approach alone provides a complete solution.\n\n\\subsection{Temporal Embedding Representation Analysis}\n\\label{sec:cosine_evolution}\n\nTo understand how the trained $\\dt$-embedding creates vulnerability, we analyze the cosine similarity between $e(\\dt{=}1)$ and $e(\\dt{=}2)$ across training (exp\\_065). Trained embeddings learn \\emph{near-opposite} representations: $\\cos(e_1, e_2) = {-}0.87$ to ${-}0.94$ at 25K steps across three configurations (Walker 008d\\_s3, Cheetah 010b\\_s0, Walker 059\\_s5), persisting at ${-}0.70$ to ${-}0.86$ at 75K steps. In contrast, frozen embeddings maintain near-zero similarity ($-0.15$ to $+0.07$, constant throughout training). The near-antipodal learned representations explain the large reward prediction gap (\\S\\ref{sec:f2}): $\\dt{=}2$ conditioning pushes the RSSM into a qualitatively different region of latent space, producing systematically biased predictions rather than minor perturbations.\n\n\\subsection{\\texorpdfstring{$\\dt$}{dt}-Embedding Differentiation Precedes Value Divergence}\n\\label{sec:cosine_temporal}\n\nThe preceding analysis established that trained $\\dt$-embeddings learn near-antipodal representations. Here we resolve the \\emph{temporal dynamics} of this differentiation across 11 experiments (${\\sim}$47 checkpoints), testing whether embedding differentiation is a consequence or precursor of CIVO.\n\n\\paragraph{Trained embeddings: monotonic relaxation.}\nAcross all trained configurations, $\\cos(e_1, e_2)$ starts near $-0.95$ within 10K steps and relaxes monotonically toward ${\\sim}{-}0.65$ (Table~\\ref{tab:cosine_evolution_ext}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity evolution between $e(\\dt{=}1)$ and $e(\\dt{=}2)$ for trained $\\dt$-embeddings. Relaxation is monotonic but never reaches zero; frozen embeddings remain constant near zero throughout training.}\n\\label{tab:cosine_evolution_ext}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Env} & \\textbf{Experiment} & \\textbf{10K} & \\textbf{25K} & \\textbf{65K} & \\textbf{75K} & \\textbf{302K} \\\\\n\\midrule\n\\multirow{2}{*}{Walker} & exp\\_066b (trained) & $-0.947$ & $-0.928$ & $-0.847$ & --- & --- \\\\\n & exp\\_045 (extension) & --- & --- & --- & --- & $-0.668$ \\\\\n\\midrule\nCheetah & exp\\_010b$\\to$048 & --- & $-0.904$ & --- & $-0.841$ & $-0.639$ \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Frozen controls:}} \\\\\nWalker & exp\\_057 (frozen) & \\multicolumn{5}{c}{$-0.150$ (constant, 25K--225K)} \\\\\nCheetah & exp\\_058 (frozen) & \\multicolumn{5}{c}{$+0.069$ (constant, 25K--225K)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nCross-seed consistency at 25K steps is high: mean $\\cos = -0.910 \\pm 0.028$ ($n{=}5$ Walker seeds), confirming the relaxation pattern is robust across random seeds. Variance increases with training ($-0.789 \\pm 0.076$ at 75K), reflecting seed-dependent relaxation rates.\n\n\\paragraph{Temporal precedence over CIVO.}\nExp\\_066b provides simultaneous cosine similarity and CIVO diagnostic data at 5K resolution (Table~\\ref{tab:cosine_vs_civo}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity relaxation and CIVO diagnostic for exp\\_066b. Embedding relaxation onset (${\\sim}$20K) precedes CIVO alert (55K, VE ratio $> 0.7$) by ${\\sim}$30--35K steps.}\n\\label{tab:cosine_vs_civo}\n\\footnotesize\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{rccc}\n\\toprule\n\\textbf{Step} & $\\cos(e_1, e_2)$ & \\textbf{VE ratio} & \\textbf{CIVO alert} \\\\\n\\midrule\n10K & $-0.947$ & 0.012 & --- \\\\\n15K & $-0.948$ & 0.033 & --- \\\\\n25K & $-0.928$ & 0.193 & --- \\\\\n35K & $-0.904$ & 0.269 & --- \\\\\n45K & $-0.880$ & 0.358 & --- \\\\\n55K & $-0.861$ & 0.710 & \\textbf{Alert} \\\\\n65K & $-0.847$ & 0.724 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nCosine relaxation begins at ${\\sim}$20K (cos transitions from $-0.948$ at 15K to $-0.928$ at 25K), while the VE ratio first exceeds 0.7 at 55K. The ${\\sim}$30--35K temporal lead establishes that embedding differentiation is an early training dynamic, not a consequence of CIVO-triggered feedback. The relaxation rate peaks at 25K--45K ($+0.024$/10K steps) before decelerating, consistent with the geometric intuition that large-angle adjustments in embedding space are cheaper early in training.\n\n\\paragraph{Embedding norms.}\nWalker and Cheetah exhibit qualitatively different norm dynamics. Walker $e(\\dt{=}1)$ norms grow from 0.23 to 0.50 ($2.2\\times$) while $e(\\dt{=}2)$ grows from 0.45 to 0.63 ($1.4\\times$)---both $\\dt$ values become more expressive over training. Cheetah norms remain nearly constant ($\\leq 1.04\\times$) despite continued cosine relaxation, indicating direction changes without magnitude change. Frozen embedding norms are an order of magnitude smaller (${\\sim}0.06$, constant).\n\n\\paragraph{Mechanistic interpretation.}\nThe temporal ordering---embedding differentiation (${\\sim}$20K) $\\to$ reward fidelity gap (${\\sim}$20K, \\S\\ref{sec:timeseries_fidelity}) $\\to$ value overestimation (${\\sim}$30K)---suggests a three-layer causal chain: the embedding first learns maximally differentiated representations that push $\\dt{=}1$ and $\\dt{=}2$ into opposite latent regions, the reward head then develops scale-dependent biases from these differentiated inputs, and the critic amplifies these biases through imagined rollout bootstrapping. The frozen embedding's constant near-zero cosine ($|\\cos| < 0.2$) prevents the first link in this chain, explaining why freezing eliminates CIVO despite maintaining identical forward-pass architecture (\\S\\ref{sec:f3}).\n\n\\subsection{Time-Series Fidelity--Value Analysis}\n\\label{sec:timeseries_fidelity}\n\nTo test the causal direction between reward fidelity degradation and value overestimation, we analyze exp\\_066 and exp\\_066b: two Walker Walk seeds (trained $\\dt$-embedding, fixed $\\dt{=}2$) evaluated at 12 dense checkpoints from 10K to 65K steps (Table~\\ref{tab:timeseries_fidelity}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Time-series fidelity and value metrics (exp\\_066, seed~0). SS = single-step MAE ratio ($\\dt{=}2$/$\\dt{=}1$); VE = value-to-eval ratio. Fidelity degradation (SS $>1.1\\times$ at 20K) precedes value overestimation onset (VE begins rising at ${\\sim}$30K) by ${\\sim}$10K steps. Seed~1 (exp\\_066b) confirms the pattern: fidelity gap onset ${\\sim}$15K $\\to$ VE onset ${\\sim}$24K (lead ${\\approx}$9K steps; VE peak ${=}0.72$).}\n\\label{tab:timeseries_fidelity}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{rcccccc}\n\\toprule\n\\textbf{Step} & \\textbf{SS ratio} & \\textbf{OL ratio} & \\textbf{VE ratio} & \\textbf{MAE$_{\\dt{=}1}$} & \\textbf{MAE$_{\\dt{=}2}$} & \\textbf{Return} \\\\\n\\midrule\n10K & 1.05 & 0.94 & 0.01 & 0.090 & 0.094 & 43.0 \\\\\n15K & 1.08 & 1.03 & 0.02 & 0.085 & 0.092 & 187.8 \\\\\n20K & 1.10 & 1.09 & 0.16 & 0.078 & 0.086 & 148.7 \\\\\n25K & 1.04 & 1.22 & 0.16 & 0.073 & 0.076 & 142.1 \\\\\n30K & 1.25 & 1.45 & 0.22 & 0.068 & 0.085 & 148.3 \\\\\n35K & 1.24 & 1.51 & 0.23 & 0.062 & 0.077 & 275.4 \\\\\n40K & 1.35 & 1.38 & \\textbf{1.59} & 0.058 & 0.078 & 202.3 \\\\\n45K & 1.40 & 1.38 & 0.36 & 0.055 & 0.077 & 107.5 \\\\\n50K & 1.47 & 1.56 & 0.62 & 0.052 & 0.076 & 178.4 \\\\\n55K & 1.37 & 1.52 & 0.62 & 0.050 & 0.069 & 60.8 \\\\\n60K & 1.61 & 1.35 & 1.40 & 0.049 & 0.079 & 125.3 \\\\\n65K & 1.68 & 1.38 & 1.40 & 0.047 & 0.079 & 94.4 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/paper/fig_temporal_ordering.pdf}\n\\caption{Temporal ordering of fidelity degradation and value overestimation (exp\\_066, seed~0). \\textbf{Left axis}: single-step fidelity ratio (SS, blue) grows steadily from $1.05\\times$ to $1.68\\times$. \\textbf{Right axis}: value-to-eval ratio (VE, red) remains near zero until 40K, then spikes. The ${\\sim}$10K onset-to-onset lag supports the causal direction: fidelity gap $\\to$ value overestimation. Seed~1 (exp\\_066b) replicates the pattern with a ${\\sim}$9K temporal lead.}\n\\label{fig:temporal_ordering}\n\\end{figure}\n\nThe $\\dt{=}1$ prediction MAE decreases monotonically ($0.090 \\to 0.047$) as the world model improves, but $\\dt{=}2$ MAE plateaus at ${\\sim}0.08$. The growing fidelity gap is therefore not caused by $\\dt{=}2$ predictions worsening, but by the model selectively improving at $\\dt{=}1$ while failing to transfer that improvement to $\\dt{=}2$---consistent with the trained $\\dt$-embedding learning maximally differentiated representations (\\S\\ref{sec:cosine_evolution}) that prevent cross-scale generalization.\n\n\\textbf{Limitation.} These results are limited to two seeds ($n{=}2$). While both seeds show consistent temporal ordering (leads of ${\\approx}$10K and ${\\approx}$9K steps), additional seeds would strengthen the causal claim.\n\n\\subsection{Actor Entropy Is Not Diagnostic of CIVO}\n\\label{sec:entropy_not_diagnostic}\n\nTo test whether actor entropy can serve as an early collapse indicator, we compare entropy trajectories between collapsed and healthy configurations at matched training steps across five experiments (Table~\\ref{tab:entropy_contrast}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Actor entropy comparison at matched time points. Collapsed and healthy configurations exhibit indistinguishable entropy at 55K steps (difference $= 0.03$ nats), despite collapsed runs showing severe return degradation.}\n\\label{tab:entropy_contrast}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Group} & \\textbf{Experiment} & \\textbf{5K} & \\textbf{25K} & \\textbf{45K} & \\textbf{55K} & \\textbf{Return} \\\\\n\\midrule\n\\multirow{2}{*}{Collapsed}\n & exp\\_008d (trained dt\\_emb) & 8.16 & $-1.86$ & $-4.58$ & $-4.88$ & ${\\sim}165$ \\\\\n & fixed\\_dt2 ($\\dt{=}2$) & 8.16 & $-3.02$ & $-5.06$ & $-5.17$ & ${\\sim}29$ \\\\\n\\midrule\n\\multirow{3}{*}{Healthy}\n & exp\\_008f (no dt\\_emb) & 8.11 & $-1.85$ & $-4.31$ & $-4.77$ & ${\\sim}460$ \\\\\n & exp\\_008a (unexposed) & 8.16 & $-4.88$ & $-5.20$ & $-5.21$ & ${\\sim}300$ \\\\\n & baseline\\_s1 ($\\dt{=}1$) & 8.10 & $-4.74$ & $-5.12$ & $-5.18$ & ${\\sim}950$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt the last comparable step (55K): collapsed mean entropy $= -5.02$ (average of $-4.88$, $-5.17$); healthy mean entropy $= -5.05$ (average of $-4.77$, $-5.21$, $-5.18$); difference $= 0.03$ nats---statistically negligible. The hypothesis that collapsed runs exhibit anomalous entropy rise (actor confusion from delusional critic gradients) is not supported during the CIVO onset window.\n\nThe fixed\\_dt2 experiment demonstrates this most clearly: returns peak at ${\\sim}580$ (40K) then crash to 29 (72K), yet entropy remains stable at $-5.1$ throughout. The actor maintains a committed, low-entropy policy during the entire collapse---it does not become confused but rather remains confident while acting on incorrect value estimates. This is consistent with CIVO operating through critic value distortion rather than actor policy degradation. The late-stage entropy explosion documented in \\S\\ref{sec:civo_mechanism} ($+2.1$ nats/10K in EG~v4, onset ${\\sim}$35K steps after return collapse) occurs well beyond this window, confirming entropy rise as a lagging consequence rather than a concurrent or predictive signal.\n\n\\paragraph{Entropy descent speed.}\nEntropy descent rate correlates with temporal configuration complexity, not collapse fate. Simpler configurations (baseline $\\dt{=}1$, unexposed exp\\_008a) reach $-4.7$ by 25K, while configurations exposed to temporal variation (both collapsed and healthy) remain near $-2.0$ at 25K, reflecting the difficulty of policy commitment when training data spans multiple temporal scales.\n\n\\paragraph{Long-horizon entropy recovery.}\nThe baseline ($\\dt{=}1$) run extended to 505K steps shows entropy recovering from $-5.2$ to ${\\sim}{-}1.5$ between 115K and 295K steps, coinciding with continued performance improvement ($700 \\to 950$ return). This adaptive entropy increase rules out entropy rise as an inherently negative signal; the actor maintains ${\\sim}950$ return with entropy 3--4 nats above its minimum, indicating a healthy exploration--exploitation balance during extended training.\n\n\\subsection{Multiple Vulnerability Pathways}\n\\label{sec:pathways}\n\nThe two collapse patterns identified in \\S\\ref{sec:f6}---CIVO (Pathway~A, value-driven, entropy decreasing) and a tentative second mode (Pathway~B, eval-driven, entropy increasing)---have distinct diagnostic signatures. Pathway~B is observed in only two seeds (008e\\_v3\\_s2 and 038\\_s2); we present it as preliminary evidence that the trained $\\dt$-embedding's learned features may affect both reward prediction across temporal scales (Pathway~A) and the representation space in which the actor operates (Pathway~B), though additional data is needed to confirm this as a distinct mechanism.  This explains why $\\nve$ is sensitive but not perfectly specific: Pathway~B's late evaluation decline inflates $\\nve$ through the same arithmetic as CIVO, yielding the sole false positive ($3.78\\times$ for 008e\\_v3 s2).  Distinguishing the two requires examining the temporal profile and entropy direction of collapse (Figure~\\ref{fig:multiple_pathways}).\n\n\n\\subsection{Implications for Temporal Abstraction in World Models}\n\\label{sec:implications}\n\nCIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \\citep{gumbsch2024thick}, Hieros \\citep{mattes2024hieros}, LS-Imagine \\citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \\citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.  The CIVO mechanism requires three structural properties: (1) a temporal embedding that co-adapts with dynamics via gradient flow, (2) multi-step imagined rollouts used for critic training, and (3) a reward head that inherits latent biases from the shared representation.  Transformer-based world models that share these properties may exhibit analogous vulnerability; architectures that decouple temporal conditioning from the reward prediction pathway would not.\n\n\\subsection{Cross-Environment TCN Evaluation}\n\\label{sec:tcn_cross_env}\n\nTable~\\ref{tab:tcn_full} reports the full TCN evaluation across environments and noise magnitudes.\n\n\\begin{table}[h]\n\\centering\n\\caption{TCN results across environments and noise magnitudes. Prevention = peak NVE $< 1.5\\times$ (35K+).}\n\\label{tab:tcn_full}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Env} & $\\sigma$ & \\textbf{Seed} & \\textbf{NVE$_{\\max}$} & \\textbf{Prevented?} & \\textbf{Eval (\\%)} \\\\\n\\midrule\nWalker & 0.1 & s0 & 1.02 & \\checkmark$^*$ & 55\\% \\\\\nWalker & 0.2 & s0 & 0.91 & \\checkmark & 91\\% \\\\\nWalker & 0.2 & s1 & 0.64 & \\checkmark & 45\\% \\\\\nWalker & 0.2 & s2 & 2.11$^\\dagger$ & $\\times$ & ${\\sim}5\\%$ \\\\\n\\rowcolor{gray!15}\nWalker & 0.2 & s3 & 3.04$^\\P$ & $\\times$ & 11\\% \\\\\nWalker & 0.5 & s0 & 3.97 & $\\times$ & 27\\% \\\\\nWalker & 0.5 & s1 & 1.64 & $\\times$ & 41\\% \\\\\n\\midrule\nCheetah & 0.2 & s0 & 1.90 & $\\times$ & crashed \\\\\nCheetah & 0.5 & s0 & 10.67 & $\\times$ & 26\\% \\\\\nCheetah & 1.0 & s0 & $\\leq$0.30 & \\checkmark$^\\S$ & 15\\% \\\\\n\\midrule\nPickCube & 0.2 & s0 & 3.71 & $\\times$ & failing \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$Borderline: NVE${=}1.02\\times$ at 95K, below $1.5\\times$ threshold but above $1.0\\times$.\\\\\n$^\\dagger$NVE $= 2.11\\times$ at 95K, still rising; eval ${\\sim}5\\%$ of baseline.\\\\\n$^\\P$Late-onset CIVO: NVE declined to $0.67\\times$ at 95K before phase-transition-like spike to $3.04\\times$ at 105K; eval 349.6 at 95K $\\to$ 71.8 at 105K $\\to$ 104.5 at 215K.\\\\\n$^\\S$CIVO prevented (NVE${\\leq}0.30$); peak eval 116\\% baseline at 35K, declining to 15\\% by 215K via progressive policy erosion. See ``impossible dose'' discussion.\\par}\n\\end{table}\n\n\\paragraph{Cheetah Run $\\sigma{=}0.5$: transient spike with permanent eval damage.}\nCheetah $\\sigma{=}0.5$ exhibits a novel failure mode: a transient CIVO spike (NVE $= 10.67\\times$ at 55K) followed by NVE recovery ($< 0.3\\times$ by 95K), but permanent evaluation damage (26\\% of baseline). The value signal self-corrects while the policy does not recover, suggesting that CIVO-induced representational damage during the spike persists within the observation window even when the critic subsequently recalibrates. This trajectory parallels the obs-decoder SGS seed~3 pattern (\\S\\ref{sec:seed_divergence}), where partial policy recovery coexists with persistent critic damage.\n\n\\paragraph{Cheetah Run $\\sigma{=}0.2$: insufficient dose.}\nAt $\\sigma{=}0.2$, Cheetah reaches NVE $= 1.9\\times$ at 55K---exceeding the $1.5\\times$ threshold---consistent with Cheetah's higher baseline CIVO severity ($8$--$108\\times$ vs.\\ Walker's $2$--$6\\times$). The noise magnitude that suffices for Walker is inadequate for Cheetah, but increasing $\\sigma$ to 0.5 trades CIVO prevention for a different failure mode rather than achieving mitigation.\n\n\\paragraph{PickCube-v1 $\\sigma{=}0.2$: manipulation failure.}\nPickCube reaches NVE $= 3.71\\times$ at 52.5K with $\\sigma{=}0.2$, indicating that TCN provides no protection in manipulation tasks. The combination of contact-gated dynamics and temporal conditioning may amplify the fidelity gap beyond what representation-level noise can attenuate.\n\n\\paragraph{Dose-response analysis.}\nWe observe $\\sigma{=}0.2$ as a local optimum on Walker Walk, achieving complete CIVO suppression in 2 of 4 seeds. Seeds~2 and~3 both fail but via distinct CIVO onset dynamics: seed~2 shows gradual escalation (NVE $= 2.11\\times$ at 95K, still rising, eval ${\\sim}5\\%$), while seed~3 exhibits a phase-transition-like onset---NVE declined to $0.67\\times$ at 95K before spiking to $3.04\\times$ at 105K (eval 349.6 $\\to$ 71.8 in 10K steps). When TCN fails to prevent CIVO onset, the resulting trajectory qualitatively resembles untreated CIVO in its terminal outcome---runaway NVE and eval collapse. The two failure modes (gradual escalation vs.\\ sudden onset after apparent suppression) reinforce that TCN operates as a binary gate on CIVO onset rather than providing graded attenuation. Below the optimum, we observe $\\sigma{=}0.1$ as insufficient (NVE $= 1.02\\times$---borderline, eval 55\\%); above it, $\\sigma{=}0.5$ overdoses (oscillatory CIVO, eval $\\leq 41\\%$). Cross-seed variance at $\\sigma{=}0.2$ (eval 5--91\\%) exceeds the cross-dose difference by a wide margin, reinforcing that seed effects dominate dose effects. TCN is the only tested intervention achieving complete CIVO suppression in any configuration, but its high seed sensitivity and failure to transfer across environments position it as a \\emph{diagnostic probe}---identifying the representation level as the relevant intervention target---rather than a deployable mitigation.\n\n\\paragraph{Cheetah Run ``impossible dose'' dilemma.}\nExp\\_030c (224K steps) reveals a qualitatively different dose-response on Cheetah. At $\\sigma{=}1.0$, CIVO is eliminated (NVE${\\leq}0.30$ throughout) and initial learning is \\emph{unimpaired}: peak eval reaches 372 at 35K (116\\% of baseline), demonstrating that $\\sigma{=}1.0$ noise does not prevent policy acquisition. However, cumulative actor gradient interference produces progressive policy erosion---eval declines from 372 to 47 by 215K (15\\% of baseline)---while the critic remains well-calibrated (value\\_mean${=}12.4$, NVE${=}0.26$ at 215K). This establishes that \\emph{policy degradation $\\neq$ value corruption}: accurate value signals are insufficient when the actor cannot optimize effectively in noise-perturbed imagination.\n\nThis ``correct values, failed policy'' pattern provides indirect evidence that CIVO is mechanistically distinct from standard overestimation. Double Q-learning and ensemble methods address critic estimation error, but at $\\sigma{=}1.0$ the critic is accurate and the policy still collapses---a failure mode orthogonal to what these countermeasures target. The impossible dose dilemma scales with environment complexity: Cheetah's baseline CIVO severity ($8$--$108\\times$ NVE) requires $\\sigma \\geq 1.0$ to suppress, but this exceeds the actor's gradient signal-to-noise tolerance. On Walker, a narrow effective window exists around $\\sigma{=}0.2$; on Cheetah, the effective dose ($\\sigma \\geq 1.0$) exceeds the tolerable dose, and environments with higher CIVO severity will systematically lack a viable dose window.\n\n\\section{DreamerV3 Hyperparameters}\n\\label{sec:hyperparameters}\n\nTable~\\ref{tab:hyperparams} lists the DreamerV3 hyperparameters used across all experiments. Unless otherwise noted, we use the default DreamerV3 configuration for continuous-control tasks (\\texttt{dmc\\_proprio}).\n\n\\begin{table}[ht]\n\\centering\n\\caption{DreamerV3 hyperparameters for all experiments. Modifications from defaults are marked with $\\diamond$.}\n\\label{tab:hyperparams}\n\\small\n\\begin{tabular}{ll}\n\\toprule\n\\textbf{Parameter} & \\textbf{Value} \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{World Model}} \\\\\nRSSM discrete states & 32 classes $\\times$ 32 categories \\\\\nRSSM stochastic dim & 32 \\\\\nRSSM deterministic dim & 512 \\\\\nMLP hidden size & 512 \\\\\nMLP layers & 2 \\\\\nActivation & SiLU \\\\\nNormalization & LayerNorm \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Training}} \\\\\nBatch size & 16 sequences $\\times$ 64 steps \\\\\nLearning rate & $3 \\times 10^{-4}$ (Adam, $\\epsilon{=}10^{-8}$) \\\\\nSequence length & 64 \\\\\nTraining ratio & 512 \\\\\nFree nats & 1.0 \\\\\nKL balance ($\\alpha$) & 0.8 \\\\\nDiscount ($\\gamma$) & 0.997 \\\\\n$\\lambda$-return & 0.95 \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Policy}} \\\\\nImagination horizon$^\\diamond$ & 8 or 15 (see Table~\\ref{tab:complete_results}) \\\\\nActor entropy scale & $3 \\times 10^{-4}$ \\\\\nActor gradient & Reinforce + dynamics backprop \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Temporal Abstraction}$^\\diamond$} \\\\\nGate enabled & True (all non-baseline) \\\\\nGate fixed $\\dt$ & 1 or 2 (per config) \\\\\nSubsample max $\\dt$ & 1 (OFF) or 2 (ON) \\\\\n$\\dt$-embedding dim & 32 \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Environment}} \\\\\nAction repeat & 2 (Walker Walk, Cheetah Run) \\\\\nObservation & Proprioceptive (no pixels) \\\\\nTotal environment steps & 105K \\\\\nEvaluation frequency & Every 10K steps \\\\\nEvaluation episodes & 10 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Online CIVO Detector Details}\n\\label{sec:detector_appendix}\n\nThis appendix provides the full algorithm specification and validation results for the online CIVO detector described in \\S\\ref{sec:detector}.\n\n\\subsection{Algorithm Specification}\n\n\nThe four conditions capture complementary signals: (1)~\\emph{Magnitude} ($r_t \\geq 0.49$) confirms that the value-to-evaluation ratio has reached a level indicative of overestimation; (2)~\\emph{Velocity} ($\\Delta r_t > 0.1$) rules out slow drift or plateau behavior; (3)~\\emph{Acceleration} ($\\Delta r_t > \\Delta r_{t-1}$, both $> 0.1$) filters oscillatory paths; (4)~\\emph{Evaluation decline} ($\\geq 2$ of 3 recent checkpoints decline) confirms that overestimation coincides with actual performance degradation. A full comparison of window sizes appears in \\S\\ref{sec:appendix_sensitivity}.\n\nSensitivity analysis over $\\tau_\\text{mag} \\in [0.30, 0.70]$ confirms that $\\tau_\\text{mag} = 0.49$ maximizes Youden's $J = 0.714$; raising the threshold to $0.50$ loses one true positive (seed~3 triggers at $r_t = 0.497$) with no reduction in false positives. The velocity threshold $\\tau_\\text{vel} = 0.1$ is stable across $[0.05, 0.18]$ (TPR remains $5/5$).\n\n\\subsection{Validation Results}\n\n\\begin{table}[ht]\n\\centering\n\\caption{Retrospective CIVO detector validation ($n{=}14$). Detection type: ``predictive'' = alert precedes 20\\% eval decline; ``reactive'' = alert follows decline onset.}\n\\label{tab:detector-validation}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{Verdict} & \\textbf{Trigger} & \\textbf{Type} & \\textbf{Peak Eval} & $r_\\text{ve}$ \\\\\n\\midrule\n008d s0 & trained $\\dt$-emb & TP & 45K & predict. & 167 & 0.69 \\\\\n010b & trained $\\dt$-emb (Cheetah) & TP & 65K & reactive & 322 & 3.18 \\\\\n008d s3 & trained $\\dt$-emb & TP & 45K & predict. & 452 & 0.50 \\\\\n008d s4 & trained $\\dt$-emb & TP & 105K & reactive & 383 & 3.03 \\\\\n010b s0 & trained $\\dt$-emb (Cheetah) & TP & 95K & reactive & 248 & 6.34 \\\\\n\\midrule\n008f s3 & no $\\dt$-emb & TN & -- & -- & 594 & -- \\\\\n009b s2 & trained $\\dt$-emb (self-corr.) & TN & -- & -- & 279 & -- \\\\\nbaseline s1 & vanilla & TN & -- & -- & 970 & -- \\\\\n009d s0 & vanilla & TN & -- & -- & 951 & -- \\\\\n009d s1 & vanilla & TN & -- & -- & 920 & -- \\\\\n019b & trained $\\dt$-emb (PickCube) & TN & -- & -- & 26.6 & -- \\\\\n\\midrule\n009c s2 & no $\\dt$-emb & FP & 105K & reactive & 359 & 0.75 \\\\\n009a s2 & vanilla & FP & 85K & predict. & 967 & 0.73 \\\\\n\\midrule\n009c s3 & no $\\dt$-emb & TN & -- & -- & 457 & -- \\\\\n\\midrule\n\\multicolumn{7}{l}{TPR = 5/5 (1.00), \\quad FPR = 2/9 (0.22)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe detector identifies all five CIVO-positive runs (TPR = 5/5). Two are detected predictively (008d seeds~0 and~3, both at 45K). Two false positives occur among nine negative cases (FPR = 2/9, precision 71\\%, F$_1$ = 0.83). Run 009c develops genuine late-stage value overestimation unrelated to CIVO; run 009a triggers during a transient eval dip at 85K before recovery to 966. Early alerts (before 70K) carry higher diagnostic confidence.\n\n\\subsection{Cross-Simulator Specificity (PickCube)}\n\nExp\\_019b applies the CIVO-trigger configuration to PickCube-v1 in ManiSkill3, a dense-reward manipulation task. The V/E ratio exhibits an oscillatory pattern rather than monotonic divergence: it spikes to $r_t = 5.66$ at 52.5K, then deflates to 1.38 by 72.5K. This trajectory prevents the acceleration condition from co-occurring with evaluation decline at any single checkpoint. Across all 14 checkpoints through 132.5K, the detector correctly remains silent (TN), confirming that the acceleration filter distinguishes transient spikes from CIVO's sustained monotonic divergence. A frozen-embedding control (exp\\_054) confirms this classification: frozen PickCube-v1 exhibits a comparable burst (peak $8.81\\times$ at 62.5K) that resolves within a single evaluation cycle ($0.55\\times$ at 72.5K), establishing environment-specific origin independent of $\\dt$-embedding training.\n\n\\subsection{Detector Limitations}\n\nFour constraints bound the current detector. First, the three-checkpoint window cannot distinguish transient dips from sustained collapse. Second, the acceleration condition assumes monotonically increasing overestimation during onset. Third, the detector identifies a \\emph{pattern} rather than a \\emph{mechanism}: run 009c shows that non-CIVO pathologies produce the same signature. Fourth, threshold values were calibrated on fourteen runs across three environments; generalization to different reward scales requires further validation.\n\n\\section{Dual-Critic Mechanism Ablation}\n\\label{sec:dual_critic_appendix}\n\n\\subsection{\\texorpdfstring{$2{\\times}2$}{2x2} Factorial Design}\n\nWe ablate the critic architecture in a $2{\\times}2$ factorial: \\{single, dual\\} $\\times$ \\{narrow (${\\sim}1.2$M), wide (${\\sim}2.4$M)\\} parameters. Table~\\ref{tab:dual_critic_full} reports all configurations.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Dual-critic $2{\\times}2$ factorial results. Walker Walk unless noted.}\n\\label{tab:dual_critic_full}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{Params} & \\textbf{NVE} & \\textbf{Eval} & \\textbf{Outcome} \\\\\n\\midrule\n008d & Single narrow & 1.2M & 4.12$\\times$ & 82.8 & Collapse \\\\\n033 & Wide single & 2.4M & 4.75$\\times$ & 407.9 & CIVO $\\to$ self-repair \\\\\n035 s0 & Narrow dual (min) & 1.2M & 2.75$\\times$ & 697.8 & CIVO $\\to$ recovery \\\\\n039 s1 & Narrow dual (min) & 1.2M & 2.19$\\times$ & 592.7 & CIVO $\\to$ recovery \\\\\n032 s0 & Wide dual (min) & 2.4M & $\\leq$1.1$\\times$ & 739.7 & CIVO prevented \\\\\n032b s1 & Wide dual (min) & 2.4M & 1.4$\\times$ & 551.8 & CIVO prevented \\\\\n038 s2 & Wide dual (min) & 2.4M & $\\leq$0.3$\\times$ & 120.9$^*$ & Non-CIVO collapse \\\\\n\\midrule\n\\multicolumn{6}{l}{\\textit{Cross-environment}} \\\\\n034 & Cheetah dual & 2.4M & 1.75$\\times$ & 97.5 & Partial recovery (31\\%) \\\\\n037 & Cheetah wide single & 2.4M & 3.60$\\times$ & 146.1 & CIVO $\\to$ self-repair \\\\\n036 & PickCube dual & 2.4M & 2.3$\\times$ & 27.7 & Transient CIVO \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$CIVO prevented (NVE $\\leq 0.3\\times$) but non-CIVO eval collapse: eval peaked at 354 (155K), then declined to 120.9 (224K) with actor entropy increasing from $-3.59$ to $-0.45$.\\par}\n\\end{table}\n\n\\subsection{Critic Convergence (\\texorpdfstring{$v_1 \\approx v_2$}{v1 ≈ v2})}\n\nAcross all dual-critic configurations and environments, the two critics converge to near-identical value functions. On Walker Walk, Pearson $\\rho > 0.999$ between $v_1$ and $v_2$ outputs; on Cheetah Run and PickCube-v1, the gap is $< 0.2$ (exact match within numerical precision). Per-sample pessimism $\\mathbb{E}[\\max(v_1, v_2) - \\min(v_1, v_2)]$ is 3--4\\% of the theoretical bound for independent critics.\n\nThis convergence occurs because both critics train on the same RSSM-generated latent features. Unlike model-free Double Q-learning, where each critic sees different mini-batches of real transitions and develops distinct function approximation errors, pure-imagination critics share identical inputs from the world model. The min operation therefore cannot provide the pessimism bias that makes Double Q effective in model-free settings.\n\n\\subsection{Recovery vs.\\ Prevention Mechanism}\n\nThe $2{\\times}2$ factorial reveals two separable dimensions:\n\n\\paragraph{Recovery (min-dominated).} The min operation is the primary factor enabling recovery from CIVO. Both narrow dual-critic seeds experience CIVO and recover fully: exp\\_035 (s0, $\\nve = 2.75\\times$, eval $33.8 \\to 697.8$, recovery ratio $20.6\\times$) and exp\\_039 (s1, $\\nve = 2.19\\times$, eval $35.9 \\to 592.7$, recovery ratio $16.5\\times$). Both outperform wide single-critic (exp\\_033, 2.4M params, eval 407.9) despite $2\\times$ fewer parameters. The min operation reduces both peak CIVO severity (2.19--2.75$\\times$ vs.\\ 4.75$\\times$ for the comparable single-critic) and enables consistent full recovery across seeds.\n\n\\paragraph{Prevention (min $+$ capacity synergy).} CIVO prevention (NVE remaining below the $1.5\\times$ threshold) requires both the min operation and increased capacity: only the wide dual-critic (exp\\_032, 3 seeds) achieves this. The mechanism for this synergy is an open question; we hypothesize that increased capacity improves value calibration quality while the min operation constrains the overestimation feedback loop during early training when the two critics briefly diverge.\n\n\\paragraph{Cross-environment limits.} On Cheetah Run, the wide dual-critic (exp\\_034) reduces NVE from $8.27\\times$ (untreated baseline) to $1.75\\times$ ($\\geq 4\\times$ reduction) but cannot prevent CIVO onset, and recovery reaches only 31\\% of the pre-CIVO peak. This confirms that the min $+$ capacity synergy has environment-dependent limits: in high-CIVO-severity environments, architecture-level interventions attenuate but do not eliminate the pathology.\n",
    "structuredPatch": [
      {
        "oldStart": 51,
        "oldLines": 12,
        "newStart": 51,
        "newLines": 10,
        "lines": [
          " 018 s1 & Full-SGS & trn$^\\ddagger$ & ON & 8 & \\sgseval{} @105K & \\sgsnve{}$\\times$$^*$ & Partial mitig.\\ (CIVO+) \\\\",
          " \\rowcolor{gray!15}",
          " 018 s2 & Full-SGS & trn$^\\ddagger$ & ON & 8 & 40.8 @105K & --- & Collapsed \\\\",
          "-008e\\_v3 s1 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.94$\\times$ & Healthy \\\\",
          "-008e\\_v3 s2$^\\dagger$ & Mitigation & trn & ON & 15 & 137.0 @105K & 3.78$\\times$ & Non-CIVO collapse \\\\",
          "-\\rowcolor{gray!15}",
          "-008e\\_v3 s3 & Mitigation & trn & ON & 15 & 92.7 @105K & 4.02$\\times$ & CIVO collapse \\\\",
          "-008e\\_v3 s4 & Mitigation & trn & ON & 15 & 899.3 @105K & 0.99$\\times$ & Healthy \\\\",
          "-008e\\_v3 s5 & Mitigation & trn & ON & 15 & 853.1 @105K & 0.61$\\times$ & Healthy \\\\",
          "+008e\\_v3 s0 & Mitigation & trn & ON & 15 & 148.0 @105K & 0.60$\\times$ & No CIVO$^j$ \\\\",
          "+008e\\_v3 s1 & Mitigation & trn & ON & 15 & 876.7 @105K & 0.60$\\times$ & Healthy \\\\",
          "+008e\\_v3 s2 & Mitigation & trn & ON & 15 & 597.1 @105K & 0.50$\\times$ & Healthy \\\\",
          "+008e\\_v3 s5 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.60$\\times$ & Healthy \\\\",
          " \\midrule",
          " \\multicolumn{8}{l}{\\textit{Cross-environment validation}} \\\\",
          " \\rowcolor{gray!15}"
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

_source line 50_

<details open><summary>🔧 Tool call — Edit · `toolu_01MuSbdbVHWKTjEFcutjRMR8`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
  "old_string": "$^i$ Cartpole: exp\\_060 reports seed~2 eval only; exp\\_061/062 report 3-seed mean.\\par}",
  "new_string": "$^i$ Cartpole: exp\\_060 reports seed~2 eval only; exp\\_061/062 report 3-seed mean.\\\\\n$^j$ CIVO-unrelated learning stagnation; NVE $\\leq 0.6\\times$, no value overestimation.\\par}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "e44de26c-d646-41e3-829a-77225a0c3a68",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014qzJiusovRz9UN3WYM6Uxv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6430,
      "cache_read_input_tokens": 88430,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6430
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

_source line 51 · 2026-05-25T16:34:03.798Z_

<details><summary>↩ Tool result · `toolu_01MuSbdbVHWKTjEFcutjRMR8`</summary>

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
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "6005a906-75d4-46f5-b29e-687c5f424e18",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
    "oldString": "$^i$ Cartpole: exp\\_060 reports seed~2 eval only; exp\\_061/062 report 3-seed mean.\\par}",
    "newString": "$^i$ Cartpole: exp\\_060 reports seed~2 eval only; exp\\_061/062 report 3-seed mean.\\\\\n$^j$ CIVO-unrelated learning stagnation; NVE $\\leq 0.6\\times$, no value overestimation.\\par}",
    "originalFile": "% --- APPENDIX ---\n\n\\section{Complete Experimental Results}\n\\label{sec:complete_results}\n\nTable~\\ref{tab:complete_results} reports all 45 experimental configurations. The main text (Table~\\ref{tab:main_results}) presents the subset most relevant to the causal argument; this table includes the additional variable-rate configurations (006, 007, 005), multi-seed factorial runs (009b, 008d\\_s3, 008d\\_s4), SGS interventions (018), cross-environment seeds (010b\\_s0), and mitigation experiments (008e\\_v3).\n\n\\begin{table*}[t]\n\\centering\n\\caption{Complete experimental results. NVE reports peak $\\nve$ in the 35K+ window (\\S\\ref{sec:metrics}). CIVO-positive seeds are shaded; $\\dagger$\\,marks a false positive (non-CIVO collapse with elevated NVE).}\n\\label{tab:complete_results}\n\\scriptsize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{dt\\_emb} & \\textbf{Sub} & \\textbf{H} & \\textbf{Eval@final} & \\textbf{NVE} & \\textbf{Outcome} \\\\\n\\midrule\n001 & Baseline ($\\dt{=}1$, s1) & --- & --- & 15 & 915.7 @105K & 1.00$\\times$ & Healthy \\\\\n001 s2 & Baseline ($\\dt{=}1$, s2) & --- & --- & 15 & 443.5 @105K & ---$^e$ & Healthy \\\\\n\\rowcolor{gray!15}\n006 & Fixed $\\dt{=}2$ & trn & ON & 15 & 132.9 @65K & 4.83$\\times$ & Collapsed \\\\\n007 & Fixed $\\dt{=}4$ & trn & ON & 15 & 152.5 @55K & --- & Collapsed \\\\\n005 & Learned gate & adaptive & OFF & 15 & 98.8 @145K & --- & Collapsed \\\\\n\\midrule\n\\rowcolor{gray!15}\n008d & Factorial (s1) & trn & ON & 8 & 82.8 @55K$^\\heartsuit$ & 4.12$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n009b & Factorial (s2) & trn & ON & 8 & 267.9 @105K & 1.62$\\times$ & Transient CIVO \\\\\n\\rowcolor{gray!15}\n008d\\_s3 & Factorial (s3) & trn & ON & 8 & 268$^\\diamond$ @105K & 1.53$\\times$ & Late-onset collapse \\\\\n\\rowcolor{gray!15}\n008d\\_s4 & Factorial (s4) & trn & ON & 8 & 63.6 @105K & 4.62$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n059 & Factorial (s5) & trn & ON & 8 & 95.8 @105K & 4.72$\\times$ & Collapse$^\\dagger$ \\\\\n\\rowcolor{gray!15}\n068 & Factorial repro (s1) & trn & ON & 8 & 39.1 @105K & 4.12$\\times$ & Full collapse \\\\\n008f & No dt\\_emb (s1) & --- & ON & 8 & 503.0 @105K & 0.97$\\times$ & Healthy \\\\\n008f s4 & No dt\\_emb (s4) & --- & ON & 8 & 289.3 @105K & 0.76$\\times$ & Healthy \\\\\n009c s3 & No dt\\_emb (s3) & --- & ON & 8 & 311.9 @105K & 1.04$\\times$ & Healthy \\\\\n008a & Unexposed emb & exp$^a$ & OFF & 15 & 777.7 @105K & 0.93$\\times$ & Healthy \\\\\n008a\\_s1 & Unexposed emb & exp$^a$ & OFF & 15 & 630.9 @105K & 0.83$\\times$ & Healthy \\\\\n008a\\_s2 & Unexposed emb & exp$^a$ & OFF & 15 & 899.4 @105K & 0.89$\\times$ & Healthy \\\\\n008a\\_s3 & Unexposed emb & exp$^a$ & OFF & 15 & 855.9 @105K & --- & Healthy \\\\\n015b & Frozen emb & frz$^b$ & ON & 8 & 204.2 @105K & 1.45$\\times$ & Grad.\\ starvation \\\\\n022b & Frozen emb + Gumbel gate & frz$^b$ & ON & 8 & 300.7 @105K & 0.63$\\times$ & No CIVO \\\\\n042 & Frozen emb (dedicated) & frz$^b$ & ON & 8 & 612.0 @105K & 0.19$\\times$ & Healthy \\\\\n047 & Frozen emb (s1) & frz$^b$ & ON & 8 & 144.2 @215K & 1.71$\\times$ & Transient (self-corr.) \\\\\n057 & Frozen emb (s2) & frz$^b$ & ON & 8 & 123.9 @215K & 1.88$\\times$ & Transient (self-corr.) \\\\\n067 & Frozen emb (s0) & frz$^b$ & ON & 8 & 281.5 @105K & 0.19$\\times$ & Healthy \\\\\n\\midrule\n018 s1 & Full-SGS & trn$^\\ddagger$ & ON & 8 & \\sgseval{} @105K & \\sgsnve{}$\\times$$^*$ & Partial mitig.\\ (CIVO+) \\\\\n\\rowcolor{gray!15}\n018 s2 & Full-SGS & trn$^\\ddagger$ & ON & 8 & 40.8 @105K & --- & Collapsed \\\\\n008e\\_v3 s0 & Mitigation & trn & ON & 15 & 148.0 @105K & 0.60$\\times$ & No CIVO$^j$ \\\\\n008e\\_v3 s1 & Mitigation & trn & ON & 15 & 876.7 @105K & 0.60$\\times$ & Healthy \\\\\n008e\\_v3 s2 & Mitigation & trn & ON & 15 & 597.1 @105K & 0.50$\\times$ & Healthy \\\\\n008e\\_v3 s5 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.60$\\times$ & Healthy \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cross-environment validation}} \\\\\n\\rowcolor{gray!15}\n010b & Cheetah Run & trn & ON & 8 & 51.7 @105K & 8.27$\\times$ & Collapsed \\\\\n\\rowcolor{gray!15}\n010b\\_s0 & Cheetah Run & trn & ON & 8 & 0.83 @105K & 108.52$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n021 & Cheetah Run & trn$^\\ddagger$ & ON & 8 & 221.5 @105K & 9.94$\\times$$^d$ & Transient CIVO (self-corr.) \\\\\n024b s0 & Cheetah Run & --- & ON & 8 & 96.5 @105K & $<$0.20$\\times$ & Healthy \\\\\n024b s1 & Cheetah Run & --- & ON & 8 & 77.3 @105K & 0.10$\\times$ & Healthy \\\\\n008a\\_ch s0 & Cheetah Run & exp$^a$ & OFF & 15 & 532.4 @105K & 1.08$\\times$ & Healthy \\\\\n008a\\_ch s1 & Cheetah Run & exp$^a$ & OFF & 15 & 504.4 @105K & 1.29$\\times$ & Healthy \\\\\n077 & Cheetah baseline (s0) & --- & --- & 15 & 448.1 @105K & 1.00$\\times$ & Healthy \\\\\n\\rowcolor{gray!15}\n078 & Cheetah trigger (s0) & trn & ON & 8 & 119.5 @105K & 4.10$\\times$ & Onset (self-corr.) \\\\\n\\rowcolor{gray!15}\n019b & PickCube-v1 & trn & ON & 8 & 26.64 @200K & 3.78$\\times$$^c$ & Transient onset \\\\\n054 & PickCube-v1 & frz$^b$ & ON & 8 & --- & 8.81$\\times$$^h$ & Env.\\ transient (ctrl) \\\\\n049 & StackCube-v1 & trn & ON & 8 & 34.9 @212K & 5.05$\\times$$^f$ & Env.\\ transient \\\\\n052 & StackCube-v1 & trn & ON & 8 & --- & 4.67$\\times$$^f$ & Env.\\ transient \\\\\n051 & StackCube-v1 & frz$^b$ & ON & 8 & 30.7 @155K & 4.30$\\times$$^f$ & Env.\\ transient (ctrl) \\\\\n050 & PegInsertionSide-v1 & trn & ON & 8 & 20.86 @212K & 10.05$\\times$$^g$ & Env.\\ dynamics \\\\\n053 & PegInsertionSide-v1 & frz$^b$ & ON & 8 & 5.89 & 8.10$\\times$$^g$ & Env.\\ dynamics (ctrl) \\\\\n055 & PegInsertionSide-v1 & trn & ON & 8 & 11.44 @212K & 3.08$\\times$$^g$ & Env.\\ dynamics \\\\\n056 & PegInsertionSide-v1 & frz$^b$ & ON & 8 & 4.37 @212K & 11.32$\\times$$^g$ & Env.\\ dynamics (ctrl) \\\\\n046 & Cheetah Run & frz$^b$ & ON & 8 & 150.5 @215K & 1.35$\\times$ & No CIVO \\\\\n058 & Cheetah Run & frz$^b$ & ON & 8 & 80.46 @215K & 0.78$\\times$ & No CIVO \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cartpole Swingup}} \\\\\n060 & Cartpole baseline (3 seeds) & --- & --- & 15 & 557.0 @105K$^i$ & --- & Healthy \\\\\n061 & Cartpole trigger (3 seeds) & trn & ON & 8 & 236.3 @105K$^i$ & --- & No CIVO \\\\\n062 & Cartpole control (3 seeds) & --- & ON & 8 & 244.8 @105K$^i$ & --- & No CIVO \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize\ntrn = trained ($d{=}32$, subsample ON);\ntrn$^\\ddagger$ = full-pathway SGS (all non-KL gradients detached);\nexp$^a$ = trained, subsample OFF;\nfrz$^b$ = frozen ($d{=}32$, \\texttt{requires\\_grad=False});\n--- = removed ($d{=}0$).\\\\\n$^*$ Seed 1 only: peak NVE with transient exceedances (1.60$\\times$ at 35K, 1.66$\\times$ at 95K); self-correcting, no sustained escalation. Seed 2 collapsed.\\\\\n$^\\diamond$ Transitional; train returns still declining (peak 470 to 139 over final 8K steps). Collapse had not reached equilibrium at 105K.\\\\\n$^\\dagger$ NVE self-corrected ($4.72\\times$ $\\to$ $1.22\\times$) but policy did not recover (eval 10.5\\% of baseline).\\\\\n$^c$ NVE normalized against exp\\_019a\\_v2 (vanilla DreamerV3 on PickCube-v1).\\\\\n$^d$ Peak NVE $9.94\\times$ at 45K (transient, self-correcting to $<$1$\\times$ by 55K); final eval 221.5.\\\\\n$^e$ Not used for NVE normalization; reported for completeness. Seed~1 (eval 915.7) is the NVE reference baseline.\\\\\n$^f$ StackCube transient: frozen control (exp\\_051, peak $4.30\\times$ at 42.5K) matches trained (exp\\_049/052), self-correcting by 82.5K; environment-specific, not $\\dt$-embedding-driven.\\\\\n$^g$ PegInsertion environment dynamics: seed~0 trained peaks at $10.05\\times$ (82.5K); seed~1 trained (exp\\_055) peaks at $3.08\\times$ (92.5K), final $0.50\\times$ at 212.5K; seed~1 frozen (exp\\_056) peaks at $11.32\\times$ (82.5K), final $1.19\\times$ at 212.5K. Frozen final exceeds trained final; ordering is seed-dependent, ruling out $\\dt$-embedding causation.\\\\\n$^h$ PickCube environment transient: frozen control peak $8.81\\times$ at 62.5K, self-correcting to $0.55\\times$ at 72.5K; matches trained (exp\\_019b) trajectory.\\\\\n$^\\heartsuit$ Evaluated at 55K steps due to early termination of exp\\_008d; extended run (exp\\_009e) reached 131.08 at 105K.\\\\\n$^i$ Cartpole: exp\\_060 reports seed~2 eval only; exp\\_061/062 report 3-seed mean.\\par}\n\\end{table*}\n\n\\begin{table}[h]\n\\centering\n\\caption{Cross-domain CIVO reproducibility. ``$\\dt$-emb-dep.'' indicates trained peaks consistently exceed frozen at matched timepoints across seeds.}\n\\label{tab:cross_domain}\n\\footnotesize\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Domain} & \\textbf{Environment} & \\textbf{Trained} & \\textbf{Frz ctrl} & \\textbf{$\\dt$-emb-dep.\\ CIVO} \\\\\n\\midrule\nLocomotion & Walker Walk & 5/5 & 0/3 & Yes (NVE $1.53$--$4.72\\times$) \\\\\nLocomotion & Cheetah Run & 2/2 & 0/2 & Yes (NVE $8.27$--$108.5\\times$) \\\\\nManipulation & StackCube-v1 & 0/2 & 0/1 & No (frozen$\\approx$trained) \\\\\nManipulation & PegInsertionSide & 0/2 & 0/2 & No (seed-dep.\\ ordering) \\\\\nManipulation & PickCube-v1 & 0/1 & 0/1 & No (frozen spike similar) \\\\\n\\midrule\nLocomotion & Cartpole Swingup & 0/3 & 0/3 & No (single-joint) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cartpole Swingup.} Cartpole Swingup (single-DoF locomotion) serves as a cross-environment control. Three seeds of the CIVO-trigger configuration (exp\\_061: trained $e_{\\dt}$, subsample ON, $H{=}8$, $\\dt{=}2$) and three seeds of the no-embedding control (exp\\_062) both produce zero CIVO onset. Despite using the hyperparameter combination that triggers collapse in all 10 tested multi-joint locomotion seeds (Walker/Cheetah), the single-joint Cartpole shows no CIVO, confirming the phenomenon requires multi-joint dynamics where temporal abstraction amplifies the reward fidelity gap.\n\n\\section{NVE Threshold Sensitivity Analysis}\n\\label{sec:appendix_sensitivity}\n\nWe report the full sensitivity analysis for the NVE diagnostic framework introduced in Section~\\ref{sec:results}. The main text reports Task~B2 (any CIVO detection, $\\nve \\geq 1.5\\times$). Here we additionally present Task~B1, which restricts the positive class to \\emph{sustained} CIVO, specifically experiments exhibiting persistent, accelerating value overestimation that progresses to performance collapse. Transient CIVO cases (e.g., exp~009b, which self-corrects after a brief excursion above the threshold) are classified as negative in B1.\n\n\\subsection{Per-Experiment NVE Values}\n\nTable~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\\_v3 seeds and exp\\_059). Experiments are sorted by descending NVE. Experiment 008e\\_v3\\_s2 exhibits elevated NVE ($3.78\\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\\_v3\\_s3 exhibits CIVO with NVE $4.02\\times$ despite $\\Delta t{=}1$ imagination.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\\ = transient CIVO with self-correction.}\n\\label{tab:nve_raw}\n\\small\n\\begin{tabular}{@{}lrccc@{}}\n\\toprule\nExperiment & NVE & Mechanism & B1 & B2 \\\\\n\\midrule\n006          & 4.83 & sustained CIVO & $+$ & $+$ \\\\\n059          & 4.72 & self-correcting CIVO & $-$ & $+$ \\\\\n008d         & 4.12 & sustained CIVO & $+$ & $+$ \\\\\n008e\\_v3\\_s3 & 4.02 & CIVO           & $+$ & $+$ \\\\\n008e\\_v3\\_s2 & 3.78 & IRD (non-CIVO) & $-$ & $-$ \\\\\n009b         & 1.62 & transient CIVO & $-$ & $+$ \\\\\n001          & 1.00 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s4 & 0.99 & non-CIVO       & $-$ & $-$ \\\\\n008f         & 0.97 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s1 & 0.94 & non-CIVO       & $-$ & $-$ \\\\\n008a         & 0.93 & non-CIVO       & $-$ & $-$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Multi-Threshold Classification Performance}\n\nTable~\\ref{tab:sensitivity_b1} reports Task~B1 classification metrics across six NVE thresholds. Task~B1 achieves $\\text{AUROC} = 0.917$ because exp\\_059 (NVE${=}4.72\\times$, self-correcting CIVO, B1-negative) ranks above two sustained-CIVO positives ($4.12\\times$, $4.02\\times$), breaking the perfect rank separation that held before its inclusion. The optimal threshold lies in the interval $(3.78, 4.02]$; we report $\\geq 3.9\\times$ as a representative value (accuracy $10/11 = 90.9\\%$). Table~\\ref{tab:sensitivity_b2} provides the corresponding analysis for Task~B2 ($\\text{AUROC} = 0.967$, imperfect separation due to 008e\\_v3\\_s2).\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B1}: Sustained CIVO detection sensitivity analysis ($n_{\\text{pos}}=3$, $n_{\\text{neg}}=8$, $n=11$, $\\text{AUROC}=0.917$). All confidence intervals are two-sided Clopper-Pearson exact binomial ($\\alpha=0.05$). $^\\dagger$Optimal threshold in $(3.78, 4.02]$; exp\\_059 (NVE${=}4.72\\times$, B1-negative) is the sole false positive.}\n\\label{tab:sensitivity_b1}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 3 & 4 & 0 & 4 & 63.6\\% \\; [30.8, 89.1] & 42.9\\% & 100\\% & 60.0\\% \\\\\n$\\geq 1.2\\times$ & 3 & 3 & 0 & 5 & 72.7\\% \\; [39.0, 94.0] & 50.0\\% & 100\\% & 66.7\\% \\\\\n$\\geq 1.5\\times$ & 3 & 3 & 0 & 5 & 72.7\\% \\; [39.0, 94.0] & 50.0\\% & 100\\% & 66.7\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.7\\times$ & 3 & 2 & 0 & 6 & 81.8\\% \\; [48.2, 97.7] & 60.0\\% & 100\\% & 75.0\\% \\\\\n$\\geq 2.0\\times$ & 3 & 2 & 0 & 6 & 81.8\\% \\; [48.2, 97.7] & 60.0\\% & 100\\% & 75.0\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 3.9\\times^\\dagger$ & 3 & 1 & 0 & 7 & 90.9\\% \\; [58.7, 99.8] & 75.0\\% & 100\\% & 85.7\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B2}: Any CIVO detection sensitivity analysis ($n_{\\text{pos}}=5$, $n_{\\text{neg}}=6$, $n=11$, $\\text{AUROC}=0.967$). The single false positive at $\\geq 1.5\\times$ is 008e\\_v3\\_s2 (IRD mechanism, not CIVO). The $1.5\\times$ threshold (highlighted) maximizes F1 while maintaining perfect recall.}\n\\label{tab:sensitivity_b2}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 5 & 2 & 0 & 4 & 81.8\\% \\; [48.2, 97.7] & 71.4\\% & 100\\% & 83.3\\% \\\\\n$\\geq 1.2\\times$ & 5 & 1 & 0 & 5 & 90.9\\% \\; [58.7, 99.8] & 83.3\\% & 100\\% & 90.9\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.5\\times$ & 5 & 1 & 0 & 5 & 90.9\\% \\; [58.7, 99.8] & 83.3\\% & 100\\% & 90.9\\% \\\\\n$\\geq 1.7\\times$ & 4 & 1 & 1 & 5 & 81.8\\% \\; [48.2, 97.7] & 80.0\\% & 80.0\\% & 80.0\\% \\\\\n$\\geq 2.0\\times$ & 4 & 1 & 1 & 5 & 81.8\\% \\; [48.2, 97.7] & 80.0\\% & 80.0\\% & 80.0\\% \\\\\n$\\geq 3.9\\times$ & 4 & 0 & 1 & 6 & 90.9\\% \\; [58.7, 99.8] & 100\\% & 80.0\\% & 88.9\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B2 (full evaluation set)}: Any CIVO detection across two environments ($n_{\\text{pos}}=9$, $n_{\\text{neg}}=8$, $n=17$, $\\text{AUROC}=0.972$). Includes Walker Walk (15 configurations) and Cheetah Run (2 configurations).}\n\\label{tab:sensitivity_b2_full}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 9 & 2 & 0 & 6 & 88.2\\% \\; [63.6, 98.5] & 81.8\\% & 100\\% & 90.0\\% \\\\\n$\\geq 1.2\\times$ & 9 & 1 & 0 & 7 & 94.1\\% \\; [71.3, 99.9] & 90.0\\% & 100\\% & 94.7\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.5\\times$ & 9 & 1 & 0 & 7 & 94.1\\% \\; [71.3, 99.9] & 90.0\\% & 100\\% & 94.7\\% \\\\\n$\\geq 1.7\\times$ & 7 & 1 & 2 & 7 & 82.4\\% \\; [56.6, 96.2] & 87.5\\% & 77.8\\% & 82.4\\% \\\\\n$\\geq 2.0\\times$ & 7 & 1 & 2 & 7 & 82.4\\% \\; [56.6, 96.2] & 87.5\\% & 77.8\\% & 82.4\\% \\\\\n$\\geq 3.9\\times$ & 7 & 0 & 2 & 8 & 88.2\\% \\; [63.6, 98.5] & 100\\% & 77.8\\% & 87.5\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\subsection{Threshold Recommendation}\n\nFor the main diagnostic (Task~B2), we recommend $\\nve \\geq 1.5\\times$ as the operating threshold for three reasons:\n\n\\begin{enumerate}[nosep,leftmargin=*]\n\\item \\textbf{Maximum recall.} The $1.5\\times$ threshold achieves 100\\% recall, detecting all five CIVO cases including the transient case (009b, $\\nve = 1.62\\times$). Raising the threshold to $1.7\\times$ loses 009b, dropping recall to 80.0\\%.\n\\item \\textbf{Best F1.} At $1.5\\times$, F1 = 90.9\\%, the highest among all tested thresholds for B2. The single false positive (008e\\_v3\\_s2) is mechanistically identifiable as IRD rather than CIVO.\n\\item \\textbf{Sensitivity--specificity tradeoff.} Lower thresholds ($1.0\\times$) add false positives without gaining true positives. Higher thresholds ($\\geq 1.7\\times$) sacrifice recall without eliminating the 008e\\_v3\\_s2 false positive (which requires $\\tau > 3.78$).\n\\end{enumerate}\n\nFor Task~B1 (sustained CIVO only), the optimal threshold $\\nve \\geq 3.9\\times$ achieves $10/11$ accuracy ($90.9\\%$, 95\\% CI: [58.7\\%, 99.8\\%]); the sole false positive is exp\\_059 (NVE${=}4.72\\times$, self-correcting CIVO classified as B1-negative).\n\n\\subsection{Expanded ROC Analysis}\n\\label{sec:roc_analysis}\n\nThe original $n{=}17$ analysis (Tables~\\ref{tab:sensitivity_b1}--\\ref{tab:sensitivity_b2_full}) predates the SGS, RAVE, and TCN experiments. We extend the NVE diagnostic evaluation to $n{=}56$ configurations spanning all tested interventions. Figure~\\ref{fig:nve_roc} shows the receiver operating characteristic curve with 95\\% bootstrap confidence interval (10{,}000 resamples).\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.7\\columnwidth]{../../artifacts/figures/nve_roc_curve.pdf}\n\\caption{NVE ROC curve ($n{=}56$ configurations, AUROC${=}0.990$, comprehensive validation). The preset $\\nve \\geq 1.5\\times$ operating point (star) achieves TPR${=}1.00$, FPR${=}0.09$, accuracy${=}53/56$, F1${=}0.941$. Three false positives arise from non-CIVO value overestimation: mitigation transient VE spike (008e\\_v3 subsample, $1.93\\times$) and frozen embedding transients (047, $1.71\\times$; 057, $1.88\\times$). Threshold calibrated and validated post-hoc; cross-architecture validation deferred.}\n\\label{fig:nve_roc}\n\\end{figure}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.7\\columnwidth]{../../artifacts/figures/nve_threshold_prf.pdf}\n\\caption{Precision, Recall, and F1 as a function of NVE threshold ($n{=}56$ configurations). Peak F1${=}0.941$ at $\\tau{=}1.5\\times$, where recall remains perfect ($1.00$) and precision${=}0.889$. The plateau of high F1 across $\\tau \\in [1.5, 1.7]$ indicates robustness to threshold selection.}\n\\label{fig:nve_prf}\n\\end{figure}\n\nWe label a configuration as CIVO-positive if and only if (i)~it uses a trained $\\dt$-embedding with multi-rate data exposure, and (ii)~NVE exceeds $1.5\\times$ with co-occurring entropy collapse. Configurations exhibiting high NVE through other mechanisms (gradient truncation side effects, value anchor pollution) are labeled non-CIVO.\n\nThe three false positives (FPR${=}0.18$) are mechanistically distinct from CIVO: (1)~RAVE anchor pollution (exp\\_028, the EMA anchor becomes inflated, producing overestimation through a different pathway); (2)~obs-decoder SGS-induced value distortion (exp\\_025 seed~2, blocking observation decoder gradients damages the RSSM latent space); (3)~IRD eval-driven collapse (exp\\_008e\\_v3 seed~2, actor entropy \\emph{increases} with evaluation collapse, mechanistically distinct from CIVO's entropy \\emph{decrease}). All three produce NVE $> 1.5\\times$ through non-CIVO mechanisms, indicating that the NVE diagnostic detects value overestimation broadly rather than CIVO specifically---a feature rather than a limitation for practitioners monitoring deployment health. The closest sub-threshold case (008f seed~4, NVE${=}1.41\\times$) lacks $\\dt$-conditioning entirely ($d{=}0$); its elevated NVE reflects transient value noise that self-corrects without the positive feedback loop characteristic of CIVO. The closest above-threshold positive (008d seed~3, NVE${=}1.53\\times$) exhibits the full CIVO causal chain: trained $\\dt$-embedding, entropy decrease, and evaluation collapse to 14\\% of baseline.\n\n\\paragraph{Comprehensive validation ($n{=}56$).}\nExpanding the evaluation set to all classifiable experiments yields $n{=}56$ ($n_{\\text{pos}}{=}24$, $n_{\\text{neg}}{=}32$), spanning Walker Walk, Cheetah Run, and multiple intervention configurations (SGS, TCN, dual-critic, frozen embedding). At the $1.5\\times$ threshold: AUROC${=}0.990$, precision${=}0.889$, recall${=}1.000$, F1${=}0.941$, accuracy${=}53/56$. The three false positives are: exp\\_008e\\_v3\\_subsample ($1.93\\times$, mitigation config with transient VE spike), exp\\_047 ($1.71\\times$, frozen embedding transient), and exp\\_057 ($1.88\\times$, frozen embedding transient). All 24 CIVO-positive configurations are correctly detected (FN${=}0$), with CIVO-positive NVE ranging from $1.53\\times$ (008d seed~3, late-onset) to $70.64\\times$ (010b seed~0, Cheetah). The substantial increase in sample size from $n{=}32$ to $n{=}56$ strengthens confidence in the $1.5\\times$ threshold as a robust diagnostic boundary.\n\n\\subsection{NVE Normalization Robustness}\n\\label{sec:nve_robustness}\n\nTo assess sensitivity to baseline seed choice, we extend the single-seed baseline (seed~1, eval 915.7 at 105K) to three additional seeds trained to 505K steps (Table~\\ref{tab:baseline_seeds}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Walker Walk baseline seeds at 105K and 505K steps.}\n\\label{tab:baseline_seeds}\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Seed} & \\textbf{Eval@105K} & \\textbf{Eval@505K} & \\textbf{ve@65K} & \\textbf{ve@105K} \\\\\n\\midrule\ns1 & 915.7 & 970.4 & 0.563 & 0.656 \\\\\ns2 & 443.5 & 945.7 & 0.898 & 0.742 \\\\\ns3 & 869.0 & 947.7 & --- & 0.664 \\\\\ns4 & 922.8 & 938.9 & --- & 0.624 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nSeed~2 exhibits slow convergence (eval 443.5 at 105K, recovering to 945.7 by 512K), confirming non-pathological slow convergence rather than seed failure. Its elevated $v/e$ ratio at 65K (0.898 vs.\\ 0.563 for seed~1) reflects the low evaluation denominator rather than pathological value overestimation. Using seed~2 as the sole normalization reference systematically deflates NVE values, causing two marginal CIVO-positive configurations (008d seed~3, peak NVE $1.53\\times$; 009b seed~2, peak NVE $1.62\\times$) to fall below the $1.5\\times$ threshold. Core CIVO cases (peak NVE $> 3\\times$) remain correctly classified under all baseline seeds.\n\nSingle-seed normalization (s1) yields AUROC $= 0.933$ and accuracy 7/8 (87.5\\%) on the Walker subset. Four-seed mean normalization yields AUROC $= 0.867$ and accuracy 6/8 (75.0\\%): the boundary case exp\\_009b flips from $\\nve = 1.62\\times$ (s1) to $1.23\\times$ (4-seed mean), because its peak occurs at 45K when the s1 $v/e$ ratio (0.331) is well below the 4-seed mean (0.436). All high-NVE configurations remain correctly classified (006: $4.84\\times \\to 4.52\\times$; 008d: $4.12\\times \\to 3.54\\times$). The $1.5\\times$ threshold thus correctly identifies all strong CIVO cases regardless of baseline choice; sensitivity is confined to configurations within 10\\% of the threshold.\n\n\\paragraph{Normalization conventions.} Walker NVE is normalized against the single-seed baseline (seed~1, exp\\_001, 505K steps). Cheetah NVE is normalized against a 5-seed mean baseline (seeds~0--4, each run to ${\\sim}$210K steps). The differing seed counts reflect available baseline data; both provide sufficient coverage of the respective experimental windows (Walker: 210K analysis window; Cheetah: 105K analysis window).\n\n\\paragraph{Limitations.} The initial $n{=}11$ analysis had wide Clopper-Pearson confidence intervals (e.g., 90.9\\% accuracy, 95\\% CI [58.7\\%, 99.8\\%]). The comprehensive evaluation ($n{=}56$, AUROC${=}0.990$, F1${=}0.941$; Figure~\\ref{fig:nve_roc}) substantially tightens these bounds. Table~\\ref{tab:sensitivity_b2_full} reports the $n{=}17$ two-environment core evaluation. Cross-architecture validation is deferred to future work.\n\n\\subsection{Leave-One-Environment-Out Cross-Validation}\n\\label{sec:nve_loeo}\n\nTo assess whether $\\theta{=}1.5\\times$ generalizes beyond the in-sample evaluation, we perform leave-one-environment-out (LOEO) cross-validation across Walker ($n{=}15$), Cheetah ($n{=}5$), and PickCube ($n{=}2$). For each fold, we hold out all experiments from one environment, select the optimal accuracy-maximizing threshold range on the remaining training set, and evaluate the fixed $\\theta{=}1.5\\times$ on the held-out environment.\n\n\\begin{table}[h]\n\\centering\n\\caption{Leave-one-environment-out cross-validation of NVE threshold $\\theta=1.5\\times$.\nFor each fold, the threshold is validated on an environment whose data was \\emph{not} used\nto select $\\theta$. The optimal threshold range on each training set is reported;\n$\\theta=1.5$ falls within the optimal range in all three folds.}\n\\label{tab:nve_loeo}\n\\begin{tabular}{lccccc}\n\\toprule\nHeld-out & $N_{\\text{train}}$ & $N_{\\text{test}}$ & $\\theta_{\\text{opt}}$ range & Test Accuracy & Test AUROC \\\\\n\\midrule\nPickCube & 20 & 2 & $(1.45,\\, 1.53]$ & 2/2 (1.000) & 1.000 \\\\\nCheetah  & 17 & 5 & $(1.45,\\, 1.53]$ & 5/5 (1.000) & 1.000 \\\\\nWalker   &  7 & 15 & $(1.00,\\, 3.78)$ & 14/15 (0.933) & 0.963 \\\\\n\\midrule\n\\textbf{Mean} & — & — & — & \\textbf{0.978} & \\textbf{0.988} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe threshold $\\theta{=}1.5\\times$ falls within the optimal accuracy range for all three training folds: $(1.45, 1.53]$ when Walker data is available, and the wider $(1.00, 3.78)$ when training on Cheetah$+$PickCube only (where CIVO and non-CIVO NVE values are well-separated). The single cross-validation error is exp\\_008e\\_v3 seed~2 (Walker), an IRD collapse mechanistically distinct from CIVO (\\S\\ref{sec:roc_analysis}). Mean held-out accuracy is 0.978 and mean AUROC is 0.988, confirming that $\\theta{=}1.5\\times$ generalizes across environments without retuning.\nPickCube fold confidence intervals remain wide (Clopper-Pearson 95\\% CI: $[0.158, 1.000]$) due to $N_{\\text{test}}{=}2$.\n\n\\subsection{Leave-One-Config-Out Cross-Validation}\n\\label{sec:nve_loco}\n\n\\paragraph{Leave-One-Config-Out Cross-Validation.}\nTo rule out threshold overfitting to any particular experimental configuration, we perform leave-one-config-out (LOCO) cross-validation over $K{=}12$ configuration groups (e.g., \\texttt{008d\\_civo\\_trigger}, \\texttt{frozen\\_dt\\_emb}, \\texttt{tcn}; $n{=}56$ total). Each fold holds out all experiments from one configuration, selects the F1-maximizing threshold on the remaining $K{-}1$ groups, and evaluates on the held-out group.\n\nIn $10/12$ folds, the training-optimal threshold falls within $\\pm 0.05$ of $\\theta{=}1.5\\times$ (mean $1.61 \\pm 0.23$, range $[1.47, 2.12]$). The two folds selecting a higher threshold ($\\theta{=}2.1$; \\texttt{008d\\_civo\\_trigger} and \\texttt{tcn}, both predominantly CIVO-positive) perform \\emph{worse} on their held-out sets than $\\theta{=}1.5$ (accuracy $0.78$/$0.88$ vs.\\ $1.00$/$1.00$), confirming that the fixed threshold generalizes better than per-fold optimization in these cases. Cross-validated accuracy at $\\theta{=}1.5$ is $53/56 = 94.6\\%$, identical to the in-sample result, with train AUROC consistently high across folds ($0.988 \\pm 0.003$). The three misclassifications are the same mechanistically distinct false positives identified in \\S\\ref{sec:roc_analysis}: two frozen-embedding transients (exp\\_047, exp\\_057) and one mitigation-config transient (exp\\_008e\\_v3\\_subsample). No CIVO-positive configuration is missed in any fold (FN${=}0$ across all 12 folds).\n\n% --- APPENDIX B: Factorial Ablation Details ---\n\n\\section{Factorial Ablation Details}\n\\label{sec:appendix_factorial}\n\nThis appendix provides the full factorial ablation results summarized in \\S\\ref{sec:f3f5_summary} of the main text.\n\n\\paragraph{Embedding gradient analysis.}\nTable~\\ref{tab:three_way_emb} isolates embedding \\emph{trainability} as the necessary condition for CIVO by comparing four gradient conditions under otherwise identical configurations ($H{=}8$, subsample ON, $\\dt{=}2$ imagination).\n\n\\begin{table}[h]\n\\centering\n\\caption{$\\dt$-embedding gradient conditions on Walker Walk. Any gradient pathway updating $e_{\\dt}$ is sufficient to induce CIVO; freezing or removing the embedding dramatically reduces severity.}\n\\label{tab:three_way_emb}\n\\footnotesize\n\\begin{tabular}{lccccl}\n\\toprule\nCondition & Grad flow & Exp(s) & NVE peak & Eval & CIVO \\\\\n\\midrule\nTrained & all & 008d, 059 & $1.53$--$4.72\\times$ & 64--268 & 5/5 \\\\\nReward detach & obs+KL only & 044 & $4.45\\times$ & 44$\\to$538$^\\dagger$ & 1/1 \\\\\nFull SGS & KL only & 018 & $1.66\\times$ & 448 & 1/1$^*$ \\\\\nFrozen & none & 042, 015b, 047, 057 & $0.19$--$1.88\\times$$^\\ddagger$ & 204--612 & 2/4 \\\\\nRemoved & N/A & 008f & $0.97$--$1.41\\times$ & 307--503 & 0/3 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$Full-SGS seed~1 (NVE $1.66\\times$); seed~2 collapsed. $^\\dagger$Self-corrected at ${\\sim}175$K (eval 44$\\to$538, 59\\% baseline; 224K run). $^\\ddagger$Exp\\_047 (NVE $1.71\\times$) and Exp\\_057 (NVE $1.88\\times$): both transient, self-correcting within 20K steps.\\par}\n\\end{table}\n\n\\paragraph{Controlled three-way causal ablation.}\nExperiments 067--069 provide a minimal causal ablation on Walker Walk (seed${=}1$), varying \\emph{only} the $\\dt$-embedding treatment while holding all other hyperparameters fixed ($H{=}8$, subsample ON, $\\dt{=}2$ imagination). Table~\\ref{tab:causal_ablation} shows that trained $\\dt$-embedding is necessary and sufficient for CIVO: freezing the embedding (gradient flow blocked, embedding weights still present) eliminates CIVO as completely as removing the embedding ($d{=}0$), ruling out the alternative hypothesis that embedding \\emph{presence} alone causes CIVO. Combined with all prior seeds, trained $\\dt$-embedding triggers CIVO in 10/10 multi-joint locomotion seeds (8 Walker, 2 Cheetah) versus 0/8 controls (Fisher exact $p < 0.0001$).\n\n\\begin{table}[h]\n\\centering\n\\caption{Three-way causal ablation (Walker Walk, seed${=}1$). Only the $\\dt$-embedding treatment varies; all other configuration is identical. Trained embedding triggers CIVO; frozen and removed do not.}\n\\label{tab:causal_ablation}\n\\footnotesize\n\\begin{tabular}{llccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Embedding} & \\textbf{NVE peak} & \\textbf{Eval final} & \\textbf{CIVO} \\\\\n\\midrule\n\\rowcolor{gray!15}\n068 & Trained ($d{=}32$) & $6.57\\times$ & 39.1 & Yes (alert @85K) \\\\\n067 & Frozen ($d{=}32$, \\texttt{req\\_grad=F}) & $0.40\\times$ & 281.5 & No \\\\\n069 & Removed ($d{=}0$) & $0.66\\times$ & 237.8 & No \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe reward-detach condition (exp\\_044, \\texttt{reward\\_dt\\_emb\\_detach=True}) uses a backward hook to block reward-head gradients from reaching $e_{\\dt}$, complementing the framework-level Reward SGS (exp\\_016e). Both yield the same directional result---CIVO onset not prevented---ruling out implementation artifacts. Exp\\_044 exhibits delayed CIVO onset (${\\sim}95$K vs.\\ typical $25$--$35$K), consistent with reduced but non-zero gradient pressure on $e_{\\dt}$. Over a full 224K run, exp\\_044 self-corrects: eval recovers from 44 (95K) to 538 (215K, 59\\% baseline), but this recovery is incomplete compared to spontaneous recovery without gradient intervention (exp\\_045: 868, 95\\% baseline). The lower asymptote suggests that selectively disrupting gradient flow may create optimization difficulties beyond CIVO itself.\n\nTable~\\ref{tab:factorial_design} summarizes the experimental configurations.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Factorial design. Each row specifies one experimental configuration. \\textbf{Emb}: $\\dt$-embedding mode. \\textbf{Sub}: temporal subsampling. \\textbf{H}: imagination horizon. \\textbf{Imag $\\dt$}: temporal resolution used during imagination.}\n\\label{tab:factorial_design}\n\\small\n\\setlength{\\tabcolsep}{3.5pt}\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\n\\textbf{ID} & \\textbf{Purpose} & \\textbf{Emb} & \\textbf{Sub} & \\textbf{H} & \\textbf{Imag $\\dt$} \\\\\n\\midrule\n001 & Reference baseline & --- & --- & 15 & 1 \\\\\n006 & Fixed $\\dt{=}2$ & trn & on & 15 & 2 \\\\\n007 & Fixed $\\dt{=}4$ & trn & on & 15 & 4 \\\\\n\\midrule\n008a & Unexposed emb ctrl & exp$^a$ & off & 15 & 2 \\\\\n008c & Horizon control & exp$^a$ & off & 8 & 2 \\\\\n008d & Collapse condition & trn & on & 8 & 2 \\\\\n008e\\_v3 & $\\dt{=}1$ imag control & trn & on & 15 & 1 \\\\\n008f & Causal ablation & --- & on & 8 & 2 \\\\\n\\midrule\n015b & Frozen-emb ctrl & frz$^b$ & on & 8 & 2 \\\\\n016e & Stop-grad (reward) & trn$^\\dagger$ & on & 8 & 2 \\\\\n018 & Full-SGS & trn$^\\ddagger$ & on & 8 & 2 \\\\\n\\midrule\n005 & Learned gate & adaptive & off & 15 & learned \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{-2pt}\n{\\raggedright\\footnotesize\ntrn = trained ($d{=}32$, exposed to $\\dt{>}1$ data via subsample ON);\nexp$^a$ = trained ($d{=}32$) but never exposed to $\\dt{>}1$ data (subsample OFF);\nfrz$^b$ = frozen random projection ($d{=}32$, \\texttt{requires\\_grad=False});\n--- = removed ($d{=}0$).\\\\\n$^\\dagger$ \\texttt{reward\\_dt\\_emb\\_detach=True}; $^\\ddagger$ all non-KL gradients to \\texttt{dt\\_emb} detached.\\par}\n\\end{table}\n\n\\subsection{F3: Unexposed Temporal Embedding Suppresses Value Drift}\n\\label{sec:f3}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig3_factorial_grid.pdf}\n\\caption{Factorial isolation of CIVO trigger. Only the combination of trained $e_{\\dt}$ and multi-rate data (upper-left cell) produces pathological NVE. Neither factor alone is sufficient.}\n\\label{fig:factorial_grid}\n\\end{figure}\n\nThe empirical finding that trained embedding \\emph{plus} multi-rate exposure jointly predict CIVO rests on two complementary controls that each remove one factor while holding the other constant.\n\n\\paragraph{Evidence A: exposure is necessary (exp\\_008a).}\nExp\\_008a uses a trained embedding ($d{=}32$, gradients enabled) that is never exposed to $\\dt{>}1$ transitions during world-model training (subsample OFF). Despite sharing the same embedding architecture as exp\\_008d, its NVE remains in the $0.83$--$0.93\\times$ range across 3 seeds (105K steps). Performance follows two V-shaped recovery cycles, reaching 777.7 at 105K (85\\% of baseline). The critical factor is not the embedding's capacity to represent temporal information, but its adaptation to multi-rate data that enables precise but inaccurate $\\dt{>}1$ state predictions within the RSSM.\n\nThis contrasts with exp\\_006 (trained $e_{\\dt}$, subsample ON, $H{=}15$), where NVE accelerates from $1.61\\times$ at 45K to $2.31\\times$ at 55K before catastrophic collapse to 132.9 at 65K. Both experiments use identical trained embeddings ($d{=}32$, gradients enabled) and $H{=}15$, differing only in whether the world model sees $\\dt{>}1$ transitions during training. This confirms that multi-rate data exposure, not embedding architecture, is the operative variable.\n\n\\paragraph{Evidence B: trainability is necessary (exp\\_015b).}\nExp\\_015b uses a frozen random-projection embedding ($d{=}32$, \\texttt{requires\\_grad=False}, subsample ON, $H{=}8$), the same multi-rate data regime as exp\\_008d, but with a non-trainable temporal signal. Despite full exposure to $\\dt{>}1$ transitions, the NVE peaks at $1.45\\times$ at 55K but does not sustain escalation: it retreats to $0.65\\times$ by 65K and settles at $0.42\\times$ by 105K (trajectory: $0.81 \\rightarrow 1.26 \\rightarrow 1.45 \\rightarrow 0.65 \\rightarrow 1.05 \\rightarrow 0.47 \\rightarrow 0.39 \\rightarrow 0.42$). The transient peak approaches but does not exceed the $1.5\\times$ CIVO threshold, and critically, the ratio self-corrects rather than exhibiting the monotonic escalation seen in trained-embedding runs. Final evaluation reaches only 204.2 at 105K, low but through a qualitatively different failure mode than CIVO. Actor loss approaches zero (gradient starvation; see \\S\\ref{sec:pathways}), the frozen embedding provides no useful gradient signal for temporal adaptation.\n\nThe contrast with exp\\_008d is stark: under identical data conditions (subsample ON, $H{=}8$), the trained embedding drives NVE to $4.12\\times$ with sustained monotonic escalation ($1.78 \\rightarrow 1.71 \\rightarrow 2.09 \\rightarrow 4.12$) and precedes full collapse (eval 82.8), while the frozen embedding peaks transiently at $1.45\\times$ before self-correcting to $0.42\\times$, a qualitative difference between sustained and transient overestimation. This demonstrates that a $\\dt$-embedding must be able to \\emph{co-adapt} with RSSM dynamics to produce the systematic reward-prediction bias that drives CIVO; a static random projection, regardless of its exposure to multi-rate data, cannot create this bias.\n\nTogether, these two controls establish that in all tested configurations, CIVO occurs only with the \\emph{joint} presence of (i)~a trainable embedding that can co-adapt with RSSM dynamics, and (ii)~multi-rate training data that drives this co-adaptation toward biased temporal predictions. Neither factor alone is sufficient.\n\nCross-environment validation on Cheetah Run replicates the empirical pattern: trained $e_{\\dt}$ precedes CIVO in both tested seeds (exp\\_010b, 2 seeds, NVE $8.27$--$108.52\\times$, collapse to 51.7/0.83) while removing the embedding eliminates it (exp\\_024b, 2 seeds, NVE $<0.2\\times$, eval 96.5/77.3). Freezing the embedding on Cheetah (exp\\_046, NVE${=}1.35\\times$ vs.\\ trained $70.64\\times$, a $52\\times$ reduction) further confirms that embedding trainability, not architecture, drives CIVO. This extends the sufficiency finding from Walker Walk to a second locomotion environment with qualitatively different dynamics (6-joint vs.\\ 2-joint).\n\n\\begin{table}[ht]\n\\centering\n\\small\n\\caption{Causal isolation: $e_{\\dt}$ configuration $\\times$ multi-rate data exposure. The combination of trained embedding and multi-rate exposure is the sole predictor of CIVO in tested configurations. Neither factor alone is sufficient.}\n\\label{tab:causal_matrix}\n\\begin{tabular}{lcc}\n\\toprule\n& Multi-rate data (\\textsc{on}) & Single-rate data (\\textsc{off}) \\\\\n\\midrule\nTrained $e_{\\dt}$ & exp\\_008d: \\textbf{CIVO} & exp\\_008a: healthy \\\\\n & NVE 4.12$\\times$, collapse & NVE 0.93$\\times$ \\\\\n\\midrule\nFrozen $e_{\\dt}$ & exp\\_015b: grad.\\ starvation & --- \\\\\n & peak NVE 1.45$\\times$ (transient) & \\\\\n\\midrule\nRemoved $e_{\\dt}$ & exp\\_008f: no CIVO & --- \\\\\n & NVE $\\leq$0.97$\\times$ & \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOnly the upper-left cell (trained embedding with multi-rate exposure) precedes CIVO (Table~\\ref{tab:causal_matrix}). This 2$\\times$2 structure establishes that both factors are jointly sufficient in tested configurations.\n\n\\subsection{F4: Degradation Scales Monotonically with \\texorpdfstring{$\\dt$}{dt}}\n\\label{sec:f4}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig5_dt_amplification.pdf}\n\\caption{Peak evaluation return as a function of imagination $\\dt$. Performance degrades monotonically: $\\dt{=}1$ (915.7) $>$ $\\dt{=}2$ (485.3, $-47\\%$) $>$ $\\dt{=}4$ (176.9, $-81\\%$).}\n\\label{fig:dt_amplification}\n\\end{figure}\n\nThe magnitude of degradation scales monotonically with the imagination step size (Figure~\\ref{fig:dt_amplification}). From the $\\dt{=}1$ baseline (915.7 at 105K), fixed $\\dt{=}2$ (exp\\_006) achieves a peak of only 485.3 ($-47\\%$), and fixed $\\dt{=}4$ (exp\\_007) peaks at 176.9 ($-81\\%$). This monotonic relationship is consistent with compounding model error: larger temporal gaps amplify the RSSM's prediction inaccuracy at each imagination step, and these errors accumulate across the rollout horizon.\n\n\\subsection{F5: Imagination Horizon and Subsampling Are Secondary Factors}\n\\label{sec:f5}\n\nNeither horizon length nor temporal subsampling precedes collapse without multi-rate data exposure: both trained-but-unexposed configurations (008a, 008c) maintain $\\nve < 0.93\\times$ (\\S\\ref{sec:f3}), while the trained-and-exposed counterpart (008d) collapses with $\\nve = 4.12\\times$.  The no-embedding configurations show cross-seed variance (008f: 503.0 vs.\\ 009c: 148.3) but neither exhibits $\\nve > 1.5\\times$; low evaluation alone does not indicate CIVO.\n\nThe $3.2\\times$ performance gap (008a: 777.7 vs.\\ 008c: 240.9) quantifies the horizon effect independently of CIVO, as both conditions maintain healthy NVE ($\\leq$0.93$\\times$).\n\n% --- APPENDIX C: Full Analysis & Discussion ---\n\n\\section{Full Analysis \\& Discussion}\n\\label{sec:appendix_analysis}\n\nThis appendix provides the complete mechanistic analysis summarized in Section~\\ref{sec:discussion} of the main text.\n\n\\subsection{The CIVO Mechanism}\n\\label{sec:civo_mechanism}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig4_mechanism_diagram.pdf}\n\\caption{CIVO mechanism diagram. The trained $\\dt$-embedding enables asymmetric reward prediction fidelity, initiating a feedback loop: biased RSSM rewards $\\to$ optimistic critic values $\\to$ actor exploitation $\\to$ reinforced state-distribution skew.}\n\\label{fig:civo_mechanism}\n\\end{figure}\n\n\\begin{table}[h]\n\\centering\n\\caption{RSSM fidelity at $\\dt{=}1$ vs.\\ $\\dt{=}2$. Trained embedding (008d) produces $2.78\\times$ reward gap; removing it (008f) eliminates the gap but degrades absolute prediction.}\n\\label{tab:rssm_fidelity}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{3}{c}{\\textbf{obs\\_MSE}} & \\multicolumn{3}{c}{\\textbf{reward\\_MAE}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\n\\textbf{Config} & $\\dt{=}1$ & $\\dt{=}2$ & Gap & $\\dt{=}1$ & $\\dt{=}2$ & Gap \\\\\n\\midrule\nBaseline & 13.49 & 27.50 & 2.04$\\times$ & 0.0102 & 0.0159 & 1.56$\\times$ \\\\\n008d (trained) & 41.31 & 53.67 & 1.30$\\times$ & 0.0568 & 0.1579 & 2.78$\\times$ \\\\\n008f (no emb) & 8.01 & 22.04 & 2.75$\\times$ & 0.7469 & 0.7526 & 1.01$\\times$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe RSSM fidelity analysis (Table~\\ref{tab:rssm_fidelity}) reveals the mechanistic core of CIVO (Figure~\\ref{fig:civo_mechanism}).  The trained $\\dt$-embedding enables the reward head to learn temporally differentiated predictions, but these predictions are asymmetrically accurate: reward MAE at $\\dt{=}1$ is $0.0568$, while at $\\dt{=}2$ it rises to $0.1579$, a $2.78\\times$ gap.  This gap is not an artifact of prediction difficulty alone; the no-embedding configuration (008f) exhibits a $1.01\\times$ gap, and the baseline shows $1.56\\times$.  The trained embedding actively amplifies the fidelity discrepancy by allowing the reward head to co-adapt with the temporal signal.\n\nThis asymmetric fidelity initiates a feedback loop with four stages: (1) the trained $\\dt$-embedding causes RSSM predictions at $\\dt > 1$ to carry systematically biased reward estimates; (2) the critic, trained entirely on imagined trajectories, internalizes these biased rewards as optimistic value estimates; (3) the actor exploits the overestimated regions of the value landscape, shifting its policy toward states that appear high-value only under the biased model; and (4) this policy shift further skews the distribution of imagined states, reinforcing the bias.  The diagnostic signature is a sustained $\\nve$ above $1.5\\times$, followed by evaluation collapse.\n\nA random-policy control experiment ($N{=}100$ rollouts, 95\\% bootstrap CI) decomposes CIVO into two necessary stages.  \\textbf{Stage~1 (dynamics bias):} even under a random policy, $\\dt{=}2$ imagination produces $1.68\\times$ higher mean reward than $\\dt{=}1$ in the trained-embedding model (008d): the RSSM prior already generates reward-favorable trajectories at $\\dt > 1$, independent of actor behavior.  \\textbf{Stage~2 (actor exploitation):} the trained actor learns to exploit these biased regions, amplifying the ratio to $2.90\\times$.  In the no-embedding control (008f), neither stage is present: the random-policy ratio is $1.11\\times$ and the trained-actor ratio is $0.98\\times$.  The decomposition attributes $\\approx 36\\%$ of the total effect to dynamics bias and $\\approx 64\\%$ to actor exploitation, which confirms that both stages are necessary for CIVO to manifest.\n\nThis mechanism is analogous to delusional bias \\citep{lu2018nondelusional}, but differs in origin: delusional bias arises from policy-class constraints, while CIVO is model-induced.  The consequence (policy exploitation of overestimated regions) is similar, but the causal pathway is distinct.\n\n\\paragraph{Signed reward error analysis.}\nTo test whether CIVO arises from one-step reward overprediction, we compute signed error (predicted $-$ actual) on posterior-conditioned RSSM predictions (Table~\\ref{tab:signed_error}). The trained-embedding model (008d) shows \\emph{negative} bias at $\\dt{=}2$ (mean signed error $-0.599$, only 8\\% of samples overpredicted), ruling out observation-level reward overprediction as the mechanism. The baseline is well-calibrated (mean SE $\\approx 0$), confirming methodological soundness. Value overestimation therefore occurs during \\emph{imagination-level} prior drift: the RSSM prior (unconditioned on observations) generates reward-favorable trajectories at $\\dt > 1$ (Stage~1 above, $1.68\\times$ ratio under random policy), and the critic accumulates these into overestimated returns. The one-step reward prediction is negatively biased when conditioned on real observations, but this posterior correction is unavailable during imagination. This also distinguishes CIVO from generic compounding error, which would produce \\emph{positive} signed error accumulating with horizon; the negative observation-level bias confirms that CIVO is a prior-drift phenomenon, not a reward-prediction artifact.\n\n\\begin{table}[h]\n\\centering\n\\caption{Signed reward error (predicted $-$ actual) on posterior-conditioned RSSM predictions. Negative values indicate underprediction. The trained-embedding model underpredicts at $\\dt{=}2$, ruling out observation-level reward overprediction as the CIVO mechanism.}\n\\label{tab:signed_error}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llrrrrr}\n\\toprule\n\\textbf{Config} & $\\dt$ & \\textbf{Mean SE} & \\textbf{Std} & \\textbf{\\%Over} & \\textbf{Actual} & \\textbf{Pred} \\\\\n\\midrule\nBaseline & 1 & $+0.001$ & 0.023 & 39.6\\% & 1.893 & 1.894 \\\\\n\\midrule\n008d (trained) & 1 & $+0.018$ & 0.072 & 61.8\\% & 0.361 & 0.379 \\\\\n008d (trained) & 2 & $\\mathbf{-0.599}$ & 0.722 & 8.0\\% & 0.721 & 0.121 \\\\\n\\midrule\n008f (no emb) & 1 & $-0.710$ & 0.704 & 14.0\\% & 0.921 & 0.211 \\\\\n008f (no emb) & 2 & $-1.645$ & 1.485 & 5.0\\% & 1.840 & 0.195 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Embedding geometry (exp\\_065).}\nTo characterize what the trained $\\dt$-embedding learns, we measure pairwise cosine similarity between $e_{\\dt{=}1}$ and $e_{\\dt{=}2}$ across training checkpoints for three trained seeds (two environments) and two frozen controls (Table~\\ref{tab:cosine_sim}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity between $e_{\\dt{=}1}$ and $e_{\\dt{=}2}$ vectors. Trained embeddings converge to near-opposite representations; frozen embeddings remain near-orthogonal throughout.}\n\\label{tab:cosine_sim}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llrrr}\n\\toprule\n\\textbf{Config} & \\textbf{Env} & \\textbf{cos@25K} & \\textbf{cos@75K} & \\textbf{Status} \\\\\n\\midrule\n008d s3 (trained) & Walker & $-0.87$ & $-0.70$ & CIVO \\\\\n059 s5 (trained) & Walker & $-0.94$ & $-0.86$ & CIVO \\\\\n010b s0 (trained) & Cheetah & $-0.90$ & $-0.84$ & CIVO \\\\\n\\midrule\n057 s2 (frozen) & Walker & $-0.15$ & $-0.15$ & Healthy \\\\\n058 s1 (frozen) & Cheetah & $+0.07$ & $+0.07$ & Healthy \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll trained seeds map $\\dt{=}1$ and $\\dt{=}2$ to nearly opposite directions (cosine similarity $-0.70$ to $-0.94$), consistent across both Walker and Cheetah environments. Frozen controls remain near-orthogonal (cosine $\\approx 0$) and constant across all checkpoints. The full pairwise cosine similarity matrix (Figure~\\ref{fig:pairwise_heatmap}) reveals that the near-antipodal relationship between $e_{\\dt{=}1}$ and $e_{\\dt{=}2}$ is the dominant structure: most other $\\dt$-pairs remain near-orthogonal ($|\\text{cos}| < 0.2$), indicating that the RSSM selectively maximizes separation along the $\\dt{=}1$ vs.\\ $\\dt{=}2$ axis rather than learning a globally structured embedding space.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.55\\columnwidth]{figures/paper/pairwise_heatmap.png}\n\\caption{Pairwise cosine similarity between all $\\dt$-embedding vectors (exp\\_008d, seed 3, step 75K). The $e_{\\dt{=}0}$--$e_{\\dt{=}1}$ pair exhibits strong anti-correlation ($-0.70$); remaining pairs are near-orthogonal, confirming that the learned geometry is dominated by a single antipodal axis.}\n\\label{fig:pairwise_heatmap}\n\\end{figure}\n\nThe magnitude of the learned separation---near-antipodal rather than merely distinct---provides converging evidence that the RSSM develops maximally differentiated internal representations for the two temporal scales, which in turn may contribute to the asymmetric reward fidelity gap reported in Table~\\ref{tab:rssm_fidelity} and replicated below.\n\n\\paragraph{Extended RSSM fidelity replication (exp\\_063).}\nTo validate the fidelity gap on independently trained checkpoints, we repeat the posterior-conditioned analysis with 15 episodes $\\times$ 40 test points $\\times$ 4 $\\dt$ levels (600 samples per model) on final checkpoints from three conditions (Table~\\ref{tab:rssm_fidelity_ext}).\n\n\\begin{table}[h]\n\\centering\n\\caption{RSSM fidelity analysis (training-time posterior-conditioned). Reward prediction gap remains the critical differentiator; observation reconstruction is paradoxically \\emph{better} with trained embedding. Independent final-checkpoint replication (exp\\_063, 008d seed~4) yields a reward gap of $2.7\\times$, confirming the qualitative pattern at lower magnitude.}\n\\label{tab:rssm_fidelity_ext}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{3}{c}{\\textbf{obs\\_MSE}} & \\multicolumn{3}{c}{\\textbf{reward\\_MAE}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\n\\textbf{Config} & $\\dt{=}1$ & $\\dt{=}2$ & Gap & $\\dt{=}1$ & $\\dt{=}2$ & Gap \\\\\n\\midrule\nBaseline (009d) & 16.08 & 23.49 & 1.46$\\times$ & 0.045 & 0.059 & 1.30$\\times$ \\\\\nCollapsed (008d) & 9.96 & 13.21 & 1.33$\\times$ & 0.057 & 0.178 & 3.11$\\times$ \\\\\nFrozen (057) & 11.14 & 14.95 & 1.34$\\times$ & 0.068 & 0.133 & 1.96$\\times$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe replication confirms the original fidelity gap pattern with two additional observations. First, the collapsed model achieves the \\emph{lowest} absolute obs\\_MSE at $\\dt{=}1$ (9.96 vs.\\ baseline 16.08), indicating that the trained $\\dt$-embedding improves world model quality overall---the pathology is selective degradation of reward predictions at longer horizons, not general model failure. Second, freezing the $\\dt$-embedding reduces the reward gap from $3.11\\times$ (training-time; $2.7\\times$ in independent replication) to $1.96\\times$, providing converging evidence for its role in preventing the co-adaptation loop while leaving residual multi-step reward prediction difficulty.\n\n\\paragraph{Value prediction analysis (exp\\_064).}\nTo examine the relationship between RSSM reward fidelity and critic value estimates, we compare critic predictions $V(s)$ against actual evaluation returns across three conditions (Table~\\ref{tab:value_pred}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Critic value predictions vs.\\ actual evaluation returns. The CIVO model's critic is well-calibrated to its $\\lambda$-return targets ($V(s) \\approx$ target) but both $V$ and targets are disconnected from reality (VE${=}3.03\\times$).}\n\\label{tab:value_pred}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lrrrr}\n\\toprule\n\\textbf{Config} & $V(s)$ & \\textbf{Eval} & \\textbf{VE ratio} & $V{-}\\text{target}$ \\\\\n\\midrule\nBaseline (001) & 665.9 & 938.9 & 0.71$\\times$ & $+0.001$ \\\\\nCIVO (008d) & 192.7 & 63.6 & \\textbf{3.03}$\\times$ & $+0.586$ \\\\\nNo emb (008f) & 116.5 & 306.5 & 0.38$\\times$ & $+0.316$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe paradox---$V(s)$ tracks its $\\lambda$-return targets faithfully yet overestimates actual performance by $3\\times$---provides converging evidence for the hypothesized mechanism in which CIVO operates upstream of the critic: the world model generates inflated imagination trajectories that the critic learns faithfully, producing targets disconnected from reality. In the baseline, VE${<}1.0$ throughout training because $V(s)$ reflects discounted imagined returns over $H{=}15$ steps, naturally lower than undiscounted episodic evaluation. The CIVO model crosses VE${=}1.0$ at step 55K and reaches $3.03\\times$ by 105K, with the gap widening as the actor exploits the overoptimistic critic.\n\n\\paragraph{Actor entropy dynamics under CIVO.}\nExtended training of collapsed configurations reveals a distinctive temporal sequence: evaluation return collapses first, followed by actor entropy explosion ${\\sim}35$K steps later. In the most severe case (EG~v4), entropy rises from $-5.21$ to $+3.22$ nats at a rate of $+2.11$ nats/10K steps, with returns declining from 583 to 93 between steps 60K--120K. A second collapsed run (EG~v5) shows $+0.61$ nats/10K with comparable return degradation (583$\\to$102). By contrast, healthy baselines exhibit gradual entropy drift at $+0.07$ to $+0.22$ nats/10K---15--30$\\times$ slower---with returns stable above 900. The return-before-entropy temporal ordering is consistent with the causal chain: delusional critic $\\to$ bad actor gradients $\\to$ policy destabilization. The entropy explosion is a lagging indicator; the NVE diagnostic detects CIVO onset ${\\sim}35$K steps before entropy rises, consistent with its use as an early-warning signal (\\S\\ref{sec:appendix_sensitivity}).\n\n\\subsection{Selective Gradient Stopping and Gradient Decomposition}\n\\label{sec:sgs_gradient_analysis}\n\n\\subsubsection{Gradient Decomposition Results}\n\\label{sec:gradient_decomposition}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/fig3_gradient_decomposition.pdf}\n\\caption{Gradient contribution to $e_{\\Delta t}$ by loss component at two training checkpoints. The reward head contributes the largest share (38--49\\%) yet reward-only SGS (exp\\_016e) fails; the observation decoder channel (16--22\\%) carries the critical $\\dt$-specific spatial information that drives the RSSM fidelity gap.}\n\\label{fig:gradient_decomp}\n\\end{figure}\n\nExp\\_016e collapses in the same qualitative pattern as the unmodified control: peak evaluation 326.7 at 75K steps followed by catastrophic decline to 31.7 at 95K, with NVE reaching $10.42\\times$. The SGS intervention neither prevented nor attenuated CIVO.\n\nTo explain this null result, we performed a gradient decomposition analysis using \\texttt{torch.autograd.grad} to measure each loss component's contribution to $\\nabla_\\theta e_{\\Delta t}$, where $\\theta$ denotes the temporal embedding parameters. Table~\\ref{tab:gradient_decomposition} reports the results.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Gradient contributions to the temporal embedding $e_{\\Delta t}$ by loss component, measured via \\texttt{torch.autograd.grad} with training configuration \\texttt{gate\\_fixed\\_dt=2}. Gradient norms are $\\ell_2$ norms of $\\nabla_\\theta \\mathcal{L}_i$ for each loss $\\mathcal{L}_i$.}\n\\label{tab:gradient_decomposition}\n\\small\n\\begin{tabular}{lrrrr}\n\\toprule\n& \\multicolumn{2}{c}{\\textbf{@55K}} & \\multicolumn{2}{c}{\\textbf{@112K}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nLoss component & Share & (\\%) & Share & (\\%) \\\\\n\\midrule\nReward head & --- & 49.0 & --- & 38.1 \\\\\nKL dynamics & --- & 34.7 & --- & 40.4 \\\\\nObservation decoders & --- & 16.3 & --- & 21.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe gradient decomposition reveals a counterintuitive structure: the reward head provides the largest gradient contribution (49.0\\% at 55K, 38.1\\% at 112K), yet reward-only SGS (exp\\_016e) fails catastrophically (NVE $10.42\\times$). The observation decoder channel contributes the smallest share (16.3\\% at 55K, 21.5\\% at 112K) yet carries the critical $\\dt$-specific spatial information.  This dissociation between gradient magnitude and causal importance explains why exp\\_016e, which targets the largest pathway, is functionally insufficient for CIVO prevention.\n\nThe gradient structure is relatively stable across training (reward shifts from 49\\% to 38\\%, obs from 16\\% to 22\\%, KL from 35\\% to 40\\%), unlike what a magnitude-based account would predict. The reward head's large gradient contribution reflects the scalar reward prediction task's sensitivity to temporal embedding parameters, but this gradient does not encode $\\Delta t$-specific structural information about spatial dynamics. The observation decoder channel, despite its smaller magnitude, is the only pathway that encodes how the RSSM should differentially predict multi-dimensional proprioceptive states across temporal scales.\n\n\\paragraph{Why the smallest channel is causally critical.} The observation decoder is the only loss component whose gradients encode how the RSSM should differentially predict multi-dimensional proprioceptive states ($14$ orientations, $9$ velocities, $1$ height) across temporal scales.  This $\\dt$-specific spatial information shapes the latent state representation in ways that propagate to reward prediction: the RSSM fidelity gap ($2.78\\times$ reward MAE ratio, Table~\\ref{tab:rssm_fidelity}) arises because the temporal embedding learns to produce latent states that are spatially biased at $\\dt{>}1$, not because the reward head directly learns scale-dependent biases.  Full-SGS targets this causal chain by preventing observation-decoder gradients from updating $e_{\\Delta t}$, though its 0/2 CIVO elimination rate on Walker (seed~1: NVE reduced from $4.12\\times$ to $1.66\\times$ but remains CIVO-positive; seed~2: collapsed) indicates that breaking the gradient pathway alone does not fully eliminate the vulnerability.\n\n\\subsubsection{Implications for the CIVO Mechanism}\n\\label{sec:sgs_implications}\n\nThe gradient decomposition reveals that gradient magnitude and causal importance are decoupled in CIVO.\n\n\\paragraph{Gradient importance $\\neq$ gradient magnitude.} The reward head contributes the largest gradient share (38--49\\%) to $e_{\\Delta t}$, yet reward-only SGS fails.  The observation decoder contributes the smallest share (16--22\\%), yet its removal (via Full-SGS) is necessary for CIVO mitigation.  This dissociation arises because the reward head's gradient, while large, does not encode $\\dt$-specific structural information: it adjusts $e_{\\Delta t}$ to minimize a scalar prediction error that is largely $\\dt$-invariant.  The observation decoder's gradient, though smaller, encodes how the RSSM should differentially reconstruct 24-dimensional proprioceptive states across temporal scales. This is the channel through which $e_{\\Delta t}$ learns scale-dependent latent biases.\n\n\\paragraph{Reframing the intervention target.} Any gradient-level strategy that targets the reward head alone (reward prediction regularization, reward-conditioned value clipping, or reward-only SGS) targets the largest pathway but not the informationally critical one.  The failure of exp\\_016e (NVE $10.42\\times$) despite detaching the dominant gradient source confirms this.  Full-pathway SGS (exp\\_018) detaches $e_{\\Delta t}$ from all non-KL gradients, retaining only the KL dynamics contribution (34--40\\%).  However, this intervention eliminates CIVO in neither seed: seed~1 shows partial mitigation (eval 448.3, peak NVE $1.66\\times$, still CIVO-positive) while seed~2 collapses (eval 40.8). Removing the observation decoder gradient channel is thus contributory but not sufficient. Figure~\\ref{fig:civo_decomposition} decomposes evaluation returns across conditions.\n\n\\begin{figure}[ht]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/fig2_civo_decomposition.pdf}\n\\caption{CIVO decomposition: peak and final (105K step) evaluation returns on Walker Walk across four conditions. \\textbf{Baseline} (001): vanilla DreamerV3. \\textbf{Trained dt-emb} (008d)\\protect\\footnotemark: learned $d{=}32$ temporal embedding with multi-rate data. \\textbf{Full-SGS} (s1, s2): trained embedding with all non-KL gradients detached from $e_{\\dt}$. Trained $\\dt$-embedding degrades peak eval by $73\\%$ and final eval by $86\\%$. Full-SGS seed~1 shows partial mitigation ($-51\\%$ final, NVE $1.66\\times$, still CIVO-positive) while seed~2 collapses ($-96\\%$ final). CIVO elimination rate $= 0/2$.}\n\\label{fig:civo_decomposition}\n\\end{figure}\n\\footnotetext{Experiment 008d terminated at 55K steps; the 105K data point uses continuation run 009e under identical configuration.}\n\nCross-environment validation on Cheetah Run (exp\\_021) further clarifies the role of Full-SGS.  The intervention did not prevent the initial CIVO onset: NVE peaked at $9.94\\times$ at 45K (comparable to the unmitigated exp\\_010b's $8.27\\times$).  However, unlike exp\\_010b, which collapsed permanently to eval 51.7, exp\\_021 self-corrected within ${\\sim}$10K steps, with sustained NVE dropping to $0.34\\times$ (55K--105K) and final evaluation recovering to 221.5.  This transient self-correcting trajectory is not attributable to the SGS intervention: the initial CIVO onset and peak severity are comparable to the unmitigated case, and the self-correction may reflect Cheetah Run's simpler dynamics rather than SGS efficacy.  Performance remains at 38.7\\% of baseline (572.5), likely because Full-SGS over-aggressively blocks actor gradients (actor gradient norms near zero throughout training).  Combined with exp\\_018's Walker results (0/2 CIVO elimination), these findings yield a 0/3 elimination rate across environments, indicating that gradient-level interventions alone do not eliminate the CIVO vulnerability. Additional mechanisms (e.g., forward-pass conditioning effects, residual capacity-dependent instabilities) operate beyond the gradient pathway.\n\n\\paragraph{Connection to RSSM fidelity analysis.} The trained-embedding condition (exp\\_008d) shows a $2.78\\times$ reward gap between $\\Delta t{=}1$ and $\\Delta t{=}2$ transitions (Table~\\ref{tab:rssm_fidelity}).  This gap arises because the observation decoder gradients shape $e_{\\Delta t}$ to produce latent states that are spatially biased at $\\dt{>}1$, and the reward head inherits these biases \\textit{through the latent state} rather than learning them directly.  The reward head's large gradient contribution reflects sensitivity to $e_{\\Delta t}$'s parameters but not causal responsibility for the fidelity gap.\n\n\\subsubsection{Entropy Dynamics Across Configurations}\n\\label{sec:entropy_dynamics}\n\n\\begin{figure}[ht]\n\\centering\n\\includegraphics[width=0.85\\columnwidth]{figures/fig4_entropy_dynamics.pdf}\n\\caption{Actor entropy trajectories for three configurations. All start at ${\\sim}8$ nats and converge to similar values (${\\sim}{-}4.5$ to ${-}5$). The CIVO-triggering configuration (008d, red) follows a normal entropy reduction trajectory; the divergence from the control (008f) is subtle in entropy space, consistent with CIVO operating through the value channel rather than the entropy channel. 018v2 (Full-SGS, seed~1) shows slightly lower terminal entropy.}\n\\label{fig:entropy_dynamics}\n\\end{figure}\n\n\\subsubsection{Exp\\_016e Reinterpreted as Stochastic Variation}\n\\label{sec:016e_reinterp}\n\nThe gradient decomposition establishes that exp\\_016e targets the largest gradient pathway (reward: 38--49\\%) but not the informationally critical one (observation decoders: 16--22\\%).  The apparent timing differences between exp\\_016e and exp\\_008d (later collapse onset, 75K vs.\\ 25K, and higher peak evaluation, 326.7 vs.\\ 167.2) must be attributed to stochastic variation rather than SGS effects, since the critical observation decoder channel remains intact.  All three trajectories (exp\\_008d, exp\\_009b, exp\\_016e) share the invariant identified by the NVE diagnostic: each crosses the $1.5\\times$ pathological threshold at some point during training.\n\n\\subsection{Post-CIVO Outcomes: Why Seeds Diverge}\n\\label{sec:seed_divergence}\n\n\\begin{table}[ht]\n\\centering\n\\caption{Post-CIVO outcomes for all ten CIVO-positive runs across two environments. Peak/Final NVE measured in the 35K+ window.}\n\\label{tab:post_civo}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccl}\n\\toprule\n\\textbf{Env} & \\textbf{Seed} & \\textbf{Peak} & \\textbf{Final} & \\textbf{Eval} & \\textbf{Outcome} \\\\\n\\midrule\nWalker & s1 (008d) & 4.12$\\times$ & 4.12$\\times$ & 82.8 & Full collapse \\\\\nWalker & s2 (009b) & 1.62$\\times$ & 0.38$\\times$ & 267.9 & Transient CIVO \\\\\nWalker & s3 (008d\\_s3) & 1.53$\\times$ & 1.53$\\times$ & 268$^\\diamond$ & Late-onset collapse \\\\\nWalker & s4 (008d\\_s4) & 4.62$\\times$ & 4.62$\\times$ & 63.6 & Full collapse \\\\\nWalker & s5 (059) & 4.72$\\times$ & 1.22$\\times$ & 95.8 & Collapse$^\\dagger$ \\\\\n\\midrule\nCheetah & s1 (010b) & 8.27$\\times$ & 8.27$\\times$ & 51.7 & Full collapse \\\\\nCheetah & s0 (078) & 4.10$\\times$ & 0.29$\\times$ & 119.5 & Self-correcting$^\\ddagger$ \\\\\nCheetah & s0 (010b\\_s0) & 108.52$\\times$ & 108.52$\\times$ & 0.83 & Full collapse \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^\\diamond$ Transitional; train returns still declining at 105K. $^\\dagger$~NVE self-corrected ($4.72\\times$ $\\to$ $1.22\\times$) but policy did not recover (eval 10.5\\% of baseline). $^\\ddagger$~Peak NVE $4.10\\times$ at 75K; eval 213.7$\\to$26.1$\\to$119.5 (26.7\\% of baseline exp\\_077, 448.1).\\par}\n\\end{table}\n\nAll ten CIVO-positive runs cross the $\\nve > 1.5\\times$ threshold (Table~\\ref{tab:post_civo}), yet the downstream damage is stochastic.\\footnote{Exp\\_009e was excluded from multi-seed analyses due to a seed configuration error (default seed=0, identical to exp\\_008d).}  Sustained collapse is the majority outcome (6/10 runs). Three runs self-correct (Walker seed~2 and both Cheetah seeds, including exp\\_078 which recovers from 26.1 to 119.5 at 105K); one (Walker seed~5) shows onset without sustained collapse---NVE self-corrects ($4.72\\times \\to 1.22\\times$) but the policy remains collapsed (eval 10.5\\% of baseline). Cheetah seed~1 (010b) exhibits more extreme overestimation (peak NVE $8.27\\times$) than Walker seeds ($1.53$--$4.62\\times$), consistent with the Cheetah reward scale amplifying the fidelity gap.  We hypothesize that the divergence relates to the critic's representational capacity at the time of CIVO onset.  \\citet{lyle2022capacity} demonstrate that deep RL networks suffer progressive capacity loss, in which early-learned features become increasingly difficult to overwrite.  If the critic's capacity is already partially consumed when CIVO injects overestimation, the network cannot recalibrate (seed~0); if sufficient capacity remains, the critic can absorb transient overestimation and recover (seed~2).\n\n\\paragraph{A fourth trajectory: CIVO-induced persistent value collapse.}\nObs-decoder SGS seed~3 (exp\\_025) exhibits a trajectory not observed in the untreated seeds: healthy through 105K ($\\nve < 1.0\\times$, eval 818.6), CIVO onset at 135K ($\\nve = 5.47\\times$, eval 67.0), followed by evaluation recovery (590.2 at 215K, 64\\% of baseline) but persistent value collapse ($\\nve = 0.14\\times$, value mean 80.6). The critic undershoots after the CIVO episode, suggesting that CIVO-induced representational damage persists even when the policy partially recovers. This contrasts with transient CIVO (seed~2, 009b), where both value and evaluation recover jointly, and with full collapse (seed~1, 008d), where neither recovers. Seed~4 exhibits the same terminal value collapse ($\\nve = 0.14\\times$ at 215K, eval 242), suggesting this overcorrection is systematic rather than seed-specific. The pattern adds a fourth post-CIVO outcome---policy recovery with critic damage---to the three documented in Table~\\ref{tab:post_civo}.\n\n\\subsubsection{Failure and Degradation Mode Taxonomy}\n\nTable~\\ref{tab:failure_modes} classifies the seven distinct failure and degradation modes observed across all experimental configurations. The taxonomy reveals that CIVO is not a single failure mode but a family of related pathologies, with the trained $\\dt$-embedding creating vulnerability through at least three independent mechanisms: value-driven collapse (monotonic, late-onset, and SGS-resistant CIVO), entropy-driven instability (IRD collapse), and gradient-mediated effects (gradient starvation, SGS-paradoxical worsening).\n\n\\begin{table}[ht]\n\\centering\n\\caption{Failure and degradation mode taxonomy. Each mode is characterized by its NVE trajectory, entropy behavior, and primary mechanism.}\n\\label{tab:failure_modes}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{@{}llccl@{}}\n\\toprule\n\\textbf{Mode} & \\textbf{Representative} & \\textbf{NVE} & \\textbf{Entropy} & \\textbf{Mechanism} \\\\\n\\midrule\nMonotonic CIVO & 008d, 008d\\_s4, 010b\\_s0 & $\\uparrow$ sustained & $\\downarrow$ & Reward bias $\\to$ critic $\\to$ actor \\\\\nLate-onset CIVO & 008d\\_s3 & $\\uparrow$ delayed & $\\downarrow$ & Same, delayed onset \\\\\nTransient CIVO & 009b & Peak $\\to$ $\\downarrow$ & Stable & Self-correction via capacity \\\\\nIRD collapse & 008e\\_v3\\_s2 & $\\uparrow$ late & $\\uparrow$ & Entropy-driven, values stable \\\\\nGrad.\\ starvation & 015b & Oscillates, decays & Stable & Frozen emb $\\to$ zero actor grad \\\\\nSGS-resistant & 018\\_s2 & $\\uparrow$ & $\\downarrow$ & Forward-pass conditioning \\\\\nSGS-paradoxical & 016e & $\\uparrow$ sustained & $\\downarrow$ & Reward SGS $\\to$ obs-dec reliance \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Extended Training Dynamics}\\label{sec:extended_training}\n\nOne Walker seed (s3, exp\\_045) was extended from 112K to approximately 302K steps to investigate long-horizon CIVO dynamics. After onset (NVE peak $4.91\\times$ at 132K steps), the system exhibited complete self-recovery: NVE declined to $0.05\\times$ and evaluation performance recovered to 867.6 (94.7\\% of baseline). This recovery required approximately 170K additional training steps beyond onset. The trajectory shows a single onset--recovery cycle with no recurrence, suggesting that the CIVO feedback loop can break spontaneously given sufficient training---though at substantial computational cost that the frozen $\\dt$-embedding diagnostic eliminates entirely.\n\n\\subsection{Why MPC Is Immune}\n\\label{sec:mpc_immune}\n\n\\citet{nhu2025tawm} show that $\\dt$-conditioning benefits TD-MPC2, raising the question of why it fails in DreamerV3.  The critical difference is that MPC re-plans from real states at every step, so imagination errors do not accumulate into the training signal because there is no critic bootstrapping from imagined trajectories.  In DreamerV3, the actor-critic trains entirely within imagination, and any systematic reward-prediction bias at $\\dt > 1$ is amplified through the closed actor-critic loop.\n\n\\subsection{The \\texorpdfstring{$\\dt$}{dt}-Embedding Dilemma}\n\\label{sec:embedding_dilemma}\n\nThe factorial results reveal a fundamental tension: removing the $\\dt$-embedding (008f) eliminates CIVO but at a $13\\times$ cost to reward prediction quality ($0.7469$ vs.\\ $0.0568$ MAE), as the world model cannot distinguish temporal scales.  Restricting imagination to $\\dt{=}1$ while retaining the trained embedding (008e\\_v3) avoids collapse in 2 of 4 seeds (50\\%), while the remaining two collapse via distinct mechanisms: Pathway~A (CIVO-driven, entropy decrease; s3, NVE $4.02\\times$) and Pathway~B (entropy-driven, entropy increase; s2, NVE $3.78\\times$; \\S\\ref{sec:f6}).  Neither approach alone provides a complete solution.\n\n\\subsection{Temporal Embedding Representation Analysis}\n\\label{sec:cosine_evolution}\n\nTo understand how the trained $\\dt$-embedding creates vulnerability, we analyze the cosine similarity between $e(\\dt{=}1)$ and $e(\\dt{=}2)$ across training (exp\\_065). Trained embeddings learn \\emph{near-opposite} representations: $\\cos(e_1, e_2) = {-}0.87$ to ${-}0.94$ at 25K steps across three configurations (Walker 008d\\_s3, Cheetah 010b\\_s0, Walker 059\\_s5), persisting at ${-}0.70$ to ${-}0.86$ at 75K steps. In contrast, frozen embeddings maintain near-zero similarity ($-0.15$ to $+0.07$, constant throughout training). The near-antipodal learned representations explain the large reward prediction gap (\\S\\ref{sec:f2}): $\\dt{=}2$ conditioning pushes the RSSM into a qualitatively different region of latent space, producing systematically biased predictions rather than minor perturbations.\n\n\\subsection{\\texorpdfstring{$\\dt$}{dt}-Embedding Differentiation Precedes Value Divergence}\n\\label{sec:cosine_temporal}\n\nThe preceding analysis established that trained $\\dt$-embeddings learn near-antipodal representations. Here we resolve the \\emph{temporal dynamics} of this differentiation across 11 experiments (${\\sim}$47 checkpoints), testing whether embedding differentiation is a consequence or precursor of CIVO.\n\n\\paragraph{Trained embeddings: monotonic relaxation.}\nAcross all trained configurations, $\\cos(e_1, e_2)$ starts near $-0.95$ within 10K steps and relaxes monotonically toward ${\\sim}{-}0.65$ (Table~\\ref{tab:cosine_evolution_ext}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity evolution between $e(\\dt{=}1)$ and $e(\\dt{=}2)$ for trained $\\dt$-embeddings. Relaxation is monotonic but never reaches zero; frozen embeddings remain constant near zero throughout training.}\n\\label{tab:cosine_evolution_ext}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Env} & \\textbf{Experiment} & \\textbf{10K} & \\textbf{25K} & \\textbf{65K} & \\textbf{75K} & \\textbf{302K} \\\\\n\\midrule\n\\multirow{2}{*}{Walker} & exp\\_066b (trained) & $-0.947$ & $-0.928$ & $-0.847$ & --- & --- \\\\\n & exp\\_045 (extension) & --- & --- & --- & --- & $-0.668$ \\\\\n\\midrule\nCheetah & exp\\_010b$\\to$048 & --- & $-0.904$ & --- & $-0.841$ & $-0.639$ \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Frozen controls:}} \\\\\nWalker & exp\\_057 (frozen) & \\multicolumn{5}{c}{$-0.150$ (constant, 25K--225K)} \\\\\nCheetah & exp\\_058 (frozen) & \\multicolumn{5}{c}{$+0.069$ (constant, 25K--225K)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nCross-seed consistency at 25K steps is high: mean $\\cos = -0.910 \\pm 0.028$ ($n{=}5$ Walker seeds), confirming the relaxation pattern is robust across random seeds. Variance increases with training ($-0.789 \\pm 0.076$ at 75K), reflecting seed-dependent relaxation rates.\n\n\\paragraph{Temporal precedence over CIVO.}\nExp\\_066b provides simultaneous cosine similarity and CIVO diagnostic data at 5K resolution (Table~\\ref{tab:cosine_vs_civo}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity relaxation and CIVO diagnostic for exp\\_066b. Embedding relaxation onset (${\\sim}$20K) precedes CIVO alert (55K, VE ratio $> 0.7$) by ${\\sim}$30--35K steps.}\n\\label{tab:cosine_vs_civo}\n\\footnotesize\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{rccc}\n\\toprule\n\\textbf{Step} & $\\cos(e_1, e_2)$ & \\textbf{VE ratio} & \\textbf{CIVO alert} \\\\\n\\midrule\n10K & $-0.947$ & 0.012 & --- \\\\\n15K & $-0.948$ & 0.033 & --- \\\\\n25K & $-0.928$ & 0.193 & --- \\\\\n35K & $-0.904$ & 0.269 & --- \\\\\n45K & $-0.880$ & 0.358 & --- \\\\\n55K & $-0.861$ & 0.710 & \\textbf{Alert} \\\\\n65K & $-0.847$ & 0.724 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nCosine relaxation begins at ${\\sim}$20K (cos transitions from $-0.948$ at 15K to $-0.928$ at 25K), while the VE ratio first exceeds 0.7 at 55K. The ${\\sim}$30--35K temporal lead establishes that embedding differentiation is an early training dynamic, not a consequence of CIVO-triggered feedback. The relaxation rate peaks at 25K--45K ($+0.024$/10K steps) before decelerating, consistent with the geometric intuition that large-angle adjustments in embedding space are cheaper early in training.\n\n\\paragraph{Embedding norms.}\nWalker and Cheetah exhibit qualitatively different norm dynamics. Walker $e(\\dt{=}1)$ norms grow from 0.23 to 0.50 ($2.2\\times$) while $e(\\dt{=}2)$ grows from 0.45 to 0.63 ($1.4\\times$)---both $\\dt$ values become more expressive over training. Cheetah norms remain nearly constant ($\\leq 1.04\\times$) despite continued cosine relaxation, indicating direction changes without magnitude change. Frozen embedding norms are an order of magnitude smaller (${\\sim}0.06$, constant).\n\n\\paragraph{Mechanistic interpretation.}\nThe temporal ordering---embedding differentiation (${\\sim}$20K) $\\to$ reward fidelity gap (${\\sim}$20K, \\S\\ref{sec:timeseries_fidelity}) $\\to$ value overestimation (${\\sim}$30K)---suggests a three-layer causal chain: the embedding first learns maximally differentiated representations that push $\\dt{=}1$ and $\\dt{=}2$ into opposite latent regions, the reward head then develops scale-dependent biases from these differentiated inputs, and the critic amplifies these biases through imagined rollout bootstrapping. The frozen embedding's constant near-zero cosine ($|\\cos| < 0.2$) prevents the first link in this chain, explaining why freezing eliminates CIVO despite maintaining identical forward-pass architecture (\\S\\ref{sec:f3}).\n\n\\subsection{Time-Series Fidelity--Value Analysis}\n\\label{sec:timeseries_fidelity}\n\nTo test the causal direction between reward fidelity degradation and value overestimation, we analyze exp\\_066 and exp\\_066b: two Walker Walk seeds (trained $\\dt$-embedding, fixed $\\dt{=}2$) evaluated at 12 dense checkpoints from 10K to 65K steps (Table~\\ref{tab:timeseries_fidelity}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Time-series fidelity and value metrics (exp\\_066, seed~0). SS = single-step MAE ratio ($\\dt{=}2$/$\\dt{=}1$); VE = value-to-eval ratio. Fidelity degradation (SS $>1.1\\times$ at 20K) precedes value overestimation onset (VE begins rising at ${\\sim}$30K) by ${\\sim}$10K steps. Seed~1 (exp\\_066b) confirms the pattern: fidelity gap onset ${\\sim}$15K $\\to$ VE onset ${\\sim}$24K (lead ${\\approx}$9K steps; VE peak ${=}0.72$).}\n\\label{tab:timeseries_fidelity}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{rcccccc}\n\\toprule\n\\textbf{Step} & \\textbf{SS ratio} & \\textbf{OL ratio} & \\textbf{VE ratio} & \\textbf{MAE$_{\\dt{=}1}$} & \\textbf{MAE$_{\\dt{=}2}$} & \\textbf{Return} \\\\\n\\midrule\n10K & 1.05 & 0.94 & 0.01 & 0.090 & 0.094 & 43.0 \\\\\n15K & 1.08 & 1.03 & 0.02 & 0.085 & 0.092 & 187.8 \\\\\n20K & 1.10 & 1.09 & 0.16 & 0.078 & 0.086 & 148.7 \\\\\n25K & 1.04 & 1.22 & 0.16 & 0.073 & 0.076 & 142.1 \\\\\n30K & 1.25 & 1.45 & 0.22 & 0.068 & 0.085 & 148.3 \\\\\n35K & 1.24 & 1.51 & 0.23 & 0.062 & 0.077 & 275.4 \\\\\n40K & 1.35 & 1.38 & \\textbf{1.59} & 0.058 & 0.078 & 202.3 \\\\\n45K & 1.40 & 1.38 & 0.36 & 0.055 & 0.077 & 107.5 \\\\\n50K & 1.47 & 1.56 & 0.62 & 0.052 & 0.076 & 178.4 \\\\\n55K & 1.37 & 1.52 & 0.62 & 0.050 & 0.069 & 60.8 \\\\\n60K & 1.61 & 1.35 & 1.40 & 0.049 & 0.079 & 125.3 \\\\\n65K & 1.68 & 1.38 & 1.40 & 0.047 & 0.079 & 94.4 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/paper/fig_temporal_ordering.pdf}\n\\caption{Temporal ordering of fidelity degradation and value overestimation (exp\\_066, seed~0). \\textbf{Left axis}: single-step fidelity ratio (SS, blue) grows steadily from $1.05\\times$ to $1.68\\times$. \\textbf{Right axis}: value-to-eval ratio (VE, red) remains near zero until 40K, then spikes. The ${\\sim}$10K onset-to-onset lag supports the causal direction: fidelity gap $\\to$ value overestimation. Seed~1 (exp\\_066b) replicates the pattern with a ${\\sim}$9K temporal lead.}\n\\label{fig:temporal_ordering}\n\\end{figure}\n\nThe $\\dt{=}1$ prediction MAE decreases monotonically ($0.090 \\to 0.047$) as the world model improves, but $\\dt{=}2$ MAE plateaus at ${\\sim}0.08$. The growing fidelity gap is therefore not caused by $\\dt{=}2$ predictions worsening, but by the model selectively improving at $\\dt{=}1$ while failing to transfer that improvement to $\\dt{=}2$---consistent with the trained $\\dt$-embedding learning maximally differentiated representations (\\S\\ref{sec:cosine_evolution}) that prevent cross-scale generalization.\n\n\\textbf{Limitation.} These results are limited to two seeds ($n{=}2$). While both seeds show consistent temporal ordering (leads of ${\\approx}$10K and ${\\approx}$9K steps), additional seeds would strengthen the causal claim.\n\n\\subsection{Actor Entropy Is Not Diagnostic of CIVO}\n\\label{sec:entropy_not_diagnostic}\n\nTo test whether actor entropy can serve as an early collapse indicator, we compare entropy trajectories between collapsed and healthy configurations at matched training steps across five experiments (Table~\\ref{tab:entropy_contrast}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Actor entropy comparison at matched time points. Collapsed and healthy configurations exhibit indistinguishable entropy at 55K steps (difference $= 0.03$ nats), despite collapsed runs showing severe return degradation.}\n\\label{tab:entropy_contrast}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Group} & \\textbf{Experiment} & \\textbf{5K} & \\textbf{25K} & \\textbf{45K} & \\textbf{55K} & \\textbf{Return} \\\\\n\\midrule\n\\multirow{2}{*}{Collapsed}\n & exp\\_008d (trained dt\\_emb) & 8.16 & $-1.86$ & $-4.58$ & $-4.88$ & ${\\sim}165$ \\\\\n & fixed\\_dt2 ($\\dt{=}2$) & 8.16 & $-3.02$ & $-5.06$ & $-5.17$ & ${\\sim}29$ \\\\\n\\midrule\n\\multirow{3}{*}{Healthy}\n & exp\\_008f (no dt\\_emb) & 8.11 & $-1.85$ & $-4.31$ & $-4.77$ & ${\\sim}460$ \\\\\n & exp\\_008a (unexposed) & 8.16 & $-4.88$ & $-5.20$ & $-5.21$ & ${\\sim}300$ \\\\\n & baseline\\_s1 ($\\dt{=}1$) & 8.10 & $-4.74$ & $-5.12$ & $-5.18$ & ${\\sim}950$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt the last comparable step (55K): collapsed mean entropy $= -5.02$ (average of $-4.88$, $-5.17$); healthy mean entropy $= -5.05$ (average of $-4.77$, $-5.21$, $-5.18$); difference $= 0.03$ nats---statistically negligible. The hypothesis that collapsed runs exhibit anomalous entropy rise (actor confusion from delusional critic gradients) is not supported during the CIVO onset window.\n\nThe fixed\\_dt2 experiment demonstrates this most clearly: returns peak at ${\\sim}580$ (40K) then crash to 29 (72K), yet entropy remains stable at $-5.1$ throughout. The actor maintains a committed, low-entropy policy during the entire collapse---it does not become confused but rather remains confident while acting on incorrect value estimates. This is consistent with CIVO operating through critic value distortion rather than actor policy degradation. The late-stage entropy explosion documented in \\S\\ref{sec:civo_mechanism} ($+2.1$ nats/10K in EG~v4, onset ${\\sim}$35K steps after return collapse) occurs well beyond this window, confirming entropy rise as a lagging consequence rather than a concurrent or predictive signal.\n\n\\paragraph{Entropy descent speed.}\nEntropy descent rate correlates with temporal configuration complexity, not collapse fate. Simpler configurations (baseline $\\dt{=}1$, unexposed exp\\_008a) reach $-4.7$ by 25K, while configurations exposed to temporal variation (both collapsed and healthy) remain near $-2.0$ at 25K, reflecting the difficulty of policy commitment when training data spans multiple temporal scales.\n\n\\paragraph{Long-horizon entropy recovery.}\nThe baseline ($\\dt{=}1$) run extended to 505K steps shows entropy recovering from $-5.2$ to ${\\sim}{-}1.5$ between 115K and 295K steps, coinciding with continued performance improvement ($700 \\to 950$ return). This adaptive entropy increase rules out entropy rise as an inherently negative signal; the actor maintains ${\\sim}950$ return with entropy 3--4 nats above its minimum, indicating a healthy exploration--exploitation balance during extended training.\n\n\\subsection{Multiple Vulnerability Pathways}\n\\label{sec:pathways}\n\nThe two collapse patterns identified in \\S\\ref{sec:f6}---CIVO (Pathway~A, value-driven, entropy decreasing) and a tentative second mode (Pathway~B, eval-driven, entropy increasing)---have distinct diagnostic signatures. Pathway~B is observed in only two seeds (008e\\_v3\\_s2 and 038\\_s2); we present it as preliminary evidence that the trained $\\dt$-embedding's learned features may affect both reward prediction across temporal scales (Pathway~A) and the representation space in which the actor operates (Pathway~B), though additional data is needed to confirm this as a distinct mechanism.  This explains why $\\nve$ is sensitive but not perfectly specific: Pathway~B's late evaluation decline inflates $\\nve$ through the same arithmetic as CIVO, yielding the sole false positive ($3.78\\times$ for 008e\\_v3 s2).  Distinguishing the two requires examining the temporal profile and entropy direction of collapse (Figure~\\ref{fig:multiple_pathways}).\n\n\n\\subsection{Implications for Temporal Abstraction in World Models}\n\\label{sec:implications}\n\nCIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \\citep{gumbsch2024thick}, Hieros \\citep{mattes2024hieros}, LS-Imagine \\citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \\citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.  The CIVO mechanism requires three structural properties: (1) a temporal embedding that co-adapts with dynamics via gradient flow, (2) multi-step imagined rollouts used for critic training, and (3) a reward head that inherits latent biases from the shared representation.  Transformer-based world models that share these properties may exhibit analogous vulnerability; architectures that decouple temporal conditioning from the reward prediction pathway would not.\n\n\\subsection{Cross-Environment TCN Evaluation}\n\\label{sec:tcn_cross_env}\n\nTable~\\ref{tab:tcn_full} reports the full TCN evaluation across environments and noise magnitudes.\n\n\\begin{table}[h]\n\\centering\n\\caption{TCN results across environments and noise magnitudes. Prevention = peak NVE $< 1.5\\times$ (35K+).}\n\\label{tab:tcn_full}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Env} & $\\sigma$ & \\textbf{Seed} & \\textbf{NVE$_{\\max}$} & \\textbf{Prevented?} & \\textbf{Eval (\\%)} \\\\\n\\midrule\nWalker & 0.1 & s0 & 1.02 & \\checkmark$^*$ & 55\\% \\\\\nWalker & 0.2 & s0 & 0.91 & \\checkmark & 91\\% \\\\\nWalker & 0.2 & s1 & 0.64 & \\checkmark & 45\\% \\\\\nWalker & 0.2 & s2 & 2.11$^\\dagger$ & $\\times$ & ${\\sim}5\\%$ \\\\\n\\rowcolor{gray!15}\nWalker & 0.2 & s3 & 3.04$^\\P$ & $\\times$ & 11\\% \\\\\nWalker & 0.5 & s0 & 3.97 & $\\times$ & 27\\% \\\\\nWalker & 0.5 & s1 & 1.64 & $\\times$ & 41\\% \\\\\n\\midrule\nCheetah & 0.2 & s0 & 1.90 & $\\times$ & crashed \\\\\nCheetah & 0.5 & s0 & 10.67 & $\\times$ & 26\\% \\\\\nCheetah & 1.0 & s0 & $\\leq$0.30 & \\checkmark$^\\S$ & 15\\% \\\\\n\\midrule\nPickCube & 0.2 & s0 & 3.71 & $\\times$ & failing \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$Borderline: NVE${=}1.02\\times$ at 95K, below $1.5\\times$ threshold but above $1.0\\times$.\\\\\n$^\\dagger$NVE $= 2.11\\times$ at 95K, still rising; eval ${\\sim}5\\%$ of baseline.\\\\\n$^\\P$Late-onset CIVO: NVE declined to $0.67\\times$ at 95K before phase-transition-like spike to $3.04\\times$ at 105K; eval 349.6 at 95K $\\to$ 71.8 at 105K $\\to$ 104.5 at 215K.\\\\\n$^\\S$CIVO prevented (NVE${\\leq}0.30$); peak eval 116\\% baseline at 35K, declining to 15\\% by 215K via progressive policy erosion. See ``impossible dose'' discussion.\\par}\n\\end{table}\n\n\\paragraph{Cheetah Run $\\sigma{=}0.5$: transient spike with permanent eval damage.}\nCheetah $\\sigma{=}0.5$ exhibits a novel failure mode: a transient CIVO spike (NVE $= 10.67\\times$ at 55K) followed by NVE recovery ($< 0.3\\times$ by 95K), but permanent evaluation damage (26\\% of baseline). The value signal self-corrects while the policy does not recover, suggesting that CIVO-induced representational damage during the spike persists within the observation window even when the critic subsequently recalibrates. This trajectory parallels the obs-decoder SGS seed~3 pattern (\\S\\ref{sec:seed_divergence}), where partial policy recovery coexists with persistent critic damage.\n\n\\paragraph{Cheetah Run $\\sigma{=}0.2$: insufficient dose.}\nAt $\\sigma{=}0.2$, Cheetah reaches NVE $= 1.9\\times$ at 55K---exceeding the $1.5\\times$ threshold---consistent with Cheetah's higher baseline CIVO severity ($8$--$108\\times$ vs.\\ Walker's $2$--$6\\times$). The noise magnitude that suffices for Walker is inadequate for Cheetah, but increasing $\\sigma$ to 0.5 trades CIVO prevention for a different failure mode rather than achieving mitigation.\n\n\\paragraph{PickCube-v1 $\\sigma{=}0.2$: manipulation failure.}\nPickCube reaches NVE $= 3.71\\times$ at 52.5K with $\\sigma{=}0.2$, indicating that TCN provides no protection in manipulation tasks. The combination of contact-gated dynamics and temporal conditioning may amplify the fidelity gap beyond what representation-level noise can attenuate.\n\n\\paragraph{Dose-response analysis.}\nWe observe $\\sigma{=}0.2$ as a local optimum on Walker Walk, achieving complete CIVO suppression in 2 of 4 seeds. Seeds~2 and~3 both fail but via distinct CIVO onset dynamics: seed~2 shows gradual escalation (NVE $= 2.11\\times$ at 95K, still rising, eval ${\\sim}5\\%$), while seed~3 exhibits a phase-transition-like onset---NVE declined to $0.67\\times$ at 95K before spiking to $3.04\\times$ at 105K (eval 349.6 $\\to$ 71.8 in 10K steps). When TCN fails to prevent CIVO onset, the resulting trajectory qualitatively resembles untreated CIVO in its terminal outcome---runaway NVE and eval collapse. The two failure modes (gradual escalation vs.\\ sudden onset after apparent suppression) reinforce that TCN operates as a binary gate on CIVO onset rather than providing graded attenuation. Below the optimum, we observe $\\sigma{=}0.1$ as insufficient (NVE $= 1.02\\times$---borderline, eval 55\\%); above it, $\\sigma{=}0.5$ overdoses (oscillatory CIVO, eval $\\leq 41\\%$). Cross-seed variance at $\\sigma{=}0.2$ (eval 5--91\\%) exceeds the cross-dose difference by a wide margin, reinforcing that seed effects dominate dose effects. TCN is the only tested intervention achieving complete CIVO suppression in any configuration, but its high seed sensitivity and failure to transfer across environments position it as a \\emph{diagnostic probe}---identifying the representation level as the relevant intervention target---rather than a deployable mitigation.\n\n\\paragraph{Cheetah Run ``impossible dose'' dilemma.}\nExp\\_030c (224K steps) reveals a qualitatively different dose-response on Cheetah. At $\\sigma{=}1.0$, CIVO is eliminated (NVE${\\leq}0.30$ throughout) and initial learning is \\emph{unimpaired}: peak eval reaches 372 at 35K (116\\% of baseline), demonstrating that $\\sigma{=}1.0$ noise does not prevent policy acquisition. However, cumulative actor gradient interference produces progressive policy erosion---eval declines from 372 to 47 by 215K (15\\% of baseline)---while the critic remains well-calibrated (value\\_mean${=}12.4$, NVE${=}0.26$ at 215K). This establishes that \\emph{policy degradation $\\neq$ value corruption}: accurate value signals are insufficient when the actor cannot optimize effectively in noise-perturbed imagination.\n\nThis ``correct values, failed policy'' pattern provides indirect evidence that CIVO is mechanistically distinct from standard overestimation. Double Q-learning and ensemble methods address critic estimation error, but at $\\sigma{=}1.0$ the critic is accurate and the policy still collapses---a failure mode orthogonal to what these countermeasures target. The impossible dose dilemma scales with environment complexity: Cheetah's baseline CIVO severity ($8$--$108\\times$ NVE) requires $\\sigma \\geq 1.0$ to suppress, but this exceeds the actor's gradient signal-to-noise tolerance. On Walker, a narrow effective window exists around $\\sigma{=}0.2$; on Cheetah, the effective dose ($\\sigma \\geq 1.0$) exceeds the tolerable dose, and environments with higher CIVO severity will systematically lack a viable dose window.\n\n\\section{DreamerV3 Hyperparameters}\n\\label{sec:hyperparameters}\n\nTable~\\ref{tab:hyperparams} lists the DreamerV3 hyperparameters used across all experiments. Unless otherwise noted, we use the default DreamerV3 configuration for continuous-control tasks (\\texttt{dmc\\_proprio}).\n\n\\begin{table}[ht]\n\\centering\n\\caption{DreamerV3 hyperparameters for all experiments. Modifications from defaults are marked with $\\diamond$.}\n\\label{tab:hyperparams}\n\\small\n\\begin{tabular}{ll}\n\\toprule\n\\textbf{Parameter} & \\textbf{Value} \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{World Model}} \\\\\nRSSM discrete states & 32 classes $\\times$ 32 categories \\\\\nRSSM stochastic dim & 32 \\\\\nRSSM deterministic dim & 512 \\\\\nMLP hidden size & 512 \\\\\nMLP layers & 2 \\\\\nActivation & SiLU \\\\\nNormalization & LayerNorm \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Training}} \\\\\nBatch size & 16 sequences $\\times$ 64 steps \\\\\nLearning rate & $3 \\times 10^{-4}$ (Adam, $\\epsilon{=}10^{-8}$) \\\\\nSequence length & 64 \\\\\nTraining ratio & 512 \\\\\nFree nats & 1.0 \\\\\nKL balance ($\\alpha$) & 0.8 \\\\\nDiscount ($\\gamma$) & 0.997 \\\\\n$\\lambda$-return & 0.95 \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Policy}} \\\\\nImagination horizon$^\\diamond$ & 8 or 15 (see Table~\\ref{tab:complete_results}) \\\\\nActor entropy scale & $3 \\times 10^{-4}$ \\\\\nActor gradient & Reinforce + dynamics backprop \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Temporal Abstraction}$^\\diamond$} \\\\\nGate enabled & True (all non-baseline) \\\\\nGate fixed $\\dt$ & 1 or 2 (per config) \\\\\nSubsample max $\\dt$ & 1 (OFF) or 2 (ON) \\\\\n$\\dt$-embedding dim & 32 \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Environment}} \\\\\nAction repeat & 2 (Walker Walk, Cheetah Run) \\\\\nObservation & Proprioceptive (no pixels) \\\\\nTotal environment steps & 105K \\\\\nEvaluation frequency & Every 10K steps \\\\\nEvaluation episodes & 10 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Online CIVO Detector Details}\n\\label{sec:detector_appendix}\n\nThis appendix provides the full algorithm specification and validation results for the online CIVO detector described in \\S\\ref{sec:detector}.\n\n\\subsection{Algorithm Specification}\n\n\nThe four conditions capture complementary signals: (1)~\\emph{Magnitude} ($r_t \\geq 0.49$) confirms that the value-to-evaluation ratio has reached a level indicative of overestimation; (2)~\\emph{Velocity} ($\\Delta r_t > 0.1$) rules out slow drift or plateau behavior; (3)~\\emph{Acceleration} ($\\Delta r_t > \\Delta r_{t-1}$, both $> 0.1$) filters oscillatory paths; (4)~\\emph{Evaluation decline} ($\\geq 2$ of 3 recent checkpoints decline) confirms that overestimation coincides with actual performance degradation. A full comparison of window sizes appears in \\S\\ref{sec:appendix_sensitivity}.\n\nSensitivity analysis over $\\tau_\\text{mag} \\in [0.30, 0.70]$ confirms that $\\tau_\\text{mag} = 0.49$ maximizes Youden's $J = 0.714$; raising the threshold to $0.50$ loses one true positive (seed~3 triggers at $r_t = 0.497$) with no reduction in false positives. The velocity threshold $\\tau_\\text{vel} = 0.1$ is stable across $[0.05, 0.18]$ (TPR remains $5/5$).\n\n\\subsection{Validation Results}\n\n\\begin{table}[ht]\n\\centering\n\\caption{Retrospective CIVO detector validation ($n{=}14$). Detection type: ``predictive'' = alert precedes 20\\% eval decline; ``reactive'' = alert follows decline onset.}\n\\label{tab:detector-validation}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{Verdict} & \\textbf{Trigger} & \\textbf{Type} & \\textbf{Peak Eval} & $r_\\text{ve}$ \\\\\n\\midrule\n008d s0 & trained $\\dt$-emb & TP & 45K & predict. & 167 & 0.69 \\\\\n010b & trained $\\dt$-emb (Cheetah) & TP & 65K & reactive & 322 & 3.18 \\\\\n008d s3 & trained $\\dt$-emb & TP & 45K & predict. & 452 & 0.50 \\\\\n008d s4 & trained $\\dt$-emb & TP & 105K & reactive & 383 & 3.03 \\\\\n010b s0 & trained $\\dt$-emb (Cheetah) & TP & 95K & reactive & 248 & 6.34 \\\\\n\\midrule\n008f s3 & no $\\dt$-emb & TN & -- & -- & 594 & -- \\\\\n009b s2 & trained $\\dt$-emb (self-corr.) & TN & -- & -- & 279 & -- \\\\\nbaseline s1 & vanilla & TN & -- & -- & 970 & -- \\\\\n009d s0 & vanilla & TN & -- & -- & 951 & -- \\\\\n009d s1 & vanilla & TN & -- & -- & 920 & -- \\\\\n019b & trained $\\dt$-emb (PickCube) & TN & -- & -- & 26.6 & -- \\\\\n\\midrule\n009c s2 & no $\\dt$-emb & FP & 105K & reactive & 359 & 0.75 \\\\\n009a s2 & vanilla & FP & 85K & predict. & 967 & 0.73 \\\\\n\\midrule\n009c s3 & no $\\dt$-emb & TN & -- & -- & 457 & -- \\\\\n\\midrule\n\\multicolumn{7}{l}{TPR = 5/5 (1.00), \\quad FPR = 2/9 (0.22)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe detector identifies all five CIVO-positive runs (TPR = 5/5). Two are detected predictively (008d seeds~0 and~3, both at 45K). Two false positives occur among nine negative cases (FPR = 2/9, precision 71\\%, F$_1$ = 0.83). Run 009c develops genuine late-stage value overestimation unrelated to CIVO; run 009a triggers during a transient eval dip at 85K before recovery to 966. Early alerts (before 70K) carry higher diagnostic confidence.\n\n\\subsection{Cross-Simulator Specificity (PickCube)}\n\nExp\\_019b applies the CIVO-trigger configuration to PickCube-v1 in ManiSkill3, a dense-reward manipulation task. The V/E ratio exhibits an oscillatory pattern rather than monotonic divergence: it spikes to $r_t = 5.66$ at 52.5K, then deflates to 1.38 by 72.5K. This trajectory prevents the acceleration condition from co-occurring with evaluation decline at any single checkpoint. Across all 14 checkpoints through 132.5K, the detector correctly remains silent (TN), confirming that the acceleration filter distinguishes transient spikes from CIVO's sustained monotonic divergence. A frozen-embedding control (exp\\_054) confirms this classification: frozen PickCube-v1 exhibits a comparable burst (peak $8.81\\times$ at 62.5K) that resolves within a single evaluation cycle ($0.55\\times$ at 72.5K), establishing environment-specific origin independent of $\\dt$-embedding training.\n\n\\subsection{Detector Limitations}\n\nFour constraints bound the current detector. First, the three-checkpoint window cannot distinguish transient dips from sustained collapse. Second, the acceleration condition assumes monotonically increasing overestimation during onset. Third, the detector identifies a \\emph{pattern} rather than a \\emph{mechanism}: run 009c shows that non-CIVO pathologies produce the same signature. Fourth, threshold values were calibrated on fourteen runs across three environments; generalization to different reward scales requires further validation.\n\n\\section{Dual-Critic Mechanism Ablation}\n\\label{sec:dual_critic_appendix}\n\n\\subsection{\\texorpdfstring{$2{\\times}2$}{2x2} Factorial Design}\n\nWe ablate the critic architecture in a $2{\\times}2$ factorial: \\{single, dual\\} $\\times$ \\{narrow (${\\sim}1.2$M), wide (${\\sim}2.4$M)\\} parameters. Table~\\ref{tab:dual_critic_full} reports all configurations.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Dual-critic $2{\\times}2$ factorial results. Walker Walk unless noted.}\n\\label{tab:dual_critic_full}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{Params} & \\textbf{NVE} & \\textbf{Eval} & \\textbf{Outcome} \\\\\n\\midrule\n008d & Single narrow & 1.2M & 4.12$\\times$ & 82.8 & Collapse \\\\\n033 & Wide single & 2.4M & 4.75$\\times$ & 407.9 & CIVO $\\to$ self-repair \\\\\n035 s0 & Narrow dual (min) & 1.2M & 2.75$\\times$ & 697.8 & CIVO $\\to$ recovery \\\\\n039 s1 & Narrow dual (min) & 1.2M & 2.19$\\times$ & 592.7 & CIVO $\\to$ recovery \\\\\n032 s0 & Wide dual (min) & 2.4M & $\\leq$1.1$\\times$ & 739.7 & CIVO prevented \\\\\n032b s1 & Wide dual (min) & 2.4M & 1.4$\\times$ & 551.8 & CIVO prevented \\\\\n038 s2 & Wide dual (min) & 2.4M & $\\leq$0.3$\\times$ & 120.9$^*$ & Non-CIVO collapse \\\\\n\\midrule\n\\multicolumn{6}{l}{\\textit{Cross-environment}} \\\\\n034 & Cheetah dual & 2.4M & 1.75$\\times$ & 97.5 & Partial recovery (31\\%) \\\\\n037 & Cheetah wide single & 2.4M & 3.60$\\times$ & 146.1 & CIVO $\\to$ self-repair \\\\\n036 & PickCube dual & 2.4M & 2.3$\\times$ & 27.7 & Transient CIVO \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$CIVO prevented (NVE $\\leq 0.3\\times$) but non-CIVO eval collapse: eval peaked at 354 (155K), then declined to 120.9 (224K) with actor entropy increasing from $-3.59$ to $-0.45$.\\par}\n\\end{table}\n\n\\subsection{Critic Convergence (\\texorpdfstring{$v_1 \\approx v_2$}{v1 ≈ v2})}\n\nAcross all dual-critic configurations and environments, the two critics converge to near-identical value functions. On Walker Walk, Pearson $\\rho > 0.999$ between $v_1$ and $v_2$ outputs; on Cheetah Run and PickCube-v1, the gap is $< 0.2$ (exact match within numerical precision). Per-sample pessimism $\\mathbb{E}[\\max(v_1, v_2) - \\min(v_1, v_2)]$ is 3--4\\% of the theoretical bound for independent critics.\n\nThis convergence occurs because both critics train on the same RSSM-generated latent features. Unlike model-free Double Q-learning, where each critic sees different mini-batches of real transitions and develops distinct function approximation errors, pure-imagination critics share identical inputs from the world model. The min operation therefore cannot provide the pessimism bias that makes Double Q effective in model-free settings.\n\n\\subsection{Recovery vs.\\ Prevention Mechanism}\n\nThe $2{\\times}2$ factorial reveals two separable dimensions:\n\n\\paragraph{Recovery (min-dominated).} The min operation is the primary factor enabling recovery from CIVO. Both narrow dual-critic seeds experience CIVO and recover fully: exp\\_035 (s0, $\\nve = 2.75\\times$, eval $33.8 \\to 697.8$, recovery ratio $20.6\\times$) and exp\\_039 (s1, $\\nve = 2.19\\times$, eval $35.9 \\to 592.7$, recovery ratio $16.5\\times$). Both outperform wide single-critic (exp\\_033, 2.4M params, eval 407.9) despite $2\\times$ fewer parameters. The min operation reduces both peak CIVO severity (2.19--2.75$\\times$ vs.\\ 4.75$\\times$ for the comparable single-critic) and enables consistent full recovery across seeds.\n\n\\paragraph{Prevention (min $+$ capacity synergy).} CIVO prevention (NVE remaining below the $1.5\\times$ threshold) requires both the min operation and increased capacity: only the wide dual-critic (exp\\_032, 3 seeds) achieves this. The mechanism for this synergy is an open question; we hypothesize that increased capacity improves value calibration quality while the min operation constrains the overestimation feedback loop during early training when the two critics briefly diverge.\n\n\\paragraph{Cross-environment limits.} On Cheetah Run, the wide dual-critic (exp\\_034) reduces NVE from $8.27\\times$ (untreated baseline) to $1.75\\times$ ($\\geq 4\\times$ reduction) but cannot prevent CIVO onset, and recovery reaches only 31\\% of the pre-CIVO peak. This confirms that the min $+$ capacity synergy has environment-dependent limits: in high-CIVO-severity environments, architecture-level interventions attenuate but do not eliminate the pathology.\n",
    "structuredPatch": [
      {
        "oldStart": 106,
        "oldLines": 7,
        "newStart": 106,
        "newLines": 8,
        "lines": [
          " $^g$ PegInsertion environment dynamics: seed~0 trained peaks at $10.05\\times$ (82.5K); seed~1 trained (exp\\_055) peaks at $3.08\\times$ (92.5K), final $0.50\\times$ at 212.5K; seed~1 frozen (exp\\_056) peaks at $11.32\\times$ (82.5K), final $1.19\\times$ at 212.5K. Frozen final exceeds trained final; ordering is seed-dependent, ruling out $\\dt$-embedding causation.\\\\",
          " $^h$ PickCube environment transient: frozen control peak $8.81\\times$ at 62.5K, self-correcting to $0.55\\times$ at 72.5K; matches trained (exp\\_019b) trajectory.\\\\",
          " $^\\heartsuit$ Evaluated at 55K steps due to early termination of exp\\_008d; extended run (exp\\_009e) reached 131.08 at 105K.\\\\",
          "-$^i$ Cartpole: exp\\_060 reports seed~2 eval only; exp\\_061/062 report 3-seed mean.\\par}",
          "+$^i$ Cartpole: exp\\_060 reports seed~2 eval only; exp\\_061/062 report 3-seed mean.\\\\",
          "+$^j$ CIVO-unrelated learning stagnation; NVE $\\leq 0.6\\times$, no value overestimation.\\par}",
          " \\end{table*}",
          " ",
          " \\begin{table}[h]"
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

_source line 52_

Now update the NVE raw table section (description, caption, and body).

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "0ed50d70-4e89-4b87-8578-c787ad99b7cf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EYGb9AEBpaMYeHCmJfGPTa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 316,
      "cache_read_input_tokens": 94860,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 316
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

_source line 53_

<details open><summary>🔧 Tool call — Edit · `toolu_01854EjWNe7xM8DtPJbJpTmm`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
  "old_string": "Table~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\\_v3 seeds and exp\\_059). Experiments are sorted by descending NVE. Experiment 008e\\_v3\\_s2 exhibits elevated NVE ($3.78\\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\\_v3\\_s3 exhibits CIVO with NVE $4.02\\times$ despite $\\Delta t{=}1$ imagination.",
  "new_string": "Table~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\\_v3 seeds and exp\\_059). Experiments are sorted by descending NVE. All four 008e\\_v3 seeds (mitigation configuration with $\\Delta t{=}1$ imagination) remain healthy with NVE $\\leq 0.6\\times$, confirming that restricting imagination to $\\Delta t{=}1$ effectively prevents CIVO."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "2be745d9-8f10-4ed4-b059-a522581b4f5d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EYGb9AEBpaMYeHCmJfGPTa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 316,
      "cache_read_input_tokens": 94860,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 316
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

_source line 54 · 2026-05-25T16:34:13.207Z_

<details><summary>↩ Tool result · `toolu_01854EjWNe7xM8DtPJbJpTmm`</summary>

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
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "a703f93d-e66e-49ee-bffa-a7d9274fc276",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
    "oldString": "Table~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\\_v3 seeds and exp\\_059). Experiments are sorted by descending NVE. Experiment 008e\\_v3\\_s2 exhibits elevated NVE ($3.78\\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\\_v3\\_s3 exhibits CIVO with NVE $4.02\\times$ despite $\\Delta t{=}1$ imagination.",
    "newString": "Table~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\\_v3 seeds and exp\\_059). Experiments are sorted by descending NVE. All four 008e\\_v3 seeds (mitigation configuration with $\\Delta t{=}1$ imagination) remain healthy with NVE $\\leq 0.6\\times$, confirming that restricting imagination to $\\Delta t{=}1$ effectively prevents CIVO.",
    "originalFile": "% --- APPENDIX ---\n\n\\section{Complete Experimental Results}\n\\label{sec:complete_results}\n\nTable~\\ref{tab:complete_results} reports all 45 experimental configurations. The main text (Table~\\ref{tab:main_results}) presents the subset most relevant to the causal argument; this table includes the additional variable-rate configurations (006, 007, 005), multi-seed factorial runs (009b, 008d\\_s3, 008d\\_s4), SGS interventions (018), cross-environment seeds (010b\\_s0), and mitigation experiments (008e\\_v3).\n\n\\begin{table*}[t]\n\\centering\n\\caption{Complete experimental results. NVE reports peak $\\nve$ in the 35K+ window (\\S\\ref{sec:metrics}). CIVO-positive seeds are shaded; $\\dagger$\\,marks a false positive (non-CIVO collapse with elevated NVE).}\n\\label{tab:complete_results}\n\\scriptsize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{dt\\_emb} & \\textbf{Sub} & \\textbf{H} & \\textbf{Eval@final} & \\textbf{NVE} & \\textbf{Outcome} \\\\\n\\midrule\n001 & Baseline ($\\dt{=}1$, s1) & --- & --- & 15 & 915.7 @105K & 1.00$\\times$ & Healthy \\\\\n001 s2 & Baseline ($\\dt{=}1$, s2) & --- & --- & 15 & 443.5 @105K & ---$^e$ & Healthy \\\\\n\\rowcolor{gray!15}\n006 & Fixed $\\dt{=}2$ & trn & ON & 15 & 132.9 @65K & 4.83$\\times$ & Collapsed \\\\\n007 & Fixed $\\dt{=}4$ & trn & ON & 15 & 152.5 @55K & --- & Collapsed \\\\\n005 & Learned gate & adaptive & OFF & 15 & 98.8 @145K & --- & Collapsed \\\\\n\\midrule\n\\rowcolor{gray!15}\n008d & Factorial (s1) & trn & ON & 8 & 82.8 @55K$^\\heartsuit$ & 4.12$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n009b & Factorial (s2) & trn & ON & 8 & 267.9 @105K & 1.62$\\times$ & Transient CIVO \\\\\n\\rowcolor{gray!15}\n008d\\_s3 & Factorial (s3) & trn & ON & 8 & 268$^\\diamond$ @105K & 1.53$\\times$ & Late-onset collapse \\\\\n\\rowcolor{gray!15}\n008d\\_s4 & Factorial (s4) & trn & ON & 8 & 63.6 @105K & 4.62$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n059 & Factorial (s5) & trn & ON & 8 & 95.8 @105K & 4.72$\\times$ & Collapse$^\\dagger$ \\\\\n\\rowcolor{gray!15}\n068 & Factorial repro (s1) & trn & ON & 8 & 39.1 @105K & 4.12$\\times$ & Full collapse \\\\\n008f & No dt\\_emb (s1) & --- & ON & 8 & 503.0 @105K & 0.97$\\times$ & Healthy \\\\\n008f s4 & No dt\\_emb (s4) & --- & ON & 8 & 289.3 @105K & 0.76$\\times$ & Healthy \\\\\n009c s3 & No dt\\_emb (s3) & --- & ON & 8 & 311.9 @105K & 1.04$\\times$ & Healthy \\\\\n008a & Unexposed emb & exp$^a$ & OFF & 15 & 777.7 @105K & 0.93$\\times$ & Healthy \\\\\n008a\\_s1 & Unexposed emb & exp$^a$ & OFF & 15 & 630.9 @105K & 0.83$\\times$ & Healthy \\\\\n008a\\_s2 & Unexposed emb & exp$^a$ & OFF & 15 & 899.4 @105K & 0.89$\\times$ & Healthy \\\\\n008a\\_s3 & Unexposed emb & exp$^a$ & OFF & 15 & 855.9 @105K & --- & Healthy \\\\\n015b & Frozen emb & frz$^b$ & ON & 8 & 204.2 @105K & 1.45$\\times$ & Grad.\\ starvation \\\\\n022b & Frozen emb + Gumbel gate & frz$^b$ & ON & 8 & 300.7 @105K & 0.63$\\times$ & No CIVO \\\\\n042 & Frozen emb (dedicated) & frz$^b$ & ON & 8 & 612.0 @105K & 0.19$\\times$ & Healthy \\\\\n047 & Frozen emb (s1) & frz$^b$ & ON & 8 & 144.2 @215K & 1.71$\\times$ & Transient (self-corr.) \\\\\n057 & Frozen emb (s2) & frz$^b$ & ON & 8 & 123.9 @215K & 1.88$\\times$ & Transient (self-corr.) \\\\\n067 & Frozen emb (s0) & frz$^b$ & ON & 8 & 281.5 @105K & 0.19$\\times$ & Healthy \\\\\n\\midrule\n018 s1 & Full-SGS & trn$^\\ddagger$ & ON & 8 & \\sgseval{} @105K & \\sgsnve{}$\\times$$^*$ & Partial mitig.\\ (CIVO+) \\\\\n\\rowcolor{gray!15}\n018 s2 & Full-SGS & trn$^\\ddagger$ & ON & 8 & 40.8 @105K & --- & Collapsed \\\\\n008e\\_v3 s0 & Mitigation & trn & ON & 15 & 148.0 @105K & 0.60$\\times$ & No CIVO$^j$ \\\\\n008e\\_v3 s1 & Mitigation & trn & ON & 15 & 876.7 @105K & 0.60$\\times$ & Healthy \\\\\n008e\\_v3 s2 & Mitigation & trn & ON & 15 & 597.1 @105K & 0.50$\\times$ & Healthy \\\\\n008e\\_v3 s5 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.60$\\times$ & Healthy \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cross-environment validation}} \\\\\n\\rowcolor{gray!15}\n010b & Cheetah Run & trn & ON & 8 & 51.7 @105K & 8.27$\\times$ & Collapsed \\\\\n\\rowcolor{gray!15}\n010b\\_s0 & Cheetah Run & trn & ON & 8 & 0.83 @105K & 108.52$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n021 & Cheetah Run & trn$^\\ddagger$ & ON & 8 & 221.5 @105K & 9.94$\\times$$^d$ & Transient CIVO (self-corr.) \\\\\n024b s0 & Cheetah Run & --- & ON & 8 & 96.5 @105K & $<$0.20$\\times$ & Healthy \\\\\n024b s1 & Cheetah Run & --- & ON & 8 & 77.3 @105K & 0.10$\\times$ & Healthy \\\\\n008a\\_ch s0 & Cheetah Run & exp$^a$ & OFF & 15 & 532.4 @105K & 1.08$\\times$ & Healthy \\\\\n008a\\_ch s1 & Cheetah Run & exp$^a$ & OFF & 15 & 504.4 @105K & 1.29$\\times$ & Healthy \\\\\n077 & Cheetah baseline (s0) & --- & --- & 15 & 448.1 @105K & 1.00$\\times$ & Healthy \\\\\n\\rowcolor{gray!15}\n078 & Cheetah trigger (s0) & trn & ON & 8 & 119.5 @105K & 4.10$\\times$ & Onset (self-corr.) \\\\\n\\rowcolor{gray!15}\n019b & PickCube-v1 & trn & ON & 8 & 26.64 @200K & 3.78$\\times$$^c$ & Transient onset \\\\\n054 & PickCube-v1 & frz$^b$ & ON & 8 & --- & 8.81$\\times$$^h$ & Env.\\ transient (ctrl) \\\\\n049 & StackCube-v1 & trn & ON & 8 & 34.9 @212K & 5.05$\\times$$^f$ & Env.\\ transient \\\\\n052 & StackCube-v1 & trn & ON & 8 & --- & 4.67$\\times$$^f$ & Env.\\ transient \\\\\n051 & StackCube-v1 & frz$^b$ & ON & 8 & 30.7 @155K & 4.30$\\times$$^f$ & Env.\\ transient (ctrl) \\\\\n050 & PegInsertionSide-v1 & trn & ON & 8 & 20.86 @212K & 10.05$\\times$$^g$ & Env.\\ dynamics \\\\\n053 & PegInsertionSide-v1 & frz$^b$ & ON & 8 & 5.89 & 8.10$\\times$$^g$ & Env.\\ dynamics (ctrl) \\\\\n055 & PegInsertionSide-v1 & trn & ON & 8 & 11.44 @212K & 3.08$\\times$$^g$ & Env.\\ dynamics \\\\\n056 & PegInsertionSide-v1 & frz$^b$ & ON & 8 & 4.37 @212K & 11.32$\\times$$^g$ & Env.\\ dynamics (ctrl) \\\\\n046 & Cheetah Run & frz$^b$ & ON & 8 & 150.5 @215K & 1.35$\\times$ & No CIVO \\\\\n058 & Cheetah Run & frz$^b$ & ON & 8 & 80.46 @215K & 0.78$\\times$ & No CIVO \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cartpole Swingup}} \\\\\n060 & Cartpole baseline (3 seeds) & --- & --- & 15 & 557.0 @105K$^i$ & --- & Healthy \\\\\n061 & Cartpole trigger (3 seeds) & trn & ON & 8 & 236.3 @105K$^i$ & --- & No CIVO \\\\\n062 & Cartpole control (3 seeds) & --- & ON & 8 & 244.8 @105K$^i$ & --- & No CIVO \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize\ntrn = trained ($d{=}32$, subsample ON);\ntrn$^\\ddagger$ = full-pathway SGS (all non-KL gradients detached);\nexp$^a$ = trained, subsample OFF;\nfrz$^b$ = frozen ($d{=}32$, \\texttt{requires\\_grad=False});\n--- = removed ($d{=}0$).\\\\\n$^*$ Seed 1 only: peak NVE with transient exceedances (1.60$\\times$ at 35K, 1.66$\\times$ at 95K); self-correcting, no sustained escalation. Seed 2 collapsed.\\\\\n$^\\diamond$ Transitional; train returns still declining (peak 470 to 139 over final 8K steps). Collapse had not reached equilibrium at 105K.\\\\\n$^\\dagger$ NVE self-corrected ($4.72\\times$ $\\to$ $1.22\\times$) but policy did not recover (eval 10.5\\% of baseline).\\\\\n$^c$ NVE normalized against exp\\_019a\\_v2 (vanilla DreamerV3 on PickCube-v1).\\\\\n$^d$ Peak NVE $9.94\\times$ at 45K (transient, self-correcting to $<$1$\\times$ by 55K); final eval 221.5.\\\\\n$^e$ Not used for NVE normalization; reported for completeness. Seed~1 (eval 915.7) is the NVE reference baseline.\\\\\n$^f$ StackCube transient: frozen control (exp\\_051, peak $4.30\\times$ at 42.5K) matches trained (exp\\_049/052), self-correcting by 82.5K; environment-specific, not $\\dt$-embedding-driven.\\\\\n$^g$ PegInsertion environment dynamics: seed~0 trained peaks at $10.05\\times$ (82.5K); seed~1 trained (exp\\_055) peaks at $3.08\\times$ (92.5K), final $0.50\\times$ at 212.5K; seed~1 frozen (exp\\_056) peaks at $11.32\\times$ (82.5K), final $1.19\\times$ at 212.5K. Frozen final exceeds trained final; ordering is seed-dependent, ruling out $\\dt$-embedding causation.\\\\\n$^h$ PickCube environment transient: frozen control peak $8.81\\times$ at 62.5K, self-correcting to $0.55\\times$ at 72.5K; matches trained (exp\\_019b) trajectory.\\\\\n$^\\heartsuit$ Evaluated at 55K steps due to early termination of exp\\_008d; extended run (exp\\_009e) reached 131.08 at 105K.\\\\\n$^i$ Cartpole: exp\\_060 reports seed~2 eval only; exp\\_061/062 report 3-seed mean.\\\\\n$^j$ CIVO-unrelated learning stagnation; NVE $\\leq 0.6\\times$, no value overestimation.\\par}\n\\end{table*}\n\n\\begin{table}[h]\n\\centering\n\\caption{Cross-domain CIVO reproducibility. ``$\\dt$-emb-dep.'' indicates trained peaks consistently exceed frozen at matched timepoints across seeds.}\n\\label{tab:cross_domain}\n\\footnotesize\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Domain} & \\textbf{Environment} & \\textbf{Trained} & \\textbf{Frz ctrl} & \\textbf{$\\dt$-emb-dep.\\ CIVO} \\\\\n\\midrule\nLocomotion & Walker Walk & 5/5 & 0/3 & Yes (NVE $1.53$--$4.72\\times$) \\\\\nLocomotion & Cheetah Run & 2/2 & 0/2 & Yes (NVE $8.27$--$108.5\\times$) \\\\\nManipulation & StackCube-v1 & 0/2 & 0/1 & No (frozen$\\approx$trained) \\\\\nManipulation & PegInsertionSide & 0/2 & 0/2 & No (seed-dep.\\ ordering) \\\\\nManipulation & PickCube-v1 & 0/1 & 0/1 & No (frozen spike similar) \\\\\n\\midrule\nLocomotion & Cartpole Swingup & 0/3 & 0/3 & No (single-joint) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cartpole Swingup.} Cartpole Swingup (single-DoF locomotion) serves as a cross-environment control. Three seeds of the CIVO-trigger configuration (exp\\_061: trained $e_{\\dt}$, subsample ON, $H{=}8$, $\\dt{=}2$) and three seeds of the no-embedding control (exp\\_062) both produce zero CIVO onset. Despite using the hyperparameter combination that triggers collapse in all 10 tested multi-joint locomotion seeds (Walker/Cheetah), the single-joint Cartpole shows no CIVO, confirming the phenomenon requires multi-joint dynamics where temporal abstraction amplifies the reward fidelity gap.\n\n\\section{NVE Threshold Sensitivity Analysis}\n\\label{sec:appendix_sensitivity}\n\nWe report the full sensitivity analysis for the NVE diagnostic framework introduced in Section~\\ref{sec:results}. The main text reports Task~B2 (any CIVO detection, $\\nve \\geq 1.5\\times$). Here we additionally present Task~B1, which restricts the positive class to \\emph{sustained} CIVO, specifically experiments exhibiting persistent, accelerating value overestimation that progresses to performance collapse. Transient CIVO cases (e.g., exp~009b, which self-corrects after a brief excursion above the threshold) are classified as negative in B1.\n\n\\subsection{Per-Experiment NVE Values}\n\nTable~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\\_v3 seeds and exp\\_059). Experiments are sorted by descending NVE. Experiment 008e\\_v3\\_s2 exhibits elevated NVE ($3.78\\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\\_v3\\_s3 exhibits CIVO with NVE $4.02\\times$ despite $\\Delta t{=}1$ imagination.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\\ = transient CIVO with self-correction.}\n\\label{tab:nve_raw}\n\\small\n\\begin{tabular}{@{}lrccc@{}}\n\\toprule\nExperiment & NVE & Mechanism & B1 & B2 \\\\\n\\midrule\n006          & 4.83 & sustained CIVO & $+$ & $+$ \\\\\n059          & 4.72 & self-correcting CIVO & $-$ & $+$ \\\\\n008d         & 4.12 & sustained CIVO & $+$ & $+$ \\\\\n008e\\_v3\\_s3 & 4.02 & CIVO           & $+$ & $+$ \\\\\n008e\\_v3\\_s2 & 3.78 & IRD (non-CIVO) & $-$ & $-$ \\\\\n009b         & 1.62 & transient CIVO & $-$ & $+$ \\\\\n001          & 1.00 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s4 & 0.99 & non-CIVO       & $-$ & $-$ \\\\\n008f         & 0.97 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s1 & 0.94 & non-CIVO       & $-$ & $-$ \\\\\n008a         & 0.93 & non-CIVO       & $-$ & $-$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Multi-Threshold Classification Performance}\n\nTable~\\ref{tab:sensitivity_b1} reports Task~B1 classification metrics across six NVE thresholds. Task~B1 achieves $\\text{AUROC} = 0.917$ because exp\\_059 (NVE${=}4.72\\times$, self-correcting CIVO, B1-negative) ranks above two sustained-CIVO positives ($4.12\\times$, $4.02\\times$), breaking the perfect rank separation that held before its inclusion. The optimal threshold lies in the interval $(3.78, 4.02]$; we report $\\geq 3.9\\times$ as a representative value (accuracy $10/11 = 90.9\\%$). Table~\\ref{tab:sensitivity_b2} provides the corresponding analysis for Task~B2 ($\\text{AUROC} = 0.967$, imperfect separation due to 008e\\_v3\\_s2).\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B1}: Sustained CIVO detection sensitivity analysis ($n_{\\text{pos}}=3$, $n_{\\text{neg}}=8$, $n=11$, $\\text{AUROC}=0.917$). All confidence intervals are two-sided Clopper-Pearson exact binomial ($\\alpha=0.05$). $^\\dagger$Optimal threshold in $(3.78, 4.02]$; exp\\_059 (NVE${=}4.72\\times$, B1-negative) is the sole false positive.}\n\\label{tab:sensitivity_b1}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 3 & 4 & 0 & 4 & 63.6\\% \\; [30.8, 89.1] & 42.9\\% & 100\\% & 60.0\\% \\\\\n$\\geq 1.2\\times$ & 3 & 3 & 0 & 5 & 72.7\\% \\; [39.0, 94.0] & 50.0\\% & 100\\% & 66.7\\% \\\\\n$\\geq 1.5\\times$ & 3 & 3 & 0 & 5 & 72.7\\% \\; [39.0, 94.0] & 50.0\\% & 100\\% & 66.7\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.7\\times$ & 3 & 2 & 0 & 6 & 81.8\\% \\; [48.2, 97.7] & 60.0\\% & 100\\% & 75.0\\% \\\\\n$\\geq 2.0\\times$ & 3 & 2 & 0 & 6 & 81.8\\% \\; [48.2, 97.7] & 60.0\\% & 100\\% & 75.0\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 3.9\\times^\\dagger$ & 3 & 1 & 0 & 7 & 90.9\\% \\; [58.7, 99.8] & 75.0\\% & 100\\% & 85.7\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B2}: Any CIVO detection sensitivity analysis ($n_{\\text{pos}}=5$, $n_{\\text{neg}}=6$, $n=11$, $\\text{AUROC}=0.967$). The single false positive at $\\geq 1.5\\times$ is 008e\\_v3\\_s2 (IRD mechanism, not CIVO). The $1.5\\times$ threshold (highlighted) maximizes F1 while maintaining perfect recall.}\n\\label{tab:sensitivity_b2}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 5 & 2 & 0 & 4 & 81.8\\% \\; [48.2, 97.7] & 71.4\\% & 100\\% & 83.3\\% \\\\\n$\\geq 1.2\\times$ & 5 & 1 & 0 & 5 & 90.9\\% \\; [58.7, 99.8] & 83.3\\% & 100\\% & 90.9\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.5\\times$ & 5 & 1 & 0 & 5 & 90.9\\% \\; [58.7, 99.8] & 83.3\\% & 100\\% & 90.9\\% \\\\\n$\\geq 1.7\\times$ & 4 & 1 & 1 & 5 & 81.8\\% \\; [48.2, 97.7] & 80.0\\% & 80.0\\% & 80.0\\% \\\\\n$\\geq 2.0\\times$ & 4 & 1 & 1 & 5 & 81.8\\% \\; [48.2, 97.7] & 80.0\\% & 80.0\\% & 80.0\\% \\\\\n$\\geq 3.9\\times$ & 4 & 0 & 1 & 6 & 90.9\\% \\; [58.7, 99.8] & 100\\% & 80.0\\% & 88.9\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B2 (full evaluation set)}: Any CIVO detection across two environments ($n_{\\text{pos}}=9$, $n_{\\text{neg}}=8$, $n=17$, $\\text{AUROC}=0.972$). Includes Walker Walk (15 configurations) and Cheetah Run (2 configurations).}\n\\label{tab:sensitivity_b2_full}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 9 & 2 & 0 & 6 & 88.2\\% \\; [63.6, 98.5] & 81.8\\% & 100\\% & 90.0\\% \\\\\n$\\geq 1.2\\times$ & 9 & 1 & 0 & 7 & 94.1\\% \\; [71.3, 99.9] & 90.0\\% & 100\\% & 94.7\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.5\\times$ & 9 & 1 & 0 & 7 & 94.1\\% \\; [71.3, 99.9] & 90.0\\% & 100\\% & 94.7\\% \\\\\n$\\geq 1.7\\times$ & 7 & 1 & 2 & 7 & 82.4\\% \\; [56.6, 96.2] & 87.5\\% & 77.8\\% & 82.4\\% \\\\\n$\\geq 2.0\\times$ & 7 & 1 & 2 & 7 & 82.4\\% \\; [56.6, 96.2] & 87.5\\% & 77.8\\% & 82.4\\% \\\\\n$\\geq 3.9\\times$ & 7 & 0 & 2 & 8 & 88.2\\% \\; [63.6, 98.5] & 100\\% & 77.8\\% & 87.5\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\subsection{Threshold Recommendation}\n\nFor the main diagnostic (Task~B2), we recommend $\\nve \\geq 1.5\\times$ as the operating threshold for three reasons:\n\n\\begin{enumerate}[nosep,leftmargin=*]\n\\item \\textbf{Maximum recall.} The $1.5\\times$ threshold achieves 100\\% recall, detecting all five CIVO cases including the transient case (009b, $\\nve = 1.62\\times$). Raising the threshold to $1.7\\times$ loses 009b, dropping recall to 80.0\\%.\n\\item \\textbf{Best F1.} At $1.5\\times$, F1 = 90.9\\%, the highest among all tested thresholds for B2. The single false positive (008e\\_v3\\_s2) is mechanistically identifiable as IRD rather than CIVO.\n\\item \\textbf{Sensitivity--specificity tradeoff.} Lower thresholds ($1.0\\times$) add false positives without gaining true positives. Higher thresholds ($\\geq 1.7\\times$) sacrifice recall without eliminating the 008e\\_v3\\_s2 false positive (which requires $\\tau > 3.78$).\n\\end{enumerate}\n\nFor Task~B1 (sustained CIVO only), the optimal threshold $\\nve \\geq 3.9\\times$ achieves $10/11$ accuracy ($90.9\\%$, 95\\% CI: [58.7\\%, 99.8\\%]); the sole false positive is exp\\_059 (NVE${=}4.72\\times$, self-correcting CIVO classified as B1-negative).\n\n\\subsection{Expanded ROC Analysis}\n\\label{sec:roc_analysis}\n\nThe original $n{=}17$ analysis (Tables~\\ref{tab:sensitivity_b1}--\\ref{tab:sensitivity_b2_full}) predates the SGS, RAVE, and TCN experiments. We extend the NVE diagnostic evaluation to $n{=}56$ configurations spanning all tested interventions. Figure~\\ref{fig:nve_roc} shows the receiver operating characteristic curve with 95\\% bootstrap confidence interval (10{,}000 resamples).\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.7\\columnwidth]{../../artifacts/figures/nve_roc_curve.pdf}\n\\caption{NVE ROC curve ($n{=}56$ configurations, AUROC${=}0.990$, comprehensive validation). The preset $\\nve \\geq 1.5\\times$ operating point (star) achieves TPR${=}1.00$, FPR${=}0.09$, accuracy${=}53/56$, F1${=}0.941$. Three false positives arise from non-CIVO value overestimation: mitigation transient VE spike (008e\\_v3 subsample, $1.93\\times$) and frozen embedding transients (047, $1.71\\times$; 057, $1.88\\times$). Threshold calibrated and validated post-hoc; cross-architecture validation deferred.}\n\\label{fig:nve_roc}\n\\end{figure}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.7\\columnwidth]{../../artifacts/figures/nve_threshold_prf.pdf}\n\\caption{Precision, Recall, and F1 as a function of NVE threshold ($n{=}56$ configurations). Peak F1${=}0.941$ at $\\tau{=}1.5\\times$, where recall remains perfect ($1.00$) and precision${=}0.889$. The plateau of high F1 across $\\tau \\in [1.5, 1.7]$ indicates robustness to threshold selection.}\n\\label{fig:nve_prf}\n\\end{figure}\n\nWe label a configuration as CIVO-positive if and only if (i)~it uses a trained $\\dt$-embedding with multi-rate data exposure, and (ii)~NVE exceeds $1.5\\times$ with co-occurring entropy collapse. Configurations exhibiting high NVE through other mechanisms (gradient truncation side effects, value anchor pollution) are labeled non-CIVO.\n\nThe three false positives (FPR${=}0.18$) are mechanistically distinct from CIVO: (1)~RAVE anchor pollution (exp\\_028, the EMA anchor becomes inflated, producing overestimation through a different pathway); (2)~obs-decoder SGS-induced value distortion (exp\\_025 seed~2, blocking observation decoder gradients damages the RSSM latent space); (3)~IRD eval-driven collapse (exp\\_008e\\_v3 seed~2, actor entropy \\emph{increases} with evaluation collapse, mechanistically distinct from CIVO's entropy \\emph{decrease}). All three produce NVE $> 1.5\\times$ through non-CIVO mechanisms, indicating that the NVE diagnostic detects value overestimation broadly rather than CIVO specifically---a feature rather than a limitation for practitioners monitoring deployment health. The closest sub-threshold case (008f seed~4, NVE${=}1.41\\times$) lacks $\\dt$-conditioning entirely ($d{=}0$); its elevated NVE reflects transient value noise that self-corrects without the positive feedback loop characteristic of CIVO. The closest above-threshold positive (008d seed~3, NVE${=}1.53\\times$) exhibits the full CIVO causal chain: trained $\\dt$-embedding, entropy decrease, and evaluation collapse to 14\\% of baseline.\n\n\\paragraph{Comprehensive validation ($n{=}56$).}\nExpanding the evaluation set to all classifiable experiments yields $n{=}56$ ($n_{\\text{pos}}{=}24$, $n_{\\text{neg}}{=}32$), spanning Walker Walk, Cheetah Run, and multiple intervention configurations (SGS, TCN, dual-critic, frozen embedding). At the $1.5\\times$ threshold: AUROC${=}0.990$, precision${=}0.889$, recall${=}1.000$, F1${=}0.941$, accuracy${=}53/56$. The three false positives are: exp\\_008e\\_v3\\_subsample ($1.93\\times$, mitigation config with transient VE spike), exp\\_047 ($1.71\\times$, frozen embedding transient), and exp\\_057 ($1.88\\times$, frozen embedding transient). All 24 CIVO-positive configurations are correctly detected (FN${=}0$), with CIVO-positive NVE ranging from $1.53\\times$ (008d seed~3, late-onset) to $70.64\\times$ (010b seed~0, Cheetah). The substantial increase in sample size from $n{=}32$ to $n{=}56$ strengthens confidence in the $1.5\\times$ threshold as a robust diagnostic boundary.\n\n\\subsection{NVE Normalization Robustness}\n\\label{sec:nve_robustness}\n\nTo assess sensitivity to baseline seed choice, we extend the single-seed baseline (seed~1, eval 915.7 at 105K) to three additional seeds trained to 505K steps (Table~\\ref{tab:baseline_seeds}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Walker Walk baseline seeds at 105K and 505K steps.}\n\\label{tab:baseline_seeds}\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Seed} & \\textbf{Eval@105K} & \\textbf{Eval@505K} & \\textbf{ve@65K} & \\textbf{ve@105K} \\\\\n\\midrule\ns1 & 915.7 & 970.4 & 0.563 & 0.656 \\\\\ns2 & 443.5 & 945.7 & 0.898 & 0.742 \\\\\ns3 & 869.0 & 947.7 & --- & 0.664 \\\\\ns4 & 922.8 & 938.9 & --- & 0.624 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nSeed~2 exhibits slow convergence (eval 443.5 at 105K, recovering to 945.7 by 512K), confirming non-pathological slow convergence rather than seed failure. Its elevated $v/e$ ratio at 65K (0.898 vs.\\ 0.563 for seed~1) reflects the low evaluation denominator rather than pathological value overestimation. Using seed~2 as the sole normalization reference systematically deflates NVE values, causing two marginal CIVO-positive configurations (008d seed~3, peak NVE $1.53\\times$; 009b seed~2, peak NVE $1.62\\times$) to fall below the $1.5\\times$ threshold. Core CIVO cases (peak NVE $> 3\\times$) remain correctly classified under all baseline seeds.\n\nSingle-seed normalization (s1) yields AUROC $= 0.933$ and accuracy 7/8 (87.5\\%) on the Walker subset. Four-seed mean normalization yields AUROC $= 0.867$ and accuracy 6/8 (75.0\\%): the boundary case exp\\_009b flips from $\\nve = 1.62\\times$ (s1) to $1.23\\times$ (4-seed mean), because its peak occurs at 45K when the s1 $v/e$ ratio (0.331) is well below the 4-seed mean (0.436). All high-NVE configurations remain correctly classified (006: $4.84\\times \\to 4.52\\times$; 008d: $4.12\\times \\to 3.54\\times$). The $1.5\\times$ threshold thus correctly identifies all strong CIVO cases regardless of baseline choice; sensitivity is confined to configurations within 10\\% of the threshold.\n\n\\paragraph{Normalization conventions.} Walker NVE is normalized against the single-seed baseline (seed~1, exp\\_001, 505K steps). Cheetah NVE is normalized against a 5-seed mean baseline (seeds~0--4, each run to ${\\sim}$210K steps). The differing seed counts reflect available baseline data; both provide sufficient coverage of the respective experimental windows (Walker: 210K analysis window; Cheetah: 105K analysis window).\n\n\\paragraph{Limitations.} The initial $n{=}11$ analysis had wide Clopper-Pearson confidence intervals (e.g., 90.9\\% accuracy, 95\\% CI [58.7\\%, 99.8\\%]). The comprehensive evaluation ($n{=}56$, AUROC${=}0.990$, F1${=}0.941$; Figure~\\ref{fig:nve_roc}) substantially tightens these bounds. Table~\\ref{tab:sensitivity_b2_full} reports the $n{=}17$ two-environment core evaluation. Cross-architecture validation is deferred to future work.\n\n\\subsection{Leave-One-Environment-Out Cross-Validation}\n\\label{sec:nve_loeo}\n\nTo assess whether $\\theta{=}1.5\\times$ generalizes beyond the in-sample evaluation, we perform leave-one-environment-out (LOEO) cross-validation across Walker ($n{=}15$), Cheetah ($n{=}5$), and PickCube ($n{=}2$). For each fold, we hold out all experiments from one environment, select the optimal accuracy-maximizing threshold range on the remaining training set, and evaluate the fixed $\\theta{=}1.5\\times$ on the held-out environment.\n\n\\begin{table}[h]\n\\centering\n\\caption{Leave-one-environment-out cross-validation of NVE threshold $\\theta=1.5\\times$.\nFor each fold, the threshold is validated on an environment whose data was \\emph{not} used\nto select $\\theta$. The optimal threshold range on each training set is reported;\n$\\theta=1.5$ falls within the optimal range in all three folds.}\n\\label{tab:nve_loeo}\n\\begin{tabular}{lccccc}\n\\toprule\nHeld-out & $N_{\\text{train}}$ & $N_{\\text{test}}$ & $\\theta_{\\text{opt}}$ range & Test Accuracy & Test AUROC \\\\\n\\midrule\nPickCube & 20 & 2 & $(1.45,\\, 1.53]$ & 2/2 (1.000) & 1.000 \\\\\nCheetah  & 17 & 5 & $(1.45,\\, 1.53]$ & 5/5 (1.000) & 1.000 \\\\\nWalker   &  7 & 15 & $(1.00,\\, 3.78)$ & 14/15 (0.933) & 0.963 \\\\\n\\midrule\n\\textbf{Mean} & — & — & — & \\textbf{0.978} & \\textbf{0.988} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe threshold $\\theta{=}1.5\\times$ falls within the optimal accuracy range for all three training folds: $(1.45, 1.53]$ when Walker data is available, and the wider $(1.00, 3.78)$ when training on Cheetah$+$PickCube only (where CIVO and non-CIVO NVE values are well-separated). The single cross-validation error is exp\\_008e\\_v3 seed~2 (Walker), an IRD collapse mechanistically distinct from CIVO (\\S\\ref{sec:roc_analysis}). Mean held-out accuracy is 0.978 and mean AUROC is 0.988, confirming that $\\theta{=}1.5\\times$ generalizes across environments without retuning.\nPickCube fold confidence intervals remain wide (Clopper-Pearson 95\\% CI: $[0.158, 1.000]$) due to $N_{\\text{test}}{=}2$.\n\n\\subsection{Leave-One-Config-Out Cross-Validation}\n\\label{sec:nve_loco}\n\n\\paragraph{Leave-One-Config-Out Cross-Validation.}\nTo rule out threshold overfitting to any particular experimental configuration, we perform leave-one-config-out (LOCO) cross-validation over $K{=}12$ configuration groups (e.g., \\texttt{008d\\_civo\\_trigger}, \\texttt{frozen\\_dt\\_emb}, \\texttt{tcn}; $n{=}56$ total). Each fold holds out all experiments from one configuration, selects the F1-maximizing threshold on the remaining $K{-}1$ groups, and evaluates on the held-out group.\n\nIn $10/12$ folds, the training-optimal threshold falls within $\\pm 0.05$ of $\\theta{=}1.5\\times$ (mean $1.61 \\pm 0.23$, range $[1.47, 2.12]$). The two folds selecting a higher threshold ($\\theta{=}2.1$; \\texttt{008d\\_civo\\_trigger} and \\texttt{tcn}, both predominantly CIVO-positive) perform \\emph{worse} on their held-out sets than $\\theta{=}1.5$ (accuracy $0.78$/$0.88$ vs.\\ $1.00$/$1.00$), confirming that the fixed threshold generalizes better than per-fold optimization in these cases. Cross-validated accuracy at $\\theta{=}1.5$ is $53/56 = 94.6\\%$, identical to the in-sample result, with train AUROC consistently high across folds ($0.988 \\pm 0.003$). The three misclassifications are the same mechanistically distinct false positives identified in \\S\\ref{sec:roc_analysis}: two frozen-embedding transients (exp\\_047, exp\\_057) and one mitigation-config transient (exp\\_008e\\_v3\\_subsample). No CIVO-positive configuration is missed in any fold (FN${=}0$ across all 12 folds).\n\n% --- APPENDIX B: Factorial Ablation Details ---\n\n\\section{Factorial Ablation Details}\n\\label{sec:appendix_factorial}\n\nThis appendix provides the full factorial ablation results summarized in \\S\\ref{sec:f3f5_summary} of the main text.\n\n\\paragraph{Embedding gradient analysis.}\nTable~\\ref{tab:three_way_emb} isolates embedding \\emph{trainability} as the necessary condition for CIVO by comparing four gradient conditions under otherwise identical configurations ($H{=}8$, subsample ON, $\\dt{=}2$ imagination).\n\n\\begin{table}[h]\n\\centering\n\\caption{$\\dt$-embedding gradient conditions on Walker Walk. Any gradient pathway updating $e_{\\dt}$ is sufficient to induce CIVO; freezing or removing the embedding dramatically reduces severity.}\n\\label{tab:three_way_emb}\n\\footnotesize\n\\begin{tabular}{lccccl}\n\\toprule\nCondition & Grad flow & Exp(s) & NVE peak & Eval & CIVO \\\\\n\\midrule\nTrained & all & 008d, 059 & $1.53$--$4.72\\times$ & 64--268 & 5/5 \\\\\nReward detach & obs+KL only & 044 & $4.45\\times$ & 44$\\to$538$^\\dagger$ & 1/1 \\\\\nFull SGS & KL only & 018 & $1.66\\times$ & 448 & 1/1$^*$ \\\\\nFrozen & none & 042, 015b, 047, 057 & $0.19$--$1.88\\times$$^\\ddagger$ & 204--612 & 2/4 \\\\\nRemoved & N/A & 008f & $0.97$--$1.41\\times$ & 307--503 & 0/3 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$Full-SGS seed~1 (NVE $1.66\\times$); seed~2 collapsed. $^\\dagger$Self-corrected at ${\\sim}175$K (eval 44$\\to$538, 59\\% baseline; 224K run). $^\\ddagger$Exp\\_047 (NVE $1.71\\times$) and Exp\\_057 (NVE $1.88\\times$): both transient, self-correcting within 20K steps.\\par}\n\\end{table}\n\n\\paragraph{Controlled three-way causal ablation.}\nExperiments 067--069 provide a minimal causal ablation on Walker Walk (seed${=}1$), varying \\emph{only} the $\\dt$-embedding treatment while holding all other hyperparameters fixed ($H{=}8$, subsample ON, $\\dt{=}2$ imagination). Table~\\ref{tab:causal_ablation} shows that trained $\\dt$-embedding is necessary and sufficient for CIVO: freezing the embedding (gradient flow blocked, embedding weights still present) eliminates CIVO as completely as removing the embedding ($d{=}0$), ruling out the alternative hypothesis that embedding \\emph{presence} alone causes CIVO. Combined with all prior seeds, trained $\\dt$-embedding triggers CIVO in 10/10 multi-joint locomotion seeds (8 Walker, 2 Cheetah) versus 0/8 controls (Fisher exact $p < 0.0001$).\n\n\\begin{table}[h]\n\\centering\n\\caption{Three-way causal ablation (Walker Walk, seed${=}1$). Only the $\\dt$-embedding treatment varies; all other configuration is identical. Trained embedding triggers CIVO; frozen and removed do not.}\n\\label{tab:causal_ablation}\n\\footnotesize\n\\begin{tabular}{llccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Embedding} & \\textbf{NVE peak} & \\textbf{Eval final} & \\textbf{CIVO} \\\\\n\\midrule\n\\rowcolor{gray!15}\n068 & Trained ($d{=}32$) & $6.57\\times$ & 39.1 & Yes (alert @85K) \\\\\n067 & Frozen ($d{=}32$, \\texttt{req\\_grad=F}) & $0.40\\times$ & 281.5 & No \\\\\n069 & Removed ($d{=}0$) & $0.66\\times$ & 237.8 & No \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe reward-detach condition (exp\\_044, \\texttt{reward\\_dt\\_emb\\_detach=True}) uses a backward hook to block reward-head gradients from reaching $e_{\\dt}$, complementing the framework-level Reward SGS (exp\\_016e). Both yield the same directional result---CIVO onset not prevented---ruling out implementation artifacts. Exp\\_044 exhibits delayed CIVO onset (${\\sim}95$K vs.\\ typical $25$--$35$K), consistent with reduced but non-zero gradient pressure on $e_{\\dt}$. Over a full 224K run, exp\\_044 self-corrects: eval recovers from 44 (95K) to 538 (215K, 59\\% baseline), but this recovery is incomplete compared to spontaneous recovery without gradient intervention (exp\\_045: 868, 95\\% baseline). The lower asymptote suggests that selectively disrupting gradient flow may create optimization difficulties beyond CIVO itself.\n\nTable~\\ref{tab:factorial_design} summarizes the experimental configurations.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Factorial design. Each row specifies one experimental configuration. \\textbf{Emb}: $\\dt$-embedding mode. \\textbf{Sub}: temporal subsampling. \\textbf{H}: imagination horizon. \\textbf{Imag $\\dt$}: temporal resolution used during imagination.}\n\\label{tab:factorial_design}\n\\small\n\\setlength{\\tabcolsep}{3.5pt}\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\n\\textbf{ID} & \\textbf{Purpose} & \\textbf{Emb} & \\textbf{Sub} & \\textbf{H} & \\textbf{Imag $\\dt$} \\\\\n\\midrule\n001 & Reference baseline & --- & --- & 15 & 1 \\\\\n006 & Fixed $\\dt{=}2$ & trn & on & 15 & 2 \\\\\n007 & Fixed $\\dt{=}4$ & trn & on & 15 & 4 \\\\\n\\midrule\n008a & Unexposed emb ctrl & exp$^a$ & off & 15 & 2 \\\\\n008c & Horizon control & exp$^a$ & off & 8 & 2 \\\\\n008d & Collapse condition & trn & on & 8 & 2 \\\\\n008e\\_v3 & $\\dt{=}1$ imag control & trn & on & 15 & 1 \\\\\n008f & Causal ablation & --- & on & 8 & 2 \\\\\n\\midrule\n015b & Frozen-emb ctrl & frz$^b$ & on & 8 & 2 \\\\\n016e & Stop-grad (reward) & trn$^\\dagger$ & on & 8 & 2 \\\\\n018 & Full-SGS & trn$^\\ddagger$ & on & 8 & 2 \\\\\n\\midrule\n005 & Learned gate & adaptive & off & 15 & learned \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{-2pt}\n{\\raggedright\\footnotesize\ntrn = trained ($d{=}32$, exposed to $\\dt{>}1$ data via subsample ON);\nexp$^a$ = trained ($d{=}32$) but never exposed to $\\dt{>}1$ data (subsample OFF);\nfrz$^b$ = frozen random projection ($d{=}32$, \\texttt{requires\\_grad=False});\n--- = removed ($d{=}0$).\\\\\n$^\\dagger$ \\texttt{reward\\_dt\\_emb\\_detach=True}; $^\\ddagger$ all non-KL gradients to \\texttt{dt\\_emb} detached.\\par}\n\\end{table}\n\n\\subsection{F3: Unexposed Temporal Embedding Suppresses Value Drift}\n\\label{sec:f3}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig3_factorial_grid.pdf}\n\\caption{Factorial isolation of CIVO trigger. Only the combination of trained $e_{\\dt}$ and multi-rate data (upper-left cell) produces pathological NVE. Neither factor alone is sufficient.}\n\\label{fig:factorial_grid}\n\\end{figure}\n\nThe empirical finding that trained embedding \\emph{plus} multi-rate exposure jointly predict CIVO rests on two complementary controls that each remove one factor while holding the other constant.\n\n\\paragraph{Evidence A: exposure is necessary (exp\\_008a).}\nExp\\_008a uses a trained embedding ($d{=}32$, gradients enabled) that is never exposed to $\\dt{>}1$ transitions during world-model training (subsample OFF). Despite sharing the same embedding architecture as exp\\_008d, its NVE remains in the $0.83$--$0.93\\times$ range across 3 seeds (105K steps). Performance follows two V-shaped recovery cycles, reaching 777.7 at 105K (85\\% of baseline). The critical factor is not the embedding's capacity to represent temporal information, but its adaptation to multi-rate data that enables precise but inaccurate $\\dt{>}1$ state predictions within the RSSM.\n\nThis contrasts with exp\\_006 (trained $e_{\\dt}$, subsample ON, $H{=}15$), where NVE accelerates from $1.61\\times$ at 45K to $2.31\\times$ at 55K before catastrophic collapse to 132.9 at 65K. Both experiments use identical trained embeddings ($d{=}32$, gradients enabled) and $H{=}15$, differing only in whether the world model sees $\\dt{>}1$ transitions during training. This confirms that multi-rate data exposure, not embedding architecture, is the operative variable.\n\n\\paragraph{Evidence B: trainability is necessary (exp\\_015b).}\nExp\\_015b uses a frozen random-projection embedding ($d{=}32$, \\texttt{requires\\_grad=False}, subsample ON, $H{=}8$), the same multi-rate data regime as exp\\_008d, but with a non-trainable temporal signal. Despite full exposure to $\\dt{>}1$ transitions, the NVE peaks at $1.45\\times$ at 55K but does not sustain escalation: it retreats to $0.65\\times$ by 65K and settles at $0.42\\times$ by 105K (trajectory: $0.81 \\rightarrow 1.26 \\rightarrow 1.45 \\rightarrow 0.65 \\rightarrow 1.05 \\rightarrow 0.47 \\rightarrow 0.39 \\rightarrow 0.42$). The transient peak approaches but does not exceed the $1.5\\times$ CIVO threshold, and critically, the ratio self-corrects rather than exhibiting the monotonic escalation seen in trained-embedding runs. Final evaluation reaches only 204.2 at 105K, low but through a qualitatively different failure mode than CIVO. Actor loss approaches zero (gradient starvation; see \\S\\ref{sec:pathways}), the frozen embedding provides no useful gradient signal for temporal adaptation.\n\nThe contrast with exp\\_008d is stark: under identical data conditions (subsample ON, $H{=}8$), the trained embedding drives NVE to $4.12\\times$ with sustained monotonic escalation ($1.78 \\rightarrow 1.71 \\rightarrow 2.09 \\rightarrow 4.12$) and precedes full collapse (eval 82.8), while the frozen embedding peaks transiently at $1.45\\times$ before self-correcting to $0.42\\times$, a qualitative difference between sustained and transient overestimation. This demonstrates that a $\\dt$-embedding must be able to \\emph{co-adapt} with RSSM dynamics to produce the systematic reward-prediction bias that drives CIVO; a static random projection, regardless of its exposure to multi-rate data, cannot create this bias.\n\nTogether, these two controls establish that in all tested configurations, CIVO occurs only with the \\emph{joint} presence of (i)~a trainable embedding that can co-adapt with RSSM dynamics, and (ii)~multi-rate training data that drives this co-adaptation toward biased temporal predictions. Neither factor alone is sufficient.\n\nCross-environment validation on Cheetah Run replicates the empirical pattern: trained $e_{\\dt}$ precedes CIVO in both tested seeds (exp\\_010b, 2 seeds, NVE $8.27$--$108.52\\times$, collapse to 51.7/0.83) while removing the embedding eliminates it (exp\\_024b, 2 seeds, NVE $<0.2\\times$, eval 96.5/77.3). Freezing the embedding on Cheetah (exp\\_046, NVE${=}1.35\\times$ vs.\\ trained $70.64\\times$, a $52\\times$ reduction) further confirms that embedding trainability, not architecture, drives CIVO. This extends the sufficiency finding from Walker Walk to a second locomotion environment with qualitatively different dynamics (6-joint vs.\\ 2-joint).\n\n\\begin{table}[ht]\n\\centering\n\\small\n\\caption{Causal isolation: $e_{\\dt}$ configuration $\\times$ multi-rate data exposure. The combination of trained embedding and multi-rate exposure is the sole predictor of CIVO in tested configurations. Neither factor alone is sufficient.}\n\\label{tab:causal_matrix}\n\\begin{tabular}{lcc}\n\\toprule\n& Multi-rate data (\\textsc{on}) & Single-rate data (\\textsc{off}) \\\\\n\\midrule\nTrained $e_{\\dt}$ & exp\\_008d: \\textbf{CIVO} & exp\\_008a: healthy \\\\\n & NVE 4.12$\\times$, collapse & NVE 0.93$\\times$ \\\\\n\\midrule\nFrozen $e_{\\dt}$ & exp\\_015b: grad.\\ starvation & --- \\\\\n & peak NVE 1.45$\\times$ (transient) & \\\\\n\\midrule\nRemoved $e_{\\dt}$ & exp\\_008f: no CIVO & --- \\\\\n & NVE $\\leq$0.97$\\times$ & \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOnly the upper-left cell (trained embedding with multi-rate exposure) precedes CIVO (Table~\\ref{tab:causal_matrix}). This 2$\\times$2 structure establishes that both factors are jointly sufficient in tested configurations.\n\n\\subsection{F4: Degradation Scales Monotonically with \\texorpdfstring{$\\dt$}{dt}}\n\\label{sec:f4}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig5_dt_amplification.pdf}\n\\caption{Peak evaluation return as a function of imagination $\\dt$. Performance degrades monotonically: $\\dt{=}1$ (915.7) $>$ $\\dt{=}2$ (485.3, $-47\\%$) $>$ $\\dt{=}4$ (176.9, $-81\\%$).}\n\\label{fig:dt_amplification}\n\\end{figure}\n\nThe magnitude of degradation scales monotonically with the imagination step size (Figure~\\ref{fig:dt_amplification}). From the $\\dt{=}1$ baseline (915.7 at 105K), fixed $\\dt{=}2$ (exp\\_006) achieves a peak of only 485.3 ($-47\\%$), and fixed $\\dt{=}4$ (exp\\_007) peaks at 176.9 ($-81\\%$). This monotonic relationship is consistent with compounding model error: larger temporal gaps amplify the RSSM's prediction inaccuracy at each imagination step, and these errors accumulate across the rollout horizon.\n\n\\subsection{F5: Imagination Horizon and Subsampling Are Secondary Factors}\n\\label{sec:f5}\n\nNeither horizon length nor temporal subsampling precedes collapse without multi-rate data exposure: both trained-but-unexposed configurations (008a, 008c) maintain $\\nve < 0.93\\times$ (\\S\\ref{sec:f3}), while the trained-and-exposed counterpart (008d) collapses with $\\nve = 4.12\\times$.  The no-embedding configurations show cross-seed variance (008f: 503.0 vs.\\ 009c: 148.3) but neither exhibits $\\nve > 1.5\\times$; low evaluation alone does not indicate CIVO.\n\nThe $3.2\\times$ performance gap (008a: 777.7 vs.\\ 008c: 240.9) quantifies the horizon effect independently of CIVO, as both conditions maintain healthy NVE ($\\leq$0.93$\\times$).\n\n% --- APPENDIX C: Full Analysis & Discussion ---\n\n\\section{Full Analysis \\& Discussion}\n\\label{sec:appendix_analysis}\n\nThis appendix provides the complete mechanistic analysis summarized in Section~\\ref{sec:discussion} of the main text.\n\n\\subsection{The CIVO Mechanism}\n\\label{sec:civo_mechanism}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig4_mechanism_diagram.pdf}\n\\caption{CIVO mechanism diagram. The trained $\\dt$-embedding enables asymmetric reward prediction fidelity, initiating a feedback loop: biased RSSM rewards $\\to$ optimistic critic values $\\to$ actor exploitation $\\to$ reinforced state-distribution skew.}\n\\label{fig:civo_mechanism}\n\\end{figure}\n\n\\begin{table}[h]\n\\centering\n\\caption{RSSM fidelity at $\\dt{=}1$ vs.\\ $\\dt{=}2$. Trained embedding (008d) produces $2.78\\times$ reward gap; removing it (008f) eliminates the gap but degrades absolute prediction.}\n\\label{tab:rssm_fidelity}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{3}{c}{\\textbf{obs\\_MSE}} & \\multicolumn{3}{c}{\\textbf{reward\\_MAE}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\n\\textbf{Config} & $\\dt{=}1$ & $\\dt{=}2$ & Gap & $\\dt{=}1$ & $\\dt{=}2$ & Gap \\\\\n\\midrule\nBaseline & 13.49 & 27.50 & 2.04$\\times$ & 0.0102 & 0.0159 & 1.56$\\times$ \\\\\n008d (trained) & 41.31 & 53.67 & 1.30$\\times$ & 0.0568 & 0.1579 & 2.78$\\times$ \\\\\n008f (no emb) & 8.01 & 22.04 & 2.75$\\times$ & 0.7469 & 0.7526 & 1.01$\\times$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe RSSM fidelity analysis (Table~\\ref{tab:rssm_fidelity}) reveals the mechanistic core of CIVO (Figure~\\ref{fig:civo_mechanism}).  The trained $\\dt$-embedding enables the reward head to learn temporally differentiated predictions, but these predictions are asymmetrically accurate: reward MAE at $\\dt{=}1$ is $0.0568$, while at $\\dt{=}2$ it rises to $0.1579$, a $2.78\\times$ gap.  This gap is not an artifact of prediction difficulty alone; the no-embedding configuration (008f) exhibits a $1.01\\times$ gap, and the baseline shows $1.56\\times$.  The trained embedding actively amplifies the fidelity discrepancy by allowing the reward head to co-adapt with the temporal signal.\n\nThis asymmetric fidelity initiates a feedback loop with four stages: (1) the trained $\\dt$-embedding causes RSSM predictions at $\\dt > 1$ to carry systematically biased reward estimates; (2) the critic, trained entirely on imagined trajectories, internalizes these biased rewards as optimistic value estimates; (3) the actor exploits the overestimated regions of the value landscape, shifting its policy toward states that appear high-value only under the biased model; and (4) this policy shift further skews the distribution of imagined states, reinforcing the bias.  The diagnostic signature is a sustained $\\nve$ above $1.5\\times$, followed by evaluation collapse.\n\nA random-policy control experiment ($N{=}100$ rollouts, 95\\% bootstrap CI) decomposes CIVO into two necessary stages.  \\textbf{Stage~1 (dynamics bias):} even under a random policy, $\\dt{=}2$ imagination produces $1.68\\times$ higher mean reward than $\\dt{=}1$ in the trained-embedding model (008d): the RSSM prior already generates reward-favorable trajectories at $\\dt > 1$, independent of actor behavior.  \\textbf{Stage~2 (actor exploitation):} the trained actor learns to exploit these biased regions, amplifying the ratio to $2.90\\times$.  In the no-embedding control (008f), neither stage is present: the random-policy ratio is $1.11\\times$ and the trained-actor ratio is $0.98\\times$.  The decomposition attributes $\\approx 36\\%$ of the total effect to dynamics bias and $\\approx 64\\%$ to actor exploitation, which confirms that both stages are necessary for CIVO to manifest.\n\nThis mechanism is analogous to delusional bias \\citep{lu2018nondelusional}, but differs in origin: delusional bias arises from policy-class constraints, while CIVO is model-induced.  The consequence (policy exploitation of overestimated regions) is similar, but the causal pathway is distinct.\n\n\\paragraph{Signed reward error analysis.}\nTo test whether CIVO arises from one-step reward overprediction, we compute signed error (predicted $-$ actual) on posterior-conditioned RSSM predictions (Table~\\ref{tab:signed_error}). The trained-embedding model (008d) shows \\emph{negative} bias at $\\dt{=}2$ (mean signed error $-0.599$, only 8\\% of samples overpredicted), ruling out observation-level reward overprediction as the mechanism. The baseline is well-calibrated (mean SE $\\approx 0$), confirming methodological soundness. Value overestimation therefore occurs during \\emph{imagination-level} prior drift: the RSSM prior (unconditioned on observations) generates reward-favorable trajectories at $\\dt > 1$ (Stage~1 above, $1.68\\times$ ratio under random policy), and the critic accumulates these into overestimated returns. The one-step reward prediction is negatively biased when conditioned on real observations, but this posterior correction is unavailable during imagination. This also distinguishes CIVO from generic compounding error, which would produce \\emph{positive} signed error accumulating with horizon; the negative observation-level bias confirms that CIVO is a prior-drift phenomenon, not a reward-prediction artifact.\n\n\\begin{table}[h]\n\\centering\n\\caption{Signed reward error (predicted $-$ actual) on posterior-conditioned RSSM predictions. Negative values indicate underprediction. The trained-embedding model underpredicts at $\\dt{=}2$, ruling out observation-level reward overprediction as the CIVO mechanism.}\n\\label{tab:signed_error}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llrrrrr}\n\\toprule\n\\textbf{Config} & $\\dt$ & \\textbf{Mean SE} & \\textbf{Std} & \\textbf{\\%Over} & \\textbf{Actual} & \\textbf{Pred} \\\\\n\\midrule\nBaseline & 1 & $+0.001$ & 0.023 & 39.6\\% & 1.893 & 1.894 \\\\\n\\midrule\n008d (trained) & 1 & $+0.018$ & 0.072 & 61.8\\% & 0.361 & 0.379 \\\\\n008d (trained) & 2 & $\\mathbf{-0.599}$ & 0.722 & 8.0\\% & 0.721 & 0.121 \\\\\n\\midrule\n008f (no emb) & 1 & $-0.710$ & 0.704 & 14.0\\% & 0.921 & 0.211 \\\\\n008f (no emb) & 2 & $-1.645$ & 1.485 & 5.0\\% & 1.840 & 0.195 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Embedding geometry (exp\\_065).}\nTo characterize what the trained $\\dt$-embedding learns, we measure pairwise cosine similarity between $e_{\\dt{=}1}$ and $e_{\\dt{=}2}$ across training checkpoints for three trained seeds (two environments) and two frozen controls (Table~\\ref{tab:cosine_sim}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity between $e_{\\dt{=}1}$ and $e_{\\dt{=}2}$ vectors. Trained embeddings converge to near-opposite representations; frozen embeddings remain near-orthogonal throughout.}\n\\label{tab:cosine_sim}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llrrr}\n\\toprule\n\\textbf{Config} & \\textbf{Env} & \\textbf{cos@25K} & \\textbf{cos@75K} & \\textbf{Status} \\\\\n\\midrule\n008d s3 (trained) & Walker & $-0.87$ & $-0.70$ & CIVO \\\\\n059 s5 (trained) & Walker & $-0.94$ & $-0.86$ & CIVO \\\\\n010b s0 (trained) & Cheetah & $-0.90$ & $-0.84$ & CIVO \\\\\n\\midrule\n057 s2 (frozen) & Walker & $-0.15$ & $-0.15$ & Healthy \\\\\n058 s1 (frozen) & Cheetah & $+0.07$ & $+0.07$ & Healthy \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll trained seeds map $\\dt{=}1$ and $\\dt{=}2$ to nearly opposite directions (cosine similarity $-0.70$ to $-0.94$), consistent across both Walker and Cheetah environments. Frozen controls remain near-orthogonal (cosine $\\approx 0$) and constant across all checkpoints. The full pairwise cosine similarity matrix (Figure~\\ref{fig:pairwise_heatmap}) reveals that the near-antipodal relationship between $e_{\\dt{=}1}$ and $e_{\\dt{=}2}$ is the dominant structure: most other $\\dt$-pairs remain near-orthogonal ($|\\text{cos}| < 0.2$), indicating that the RSSM selectively maximizes separation along the $\\dt{=}1$ vs.\\ $\\dt{=}2$ axis rather than learning a globally structured embedding space.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.55\\columnwidth]{figures/paper/pairwise_heatmap.png}\n\\caption{Pairwise cosine similarity between all $\\dt$-embedding vectors (exp\\_008d, seed 3, step 75K). The $e_{\\dt{=}0}$--$e_{\\dt{=}1}$ pair exhibits strong anti-correlation ($-0.70$); remaining pairs are near-orthogonal, confirming that the learned geometry is dominated by a single antipodal axis.}\n\\label{fig:pairwise_heatmap}\n\\end{figure}\n\nThe magnitude of the learned separation---near-antipodal rather than merely distinct---provides converging evidence that the RSSM develops maximally differentiated internal representations for the two temporal scales, which in turn may contribute to the asymmetric reward fidelity gap reported in Table~\\ref{tab:rssm_fidelity} and replicated below.\n\n\\paragraph{Extended RSSM fidelity replication (exp\\_063).}\nTo validate the fidelity gap on independently trained checkpoints, we repeat the posterior-conditioned analysis with 15 episodes $\\times$ 40 test points $\\times$ 4 $\\dt$ levels (600 samples per model) on final checkpoints from three conditions (Table~\\ref{tab:rssm_fidelity_ext}).\n\n\\begin{table}[h]\n\\centering\n\\caption{RSSM fidelity analysis (training-time posterior-conditioned). Reward prediction gap remains the critical differentiator; observation reconstruction is paradoxically \\emph{better} with trained embedding. Independent final-checkpoint replication (exp\\_063, 008d seed~4) yields a reward gap of $2.7\\times$, confirming the qualitative pattern at lower magnitude.}\n\\label{tab:rssm_fidelity_ext}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{3}{c}{\\textbf{obs\\_MSE}} & \\multicolumn{3}{c}{\\textbf{reward\\_MAE}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\n\\textbf{Config} & $\\dt{=}1$ & $\\dt{=}2$ & Gap & $\\dt{=}1$ & $\\dt{=}2$ & Gap \\\\\n\\midrule\nBaseline (009d) & 16.08 & 23.49 & 1.46$\\times$ & 0.045 & 0.059 & 1.30$\\times$ \\\\\nCollapsed (008d) & 9.96 & 13.21 & 1.33$\\times$ & 0.057 & 0.178 & 3.11$\\times$ \\\\\nFrozen (057) & 11.14 & 14.95 & 1.34$\\times$ & 0.068 & 0.133 & 1.96$\\times$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe replication confirms the original fidelity gap pattern with two additional observations. First, the collapsed model achieves the \\emph{lowest} absolute obs\\_MSE at $\\dt{=}1$ (9.96 vs.\\ baseline 16.08), indicating that the trained $\\dt$-embedding improves world model quality overall---the pathology is selective degradation of reward predictions at longer horizons, not general model failure. Second, freezing the $\\dt$-embedding reduces the reward gap from $3.11\\times$ (training-time; $2.7\\times$ in independent replication) to $1.96\\times$, providing converging evidence for its role in preventing the co-adaptation loop while leaving residual multi-step reward prediction difficulty.\n\n\\paragraph{Value prediction analysis (exp\\_064).}\nTo examine the relationship between RSSM reward fidelity and critic value estimates, we compare critic predictions $V(s)$ against actual evaluation returns across three conditions (Table~\\ref{tab:value_pred}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Critic value predictions vs.\\ actual evaluation returns. The CIVO model's critic is well-calibrated to its $\\lambda$-return targets ($V(s) \\approx$ target) but both $V$ and targets are disconnected from reality (VE${=}3.03\\times$).}\n\\label{tab:value_pred}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lrrrr}\n\\toprule\n\\textbf{Config} & $V(s)$ & \\textbf{Eval} & \\textbf{VE ratio} & $V{-}\\text{target}$ \\\\\n\\midrule\nBaseline (001) & 665.9 & 938.9 & 0.71$\\times$ & $+0.001$ \\\\\nCIVO (008d) & 192.7 & 63.6 & \\textbf{3.03}$\\times$ & $+0.586$ \\\\\nNo emb (008f) & 116.5 & 306.5 & 0.38$\\times$ & $+0.316$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe paradox---$V(s)$ tracks its $\\lambda$-return targets faithfully yet overestimates actual performance by $3\\times$---provides converging evidence for the hypothesized mechanism in which CIVO operates upstream of the critic: the world model generates inflated imagination trajectories that the critic learns faithfully, producing targets disconnected from reality. In the baseline, VE${<}1.0$ throughout training because $V(s)$ reflects discounted imagined returns over $H{=}15$ steps, naturally lower than undiscounted episodic evaluation. The CIVO model crosses VE${=}1.0$ at step 55K and reaches $3.03\\times$ by 105K, with the gap widening as the actor exploits the overoptimistic critic.\n\n\\paragraph{Actor entropy dynamics under CIVO.}\nExtended training of collapsed configurations reveals a distinctive temporal sequence: evaluation return collapses first, followed by actor entropy explosion ${\\sim}35$K steps later. In the most severe case (EG~v4), entropy rises from $-5.21$ to $+3.22$ nats at a rate of $+2.11$ nats/10K steps, with returns declining from 583 to 93 between steps 60K--120K. A second collapsed run (EG~v5) shows $+0.61$ nats/10K with comparable return degradation (583$\\to$102). By contrast, healthy baselines exhibit gradual entropy drift at $+0.07$ to $+0.22$ nats/10K---15--30$\\times$ slower---with returns stable above 900. The return-before-entropy temporal ordering is consistent with the causal chain: delusional critic $\\to$ bad actor gradients $\\to$ policy destabilization. The entropy explosion is a lagging indicator; the NVE diagnostic detects CIVO onset ${\\sim}35$K steps before entropy rises, consistent with its use as an early-warning signal (\\S\\ref{sec:appendix_sensitivity}).\n\n\\subsection{Selective Gradient Stopping and Gradient Decomposition}\n\\label{sec:sgs_gradient_analysis}\n\n\\subsubsection{Gradient Decomposition Results}\n\\label{sec:gradient_decomposition}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/fig3_gradient_decomposition.pdf}\n\\caption{Gradient contribution to $e_{\\Delta t}$ by loss component at two training checkpoints. The reward head contributes the largest share (38--49\\%) yet reward-only SGS (exp\\_016e) fails; the observation decoder channel (16--22\\%) carries the critical $\\dt$-specific spatial information that drives the RSSM fidelity gap.}\n\\label{fig:gradient_decomp}\n\\end{figure}\n\nExp\\_016e collapses in the same qualitative pattern as the unmodified control: peak evaluation 326.7 at 75K steps followed by catastrophic decline to 31.7 at 95K, with NVE reaching $10.42\\times$. The SGS intervention neither prevented nor attenuated CIVO.\n\nTo explain this null result, we performed a gradient decomposition analysis using \\texttt{torch.autograd.grad} to measure each loss component's contribution to $\\nabla_\\theta e_{\\Delta t}$, where $\\theta$ denotes the temporal embedding parameters. Table~\\ref{tab:gradient_decomposition} reports the results.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Gradient contributions to the temporal embedding $e_{\\Delta t}$ by loss component, measured via \\texttt{torch.autograd.grad} with training configuration \\texttt{gate\\_fixed\\_dt=2}. Gradient norms are $\\ell_2$ norms of $\\nabla_\\theta \\mathcal{L}_i$ for each loss $\\mathcal{L}_i$.}\n\\label{tab:gradient_decomposition}\n\\small\n\\begin{tabular}{lrrrr}\n\\toprule\n& \\multicolumn{2}{c}{\\textbf{@55K}} & \\multicolumn{2}{c}{\\textbf{@112K}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nLoss component & Share & (\\%) & Share & (\\%) \\\\\n\\midrule\nReward head & --- & 49.0 & --- & 38.1 \\\\\nKL dynamics & --- & 34.7 & --- & 40.4 \\\\\nObservation decoders & --- & 16.3 & --- & 21.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe gradient decomposition reveals a counterintuitive structure: the reward head provides the largest gradient contribution (49.0\\% at 55K, 38.1\\% at 112K), yet reward-only SGS (exp\\_016e) fails catastrophically (NVE $10.42\\times$). The observation decoder channel contributes the smallest share (16.3\\% at 55K, 21.5\\% at 112K) yet carries the critical $\\dt$-specific spatial information.  This dissociation between gradient magnitude and causal importance explains why exp\\_016e, which targets the largest pathway, is functionally insufficient for CIVO prevention.\n\nThe gradient structure is relatively stable across training (reward shifts from 49\\% to 38\\%, obs from 16\\% to 22\\%, KL from 35\\% to 40\\%), unlike what a magnitude-based account would predict. The reward head's large gradient contribution reflects the scalar reward prediction task's sensitivity to temporal embedding parameters, but this gradient does not encode $\\Delta t$-specific structural information about spatial dynamics. The observation decoder channel, despite its smaller magnitude, is the only pathway that encodes how the RSSM should differentially predict multi-dimensional proprioceptive states across temporal scales.\n\n\\paragraph{Why the smallest channel is causally critical.} The observation decoder is the only loss component whose gradients encode how the RSSM should differentially predict multi-dimensional proprioceptive states ($14$ orientations, $9$ velocities, $1$ height) across temporal scales.  This $\\dt$-specific spatial information shapes the latent state representation in ways that propagate to reward prediction: the RSSM fidelity gap ($2.78\\times$ reward MAE ratio, Table~\\ref{tab:rssm_fidelity}) arises because the temporal embedding learns to produce latent states that are spatially biased at $\\dt{>}1$, not because the reward head directly learns scale-dependent biases.  Full-SGS targets this causal chain by preventing observation-decoder gradients from updating $e_{\\Delta t}$, though its 0/2 CIVO elimination rate on Walker (seed~1: NVE reduced from $4.12\\times$ to $1.66\\times$ but remains CIVO-positive; seed~2: collapsed) indicates that breaking the gradient pathway alone does not fully eliminate the vulnerability.\n\n\\subsubsection{Implications for the CIVO Mechanism}\n\\label{sec:sgs_implications}\n\nThe gradient decomposition reveals that gradient magnitude and causal importance are decoupled in CIVO.\n\n\\paragraph{Gradient importance $\\neq$ gradient magnitude.} The reward head contributes the largest gradient share (38--49\\%) to $e_{\\Delta t}$, yet reward-only SGS fails.  The observation decoder contributes the smallest share (16--22\\%), yet its removal (via Full-SGS) is necessary for CIVO mitigation.  This dissociation arises because the reward head's gradient, while large, does not encode $\\dt$-specific structural information: it adjusts $e_{\\Delta t}$ to minimize a scalar prediction error that is largely $\\dt$-invariant.  The observation decoder's gradient, though smaller, encodes how the RSSM should differentially reconstruct 24-dimensional proprioceptive states across temporal scales. This is the channel through which $e_{\\Delta t}$ learns scale-dependent latent biases.\n\n\\paragraph{Reframing the intervention target.} Any gradient-level strategy that targets the reward head alone (reward prediction regularization, reward-conditioned value clipping, or reward-only SGS) targets the largest pathway but not the informationally critical one.  The failure of exp\\_016e (NVE $10.42\\times$) despite detaching the dominant gradient source confirms this.  Full-pathway SGS (exp\\_018) detaches $e_{\\Delta t}$ from all non-KL gradients, retaining only the KL dynamics contribution (34--40\\%).  However, this intervention eliminates CIVO in neither seed: seed~1 shows partial mitigation (eval 448.3, peak NVE $1.66\\times$, still CIVO-positive) while seed~2 collapses (eval 40.8). Removing the observation decoder gradient channel is thus contributory but not sufficient. Figure~\\ref{fig:civo_decomposition} decomposes evaluation returns across conditions.\n\n\\begin{figure}[ht]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/fig2_civo_decomposition.pdf}\n\\caption{CIVO decomposition: peak and final (105K step) evaluation returns on Walker Walk across four conditions. \\textbf{Baseline} (001): vanilla DreamerV3. \\textbf{Trained dt-emb} (008d)\\protect\\footnotemark: learned $d{=}32$ temporal embedding with multi-rate data. \\textbf{Full-SGS} (s1, s2): trained embedding with all non-KL gradients detached from $e_{\\dt}$. Trained $\\dt$-embedding degrades peak eval by $73\\%$ and final eval by $86\\%$. Full-SGS seed~1 shows partial mitigation ($-51\\%$ final, NVE $1.66\\times$, still CIVO-positive) while seed~2 collapses ($-96\\%$ final). CIVO elimination rate $= 0/2$.}\n\\label{fig:civo_decomposition}\n\\end{figure}\n\\footnotetext{Experiment 008d terminated at 55K steps; the 105K data point uses continuation run 009e under identical configuration.}\n\nCross-environment validation on Cheetah Run (exp\\_021) further clarifies the role of Full-SGS.  The intervention did not prevent the initial CIVO onset: NVE peaked at $9.94\\times$ at 45K (comparable to the unmitigated exp\\_010b's $8.27\\times$).  However, unlike exp\\_010b, which collapsed permanently to eval 51.7, exp\\_021 self-corrected within ${\\sim}$10K steps, with sustained NVE dropping to $0.34\\times$ (55K--105K) and final evaluation recovering to 221.5.  This transient self-correcting trajectory is not attributable to the SGS intervention: the initial CIVO onset and peak severity are comparable to the unmitigated case, and the self-correction may reflect Cheetah Run's simpler dynamics rather than SGS efficacy.  Performance remains at 38.7\\% of baseline (572.5), likely because Full-SGS over-aggressively blocks actor gradients (actor gradient norms near zero throughout training).  Combined with exp\\_018's Walker results (0/2 CIVO elimination), these findings yield a 0/3 elimination rate across environments, indicating that gradient-level interventions alone do not eliminate the CIVO vulnerability. Additional mechanisms (e.g., forward-pass conditioning effects, residual capacity-dependent instabilities) operate beyond the gradient pathway.\n\n\\paragraph{Connection to RSSM fidelity analysis.} The trained-embedding condition (exp\\_008d) shows a $2.78\\times$ reward gap between $\\Delta t{=}1$ and $\\Delta t{=}2$ transitions (Table~\\ref{tab:rssm_fidelity}).  This gap arises because the observation decoder gradients shape $e_{\\Delta t}$ to produce latent states that are spatially biased at $\\dt{>}1$, and the reward head inherits these biases \\textit{through the latent state} rather than learning them directly.  The reward head's large gradient contribution reflects sensitivity to $e_{\\Delta t}$'s parameters but not causal responsibility for the fidelity gap.\n\n\\subsubsection{Entropy Dynamics Across Configurations}\n\\label{sec:entropy_dynamics}\n\n\\begin{figure}[ht]\n\\centering\n\\includegraphics[width=0.85\\columnwidth]{figures/fig4_entropy_dynamics.pdf}\n\\caption{Actor entropy trajectories for three configurations. All start at ${\\sim}8$ nats and converge to similar values (${\\sim}{-}4.5$ to ${-}5$). The CIVO-triggering configuration (008d, red) follows a normal entropy reduction trajectory; the divergence from the control (008f) is subtle in entropy space, consistent with CIVO operating through the value channel rather than the entropy channel. 018v2 (Full-SGS, seed~1) shows slightly lower terminal entropy.}\n\\label{fig:entropy_dynamics}\n\\end{figure}\n\n\\subsubsection{Exp\\_016e Reinterpreted as Stochastic Variation}\n\\label{sec:016e_reinterp}\n\nThe gradient decomposition establishes that exp\\_016e targets the largest gradient pathway (reward: 38--49\\%) but not the informationally critical one (observation decoders: 16--22\\%).  The apparent timing differences between exp\\_016e and exp\\_008d (later collapse onset, 75K vs.\\ 25K, and higher peak evaluation, 326.7 vs.\\ 167.2) must be attributed to stochastic variation rather than SGS effects, since the critical observation decoder channel remains intact.  All three trajectories (exp\\_008d, exp\\_009b, exp\\_016e) share the invariant identified by the NVE diagnostic: each crosses the $1.5\\times$ pathological threshold at some point during training.\n\n\\subsection{Post-CIVO Outcomes: Why Seeds Diverge}\n\\label{sec:seed_divergence}\n\n\\begin{table}[ht]\n\\centering\n\\caption{Post-CIVO outcomes for all ten CIVO-positive runs across two environments. Peak/Final NVE measured in the 35K+ window.}\n\\label{tab:post_civo}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccl}\n\\toprule\n\\textbf{Env} & \\textbf{Seed} & \\textbf{Peak} & \\textbf{Final} & \\textbf{Eval} & \\textbf{Outcome} \\\\\n\\midrule\nWalker & s1 (008d) & 4.12$\\times$ & 4.12$\\times$ & 82.8 & Full collapse \\\\\nWalker & s2 (009b) & 1.62$\\times$ & 0.38$\\times$ & 267.9 & Transient CIVO \\\\\nWalker & s3 (008d\\_s3) & 1.53$\\times$ & 1.53$\\times$ & 268$^\\diamond$ & Late-onset collapse \\\\\nWalker & s4 (008d\\_s4) & 4.62$\\times$ & 4.62$\\times$ & 63.6 & Full collapse \\\\\nWalker & s5 (059) & 4.72$\\times$ & 1.22$\\times$ & 95.8 & Collapse$^\\dagger$ \\\\\n\\midrule\nCheetah & s1 (010b) & 8.27$\\times$ & 8.27$\\times$ & 51.7 & Full collapse \\\\\nCheetah & s0 (078) & 4.10$\\times$ & 0.29$\\times$ & 119.5 & Self-correcting$^\\ddagger$ \\\\\nCheetah & s0 (010b\\_s0) & 108.52$\\times$ & 108.52$\\times$ & 0.83 & Full collapse \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^\\diamond$ Transitional; train returns still declining at 105K. $^\\dagger$~NVE self-corrected ($4.72\\times$ $\\to$ $1.22\\times$) but policy did not recover (eval 10.5\\% of baseline). $^\\ddagger$~Peak NVE $4.10\\times$ at 75K; eval 213.7$\\to$26.1$\\to$119.5 (26.7\\% of baseline exp\\_077, 448.1).\\par}\n\\end{table}\n\nAll ten CIVO-positive runs cross the $\\nve > 1.5\\times$ threshold (Table~\\ref{tab:post_civo}), yet the downstream damage is stochastic.\\footnote{Exp\\_009e was excluded from multi-seed analyses due to a seed configuration error (default seed=0, identical to exp\\_008d).}  Sustained collapse is the majority outcome (6/10 runs). Three runs self-correct (Walker seed~2 and both Cheetah seeds, including exp\\_078 which recovers from 26.1 to 119.5 at 105K); one (Walker seed~5) shows onset without sustained collapse---NVE self-corrects ($4.72\\times \\to 1.22\\times$) but the policy remains collapsed (eval 10.5\\% of baseline). Cheetah seed~1 (010b) exhibits more extreme overestimation (peak NVE $8.27\\times$) than Walker seeds ($1.53$--$4.62\\times$), consistent with the Cheetah reward scale amplifying the fidelity gap.  We hypothesize that the divergence relates to the critic's representational capacity at the time of CIVO onset.  \\citet{lyle2022capacity} demonstrate that deep RL networks suffer progressive capacity loss, in which early-learned features become increasingly difficult to overwrite.  If the critic's capacity is already partially consumed when CIVO injects overestimation, the network cannot recalibrate (seed~0); if sufficient capacity remains, the critic can absorb transient overestimation and recover (seed~2).\n\n\\paragraph{A fourth trajectory: CIVO-induced persistent value collapse.}\nObs-decoder SGS seed~3 (exp\\_025) exhibits a trajectory not observed in the untreated seeds: healthy through 105K ($\\nve < 1.0\\times$, eval 818.6), CIVO onset at 135K ($\\nve = 5.47\\times$, eval 67.0), followed by evaluation recovery (590.2 at 215K, 64\\% of baseline) but persistent value collapse ($\\nve = 0.14\\times$, value mean 80.6). The critic undershoots after the CIVO episode, suggesting that CIVO-induced representational damage persists even when the policy partially recovers. This contrasts with transient CIVO (seed~2, 009b), where both value and evaluation recover jointly, and with full collapse (seed~1, 008d), where neither recovers. Seed~4 exhibits the same terminal value collapse ($\\nve = 0.14\\times$ at 215K, eval 242), suggesting this overcorrection is systematic rather than seed-specific. The pattern adds a fourth post-CIVO outcome---policy recovery with critic damage---to the three documented in Table~\\ref{tab:post_civo}.\n\n\\subsubsection{Failure and Degradation Mode Taxonomy}\n\nTable~\\ref{tab:failure_modes} classifies the seven distinct failure and degradation modes observed across all experimental configurations. The taxonomy reveals that CIVO is not a single failure mode but a family of related pathologies, with the trained $\\dt$-embedding creating vulnerability through at least three independent mechanisms: value-driven collapse (monotonic, late-onset, and SGS-resistant CIVO), entropy-driven instability (IRD collapse), and gradient-mediated effects (gradient starvation, SGS-paradoxical worsening).\n\n\\begin{table}[ht]\n\\centering\n\\caption{Failure and degradation mode taxonomy. Each mode is characterized by its NVE trajectory, entropy behavior, and primary mechanism.}\n\\label{tab:failure_modes}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{@{}llccl@{}}\n\\toprule\n\\textbf{Mode} & \\textbf{Representative} & \\textbf{NVE} & \\textbf{Entropy} & \\textbf{Mechanism} \\\\\n\\midrule\nMonotonic CIVO & 008d, 008d\\_s4, 010b\\_s0 & $\\uparrow$ sustained & $\\downarrow$ & Reward bias $\\to$ critic $\\to$ actor \\\\\nLate-onset CIVO & 008d\\_s3 & $\\uparrow$ delayed & $\\downarrow$ & Same, delayed onset \\\\\nTransient CIVO & 009b & Peak $\\to$ $\\downarrow$ & Stable & Self-correction via capacity \\\\\nIRD collapse & 008e\\_v3\\_s2 & $\\uparrow$ late & $\\uparrow$ & Entropy-driven, values stable \\\\\nGrad.\\ starvation & 015b & Oscillates, decays & Stable & Frozen emb $\\to$ zero actor grad \\\\\nSGS-resistant & 018\\_s2 & $\\uparrow$ & $\\downarrow$ & Forward-pass conditioning \\\\\nSGS-paradoxical & 016e & $\\uparrow$ sustained & $\\downarrow$ & Reward SGS $\\to$ obs-dec reliance \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Extended Training Dynamics}\\label{sec:extended_training}\n\nOne Walker seed (s3, exp\\_045) was extended from 112K to approximately 302K steps to investigate long-horizon CIVO dynamics. After onset (NVE peak $4.91\\times$ at 132K steps), the system exhibited complete self-recovery: NVE declined to $0.05\\times$ and evaluation performance recovered to 867.6 (94.7\\% of baseline). This recovery required approximately 170K additional training steps beyond onset. The trajectory shows a single onset--recovery cycle with no recurrence, suggesting that the CIVO feedback loop can break spontaneously given sufficient training---though at substantial computational cost that the frozen $\\dt$-embedding diagnostic eliminates entirely.\n\n\\subsection{Why MPC Is Immune}\n\\label{sec:mpc_immune}\n\n\\citet{nhu2025tawm} show that $\\dt$-conditioning benefits TD-MPC2, raising the question of why it fails in DreamerV3.  The critical difference is that MPC re-plans from real states at every step, so imagination errors do not accumulate into the training signal because there is no critic bootstrapping from imagined trajectories.  In DreamerV3, the actor-critic trains entirely within imagination, and any systematic reward-prediction bias at $\\dt > 1$ is amplified through the closed actor-critic loop.\n\n\\subsection{The \\texorpdfstring{$\\dt$}{dt}-Embedding Dilemma}\n\\label{sec:embedding_dilemma}\n\nThe factorial results reveal a fundamental tension: removing the $\\dt$-embedding (008f) eliminates CIVO but at a $13\\times$ cost to reward prediction quality ($0.7469$ vs.\\ $0.0568$ MAE), as the world model cannot distinguish temporal scales.  Restricting imagination to $\\dt{=}1$ while retaining the trained embedding (008e\\_v3) avoids collapse in 2 of 4 seeds (50\\%), while the remaining two collapse via distinct mechanisms: Pathway~A (CIVO-driven, entropy decrease; s3, NVE $4.02\\times$) and Pathway~B (entropy-driven, entropy increase; s2, NVE $3.78\\times$; \\S\\ref{sec:f6}).  Neither approach alone provides a complete solution.\n\n\\subsection{Temporal Embedding Representation Analysis}\n\\label{sec:cosine_evolution}\n\nTo understand how the trained $\\dt$-embedding creates vulnerability, we analyze the cosine similarity between $e(\\dt{=}1)$ and $e(\\dt{=}2)$ across training (exp\\_065). Trained embeddings learn \\emph{near-opposite} representations: $\\cos(e_1, e_2) = {-}0.87$ to ${-}0.94$ at 25K steps across three configurations (Walker 008d\\_s3, Cheetah 010b\\_s0, Walker 059\\_s5), persisting at ${-}0.70$ to ${-}0.86$ at 75K steps. In contrast, frozen embeddings maintain near-zero similarity ($-0.15$ to $+0.07$, constant throughout training). The near-antipodal learned representations explain the large reward prediction gap (\\S\\ref{sec:f2}): $\\dt{=}2$ conditioning pushes the RSSM into a qualitatively different region of latent space, producing systematically biased predictions rather than minor perturbations.\n\n\\subsection{\\texorpdfstring{$\\dt$}{dt}-Embedding Differentiation Precedes Value Divergence}\n\\label{sec:cosine_temporal}\n\nThe preceding analysis established that trained $\\dt$-embeddings learn near-antipodal representations. Here we resolve the \\emph{temporal dynamics} of this differentiation across 11 experiments (${\\sim}$47 checkpoints), testing whether embedding differentiation is a consequence or precursor of CIVO.\n\n\\paragraph{Trained embeddings: monotonic relaxation.}\nAcross all trained configurations, $\\cos(e_1, e_2)$ starts near $-0.95$ within 10K steps and relaxes monotonically toward ${\\sim}{-}0.65$ (Table~\\ref{tab:cosine_evolution_ext}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity evolution between $e(\\dt{=}1)$ and $e(\\dt{=}2)$ for trained $\\dt$-embeddings. Relaxation is monotonic but never reaches zero; frozen embeddings remain constant near zero throughout training.}\n\\label{tab:cosine_evolution_ext}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Env} & \\textbf{Experiment} & \\textbf{10K} & \\textbf{25K} & \\textbf{65K} & \\textbf{75K} & \\textbf{302K} \\\\\n\\midrule\n\\multirow{2}{*}{Walker} & exp\\_066b (trained) & $-0.947$ & $-0.928$ & $-0.847$ & --- & --- \\\\\n & exp\\_045 (extension) & --- & --- & --- & --- & $-0.668$ \\\\\n\\midrule\nCheetah & exp\\_010b$\\to$048 & --- & $-0.904$ & --- & $-0.841$ & $-0.639$ \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Frozen controls:}} \\\\\nWalker & exp\\_057 (frozen) & \\multicolumn{5}{c}{$-0.150$ (constant, 25K--225K)} \\\\\nCheetah & exp\\_058 (frozen) & \\multicolumn{5}{c}{$+0.069$ (constant, 25K--225K)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nCross-seed consistency at 25K steps is high: mean $\\cos = -0.910 \\pm 0.028$ ($n{=}5$ Walker seeds), confirming the relaxation pattern is robust across random seeds. Variance increases with training ($-0.789 \\pm 0.076$ at 75K), reflecting seed-dependent relaxation rates.\n\n\\paragraph{Temporal precedence over CIVO.}\nExp\\_066b provides simultaneous cosine similarity and CIVO diagnostic data at 5K resolution (Table~\\ref{tab:cosine_vs_civo}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity relaxation and CIVO diagnostic for exp\\_066b. Embedding relaxation onset (${\\sim}$20K) precedes CIVO alert (55K, VE ratio $> 0.7$) by ${\\sim}$30--35K steps.}\n\\label{tab:cosine_vs_civo}\n\\footnotesize\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{rccc}\n\\toprule\n\\textbf{Step} & $\\cos(e_1, e_2)$ & \\textbf{VE ratio} & \\textbf{CIVO alert} \\\\\n\\midrule\n10K & $-0.947$ & 0.012 & --- \\\\\n15K & $-0.948$ & 0.033 & --- \\\\\n25K & $-0.928$ & 0.193 & --- \\\\\n35K & $-0.904$ & 0.269 & --- \\\\\n45K & $-0.880$ & 0.358 & --- \\\\\n55K & $-0.861$ & 0.710 & \\textbf{Alert} \\\\\n65K & $-0.847$ & 0.724 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nCosine relaxation begins at ${\\sim}$20K (cos transitions from $-0.948$ at 15K to $-0.928$ at 25K), while the VE ratio first exceeds 0.7 at 55K. The ${\\sim}$30--35K temporal lead establishes that embedding differentiation is an early training dynamic, not a consequence of CIVO-triggered feedback. The relaxation rate peaks at 25K--45K ($+0.024$/10K steps) before decelerating, consistent with the geometric intuition that large-angle adjustments in embedding space are cheaper early in training.\n\n\\paragraph{Embedding norms.}\nWalker and Cheetah exhibit qualitatively different norm dynamics. Walker $e(\\dt{=}1)$ norms grow from 0.23 to 0.50 ($2.2\\times$) while $e(\\dt{=}2)$ grows from 0.45 to 0.63 ($1.4\\times$)---both $\\dt$ values become more expressive over training. Cheetah norms remain nearly constant ($\\leq 1.04\\times$) despite continued cosine relaxation, indicating direction changes without magnitude change. Frozen embedding norms are an order of magnitude smaller (${\\sim}0.06$, constant).\n\n\\paragraph{Mechanistic interpretation.}\nThe temporal ordering---embedding differentiation (${\\sim}$20K) $\\to$ reward fidelity gap (${\\sim}$20K, \\S\\ref{sec:timeseries_fidelity}) $\\to$ value overestimation (${\\sim}$30K)---suggests a three-layer causal chain: the embedding first learns maximally differentiated representations that push $\\dt{=}1$ and $\\dt{=}2$ into opposite latent regions, the reward head then develops scale-dependent biases from these differentiated inputs, and the critic amplifies these biases through imagined rollout bootstrapping. The frozen embedding's constant near-zero cosine ($|\\cos| < 0.2$) prevents the first link in this chain, explaining why freezing eliminates CIVO despite maintaining identical forward-pass architecture (\\S\\ref{sec:f3}).\n\n\\subsection{Time-Series Fidelity--Value Analysis}\n\\label{sec:timeseries_fidelity}\n\nTo test the causal direction between reward fidelity degradation and value overestimation, we analyze exp\\_066 and exp\\_066b: two Walker Walk seeds (trained $\\dt$-embedding, fixed $\\dt{=}2$) evaluated at 12 dense checkpoints from 10K to 65K steps (Table~\\ref{tab:timeseries_fidelity}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Time-series fidelity and value metrics (exp\\_066, seed~0). SS = single-step MAE ratio ($\\dt{=}2$/$\\dt{=}1$); VE = value-to-eval ratio. Fidelity degradation (SS $>1.1\\times$ at 20K) precedes value overestimation onset (VE begins rising at ${\\sim}$30K) by ${\\sim}$10K steps. Seed~1 (exp\\_066b) confirms the pattern: fidelity gap onset ${\\sim}$15K $\\to$ VE onset ${\\sim}$24K (lead ${\\approx}$9K steps; VE peak ${=}0.72$).}\n\\label{tab:timeseries_fidelity}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{rcccccc}\n\\toprule\n\\textbf{Step} & \\textbf{SS ratio} & \\textbf{OL ratio} & \\textbf{VE ratio} & \\textbf{MAE$_{\\dt{=}1}$} & \\textbf{MAE$_{\\dt{=}2}$} & \\textbf{Return} \\\\\n\\midrule\n10K & 1.05 & 0.94 & 0.01 & 0.090 & 0.094 & 43.0 \\\\\n15K & 1.08 & 1.03 & 0.02 & 0.085 & 0.092 & 187.8 \\\\\n20K & 1.10 & 1.09 & 0.16 & 0.078 & 0.086 & 148.7 \\\\\n25K & 1.04 & 1.22 & 0.16 & 0.073 & 0.076 & 142.1 \\\\\n30K & 1.25 & 1.45 & 0.22 & 0.068 & 0.085 & 148.3 \\\\\n35K & 1.24 & 1.51 & 0.23 & 0.062 & 0.077 & 275.4 \\\\\n40K & 1.35 & 1.38 & \\textbf{1.59} & 0.058 & 0.078 & 202.3 \\\\\n45K & 1.40 & 1.38 & 0.36 & 0.055 & 0.077 & 107.5 \\\\\n50K & 1.47 & 1.56 & 0.62 & 0.052 & 0.076 & 178.4 \\\\\n55K & 1.37 & 1.52 & 0.62 & 0.050 & 0.069 & 60.8 \\\\\n60K & 1.61 & 1.35 & 1.40 & 0.049 & 0.079 & 125.3 \\\\\n65K & 1.68 & 1.38 & 1.40 & 0.047 & 0.079 & 94.4 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/paper/fig_temporal_ordering.pdf}\n\\caption{Temporal ordering of fidelity degradation and value overestimation (exp\\_066, seed~0). \\textbf{Left axis}: single-step fidelity ratio (SS, blue) grows steadily from $1.05\\times$ to $1.68\\times$. \\textbf{Right axis}: value-to-eval ratio (VE, red) remains near zero until 40K, then spikes. The ${\\sim}$10K onset-to-onset lag supports the causal direction: fidelity gap $\\to$ value overestimation. Seed~1 (exp\\_066b) replicates the pattern with a ${\\sim}$9K temporal lead.}\n\\label{fig:temporal_ordering}\n\\end{figure}\n\nThe $\\dt{=}1$ prediction MAE decreases monotonically ($0.090 \\to 0.047$) as the world model improves, but $\\dt{=}2$ MAE plateaus at ${\\sim}0.08$. The growing fidelity gap is therefore not caused by $\\dt{=}2$ predictions worsening, but by the model selectively improving at $\\dt{=}1$ while failing to transfer that improvement to $\\dt{=}2$---consistent with the trained $\\dt$-embedding learning maximally differentiated representations (\\S\\ref{sec:cosine_evolution}) that prevent cross-scale generalization.\n\n\\textbf{Limitation.} These results are limited to two seeds ($n{=}2$). While both seeds show consistent temporal ordering (leads of ${\\approx}$10K and ${\\approx}$9K steps), additional seeds would strengthen the causal claim.\n\n\\subsection{Actor Entropy Is Not Diagnostic of CIVO}\n\\label{sec:entropy_not_diagnostic}\n\nTo test whether actor entropy can serve as an early collapse indicator, we compare entropy trajectories between collapsed and healthy configurations at matched training steps across five experiments (Table~\\ref{tab:entropy_contrast}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Actor entropy comparison at matched time points. Collapsed and healthy configurations exhibit indistinguishable entropy at 55K steps (difference $= 0.03$ nats), despite collapsed runs showing severe return degradation.}\n\\label{tab:entropy_contrast}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Group} & \\textbf{Experiment} & \\textbf{5K} & \\textbf{25K} & \\textbf{45K} & \\textbf{55K} & \\textbf{Return} \\\\\n\\midrule\n\\multirow{2}{*}{Collapsed}\n & exp\\_008d (trained dt\\_emb) & 8.16 & $-1.86$ & $-4.58$ & $-4.88$ & ${\\sim}165$ \\\\\n & fixed\\_dt2 ($\\dt{=}2$) & 8.16 & $-3.02$ & $-5.06$ & $-5.17$ & ${\\sim}29$ \\\\\n\\midrule\n\\multirow{3}{*}{Healthy}\n & exp\\_008f (no dt\\_emb) & 8.11 & $-1.85$ & $-4.31$ & $-4.77$ & ${\\sim}460$ \\\\\n & exp\\_008a (unexposed) & 8.16 & $-4.88$ & $-5.20$ & $-5.21$ & ${\\sim}300$ \\\\\n & baseline\\_s1 ($\\dt{=}1$) & 8.10 & $-4.74$ & $-5.12$ & $-5.18$ & ${\\sim}950$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt the last comparable step (55K): collapsed mean entropy $= -5.02$ (average of $-4.88$, $-5.17$); healthy mean entropy $= -5.05$ (average of $-4.77$, $-5.21$, $-5.18$); difference $= 0.03$ nats---statistically negligible. The hypothesis that collapsed runs exhibit anomalous entropy rise (actor confusion from delusional critic gradients) is not supported during the CIVO onset window.\n\nThe fixed\\_dt2 experiment demonstrates this most clearly: returns peak at ${\\sim}580$ (40K) then crash to 29 (72K), yet entropy remains stable at $-5.1$ throughout. The actor maintains a committed, low-entropy policy during the entire collapse---it does not become confused but rather remains confident while acting on incorrect value estimates. This is consistent with CIVO operating through critic value distortion rather than actor policy degradation. The late-stage entropy explosion documented in \\S\\ref{sec:civo_mechanism} ($+2.1$ nats/10K in EG~v4, onset ${\\sim}$35K steps after return collapse) occurs well beyond this window, confirming entropy rise as a lagging consequence rather than a concurrent or predictive signal.\n\n\\paragraph{Entropy descent speed.}\nEntropy descent rate correlates with temporal configuration complexity, not collapse fate. Simpler configurations (baseline $\\dt{=}1$, unexposed exp\\_008a) reach $-4.7$ by 25K, while configurations exposed to temporal variation (both collapsed and healthy) remain near $-2.0$ at 25K, reflecting the difficulty of policy commitment when training data spans multiple temporal scales.\n\n\\paragraph{Long-horizon entropy recovery.}\nThe baseline ($\\dt{=}1$) run extended to 505K steps shows entropy recovering from $-5.2$ to ${\\sim}{-}1.5$ between 115K and 295K steps, coinciding with continued performance improvement ($700 \\to 950$ return). This adaptive entropy increase rules out entropy rise as an inherently negative signal; the actor maintains ${\\sim}950$ return with entropy 3--4 nats above its minimum, indicating a healthy exploration--exploitation balance during extended training.\n\n\\subsection{Multiple Vulnerability Pathways}\n\\label{sec:pathways}\n\nThe two collapse patterns identified in \\S\\ref{sec:f6}---CIVO (Pathway~A, value-driven, entropy decreasing) and a tentative second mode (Pathway~B, eval-driven, entropy increasing)---have distinct diagnostic signatures. Pathway~B is observed in only two seeds (008e\\_v3\\_s2 and 038\\_s2); we present it as preliminary evidence that the trained $\\dt$-embedding's learned features may affect both reward prediction across temporal scales (Pathway~A) and the representation space in which the actor operates (Pathway~B), though additional data is needed to confirm this as a distinct mechanism.  This explains why $\\nve$ is sensitive but not perfectly specific: Pathway~B's late evaluation decline inflates $\\nve$ through the same arithmetic as CIVO, yielding the sole false positive ($3.78\\times$ for 008e\\_v3 s2).  Distinguishing the two requires examining the temporal profile and entropy direction of collapse (Figure~\\ref{fig:multiple_pathways}).\n\n\n\\subsection{Implications for Temporal Abstraction in World Models}\n\\label{sec:implications}\n\nCIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \\citep{gumbsch2024thick}, Hieros \\citep{mattes2024hieros}, LS-Imagine \\citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \\citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.  The CIVO mechanism requires three structural properties: (1) a temporal embedding that co-adapts with dynamics via gradient flow, (2) multi-step imagined rollouts used for critic training, and (3) a reward head that inherits latent biases from the shared representation.  Transformer-based world models that share these properties may exhibit analogous vulnerability; architectures that decouple temporal conditioning from the reward prediction pathway would not.\n\n\\subsection{Cross-Environment TCN Evaluation}\n\\label{sec:tcn_cross_env}\n\nTable~\\ref{tab:tcn_full} reports the full TCN evaluation across environments and noise magnitudes.\n\n\\begin{table}[h]\n\\centering\n\\caption{TCN results across environments and noise magnitudes. Prevention = peak NVE $< 1.5\\times$ (35K+).}\n\\label{tab:tcn_full}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Env} & $\\sigma$ & \\textbf{Seed} & \\textbf{NVE$_{\\max}$} & \\textbf{Prevented?} & \\textbf{Eval (\\%)} \\\\\n\\midrule\nWalker & 0.1 & s0 & 1.02 & \\checkmark$^*$ & 55\\% \\\\\nWalker & 0.2 & s0 & 0.91 & \\checkmark & 91\\% \\\\\nWalker & 0.2 & s1 & 0.64 & \\checkmark & 45\\% \\\\\nWalker & 0.2 & s2 & 2.11$^\\dagger$ & $\\times$ & ${\\sim}5\\%$ \\\\\n\\rowcolor{gray!15}\nWalker & 0.2 & s3 & 3.04$^\\P$ & $\\times$ & 11\\% \\\\\nWalker & 0.5 & s0 & 3.97 & $\\times$ & 27\\% \\\\\nWalker & 0.5 & s1 & 1.64 & $\\times$ & 41\\% \\\\\n\\midrule\nCheetah & 0.2 & s0 & 1.90 & $\\times$ & crashed \\\\\nCheetah & 0.5 & s0 & 10.67 & $\\times$ & 26\\% \\\\\nCheetah & 1.0 & s0 & $\\leq$0.30 & \\checkmark$^\\S$ & 15\\% \\\\\n\\midrule\nPickCube & 0.2 & s0 & 3.71 & $\\times$ & failing \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$Borderline: NVE${=}1.02\\times$ at 95K, below $1.5\\times$ threshold but above $1.0\\times$.\\\\\n$^\\dagger$NVE $= 2.11\\times$ at 95K, still rising; eval ${\\sim}5\\%$ of baseline.\\\\\n$^\\P$Late-onset CIVO: NVE declined to $0.67\\times$ at 95K before phase-transition-like spike to $3.04\\times$ at 105K; eval 349.6 at 95K $\\to$ 71.8 at 105K $\\to$ 104.5 at 215K.\\\\\n$^\\S$CIVO prevented (NVE${\\leq}0.30$); peak eval 116\\% baseline at 35K, declining to 15\\% by 215K via progressive policy erosion. See ``impossible dose'' discussion.\\par}\n\\end{table}\n\n\\paragraph{Cheetah Run $\\sigma{=}0.5$: transient spike with permanent eval damage.}\nCheetah $\\sigma{=}0.5$ exhibits a novel failure mode: a transient CIVO spike (NVE $= 10.67\\times$ at 55K) followed by NVE recovery ($< 0.3\\times$ by 95K), but permanent evaluation damage (26\\% of baseline). The value signal self-corrects while the policy does not recover, suggesting that CIVO-induced representational damage during the spike persists within the observation window even when the critic subsequently recalibrates. This trajectory parallels the obs-decoder SGS seed~3 pattern (\\S\\ref{sec:seed_divergence}), where partial policy recovery coexists with persistent critic damage.\n\n\\paragraph{Cheetah Run $\\sigma{=}0.2$: insufficient dose.}\nAt $\\sigma{=}0.2$, Cheetah reaches NVE $= 1.9\\times$ at 55K---exceeding the $1.5\\times$ threshold---consistent with Cheetah's higher baseline CIVO severity ($8$--$108\\times$ vs.\\ Walker's $2$--$6\\times$). The noise magnitude that suffices for Walker is inadequate for Cheetah, but increasing $\\sigma$ to 0.5 trades CIVO prevention for a different failure mode rather than achieving mitigation.\n\n\\paragraph{PickCube-v1 $\\sigma{=}0.2$: manipulation failure.}\nPickCube reaches NVE $= 3.71\\times$ at 52.5K with $\\sigma{=}0.2$, indicating that TCN provides no protection in manipulation tasks. The combination of contact-gated dynamics and temporal conditioning may amplify the fidelity gap beyond what representation-level noise can attenuate.\n\n\\paragraph{Dose-response analysis.}\nWe observe $\\sigma{=}0.2$ as a local optimum on Walker Walk, achieving complete CIVO suppression in 2 of 4 seeds. Seeds~2 and~3 both fail but via distinct CIVO onset dynamics: seed~2 shows gradual escalation (NVE $= 2.11\\times$ at 95K, still rising, eval ${\\sim}5\\%$), while seed~3 exhibits a phase-transition-like onset---NVE declined to $0.67\\times$ at 95K before spiking to $3.04\\times$ at 105K (eval 349.6 $\\to$ 71.8 in 10K steps). When TCN fails to prevent CIVO onset, the resulting trajectory qualitatively resembles untreated CIVO in its terminal outcome---runaway NVE and eval collapse. The two failure modes (gradual escalation vs.\\ sudden onset after apparent suppression) reinforce that TCN operates as a binary gate on CIVO onset rather than providing graded attenuation. Below the optimum, we observe $\\sigma{=}0.1$ as insufficient (NVE $= 1.02\\times$---borderline, eval 55\\%); above it, $\\sigma{=}0.5$ overdoses (oscillatory CIVO, eval $\\leq 41\\%$). Cross-seed variance at $\\sigma{=}0.2$ (eval 5--91\\%) exceeds the cross-dose difference by a wide margin, reinforcing that seed effects dominate dose effects. TCN is the only tested intervention achieving complete CIVO suppression in any configuration, but its high seed sensitivity and failure to transfer across environments position it as a \\emph{diagnostic probe}---identifying the representation level as the relevant intervention target---rather than a deployable mitigation.\n\n\\paragraph{Cheetah Run ``impossible dose'' dilemma.}\nExp\\_030c (224K steps) reveals a qualitatively different dose-response on Cheetah. At $\\sigma{=}1.0$, CIVO is eliminated (NVE${\\leq}0.30$ throughout) and initial learning is \\emph{unimpaired}: peak eval reaches 372 at 35K (116\\% of baseline), demonstrating that $\\sigma{=}1.0$ noise does not prevent policy acquisition. However, cumulative actor gradient interference produces progressive policy erosion---eval declines from 372 to 47 by 215K (15\\% of baseline)---while the critic remains well-calibrated (value\\_mean${=}12.4$, NVE${=}0.26$ at 215K). This establishes that \\emph{policy degradation $\\neq$ value corruption}: accurate value signals are insufficient when the actor cannot optimize effectively in noise-perturbed imagination.\n\nThis ``correct values, failed policy'' pattern provides indirect evidence that CIVO is mechanistically distinct from standard overestimation. Double Q-learning and ensemble methods address critic estimation error, but at $\\sigma{=}1.0$ the critic is accurate and the policy still collapses---a failure mode orthogonal to what these countermeasures target. The impossible dose dilemma scales with environment complexity: Cheetah's baseline CIVO severity ($8$--$108\\times$ NVE) requires $\\sigma \\geq 1.0$ to suppress, but this exceeds the actor's gradient signal-to-noise tolerance. On Walker, a narrow effective window exists around $\\sigma{=}0.2$; on Cheetah, the effective dose ($\\sigma \\geq 1.0$) exceeds the tolerable dose, and environments with higher CIVO severity will systematically lack a viable dose window.\n\n\\section{DreamerV3 Hyperparameters}\n\\label{sec:hyperparameters}\n\nTable~\\ref{tab:hyperparams} lists the DreamerV3 hyperparameters used across all experiments. Unless otherwise noted, we use the default DreamerV3 configuration for continuous-control tasks (\\texttt{dmc\\_proprio}).\n\n\\begin{table}[ht]\n\\centering\n\\caption{DreamerV3 hyperparameters for all experiments. Modifications from defaults are marked with $\\diamond$.}\n\\label{tab:hyperparams}\n\\small\n\\begin{tabular}{ll}\n\\toprule\n\\textbf{Parameter} & \\textbf{Value} \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{World Model}} \\\\\nRSSM discrete states & 32 classes $\\times$ 32 categories \\\\\nRSSM stochastic dim & 32 \\\\\nRSSM deterministic dim & 512 \\\\\nMLP hidden size & 512 \\\\\nMLP layers & 2 \\\\\nActivation & SiLU \\\\\nNormalization & LayerNorm \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Training}} \\\\\nBatch size & 16 sequences $\\times$ 64 steps \\\\\nLearning rate & $3 \\times 10^{-4}$ (Adam, $\\epsilon{=}10^{-8}$) \\\\\nSequence length & 64 \\\\\nTraining ratio & 512 \\\\\nFree nats & 1.0 \\\\\nKL balance ($\\alpha$) & 0.8 \\\\\nDiscount ($\\gamma$) & 0.997 \\\\\n$\\lambda$-return & 0.95 \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Policy}} \\\\\nImagination horizon$^\\diamond$ & 8 or 15 (see Table~\\ref{tab:complete_results}) \\\\\nActor entropy scale & $3 \\times 10^{-4}$ \\\\\nActor gradient & Reinforce + dynamics backprop \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Temporal Abstraction}$^\\diamond$} \\\\\nGate enabled & True (all non-baseline) \\\\\nGate fixed $\\dt$ & 1 or 2 (per config) \\\\\nSubsample max $\\dt$ & 1 (OFF) or 2 (ON) \\\\\n$\\dt$-embedding dim & 32 \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Environment}} \\\\\nAction repeat & 2 (Walker Walk, Cheetah Run) \\\\\nObservation & Proprioceptive (no pixels) \\\\\nTotal environment steps & 105K \\\\\nEvaluation frequency & Every 10K steps \\\\\nEvaluation episodes & 10 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Online CIVO Detector Details}\n\\label{sec:detector_appendix}\n\nThis appendix provides the full algorithm specification and validation results for the online CIVO detector described in \\S\\ref{sec:detector}.\n\n\\subsection{Algorithm Specification}\n\n\nThe four conditions capture complementary signals: (1)~\\emph{Magnitude} ($r_t \\geq 0.49$) confirms that the value-to-evaluation ratio has reached a level indicative of overestimation; (2)~\\emph{Velocity} ($\\Delta r_t > 0.1$) rules out slow drift or plateau behavior; (3)~\\emph{Acceleration} ($\\Delta r_t > \\Delta r_{t-1}$, both $> 0.1$) filters oscillatory paths; (4)~\\emph{Evaluation decline} ($\\geq 2$ of 3 recent checkpoints decline) confirms that overestimation coincides with actual performance degradation. A full comparison of window sizes appears in \\S\\ref{sec:appendix_sensitivity}.\n\nSensitivity analysis over $\\tau_\\text{mag} \\in [0.30, 0.70]$ confirms that $\\tau_\\text{mag} = 0.49$ maximizes Youden's $J = 0.714$; raising the threshold to $0.50$ loses one true positive (seed~3 triggers at $r_t = 0.497$) with no reduction in false positives. The velocity threshold $\\tau_\\text{vel} = 0.1$ is stable across $[0.05, 0.18]$ (TPR remains $5/5$).\n\n\\subsection{Validation Results}\n\n\\begin{table}[ht]\n\\centering\n\\caption{Retrospective CIVO detector validation ($n{=}14$). Detection type: ``predictive'' = alert precedes 20\\% eval decline; ``reactive'' = alert follows decline onset.}\n\\label{tab:detector-validation}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{Verdict} & \\textbf{Trigger} & \\textbf{Type} & \\textbf{Peak Eval} & $r_\\text{ve}$ \\\\\n\\midrule\n008d s0 & trained $\\dt$-emb & TP & 45K & predict. & 167 & 0.69 \\\\\n010b & trained $\\dt$-emb (Cheetah) & TP & 65K & reactive & 322 & 3.18 \\\\\n008d s3 & trained $\\dt$-emb & TP & 45K & predict. & 452 & 0.50 \\\\\n008d s4 & trained $\\dt$-emb & TP & 105K & reactive & 383 & 3.03 \\\\\n010b s0 & trained $\\dt$-emb (Cheetah) & TP & 95K & reactive & 248 & 6.34 \\\\\n\\midrule\n008f s3 & no $\\dt$-emb & TN & -- & -- & 594 & -- \\\\\n009b s2 & trained $\\dt$-emb (self-corr.) & TN & -- & -- & 279 & -- \\\\\nbaseline s1 & vanilla & TN & -- & -- & 970 & -- \\\\\n009d s0 & vanilla & TN & -- & -- & 951 & -- \\\\\n009d s1 & vanilla & TN & -- & -- & 920 & -- \\\\\n019b & trained $\\dt$-emb (PickCube) & TN & -- & -- & 26.6 & -- \\\\\n\\midrule\n009c s2 & no $\\dt$-emb & FP & 105K & reactive & 359 & 0.75 \\\\\n009a s2 & vanilla & FP & 85K & predict. & 967 & 0.73 \\\\\n\\midrule\n009c s3 & no $\\dt$-emb & TN & -- & -- & 457 & -- \\\\\n\\midrule\n\\multicolumn{7}{l}{TPR = 5/5 (1.00), \\quad FPR = 2/9 (0.22)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe detector identifies all five CIVO-positive runs (TPR = 5/5). Two are detected predictively (008d seeds~0 and~3, both at 45K). Two false positives occur among nine negative cases (FPR = 2/9, precision 71\\%, F$_1$ = 0.83). Run 009c develops genuine late-stage value overestimation unrelated to CIVO; run 009a triggers during a transient eval dip at 85K before recovery to 966. Early alerts (before 70K) carry higher diagnostic confidence.\n\n\\subsection{Cross-Simulator Specificity (PickCube)}\n\nExp\\_019b applies the CIVO-trigger configuration to PickCube-v1 in ManiSkill3, a dense-reward manipulation task. The V/E ratio exhibits an oscillatory pattern rather than monotonic divergence: it spikes to $r_t = 5.66$ at 52.5K, then deflates to 1.38 by 72.5K. This trajectory prevents the acceleration condition from co-occurring with evaluation decline at any single checkpoint. Across all 14 checkpoints through 132.5K, the detector correctly remains silent (TN), confirming that the acceleration filter distinguishes transient spikes from CIVO's sustained monotonic divergence. A frozen-embedding control (exp\\_054) confirms this classification: frozen PickCube-v1 exhibits a comparable burst (peak $8.81\\times$ at 62.5K) that resolves within a single evaluation cycle ($0.55\\times$ at 72.5K), establishing environment-specific origin independent of $\\dt$-embedding training.\n\n\\subsection{Detector Limitations}\n\nFour constraints bound the current detector. First, the three-checkpoint window cannot distinguish transient dips from sustained collapse. Second, the acceleration condition assumes monotonically increasing overestimation during onset. Third, the detector identifies a \\emph{pattern} rather than a \\emph{mechanism}: run 009c shows that non-CIVO pathologies produce the same signature. Fourth, threshold values were calibrated on fourteen runs across three environments; generalization to different reward scales requires further validation.\n\n\\section{Dual-Critic Mechanism Ablation}\n\\label{sec:dual_critic_appendix}\n\n\\subsection{\\texorpdfstring{$2{\\times}2$}{2x2} Factorial Design}\n\nWe ablate the critic architecture in a $2{\\times}2$ factorial: \\{single, dual\\} $\\times$ \\{narrow (${\\sim}1.2$M), wide (${\\sim}2.4$M)\\} parameters. Table~\\ref{tab:dual_critic_full} reports all configurations.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Dual-critic $2{\\times}2$ factorial results. Walker Walk unless noted.}\n\\label{tab:dual_critic_full}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{Params} & \\textbf{NVE} & \\textbf{Eval} & \\textbf{Outcome} \\\\\n\\midrule\n008d & Single narrow & 1.2M & 4.12$\\times$ & 82.8 & Collapse \\\\\n033 & Wide single & 2.4M & 4.75$\\times$ & 407.9 & CIVO $\\to$ self-repair \\\\\n035 s0 & Narrow dual (min) & 1.2M & 2.75$\\times$ & 697.8 & CIVO $\\to$ recovery \\\\\n039 s1 & Narrow dual (min) & 1.2M & 2.19$\\times$ & 592.7 & CIVO $\\to$ recovery \\\\\n032 s0 & Wide dual (min) & 2.4M & $\\leq$1.1$\\times$ & 739.7 & CIVO prevented \\\\\n032b s1 & Wide dual (min) & 2.4M & 1.4$\\times$ & 551.8 & CIVO prevented \\\\\n038 s2 & Wide dual (min) & 2.4M & $\\leq$0.3$\\times$ & 120.9$^*$ & Non-CIVO collapse \\\\\n\\midrule\n\\multicolumn{6}{l}{\\textit{Cross-environment}} \\\\\n034 & Cheetah dual & 2.4M & 1.75$\\times$ & 97.5 & Partial recovery (31\\%) \\\\\n037 & Cheetah wide single & 2.4M & 3.60$\\times$ & 146.1 & CIVO $\\to$ self-repair \\\\\n036 & PickCube dual & 2.4M & 2.3$\\times$ & 27.7 & Transient CIVO \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$CIVO prevented (NVE $\\leq 0.3\\times$) but non-CIVO eval collapse: eval peaked at 354 (155K), then declined to 120.9 (224K) with actor entropy increasing from $-3.59$ to $-0.45$.\\par}\n\\end{table}\n\n\\subsection{Critic Convergence (\\texorpdfstring{$v_1 \\approx v_2$}{v1 ≈ v2})}\n\nAcross all dual-critic configurations and environments, the two critics converge to near-identical value functions. On Walker Walk, Pearson $\\rho > 0.999$ between $v_1$ and $v_2$ outputs; on Cheetah Run and PickCube-v1, the gap is $< 0.2$ (exact match within numerical precision). Per-sample pessimism $\\mathbb{E}[\\max(v_1, v_2) - \\min(v_1, v_2)]$ is 3--4\\% of the theoretical bound for independent critics.\n\nThis convergence occurs because both critics train on the same RSSM-generated latent features. Unlike model-free Double Q-learning, where each critic sees different mini-batches of real transitions and develops distinct function approximation errors, pure-imagination critics share identical inputs from the world model. The min operation therefore cannot provide the pessimism bias that makes Double Q effective in model-free settings.\n\n\\subsection{Recovery vs.\\ Prevention Mechanism}\n\nThe $2{\\times}2$ factorial reveals two separable dimensions:\n\n\\paragraph{Recovery (min-dominated).} The min operation is the primary factor enabling recovery from CIVO. Both narrow dual-critic seeds experience CIVO and recover fully: exp\\_035 (s0, $\\nve = 2.75\\times$, eval $33.8 \\to 697.8$, recovery ratio $20.6\\times$) and exp\\_039 (s1, $\\nve = 2.19\\times$, eval $35.9 \\to 592.7$, recovery ratio $16.5\\times$). Both outperform wide single-critic (exp\\_033, 2.4M params, eval 407.9) despite $2\\times$ fewer parameters. The min operation reduces both peak CIVO severity (2.19--2.75$\\times$ vs.\\ 4.75$\\times$ for the comparable single-critic) and enables consistent full recovery across seeds.\n\n\\paragraph{Prevention (min $+$ capacity synergy).} CIVO prevention (NVE remaining below the $1.5\\times$ threshold) requires both the min operation and increased capacity: only the wide dual-critic (exp\\_032, 3 seeds) achieves this. The mechanism for this synergy is an open question; we hypothesize that increased capacity improves value calibration quality while the min operation constrains the overestimation feedback loop during early training when the two critics briefly diverge.\n\n\\paragraph{Cross-environment limits.} On Cheetah Run, the wide dual-critic (exp\\_034) reduces NVE from $8.27\\times$ (untreated baseline) to $1.75\\times$ ($\\geq 4\\times$ reduction) but cannot prevent CIVO onset, and recovery reaches only 31\\% of the pre-CIVO peak. This confirms that the min $+$ capacity synergy has environment-dependent limits: in high-CIVO-severity environments, architecture-level interventions attenuate but do not eliminate the pathology.\n",
    "structuredPatch": [
      {
        "oldStart": 139,
        "oldLines": 7,
        "newStart": 139,
        "newLines": 7,
        "lines": [
          " ",
          " \\subsection{Per-Experiment NVE Values}",
          " ",
          "-Table~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\\_v3 seeds and exp\\_059). Experiments are sorted by descending NVE. Experiment 008e\\_v3\\_s2 exhibits elevated NVE ($3.78\\times$) due to Imagination-Reality Divergence (IRD), a mechanistically distinct phenomenon from CIVO, and is classified as negative in both tasks. Experiment 008e\\_v3\\_s3 exhibits CIVO with NVE $4.02\\times$ despite $\\Delta t{=}1$ imagination.",
          "+Table~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\\_v3 seeds and exp\\_059). Experiments are sorted by descending NVE. All four 008e\\_v3 seeds (mitigation configuration with $\\Delta t{=}1$ imagination) remain healthy with NVE $\\leq 0.6\\times$, confirming that restricting imagination to $\\Delta t{=}1$ effectively prevents CIVO.",
          " ",
          " \\begin{table}[ht]",
          " \\centering"
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

_source line 55_

<details open><summary>🔧 Tool call — Edit · `toolu_01Fseee2f8WAgZJZRbmJqkZt`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
  "old_string": "\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\\ = transient CIVO with self-correction.}",
  "new_string": "\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. Trans.\\ = transient CIVO with self-correction.}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "08002e7e-54d5-4abf-9c29-09ad15443118",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01F2tx699QkqL8YwYh9f26TU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 499,
      "cache_read_input_tokens": 95176,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 499
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

_source line 56 · 2026-05-25T16:34:19.106Z_

<details><summary>↩ Tool result · `toolu_01Fseee2f8WAgZJZRbmJqkZt`</summary>

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
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "eca2f0cc-f2e9-46ff-98fd-d694df76cd28",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
    "oldString": "\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\\ = transient CIVO with self-correction.}",
    "newString": "\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. Trans.\\ = transient CIVO with self-correction.}",
    "originalFile": "% --- APPENDIX ---\n\n\\section{Complete Experimental Results}\n\\label{sec:complete_results}\n\nTable~\\ref{tab:complete_results} reports all 45 experimental configurations. The main text (Table~\\ref{tab:main_results}) presents the subset most relevant to the causal argument; this table includes the additional variable-rate configurations (006, 007, 005), multi-seed factorial runs (009b, 008d\\_s3, 008d\\_s4), SGS interventions (018), cross-environment seeds (010b\\_s0), and mitigation experiments (008e\\_v3).\n\n\\begin{table*}[t]\n\\centering\n\\caption{Complete experimental results. NVE reports peak $\\nve$ in the 35K+ window (\\S\\ref{sec:metrics}). CIVO-positive seeds are shaded; $\\dagger$\\,marks a false positive (non-CIVO collapse with elevated NVE).}\n\\label{tab:complete_results}\n\\scriptsize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{dt\\_emb} & \\textbf{Sub} & \\textbf{H} & \\textbf{Eval@final} & \\textbf{NVE} & \\textbf{Outcome} \\\\\n\\midrule\n001 & Baseline ($\\dt{=}1$, s1) & --- & --- & 15 & 915.7 @105K & 1.00$\\times$ & Healthy \\\\\n001 s2 & Baseline ($\\dt{=}1$, s2) & --- & --- & 15 & 443.5 @105K & ---$^e$ & Healthy \\\\\n\\rowcolor{gray!15}\n006 & Fixed $\\dt{=}2$ & trn & ON & 15 & 132.9 @65K & 4.83$\\times$ & Collapsed \\\\\n007 & Fixed $\\dt{=}4$ & trn & ON & 15 & 152.5 @55K & --- & Collapsed \\\\\n005 & Learned gate & adaptive & OFF & 15 & 98.8 @145K & --- & Collapsed \\\\\n\\midrule\n\\rowcolor{gray!15}\n008d & Factorial (s1) & trn & ON & 8 & 82.8 @55K$^\\heartsuit$ & 4.12$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n009b & Factorial (s2) & trn & ON & 8 & 267.9 @105K & 1.62$\\times$ & Transient CIVO \\\\\n\\rowcolor{gray!15}\n008d\\_s3 & Factorial (s3) & trn & ON & 8 & 268$^\\diamond$ @105K & 1.53$\\times$ & Late-onset collapse \\\\\n\\rowcolor{gray!15}\n008d\\_s4 & Factorial (s4) & trn & ON & 8 & 63.6 @105K & 4.62$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n059 & Factorial (s5) & trn & ON & 8 & 95.8 @105K & 4.72$\\times$ & Collapse$^\\dagger$ \\\\\n\\rowcolor{gray!15}\n068 & Factorial repro (s1) & trn & ON & 8 & 39.1 @105K & 4.12$\\times$ & Full collapse \\\\\n008f & No dt\\_emb (s1) & --- & ON & 8 & 503.0 @105K & 0.97$\\times$ & Healthy \\\\\n008f s4 & No dt\\_emb (s4) & --- & ON & 8 & 289.3 @105K & 0.76$\\times$ & Healthy \\\\\n009c s3 & No dt\\_emb (s3) & --- & ON & 8 & 311.9 @105K & 1.04$\\times$ & Healthy \\\\\n008a & Unexposed emb & exp$^a$ & OFF & 15 & 777.7 @105K & 0.93$\\times$ & Healthy \\\\\n008a\\_s1 & Unexposed emb & exp$^a$ & OFF & 15 & 630.9 @105K & 0.83$\\times$ & Healthy \\\\\n008a\\_s2 & Unexposed emb & exp$^a$ & OFF & 15 & 899.4 @105K & 0.89$\\times$ & Healthy \\\\\n008a\\_s3 & Unexposed emb & exp$^a$ & OFF & 15 & 855.9 @105K & --- & Healthy \\\\\n015b & Frozen emb & frz$^b$ & ON & 8 & 204.2 @105K & 1.45$\\times$ & Grad.\\ starvation \\\\\n022b & Frozen emb + Gumbel gate & frz$^b$ & ON & 8 & 300.7 @105K & 0.63$\\times$ & No CIVO \\\\\n042 & Frozen emb (dedicated) & frz$^b$ & ON & 8 & 612.0 @105K & 0.19$\\times$ & Healthy \\\\\n047 & Frozen emb (s1) & frz$^b$ & ON & 8 & 144.2 @215K & 1.71$\\times$ & Transient (self-corr.) \\\\\n057 & Frozen emb (s2) & frz$^b$ & ON & 8 & 123.9 @215K & 1.88$\\times$ & Transient (self-corr.) \\\\\n067 & Frozen emb (s0) & frz$^b$ & ON & 8 & 281.5 @105K & 0.19$\\times$ & Healthy \\\\\n\\midrule\n018 s1 & Full-SGS & trn$^\\ddagger$ & ON & 8 & \\sgseval{} @105K & \\sgsnve{}$\\times$$^*$ & Partial mitig.\\ (CIVO+) \\\\\n\\rowcolor{gray!15}\n018 s2 & Full-SGS & trn$^\\ddagger$ & ON & 8 & 40.8 @105K & --- & Collapsed \\\\\n008e\\_v3 s0 & Mitigation & trn & ON & 15 & 148.0 @105K & 0.60$\\times$ & No CIVO$^j$ \\\\\n008e\\_v3 s1 & Mitigation & trn & ON & 15 & 876.7 @105K & 0.60$\\times$ & Healthy \\\\\n008e\\_v3 s2 & Mitigation & trn & ON & 15 & 597.1 @105K & 0.50$\\times$ & Healthy \\\\\n008e\\_v3 s5 & Mitigation & trn & ON & 15 & 869.9 @105K & 0.60$\\times$ & Healthy \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cross-environment validation}} \\\\\n\\rowcolor{gray!15}\n010b & Cheetah Run & trn & ON & 8 & 51.7 @105K & 8.27$\\times$ & Collapsed \\\\\n\\rowcolor{gray!15}\n010b\\_s0 & Cheetah Run & trn & ON & 8 & 0.83 @105K & 108.52$\\times$ & Full collapse \\\\\n\\rowcolor{gray!15}\n021 & Cheetah Run & trn$^\\ddagger$ & ON & 8 & 221.5 @105K & 9.94$\\times$$^d$ & Transient CIVO (self-corr.) \\\\\n024b s0 & Cheetah Run & --- & ON & 8 & 96.5 @105K & $<$0.20$\\times$ & Healthy \\\\\n024b s1 & Cheetah Run & --- & ON & 8 & 77.3 @105K & 0.10$\\times$ & Healthy \\\\\n008a\\_ch s0 & Cheetah Run & exp$^a$ & OFF & 15 & 532.4 @105K & 1.08$\\times$ & Healthy \\\\\n008a\\_ch s1 & Cheetah Run & exp$^a$ & OFF & 15 & 504.4 @105K & 1.29$\\times$ & Healthy \\\\\n077 & Cheetah baseline (s0) & --- & --- & 15 & 448.1 @105K & 1.00$\\times$ & Healthy \\\\\n\\rowcolor{gray!15}\n078 & Cheetah trigger (s0) & trn & ON & 8 & 119.5 @105K & 4.10$\\times$ & Onset (self-corr.) \\\\\n\\rowcolor{gray!15}\n019b & PickCube-v1 & trn & ON & 8 & 26.64 @200K & 3.78$\\times$$^c$ & Transient onset \\\\\n054 & PickCube-v1 & frz$^b$ & ON & 8 & --- & 8.81$\\times$$^h$ & Env.\\ transient (ctrl) \\\\\n049 & StackCube-v1 & trn & ON & 8 & 34.9 @212K & 5.05$\\times$$^f$ & Env.\\ transient \\\\\n052 & StackCube-v1 & trn & ON & 8 & --- & 4.67$\\times$$^f$ & Env.\\ transient \\\\\n051 & StackCube-v1 & frz$^b$ & ON & 8 & 30.7 @155K & 4.30$\\times$$^f$ & Env.\\ transient (ctrl) \\\\\n050 & PegInsertionSide-v1 & trn & ON & 8 & 20.86 @212K & 10.05$\\times$$^g$ & Env.\\ dynamics \\\\\n053 & PegInsertionSide-v1 & frz$^b$ & ON & 8 & 5.89 & 8.10$\\times$$^g$ & Env.\\ dynamics (ctrl) \\\\\n055 & PegInsertionSide-v1 & trn & ON & 8 & 11.44 @212K & 3.08$\\times$$^g$ & Env.\\ dynamics \\\\\n056 & PegInsertionSide-v1 & frz$^b$ & ON & 8 & 4.37 @212K & 11.32$\\times$$^g$ & Env.\\ dynamics (ctrl) \\\\\n046 & Cheetah Run & frz$^b$ & ON & 8 & 150.5 @215K & 1.35$\\times$ & No CIVO \\\\\n058 & Cheetah Run & frz$^b$ & ON & 8 & 80.46 @215K & 0.78$\\times$ & No CIVO \\\\\n\\midrule\n\\multicolumn{8}{l}{\\textit{Cartpole Swingup}} \\\\\n060 & Cartpole baseline (3 seeds) & --- & --- & 15 & 557.0 @105K$^i$ & --- & Healthy \\\\\n061 & Cartpole trigger (3 seeds) & trn & ON & 8 & 236.3 @105K$^i$ & --- & No CIVO \\\\\n062 & Cartpole control (3 seeds) & --- & ON & 8 & 244.8 @105K$^i$ & --- & No CIVO \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize\ntrn = trained ($d{=}32$, subsample ON);\ntrn$^\\ddagger$ = full-pathway SGS (all non-KL gradients detached);\nexp$^a$ = trained, subsample OFF;\nfrz$^b$ = frozen ($d{=}32$, \\texttt{requires\\_grad=False});\n--- = removed ($d{=}0$).\\\\\n$^*$ Seed 1 only: peak NVE with transient exceedances (1.60$\\times$ at 35K, 1.66$\\times$ at 95K); self-correcting, no sustained escalation. Seed 2 collapsed.\\\\\n$^\\diamond$ Transitional; train returns still declining (peak 470 to 139 over final 8K steps). Collapse had not reached equilibrium at 105K.\\\\\n$^\\dagger$ NVE self-corrected ($4.72\\times$ $\\to$ $1.22\\times$) but policy did not recover (eval 10.5\\% of baseline).\\\\\n$^c$ NVE normalized against exp\\_019a\\_v2 (vanilla DreamerV3 on PickCube-v1).\\\\\n$^d$ Peak NVE $9.94\\times$ at 45K (transient, self-correcting to $<$1$\\times$ by 55K); final eval 221.5.\\\\\n$^e$ Not used for NVE normalization; reported for completeness. Seed~1 (eval 915.7) is the NVE reference baseline.\\\\\n$^f$ StackCube transient: frozen control (exp\\_051, peak $4.30\\times$ at 42.5K) matches trained (exp\\_049/052), self-correcting by 82.5K; environment-specific, not $\\dt$-embedding-driven.\\\\\n$^g$ PegInsertion environment dynamics: seed~0 trained peaks at $10.05\\times$ (82.5K); seed~1 trained (exp\\_055) peaks at $3.08\\times$ (92.5K), final $0.50\\times$ at 212.5K; seed~1 frozen (exp\\_056) peaks at $11.32\\times$ (82.5K), final $1.19\\times$ at 212.5K. Frozen final exceeds trained final; ordering is seed-dependent, ruling out $\\dt$-embedding causation.\\\\\n$^h$ PickCube environment transient: frozen control peak $8.81\\times$ at 62.5K, self-correcting to $0.55\\times$ at 72.5K; matches trained (exp\\_019b) trajectory.\\\\\n$^\\heartsuit$ Evaluated at 55K steps due to early termination of exp\\_008d; extended run (exp\\_009e) reached 131.08 at 105K.\\\\\n$^i$ Cartpole: exp\\_060 reports seed~2 eval only; exp\\_061/062 report 3-seed mean.\\\\\n$^j$ CIVO-unrelated learning stagnation; NVE $\\leq 0.6\\times$, no value overestimation.\\par}\n\\end{table*}\n\n\\begin{table}[h]\n\\centering\n\\caption{Cross-domain CIVO reproducibility. ``$\\dt$-emb-dep.'' indicates trained peaks consistently exceed frozen at matched timepoints across seeds.}\n\\label{tab:cross_domain}\n\\footnotesize\n\\begin{tabular}{llccc}\n\\toprule\n\\textbf{Domain} & \\textbf{Environment} & \\textbf{Trained} & \\textbf{Frz ctrl} & \\textbf{$\\dt$-emb-dep.\\ CIVO} \\\\\n\\midrule\nLocomotion & Walker Walk & 5/5 & 0/3 & Yes (NVE $1.53$--$4.72\\times$) \\\\\nLocomotion & Cheetah Run & 2/2 & 0/2 & Yes (NVE $8.27$--$108.5\\times$) \\\\\nManipulation & StackCube-v1 & 0/2 & 0/1 & No (frozen$\\approx$trained) \\\\\nManipulation & PegInsertionSide & 0/2 & 0/2 & No (seed-dep.\\ ordering) \\\\\nManipulation & PickCube-v1 & 0/1 & 0/1 & No (frozen spike similar) \\\\\n\\midrule\nLocomotion & Cartpole Swingup & 0/3 & 0/3 & No (single-joint) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cartpole Swingup.} Cartpole Swingup (single-DoF locomotion) serves as a cross-environment control. Three seeds of the CIVO-trigger configuration (exp\\_061: trained $e_{\\dt}$, subsample ON, $H{=}8$, $\\dt{=}2$) and three seeds of the no-embedding control (exp\\_062) both produce zero CIVO onset. Despite using the hyperparameter combination that triggers collapse in all 10 tested multi-joint locomotion seeds (Walker/Cheetah), the single-joint Cartpole shows no CIVO, confirming the phenomenon requires multi-joint dynamics where temporal abstraction amplifies the reward fidelity gap.\n\n\\section{NVE Threshold Sensitivity Analysis}\n\\label{sec:appendix_sensitivity}\n\nWe report the full sensitivity analysis for the NVE diagnostic framework introduced in Section~\\ref{sec:results}. The main text reports Task~B2 (any CIVO detection, $\\nve \\geq 1.5\\times$). Here we additionally present Task~B1, which restricts the positive class to \\emph{sustained} CIVO, specifically experiments exhibiting persistent, accelerating value overestimation that progresses to performance collapse. Transient CIVO cases (e.g., exp~009b, which self-corrects after a brief excursion above the threshold) are classified as negative in B1.\n\n\\subsection{Per-Experiment NVE Values}\n\nTable~\\ref{tab:nve_raw} lists the NVE values at 35K+ training steps for all eleven factorial experiments (including four 008e\\_v3 seeds and exp\\_059). Experiments are sorted by descending NVE. All four 008e\\_v3 seeds (mitigation configuration with $\\Delta t{=}1$ imagination) remain healthy with NVE $\\leq 0.6\\times$, confirming that restricting imagination to $\\Delta t{=}1$ effectively prevents CIVO.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\\ = transient CIVO with self-correction.}\n\\label{tab:nve_raw}\n\\small\n\\begin{tabular}{@{}lrccc@{}}\n\\toprule\nExperiment & NVE & Mechanism & B1 & B2 \\\\\n\\midrule\n006          & 4.83 & sustained CIVO & $+$ & $+$ \\\\\n059          & 4.72 & self-correcting CIVO & $-$ & $+$ \\\\\n008d         & 4.12 & sustained CIVO & $+$ & $+$ \\\\\n008e\\_v3\\_s3 & 4.02 & CIVO           & $+$ & $+$ \\\\\n008e\\_v3\\_s2 & 3.78 & IRD (non-CIVO) & $-$ & $-$ \\\\\n009b         & 1.62 & transient CIVO & $-$ & $+$ \\\\\n001          & 1.00 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s4 & 0.99 & non-CIVO       & $-$ & $-$ \\\\\n008f         & 0.97 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s1 & 0.94 & non-CIVO       & $-$ & $-$ \\\\\n008a         & 0.93 & non-CIVO       & $-$ & $-$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Multi-Threshold Classification Performance}\n\nTable~\\ref{tab:sensitivity_b1} reports Task~B1 classification metrics across six NVE thresholds. Task~B1 achieves $\\text{AUROC} = 0.917$ because exp\\_059 (NVE${=}4.72\\times$, self-correcting CIVO, B1-negative) ranks above two sustained-CIVO positives ($4.12\\times$, $4.02\\times$), breaking the perfect rank separation that held before its inclusion. The optimal threshold lies in the interval $(3.78, 4.02]$; we report $\\geq 3.9\\times$ as a representative value (accuracy $10/11 = 90.9\\%$). Table~\\ref{tab:sensitivity_b2} provides the corresponding analysis for Task~B2 ($\\text{AUROC} = 0.967$, imperfect separation due to 008e\\_v3\\_s2).\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B1}: Sustained CIVO detection sensitivity analysis ($n_{\\text{pos}}=3$, $n_{\\text{neg}}=8$, $n=11$, $\\text{AUROC}=0.917$). All confidence intervals are two-sided Clopper-Pearson exact binomial ($\\alpha=0.05$). $^\\dagger$Optimal threshold in $(3.78, 4.02]$; exp\\_059 (NVE${=}4.72\\times$, B1-negative) is the sole false positive.}\n\\label{tab:sensitivity_b1}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 3 & 4 & 0 & 4 & 63.6\\% \\; [30.8, 89.1] & 42.9\\% & 100\\% & 60.0\\% \\\\\n$\\geq 1.2\\times$ & 3 & 3 & 0 & 5 & 72.7\\% \\; [39.0, 94.0] & 50.0\\% & 100\\% & 66.7\\% \\\\\n$\\geq 1.5\\times$ & 3 & 3 & 0 & 5 & 72.7\\% \\; [39.0, 94.0] & 50.0\\% & 100\\% & 66.7\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.7\\times$ & 3 & 2 & 0 & 6 & 81.8\\% \\; [48.2, 97.7] & 60.0\\% & 100\\% & 75.0\\% \\\\\n$\\geq 2.0\\times$ & 3 & 2 & 0 & 6 & 81.8\\% \\; [48.2, 97.7] & 60.0\\% & 100\\% & 75.0\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 3.9\\times^\\dagger$ & 3 & 1 & 0 & 7 & 90.9\\% \\; [58.7, 99.8] & 75.0\\% & 100\\% & 85.7\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B2}: Any CIVO detection sensitivity analysis ($n_{\\text{pos}}=5$, $n_{\\text{neg}}=6$, $n=11$, $\\text{AUROC}=0.967$). The single false positive at $\\geq 1.5\\times$ is 008e\\_v3\\_s2 (IRD mechanism, not CIVO). The $1.5\\times$ threshold (highlighted) maximizes F1 while maintaining perfect recall.}\n\\label{tab:sensitivity_b2}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 5 & 2 & 0 & 4 & 81.8\\% \\; [48.2, 97.7] & 71.4\\% & 100\\% & 83.3\\% \\\\\n$\\geq 1.2\\times$ & 5 & 1 & 0 & 5 & 90.9\\% \\; [58.7, 99.8] & 83.3\\% & 100\\% & 90.9\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.5\\times$ & 5 & 1 & 0 & 5 & 90.9\\% \\; [58.7, 99.8] & 83.3\\% & 100\\% & 90.9\\% \\\\\n$\\geq 1.7\\times$ & 4 & 1 & 1 & 5 & 81.8\\% \\; [48.2, 97.7] & 80.0\\% & 80.0\\% & 80.0\\% \\\\\n$\\geq 2.0\\times$ & 4 & 1 & 1 & 5 & 81.8\\% \\; [48.2, 97.7] & 80.0\\% & 80.0\\% & 80.0\\% \\\\\n$\\geq 3.9\\times$ & 4 & 0 & 1 & 6 & 90.9\\% \\; [58.7, 99.8] & 100\\% & 80.0\\% & 88.9\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{table*}[t]\n\\centering\n\\caption{\\textbf{Task~B2 (full evaluation set)}: Any CIVO detection across two environments ($n_{\\text{pos}}=9$, $n_{\\text{neg}}=8$, $n=17$, $\\text{AUROC}=0.972$). Includes Walker Walk (15 configurations) and Cheetah Run (2 configurations).}\n\\label{tab:sensitivity_b2_full}\n\\small\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{@{}lcccccccc@{}}\n\\toprule\nThreshold & TP & FP & FN & TN & Accuracy [95\\% CI] & Precision & Recall & F1 \\\\\n\\midrule\n$\\geq 1.0\\times$ & 9 & 2 & 0 & 6 & 88.2\\% \\; [63.6, 98.5] & 81.8\\% & 100\\% & 90.0\\% \\\\\n$\\geq 1.2\\times$ & 9 & 1 & 0 & 7 & 94.1\\% \\; [71.3, 99.9] & 90.0\\% & 100\\% & 94.7\\% \\\\\n\\rowcolor{gray!15}\n$\\geq 1.5\\times$ & 9 & 1 & 0 & 7 & 94.1\\% \\; [71.3, 99.9] & 90.0\\% & 100\\% & 94.7\\% \\\\\n$\\geq 1.7\\times$ & 7 & 1 & 2 & 7 & 82.4\\% \\; [56.6, 96.2] & 87.5\\% & 77.8\\% & 82.4\\% \\\\\n$\\geq 2.0\\times$ & 7 & 1 & 2 & 7 & 82.4\\% \\; [56.6, 96.2] & 87.5\\% & 77.8\\% & 82.4\\% \\\\\n$\\geq 3.9\\times$ & 7 & 0 & 2 & 8 & 88.2\\% \\; [63.6, 98.5] & 100\\% & 77.8\\% & 87.5\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\subsection{Threshold Recommendation}\n\nFor the main diagnostic (Task~B2), we recommend $\\nve \\geq 1.5\\times$ as the operating threshold for three reasons:\n\n\\begin{enumerate}[nosep,leftmargin=*]\n\\item \\textbf{Maximum recall.} The $1.5\\times$ threshold achieves 100\\% recall, detecting all five CIVO cases including the transient case (009b, $\\nve = 1.62\\times$). Raising the threshold to $1.7\\times$ loses 009b, dropping recall to 80.0\\%.\n\\item \\textbf{Best F1.} At $1.5\\times$, F1 = 90.9\\%, the highest among all tested thresholds for B2. The single false positive (008e\\_v3\\_s2) is mechanistically identifiable as IRD rather than CIVO.\n\\item \\textbf{Sensitivity--specificity tradeoff.} Lower thresholds ($1.0\\times$) add false positives without gaining true positives. Higher thresholds ($\\geq 1.7\\times$) sacrifice recall without eliminating the 008e\\_v3\\_s2 false positive (which requires $\\tau > 3.78$).\n\\end{enumerate}\n\nFor Task~B1 (sustained CIVO only), the optimal threshold $\\nve \\geq 3.9\\times$ achieves $10/11$ accuracy ($90.9\\%$, 95\\% CI: [58.7\\%, 99.8\\%]); the sole false positive is exp\\_059 (NVE${=}4.72\\times$, self-correcting CIVO classified as B1-negative).\n\n\\subsection{Expanded ROC Analysis}\n\\label{sec:roc_analysis}\n\nThe original $n{=}17$ analysis (Tables~\\ref{tab:sensitivity_b1}--\\ref{tab:sensitivity_b2_full}) predates the SGS, RAVE, and TCN experiments. We extend the NVE diagnostic evaluation to $n{=}56$ configurations spanning all tested interventions. Figure~\\ref{fig:nve_roc} shows the receiver operating characteristic curve with 95\\% bootstrap confidence interval (10{,}000 resamples).\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.7\\columnwidth]{../../artifacts/figures/nve_roc_curve.pdf}\n\\caption{NVE ROC curve ($n{=}56$ configurations, AUROC${=}0.990$, comprehensive validation). The preset $\\nve \\geq 1.5\\times$ operating point (star) achieves TPR${=}1.00$, FPR${=}0.09$, accuracy${=}53/56$, F1${=}0.941$. Three false positives arise from non-CIVO value overestimation: mitigation transient VE spike (008e\\_v3 subsample, $1.93\\times$) and frozen embedding transients (047, $1.71\\times$; 057, $1.88\\times$). Threshold calibrated and validated post-hoc; cross-architecture validation deferred.}\n\\label{fig:nve_roc}\n\\end{figure}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.7\\columnwidth]{../../artifacts/figures/nve_threshold_prf.pdf}\n\\caption{Precision, Recall, and F1 as a function of NVE threshold ($n{=}56$ configurations). Peak F1${=}0.941$ at $\\tau{=}1.5\\times$, where recall remains perfect ($1.00$) and precision${=}0.889$. The plateau of high F1 across $\\tau \\in [1.5, 1.7]$ indicates robustness to threshold selection.}\n\\label{fig:nve_prf}\n\\end{figure}\n\nWe label a configuration as CIVO-positive if and only if (i)~it uses a trained $\\dt$-embedding with multi-rate data exposure, and (ii)~NVE exceeds $1.5\\times$ with co-occurring entropy collapse. Configurations exhibiting high NVE through other mechanisms (gradient truncation side effects, value anchor pollution) are labeled non-CIVO.\n\nThe three false positives (FPR${=}0.18$) are mechanistically distinct from CIVO: (1)~RAVE anchor pollution (exp\\_028, the EMA anchor becomes inflated, producing overestimation through a different pathway); (2)~obs-decoder SGS-induced value distortion (exp\\_025 seed~2, blocking observation decoder gradients damages the RSSM latent space); (3)~IRD eval-driven collapse (exp\\_008e\\_v3 seed~2, actor entropy \\emph{increases} with evaluation collapse, mechanistically distinct from CIVO's entropy \\emph{decrease}). All three produce NVE $> 1.5\\times$ through non-CIVO mechanisms, indicating that the NVE diagnostic detects value overestimation broadly rather than CIVO specifically---a feature rather than a limitation for practitioners monitoring deployment health. The closest sub-threshold case (008f seed~4, NVE${=}1.41\\times$) lacks $\\dt$-conditioning entirely ($d{=}0$); its elevated NVE reflects transient value noise that self-corrects without the positive feedback loop characteristic of CIVO. The closest above-threshold positive (008d seed~3, NVE${=}1.53\\times$) exhibits the full CIVO causal chain: trained $\\dt$-embedding, entropy decrease, and evaluation collapse to 14\\% of baseline.\n\n\\paragraph{Comprehensive validation ($n{=}56$).}\nExpanding the evaluation set to all classifiable experiments yields $n{=}56$ ($n_{\\text{pos}}{=}24$, $n_{\\text{neg}}{=}32$), spanning Walker Walk, Cheetah Run, and multiple intervention configurations (SGS, TCN, dual-critic, frozen embedding). At the $1.5\\times$ threshold: AUROC${=}0.990$, precision${=}0.889$, recall${=}1.000$, F1${=}0.941$, accuracy${=}53/56$. The three false positives are: exp\\_008e\\_v3\\_subsample ($1.93\\times$, mitigation config with transient VE spike), exp\\_047 ($1.71\\times$, frozen embedding transient), and exp\\_057 ($1.88\\times$, frozen embedding transient). All 24 CIVO-positive configurations are correctly detected (FN${=}0$), with CIVO-positive NVE ranging from $1.53\\times$ (008d seed~3, late-onset) to $70.64\\times$ (010b seed~0, Cheetah). The substantial increase in sample size from $n{=}32$ to $n{=}56$ strengthens confidence in the $1.5\\times$ threshold as a robust diagnostic boundary.\n\n\\subsection{NVE Normalization Robustness}\n\\label{sec:nve_robustness}\n\nTo assess sensitivity to baseline seed choice, we extend the single-seed baseline (seed~1, eval 915.7 at 105K) to three additional seeds trained to 505K steps (Table~\\ref{tab:baseline_seeds}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Walker Walk baseline seeds at 105K and 505K steps.}\n\\label{tab:baseline_seeds}\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Seed} & \\textbf{Eval@105K} & \\textbf{Eval@505K} & \\textbf{ve@65K} & \\textbf{ve@105K} \\\\\n\\midrule\ns1 & 915.7 & 970.4 & 0.563 & 0.656 \\\\\ns2 & 443.5 & 945.7 & 0.898 & 0.742 \\\\\ns3 & 869.0 & 947.7 & --- & 0.664 \\\\\ns4 & 922.8 & 938.9 & --- & 0.624 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nSeed~2 exhibits slow convergence (eval 443.5 at 105K, recovering to 945.7 by 512K), confirming non-pathological slow convergence rather than seed failure. Its elevated $v/e$ ratio at 65K (0.898 vs.\\ 0.563 for seed~1) reflects the low evaluation denominator rather than pathological value overestimation. Using seed~2 as the sole normalization reference systematically deflates NVE values, causing two marginal CIVO-positive configurations (008d seed~3, peak NVE $1.53\\times$; 009b seed~2, peak NVE $1.62\\times$) to fall below the $1.5\\times$ threshold. Core CIVO cases (peak NVE $> 3\\times$) remain correctly classified under all baseline seeds.\n\nSingle-seed normalization (s1) yields AUROC $= 0.933$ and accuracy 7/8 (87.5\\%) on the Walker subset. Four-seed mean normalization yields AUROC $= 0.867$ and accuracy 6/8 (75.0\\%): the boundary case exp\\_009b flips from $\\nve = 1.62\\times$ (s1) to $1.23\\times$ (4-seed mean), because its peak occurs at 45K when the s1 $v/e$ ratio (0.331) is well below the 4-seed mean (0.436). All high-NVE configurations remain correctly classified (006: $4.84\\times \\to 4.52\\times$; 008d: $4.12\\times \\to 3.54\\times$). The $1.5\\times$ threshold thus correctly identifies all strong CIVO cases regardless of baseline choice; sensitivity is confined to configurations within 10\\% of the threshold.\n\n\\paragraph{Normalization conventions.} Walker NVE is normalized against the single-seed baseline (seed~1, exp\\_001, 505K steps). Cheetah NVE is normalized against a 5-seed mean baseline (seeds~0--4, each run to ${\\sim}$210K steps). The differing seed counts reflect available baseline data; both provide sufficient coverage of the respective experimental windows (Walker: 210K analysis window; Cheetah: 105K analysis window).\n\n\\paragraph{Limitations.} The initial $n{=}11$ analysis had wide Clopper-Pearson confidence intervals (e.g., 90.9\\% accuracy, 95\\% CI [58.7\\%, 99.8\\%]). The comprehensive evaluation ($n{=}56$, AUROC${=}0.990$, F1${=}0.941$; Figure~\\ref{fig:nve_roc}) substantially tightens these bounds. Table~\\ref{tab:sensitivity_b2_full} reports the $n{=}17$ two-environment core evaluation. Cross-architecture validation is deferred to future work.\n\n\\subsection{Leave-One-Environment-Out Cross-Validation}\n\\label{sec:nve_loeo}\n\nTo assess whether $\\theta{=}1.5\\times$ generalizes beyond the in-sample evaluation, we perform leave-one-environment-out (LOEO) cross-validation across Walker ($n{=}15$), Cheetah ($n{=}5$), and PickCube ($n{=}2$). For each fold, we hold out all experiments from one environment, select the optimal accuracy-maximizing threshold range on the remaining training set, and evaluate the fixed $\\theta{=}1.5\\times$ on the held-out environment.\n\n\\begin{table}[h]\n\\centering\n\\caption{Leave-one-environment-out cross-validation of NVE threshold $\\theta=1.5\\times$.\nFor each fold, the threshold is validated on an environment whose data was \\emph{not} used\nto select $\\theta$. The optimal threshold range on each training set is reported;\n$\\theta=1.5$ falls within the optimal range in all three folds.}\n\\label{tab:nve_loeo}\n\\begin{tabular}{lccccc}\n\\toprule\nHeld-out & $N_{\\text{train}}$ & $N_{\\text{test}}$ & $\\theta_{\\text{opt}}$ range & Test Accuracy & Test AUROC \\\\\n\\midrule\nPickCube & 20 & 2 & $(1.45,\\, 1.53]$ & 2/2 (1.000) & 1.000 \\\\\nCheetah  & 17 & 5 & $(1.45,\\, 1.53]$ & 5/5 (1.000) & 1.000 \\\\\nWalker   &  7 & 15 & $(1.00,\\, 3.78)$ & 14/15 (0.933) & 0.963 \\\\\n\\midrule\n\\textbf{Mean} & — & — & — & \\textbf{0.978} & \\textbf{0.988} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe threshold $\\theta{=}1.5\\times$ falls within the optimal accuracy range for all three training folds: $(1.45, 1.53]$ when Walker data is available, and the wider $(1.00, 3.78)$ when training on Cheetah$+$PickCube only (where CIVO and non-CIVO NVE values are well-separated). The single cross-validation error is exp\\_008e\\_v3 seed~2 (Walker), an IRD collapse mechanistically distinct from CIVO (\\S\\ref{sec:roc_analysis}). Mean held-out accuracy is 0.978 and mean AUROC is 0.988, confirming that $\\theta{=}1.5\\times$ generalizes across environments without retuning.\nPickCube fold confidence intervals remain wide (Clopper-Pearson 95\\% CI: $[0.158, 1.000]$) due to $N_{\\text{test}}{=}2$.\n\n\\subsection{Leave-One-Config-Out Cross-Validation}\n\\label{sec:nve_loco}\n\n\\paragraph{Leave-One-Config-Out Cross-Validation.}\nTo rule out threshold overfitting to any particular experimental configuration, we perform leave-one-config-out (LOCO) cross-validation over $K{=}12$ configuration groups (e.g., \\texttt{008d\\_civo\\_trigger}, \\texttt{frozen\\_dt\\_emb}, \\texttt{tcn}; $n{=}56$ total). Each fold holds out all experiments from one configuration, selects the F1-maximizing threshold on the remaining $K{-}1$ groups, and evaluates on the held-out group.\n\nIn $10/12$ folds, the training-optimal threshold falls within $\\pm 0.05$ of $\\theta{=}1.5\\times$ (mean $1.61 \\pm 0.23$, range $[1.47, 2.12]$). The two folds selecting a higher threshold ($\\theta{=}2.1$; \\texttt{008d\\_civo\\_trigger} and \\texttt{tcn}, both predominantly CIVO-positive) perform \\emph{worse} on their held-out sets than $\\theta{=}1.5$ (accuracy $0.78$/$0.88$ vs.\\ $1.00$/$1.00$), confirming that the fixed threshold generalizes better than per-fold optimization in these cases. Cross-validated accuracy at $\\theta{=}1.5$ is $53/56 = 94.6\\%$, identical to the in-sample result, with train AUROC consistently high across folds ($0.988 \\pm 0.003$). The three misclassifications are the same mechanistically distinct false positives identified in \\S\\ref{sec:roc_analysis}: two frozen-embedding transients (exp\\_047, exp\\_057) and one mitigation-config transient (exp\\_008e\\_v3\\_subsample). No CIVO-positive configuration is missed in any fold (FN${=}0$ across all 12 folds).\n\n% --- APPENDIX B: Factorial Ablation Details ---\n\n\\section{Factorial Ablation Details}\n\\label{sec:appendix_factorial}\n\nThis appendix provides the full factorial ablation results summarized in \\S\\ref{sec:f3f5_summary} of the main text.\n\n\\paragraph{Embedding gradient analysis.}\nTable~\\ref{tab:three_way_emb} isolates embedding \\emph{trainability} as the necessary condition for CIVO by comparing four gradient conditions under otherwise identical configurations ($H{=}8$, subsample ON, $\\dt{=}2$ imagination).\n\n\\begin{table}[h]\n\\centering\n\\caption{$\\dt$-embedding gradient conditions on Walker Walk. Any gradient pathway updating $e_{\\dt}$ is sufficient to induce CIVO; freezing or removing the embedding dramatically reduces severity.}\n\\label{tab:three_way_emb}\n\\footnotesize\n\\begin{tabular}{lccccl}\n\\toprule\nCondition & Grad flow & Exp(s) & NVE peak & Eval & CIVO \\\\\n\\midrule\nTrained & all & 008d, 059 & $1.53$--$4.72\\times$ & 64--268 & 5/5 \\\\\nReward detach & obs+KL only & 044 & $4.45\\times$ & 44$\\to$538$^\\dagger$ & 1/1 \\\\\nFull SGS & KL only & 018 & $1.66\\times$ & 448 & 1/1$^*$ \\\\\nFrozen & none & 042, 015b, 047, 057 & $0.19$--$1.88\\times$$^\\ddagger$ & 204--612 & 2/4 \\\\\nRemoved & N/A & 008f & $0.97$--$1.41\\times$ & 307--503 & 0/3 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$Full-SGS seed~1 (NVE $1.66\\times$); seed~2 collapsed. $^\\dagger$Self-corrected at ${\\sim}175$K (eval 44$\\to$538, 59\\% baseline; 224K run). $^\\ddagger$Exp\\_047 (NVE $1.71\\times$) and Exp\\_057 (NVE $1.88\\times$): both transient, self-correcting within 20K steps.\\par}\n\\end{table}\n\n\\paragraph{Controlled three-way causal ablation.}\nExperiments 067--069 provide a minimal causal ablation on Walker Walk (seed${=}1$), varying \\emph{only} the $\\dt$-embedding treatment while holding all other hyperparameters fixed ($H{=}8$, subsample ON, $\\dt{=}2$ imagination). Table~\\ref{tab:causal_ablation} shows that trained $\\dt$-embedding is necessary and sufficient for CIVO: freezing the embedding (gradient flow blocked, embedding weights still present) eliminates CIVO as completely as removing the embedding ($d{=}0$), ruling out the alternative hypothesis that embedding \\emph{presence} alone causes CIVO. Combined with all prior seeds, trained $\\dt$-embedding triggers CIVO in 10/10 multi-joint locomotion seeds (8 Walker, 2 Cheetah) versus 0/8 controls (Fisher exact $p < 0.0001$).\n\n\\begin{table}[h]\n\\centering\n\\caption{Three-way causal ablation (Walker Walk, seed${=}1$). Only the $\\dt$-embedding treatment varies; all other configuration is identical. Trained embedding triggers CIVO; frozen and removed do not.}\n\\label{tab:causal_ablation}\n\\footnotesize\n\\begin{tabular}{llccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Embedding} & \\textbf{NVE peak} & \\textbf{Eval final} & \\textbf{CIVO} \\\\\n\\midrule\n\\rowcolor{gray!15}\n068 & Trained ($d{=}32$) & $6.57\\times$ & 39.1 & Yes (alert @85K) \\\\\n067 & Frozen ($d{=}32$, \\texttt{req\\_grad=F}) & $0.40\\times$ & 281.5 & No \\\\\n069 & Removed ($d{=}0$) & $0.66\\times$ & 237.8 & No \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe reward-detach condition (exp\\_044, \\texttt{reward\\_dt\\_emb\\_detach=True}) uses a backward hook to block reward-head gradients from reaching $e_{\\dt}$, complementing the framework-level Reward SGS (exp\\_016e). Both yield the same directional result---CIVO onset not prevented---ruling out implementation artifacts. Exp\\_044 exhibits delayed CIVO onset (${\\sim}95$K vs.\\ typical $25$--$35$K), consistent with reduced but non-zero gradient pressure on $e_{\\dt}$. Over a full 224K run, exp\\_044 self-corrects: eval recovers from 44 (95K) to 538 (215K, 59\\% baseline), but this recovery is incomplete compared to spontaneous recovery without gradient intervention (exp\\_045: 868, 95\\% baseline). The lower asymptote suggests that selectively disrupting gradient flow may create optimization difficulties beyond CIVO itself.\n\nTable~\\ref{tab:factorial_design} summarizes the experimental configurations.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Factorial design. Each row specifies one experimental configuration. \\textbf{Emb}: $\\dt$-embedding mode. \\textbf{Sub}: temporal subsampling. \\textbf{H}: imagination horizon. \\textbf{Imag $\\dt$}: temporal resolution used during imagination.}\n\\label{tab:factorial_design}\n\\small\n\\setlength{\\tabcolsep}{3.5pt}\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\n\\textbf{ID} & \\textbf{Purpose} & \\textbf{Emb} & \\textbf{Sub} & \\textbf{H} & \\textbf{Imag $\\dt$} \\\\\n\\midrule\n001 & Reference baseline & --- & --- & 15 & 1 \\\\\n006 & Fixed $\\dt{=}2$ & trn & on & 15 & 2 \\\\\n007 & Fixed $\\dt{=}4$ & trn & on & 15 & 4 \\\\\n\\midrule\n008a & Unexposed emb ctrl & exp$^a$ & off & 15 & 2 \\\\\n008c & Horizon control & exp$^a$ & off & 8 & 2 \\\\\n008d & Collapse condition & trn & on & 8 & 2 \\\\\n008e\\_v3 & $\\dt{=}1$ imag control & trn & on & 15 & 1 \\\\\n008f & Causal ablation & --- & on & 8 & 2 \\\\\n\\midrule\n015b & Frozen-emb ctrl & frz$^b$ & on & 8 & 2 \\\\\n016e & Stop-grad (reward) & trn$^\\dagger$ & on & 8 & 2 \\\\\n018 & Full-SGS & trn$^\\ddagger$ & on & 8 & 2 \\\\\n\\midrule\n005 & Learned gate & adaptive & off & 15 & learned \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{-2pt}\n{\\raggedright\\footnotesize\ntrn = trained ($d{=}32$, exposed to $\\dt{>}1$ data via subsample ON);\nexp$^a$ = trained ($d{=}32$) but never exposed to $\\dt{>}1$ data (subsample OFF);\nfrz$^b$ = frozen random projection ($d{=}32$, \\texttt{requires\\_grad=False});\n--- = removed ($d{=}0$).\\\\\n$^\\dagger$ \\texttt{reward\\_dt\\_emb\\_detach=True}; $^\\ddagger$ all non-KL gradients to \\texttt{dt\\_emb} detached.\\par}\n\\end{table}\n\n\\subsection{F3: Unexposed Temporal Embedding Suppresses Value Drift}\n\\label{sec:f3}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig3_factorial_grid.pdf}\n\\caption{Factorial isolation of CIVO trigger. Only the combination of trained $e_{\\dt}$ and multi-rate data (upper-left cell) produces pathological NVE. Neither factor alone is sufficient.}\n\\label{fig:factorial_grid}\n\\end{figure}\n\nThe empirical finding that trained embedding \\emph{plus} multi-rate exposure jointly predict CIVO rests on two complementary controls that each remove one factor while holding the other constant.\n\n\\paragraph{Evidence A: exposure is necessary (exp\\_008a).}\nExp\\_008a uses a trained embedding ($d{=}32$, gradients enabled) that is never exposed to $\\dt{>}1$ transitions during world-model training (subsample OFF). Despite sharing the same embedding architecture as exp\\_008d, its NVE remains in the $0.83$--$0.93\\times$ range across 3 seeds (105K steps). Performance follows two V-shaped recovery cycles, reaching 777.7 at 105K (85\\% of baseline). The critical factor is not the embedding's capacity to represent temporal information, but its adaptation to multi-rate data that enables precise but inaccurate $\\dt{>}1$ state predictions within the RSSM.\n\nThis contrasts with exp\\_006 (trained $e_{\\dt}$, subsample ON, $H{=}15$), where NVE accelerates from $1.61\\times$ at 45K to $2.31\\times$ at 55K before catastrophic collapse to 132.9 at 65K. Both experiments use identical trained embeddings ($d{=}32$, gradients enabled) and $H{=}15$, differing only in whether the world model sees $\\dt{>}1$ transitions during training. This confirms that multi-rate data exposure, not embedding architecture, is the operative variable.\n\n\\paragraph{Evidence B: trainability is necessary (exp\\_015b).}\nExp\\_015b uses a frozen random-projection embedding ($d{=}32$, \\texttt{requires\\_grad=False}, subsample ON, $H{=}8$), the same multi-rate data regime as exp\\_008d, but with a non-trainable temporal signal. Despite full exposure to $\\dt{>}1$ transitions, the NVE peaks at $1.45\\times$ at 55K but does not sustain escalation: it retreats to $0.65\\times$ by 65K and settles at $0.42\\times$ by 105K (trajectory: $0.81 \\rightarrow 1.26 \\rightarrow 1.45 \\rightarrow 0.65 \\rightarrow 1.05 \\rightarrow 0.47 \\rightarrow 0.39 \\rightarrow 0.42$). The transient peak approaches but does not exceed the $1.5\\times$ CIVO threshold, and critically, the ratio self-corrects rather than exhibiting the monotonic escalation seen in trained-embedding runs. Final evaluation reaches only 204.2 at 105K, low but through a qualitatively different failure mode than CIVO. Actor loss approaches zero (gradient starvation; see \\S\\ref{sec:pathways}), the frozen embedding provides no useful gradient signal for temporal adaptation.\n\nThe contrast with exp\\_008d is stark: under identical data conditions (subsample ON, $H{=}8$), the trained embedding drives NVE to $4.12\\times$ with sustained monotonic escalation ($1.78 \\rightarrow 1.71 \\rightarrow 2.09 \\rightarrow 4.12$) and precedes full collapse (eval 82.8), while the frozen embedding peaks transiently at $1.45\\times$ before self-correcting to $0.42\\times$, a qualitative difference between sustained and transient overestimation. This demonstrates that a $\\dt$-embedding must be able to \\emph{co-adapt} with RSSM dynamics to produce the systematic reward-prediction bias that drives CIVO; a static random projection, regardless of its exposure to multi-rate data, cannot create this bias.\n\nTogether, these two controls establish that in all tested configurations, CIVO occurs only with the \\emph{joint} presence of (i)~a trainable embedding that can co-adapt with RSSM dynamics, and (ii)~multi-rate training data that drives this co-adaptation toward biased temporal predictions. Neither factor alone is sufficient.\n\nCross-environment validation on Cheetah Run replicates the empirical pattern: trained $e_{\\dt}$ precedes CIVO in both tested seeds (exp\\_010b, 2 seeds, NVE $8.27$--$108.52\\times$, collapse to 51.7/0.83) while removing the embedding eliminates it (exp\\_024b, 2 seeds, NVE $<0.2\\times$, eval 96.5/77.3). Freezing the embedding on Cheetah (exp\\_046, NVE${=}1.35\\times$ vs.\\ trained $70.64\\times$, a $52\\times$ reduction) further confirms that embedding trainability, not architecture, drives CIVO. This extends the sufficiency finding from Walker Walk to a second locomotion environment with qualitatively different dynamics (6-joint vs.\\ 2-joint).\n\n\\begin{table}[ht]\n\\centering\n\\small\n\\caption{Causal isolation: $e_{\\dt}$ configuration $\\times$ multi-rate data exposure. The combination of trained embedding and multi-rate exposure is the sole predictor of CIVO in tested configurations. Neither factor alone is sufficient.}\n\\label{tab:causal_matrix}\n\\begin{tabular}{lcc}\n\\toprule\n& Multi-rate data (\\textsc{on}) & Single-rate data (\\textsc{off}) \\\\\n\\midrule\nTrained $e_{\\dt}$ & exp\\_008d: \\textbf{CIVO} & exp\\_008a: healthy \\\\\n & NVE 4.12$\\times$, collapse & NVE 0.93$\\times$ \\\\\n\\midrule\nFrozen $e_{\\dt}$ & exp\\_015b: grad.\\ starvation & --- \\\\\n & peak NVE 1.45$\\times$ (transient) & \\\\\n\\midrule\nRemoved $e_{\\dt}$ & exp\\_008f: no CIVO & --- \\\\\n & NVE $\\leq$0.97$\\times$ & \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOnly the upper-left cell (trained embedding with multi-rate exposure) precedes CIVO (Table~\\ref{tab:causal_matrix}). This 2$\\times$2 structure establishes that both factors are jointly sufficient in tested configurations.\n\n\\subsection{F4: Degradation Scales Monotonically with \\texorpdfstring{$\\dt$}{dt}}\n\\label{sec:f4}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig5_dt_amplification.pdf}\n\\caption{Peak evaluation return as a function of imagination $\\dt$. Performance degrades monotonically: $\\dt{=}1$ (915.7) $>$ $\\dt{=}2$ (485.3, $-47\\%$) $>$ $\\dt{=}4$ (176.9, $-81\\%$).}\n\\label{fig:dt_amplification}\n\\end{figure}\n\nThe magnitude of degradation scales monotonically with the imagination step size (Figure~\\ref{fig:dt_amplification}). From the $\\dt{=}1$ baseline (915.7 at 105K), fixed $\\dt{=}2$ (exp\\_006) achieves a peak of only 485.3 ($-47\\%$), and fixed $\\dt{=}4$ (exp\\_007) peaks at 176.9 ($-81\\%$). This monotonic relationship is consistent with compounding model error: larger temporal gaps amplify the RSSM's prediction inaccuracy at each imagination step, and these errors accumulate across the rollout horizon.\n\n\\subsection{F5: Imagination Horizon and Subsampling Are Secondary Factors}\n\\label{sec:f5}\n\nNeither horizon length nor temporal subsampling precedes collapse without multi-rate data exposure: both trained-but-unexposed configurations (008a, 008c) maintain $\\nve < 0.93\\times$ (\\S\\ref{sec:f3}), while the trained-and-exposed counterpart (008d) collapses with $\\nve = 4.12\\times$.  The no-embedding configurations show cross-seed variance (008f: 503.0 vs.\\ 009c: 148.3) but neither exhibits $\\nve > 1.5\\times$; low evaluation alone does not indicate CIVO.\n\nThe $3.2\\times$ performance gap (008a: 777.7 vs.\\ 008c: 240.9) quantifies the horizon effect independently of CIVO, as both conditions maintain healthy NVE ($\\leq$0.93$\\times$).\n\n% --- APPENDIX C: Full Analysis & Discussion ---\n\n\\section{Full Analysis \\& Discussion}\n\\label{sec:appendix_analysis}\n\nThis appendix provides the complete mechanistic analysis summarized in Section~\\ref{sec:discussion} of the main text.\n\n\\subsection{The CIVO Mechanism}\n\\label{sec:civo_mechanism}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/paper/fig4_mechanism_diagram.pdf}\n\\caption{CIVO mechanism diagram. The trained $\\dt$-embedding enables asymmetric reward prediction fidelity, initiating a feedback loop: biased RSSM rewards $\\to$ optimistic critic values $\\to$ actor exploitation $\\to$ reinforced state-distribution skew.}\n\\label{fig:civo_mechanism}\n\\end{figure}\n\n\\begin{table}[h]\n\\centering\n\\caption{RSSM fidelity at $\\dt{=}1$ vs.\\ $\\dt{=}2$. Trained embedding (008d) produces $2.78\\times$ reward gap; removing it (008f) eliminates the gap but degrades absolute prediction.}\n\\label{tab:rssm_fidelity}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{3}{c}{\\textbf{obs\\_MSE}} & \\multicolumn{3}{c}{\\textbf{reward\\_MAE}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\n\\textbf{Config} & $\\dt{=}1$ & $\\dt{=}2$ & Gap & $\\dt{=}1$ & $\\dt{=}2$ & Gap \\\\\n\\midrule\nBaseline & 13.49 & 27.50 & 2.04$\\times$ & 0.0102 & 0.0159 & 1.56$\\times$ \\\\\n008d (trained) & 41.31 & 53.67 & 1.30$\\times$ & 0.0568 & 0.1579 & 2.78$\\times$ \\\\\n008f (no emb) & 8.01 & 22.04 & 2.75$\\times$ & 0.7469 & 0.7526 & 1.01$\\times$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe RSSM fidelity analysis (Table~\\ref{tab:rssm_fidelity}) reveals the mechanistic core of CIVO (Figure~\\ref{fig:civo_mechanism}).  The trained $\\dt$-embedding enables the reward head to learn temporally differentiated predictions, but these predictions are asymmetrically accurate: reward MAE at $\\dt{=}1$ is $0.0568$, while at $\\dt{=}2$ it rises to $0.1579$, a $2.78\\times$ gap.  This gap is not an artifact of prediction difficulty alone; the no-embedding configuration (008f) exhibits a $1.01\\times$ gap, and the baseline shows $1.56\\times$.  The trained embedding actively amplifies the fidelity discrepancy by allowing the reward head to co-adapt with the temporal signal.\n\nThis asymmetric fidelity initiates a feedback loop with four stages: (1) the trained $\\dt$-embedding causes RSSM predictions at $\\dt > 1$ to carry systematically biased reward estimates; (2) the critic, trained entirely on imagined trajectories, internalizes these biased rewards as optimistic value estimates; (3) the actor exploits the overestimated regions of the value landscape, shifting its policy toward states that appear high-value only under the biased model; and (4) this policy shift further skews the distribution of imagined states, reinforcing the bias.  The diagnostic signature is a sustained $\\nve$ above $1.5\\times$, followed by evaluation collapse.\n\nA random-policy control experiment ($N{=}100$ rollouts, 95\\% bootstrap CI) decomposes CIVO into two necessary stages.  \\textbf{Stage~1 (dynamics bias):} even under a random policy, $\\dt{=}2$ imagination produces $1.68\\times$ higher mean reward than $\\dt{=}1$ in the trained-embedding model (008d): the RSSM prior already generates reward-favorable trajectories at $\\dt > 1$, independent of actor behavior.  \\textbf{Stage~2 (actor exploitation):} the trained actor learns to exploit these biased regions, amplifying the ratio to $2.90\\times$.  In the no-embedding control (008f), neither stage is present: the random-policy ratio is $1.11\\times$ and the trained-actor ratio is $0.98\\times$.  The decomposition attributes $\\approx 36\\%$ of the total effect to dynamics bias and $\\approx 64\\%$ to actor exploitation, which confirms that both stages are necessary for CIVO to manifest.\n\nThis mechanism is analogous to delusional bias \\citep{lu2018nondelusional}, but differs in origin: delusional bias arises from policy-class constraints, while CIVO is model-induced.  The consequence (policy exploitation of overestimated regions) is similar, but the causal pathway is distinct.\n\n\\paragraph{Signed reward error analysis.}\nTo test whether CIVO arises from one-step reward overprediction, we compute signed error (predicted $-$ actual) on posterior-conditioned RSSM predictions (Table~\\ref{tab:signed_error}). The trained-embedding model (008d) shows \\emph{negative} bias at $\\dt{=}2$ (mean signed error $-0.599$, only 8\\% of samples overpredicted), ruling out observation-level reward overprediction as the mechanism. The baseline is well-calibrated (mean SE $\\approx 0$), confirming methodological soundness. Value overestimation therefore occurs during \\emph{imagination-level} prior drift: the RSSM prior (unconditioned on observations) generates reward-favorable trajectories at $\\dt > 1$ (Stage~1 above, $1.68\\times$ ratio under random policy), and the critic accumulates these into overestimated returns. The one-step reward prediction is negatively biased when conditioned on real observations, but this posterior correction is unavailable during imagination. This also distinguishes CIVO from generic compounding error, which would produce \\emph{positive} signed error accumulating with horizon; the negative observation-level bias confirms that CIVO is a prior-drift phenomenon, not a reward-prediction artifact.\n\n\\begin{table}[h]\n\\centering\n\\caption{Signed reward error (predicted $-$ actual) on posterior-conditioned RSSM predictions. Negative values indicate underprediction. The trained-embedding model underpredicts at $\\dt{=}2$, ruling out observation-level reward overprediction as the CIVO mechanism.}\n\\label{tab:signed_error}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llrrrrr}\n\\toprule\n\\textbf{Config} & $\\dt$ & \\textbf{Mean SE} & \\textbf{Std} & \\textbf{\\%Over} & \\textbf{Actual} & \\textbf{Pred} \\\\\n\\midrule\nBaseline & 1 & $+0.001$ & 0.023 & 39.6\\% & 1.893 & 1.894 \\\\\n\\midrule\n008d (trained) & 1 & $+0.018$ & 0.072 & 61.8\\% & 0.361 & 0.379 \\\\\n008d (trained) & 2 & $\\mathbf{-0.599}$ & 0.722 & 8.0\\% & 0.721 & 0.121 \\\\\n\\midrule\n008f (no emb) & 1 & $-0.710$ & 0.704 & 14.0\\% & 0.921 & 0.211 \\\\\n008f (no emb) & 2 & $-1.645$ & 1.485 & 5.0\\% & 1.840 & 0.195 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Embedding geometry (exp\\_065).}\nTo characterize what the trained $\\dt$-embedding learns, we measure pairwise cosine similarity between $e_{\\dt{=}1}$ and $e_{\\dt{=}2}$ across training checkpoints for three trained seeds (two environments) and two frozen controls (Table~\\ref{tab:cosine_sim}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity between $e_{\\dt{=}1}$ and $e_{\\dt{=}2}$ vectors. Trained embeddings converge to near-opposite representations; frozen embeddings remain near-orthogonal throughout.}\n\\label{tab:cosine_sim}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llrrr}\n\\toprule\n\\textbf{Config} & \\textbf{Env} & \\textbf{cos@25K} & \\textbf{cos@75K} & \\textbf{Status} \\\\\n\\midrule\n008d s3 (trained) & Walker & $-0.87$ & $-0.70$ & CIVO \\\\\n059 s5 (trained) & Walker & $-0.94$ & $-0.86$ & CIVO \\\\\n010b s0 (trained) & Cheetah & $-0.90$ & $-0.84$ & CIVO \\\\\n\\midrule\n057 s2 (frozen) & Walker & $-0.15$ & $-0.15$ & Healthy \\\\\n058 s1 (frozen) & Cheetah & $+0.07$ & $+0.07$ & Healthy \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll trained seeds map $\\dt{=}1$ and $\\dt{=}2$ to nearly opposite directions (cosine similarity $-0.70$ to $-0.94$), consistent across both Walker and Cheetah environments. Frozen controls remain near-orthogonal (cosine $\\approx 0$) and constant across all checkpoints. The full pairwise cosine similarity matrix (Figure~\\ref{fig:pairwise_heatmap}) reveals that the near-antipodal relationship between $e_{\\dt{=}1}$ and $e_{\\dt{=}2}$ is the dominant structure: most other $\\dt$-pairs remain near-orthogonal ($|\\text{cos}| < 0.2$), indicating that the RSSM selectively maximizes separation along the $\\dt{=}1$ vs.\\ $\\dt{=}2$ axis rather than learning a globally structured embedding space.\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.55\\columnwidth]{figures/paper/pairwise_heatmap.png}\n\\caption{Pairwise cosine similarity between all $\\dt$-embedding vectors (exp\\_008d, seed 3, step 75K). The $e_{\\dt{=}0}$--$e_{\\dt{=}1}$ pair exhibits strong anti-correlation ($-0.70$); remaining pairs are near-orthogonal, confirming that the learned geometry is dominated by a single antipodal axis.}\n\\label{fig:pairwise_heatmap}\n\\end{figure}\n\nThe magnitude of the learned separation---near-antipodal rather than merely distinct---provides converging evidence that the RSSM develops maximally differentiated internal representations for the two temporal scales, which in turn may contribute to the asymmetric reward fidelity gap reported in Table~\\ref{tab:rssm_fidelity} and replicated below.\n\n\\paragraph{Extended RSSM fidelity replication (exp\\_063).}\nTo validate the fidelity gap on independently trained checkpoints, we repeat the posterior-conditioned analysis with 15 episodes $\\times$ 40 test points $\\times$ 4 $\\dt$ levels (600 samples per model) on final checkpoints from three conditions (Table~\\ref{tab:rssm_fidelity_ext}).\n\n\\begin{table}[h]\n\\centering\n\\caption{RSSM fidelity analysis (training-time posterior-conditioned). Reward prediction gap remains the critical differentiator; observation reconstruction is paradoxically \\emph{better} with trained embedding. Independent final-checkpoint replication (exp\\_063, 008d seed~4) yields a reward gap of $2.7\\times$, confirming the qualitative pattern at lower magnitude.}\n\\label{tab:rssm_fidelity_ext}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lcccccc}\n\\toprule\n& \\multicolumn{3}{c}{\\textbf{obs\\_MSE}} & \\multicolumn{3}{c}{\\textbf{reward\\_MAE}} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\n\\textbf{Config} & $\\dt{=}1$ & $\\dt{=}2$ & Gap & $\\dt{=}1$ & $\\dt{=}2$ & Gap \\\\\n\\midrule\nBaseline (009d) & 16.08 & 23.49 & 1.46$\\times$ & 0.045 & 0.059 & 1.30$\\times$ \\\\\nCollapsed (008d) & 9.96 & 13.21 & 1.33$\\times$ & 0.057 & 0.178 & 3.11$\\times$ \\\\\nFrozen (057) & 11.14 & 14.95 & 1.34$\\times$ & 0.068 & 0.133 & 1.96$\\times$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe replication confirms the original fidelity gap pattern with two additional observations. First, the collapsed model achieves the \\emph{lowest} absolute obs\\_MSE at $\\dt{=}1$ (9.96 vs.\\ baseline 16.08), indicating that the trained $\\dt$-embedding improves world model quality overall---the pathology is selective degradation of reward predictions at longer horizons, not general model failure. Second, freezing the $\\dt$-embedding reduces the reward gap from $3.11\\times$ (training-time; $2.7\\times$ in independent replication) to $1.96\\times$, providing converging evidence for its role in preventing the co-adaptation loop while leaving residual multi-step reward prediction difficulty.\n\n\\paragraph{Value prediction analysis (exp\\_064).}\nTo examine the relationship between RSSM reward fidelity and critic value estimates, we compare critic predictions $V(s)$ against actual evaluation returns across three conditions (Table~\\ref{tab:value_pred}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Critic value predictions vs.\\ actual evaluation returns. The CIVO model's critic is well-calibrated to its $\\lambda$-return targets ($V(s) \\approx$ target) but both $V$ and targets are disconnected from reality (VE${=}3.03\\times$).}\n\\label{tab:value_pred}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{lrrrr}\n\\toprule\n\\textbf{Config} & $V(s)$ & \\textbf{Eval} & \\textbf{VE ratio} & $V{-}\\text{target}$ \\\\\n\\midrule\nBaseline (001) & 665.9 & 938.9 & 0.71$\\times$ & $+0.001$ \\\\\nCIVO (008d) & 192.7 & 63.6 & \\textbf{3.03}$\\times$ & $+0.586$ \\\\\nNo emb (008f) & 116.5 & 306.5 & 0.38$\\times$ & $+0.316$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe paradox---$V(s)$ tracks its $\\lambda$-return targets faithfully yet overestimates actual performance by $3\\times$---provides converging evidence for the hypothesized mechanism in which CIVO operates upstream of the critic: the world model generates inflated imagination trajectories that the critic learns faithfully, producing targets disconnected from reality. In the baseline, VE${<}1.0$ throughout training because $V(s)$ reflects discounted imagined returns over $H{=}15$ steps, naturally lower than undiscounted episodic evaluation. The CIVO model crosses VE${=}1.0$ at step 55K and reaches $3.03\\times$ by 105K, with the gap widening as the actor exploits the overoptimistic critic.\n\n\\paragraph{Actor entropy dynamics under CIVO.}\nExtended training of collapsed configurations reveals a distinctive temporal sequence: evaluation return collapses first, followed by actor entropy explosion ${\\sim}35$K steps later. In the most severe case (EG~v4), entropy rises from $-5.21$ to $+3.22$ nats at a rate of $+2.11$ nats/10K steps, with returns declining from 583 to 93 between steps 60K--120K. A second collapsed run (EG~v5) shows $+0.61$ nats/10K with comparable return degradation (583$\\to$102). By contrast, healthy baselines exhibit gradual entropy drift at $+0.07$ to $+0.22$ nats/10K---15--30$\\times$ slower---with returns stable above 900. The return-before-entropy temporal ordering is consistent with the causal chain: delusional critic $\\to$ bad actor gradients $\\to$ policy destabilization. The entropy explosion is a lagging indicator; the NVE diagnostic detects CIVO onset ${\\sim}35$K steps before entropy rises, consistent with its use as an early-warning signal (\\S\\ref{sec:appendix_sensitivity}).\n\n\\subsection{Selective Gradient Stopping and Gradient Decomposition}\n\\label{sec:sgs_gradient_analysis}\n\n\\subsubsection{Gradient Decomposition Results}\n\\label{sec:gradient_decomposition}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/fig3_gradient_decomposition.pdf}\n\\caption{Gradient contribution to $e_{\\Delta t}$ by loss component at two training checkpoints. The reward head contributes the largest share (38--49\\%) yet reward-only SGS (exp\\_016e) fails; the observation decoder channel (16--22\\%) carries the critical $\\dt$-specific spatial information that drives the RSSM fidelity gap.}\n\\label{fig:gradient_decomp}\n\\end{figure}\n\nExp\\_016e collapses in the same qualitative pattern as the unmodified control: peak evaluation 326.7 at 75K steps followed by catastrophic decline to 31.7 at 95K, with NVE reaching $10.42\\times$. The SGS intervention neither prevented nor attenuated CIVO.\n\nTo explain this null result, we performed a gradient decomposition analysis using \\texttt{torch.autograd.grad} to measure each loss component's contribution to $\\nabla_\\theta e_{\\Delta t}$, where $\\theta$ denotes the temporal embedding parameters. Table~\\ref{tab:gradient_decomposition} reports the results.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Gradient contributions to the temporal embedding $e_{\\Delta t}$ by loss component, measured via \\texttt{torch.autograd.grad} with training configuration \\texttt{gate\\_fixed\\_dt=2}. Gradient norms are $\\ell_2$ norms of $\\nabla_\\theta \\mathcal{L}_i$ for each loss $\\mathcal{L}_i$.}\n\\label{tab:gradient_decomposition}\n\\small\n\\begin{tabular}{lrrrr}\n\\toprule\n& \\multicolumn{2}{c}{\\textbf{@55K}} & \\multicolumn{2}{c}{\\textbf{@112K}} \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5}\nLoss component & Share & (\\%) & Share & (\\%) \\\\\n\\midrule\nReward head & --- & 49.0 & --- & 38.1 \\\\\nKL dynamics & --- & 34.7 & --- & 40.4 \\\\\nObservation decoders & --- & 16.3 & --- & 21.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe gradient decomposition reveals a counterintuitive structure: the reward head provides the largest gradient contribution (49.0\\% at 55K, 38.1\\% at 112K), yet reward-only SGS (exp\\_016e) fails catastrophically (NVE $10.42\\times$). The observation decoder channel contributes the smallest share (16.3\\% at 55K, 21.5\\% at 112K) yet carries the critical $\\dt$-specific spatial information.  This dissociation between gradient magnitude and causal importance explains why exp\\_016e, which targets the largest pathway, is functionally insufficient for CIVO prevention.\n\nThe gradient structure is relatively stable across training (reward shifts from 49\\% to 38\\%, obs from 16\\% to 22\\%, KL from 35\\% to 40\\%), unlike what a magnitude-based account would predict. The reward head's large gradient contribution reflects the scalar reward prediction task's sensitivity to temporal embedding parameters, but this gradient does not encode $\\Delta t$-specific structural information about spatial dynamics. The observation decoder channel, despite its smaller magnitude, is the only pathway that encodes how the RSSM should differentially predict multi-dimensional proprioceptive states across temporal scales.\n\n\\paragraph{Why the smallest channel is causally critical.} The observation decoder is the only loss component whose gradients encode how the RSSM should differentially predict multi-dimensional proprioceptive states ($14$ orientations, $9$ velocities, $1$ height) across temporal scales.  This $\\dt$-specific spatial information shapes the latent state representation in ways that propagate to reward prediction: the RSSM fidelity gap ($2.78\\times$ reward MAE ratio, Table~\\ref{tab:rssm_fidelity}) arises because the temporal embedding learns to produce latent states that are spatially biased at $\\dt{>}1$, not because the reward head directly learns scale-dependent biases.  Full-SGS targets this causal chain by preventing observation-decoder gradients from updating $e_{\\Delta t}$, though its 0/2 CIVO elimination rate on Walker (seed~1: NVE reduced from $4.12\\times$ to $1.66\\times$ but remains CIVO-positive; seed~2: collapsed) indicates that breaking the gradient pathway alone does not fully eliminate the vulnerability.\n\n\\subsubsection{Implications for the CIVO Mechanism}\n\\label{sec:sgs_implications}\n\nThe gradient decomposition reveals that gradient magnitude and causal importance are decoupled in CIVO.\n\n\\paragraph{Gradient importance $\\neq$ gradient magnitude.} The reward head contributes the largest gradient share (38--49\\%) to $e_{\\Delta t}$, yet reward-only SGS fails.  The observation decoder contributes the smallest share (16--22\\%), yet its removal (via Full-SGS) is necessary for CIVO mitigation.  This dissociation arises because the reward head's gradient, while large, does not encode $\\dt$-specific structural information: it adjusts $e_{\\Delta t}$ to minimize a scalar prediction error that is largely $\\dt$-invariant.  The observation decoder's gradient, though smaller, encodes how the RSSM should differentially reconstruct 24-dimensional proprioceptive states across temporal scales. This is the channel through which $e_{\\Delta t}$ learns scale-dependent latent biases.\n\n\\paragraph{Reframing the intervention target.} Any gradient-level strategy that targets the reward head alone (reward prediction regularization, reward-conditioned value clipping, or reward-only SGS) targets the largest pathway but not the informationally critical one.  The failure of exp\\_016e (NVE $10.42\\times$) despite detaching the dominant gradient source confirms this.  Full-pathway SGS (exp\\_018) detaches $e_{\\Delta t}$ from all non-KL gradients, retaining only the KL dynamics contribution (34--40\\%).  However, this intervention eliminates CIVO in neither seed: seed~1 shows partial mitigation (eval 448.3, peak NVE $1.66\\times$, still CIVO-positive) while seed~2 collapses (eval 40.8). Removing the observation decoder gradient channel is thus contributory but not sufficient. Figure~\\ref{fig:civo_decomposition} decomposes evaluation returns across conditions.\n\n\\begin{figure}[ht]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/fig2_civo_decomposition.pdf}\n\\caption{CIVO decomposition: peak and final (105K step) evaluation returns on Walker Walk across four conditions. \\textbf{Baseline} (001): vanilla DreamerV3. \\textbf{Trained dt-emb} (008d)\\protect\\footnotemark: learned $d{=}32$ temporal embedding with multi-rate data. \\textbf{Full-SGS} (s1, s2): trained embedding with all non-KL gradients detached from $e_{\\dt}$. Trained $\\dt$-embedding degrades peak eval by $73\\%$ and final eval by $86\\%$. Full-SGS seed~1 shows partial mitigation ($-51\\%$ final, NVE $1.66\\times$, still CIVO-positive) while seed~2 collapses ($-96\\%$ final). CIVO elimination rate $= 0/2$.}\n\\label{fig:civo_decomposition}\n\\end{figure}\n\\footnotetext{Experiment 008d terminated at 55K steps; the 105K data point uses continuation run 009e under identical configuration.}\n\nCross-environment validation on Cheetah Run (exp\\_021) further clarifies the role of Full-SGS.  The intervention did not prevent the initial CIVO onset: NVE peaked at $9.94\\times$ at 45K (comparable to the unmitigated exp\\_010b's $8.27\\times$).  However, unlike exp\\_010b, which collapsed permanently to eval 51.7, exp\\_021 self-corrected within ${\\sim}$10K steps, with sustained NVE dropping to $0.34\\times$ (55K--105K) and final evaluation recovering to 221.5.  This transient self-correcting trajectory is not attributable to the SGS intervention: the initial CIVO onset and peak severity are comparable to the unmitigated case, and the self-correction may reflect Cheetah Run's simpler dynamics rather than SGS efficacy.  Performance remains at 38.7\\% of baseline (572.5), likely because Full-SGS over-aggressively blocks actor gradients (actor gradient norms near zero throughout training).  Combined with exp\\_018's Walker results (0/2 CIVO elimination), these findings yield a 0/3 elimination rate across environments, indicating that gradient-level interventions alone do not eliminate the CIVO vulnerability. Additional mechanisms (e.g., forward-pass conditioning effects, residual capacity-dependent instabilities) operate beyond the gradient pathway.\n\n\\paragraph{Connection to RSSM fidelity analysis.} The trained-embedding condition (exp\\_008d) shows a $2.78\\times$ reward gap between $\\Delta t{=}1$ and $\\Delta t{=}2$ transitions (Table~\\ref{tab:rssm_fidelity}).  This gap arises because the observation decoder gradients shape $e_{\\Delta t}$ to produce latent states that are spatially biased at $\\dt{>}1$, and the reward head inherits these biases \\textit{through the latent state} rather than learning them directly.  The reward head's large gradient contribution reflects sensitivity to $e_{\\Delta t}$'s parameters but not causal responsibility for the fidelity gap.\n\n\\subsubsection{Entropy Dynamics Across Configurations}\n\\label{sec:entropy_dynamics}\n\n\\begin{figure}[ht]\n\\centering\n\\includegraphics[width=0.85\\columnwidth]{figures/fig4_entropy_dynamics.pdf}\n\\caption{Actor entropy trajectories for three configurations. All start at ${\\sim}8$ nats and converge to similar values (${\\sim}{-}4.5$ to ${-}5$). The CIVO-triggering configuration (008d, red) follows a normal entropy reduction trajectory; the divergence from the control (008f) is subtle in entropy space, consistent with CIVO operating through the value channel rather than the entropy channel. 018v2 (Full-SGS, seed~1) shows slightly lower terminal entropy.}\n\\label{fig:entropy_dynamics}\n\\end{figure}\n\n\\subsubsection{Exp\\_016e Reinterpreted as Stochastic Variation}\n\\label{sec:016e_reinterp}\n\nThe gradient decomposition establishes that exp\\_016e targets the largest gradient pathway (reward: 38--49\\%) but not the informationally critical one (observation decoders: 16--22\\%).  The apparent timing differences between exp\\_016e and exp\\_008d (later collapse onset, 75K vs.\\ 25K, and higher peak evaluation, 326.7 vs.\\ 167.2) must be attributed to stochastic variation rather than SGS effects, since the critical observation decoder channel remains intact.  All three trajectories (exp\\_008d, exp\\_009b, exp\\_016e) share the invariant identified by the NVE diagnostic: each crosses the $1.5\\times$ pathological threshold at some point during training.\n\n\\subsection{Post-CIVO Outcomes: Why Seeds Diverge}\n\\label{sec:seed_divergence}\n\n\\begin{table}[ht]\n\\centering\n\\caption{Post-CIVO outcomes for all ten CIVO-positive runs across two environments. Peak/Final NVE measured in the 35K+ window.}\n\\label{tab:post_civo}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccl}\n\\toprule\n\\textbf{Env} & \\textbf{Seed} & \\textbf{Peak} & \\textbf{Final} & \\textbf{Eval} & \\textbf{Outcome} \\\\\n\\midrule\nWalker & s1 (008d) & 4.12$\\times$ & 4.12$\\times$ & 82.8 & Full collapse \\\\\nWalker & s2 (009b) & 1.62$\\times$ & 0.38$\\times$ & 267.9 & Transient CIVO \\\\\nWalker & s3 (008d\\_s3) & 1.53$\\times$ & 1.53$\\times$ & 268$^\\diamond$ & Late-onset collapse \\\\\nWalker & s4 (008d\\_s4) & 4.62$\\times$ & 4.62$\\times$ & 63.6 & Full collapse \\\\\nWalker & s5 (059) & 4.72$\\times$ & 1.22$\\times$ & 95.8 & Collapse$^\\dagger$ \\\\\n\\midrule\nCheetah & s1 (010b) & 8.27$\\times$ & 8.27$\\times$ & 51.7 & Full collapse \\\\\nCheetah & s0 (078) & 4.10$\\times$ & 0.29$\\times$ & 119.5 & Self-correcting$^\\ddagger$ \\\\\nCheetah & s0 (010b\\_s0) & 108.52$\\times$ & 108.52$\\times$ & 0.83 & Full collapse \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^\\diamond$ Transitional; train returns still declining at 105K. $^\\dagger$~NVE self-corrected ($4.72\\times$ $\\to$ $1.22\\times$) but policy did not recover (eval 10.5\\% of baseline). $^\\ddagger$~Peak NVE $4.10\\times$ at 75K; eval 213.7$\\to$26.1$\\to$119.5 (26.7\\% of baseline exp\\_077, 448.1).\\par}\n\\end{table}\n\nAll ten CIVO-positive runs cross the $\\nve > 1.5\\times$ threshold (Table~\\ref{tab:post_civo}), yet the downstream damage is stochastic.\\footnote{Exp\\_009e was excluded from multi-seed analyses due to a seed configuration error (default seed=0, identical to exp\\_008d).}  Sustained collapse is the majority outcome (6/10 runs). Three runs self-correct (Walker seed~2 and both Cheetah seeds, including exp\\_078 which recovers from 26.1 to 119.5 at 105K); one (Walker seed~5) shows onset without sustained collapse---NVE self-corrects ($4.72\\times \\to 1.22\\times$) but the policy remains collapsed (eval 10.5\\% of baseline). Cheetah seed~1 (010b) exhibits more extreme overestimation (peak NVE $8.27\\times$) than Walker seeds ($1.53$--$4.62\\times$), consistent with the Cheetah reward scale amplifying the fidelity gap.  We hypothesize that the divergence relates to the critic's representational capacity at the time of CIVO onset.  \\citet{lyle2022capacity} demonstrate that deep RL networks suffer progressive capacity loss, in which early-learned features become increasingly difficult to overwrite.  If the critic's capacity is already partially consumed when CIVO injects overestimation, the network cannot recalibrate (seed~0); if sufficient capacity remains, the critic can absorb transient overestimation and recover (seed~2).\n\n\\paragraph{A fourth trajectory: CIVO-induced persistent value collapse.}\nObs-decoder SGS seed~3 (exp\\_025) exhibits a trajectory not observed in the untreated seeds: healthy through 105K ($\\nve < 1.0\\times$, eval 818.6), CIVO onset at 135K ($\\nve = 5.47\\times$, eval 67.0), followed by evaluation recovery (590.2 at 215K, 64\\% of baseline) but persistent value collapse ($\\nve = 0.14\\times$, value mean 80.6). The critic undershoots after the CIVO episode, suggesting that CIVO-induced representational damage persists even when the policy partially recovers. This contrasts with transient CIVO (seed~2, 009b), where both value and evaluation recover jointly, and with full collapse (seed~1, 008d), where neither recovers. Seed~4 exhibits the same terminal value collapse ($\\nve = 0.14\\times$ at 215K, eval 242), suggesting this overcorrection is systematic rather than seed-specific. The pattern adds a fourth post-CIVO outcome---policy recovery with critic damage---to the three documented in Table~\\ref{tab:post_civo}.\n\n\\subsubsection{Failure and Degradation Mode Taxonomy}\n\nTable~\\ref{tab:failure_modes} classifies the seven distinct failure and degradation modes observed across all experimental configurations. The taxonomy reveals that CIVO is not a single failure mode but a family of related pathologies, with the trained $\\dt$-embedding creating vulnerability through at least three independent mechanisms: value-driven collapse (monotonic, late-onset, and SGS-resistant CIVO), entropy-driven instability (IRD collapse), and gradient-mediated effects (gradient starvation, SGS-paradoxical worsening).\n\n\\begin{table}[ht]\n\\centering\n\\caption{Failure and degradation mode taxonomy. Each mode is characterized by its NVE trajectory, entropy behavior, and primary mechanism.}\n\\label{tab:failure_modes}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{@{}llccl@{}}\n\\toprule\n\\textbf{Mode} & \\textbf{Representative} & \\textbf{NVE} & \\textbf{Entropy} & \\textbf{Mechanism} \\\\\n\\midrule\nMonotonic CIVO & 008d, 008d\\_s4, 010b\\_s0 & $\\uparrow$ sustained & $\\downarrow$ & Reward bias $\\to$ critic $\\to$ actor \\\\\nLate-onset CIVO & 008d\\_s3 & $\\uparrow$ delayed & $\\downarrow$ & Same, delayed onset \\\\\nTransient CIVO & 009b & Peak $\\to$ $\\downarrow$ & Stable & Self-correction via capacity \\\\\nIRD collapse & 008e\\_v3\\_s2 & $\\uparrow$ late & $\\uparrow$ & Entropy-driven, values stable \\\\\nGrad.\\ starvation & 015b & Oscillates, decays & Stable & Frozen emb $\\to$ zero actor grad \\\\\nSGS-resistant & 018\\_s2 & $\\uparrow$ & $\\downarrow$ & Forward-pass conditioning \\\\\nSGS-paradoxical & 016e & $\\uparrow$ sustained & $\\downarrow$ & Reward SGS $\\to$ obs-dec reliance \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Extended Training Dynamics}\\label{sec:extended_training}\n\nOne Walker seed (s3, exp\\_045) was extended from 112K to approximately 302K steps to investigate long-horizon CIVO dynamics. After onset (NVE peak $4.91\\times$ at 132K steps), the system exhibited complete self-recovery: NVE declined to $0.05\\times$ and evaluation performance recovered to 867.6 (94.7\\% of baseline). This recovery required approximately 170K additional training steps beyond onset. The trajectory shows a single onset--recovery cycle with no recurrence, suggesting that the CIVO feedback loop can break spontaneously given sufficient training---though at substantial computational cost that the frozen $\\dt$-embedding diagnostic eliminates entirely.\n\n\\subsection{Why MPC Is Immune}\n\\label{sec:mpc_immune}\n\n\\citet{nhu2025tawm} show that $\\dt$-conditioning benefits TD-MPC2, raising the question of why it fails in DreamerV3.  The critical difference is that MPC re-plans from real states at every step, so imagination errors do not accumulate into the training signal because there is no critic bootstrapping from imagined trajectories.  In DreamerV3, the actor-critic trains entirely within imagination, and any systematic reward-prediction bias at $\\dt > 1$ is amplified through the closed actor-critic loop.\n\n\\subsection{The \\texorpdfstring{$\\dt$}{dt}-Embedding Dilemma}\n\\label{sec:embedding_dilemma}\n\nThe factorial results reveal a fundamental tension: removing the $\\dt$-embedding (008f) eliminates CIVO but at a $13\\times$ cost to reward prediction quality ($0.7469$ vs.\\ $0.0568$ MAE), as the world model cannot distinguish temporal scales.  Restricting imagination to $\\dt{=}1$ while retaining the trained embedding (008e\\_v3) avoids collapse in 2 of 4 seeds (50\\%), while the remaining two collapse via distinct mechanisms: Pathway~A (CIVO-driven, entropy decrease; s3, NVE $4.02\\times$) and Pathway~B (entropy-driven, entropy increase; s2, NVE $3.78\\times$; \\S\\ref{sec:f6}).  Neither approach alone provides a complete solution.\n\n\\subsection{Temporal Embedding Representation Analysis}\n\\label{sec:cosine_evolution}\n\nTo understand how the trained $\\dt$-embedding creates vulnerability, we analyze the cosine similarity between $e(\\dt{=}1)$ and $e(\\dt{=}2)$ across training (exp\\_065). Trained embeddings learn \\emph{near-opposite} representations: $\\cos(e_1, e_2) = {-}0.87$ to ${-}0.94$ at 25K steps across three configurations (Walker 008d\\_s3, Cheetah 010b\\_s0, Walker 059\\_s5), persisting at ${-}0.70$ to ${-}0.86$ at 75K steps. In contrast, frozen embeddings maintain near-zero similarity ($-0.15$ to $+0.07$, constant throughout training). The near-antipodal learned representations explain the large reward prediction gap (\\S\\ref{sec:f2}): $\\dt{=}2$ conditioning pushes the RSSM into a qualitatively different region of latent space, producing systematically biased predictions rather than minor perturbations.\n\n\\subsection{\\texorpdfstring{$\\dt$}{dt}-Embedding Differentiation Precedes Value Divergence}\n\\label{sec:cosine_temporal}\n\nThe preceding analysis established that trained $\\dt$-embeddings learn near-antipodal representations. Here we resolve the \\emph{temporal dynamics} of this differentiation across 11 experiments (${\\sim}$47 checkpoints), testing whether embedding differentiation is a consequence or precursor of CIVO.\n\n\\paragraph{Trained embeddings: monotonic relaxation.}\nAcross all trained configurations, $\\cos(e_1, e_2)$ starts near $-0.95$ within 10K steps and relaxes monotonically toward ${\\sim}{-}0.65$ (Table~\\ref{tab:cosine_evolution_ext}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity evolution between $e(\\dt{=}1)$ and $e(\\dt{=}2)$ for trained $\\dt$-embeddings. Relaxation is monotonic but never reaches zero; frozen embeddings remain constant near zero throughout training.}\n\\label{tab:cosine_evolution_ext}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Env} & \\textbf{Experiment} & \\textbf{10K} & \\textbf{25K} & \\textbf{65K} & \\textbf{75K} & \\textbf{302K} \\\\\n\\midrule\n\\multirow{2}{*}{Walker} & exp\\_066b (trained) & $-0.947$ & $-0.928$ & $-0.847$ & --- & --- \\\\\n & exp\\_045 (extension) & --- & --- & --- & --- & $-0.668$ \\\\\n\\midrule\nCheetah & exp\\_010b$\\to$048 & --- & $-0.904$ & --- & $-0.841$ & $-0.639$ \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Frozen controls:}} \\\\\nWalker & exp\\_057 (frozen) & \\multicolumn{5}{c}{$-0.150$ (constant, 25K--225K)} \\\\\nCheetah & exp\\_058 (frozen) & \\multicolumn{5}{c}{$+0.069$ (constant, 25K--225K)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nCross-seed consistency at 25K steps is high: mean $\\cos = -0.910 \\pm 0.028$ ($n{=}5$ Walker seeds), confirming the relaxation pattern is robust across random seeds. Variance increases with training ($-0.789 \\pm 0.076$ at 75K), reflecting seed-dependent relaxation rates.\n\n\\paragraph{Temporal precedence over CIVO.}\nExp\\_066b provides simultaneous cosine similarity and CIVO diagnostic data at 5K resolution (Table~\\ref{tab:cosine_vs_civo}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Cosine similarity relaxation and CIVO diagnostic for exp\\_066b. Embedding relaxation onset (${\\sim}$20K) precedes CIVO alert (55K, VE ratio $> 0.7$) by ${\\sim}$30--35K steps.}\n\\label{tab:cosine_vs_civo}\n\\footnotesize\n\\setlength{\\tabcolsep}{5pt}\n\\begin{tabular}{rccc}\n\\toprule\n\\textbf{Step} & $\\cos(e_1, e_2)$ & \\textbf{VE ratio} & \\textbf{CIVO alert} \\\\\n\\midrule\n10K & $-0.947$ & 0.012 & --- \\\\\n15K & $-0.948$ & 0.033 & --- \\\\\n25K & $-0.928$ & 0.193 & --- \\\\\n35K & $-0.904$ & 0.269 & --- \\\\\n45K & $-0.880$ & 0.358 & --- \\\\\n55K & $-0.861$ & 0.710 & \\textbf{Alert} \\\\\n65K & $-0.847$ & 0.724 & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nCosine relaxation begins at ${\\sim}$20K (cos transitions from $-0.948$ at 15K to $-0.928$ at 25K), while the VE ratio first exceeds 0.7 at 55K. The ${\\sim}$30--35K temporal lead establishes that embedding differentiation is an early training dynamic, not a consequence of CIVO-triggered feedback. The relaxation rate peaks at 25K--45K ($+0.024$/10K steps) before decelerating, consistent with the geometric intuition that large-angle adjustments in embedding space are cheaper early in training.\n\n\\paragraph{Embedding norms.}\nWalker and Cheetah exhibit qualitatively different norm dynamics. Walker $e(\\dt{=}1)$ norms grow from 0.23 to 0.50 ($2.2\\times$) while $e(\\dt{=}2)$ grows from 0.45 to 0.63 ($1.4\\times$)---both $\\dt$ values become more expressive over training. Cheetah norms remain nearly constant ($\\leq 1.04\\times$) despite continued cosine relaxation, indicating direction changes without magnitude change. Frozen embedding norms are an order of magnitude smaller (${\\sim}0.06$, constant).\n\n\\paragraph{Mechanistic interpretation.}\nThe temporal ordering---embedding differentiation (${\\sim}$20K) $\\to$ reward fidelity gap (${\\sim}$20K, \\S\\ref{sec:timeseries_fidelity}) $\\to$ value overestimation (${\\sim}$30K)---suggests a three-layer causal chain: the embedding first learns maximally differentiated representations that push $\\dt{=}1$ and $\\dt{=}2$ into opposite latent regions, the reward head then develops scale-dependent biases from these differentiated inputs, and the critic amplifies these biases through imagined rollout bootstrapping. The frozen embedding's constant near-zero cosine ($|\\cos| < 0.2$) prevents the first link in this chain, explaining why freezing eliminates CIVO despite maintaining identical forward-pass architecture (\\S\\ref{sec:f3}).\n\n\\subsection{Time-Series Fidelity--Value Analysis}\n\\label{sec:timeseries_fidelity}\n\nTo test the causal direction between reward fidelity degradation and value overestimation, we analyze exp\\_066 and exp\\_066b: two Walker Walk seeds (trained $\\dt$-embedding, fixed $\\dt{=}2$) evaluated at 12 dense checkpoints from 10K to 65K steps (Table~\\ref{tab:timeseries_fidelity}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Time-series fidelity and value metrics (exp\\_066, seed~0). SS = single-step MAE ratio ($\\dt{=}2$/$\\dt{=}1$); VE = value-to-eval ratio. Fidelity degradation (SS $>1.1\\times$ at 20K) precedes value overestimation onset (VE begins rising at ${\\sim}$30K) by ${\\sim}$10K steps. Seed~1 (exp\\_066b) confirms the pattern: fidelity gap onset ${\\sim}$15K $\\to$ VE onset ${\\sim}$24K (lead ${\\approx}$9K steps; VE peak ${=}0.72$).}\n\\label{tab:timeseries_fidelity}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{rcccccc}\n\\toprule\n\\textbf{Step} & \\textbf{SS ratio} & \\textbf{OL ratio} & \\textbf{VE ratio} & \\textbf{MAE$_{\\dt{=}1}$} & \\textbf{MAE$_{\\dt{=}2}$} & \\textbf{Return} \\\\\n\\midrule\n10K & 1.05 & 0.94 & 0.01 & 0.090 & 0.094 & 43.0 \\\\\n15K & 1.08 & 1.03 & 0.02 & 0.085 & 0.092 & 187.8 \\\\\n20K & 1.10 & 1.09 & 0.16 & 0.078 & 0.086 & 148.7 \\\\\n25K & 1.04 & 1.22 & 0.16 & 0.073 & 0.076 & 142.1 \\\\\n30K & 1.25 & 1.45 & 0.22 & 0.068 & 0.085 & 148.3 \\\\\n35K & 1.24 & 1.51 & 0.23 & 0.062 & 0.077 & 275.4 \\\\\n40K & 1.35 & 1.38 & \\textbf{1.59} & 0.058 & 0.078 & 202.3 \\\\\n45K & 1.40 & 1.38 & 0.36 & 0.055 & 0.077 & 107.5 \\\\\n50K & 1.47 & 1.56 & 0.62 & 0.052 & 0.076 & 178.4 \\\\\n55K & 1.37 & 1.52 & 0.62 & 0.050 & 0.069 & 60.8 \\\\\n60K & 1.61 & 1.35 & 1.40 & 0.049 & 0.079 & 125.3 \\\\\n65K & 1.68 & 1.38 & 1.40 & 0.047 & 0.079 & 94.4 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=0.75\\columnwidth]{figures/paper/fig_temporal_ordering.pdf}\n\\caption{Temporal ordering of fidelity degradation and value overestimation (exp\\_066, seed~0). \\textbf{Left axis}: single-step fidelity ratio (SS, blue) grows steadily from $1.05\\times$ to $1.68\\times$. \\textbf{Right axis}: value-to-eval ratio (VE, red) remains near zero until 40K, then spikes. The ${\\sim}$10K onset-to-onset lag supports the causal direction: fidelity gap $\\to$ value overestimation. Seed~1 (exp\\_066b) replicates the pattern with a ${\\sim}$9K temporal lead.}\n\\label{fig:temporal_ordering}\n\\end{figure}\n\nThe $\\dt{=}1$ prediction MAE decreases monotonically ($0.090 \\to 0.047$) as the world model improves, but $\\dt{=}2$ MAE plateaus at ${\\sim}0.08$. The growing fidelity gap is therefore not caused by $\\dt{=}2$ predictions worsening, but by the model selectively improving at $\\dt{=}1$ while failing to transfer that improvement to $\\dt{=}2$---consistent with the trained $\\dt$-embedding learning maximally differentiated representations (\\S\\ref{sec:cosine_evolution}) that prevent cross-scale generalization.\n\n\\textbf{Limitation.} These results are limited to two seeds ($n{=}2$). While both seeds show consistent temporal ordering (leads of ${\\approx}$10K and ${\\approx}$9K steps), additional seeds would strengthen the causal claim.\n\n\\subsection{Actor Entropy Is Not Diagnostic of CIVO}\n\\label{sec:entropy_not_diagnostic}\n\nTo test whether actor entropy can serve as an early collapse indicator, we compare entropy trajectories between collapsed and healthy configurations at matched training steps across five experiments (Table~\\ref{tab:entropy_contrast}).\n\n\\begin{table}[h]\n\\centering\n\\caption{Actor entropy comparison at matched time points. Collapsed and healthy configurations exhibit indistinguishable entropy at 55K steps (difference $= 0.03$ nats), despite collapsed runs showing severe return degradation.}\n\\label{tab:entropy_contrast}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Group} & \\textbf{Experiment} & \\textbf{5K} & \\textbf{25K} & \\textbf{45K} & \\textbf{55K} & \\textbf{Return} \\\\\n\\midrule\n\\multirow{2}{*}{Collapsed}\n & exp\\_008d (trained dt\\_emb) & 8.16 & $-1.86$ & $-4.58$ & $-4.88$ & ${\\sim}165$ \\\\\n & fixed\\_dt2 ($\\dt{=}2$) & 8.16 & $-3.02$ & $-5.06$ & $-5.17$ & ${\\sim}29$ \\\\\n\\midrule\n\\multirow{3}{*}{Healthy}\n & exp\\_008f (no dt\\_emb) & 8.11 & $-1.85$ & $-4.31$ & $-4.77$ & ${\\sim}460$ \\\\\n & exp\\_008a (unexposed) & 8.16 & $-4.88$ & $-5.20$ & $-5.21$ & ${\\sim}300$ \\\\\n & baseline\\_s1 ($\\dt{=}1$) & 8.10 & $-4.74$ & $-5.12$ & $-5.18$ & ${\\sim}950$ \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAt the last comparable step (55K): collapsed mean entropy $= -5.02$ (average of $-4.88$, $-5.17$); healthy mean entropy $= -5.05$ (average of $-4.77$, $-5.21$, $-5.18$); difference $= 0.03$ nats---statistically negligible. The hypothesis that collapsed runs exhibit anomalous entropy rise (actor confusion from delusional critic gradients) is not supported during the CIVO onset window.\n\nThe fixed\\_dt2 experiment demonstrates this most clearly: returns peak at ${\\sim}580$ (40K) then crash to 29 (72K), yet entropy remains stable at $-5.1$ throughout. The actor maintains a committed, low-entropy policy during the entire collapse---it does not become confused but rather remains confident while acting on incorrect value estimates. This is consistent with CIVO operating through critic value distortion rather than actor policy degradation. The late-stage entropy explosion documented in \\S\\ref{sec:civo_mechanism} ($+2.1$ nats/10K in EG~v4, onset ${\\sim}$35K steps after return collapse) occurs well beyond this window, confirming entropy rise as a lagging consequence rather than a concurrent or predictive signal.\n\n\\paragraph{Entropy descent speed.}\nEntropy descent rate correlates with temporal configuration complexity, not collapse fate. Simpler configurations (baseline $\\dt{=}1$, unexposed exp\\_008a) reach $-4.7$ by 25K, while configurations exposed to temporal variation (both collapsed and healthy) remain near $-2.0$ at 25K, reflecting the difficulty of policy commitment when training data spans multiple temporal scales.\n\n\\paragraph{Long-horizon entropy recovery.}\nThe baseline ($\\dt{=}1$) run extended to 505K steps shows entropy recovering from $-5.2$ to ${\\sim}{-}1.5$ between 115K and 295K steps, coinciding with continued performance improvement ($700 \\to 950$ return). This adaptive entropy increase rules out entropy rise as an inherently negative signal; the actor maintains ${\\sim}950$ return with entropy 3--4 nats above its minimum, indicating a healthy exploration--exploitation balance during extended training.\n\n\\subsection{Multiple Vulnerability Pathways}\n\\label{sec:pathways}\n\nThe two collapse patterns identified in \\S\\ref{sec:f6}---CIVO (Pathway~A, value-driven, entropy decreasing) and a tentative second mode (Pathway~B, eval-driven, entropy increasing)---have distinct diagnostic signatures. Pathway~B is observed in only two seeds (008e\\_v3\\_s2 and 038\\_s2); we present it as preliminary evidence that the trained $\\dt$-embedding's learned features may affect both reward prediction across temporal scales (Pathway~A) and the representation space in which the actor operates (Pathway~B), though additional data is needed to confirm this as a distinct mechanism.  This explains why $\\nve$ is sensitive but not perfectly specific: Pathway~B's late evaluation decline inflates $\\nve$ through the same arithmetic as CIVO, yielding the sole false positive ($3.78\\times$ for 008e\\_v3 s2).  Distinguishing the two requires examining the temporal profile and entropy direction of collapse (Figure~\\ref{fig:multiple_pathways}).\n\n\n\\subsection{Implications for Temporal Abstraction in World Models}\n\\label{sec:implications}\n\nCIVO identifies a structural incompatibility between flat temporal conditioning and imagination-based actor-critic training.  Hierarchical approaches (THICK \\citep{gumbsch2024thick}, Hieros \\citep{mattes2024hieros}, LS-Imagine \\citep{li2025lsimagine}) may avoid this by maintaining separate dynamics per temporal scale.  Whether CIVO transfers to transformer-based world models (DreamerV4; \\citealt{hafner2025dreamerv4}) depends on whether attention weights co-adapt with temporal embeddings analogously.  The CIVO mechanism requires three structural properties: (1) a temporal embedding that co-adapts with dynamics via gradient flow, (2) multi-step imagined rollouts used for critic training, and (3) a reward head that inherits latent biases from the shared representation.  Transformer-based world models that share these properties may exhibit analogous vulnerability; architectures that decouple temporal conditioning from the reward prediction pathway would not.\n\n\\subsection{Cross-Environment TCN Evaluation}\n\\label{sec:tcn_cross_env}\n\nTable~\\ref{tab:tcn_full} reports the full TCN evaluation across environments and noise magnitudes.\n\n\\begin{table}[h]\n\\centering\n\\caption{TCN results across environments and noise magnitudes. Prevention = peak NVE $< 1.5\\times$ (35K+).}\n\\label{tab:tcn_full}\n\\footnotesize\n\\setlength{\\tabcolsep}{4pt}\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Env} & $\\sigma$ & \\textbf{Seed} & \\textbf{NVE$_{\\max}$} & \\textbf{Prevented?} & \\textbf{Eval (\\%)} \\\\\n\\midrule\nWalker & 0.1 & s0 & 1.02 & \\checkmark$^*$ & 55\\% \\\\\nWalker & 0.2 & s0 & 0.91 & \\checkmark & 91\\% \\\\\nWalker & 0.2 & s1 & 0.64 & \\checkmark & 45\\% \\\\\nWalker & 0.2 & s2 & 2.11$^\\dagger$ & $\\times$ & ${\\sim}5\\%$ \\\\\n\\rowcolor{gray!15}\nWalker & 0.2 & s3 & 3.04$^\\P$ & $\\times$ & 11\\% \\\\\nWalker & 0.5 & s0 & 3.97 & $\\times$ & 27\\% \\\\\nWalker & 0.5 & s1 & 1.64 & $\\times$ & 41\\% \\\\\n\\midrule\nCheetah & 0.2 & s0 & 1.90 & $\\times$ & crashed \\\\\nCheetah & 0.5 & s0 & 10.67 & $\\times$ & 26\\% \\\\\nCheetah & 1.0 & s0 & $\\leq$0.30 & \\checkmark$^\\S$ & 15\\% \\\\\n\\midrule\nPickCube & 0.2 & s0 & 3.71 & $\\times$ & failing \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$Borderline: NVE${=}1.02\\times$ at 95K, below $1.5\\times$ threshold but above $1.0\\times$.\\\\\n$^\\dagger$NVE $= 2.11\\times$ at 95K, still rising; eval ${\\sim}5\\%$ of baseline.\\\\\n$^\\P$Late-onset CIVO: NVE declined to $0.67\\times$ at 95K before phase-transition-like spike to $3.04\\times$ at 105K; eval 349.6 at 95K $\\to$ 71.8 at 105K $\\to$ 104.5 at 215K.\\\\\n$^\\S$CIVO prevented (NVE${\\leq}0.30$); peak eval 116\\% baseline at 35K, declining to 15\\% by 215K via progressive policy erosion. See ``impossible dose'' discussion.\\par}\n\\end{table}\n\n\\paragraph{Cheetah Run $\\sigma{=}0.5$: transient spike with permanent eval damage.}\nCheetah $\\sigma{=}0.5$ exhibits a novel failure mode: a transient CIVO spike (NVE $= 10.67\\times$ at 55K) followed by NVE recovery ($< 0.3\\times$ by 95K), but permanent evaluation damage (26\\% of baseline). The value signal self-corrects while the policy does not recover, suggesting that CIVO-induced representational damage during the spike persists within the observation window even when the critic subsequently recalibrates. This trajectory parallels the obs-decoder SGS seed~3 pattern (\\S\\ref{sec:seed_divergence}), where partial policy recovery coexists with persistent critic damage.\n\n\\paragraph{Cheetah Run $\\sigma{=}0.2$: insufficient dose.}\nAt $\\sigma{=}0.2$, Cheetah reaches NVE $= 1.9\\times$ at 55K---exceeding the $1.5\\times$ threshold---consistent with Cheetah's higher baseline CIVO severity ($8$--$108\\times$ vs.\\ Walker's $2$--$6\\times$). The noise magnitude that suffices for Walker is inadequate for Cheetah, but increasing $\\sigma$ to 0.5 trades CIVO prevention for a different failure mode rather than achieving mitigation.\n\n\\paragraph{PickCube-v1 $\\sigma{=}0.2$: manipulation failure.}\nPickCube reaches NVE $= 3.71\\times$ at 52.5K with $\\sigma{=}0.2$, indicating that TCN provides no protection in manipulation tasks. The combination of contact-gated dynamics and temporal conditioning may amplify the fidelity gap beyond what representation-level noise can attenuate.\n\n\\paragraph{Dose-response analysis.}\nWe observe $\\sigma{=}0.2$ as a local optimum on Walker Walk, achieving complete CIVO suppression in 2 of 4 seeds. Seeds~2 and~3 both fail but via distinct CIVO onset dynamics: seed~2 shows gradual escalation (NVE $= 2.11\\times$ at 95K, still rising, eval ${\\sim}5\\%$), while seed~3 exhibits a phase-transition-like onset---NVE declined to $0.67\\times$ at 95K before spiking to $3.04\\times$ at 105K (eval 349.6 $\\to$ 71.8 in 10K steps). When TCN fails to prevent CIVO onset, the resulting trajectory qualitatively resembles untreated CIVO in its terminal outcome---runaway NVE and eval collapse. The two failure modes (gradual escalation vs.\\ sudden onset after apparent suppression) reinforce that TCN operates as a binary gate on CIVO onset rather than providing graded attenuation. Below the optimum, we observe $\\sigma{=}0.1$ as insufficient (NVE $= 1.02\\times$---borderline, eval 55\\%); above it, $\\sigma{=}0.5$ overdoses (oscillatory CIVO, eval $\\leq 41\\%$). Cross-seed variance at $\\sigma{=}0.2$ (eval 5--91\\%) exceeds the cross-dose difference by a wide margin, reinforcing that seed effects dominate dose effects. TCN is the only tested intervention achieving complete CIVO suppression in any configuration, but its high seed sensitivity and failure to transfer across environments position it as a \\emph{diagnostic probe}---identifying the representation level as the relevant intervention target---rather than a deployable mitigation.\n\n\\paragraph{Cheetah Run ``impossible dose'' dilemma.}\nExp\\_030c (224K steps) reveals a qualitatively different dose-response on Cheetah. At $\\sigma{=}1.0$, CIVO is eliminated (NVE${\\leq}0.30$ throughout) and initial learning is \\emph{unimpaired}: peak eval reaches 372 at 35K (116\\% of baseline), demonstrating that $\\sigma{=}1.0$ noise does not prevent policy acquisition. However, cumulative actor gradient interference produces progressive policy erosion---eval declines from 372 to 47 by 215K (15\\% of baseline)---while the critic remains well-calibrated (value\\_mean${=}12.4$, NVE${=}0.26$ at 215K). This establishes that \\emph{policy degradation $\\neq$ value corruption}: accurate value signals are insufficient when the actor cannot optimize effectively in noise-perturbed imagination.\n\nThis ``correct values, failed policy'' pattern provides indirect evidence that CIVO is mechanistically distinct from standard overestimation. Double Q-learning and ensemble methods address critic estimation error, but at $\\sigma{=}1.0$ the critic is accurate and the policy still collapses---a failure mode orthogonal to what these countermeasures target. The impossible dose dilemma scales with environment complexity: Cheetah's baseline CIVO severity ($8$--$108\\times$ NVE) requires $\\sigma \\geq 1.0$ to suppress, but this exceeds the actor's gradient signal-to-noise tolerance. On Walker, a narrow effective window exists around $\\sigma{=}0.2$; on Cheetah, the effective dose ($\\sigma \\geq 1.0$) exceeds the tolerable dose, and environments with higher CIVO severity will systematically lack a viable dose window.\n\n\\section{DreamerV3 Hyperparameters}\n\\label{sec:hyperparameters}\n\nTable~\\ref{tab:hyperparams} lists the DreamerV3 hyperparameters used across all experiments. Unless otherwise noted, we use the default DreamerV3 configuration for continuous-control tasks (\\texttt{dmc\\_proprio}).\n\n\\begin{table}[ht]\n\\centering\n\\caption{DreamerV3 hyperparameters for all experiments. Modifications from defaults are marked with $\\diamond$.}\n\\label{tab:hyperparams}\n\\small\n\\begin{tabular}{ll}\n\\toprule\n\\textbf{Parameter} & \\textbf{Value} \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{World Model}} \\\\\nRSSM discrete states & 32 classes $\\times$ 32 categories \\\\\nRSSM stochastic dim & 32 \\\\\nRSSM deterministic dim & 512 \\\\\nMLP hidden size & 512 \\\\\nMLP layers & 2 \\\\\nActivation & SiLU \\\\\nNormalization & LayerNorm \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Training}} \\\\\nBatch size & 16 sequences $\\times$ 64 steps \\\\\nLearning rate & $3 \\times 10^{-4}$ (Adam, $\\epsilon{=}10^{-8}$) \\\\\nSequence length & 64 \\\\\nTraining ratio & 512 \\\\\nFree nats & 1.0 \\\\\nKL balance ($\\alpha$) & 0.8 \\\\\nDiscount ($\\gamma$) & 0.997 \\\\\n$\\lambda$-return & 0.95 \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Policy}} \\\\\nImagination horizon$^\\diamond$ & 8 or 15 (see Table~\\ref{tab:complete_results}) \\\\\nActor entropy scale & $3 \\times 10^{-4}$ \\\\\nActor gradient & Reinforce + dynamics backprop \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Temporal Abstraction}$^\\diamond$} \\\\\nGate enabled & True (all non-baseline) \\\\\nGate fixed $\\dt$ & 1 or 2 (per config) \\\\\nSubsample max $\\dt$ & 1 (OFF) or 2 (ON) \\\\\n$\\dt$-embedding dim & 32 \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Environment}} \\\\\nAction repeat & 2 (Walker Walk, Cheetah Run) \\\\\nObservation & Proprioceptive (no pixels) \\\\\nTotal environment steps & 105K \\\\\nEvaluation frequency & Every 10K steps \\\\\nEvaluation episodes & 10 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Online CIVO Detector Details}\n\\label{sec:detector_appendix}\n\nThis appendix provides the full algorithm specification and validation results for the online CIVO detector described in \\S\\ref{sec:detector}.\n\n\\subsection{Algorithm Specification}\n\n\nThe four conditions capture complementary signals: (1)~\\emph{Magnitude} ($r_t \\geq 0.49$) confirms that the value-to-evaluation ratio has reached a level indicative of overestimation; (2)~\\emph{Velocity} ($\\Delta r_t > 0.1$) rules out slow drift or plateau behavior; (3)~\\emph{Acceleration} ($\\Delta r_t > \\Delta r_{t-1}$, both $> 0.1$) filters oscillatory paths; (4)~\\emph{Evaluation decline} ($\\geq 2$ of 3 recent checkpoints decline) confirms that overestimation coincides with actual performance degradation. A full comparison of window sizes appears in \\S\\ref{sec:appendix_sensitivity}.\n\nSensitivity analysis over $\\tau_\\text{mag} \\in [0.30, 0.70]$ confirms that $\\tau_\\text{mag} = 0.49$ maximizes Youden's $J = 0.714$; raising the threshold to $0.50$ loses one true positive (seed~3 triggers at $r_t = 0.497$) with no reduction in false positives. The velocity threshold $\\tau_\\text{vel} = 0.1$ is stable across $[0.05, 0.18]$ (TPR remains $5/5$).\n\n\\subsection{Validation Results}\n\n\\begin{table}[ht]\n\\centering\n\\caption{Retrospective CIVO detector validation ($n{=}14$). Detection type: ``predictive'' = alert precedes 20\\% eval decline; ``reactive'' = alert follows decline onset.}\n\\label{tab:detector-validation}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llccccc}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{Verdict} & \\textbf{Trigger} & \\textbf{Type} & \\textbf{Peak Eval} & $r_\\text{ve}$ \\\\\n\\midrule\n008d s0 & trained $\\dt$-emb & TP & 45K & predict. & 167 & 0.69 \\\\\n010b & trained $\\dt$-emb (Cheetah) & TP & 65K & reactive & 322 & 3.18 \\\\\n008d s3 & trained $\\dt$-emb & TP & 45K & predict. & 452 & 0.50 \\\\\n008d s4 & trained $\\dt$-emb & TP & 105K & reactive & 383 & 3.03 \\\\\n010b s0 & trained $\\dt$-emb (Cheetah) & TP & 95K & reactive & 248 & 6.34 \\\\\n\\midrule\n008f s3 & no $\\dt$-emb & TN & -- & -- & 594 & -- \\\\\n009b s2 & trained $\\dt$-emb (self-corr.) & TN & -- & -- & 279 & -- \\\\\nbaseline s1 & vanilla & TN & -- & -- & 970 & -- \\\\\n009d s0 & vanilla & TN & -- & -- & 951 & -- \\\\\n009d s1 & vanilla & TN & -- & -- & 920 & -- \\\\\n019b & trained $\\dt$-emb (PickCube) & TN & -- & -- & 26.6 & -- \\\\\n\\midrule\n009c s2 & no $\\dt$-emb & FP & 105K & reactive & 359 & 0.75 \\\\\n009a s2 & vanilla & FP & 85K & predict. & 967 & 0.73 \\\\\n\\midrule\n009c s3 & no $\\dt$-emb & TN & -- & -- & 457 & -- \\\\\n\\midrule\n\\multicolumn{7}{l}{TPR = 5/5 (1.00), \\quad FPR = 2/9 (0.22)} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe detector identifies all five CIVO-positive runs (TPR = 5/5). Two are detected predictively (008d seeds~0 and~3, both at 45K). Two false positives occur among nine negative cases (FPR = 2/9, precision 71\\%, F$_1$ = 0.83). Run 009c develops genuine late-stage value overestimation unrelated to CIVO; run 009a triggers during a transient eval dip at 85K before recovery to 966. Early alerts (before 70K) carry higher diagnostic confidence.\n\n\\subsection{Cross-Simulator Specificity (PickCube)}\n\nExp\\_019b applies the CIVO-trigger configuration to PickCube-v1 in ManiSkill3, a dense-reward manipulation task. The V/E ratio exhibits an oscillatory pattern rather than monotonic divergence: it spikes to $r_t = 5.66$ at 52.5K, then deflates to 1.38 by 72.5K. This trajectory prevents the acceleration condition from co-occurring with evaluation decline at any single checkpoint. Across all 14 checkpoints through 132.5K, the detector correctly remains silent (TN), confirming that the acceleration filter distinguishes transient spikes from CIVO's sustained monotonic divergence. A frozen-embedding control (exp\\_054) confirms this classification: frozen PickCube-v1 exhibits a comparable burst (peak $8.81\\times$ at 62.5K) that resolves within a single evaluation cycle ($0.55\\times$ at 72.5K), establishing environment-specific origin independent of $\\dt$-embedding training.\n\n\\subsection{Detector Limitations}\n\nFour constraints bound the current detector. First, the three-checkpoint window cannot distinguish transient dips from sustained collapse. Second, the acceleration condition assumes monotonically increasing overestimation during onset. Third, the detector identifies a \\emph{pattern} rather than a \\emph{mechanism}: run 009c shows that non-CIVO pathologies produce the same signature. Fourth, threshold values were calibrated on fourteen runs across three environments; generalization to different reward scales requires further validation.\n\n\\section{Dual-Critic Mechanism Ablation}\n\\label{sec:dual_critic_appendix}\n\n\\subsection{\\texorpdfstring{$2{\\times}2$}{2x2} Factorial Design}\n\nWe ablate the critic architecture in a $2{\\times}2$ factorial: \\{single, dual\\} $\\times$ \\{narrow (${\\sim}1.2$M), wide (${\\sim}2.4$M)\\} parameters. Table~\\ref{tab:dual_critic_full} reports all configurations.\n\n\\begin{table}[ht]\n\\centering\n\\caption{Dual-critic $2{\\times}2$ factorial results. Walker Walk unless noted.}\n\\label{tab:dual_critic_full}\n\\footnotesize\n\\setlength{\\tabcolsep}{3pt}\n\\begin{tabular}{llcccl}\n\\toprule\n\\textbf{Exp} & \\textbf{Config} & \\textbf{Params} & \\textbf{NVE} & \\textbf{Eval} & \\textbf{Outcome} \\\\\n\\midrule\n008d & Single narrow & 1.2M & 4.12$\\times$ & 82.8 & Collapse \\\\\n033 & Wide single & 2.4M & 4.75$\\times$ & 407.9 & CIVO $\\to$ self-repair \\\\\n035 s0 & Narrow dual (min) & 1.2M & 2.75$\\times$ & 697.8 & CIVO $\\to$ recovery \\\\\n039 s1 & Narrow dual (min) & 1.2M & 2.19$\\times$ & 592.7 & CIVO $\\to$ recovery \\\\\n032 s0 & Wide dual (min) & 2.4M & $\\leq$1.1$\\times$ & 739.7 & CIVO prevented \\\\\n032b s1 & Wide dual (min) & 2.4M & 1.4$\\times$ & 551.8 & CIVO prevented \\\\\n038 s2 & Wide dual (min) & 2.4M & $\\leq$0.3$\\times$ & 120.9$^*$ & Non-CIVO collapse \\\\\n\\midrule\n\\multicolumn{6}{l}{\\textit{Cross-environment}} \\\\\n034 & Cheetah dual & 2.4M & 1.75$\\times$ & 97.5 & Partial recovery (31\\%) \\\\\n037 & Cheetah wide single & 2.4M & 3.60$\\times$ & 146.1 & CIVO $\\to$ self-repair \\\\\n036 & PickCube dual & 2.4M & 2.3$\\times$ & 27.7 & Transient CIVO \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{1pt}\n{\\raggedright\\footnotesize $^*$CIVO prevented (NVE $\\leq 0.3\\times$) but non-CIVO eval collapse: eval peaked at 354 (155K), then declined to 120.9 (224K) with actor entropy increasing from $-3.59$ to $-0.45$.\\par}\n\\end{table}\n\n\\subsection{Critic Convergence (\\texorpdfstring{$v_1 \\approx v_2$}{v1 ≈ v2})}\n\nAcross all dual-critic configurations and environments, the two critics converge to near-identical value functions. On Walker Walk, Pearson $\\rho > 0.999$ between $v_1$ and $v_2$ outputs; on Cheetah Run and PickCube-v1, the gap is $< 0.2$ (exact match within numerical precision). Per-sample pessimism $\\mathbb{E}[\\max(v_1, v_2) - \\min(v_1, v_2)]$ is 3--4\\% of the theoretical bound for independent critics.\n\nThis convergence occurs because both critics train on the same RSSM-generated latent features. Unlike model-free Double Q-learning, where each critic sees different mini-batches of real transitions and develops distinct function approximation errors, pure-imagination critics share identical inputs from the world model. The min operation therefore cannot provide the pessimism bias that makes Double Q effective in model-free settings.\n\n\\subsection{Recovery vs.\\ Prevention Mechanism}\n\nThe $2{\\times}2$ factorial reveals two separable dimensions:\n\n\\paragraph{Recovery (min-dominated).} The min operation is the primary factor enabling recovery from CIVO. Both narrow dual-critic seeds experience CIVO and recover fully: exp\\_035 (s0, $\\nve = 2.75\\times$, eval $33.8 \\to 697.8$, recovery ratio $20.6\\times$) and exp\\_039 (s1, $\\nve = 2.19\\times$, eval $35.9 \\to 592.7$, recovery ratio $16.5\\times$). Both outperform wide single-critic (exp\\_033, 2.4M params, eval 407.9) despite $2\\times$ fewer parameters. The min operation reduces both peak CIVO severity (2.19--2.75$\\times$ vs.\\ 4.75$\\times$ for the comparable single-critic) and enables consistent full recovery across seeds.\n\n\\paragraph{Prevention (min $+$ capacity synergy).} CIVO prevention (NVE remaining below the $1.5\\times$ threshold) requires both the min operation and increased capacity: only the wide dual-critic (exp\\_032, 3 seeds) achieves this. The mechanism for this synergy is an open question; we hypothesize that increased capacity improves value calibration quality while the min operation constrains the overestimation feedback loop during early training when the two critics briefly diverge.\n\n\\paragraph{Cross-environment limits.} On Cheetah Run, the wide dual-critic (exp\\_034) reduces NVE from $8.27\\times$ (untreated baseline) to $1.75\\times$ ($\\geq 4\\times$ reduction) but cannot prevent CIVO onset, and recovery reaches only 31\\% of the pre-CIVO peak. This confirms that the min $+$ capacity synergy has environment-dependent limits: in high-CIVO-severity environments, architecture-level interventions attenuate but do not eliminate the pathology.\n",
    "structuredPatch": [
      {
        "oldStart": 143,
        "oldLines": 7,
        "newStart": 143,
        "newLines": 7,
        "lines": [
          " ",
          " \\begin{table}[ht]",
          " \\centering",
          "-\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. IRD = Imagination-Reality Divergence; trans.\\ = transient CIVO with self-correction.}",
          "+\\caption{Per-experiment NVE values (35K+ steps) and ground truth labels. $+$ = positive (CIVO), $-$ = negative. Trans.\\ = transient CIVO with self-correction.}",
          " \\label{tab:nve_raw}",
          " \\small",
          " \\begin{tabular}{@{}lrccc@{}}"
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

_source line 57_

<details open><summary>🔧 Tool call — Edit · `toolu_012XHRFbPG4eQkX6gF36pS7q`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_9/projects/event-gated-adaptive-horizon/docs/paper/sections/appendix.tex",
  "old_string": "006          & 4.83 & sustained CIVO & $+$ & $+$ \\\\\n059          & 4.72 & self-correcting CIVO & $-$ & $+$ \\\\\n008d         & 4.12 & sustained CIVO & $+$ & $+$ \\\\\n008e\\_v3\\_s3 & 4.02 & CIVO           & $+$ & $+$ \\\\\n008e\\_v3\\_s2 & 3.78 & IRD (non-CIVO) & $-$ & $-$ \\\\\n009b         & 1.62 & transient CIVO & $-$ & $+$ \\\\\n001          & 1.00 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s4 & 0.99 & non-CIVO       & $-$ & $-$ \\\\\n008f         & 0.97 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s1 & 0.94 & non-CIVO       & $-$ & $-$ \\\\\n008a         & 0.93 & non-CIVO       & $-$ & $-$ \\\\",
  "new_string": "006          & 4.83 & sustained CIVO & $+$ & $+$ \\\\\n059          & 4.72 & self-correcting CIVO & $-$ & $+$ \\\\\n008d         & 4.12 & sustained CIVO & $+$ & $+$ \\\\\n009b         & 1.62 & transient CIVO & $-$ & $+$ \\\\\n001          & 1.00 & non-CIVO       & $-$ & $-$ \\\\\n008f         & 0.97 & non-CIVO       & $-$ & $-$ \\\\\n008a         & 0.93 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s0 & 0.60 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s1 & 0.60 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s5 & 0.60 & non-CIVO       & $-$ & $-$ \\\\\n008e\\_v3\\_s2 & 0.50 & non-CIVO       & $-$ & $-$ \\\\"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a08170ba-d0ed-49ec-918a-a297ecfee54f",
  "uuid": "f5258bfb-5865-47ea-bfe9-49433fb4efce",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NuynpjdTHBQtThBv5dSMDX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 320,
      "cache_read_input_tokens": 95675,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 320
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
