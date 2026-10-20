# Research conversation: Search for all LaTeX table definitions in the paper at /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_re

**Exposure Bias Collapses Auxiliary Attention Losses in Multi-Turn Dialogue (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 51
- **Recorded user turns:** 1
- **Tool calls:** 22
- **Original source:** `logs/chats/exported-trajectories/account-1/agent-abd64e66887e6e7f7.jsonl`
- **Structured JSON:** [`800ae7dfaf8b735ef9b1.json`](../../sessions/80/800ae7dfaf8b735ef9b1.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

51 recorded events

### User

_source line 1 · 2026-05-25T20:12:53.423Z_

Search for all LaTeX table definitions in the paper at /home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/docs/paper/

1. Find where Table 1 (tab:five-way) is defined - read the full table data
2. Find where Table tab:gradient-crossmodel is defined
3. Find any other tables referenced in the main text
4. Read any appendix files that contain data referenced from the main text sections (especially appendix-hyper for hyperparameters, appendix-stats for p-values, appendix-ir for instruction retention)

Report all numbers found in these tables verbatim.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "8e87cca6-70d3-4673-9fb6-93c54604281d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-25T20:12:53.425Z_

```json
{
  "parentUuid": "8e87cca6-70d3-4673-9fb6-93c54604281d",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "attachment": {
    "type": "deferred_tools_delta",
    "addedNames": [
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterWorktree",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__append_idea",
      "mcp__agent-ml-research__compare_wandb_runs",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__fetch_wandb_run_history",
      "mcp__agent-ml-research__get_best_wandb_run",
      "mcp__agent-ml-research__list_wandb_runs",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__update_registry"
    ],
    "addedLines": [
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterWorktree",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__append_idea",
      "mcp__agent-ml-research__compare_wandb_runs",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__fetch_wandb_run_history",
      "mcp__agent-ml-research__get_best_wandb_run",
      "mcp__agent-ml-research__list_wandb_runs",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__update_registry"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "2a3c00d8-2b49-4cd7-b9b7-de43ce454e28",
  "timestamp": "2026-05-25T20:12:53.425Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Assistant

_source line 3 · 2026-05-25T20:12:56.237Z_



I'll search for all LaTeX table definitions in the paper directory.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2a3c00d8-2b49-4cd7-b9b7-de43ce454e28",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu2TSP8pMtDrwo7Atgt",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "0bbfde5b-e9fb-467b-b79a-fa5db38cfc6c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011e9P1k5QGhxArXeUhz57Zx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 7069,
      "cache_read_input_tokens": 9326,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7069,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 9,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 4 · 2026-05-25T20:12:57.428Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01EqoCRNfFZJmyJqvyTBEAwm`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0bbfde5b-e9fb-467b-b79a-fa5db38cfc6c",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu2TSP8pMtDrwo7Atgt",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "bcf28126-d7d4-4862-8a9f-696990c0de02",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011e9P1k5QGhxArXeUhz57Zx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 7069,
      "cache_read_input_tokens": 9326,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7069,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 9,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 5 · 2026-05-25T20:12:57.445Z_

<details><summary>↩ Tool result · `toolu_01EqoCRNfFZJmyJqvyTBEAwm`</summary>

```text
docs/paper/background.tex
docs/paper/related_work.tex
docs/paper/experiments.tex
docs/paper/method.tex
docs/paper/introduction.tex
docs/paper/analysis.tex
docs/paper/discussion.tex
docs/paper/conclusion.tex
docs/paper/limitations.tex
docs/paper/abstract.tex
docs/paper/sections/abstract.tex
docs/paper/sections/analysis.tex
docs/paper/sections/appendix.tex
docs/paper/sections/conclusion.tex
docs/paper/sections/discussion.tex
docs/paper/sections/experiments.tex
docs/paper/sections/introduction.tex
docs/paper/sections/limitations.tex
docs/paper/sections/method.tex
docs/paper/sections/related_work.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bcf28126-d7d4-4862-8a9f-696990c0de02",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "d3b77d4e-0358-4d9a-ab95-18260fa0e18b",
  "sourceToolAssistantUUID": "bcf28126-d7d4-4862-8a9f-696990c0de02",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 6 · 2026-05-25T20:12:58.473Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01E8oHRege2ChAQ7VPyxiuNZ`</summary>

```json
{
  "pattern": "\\\\begin\\{table",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/docs/paper",
  "output_mode": "files_with_matches"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d3b77d4e-0358-4d9a-ab95-18260fa0e18b",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu2TSP8pMtDrwo7Atgt",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "f20be360-fb73-4974-bd6c-6d5141f381d4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011e9P1k5QGhxArXeUhz57Zx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 7069,
      "cache_read_input_tokens": 9326,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7069,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 9,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 7 · 2026-05-25T20:12:58.494Z_

<details><summary>↩ Tool result · `toolu_01E8oHRege2ChAQ7VPyxiuNZ`</summary>

```text
Found 4 files
docs/paper/sections/related_work.tex
docs/paper/sections/appendix.tex
docs/paper/analysis.tex
docs/paper/experiments.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f20be360-fb73-4974-bd6c-6d5141f381d4",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "f74c5a43-f58e-4c0d-a8d5-0092068b1320",
  "sourceToolAssistantUUID": "f20be360-fb73-4974-bd6c-6d5141f381d4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 8 · 2026-05-25T20:12:59.139Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01LzGWpb9NWG3Vo2ZwgBt8GM`</summary>

```json
{
  "pattern": "\\\\label\\{tab:",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/docs/paper",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f74c5a43-f58e-4c0d-a8d5-0092068b1320",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu2TSP8pMtDrwo7Atgt",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "9e7a6036-88cd-49ca-8ff1-dd3c63c8d784",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011e9P1k5QGhxArXeUhz57Zx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 7069,
      "cache_read_input_tokens": 9326,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7069,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 9,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 9 · 2026-05-25T20:12:59.158Z_

<details><summary>↩ Tool result · `toolu_01LzGWpb9NWG3Vo2ZwgBt8GM`</summary>

```text
docs/paper/analysis.tex:13:\label{tab:grad-conflict}
docs/paper/experiments.tex:24:\label{tab:four-way}
docs/paper/sections/related_work.tex:16:\label{tab:five-way}
docs/paper/sections/appendix.tex:8:\label{tab:hyperparams}
docs/paper/sections/appendix.tex:50:\label{tab:loss-iterations}
docs/paper/sections/appendix.tex:90:\label{tab:ir-results}
docs/paper/sections/appendix.tex:118:\label{tab:n5-ar}
docs/paper/sections/appendix.tex:148:\label{tab:stat-tests}
docs/paper/sections/appendix.tex:182:\label{tab:llama-full}
docs/paper/sections/appendix.tex:222:\label{tab:gradient-crossmodel}
docs/paper/sections/appendix.tex:311:\label{tab:steering-full}
docs/paper/sections/appendix.tex:345:\label{tab:gate-profile}
docs/paper/sections/appendix.tex:390:\label{tab:cost}
docs/paper/sections/appendix.tex:425:\label{tab:examples}
docs/paper/sections/appendix.tex:473:\label{tab:data-stats}
docs/paper/sections/appendix.tex:533:\label{tab:kl-perhead}
docs/paper/sections/appendix.tex:558:\label{tab:gar-robust}
docs/paper/sections/appendix.tex:582:\label{tab:mmlu}
docs/paper/sections/appendix.tex:610:\label{tab:1.5b-steering}
docs/paper/sections/appendix.tex:799:\label{tab:llama-ss-steering}
docs/paper/sections/appendix.tex:821:\label{tab:llama-vs-qwen-ss}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9e7a6036-88cd-49ca-8ff1-dd3c63c8d784",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "13188fbc-d0e7-4e18-9707-f94dce501654",
  "sourceToolAssistantUUID": "9e7a6036-88cd-49ca-8ff1-dd3c63c8d784",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 10 · 2026-05-25T20:13:02.034Z_

Now let me read all the table definitions. I'll start with the main text tables and appendix.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "13188fbc-d0e7-4e18-9707-f94dce501654",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu2t9BdRDsGPPbzcJ1y",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "57201865-e27c-4b93-b09c-848f99e9fbb2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JbGm443x5f2scVH8GiAZAM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1959,
      "cache_read_input_tokens": 16395,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1959,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-25T20:13:04.155Z_

<details open><summary>🔧 Tool call — Read · `toolu_01UhVkxHwsqVeTwTyG5TDX1J`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/docs/paper/sections/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "57201865-e27c-4b93-b09c-848f99e9fbb2",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu2t9BdRDsGPPbzcJ1y",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "dab6d070-5ccc-49d0-9e4e-5098f5181466",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JbGm443x5f2scVH8GiAZAM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1959,
      "cache_read_input_tokens": 16395,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1959,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-25T20:13:04.160Z_

<details><summary>↩ Tool result · `toolu_01UhVkxHwsqVeTwTyG5TDX1J`</summary>

```text
1	\section{Related Work}\label{sec:related}
2	
3	\paragraph{Multi-turn dialogue and attention decay.}
4	Multi-turn coherence has been a persistent challenge from early dialogue systems \citep{li2016persona,roller2021recipes,zhang2020dialogpt} through modern long-context models \citep{xu2022goldfish}, with benchmarks such as MT-Bench \citep{zheng2024judging} and MT-Bench-101 \citep{bai2024mtbench101} continuing to expose quality gaps at later turns \citep{laban2025lost,liu2026intent}. Most relevant to our work, \citet{dongre2026attention} defined the Goal Accessibility Ratio (GAR) and showed that attention to goal tokens decays 27--48\% across 12 models while residual probes retain goal information (AUC\,=\,0.98). We observe a steeper 70.8\% decline on Qwen-2.5-7B. \citet{li2024measuring} independently quantified instruction instability and proposed split-softmax as an inference-time remedy. Our work differs in scope: we diagnose \emph{why} training-time attention optimization fails to transfer to inference, and provide the first training-time mitigation.
5	
6	\paragraph{Gating and attention manipulation.}
7	Residual gating spans highway networks \citep{srivastava2015highway}, ReZero \citep{bachlechner2021rezero}, layer pruning \citep{gromov2024unreasonable,fan2020layerdrop}, and adaptive depth \citep{schuster2022calm,raposo2024mixture}. Most relevant is Gated Attention \citep{qiu2025gated}: per-head sigmoid gates achieving MMLU \citep{hendrycks2021measuring} $+$2.03 at 15B scale; ThreadGate differs in conditioning on turn position. On the analysis side, head specialization \citep{clark2019what,voita2019analyzing,kovaleva2019revealing}, positional bias calibration \citep{liu2024lost,xiao2024streaming}, and attention steering (PASTA; \citealp{zhang2024tell}) address inference behavior; our $\beta$-steering serves a diagnostic role. PCGrad \citep{yu2020pcgrad} and CAGrad \citep{liu2021cagrad} treat gradient conflict as the root cause; we show direction conflict is a symptom, not the primary cause.
8	
9	\paragraph{Exposure bias in sequence models.}
10	Teacher forcing creates a distributional mismatch between training and inference \citep{wiseman2016sequence,arora2022exposure}. Scheduled sampling \citep{bengio2015scheduled} introduced curriculum-based mixing; subsequent work proposed sequence-level objectives \citep{ranzato2016sequence}, adversarial regularization \citep{lamb2016professor}, self-recovery analysis \citep{he2019exposure}, bridging strategies for neural machine translation (NMT; \citealp{zhang2019bridging}), and search-based training \citep{leblond2018searnn}. \citet{mihaylova2019scheduled} extended scheduled sampling to transformers for single-turn NMT. \citet{dou2019attention} proposed attention forcing (supervising cross-attention during NMT), and \citet{dou2022parallel} extended it with KL-divergence switching. Our work differs: (i)~time-scheduled sampling (linearly increasing $\rho$), not data-dependent; (ii)~self-attention in multi-turn dialogue, not cross-attention in NMT; (iii)~auxiliary attention objectives, not primary translation loss. No prior work examines exposure bias on \emph{auxiliary} attention objectives or provides multi-turn transformer mitigation; we fill both gaps.
11	
12	\begin{table*}[!t]
13	\centering
14	\small
15	\caption{Five-way comparison on Qwen-2.5-7B-Instruct. TF evaluation uses IID UltraChat and 50 held-out conversations; AR evaluation uses $N$\,=\,50 held-out conversations (mean 3.6 user turns). All fine-tuned variants converge under TF ($\leq$2\,pp spread); the 8--17$\times$ TF-AR gap persists across all configurations. $\bar{g}\!\pm\!\sigma_g$: learned gate mean and std across 28 layers (LoRA-only has no gates). GAR-O = GAR-ours; GAR-D = GAR-Dongre \citep{dongre2026attention}.}
16	\label{tab:five-way}
17	\begin{tabular}{l ccc ccc cc c}
18	\toprule
19	& \multicolumn{3}{c}{\textbf{IID (TF)}} & \multicolumn{3}{c}{\textbf{Held-out (TF)}} & \multicolumn{2}{c}{\textbf{AR ($N$\,=\,50)}} & \\
20	\cmidrule(lr){2-4} \cmidrule(lr){5-7} \cmidrule(lr){8-9}
21	\textbf{Configuration} & GAR-O & GAR-D & PPL & GAR-O & GAR-D & PPL & GAR-O & 95\% CI & $\bar{g}\!\pm\!\sigma_g$ \\
22	\midrule
23	\multicolumn{10}{l}{\emph{Baseline}} \\
24	Base              & 0.01 & 0.00 & 4.23 & 0.01 & 0.00 & 4.34 & 0.019 & {\scriptsize[.014,\,.024]} & --- \\
25	\midrule
26	\multicolumn{10}{l}{\emph{Gated variants}} \\
27	ThreadGate        & 0.50 & \textbf{0.02} & 2.78 & 0.50 & \textbf{0.02} & 2.78 & \textbf{0.064} & {\scriptsize[.041,\,.091]} & .93\,{\scriptsize$\pm$\,.05} \\
28	\;+\,PCGrad       & 0.50 & 0.01 & 2.78 & 0.50 & 0.01 & 2.78 & 0.030 & {\scriptsize[.023,\,.038]} & --- \\
29	Uniform Gate      & 0.49 & 0.01 & 2.78 & \textbf{0.51} & 0.01 & 2.78 & 0.033 & {\scriptsize[.025,\,.043]} & .96\,{\scriptsize$\pm$\,.05} \\
30	\midrule
31	\multicolumn{10}{l}{\emph{Ungated}} \\
32	LoRA-only         & 0.50 & 0.01 & 2.78 & 0.50 & 0.01 & 2.78 & 0.037 & {\scriptsize[.027,\,.050]} & 1.00 \\
33	\bottomrule
34	\end{tabular}
35	\end{table*}
36	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dab6d070-5ccc-49d0-9e4e-5098f5181466",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "951c8e60-4d1e-4a58-8708-f7125c90851b",
  "sourceToolAssistantUUID": "dab6d070-5ccc-49d0-9e4e-5098f5181466",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-25T20:13:04.782Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Y2g5DZytfxLuJGdYLdZNFn`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "951c8e60-4d1e-4a58-8708-f7125c90851b",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu2t9BdRDsGPPbzcJ1y",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "4c0e61fc-bef5-460c-ba3b-d94e18b5fb2b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JbGm443x5f2scVH8GiAZAM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1959,
      "cache_read_input_tokens": 16395,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1959,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-25T20:13:04.786Z_

<details><summary>↩ Tool result · `toolu_01Y2g5DZytfxLuJGdYLdZNFn`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\subsection{Setup}
5	
6	We fine-tune Qwen-2.5-7B-Instruct on 8K multi-turn conversations from the UltraChat training split, a dataset of naturalistic dialogues across diverse topics. LoRA adapters (rank 8) are applied to all linear layers. The combined loss $\mathcal{L} = \mathcal{L}_\text{NTP} + \lambda_\text{GAR}\mathcal{L}_\text{GAR} + \lambda_\text{div}\mathcal{L}_\text{div}$ uses $\lambda_\text{GAR} = \lambda_\text{div} = 1.0$ with MSE target $\tau = 0.5$ (\S\ref{sec:loss}). We train for 3 epochs with AdamW (lr $= 2 \times 10^{-4}$, batch size 1, gradient accumulation 8, seed 42); each variant requires approximately 6 hours on a single NVIDIA RTX PRO 6000 Blackwell Server Edition GPU (102\,GB). Full hyperparameters are provided in Appendix~A.
7	
8	To isolate the contribution of gating, we evaluate four configurations: (1)~\textbf{ThreadGate}: LoRA + per-layer learned gates + NTP + GAR loss; (2)~\textbf{Uniform Gate}: LoRA + a single shared gate across all layers + NTP + GAR loss; (3)~\textbf{LoRA-only}: LoRA + NTP + GAR loss, with gates fixed at 1.0 (no learned gating mechanism); (4)~\textbf{Base}: the pretrained model without any fine-tuning. Each configuration is evaluated under two teacher-forced protocols. \emph{IID evaluation} computes metrics on UltraChat text from the same distribution as training. \emph{Held-out evaluation} uses 50 non-overlapping conversations to test within-distribution generalization. We report three metrics: GAR-ours (attention to goal tokens at the last token of each assistant turn, as defined in \S\ref{sec:background}), GAR-Dongre \citep{dongre2026attention} (attention to goal tokens averaged across all response tokens, all layers, and all heads), and perplexity (PPL).
9	
10	\subsection{Main Results}
11	
12	Table~\ref{tab:four-way} presents the four-way ablation. The central finding is that all three fine-tuned variants converge to nearly identical performance across both evaluation settings. On held-out data, GAR-ours spans only 0.75 percentage points (pp) across ThreadGate (0.50), Uniform Gate (0.51), and LoRA-only (0.50), and PPL is identical at 2.78 for all three. This convergence replicates on IID evaluation, where GAR-ours is 0.49 for all three variants and PPL varies by at most 0.01. Neither per-layer gating (ThreadGate) nor shared gating (Uniform Gate) provides any measurable benefit over LoRA-only fine-tuning. These results hold without exception across every metric-split combination in Table~\ref{tab:four-way}.
13	
14	The Base model confirms that LoRA fine-tuning is the operative variable. GAR-ours increases from 0.01 (Base) to approximately 0.49 (all fine-tuned variants) under teacher-forced evaluation, a roughly 45-fold increase. Since all three fine-tuned variants share the same GAR auxiliary loss ($\tau = 0.5$), this convergence near the target is expected; it confirms that the loss functions normally but does not by itself demonstrate benefit from the gating mechanism. PPL improves correspondingly from 4.23 to 2.63 on IID data, which confirms that NTP training functions normally across all configurations. The three-variant convergence holds across both metrics and both evaluation splits; overfitting cannot account for a pattern this consistent.
15	
16	GAR-Dongre remains uniformly low across all conditions (0.00 for Base, 0.01--0.02 for fine-tuned variants). This is consistent with the observation of \citet{dongre2026attention} that the original GAR definition, which averages over all response tokens across all layers and heads, captures a persistently diffuse attention signal. The contrast with GAR-ours reflects measurement granularity: GAR-ours isolates the last token of each assistant turn, where learned attention steering concentrates its effect, while GAR-Dongre dilutes the signal across all positions.
17	
18	The teacher-forced GAR-ours values of 0.49--0.51 stand in sharp contrast to autoregressive generation, where GAR-ours drops to 0.016 for ThreadGate. This 30$\times$ gap between teacher-forced and model-generated evaluation is the central empirical finding of this paper. Under teacher-forcing, the model conditions on UltraChat reference text as the prefix for each response; under autoregressive generation, the prefix consists of the model's own prior outputs. The attention patterns optimized for the former distribution do not transfer to the latter, and the gating mechanism does nothing to bridge this gap. We defer the mechanistic analysis of this distribution shift to \S\ref{sec:analysis}.
19	
20	\begin{table*}[t]
21	\centering
22	\small
23	\caption{Four-way ablation on Qwen-2.5-7B-Instruct. IID evaluation uses teacher-forced UltraChat text; held-out uses 50 non-overlapping conversations. All three fine-tuned variants converge to within 0.75\,pp on GAR-ours and 0\,pp on PPL (held-out). GAR-O = GAR-ours; GAR-D = GAR-Dongre \citep{dongre2026attention}. No values are bolded because no configuration achieves a meaningful advantage.}
24	\label{tab:four-way}
25	\begin{tabular}{l ccc ccc}
26	\toprule
27	& \multicolumn{3}{c}{\textbf{IID Evaluation}} & \multicolumn{3}{c}{\textbf{Held-out Evaluation}} \\
28	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
29	\textbf{Configuration} & GAR-O & GAR-D & PPL & GAR-O & GAR-D & PPL \\
30	\midrule
31	Base          & 0.01 & 0.00 & 4.23 & 0.01 & 0.00 & 4.34 \\
32	ThreadGate    & 0.49 & 0.02 & 2.63 & 0.50 & 0.02 & 2.78 \\
33	Uniform Gate  & 0.49 & 0.01 & 2.62 & 0.51 & 0.01 & 2.78 \\
34	LoRA-only     & 0.49 & 0.01 & 2.63 & 0.50 & 0.01 & 2.78 \\
35	\bottomrule
36	\end{tabular}
37	\end{table*}
38	
39	\subsection{Cross-Model Validation}
40	\label{sec:cross-model}
41	
42	To verify that the convergence pattern and the 30$\times$ training-inference gap are not specific to the Qwen architecture, we are conducting parallel experiments on Llama-3.1-8B-Instruct. Llama-3.1 differs from Qwen-2.5 in several architectural choices, including grouped-query attention with 8 KV heads and a distinct BPE tokenizer. These differences provide a meaningful test of generalization across model families. Results will be reported in the final version of this paper.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4c0e61fc-bef5-460c-ba3b-d94e18b5fb2b",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "b0e835bf-bb3e-4e53-be31-3f532dbd1bad",
  "sourceToolAssistantUUID": "4c0e61fc-bef5-460c-ba3b-d94e18b5fb2b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-25T20:13:04.969Z_

<details open><summary>🔧 Tool call — Read · `toolu_01EvTark1hcAQUxEtbkJEu2z`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/docs/paper/analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b0e835bf-bb3e-4e53-be31-3f532dbd1bad",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu2t9BdRDsGPPbzcJ1y",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8a5eb5a7-db7c-4e1f-b0ec-cddd94c5e3a1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JbGm443x5f2scVH8GiAZAM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1959,
      "cache_read_input_tokens": 16395,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1959,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-25T20:13:04.975Z_

<details><summary>↩ Tool result · `toolu_01EvTark1hcAQUxEtbkJEu2z`</summary>

```text
1	\section{Analysis}\label{sec:analysis}
2	
3	The four-way ablation in \S\ref{sec:experiments} established that gating produces no measurable benefit over LoRA-only fine-tuning. This section investigates why. We first characterize the gradient dynamics between the two training objectives (\S\ref{subsec:gradient-conflict}), then show that the learned gates exhibit behavior opposite to the design intent (\S\ref{subsec:gate-conditioning}). A targeted causal experiment rules out gradient direction conflict as the explanation (\S\ref{subsec:pcgrad}), and a distribution shift analysis identifies the actual failure mode (\S\ref{subsec:dist-shift}).
4	
5	\subsection{Gradient Conflict Observation}\label{subsec:gradient-conflict}
6	
7	To understand how the two loss terms interact during training, we measure the cosine similarity between $\nabla_\theta \mathcal{L}_\text{NTP}$ and $\nabla_\theta \mathcal{L}_\text{GAR}$ at each transformer layer across three training epochs. Table~\ref{tab:grad-conflict} summarizes the results.
8	
9	\begin{table}[t]
10	\centering
11	\small
12	\caption{Gradient interaction between $\mathcal{L}_\text{NTP}$ and $\mathcal{L}_\text{GAR}$ across training epochs. \textit{cos\_sim}: mean cosine similarity across layers. \textit{neg\%}: percentage of layers with negative cosine similarity. \textit{mag\_ratio}: ratio of NTP to GAR gradient magnitudes.}
13	\label{tab:grad-conflict}
14	\begin{tabular}{lccc}
15	\toprule
16	\textbf{Epoch} & \textbf{cos\_sim} & \textbf{neg\%} & \textbf{mag\_ratio} \\
17	\midrule
18	0 & $-$0.089 & 78.6 & 7.5$\times$ \\
19	1 & $-$0.054 & 71.4 & 13.7$\times$ \\
20	2 & $-$0.042 & 67.9 & 14.7$\times$ \\
21	\bottomrule
22	\end{tabular}
23	\end{table}
24	
25	Two patterns are apparent. First, the NTP and GAR gradients point in opposing directions across 68--79\% of layers throughout training. The mean cosine similarity is negative at every epoch, though it attenuates slightly from $-$0.089 to $-$0.042 as training progresses. Second, the NTP gradient magnitude dominates the GAR gradient by a factor that grows from 7.5$\times$ at epoch~0 to 14.7$\times$ at epoch~2. Direction conflict decreases while magnitude imbalance worsens. We observe these patterns as descriptive statistics of the training dynamics. This does not establish that gradient conflict causes $\mathcal{L}_\text{GAR}$ to fail; \S\ref{subsec:pcgrad} tests this hypothesis directly.
26	
27	\subsection{Gate Turn Conditioning}\label{subsec:gate-conditioning}
28	
29	The design intent of ThreadGate is to modulate the residual stream more aggressively at late conversation turns, where GAR naturally decays (\S\ref{sec:background}). We test whether the learned gates achieve this by comparing gate values at turn~1 (early) and turn~21 (late) across all 28 layers of the trained model.
30	
31	The gates do the opposite. In 27 of 28 layers, the gate value at turn~1 is lower than at turn~21 (Wilcoxon signed-rank test: $p = 3.73 \times 10^{-8}$, effect size $r = 0.975$). At layer~23, the gate is 0.769 at turn~1 and 0.979 at turn~21; at layer~14, it is 0.747 at turn~1 and 0.928 at turn~21. The pattern is consistent: gates suppress the residual stream more at early turns (where GAR is already high) and become nearly passive at late turns (where intervention is most needed). This inversion has a straightforward explanation. NTP loss pressure is highest at late turns, where the model must predict tokens conditioned on a long context. The NTP gradient pushes gates toward 1.0 to preserve the full sublayer computation, and this pressure is strongest precisely where GAR-based attenuation would be most useful.
32	
33	The practical consequence is that the gates provide almost no intervention at inference time. Across all layers, mean gate values during inference range from 0.93 to 0.98, corresponding to residual stream attenuation of only 2--7\%. This attenuation is far below what would be required for meaningful modulation, and it explains the convergence with LoRA-only in Table~\ref{tab:four-way}. Figure~\ref{fig:gate-shift}(a) visualizes the per-layer gate difference between early and late turns.
34	
35	\subsection{PCGrad Causal Exclusion}\label{subsec:pcgrad}
36	
37	The gradient conflict observed in \S\ref{subsec:gradient-conflict} raises a natural hypothesis: perhaps the opposing gradient directions between $\mathcal{L}_\text{NTP}$ and $\mathcal{L}_\text{GAR}$ prevent the GAR objective from converging. If direction conflict is the cause of $\mathcal{L}_\text{GAR}$ collapse, then eliminating direction conflict should prevent the collapse. We test this prediction using PCGrad \citep{yu2020pcgrad}.
38	
39	PCGrad projects the gradient of one task onto the normal plane of the other whenever two task gradients conflict in direction. We apply PCGrad to the gate parameters only, projecting $\nabla_\theta \mathcal{L}_\text{NTP}$ onto the orthogonal complement of $\nabla_\theta \mathcal{L}_\text{GAR}$ whenever their cosine similarity is negative. This eliminates the directional component of the conflict while leaving magnitude differences intact. PCGrad does not address magnitude imbalance (which GradNorm targets; \citealp{chen2018gradnorm}) or Nash equilibrium violations (which Nash-MTL targets; \citealp{navon2022nash}); our claim is scoped to direction conflict alone.
40	
41	The result is unambiguous. Under PCGrad, the cosine similarity between NTP and GAR gradients on gate parameters turns positive by gradient step~200 ($+$0.086), confirming that PCGrad successfully removes direction conflict. Yet $\mathcal{L}_\text{GAR}$ follows a trajectory nearly identical to the baseline (v7) and collapses in the same manner. Figure~\ref{fig:training-pcgrad}(b) overlays the $\mathcal{L}_\text{GAR}$ training curves for both conditions.
42	
43	The causal exclusion follows by \emph{modus tollens}:
44	\begin{enumerate}
45	    \item If direction conflict causes $\mathcal{L}_\text{GAR}$ collapse, then removing direction conflict should prevent the collapse.
46	    \item PCGrad removes direction conflict (cosine similarity turns positive at step~200).
47	    \item $\mathcal{L}_\text{GAR}$ collapses regardless.
48	    \item Therefore, direction conflict is not the cause of $\mathcal{L}_\text{GAR}$ collapse.
49	\end{enumerate}
50	
51	This result recharacterizes the gradient observations in \S\ref{subsec:gradient-conflict}: direction conflict between $\mathcal{L}_\text{NTP}$ and $\mathcal{L}_\text{GAR}$ is a symptom of the multi-objective optimization dynamics, not the mechanism responsible for GAR failure. The magnitude imbalance (7.5--14.7$\times$) and potential Nash equilibrium violations remain as candidate explanations that future work can test with GradNorm \citep{chen2018gradnorm} and Nash-MTL \citep{navon2022nash}.
52	
53	\subsection{Distribution Shift Analysis}\label{subsec:dist-shift}
54	
55	The preceding subsections explain why the gating mechanism is ineffective during training. This subsection addresses why the learned GAR improvements fail to transfer from training to inference.
56	
57	Recall from \S\ref{sec:experiments} that teacher-forced GAR-ours reaches 0.49 for all fine-tuned variants, while autoregressive GAR-ours drops to 0.016 for ThreadGate, a 30$\times$ gap. We decompose this gap by comparing same-distribution and cross-distribution evaluation. Under same-distribution evaluation (teacher-forced UltraChat text), GAR-ours is approximately 0.49, confirming that the model has learned the intended attention pattern on the training distribution. Under cross-distribution evaluation (model-generated text), GAR-ours drops to 0.016. The training itself is sound; the failure is one of generalization.
58	
59	GAR-Dongre provides a revealing control. Across both evaluation conditions, GAR-Dongre remains uniformly low (0.01--0.02) with no distribution gap. The distribution shift selectively destroys the concentrated attention pattern captured by GAR-ours (last-token, summary-position attention) while leaving the diffuse attention pattern captured by GAR-Dongre (averaged across all positions) unaffected. This selectivity implies that the distribution shift disrupts a specific learned routing behavior rather than attention computation in general.
60	
61	The mechanism connecting training regime to distribution shift is exposure bias \citep{bengio2015scheduled}. During training, the model conditions each token prediction on ground-truth prefixes from UltraChat. At inference, it conditions on its own prior outputs. The attention patterns optimized for the former distribution do not transfer to the latter, because the statistical properties of model-generated text diverge from those of human-written reference text. The 2--7\% gate attenuation documented in \S\ref{subsec:gate-conditioning} is far too weak to compensate for this distributional mismatch.
62	
63	\citet{he2019exposure} showed that language models exhibit token-level self-recovery from exposure bias: accumulated errors in autoregressive generation do not degrade perplexity as severely as worst-case analysis predicts. Our results are consistent with this finding at the token level, as PPL remains normal across all conditions (Table~\ref{tab:four-way}). The critical distinction is between primary and auxiliary objectives. The NTP objective is robust to exposure bias because next-token prediction is the same task at both training and inference time. The GAR auxiliary objective is fragile because it optimizes an attention pattern under teacher-forced context that has no counterpart in autoregressive generation. Primary-task self-recovery does not extend to auxiliary objectives that depend on distributional properties of the input prefix. Figure~\ref{fig:gate-shift}(b) summarizes the four-model GAR comparison across evaluation conditions.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8a5eb5a7-db7c-4e1f-b0ec-cddd94c5e3a1",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "d80b546a-ec9a-4879-96c8-55f59278de10",
  "sourceToolAssistantUUID": "8a5eb5a7-db7c-4e1f-b0ec-cddd94c5e3a1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-25T20:13:05.672Z_

<details open><summary>🔧 Tool call — Read · `toolu_019b58okJRQBUGJZUkgQKsG1`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/docs/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d80b546a-ec9a-4879-96c8-55f59278de10",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu2t9BdRDsGPPbzcJ1y",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "4c24d43b-39d9-4e7d-a9ab-a89c1043eeb9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JbGm443x5f2scVH8GiAZAM",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1959,
      "cache_read_input_tokens": 16395,
      "output_tokens": 334,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1959
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 334,
          "cache_read_input_tokens": 16395,
          "cache_creation_input_tokens": 1959,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1959,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-25T20:13:05.963Z_

<details><summary>↩ Tool result · reported error · `toolu_019b58okJRQBUGJZUkgQKsG1`</summary>

```text
File content (26122 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4c24d43b-39d9-4e7d-a9ab-a89c1043eeb9",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "9bce7c61-bba3-4662-9e9e-867eb0c7579f",
  "toolUseResult": "Error: File content (26122 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.",
  "sourceToolAssistantUUID": "4c24d43b-39d9-4e7d-a9ab-a89c1043eeb9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 19 · 2026-05-25T20:13:09.817Z_

The appendix is too large. Let me read it in chunks.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9bce7c61-bba3-4662-9e9e-867eb0c7579f",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu3NxYALbTA1jckHP68",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "6092859f-da22-4afb-bfd1-4fdf52bff461",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NLzASVs7V4gRoxjyZSm1Kb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7048,
      "cache_read_input_tokens": 18354,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7048,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 20 · 2026-05-25T20:13:11.673Z_

<details open><summary>🔧 Tool call — Read · `toolu_011QAMJz5SQ1CuHi7VKKVrvQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/docs/paper/sections/appendix.tex",
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6092859f-da22-4afb-bfd1-4fdf52bff461",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu3NxYALbTA1jckHP68",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "98be2355-eb3b-4ac6-87af-7d91a9a95e8f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NLzASVs7V4gRoxjyZSm1Kb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7048,
      "cache_read_input_tokens": 18354,
      "output_tokens": 124,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7048
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 124,
          "cache_read_input_tokens": 18354,
          "cache_creation_input_tokens": 7048,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7048,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 21 · 2026-05-25T20:13:11.681Z_

<details><summary>↩ Tool result · `toolu_011QAMJz5SQ1CuHi7VKKVrvQ`</summary>

```text
1	\section{Training Configuration}\label{sec:appendix-hyper}
2	
3	Table~\ref{tab:hyperparams} lists the full training configuration shared across all fine-tuned variants. ThreadGate gate parameters receive a $10\times$ learning rate multiplier and are initialized with bias 1.5 ($\sigma(1.5) \approx 0.82$); the gate MLP adds ${\sim}$57K parameters per variant ($<$0.001\% of 7B). The scheduled sampling variant (v8b) linearly increases the model-generated context ratio from 0 to 0.5 over 3 epochs (29.7--37.1\% effective usage due to per-sample Bernoulli sampling). All experiments were conducted on a single NVIDIA RTX PRO 6000 Blackwell Server Edition GPU (96\,GB VRAM), requiring 6--8 hours per variant.
4	
5	\begin{table}[t]
6	\centering\small
7	\caption{Training hyperparameters for all fine-tuned variants. Entries marked $\dagger$ apply only to ThreadGate and its ablations.}
8	\label{tab:hyperparams}
9	\begin{tabular}{l@{\hspace{8pt}}l}
10	\toprule
11	\textbf{Parameter} & \textbf{Value} \\
12	\midrule
13	Base model & Qwen-2.5-7B-Instruct \\
14	LoRA rank / $\alpha$ & 16 / 32 \\
15	LoRA targets & \texttt{q\_proj}, \texttt{v\_proj} \\
16	Optimizer & AdamW ($\beta_1$\!=\!0.9, $\beta_2$\!=\!0.999) \\
17	Learning rate & $2 \times 10^{-4}$ \\
18	Gate LR mult.$^\dagger$ & $10\times$ \\
19	Batch / grad accum & 1 / 8 (eff.\ 8) \\
20	Epochs & 3 \\
21	Max seq length & 2048 \\
22	Training data & 8K UltraChat convs \\
23	Seed & 42 (+123 for TG, SS) \\
24	$\lambda_\text{GAR}$/$\lambda_\text{div}$ & 1.0 / 1.0 \\
25	GAR target $\tau$ & 0.5 \\
26	Gate init bias$^\dagger$ & 1.5 ($\sigma\!\approx\!0.82$) \\
27	Gate hidden dim$^\dagger$ & 64 \\
28	Turn embed dim$^\dagger$ & 16 \\
29	GPU & RTX PRO 6000 (96\,GB) \\
30	Training time & 6--8 h / variant \\
31	\bottomrule
32	\end{tabular}
33	\end{table}
34	
35	\section{Loss Formulation Search}\label{sec:appendix-loss}
36	
37	The final MSE + gate diversity loss (\S\ref{sec:loss}) emerged from seven iterations spanning four loss families. Table~\ref{tab:loss-iterations} summarizes the progression. The search was motivated by a consistent failure mode: naive formulations either collapse to trivial solutions (cumulative losses) or drive gates toward identity (maximize-family losses). We describe each family below.
38	
39	\paragraph{Cumulative losses (v1--v2).} These losses accumulate GAR contributions across layers, rewarding monotonically increasing attention. v1 collapsed because once the cumulative GAR exceeded the threshold, the loss gradient vanished and gates froze. v2 added an $\varepsilon$-stabilization term to the cumulative product, but numerical instability from the product of 28 per-layer terms dominated, and training followed the same trajectory.
40	
41	\paragraph{Maximize losses (v3--v5).} These losses directly maximize mean GAR ($-\text{mean}(\text{GAR})$). The unbounded objective rewards full pass-through ($g \to 1.0$), collapsing gate diversity (std $<$ 0.025). At $\lambda$=2 (v3), gates froze within 100 steps; at $\lambda$=10 (v3b), convergence to identity accelerated; at $\lambda$=1 (v5), rebalancing delayed but did not prevent the same degenerate solution.
42	
43	\paragraph{Smooth saturation (v6).} This bounded the reward using a saturating function, intended to prevent the unbounded growth of maximize losses. In practice, the loss landscape remained monotonic in $g$, and training followed the same terminal trajectory as the maximize family, only more slowly.
44	
45	\paragraph{MSE + gate diversity (v7).} The MSE formulation provides bidirectional pressure: GAR above $\tau$ incurs the same penalty as GAR below $\tau$, preventing the runaway optimization of maximize losses. The gate diversity regularizer ($\mathcal{L}_\text{div}$) enforces a minimum standard deviation across per-layer gate values, preventing all gates from collapsing to a uniform value. This combination is the only one that achieved stable convergence (GAR-ours = 0.50, PPL = 2.78).
46	
47	\begin{table*}[t]
48	\centering\footnotesize
49	\caption{Loss formulation iterations on Qwen-2.5-7B-Instruct. GAR-ours (teacher-forced) and PPL are reported only for the converged configuration (v7).}
50	\label{tab:loss-iterations}
51	\begin{tabular}{l l l p{5.8cm} c c}
52	\toprule
53	 & \textbf{Loss Family} & \textbf{Status} & \textbf{Failure Mechanism} & \textbf{GAR} & \textbf{PPL} \\
54	\midrule
55	v1  & Cumulative            & \texttimes~GAR loss $\to$ 0     & GAR loss collapses to zero once threshold is reached; gate gradients vanish at equilibrium & ---  & ---  \\
56	v2  & Cumulative + $\varepsilon$ & \texttimes~same trajectory & Numerical instability from cumulative product; $\varepsilon$-stabilization insufficient & ---  & ---  \\
57	v3  & Maximize ($\lambda$=2)  & \texttimes~gate frozen        & Unbounded reward drives gates toward identity (all-pass); no layer selectivity & ---  & ---  \\
58	v3b & Maximize ($\lambda$=10) & \texttimes~identity collapse   & Higher $\lambda$ accelerates convergence to same degenerate identity solution & ---  & ---  \\
59	v5  & Maximize ($\lambda$=1)  & \texttimes~identity collapse   & Rebalancing delays but does not prevent identity collapse & ---  & ---  \\
60	v6  & Smooth saturation       & \texttimes~identity collapse   & Monotonic reward identical to maximize in practice; boundedness slows but does not alter terminal trajectory & ---  & ---  \\
61	v7  & MSE + gate div          & \checkmark~\textbf{converged}  & \textbf{Bidirectional penalty prevents identity collapse; gate diversity regularizer enforces layer selectivity} & 0.50 & 2.78 \\
62	\bottomrule
63	\end{tabular}
64	\end{table*}
65	
66	\section{Instruction Retention Details}\label{sec:appendix-ir}
67	
68	To evaluate whether GAR improvements translate to downstream task performance, we test instruction retention across 18 system-prompt constraint types using the ThreadGate checkpoint with $\beta$\,=\,3 steering on $N$\,=\,200 held-out conversations. Each constraint type requires the model to follow a specific instruction embedded in the system prompt (e.g., ``always respond in bullet points'', ``never use the word X'', ``include a summary at the end''). This evaluation bridges the gap between our attention-level metric (GAR) and observable model behavior.
69	
70	\paragraph{Evaluation protocol.} For each conversation, we inject a constraint into the system prompt and evaluate compliance across all assistant turns. A turn is compliant if it satisfies the constraint according to rule-based checkers (for format, count, and position constraints) or GPT-4-based evaluation (for content constraints, which require semantic judgment). We use the same 18 constraint types across all conversations, yielding $N$\,=\,54 paired evaluations (18 types $\times$ 3 conversations per type) for the McNemar analysis.
71	
72	\paragraph{Per-category results.} Table~\ref{tab:ir-results} reports per-category compliance rates. Content constraints---which require attending to and recalling specific system-prompt instructions across turns---show the largest improvement (+23.8\,pp), consistent with GAR measuring attention to goal tokens. This category includes constraints like ``mention X in every response'' and ``always reference the original topic,'' which require sustained attention to the system prompt. Position constraints (e.g., ``start each response with Y'') show a modest improvement (+6.7\,pp), as they partially depend on goal-token attention. Format (e.g., ``use bullet points'') and count constraints (e.g., ``exactly 3 sentences'') show no change, consistent with these being procedural patterns that are cached in the model's generation routine rather than requiring ongoing attention to the system prompt.
73	
74	\paragraph{Correlation analysis.} The GAR-compliance correlation ($r$\,=\,0.200, $p$\,=\,0.007) is statistically significant but modest, suggesting that attention to goal tokens is one of several factors in instruction compliance. Other factors likely include the model's procedural memory for format constraints, the specificity of the constraint (vague constraints are harder regardless of attention), and the interaction between constraint type and conversation topic. McNemar's test ($p$\,=\,0.077) is marginally significant for the overall compliance improvement, reflecting the small sample size (18 constraint types). These results are exploratory and pending multi-model confirmation.
75	
76	Figure~\ref{fig:ir-bar} visualizes the per-category breakdown.
77	
78	\begin{figure}[t]
79	  \centering
80	  \includegraphics[width=\columnwidth]{fig_instruction_retention.pdf}
81	  \caption{Instruction retention by constraint category under $\beta$\,=\,3 steering. Content constraints benefit most (+23.8\,pp); format and count constraints are unaffected.}
82	  \label{fig:ir-bar}
83	\end{figure}
84	
85	\FloatBarrier
86	
87	\begin{table}[t]
88	\centering\small
89	\caption{Instruction retention by constraint category ($\beta$\,=\,3 steering on ThreadGate checkpoint). Content constraints benefit most from increased goal attention.}
90	\label{tab:ir-results}
91	\begin{tabular}{lccc}
92	\toprule
93	\textbf{Category} & $\beta$\,=\,0 & $\beta$\,=\,3 & $\Delta$ \\
94	\midrule
95	Content    & 61.9\% & 85.7\% & +23.8\,pp \\
96	Position   & 66.7\% & 73.3\% & +6.7\,pp \\
97	Count      & 100\%  & 100\%  & 0 \\
98	Format     & 100\%  & 100\%  & 0 \\
99	\midrule
100	\textbf{Overall} & 75.9\% & 87.0\% & +11.1\,pp \\
101	\bottomrule
102	\end{tabular}
103	\end{table}
104	
105	\section{Long-Conversation AR Evaluation}\label{sec:appendix-n5}
106	
107	The main results (Table~\ref{tab:five-way}) report AR GAR from $N$\,=\,50 held-out conversations with a mean of 3.6 user turns. Table~\ref{tab:n5-ar} presents complementary results on $N$\,=\,5 conversations with 10 turns each, testing whether the observed patterns generalize beyond the training distribution's conversation length.
108	
109	\paragraph{Gating advantage vanishes at length.} In these longer dialogues, the gating advantage observed in shorter conversations vanishes: all fine-tuned variants collapse to AR GAR-ours of 0.015--0.025, compared to 0.030--0.064 in the shorter evaluation. ThreadGate's advantage over LoRA-only shrinks from 1.7$\times$ (0.064 vs.\ 0.037 in the $N$\,=\,50 evaluation) to 0.64$\times$ (0.016 vs.\ 0.025), actually reversing the ordering. This reversal is not statistically robust given the small sample ($N$\,=\,5) but directionally suggests that architectural modifications provide diminishing returns as conversation length increases and exposure bias accumulates.
110	
111	\paragraph{Convergence to base.} By turn~10, all fine-tuned variants converge to within 2$\times$ of the base model's GAR, compared to 3.4$\times$ at turn~1 in the shorter evaluation. This convergence is consistent with exposure bias compounding multiplicatively over turns: each model-generated turn introduces additional distributional drift from the teacher-forced training regime, and by turn~10 the accumulated drift overwhelms any gating or LoRA signal, leaving only the base model's intrinsic attention patterns.
112	
113	\paragraph{Caveats.} The $N$\,=\,5 sample size limits statistical power, and the 10-turn conversations may differ systematically from the 3--5 turn training distribution in ways beyond length (e.g., topic complexity, user engagement patterns). We present these results as directional evidence rather than definitive conclusions.
114	
115	\begin{table}[t]
116	\centering\small
117	\caption{AR GAR-ours on $N$\,=\,5 ten-turn conversations. The gating advantage observed in Table~\ref{tab:five-way} ($N$\,=\,50, mean 3.6 turns) diminishes with conversation length.}
118	\label{tab:n5-ar}
119	\begin{tabular}{lcc}
120	\toprule
121	\textbf{Configuration} & \textbf{AR GAR-O} & \textbf{$\Delta$ vs.\ Table~\ref{tab:five-way}} \\
122	\midrule
123	Base & 0.012 & $-$0.007 \\
124	\midrule
125	ThreadGate & 0.016 & $-$0.048 \\
126	\;+\,PCGrad & 0.015 & $-$0.015 \\
127	Uniform Gate & 0.015 & $-$0.018 \\
128	LoRA-only & 0.025 & $-$0.012 \\
129	\bottomrule
130	\end{tabular}
131	\end{table}
132	
133	\section{Statistical Test Details}\label{sec:appendix-stats}
134	
135	All statistical tests reported in the main text use non-parametric methods due to the non-normal, heavy-tailed distribution of per-conversation GAR values. Table~\ref{tab:stat-tests} consolidates the full results.
136	
137	\paragraph{Wilcoxon signed-rank tests.} We use paired Wilcoxon signed-rank tests for all pairwise configuration comparisons under AR evaluation, treating each conversation as a paired observation. The TG vs.\ LoRA-only comparison ($p$\,=\,0.004, $r$\,=\,0.454) confirms that turn-conditioned gating provides a statistically significant but modest improvement. The TG vs.\ +PCGrad comparison ($p$\,=\,0.002) shows that resolving gradient conflict is actively harmful. Gate turn conditioning uses an unpaired Wilcoxon test across 28 layers.
138	
139	\paragraph{Bootstrap confidence intervals.} The 95\% CIs in Table~\ref{tab:five-way} are computed via 10,000 bootstrap resamples of per-conversation mid-turn GAR averages (turns 2--$T$), using the percentile method.
140	
141	\paragraph{Effect sizes.} We report rank-biserial correlation $r = Z / \sqrt{N}$ as the effect size for Wilcoxon tests, where $Z$ is the standardized test statistic and $N$ is the number of observations. By standard conventions: $r < 0.3$ is small, $0.3 \leq r < 0.5$ is medium, and $r \geq 0.5$ is large. The TG vs.\ LoRA-only effect ($r$\,=\,0.454) is medium, and TG vs.\ Base ($r$\,=\,0.802) is large.
142	
143	\paragraph{Multiple comparisons.} We report uncorrected $p$-values throughout, as our comparisons are hypothesis-driven (each tests a specific causal exclusion) rather than exploratory. Applying Bonferroni correction to the 4 primary AR comparisons would adjust the significance threshold to 0.0125; all reported significant results ($p \leq 0.004$) survive this correction.
144	
145	\begin{table}[t]
146	\centering\small
147	\caption{Consolidated statistical tests. All AR comparisons use $N$\,=\,50 conversations (39 with $\geq$3 turns); gate conditioning uses 28 layers.}
148	\label{tab:stat-tests}
149	\begin{tabular}{llcc}
150	\toprule
151	\textbf{Comparison} & \textbf{Test} & $p$ & $r$ \\
152	\midrule
153	\multicolumn{4}{l}{\emph{AR GAR-ours ($\beta$\,=\,0)}} \\
154	TG vs.\ Base & Wilcoxon & $<$0.001 & 0.802 \\
155	TG vs.\ LoRA-only & Wilcoxon & 0.004 & 0.454 \\
156	TG vs.\ +PCGrad & Wilcoxon & 0.002 & --- \\
157	SS vs.\ TG & Wilcoxon & $<$0.001 & 0.869 \\
158	\midrule
159	\multicolumn{4}{l}{\emph{Gate conditioning (28 layers)}} \\
160	Turn 1 vs.\ Turn 21 & Wilcoxon & $3.7\!\times\!10^{-8}$ & 0.975 \\
161	\midrule
162	\multicolumn{4}{l}{\emph{Instruction retention}} \\
163	$\beta$\,=\,0 vs.\ $\beta$\,=\,3 & McNemar & 0.077 & --- \\
164	GAR--compliance & Pearson & 0.007 & 0.200 \\
165	\bottomrule
166	\end{tabular}
167	\end{table}
168	
169	\section{Llama-3.1-8B Complete Results}\label{sec:appendix-llama}
170	
171	Table~\ref{tab:llama-full} presents the complete Llama-3.1-8B-Instruct results, complementing the summary in \S\ref{subsec:cross-model}. Three configurations were trained (Base, ThreadGate, LoRA-only) using the same training pipeline as Qwen-2.5-7B (8K UltraChat, 3 epochs, LoRA rank 16). Training required 7.0--7.3 hours per variant on the same GPU.
172	
173	\paragraph{Teacher-forced evaluation.} TF GAR-ours is 0.484 (TG) and 0.481 (LoRA-only), confirming that gating provides zero benefit under teacher forcing on Llama, consistent with the Qwen results (0.50 vs.\ 0.50).
174	
175	\paragraph{Autoregressive evaluation.} AR evaluation uses $N$\,=\,20 mid-turn conversations (turns 3--$T$, excluding the first two turns to avoid initialization effects). The AR GAR distribution is heavy-tailed: the coefficient of variation exceeds 100\% for ThreadGate (mean 0.043, std 0.100), and 5\% of turn-level measurements exhibit sporadic attention spikes (GAR $\geq$ 0.4). We therefore report both mean and median.
176	
177	\paragraph{Gate profile.} Llama's gate profile differs qualitatively from Qwen's: Qwen shows minimum attenuation at early layers (L1\,=\,0.793, L5\,=\,0.797), while Llama shows a V-shaped valley at mid-to-late layers (L25\,=\,0.719, L24\,=\,0.809). Despite this architectural difference, both models converge toward identity under NTP pressure, and the TF-AR gap is comparable (27$\times$ by median for Llama vs.\ 8--17$\times$ for Qwen).
178	
179	\begin{table}[t]
180	\centering\small
181	\caption{Llama-3.1-8B-Instruct complete results. TF: teacher-forced ($N$\,=\,50); AR: autoregressive ($N$\,=\,20 for Base/TG/LoRA-only, $N$\,=\,50 for SS). Median is more representative due to heavy-tailed AR distributions (SS uses mean only).}
182	\label{tab:llama-full}
183	\resizebox{\columnwidth}{!}{%
184	\begin{tabular}{lcccc}
185	\toprule
186	& \multicolumn{2}{c}{\textbf{TF}} & \multicolumn{2}{c}{\textbf{AR}} \\
187	\cmidrule(lr){2-3} \cmidrule(lr){4-5}
188	& GAR-O & PPL & GAR-O (mean) & GAR-O (med) \\
189	\midrule
190	Base & 0.017 & 3.45 & 0.009 & 0.009 \\
191	ThreadGate & 0.484 & 2.57 & 0.043 & 0.018 \\
192	LoRA-only & 0.481 & 2.60 & 0.028 & 0.018 \\
193	\textbf{SS} & 0.477 & 2.82 & \textbf{0.166} & --- \\
194	\bottomrule
195	\end{tabular}}
196	\end{table}
197	
198	\FloatBarrier
199	
200	\begin{figure}[t]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "98be2355-eb3b-4ac6-87af-7d91a9a95e8f",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "32401bcd-3eed-46e1-a447-f02d1774bfcc",
  "sourceToolAssistantUUID": "98be2355-eb3b-4ac6-87af-7d91a9a95e8f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 22 · 2026-05-25T20:13:16.937Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NvVgy4YUDZGA1bckNiwyR9`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/docs/paper/sections/appendix.tex",
  "offset": 200,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "32401bcd-3eed-46e1-a447-f02d1774bfcc",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu3oNyGNee2RMiHyYb9",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3017c0e8-3733-41ab-bd19-1824d94c440d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NRywgBwv2fYPxxm7L5CUN1",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6153,
      "cache_read_input_tokens": 25402,
      "output_tokens": 126,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 6153
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 126,
          "cache_read_input_tokens": 25402,
          "cache_creation_input_tokens": 6153,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 6153,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 23 · 2026-05-25T20:13:16.943Z_

<details><summary>↩ Tool result · `toolu_01NvVgy4YUDZGA1bckNiwyR9`</summary>

```text
200	\begin{figure}[t]
201	  \centering
202	  \includegraphics[width=\columnwidth]{fig_crossmodel.pdf}
203	  \caption{Cross-architecture validation. (a)~The TF-AR gap persists on Llama-3.1-8B (27$\times$ by median), exceeding Qwen's 8$\times$. (b)~Gate profiles on normalized depth: Qwen dips at early layers, Llama at late layers; architecture-dependent patterns, but both converge toward identity.}
204	  \label{fig:crossmodel}
205	\end{figure}
206	
207	\paragraph{Cross-model summary.} Table~\ref{tab:crossmodel-detail} consolidates the cross-model comparison, showing TF GAR, AR GAR, PPL, and gap ratios side by side for both architectures. The consistent pattern---TF GAR $\approx$ 0.5, AR GAR $\ll$ 0.1, gap $\geq$ 7.9$\times$---across two architectures with different layer counts, attention head configurations, and pre-training corpora provides strong evidence that exposure bias is architecture-independent. Notably, Llama's larger gaps (27$\times$ by median for TG; mean-based range 11.2--17.2$\times$) compared to Qwen's (7.9--13.5$\times$) may reflect its deeper architecture (32 vs.\ 28 layers), which allows more layers for distributional drift to compound through.
208	
209	\input{../artifacts/appendix_expansion/tab_crossmodel_detail.tex}
210	
211	\paragraph{GAR-Dongre cross-model comparison.} GAR-Dongre shows negligible distribution shift on Llama (AR/TF ratio 1.002$\times$), compared to 1.28$\times$ on Qwen. This confirms the mechanism specificity finding: exposure bias selectively disrupts the concentrated last-token attention pattern (GAR-ours) while leaving the diffuse all-token attention (GAR-Dongre) unaffected across both architectures.
212	
213	\paragraph{Training details.} Llama variants used the same pipeline as Qwen: 8K UltraChat conversations, LoRA rank 16 targeting $q$/$v$ projections, 3 epochs. Training loss converged to 0.929 (LoRA-only) and 0.934 (ThreadGate); the slight difference is attributable to the additional GAR loss component. Wall-clock time was 7.0h (LoRA-only) and 7.3h (ThreadGate), approximately 17\% longer than Qwen due to Llama's larger layer count (32 vs.\ 28 layers).
214	
215	\paragraph{Phase 1 diagnostics.} Before fine-tuning, we confirmed that Llama exhibits the same goal attention decay as Qwen. Base model GAR decays from 0.026 (turn 1) to 0.003 (turn 10), a 90\% decline. This is steeper than Qwen's 70.8\% decline, suggesting that attention decay may be more severe in Llama's architecture despite its larger head count (32 vs.\ 28 KV heads).
216	
217	\paragraph{Cross-model gradient analysis.} Table~\ref{tab:gradient-crossmodel} compares NTP--GAR gradient interaction between the two architectures. Both models exhibit near-orthogonal gradients (cosine similarity $\approx$\,0), not systematic conflict: Qwen shows a slight negative mean ($-$0.042) while Llama is marginally positive (+0.005). NTP gradients dominate GAR by 14.7$\times$ on Qwen and 25.7$\times$ on Llama, indicating that the auxiliary signal is overwhelmed by magnitude rather than opposed by direction. The cross-model consistency---near-zero cosine similarity and order-of-magnitude NTP dominance on both architectures---reinforces the \emph{modus tollens} argument (\S\ref{subsec:pcgrad}): gradient direction conflict is not the primary cause of the TF-AR gap.
218	
219	\begin{table}[t]
220	\centering\small
221	\caption{Cross-model NTP--GAR gradient interaction. Gradients are near-orthogonal on both architectures; NTP magnitude dominates GAR by 15--26$\times$.}
222	\label{tab:gradient-crossmodel}
223	\begin{tabular}{lcc}
224	\toprule
225	\textbf{Metric} & \textbf{Qwen-7B} & \textbf{Llama-8B} \\
226	\midrule
227	Mean cos sim & $-$0.042 & +0.005 \\
228	Neg-layer \% & 67.9\% & 53.1\% \\
229	NTP/GAR mag ratio & 14.7$\times$ & 25.7$\times$ \\
230	\bottomrule
231	\end{tabular}
232	\end{table}
233	
234	\section{Additional Visualizations}\label{sec:appendix-viz}
235	
236	This section presents extended visualizations referenced in the main text. Each figure examines a different aspect of the gating behavior and its failure under autoregressive generation.
237	
238	\subsection{Gate Profile Heatmap}
239	
240	Figure~\ref{fig:gate-heatmap} shows the per-layer gate values across all training configurations for both Qwen-2.5-7B (28 layers) and Llama-3.1-8B (32 layers). The key observation is that early layers consistently receive the lowest gate values across all conditions, suggesting that these layers contribute more dispensable computations for the NTP objective. The pattern is remarkably consistent across ThreadGate, Uniform Gate, and PCGrad variants, indicating that gate-value allocation is driven primarily by the NTP loss landscape rather than the GAR auxiliary objective.
241	
242	\begin{figure}[H]
243	\centering
244	\includegraphics[width=\columnwidth]{fig_gate_profile_heatmap.pdf}
245	\caption{Per-layer gate values across training for Qwen-2.5-7B (28 layers $\times$ 5 conditions) and Llama-3.1-8B (32 layers $\times$ 1 condition). Early layers (L1, L4--5) consistently receive the lowest gate values across conditions.}
246	\label{fig:gate-heatmap}
247	\end{figure}
248	
249	\subsection{Cross-Model Gate Profile Comparison}
250	
251	Figure~\ref{fig:gate-crossmodel} compares gate profiles between the two architectures. Qwen-2.5-7B shows minimum gate values at early layers (L1\,=\,0.793, L5\,=\,0.797), suggesting these layers are most amenable to attenuation without disrupting NTP. Llama-3.1-8B instead shows a V-shaped valley at mid-to-late layers (L25\,=\,0.719), indicating that architecturally distinct models learn different layer-importance hierarchies. Both profiles converge toward identity at their respective final layers, consistent with NTP gradient pressure dominating gate optimization at output-adjacent layers.
252	
253	\begin{figure}[H]
254	\centering
255	\includegraphics[width=\columnwidth]{fig_gate_profile_crossmodel.pdf}
256	\caption{Side-by-side gate profiles for Qwen-2.5-7B and Llama-3.1-8B. Qwen dips at early layers (L1\,=\,0.793, L5\,=\,0.797), while Llama shows a V-shaped valley at mid-to-late layers (L25\,=\,0.719). Both models learn layer-selective gating but with architecture-dependent patterns.}
257	\label{fig:gate-crossmodel}
258	\end{figure}
259	
260	\subsection{Per-Turn AR GAR Decay}
261	
262	Figure~\ref{fig:ar-gar-perturn} visualizes the monotonic decay of GAR across conversation turns under autoregressive generation. Qwen base drops 85\% from turn 1 to turn 10; Llama base drops 90\%. The ThreadGate-trained model shows slight elevation in absolute GAR values but follows the same decay pattern, confirming that training-time GAR optimization does not alter the fundamental decay dynamic during generation. This per-turn view complements the aggregate TF-AR gap reported in Table~\ref{tab:five-way}: the gap is not a fixed offset but grows with conversation length, consistent with cumulative exposure bias.
263	
264	\begin{figure}[H]
265	\centering
266	\includegraphics[width=\columnwidth]{fig_ar_gar_perturn.pdf}
267	\caption{GAR decays monotonically across turns under autoregressive generation. Qwen base drops 85\% (turn 1$\to$10), Llama base drops 90\%. The ThreadGate-trained model (AR) shows slight elevation but the same decay pattern, confirming that training-time GAR optimization does not transfer to generation.}
268	\label{fig:ar-gar-perturn}
269	\end{figure}
270	
271	\subsection{Bootstrap Confidence Intervals}
272	
273	Figure~\ref{fig:bootstrap-ci} shows the bootstrap resampling distributions underlying the 95\% CIs reported in Table~\ref{tab:five-way}.
274	
275	\begin{figure}[H]
276	  \centering
277	  \includegraphics[width=\columnwidth]{fig_bootstrap_ci.pdf}
278	  \caption{Bootstrap CI distributions for AR GAR-ours (ThreadGate vs.\ LoRA-only, $N$\,=\,50, 10K resamples). Distributions overlap substantially, consistent with the modest effect size ($r$\,=\,0.454).}
279	  \label{fig:bootstrap-ci}
280	\end{figure}
281	
282	\subsection{Gate Value Distributions}
283	
284	Figure~\ref{fig:gate-distribution} shows the full distribution of per-layer gate values for ThreadGate, Uniform Gate, and PCGrad variants. All three converge to similar distributions (mean $\sim$0.94--0.96, concentrated between 0.9 and 1.0), confirming that the gating mechanism provides minimal modulation regardless of the specific variant. The distributions are right-skewed with a sharp cutoff at 1.0, reflecting NTP pressure pushing gates toward identity.
285	
286	\begin{figure}[H]
287	\centering
288	\includegraphics[width=\columnwidth]{fig_gate_distribution.pdf}
289	\caption{Per-layer gate value distributions for ThreadGate, Uniform Gate, and PCGrad variants. All three converge to similar distributions (mean $\sim$0.94--0.96), confirming minimal modulation from the gating mechanism.}
290	\label{fig:gate-distribution}
291	\end{figure}
292	
293	\subsection{Training Loss Curves}
294	
295	Figure~\ref{fig:training-loss} shows the NTP, GAR, and total loss trajectories during training. GAR loss collapses to near-zero within the first epoch across all variants, indicating rapid convergence of the auxiliary objective under teacher forcing. NTP loss converges normally to ${\sim}$0.93 by epoch 3. The fast GAR convergence is not itself pathological---it indicates successful optimization under the training distribution. The pathology emerges only at the transition to autoregressive generation, where the learned attention patterns fail to transfer.
296	
297	\begin{figure}[H]
298	\centering
299	\includegraphics[width=\columnwidth]{fig_training_loss_curves.pdf}
300	\caption{NTP, GAR, and total loss trajectories. GAR loss collapses to near-zero within the first epoch across all variants, while NTP loss converges normally.}
301	\label{fig:training-loss}
302	\end{figure}
303	
304	\subsection{Full Attention Steering Results}\label{sec:appendix-steering}
305	
306	\begin{table*}[t]
307	\centering\small
308	\caption{Full attention steering results across evaluation settings.
309	\textbf{Bold} indicates the operating point cited in the main text ($\beta$\,=\,5).
310	A visual gap separates the phase-transition boundary: GAR jumps sharply between $\beta$\,=\,2 and $\beta$\,=\,3 across all settings.}
311	\label{tab:steering-full}
312	\begin{tabular}{r cc cc cc}
313	\toprule
314	 & \multicolumn{2}{c}{\textbf{$N$\,=\,5, Gen}} & \multicolumn{2}{c}{\textbf{$N$\,=\,50, Gen}} & \multicolumn{2}{c}{\textbf{$N$\,=\,200, TF}} \\
315	\cmidrule(lr){2-3} \cmidrule(lr){4-5} \cmidrule(lr){6-7}
316	$\beta$ & GAR & PPL & GAR & PPL & GAR & PPL \\
317	\midrule
318	0   & .028 & 1.41 & $.064 \pm .081$ & $1.43 \pm .10$ & .535 & 2.62 \\
319	0.5 & .029 & 1.39 & ---             & ---             & ---  & ---  \\
320	1   & .035 & 1.36 & ---             & ---             & ---  & ---  \\
321	2   & .062 & 1.41 & $.128 \pm .110$ & $1.48 \pm .14$ & .611 & 2.69 \\
322	\addlinespace[3pt]
323	3   & ---  & ---  & $.556 \pm .060$ & $1.56 \pm .17$ & .788 & 2.93 \\
324	4   & ---  & ---  & $.644 \pm .061$ & $1.67 \pm .22$ & .817 & 3.49 \\
325	\textbf{5}  & \textbf{.680} & \textbf{1.91} & $\mathbf{.727 \pm .061}$ & $\mathbf{1.77 \pm .27}$ & \textbf{.833} & \textbf{6.15} \\
326	10  & .959 & 4.22 & $.961 \pm .015$ & $3.45 \pm 1.78$ & .977 & 505.2 \\
327	\bottomrule
328	\end{tabular}
329	\end{table*}
330	
331	\begin{figure}[t]
332	  \centering
333	  \includegraphics[width=\columnwidth]{fig_steering_standalone.pdf}
334	  \caption{Detailed $\beta$-steering trade-off ($N$\,=\,50). GAR-ours (top) increases monotonically with $\beta$; PPL (bottom) remains stable below $\beta$\,=\,3 (9\% cost), then rises sharply. The $\beta$\,=\,3 operating point (circled) achieves 8.7$\times$ GAR recovery while crossing the TF baseline, representing the optimal trade-off.}
335	  \label{fig:steering-standalone}
336	\end{figure}
337	
338	\section{Per-Layer Gate Profile}\label{sec:appendix-gate-profile}
339	
340	Table~\ref{tab:gate-profile} reports the final per-layer gate values for ThreadGate (seed 123) on Qwen-2.5-7B-Instruct (28 layers). Gate values are averaged across all tokens in the evaluation set. Layers 1 and 5 show the lowest gate values (0.793 and 0.797), indicating these layers are most amenable to attenuation without disrupting NTP. Layers 26--27 converge to $\geq$0.988, consistent with NTP gradient pressure dominating at output-adjacent layers. The mean across all layers is 0.947 ($\sigma$\,=\,0.051).
341	
342	\begin{table}[t]
343	\centering\small
344	\caption{Per-layer gate values for ThreadGate (seed 123) on Qwen-2.5-7B-Instruct. Min values (L1, L5) in bold.}
345	\label{tab:gate-profile}
346	\resizebox{\columnwidth}{!}{%
347	\begin{tabular}{cccccccc}
348	\toprule
349	L0 & L1 & L2 & L3 & L4 & L5 & L6 & L7 \\
350	.883 & \textbf{.793} & .996 & .988 & .984 & \textbf{.797} & .961 & .918 \\
351	\midrule
352	L8 & L9 & L10 & L11 & L12 & L13 & L14 & L15 \\
353	.965 & .934 & .969 & .918 & .926 & .941 & .930 & .965 \\
354	\midrule
355	L16 & L17 & L18 & L19 & L20 & L21 & L22 & L23 \\
356	.941 & .910 & .961 & .965 & .973 & .988 & .969 & .980 \\
357	\midrule
358	L24 & L25 & L26 & L27 & \multicolumn{4}{c}{Summary} \\
359	.980 & .984 & .988 & 1.00 & \multicolumn{4}{c}{$\bar{g}$\,=\,.947, $\sigma$\,=\,.051} \\
360	\bottomrule
361	\end{tabular}}
362	\end{table}
363	
364	The gate profile exhibits two notable patterns: (1)~a bimodal dip at L1 and L5, suggesting two distinct ``dispensable'' layer clusters in Qwen's architecture; (2)~monotonic increase from L17 to L27, indicating output-adjacent layers are progressively more critical for NTP. Seed 42 produces a similar profile (mean 0.934, min at L3--L5), confirming the pattern is not seed-dependent.
365	
366	\paragraph{Cross-model comparison.} See \S\ref{sec:appendix-viz} for the full cross-model gate profile comparison (Figure~\ref{fig:gate-crossmodel}). Llama-3.1-8B shows a qualitatively different profile---a V-shaped valley at mid-to-late layers rather than early-layer dips---suggesting architecture-dependent layer importance hierarchies.
367	
368	\section{Scheduled Sampling Implementation}\label{sec:appendix-ss}
369	
370	Our scheduled sampling implementation follows \citet{bengio2015scheduled} with modifications for multi-turn transformer training:
371	
372	\paragraph{Sampling schedule.} The model-generated context ratio $\rho$ increases linearly from 0 to 0.3 over 3 epochs. At each training step, a Bernoulli trial with probability $\rho$ determines whether the input prefix is replaced with model-generated tokens. The effective usage rate (29.7--37.1\%) is lower than the nominal schedule due to per-sample Bernoulli variance.
373	
374	\paragraph{Context generation.} When model-generated context is selected, the model autoregressively generates the assistant turns from the conversation prefix up to the current training position. The generated tokens replace the ground-truth assistant tokens in the input, while user turns remain unchanged. This preserves the multi-turn structure while introducing distributional diversity in the conditioning context.
375	
376	\paragraph{Training dynamics.} The scheduled sampling variant converges to similar final loss (NTP 0.932 vs.\ 0.930 for standard ThreadGate) but with higher variance in early epochs due to the stochastic context mixing (Figure~\ref{fig:ss-dynamics}). Gate profiles remain similar (mean 0.953 vs.\ 0.947, min at L4 vs.\ L1), indicating that scheduled sampling does not fundamentally alter gate optimization but rather improves the robustness of the learned attention patterns to distributional shift. Training time increases by 8--80\% across seeds (seed-dependent; dominated by GAR forward pass overhead): 6.5h (seed 42), 10.8h (seed 123), and 6.5h (seed 456) vs.\ 6.0h for standard ThreadGate on Qwen. Seed 456 exhibits consistent training dynamics with seeds 42 and 123.
377	
378	\begin{figure}[t]
379	  \centering
380	  \includegraphics[width=\columnwidth]{fig_ss_training_dynamics.pdf}
381	  \caption{Scheduled sampling training dynamics: sampling ratio $\rho$ ramps linearly from 0 to 0.3 (left axis); GAR loss (right axis) shows higher early-epoch variance due to stochastic context mixing.}
382	  \label{fig:ss-dynamics}
383	\end{figure}
384	
385	\section{Computational Cost Analysis}\label{sec:appendix-cost}
386	
387	\begin{table}[t]
388	\centering\small
389	\caption{Computational cost across training configurations. All experiments use a single NVIDIA RTX PRO 6000 (96\,GB VRAM).}
390	\label{tab:cost}
391	\resizebox{\columnwidth}{!}{%
392	\begin{tabular}{lcccc}
393	\toprule
394	\textbf{Config} & \textbf{Params} & \textbf{Time (h)} & \textbf{VRAM} & \textbf{Overhead} \\
395	\midrule
396	\multicolumn{5}{l}{\emph{Qwen-2.5-7B-Instruct}} \\
397	LoRA-only & 4.2M & 6.0 & 42\,GB & baseline \\
398	ThreadGate & 4.3M & 6.0 & 43\,GB & $+$57K \\
399	\;+\,PCGrad & 4.3M & 8.0 & 43\,GB & $+$33\% \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3017c0e8-3733-41ab-bd19-1824d94c440d",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "52c8b3ea-9dbd-49fe-bbfa-41a1aa3a699c",
  "sourceToolAssistantUUID": "3017c0e8-3733-41ab-bd19-1824d94c440d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-25T20:13:28.256Z_

<details open><summary>🔧 Tool call — Read · `toolu_01YbkYyqzH6Ly4yWpfsUae6T`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/docs/paper/sections/appendix.tex",
  "offset": 399,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "52c8b3ea-9dbd-49fe-bbfa-41a1aa3a699c",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu4BqqA2ZddwoxPHhwJ",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "84eb8edd-6b2f-4cdc-8cdc-95b14ea3780f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BoXA6uqykjHL6df8XZrPTv",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5897,
      "cache_read_input_tokens": 31555,
      "output_tokens": 126,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 5897
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 126,
          "cache_read_input_tokens": 31555,
          "cache_creation_input_tokens": 5897,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 5897,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 25 · 2026-05-25T20:13:28.274Z_

<details><summary>↩ Tool result · `toolu_01YbkYyqzH6Ly4yWpfsUae6T`</summary>

```text
399	\;+\,PCGrad & 4.3M & 8.0 & 43\,GB & $+$33\% \\
400	Uniform Gate & 4.3M & 6.0 & 43\,GB & $+$57K \\
401	SS (s42) & 4.3M & 6.5 & 43\,GB & $+$8\% \\
402	SS (s123) & 4.3M & 10.8 & 43\,GB & $+$80\% \\
403	SS (s456) & 4.3M & 6.5 & 43\,GB & $+$8\% \\
404	\midrule
405	\multicolumn{5}{l}{\emph{Llama-3.1-8B-Instruct}} \\
406	LoRA-only & 4.2M & 7.0 & 45\,GB & baseline \\
407	ThreadGate & 4.3M & 7.3 & 46\,GB & $+$65K \\
408	\bottomrule
409	\end{tabular}}
410	\end{table}
411	
412	\paragraph{Parameter overhead.} ThreadGate adds ${\sim}$57K gate parameters for Qwen-2.5-7B (28 layers $\times$ 2K per gate MLP) and ${\sim}$65K for Llama-3.1-8B (32 layers), representing $<$0.001\% of the base model. LoRA adapters (rank 16, targeting $q$/$v$ projections) contribute 4.2M parameters across both architectures.
413	
414	\paragraph{Training time.} Standard variants (ThreadGate, Uniform Gate, LoRA-only) train in 6.0--7.3 hours. PCGrad adds ${\sim}$33\% overhead due to the per-step gradient projection computation. Scheduled sampling overhead varies: seed 42 adds only 8\% (6.5h) due to efficient batched generation, while seed 123 adds 80\% (10.8h) because of a longer generation schedule. The difference is due to the extended AR generation schedule in the seed 123 variant.
415	
416	\paragraph{Inference overhead.} Gate computation at inference time is negligible: a single 32$\to$64$\to$1 MLP forward pass per layer adds $<$0.1\% latency. $\beta$-steering requires identifying goal tokens (a one-time operation per conversation) and adding a constant bias to attention logits, with zero additional parameters.
417	
418	\section{Qualitative Steering Examples}\label{sec:appendix-examples}
419	
420	Table~\ref{tab:examples} illustrates the effect of $\beta$-steering on model behavior in a 4-turn conversation where the system prompt instructs ``Always respond in exactly three bullet points.''
421	
422	\begin{table*}[t]
423	\centering\small
424	\caption{Qualitative effect of $\beta$-steering on instruction following across conversation turns. System prompt: ``Always respond in exactly three bullet points.'' ThreadGate checkpoint, 4-turn conversation.}
425	\label{tab:examples}
426	\begin{tabular}{c p{5.5cm} p{5.5cm}}
427	\toprule
428	\textbf{Turn} & \textbf{$\beta$\,=\,0 (unsteered)} & \textbf{$\beta$\,=\,3 (steered)} \\
429	\midrule
430	1 & \checkmark~Three bullet points, on-topic & \checkmark~Three bullet points, on-topic \\
431	2 & \checkmark~Three bullet points, relevant & \checkmark~Three bullet points, relevant \\
432	3 & $\sim$~Four bullet points, partially on-topic & \checkmark~Three bullet points, on-topic \\
433	4 & \texttimes~Free-form paragraph, no bullets & \checkmark~Three bullet points, on-topic \\
434	\bottomrule
435	\end{tabular}
436	\end{table*}
437	
438	The pattern is consistent with the GAR decay analysis (\S\ref{sec:analysis}): unsteered models progressively lose attention to the system-prompt constraint, leading to format violations at later turns. Steering maintains goal-token attention, preserving instruction compliance. The per-category breakdown in Table~\ref{tab:ir-results} shows that content constraints benefit most from this effect.
439	
440	\section{Gradient Conflict Analysis}\label{sec:appendix-gradient}
441	
442	\begin{figure}[t]
443	  \centering
444	  \includegraphics[width=\columnwidth,height=0.42\textheight,keepaspectratio]{fig2_training_pcgrad.pdf}
445	  \caption{(a)~Training GAR convergence to target ($\tau$\,=\,0.5). (b)~PCGrad removes gradient conflict but $\mathcal{L}_\text{GAR}$ still collapses, confirming that gradient direction conflict is not the primary cause (\S\ref{subsec:pcgrad}).}
446	  \label{fig:training-pcgrad}
447	\end{figure}
448	
449	This section provides extended gradient interaction analysis supporting the PCGrad exclusion argument in \S\ref{subsec:pcgrad}. We measure per-layer cosine similarity between NTP and GAR gradients, gradient magnitude ratios, and the effect of PCGrad projection on these quantities.
450	
451	\paragraph{Gradient direction analysis.} Figure~\ref{fig:gradient-heatmap} visualizes the per-layer cosine similarity between NTP and GAR gradients across training epochs for both standard ThreadGate and PCGrad training. Under standard training, 79\% of layers show negative cosine similarity (gradient conflict) at epoch~0, declining to 68\% by epoch~2 as GAR loss converges to near-zero. This decline reflects diminishing GAR gradient magnitude rather than alignment improvement---as GAR loss approaches zero, the GAR gradient shrinks proportionally, making cosine similarity measurements less reliable (small gradients produce noisy direction estimates). Under PCGrad training, the conflict percentage decreases more slowly (79\%$\to$71\%), consistent with PCGrad projecting conflicting gradients onto the other's normal plane but not eliminating the underlying gradient conflict.
452	
453	\paragraph{Spatial patterns.} The early layers (L0--L5) and output-adjacent layers (L24--L27) show the strongest conflict, corresponding to the layers where gate values deviate most from identity (Figure~\ref{fig:gate-heatmap}). This spatial correlation is not causal: removing gradient conflict via PCGrad does not improve AR GAR, and gates at high-conflict layers are not systematically different from gates at low-conflict layers (Spearman $\rho$\,=\,$-$0.12, $p$\,=\,0.54 between gate value and conflict magnitude).
454	
455	\paragraph{Magnitude dominance.} NTP gradient magnitude dominates GAR by 7.5$\times$ at epoch~0 and 14.7$\times$ by epoch~2, as GAR loss converges while NTP loss remains at $\sim$0.93. This growing dominance means that even when directions oppose, the effective update direction is determined almost entirely by NTP. PCGrad addresses gradient conflict but not magnitude dominance---it projects conflicting gradients onto the other's normal plane (changing direction) but preserves relative magnitudes. The 7.5--14.7$\times$ magnitude ratio means that even after PCGrad projection, GAR contributes $<$7\% of the effective update magnitude, explaining why PCGrad is ineffective.
456	
457	\paragraph{Cross-model consistency.} Table~\ref{tab:gradient-crossmodel} confirms the pattern on Llama-3.1-8B: gradients are near-orthogonal (mean cosine $+$0.005, essentially zero) rather than systematically conflicting, with 25.7$\times$ NTP dominance. The Llama result is particularly informative because it shows that even without systematic gradient conflict (53\% negative layers, near chance), the same TF-AR gap persists. This cross-model evidence strengthens the \textit{modus tollens} argument: if gradient conflict were the cause, it should be present on both architectures; it is absent on Llama, yet the gap persists; therefore gradient direction conflict is not the primary cause.
458	
459	\begin{figure*}[t]
460	\centering
461	\includegraphics[width=0.95\textwidth]{fig_gradient_conflict_heatmap.pdf}
462	\caption{Per-layer cosine similarity between NTP and GAR gradients across training epochs. (a)~Standard training: conflict decreases from 79\% to 68\% of layers as GAR loss vanishes. (b)~PCGrad training: projection reduces conflict more slowly (79\%$\to$71\%) but does not improve AR GAR, ruling out gradient direction conflict as the primary cause (\S\ref{subsec:pcgrad}).}
463	\label{fig:gradient-heatmap}
464	\end{figure*}
465	
466	\section{Training Data Characteristics}\label{sec:appendix-data}
467	
468	All experiments use 8,000 multi-turn conversations sampled from the UltraChat \citep{ding2023ultrachat} training split. Table~\ref{tab:data-stats} summarizes the dataset characteristics. Conversations are truncated to 2,048 tokens; conversations shorter than 3 user turns are excluded to ensure sufficient multi-turn structure for GAR computation. The held-out evaluation sets use separate non-overlapping samples: $N$\,=\,50 conversations (mean 3.6 user turns) for the primary AR evaluation and $N$\,=\,5 conversations (10 turns each) for the long-conversation analysis (Appendix~\ref{sec:appendix-n5}).
469	
470	\begin{table}[t]
471	\centering\small
472	\caption{Training and evaluation data characteristics. All data from UltraChat \citep{ding2023ultrachat}.}
473	\label{tab:data-stats}
474	\begin{tabular}{lcc}
475	\toprule
476	\textbf{Property} & \textbf{Train} & \textbf{Eval (primary)} \\
477	\midrule
478	Conversations & 8,000 & 50 \\
479	Min user turns & 3 & 3 \\
480	Max sequence length & 2,048 & 2,048 \\
481	Source & UltraChat train & UltraChat train \\
482	Overlap & --- & non-overlapping \\
483	\bottomrule
484	\end{tabular}
485	\end{table}
486	
487	\section{Exposure Bias Scaling}\label{sec:appendix-eb-scaling}
488	
489	Figure~\ref{fig:eb-scaling} quantifies two scaling dimensions of the exposure bias phenomenon: cross-variant gap ratios (panel~a) and length-dependent gap compounding (panel~b).
490	
491	\paragraph{Cross-variant gaps.} On Qwen, ThreadGate achieves the smallest gap among standard variants (7.8$\times$) while PCGrad shows the largest (16.7$\times$, consistent with its counterproductive effect on AR GAR). Scheduled sampling reduces the gap to ${\sim}$1.3$\times$, the only variant approaching parity. The ordering of gap ratios (SS $\ll$ TG $<$ LoRA $<$ UG $<$ PCGrad) differs from the ordering of TF GAR (all $\approx$ 0.50), confirming that training-time optimization success does not predict inference-time robustness. On Llama, both ThreadGate and LoRA-only show $\sim$27$\times$ gaps (by median), larger than any Qwen variant. The consistently larger Llama gaps may reflect its deeper architecture (32 vs.\ 28 layers), which provides more layers for distributional drift to compound through.
492	
493	\paragraph{Length-dependent compounding.} Panel~(b) shows that the gap compounds with conversation length: at 3.6 mean turns ($N$\,=\,50), ThreadGate's gap is 8$\times$; at 10 turns ($N$\,=\,5), it widens to 31$\times$. The relationship is approximately linear in the number of turns on a log scale, suggesting that the per-turn drift contribution is roughly multiplicative. Extrapolating this trend suggests that at 20 turns the gap would exceed 100$\times$, making any training-time attention signal essentially undetectable. This length dependence is consistent with cumulative distributional drift---each model-generated turn introduces additional divergence from the teacher-forced training distribution, and by turn~10 the accumulated drift overwhelms any gating signal.
494	
495	\paragraph{Implications for deployment.} These scaling results have practical implications: (1)~for applications requiring sustained attention over many turns (e.g., long-form tutoring, multi-step reasoning), architectural modifications alone are insufficient---distributional robustification or inference-time intervention is necessary; (2)~the near-parity of scheduled sampling (${\sim}$1.3$\times$ gap) suggests that bridging the training-inference distribution gap is both necessary and sufficient for maintaining attention; (3)~the $\beta$-steering approach provides a complementary inference-time solution, but its effectiveness also depends on conversation length (Appendix~\ref{sec:appendix-steering-viz}).
496	
497	\begin{figure}[t]
498	\centering
499	\includegraphics[width=\columnwidth]{fig_eb_scaling.pdf}
500	\caption{Exposure bias scaling analysis. (a)~TF/AR gap ratio across training variants; scheduled sampling (SS, ${\sim}$1.3$\times$) is the only variant near parity. Llama gaps ($\sim$27$\times$) exceed all Qwen variants. (b)~Gap compounds with conversation length: ThreadGate's gap widens from 8$\times$ (3.6 turns) to 31$\times$ (10 turns).}
501	\label{fig:eb-scaling}
502	\end{figure}
503	
504	\section{Per-Turn AR GAR Dynamics}\label{sec:appendix-ar-gar-dynamics}
505	
506	To characterize how goal attention evolves across conversation turns under autoregressive generation, we compute per-turn AR GAR for all six Qwen-2.5-7B training configurations (Base, LoRA-only, Uniform Gate, PCGrad, Scheduled Sampling, ThreadGate) on the held-out evaluation set. Figure~\ref{fig:kl_ar_gar_curves} plots per-turn AR GAR trajectories across turns 1--5, and Figure~\ref{fig:kl_ar_gar_bar} compares mid-turn AR GAR levels across configurations.
507	
508	All six configurations exhibit monotonic GAR decay as turn index increases, consistent with cumulative exposure bias eroding attention to goal tokens. The decay rate varies substantially: Scheduled Sampling retains by far the highest mid-turn GAR (0.423), followed distantly by ThreadGate (0.064), LoRA-only (0.037), Uniform Gate (0.033), PCGrad (0.030), and Base (0.019). Base decays most rapidly, losing the majority of its initial GAR within the first few turns. The large SS--TG gap mirrors Table~\ref{tab:five-way} and confirms that distributional robustification---not gating architecture alone---is the primary driver of AR GAR retention.\footnote{SS configuration uses seed 123 data; all other configurations use seed 42. Cross-seed trends are consistent (\S\ref{subsec:ss}).}
509	
510	\begin{figure}[t]
511	\centering
512	\includegraphics[width=\columnwidth]{fig_kl_ar_gar_curves.pdf}
513	\caption{Per-turn AR GAR trajectories for six Qwen-2.5-7B configurations (turns 1--5). All models show monotonic decay; Scheduled Sampling retains far higher GAR throughout (0.53$\to$0.39), while the remaining five variants cluster below 0.13 and decay rapidly.}
514	\label{fig:kl_ar_gar_curves}
515	\end{figure}
516	
517	\begin{figure}[t]
518	\centering
519	\includegraphics[width=\columnwidth]{fig_kl_ar_gar_bar.pdf}
520	\caption{Mid-turn AR GAR comparison across six training configurations. Ranking from highest to lowest: Scheduled Sampling (0.423), ThreadGate (0.064), LoRA-only (0.037), Uniform Gate (0.033), PCGrad (0.030), Base (0.019).}
521	\label{fig:kl_ar_gar_bar}
522	\end{figure}
523	
524	This pattern contrasts with teacher-forced evaluation, where GAR remains relatively stable across turns for all configurations. Under teacher forcing, the model conditions on ground-truth context at each turn, preventing the distributional drift that causes GAR erosion in AR mode. The divergence between TF stability and AR decay provides turn-level evidence for the exposure bias mechanism described in \S\ref{sec:analysis}: training-time attention patterns are optimized for a distribution that AR generation progressively departs from.
525	
526	\section{Per-Head KL Divergence Analysis}\label{sec:appendix-kl}
527	
528	To test whether exposure bias selectively disrupts goal-attending heads rather than uniformly affecting all attention patterns, we compute per-head TF vs.\ AR attention divergence on 30 held-out conversations. For each of the 28 attention heads per layer (784 heads total), we measure the KL divergence $D_\text{KL}(p_\text{TF} \| p_\text{AR})$ between teacher-forced and autoregressive attention distributions, and the absolute GAR shift $\Delta\text{GAR} = |\text{GAR}_\text{TF} - \text{GAR}_\text{AR}|$. This head-level analysis provides diagnostic evidence for the exposure bias interpretation beyond the aggregate TF-AR gap.
529	
530	\begin{table}[t]
531	\centering\small
532	\caption{Per-head TF-AR divergence statistics for Base and ThreadGate (Qwen-2.5-7B, 30 conversations). TG trains more concentrated goal attention under TF, but these high-GAR heads shift most under AR ($r$\,=\,0.743).}
533	\label{tab:kl-perhead}
534	\begin{tabular}{lcc}
535	\toprule
536	\textbf{Metric} & \textbf{Base} & \textbf{TG} \\
537	\midrule
538	Mean $\Delta$GAR & 0.012 & 0.016 \\
539	Mean KL & 0.043 & 0.054 \\
540	Corr(TF\_GAR, $\Delta$GAR) & 0.673 & 0.743 \\
541	\bottomrule
542	\end{tabular}
543	\end{table}
544	
545	\paragraph{Selective disruption.} ThreadGate exhibits 35\% larger mean $\Delta$GAR (0.016 vs.\ 0.012) and 26\% larger mean KL (0.054 vs.\ 0.043) than Base. This is counterintuitive: the auxiliary GAR loss successfully trains more concentrated goal attention (higher TF GAR per head), but these very same heads shift more under AR generation. The correlation between per-head TF GAR and $\Delta$GAR is strong for both models ($r$\,=\,0.673 for Base, 0.743 for TG), confirming that heads with higher goal attention under teacher forcing are disproportionately disrupted under autoregressive generation. This selectivity is a hallmark of exposure bias: the training-time optimization succeeds at creating a specific attention pattern (concentrated goal attention), but precisely this pattern has no autoregressive counterpart because it depends on conditioning on ground-truth context.
546	
547	\paragraph{Layer-depth dependence.} The highest-KL heads concentrate at output-adjacent layers (L23--L27, KL\,$>$\,0.077) and L9 (KL\,$\approx$\,0.068). Output-adjacent layers participate most directly in next-token prediction, so their attention distributions are most sensitive to changes in the conditioning context. L9's elevated KL may reflect a ``routing layer'' phenomenon observed in multi-layer transformers, where specific intermediate layers specialize in long-range information routing. The depth dependence is consistent with cumulative error propagation: distributional drift from model-generated tokens accumulates as information flows through successive layers, producing the largest attention shifts at the deepest layers.
548	
549	\paragraph{Gate--KL independence.} Gate magnitude does not predict per-layer exposure bias severity: Spearman correlation between gate value and per-layer KL is 0.061 ($p$\,=\,0.757). The highest KL values concentrate at deep layers (L22--L27) where gates are near identity ($\approx$1.0), while the lowest-gate layers show below-average KL (0.041 vs.\ 0.056 for highest-gate layers). This independence confirms that the gating mechanism and the exposure bias phenomenon operate on different axes: gates modulate the magnitude of residual contributions, while exposure bias disrupts the direction (attention distribution) of those contributions. Even a ``perfect'' gate that could fully attenuate certain layers' residuals would not address the fundamental distributional mismatch that causes the attention shift.
550	
551	\section{GAR Definition Robustness}\label{sec:appendix-gar-robust}
552	
553	To assess whether our conclusions depend on the specific GAR definition, we evaluate four alternative token-position variants on 50 held-out conversations (Table~\ref{tab:gar-robust}): (1)~\emph{ours} (last-token): attention from the last token to goal tokens (standard GAR-ours); (2)~\emph{all-token}: average attention from all tokens to goal tokens; (3)~\emph{first-token}: attention from the first assistant token to goal tokens; (4)~\emph{goal-only}: attention from the last token to system-prompt-only tokens (excluding conversation content).
554	
555	\begin{table}[t]
556	\centering\small
557	\caption{Mid-turn GAR under four alternative definitions ($N$\,=\,50 conversations). ThreadGate only improves query-position-specific definitions (last-token, goal-only); Scheduled Sampling raises all four definitions above 0.36.}
558	\label{tab:gar-robust}
559	\begin{tabular}{lccc}
560	\toprule
561	\textbf{Definition} & \textbf{Base} & \textbf{TG} & \textbf{SS} \\
562	\midrule
563	Ours (last-token) & 0.015 & \textbf{0.325} & \textbf{0.458} \\
564	All-token & 0.015 & 0.025 & \textbf{0.366} \\
565	First-token & 0.022 & 0.039 & \textbf{0.412} \\
566	Goal-only & 0.005 & \textbf{0.310} & \textbf{0.444} \\
567	\bottomrule
568	\end{tabular}
569	\end{table}
570	
571	ThreadGate improvements are query-position-specific: the two definitions using the last token as query (ours: $0.015 \to 0.325$; goal-only: $0.005 \to 0.310$) show large gains, while all-token ($0.025$) and first-token ($0.039$) remain near base levels. This is expected: the GAR loss optimizes attention at the last-token position, so the learned routing does not generalize to other query positions.
572	
573	Scheduled Sampling raises all four definitions above 0.36, with no definition falling below Base-relative gains. This confirms that SS builds a broad goal-attention pattern across token positions, rather than overfitting to the specific position targeted by the GAR loss. The pattern holds regardless of GAR definition: both the exposure bias diagnosis and the SS mitigation are robust to metric choice.
574	
575	\section{General Capability Preservation (MMLU)}\label{sec:appendix-mmlu}
576	
577	To confirm that auxiliary GAR losses and attention steering do not degrade general language understanding, we evaluate all six Qwen-2.5-7B variants on MMLU 5-shot \citep{hendrycks2021measuring} ($N$\,=\,14{,}042 questions).
578	
579	\begin{table}[t]
580	\centering\small
581	\caption{MMLU 5-shot accuracy on Qwen-2.5-7B-Instruct. All fine-tuned variants remain within 0.8\,pp of the base LoRA-only checkpoint.}
582	\label{tab:mmlu}
583	\begin{tabular}{lcc}
584	\toprule
585	\textbf{Model} & \textbf{Acc (\%)} & \textbf{$\Delta$ vs Base} \\
586	\midrule
587	Base (LoRA-only) & 74.23 & --- \\
588	PCGrad & 73.86 & $-$0.38 \\
589	SS & 73.75 & $-$0.48 \\
590	LoRA-only & 73.57 & $-$0.66 \\
591	ThreadGate & 73.47 & $-$0.77 \\
592	Uniform Gate & 73.46 & $-$0.78 \\
593	\bottomrule
594	\end{tabular}
595	\end{table}
596	
597	All variants degrade by $<$0.8\,pp, confirming that attention steering and auxiliary GAR losses do not harm general language understanding. The ordering does not track GAR performance (e.g., PCGrad shows the smallest MMLU drop despite the worst AR GAR), consistent with GAR and NTP occupying largely orthogonal subspaces.
598	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "84eb8edd-6b2f-4cdc-8cdc-95b14ea3780f",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "2c16b124-20d5-486e-80de-a6213ad1ecc3",
  "sourceToolAssistantUUID": "84eb8edd-6b2f-4cdc-8cdc-95b14ea3780f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-25T20:13:33.299Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DfqD6XPFVkCG7mE7VQzuwV`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/docs/paper/sections/appendix.tex",
  "offset": 598,
  "limit": 250
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2c16b124-20d5-486e-80de-a6213ad1ecc3",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu52jREfQJ28esAFcT7",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3e413c86-fb09-4fe8-96e5-e9418a3b4dbd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TtSpLXve6W7UipiDzerpM9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6790,
      "cache_read_input_tokens": 37452,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6790,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 36,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 27 · 2026-05-25T20:13:33.600Z_

<details><summary>↩ Tool result · `toolu_01DfqD6XPFVkCG7mE7VQzuwV`</summary>

```text
598	
599	\section{Cross-Scale Validation (Qwen-2.5-1.5B)}\label{sec:appendix-1.5b}
600	
601	We validate cross-scale on Qwen-2.5-1.5B-Instruct to test whether goal attention decay and $\beta$-steering generalize to smaller models.
602	
603	\paragraph{Phase~1 GAR decay.} The 1.5B base model exhibits 79.8\% GAR decline from turn~1 to mid-turns (vs.\ 70.8\% on 7B), confirming that attention decay is present across scales and is more severe at smaller model sizes.
604	
605	\paragraph{Steering evaluation.} Table~\ref{tab:1.5b-steering} reports AR evaluation ($N$\,=\,50). We report median PPL because Base $\beta$\,=\,3 contains a catastrophic outlier (conversation~\#11, PPL\,$>$\,$10^8$) that inflates the mean.\footnote{The outlier occurs in a single conversation where $\beta$-steering causes the base model to enter a degenerate repetition loop. ThreadGate produces zero such outliers across all $\beta$ values, suggesting the gate provides stability against catastrophic steering failures.}
606	
607	\begin{table}[t]
608	\centering\small
609	\caption{Cross-scale $\beta$-steering on Qwen-2.5-1.5B ($N$\,=\,50, AR). PPL is median due to catastrophic Base outlier at $\beta$\,=\,3. TG eliminates outliers across all $\beta$ values.}
610	\label{tab:1.5b-steering}
611	\begin{tabular}{llcc}
612	\toprule
613	\textbf{Model} & $\beta$ & \textbf{AR GAR} & \textbf{PPL (med)} \\
614	\midrule
615	Base & 0 & 0.017 & 1.909 \\
616	TG & 0 & 0.023 & 1.897 \\
617	\midrule
618	Base & 3 & 0.120 & 2.216 \\
619	TG & 3 & 0.114 & 1.975 \\
620	\midrule
621	Base & 5 & 0.657 & 2.804 \\
622	TG & 5 & 0.715 & 2.624 \\
623	\bottomrule
624	\end{tabular}
625	\end{table}
626	
627	The steering pattern mirrors the 7B results: $\beta$\,=\,5 recovers GAR to 0.657--0.715 ($p < 0.001$), confirming that attention misallocation is the proximal cause of GAR collapse across scales. At $\beta$\,=\,0, TG shows a small but significant GAR advantage ($p$\,=\,0.005); at $\beta$\,=\,3, the TG--Base difference is not statistically significant ($p$\,=\,0.815), unlike the 7B pattern where TG consistently outperforms Base. This scale-specific difference may reflect the 1.5B model's limited capacity to maintain learned routing at intermediate steering strengths. ThreadGate does provide a stability advantage---zero catastrophic PPL outliers vs.\ one in Base---suggesting that residual gating regularizes attention distributions even when aggregate GAR is comparable.
628	
629	\section{Per-Seed Detailed Results}\label{sec:appendix-perseed}
630	
631	Tables~\ref{tab:perseed-ss} and~\ref{tab:perseed-tg} report full per-seed breakdowns for the two multi-seed configurations, providing evidence that our main findings are robust to random initialization.
632	
633	\paragraph{Scheduled sampling (3 seeds).} TF GAR-ours averages $0.517\pm0.032$ across seeds under the held-out protocol (Table~\ref{tab:perseed-ss}); under IID evaluation, TF is more stable ($0.499\pm0.003$), with the held-out variance driven by seed~123's higher value on the larger $N$\,=\,200 sample. AR GAR shows meaningful variance (std\,=\,0.047): seed 42 produces the lowest AR GAR (0.347, gap 1.4$\times$), seed 123 is intermediate (0.423, gap 1.3$\times$), and seed 456 is highest (0.433, gap 1.2$\times$). This variance is expected: AR evaluation involves free-form generation where small differences in learned attention patterns can compound across turns. The variance is asymmetric---all seeds remain well above the non-SS baseline (0.064)---so the qualitative conclusion (SS provides order-of-magnitude improvement) holds across seeds. At $\beta$\,=\,5, the cross-seed variance nearly vanishes ($0.717\pm0.001$), confirming that strong steering converges to a seed-independent attention equilibrium that overwhelms initialization differences.
634	
635	\paragraph{ThreadGate (2 seeds).} Two seeds produce nearly identical TF metrics ($0.504\pm0.001$) and similar AR GAR (0.064 vs.\ 0.055), with gap ratios of 7.8$\times$ and 9.1$\times$ respectively. The 15\% relative difference in AR GAR is small compared to the order-of-magnitude TF-AR gap, confirming that the exposure bias phenomenon is not seed-dependent.
636	
637	\paragraph{Training dynamics.} Seed variance in training time is non-trivial for scheduled sampling: seed 123 requires 10.8 hours (80\% overhead) vs.\ 6.5 hours for seeds 42 and 456 (8\% overhead). This variance is driven by the stochastic Bernoulli sampling of model-generated contexts: seed 123 happens to trigger longer autoregressive generation episodes early in training, where the model produces longer outputs before hitting the max-length cutoff. Despite this training-time variance, all three seeds converge to similar final metrics, suggesting the optimization landscape is robust.
638	
639	\input{../artifacts/appendix_expansion/tab_perseed_ss.tex}
640	
641	\input{../artifacts/appendix_expansion/tab_perseed_tg.tex}
642	
643	\section{Per-Turn GAR Decay Analysis}\label{sec:appendix-perturn-detail}
644	
645	Tables~\ref{tab:perturn-qwen} and~\ref{tab:perturn-llama} present per-turn AR GAR values for all configurations on both architectures, complementing the aggregate mid-turn GAR reported in the main text (Table~\ref{tab:five-way}).
646	
647	\paragraph{Qwen per-turn dynamics.} On Qwen (Table~\ref{tab:perturn-qwen}), all non-SS variants show rapid monotonic decay: turn-1 GAR ranges from 0.085 (Base) to 0.130 (ThreadGate), but by turn~5 all collapse below 0.07. The decay rate is approximately exponential for the first 3 turns, then plateaus near a floor value that varies by configuration (Base: 0.004, ThreadGate: 0.043--0.066, LoRA-only: 0.040). ThreadGate and LoRA-only show occasional turn-level fluctuations (e.g., TG turn~5 = 0.066 $>$ turn~4 = 0.043), which reflect stochastic variation in individual conversations rather than systematic recovery. Scheduled sampling retains substantially higher GAR throughout (turn-5 GAR\,=\,0.365 vs.\ 0.066 for ThreadGate), with a much flatter decay profile (15\% decline from turn~1 to turn~5 vs.\ 49\% for ThreadGate). This flatter profile is the signature of distributional robustification: SS-trained models encounter model-generated context during training, so the attention patterns are calibrated for the distribution they actually face during inference.
648	
649	\paragraph{Llama per-turn dynamics.} On Llama (Table~\ref{tab:perturn-llama}), the decay is steeper: Base GAR drops from 0.028 to 0.008 over 4 turns (71\% decline in the $N$\,=\,20 evaluation), and from 0.026 to 0.003 over 10 turns (88\% decline in the $N$\,=\,5 long-conversation evaluation). ThreadGate on Llama shows a distinctive pattern: turn-level GAR is roughly constant (0.038--0.049) rather than monotonically declining, suggesting that the gating mechanism maintains a stable floor on Llama that it fails to maintain on Qwen. However, this floor (0.04) is still an order of magnitude below the TF target (0.484), confirming that the fundamental TF-AR gap persists.
650	
651	\paragraph{Cross-architecture comparison.} The per-turn decay profiles reveal an architectural difference: Qwen shows a sharper initial decline (turn~1 to turn~2: $-$62\% for Base) followed by a plateau, while Llama shows a more gradual and sustained decline throughout. This difference may reflect the two architectures' different attention head configurations and layer counts, but the qualitative pattern---monotonic or near-monotonic decline toward a near-zero floor---is universal.
652	
653	Figures~\ref{fig:perturn-qwen-detail} and~\ref{fig:perturn-llama-detail} visualize these trajectories.
654	
655	\input{../artifacts/appendix_expansion/tab_perturn_qwen.tex}
656	
657	\begin{figure}[t]
658	  \centering
659	  \includegraphics[width=\columnwidth]{fig_perturn_qwen_detail.pdf}
660	  \caption{Per-turn AR GAR-ours across six Qwen-2.5-7B configurations. Scheduled sampling (green) retains far higher GAR than all other variants, which cluster below 0.13 and decay rapidly.}
661	  \label{fig:perturn-qwen-detail}
662	\end{figure}
663	
664	\input{../artifacts/appendix_expansion/tab_perturn_llama.tex}
665	
666	\begin{figure}[t]
667	  \centering
668	  \includegraphics[width=\columnwidth]{fig_perturn_llama_detail.pdf}
669	  \caption{Per-turn AR GAR decay on Llama-3.1-8B. (a)~Three-way comparison (Base, TG, LoRA-only; $N$\,=\,20, 4 turns). (b)~Extended Base decay profile ($N$\,=\,5, 10 turns), showing 90\% decline.}
670	  \label{fig:perturn-llama-detail}
671	\end{figure}
672	
673	\section{Extended Dataset Statistics}\label{sec:appendix-dataset-ext}
674	
675	Table~\ref{tab:dataset_stats} provides detailed statistics for the UltraChat training and evaluation splits. From the full UltraChat-200K corpus (207,865 conversations in the \texttt{train\_sft} split), we filter for conversations with $\geq$5 assistant turns, yielding 17,302 candidates (8.3\% of the full corpus). We randomly sample 8,000 for training, 50 for primary AR evaluation (mean 3.6 user turns), 50 for IID GAR diagnostics, and 200 for the instruction retention evaluation.
676	
677	\paragraph{Filtering rationale.} The $\geq$5 assistant turns threshold was chosen empirically: conversations with fewer than 3 assistant turns do not exhibit measurable attention decay (turn-1 to turn-3 GAR decline $<$5\%), making them uninformative for studying multi-turn exposure bias. The 5-turn threshold provides sufficient turn depth while retaining a reasonable fraction of the corpus. The average conversation in the filtered set contains 5.6 assistant turns (range: 5--7), with a mean sequence length of 1,247 tokens after tokenization with the Qwen-2.5 tokenizer.
678	
679	\paragraph{Evaluation split design.} We maintain four non-overlapping evaluation sets to avoid contamination: (1)~the primary AR evaluation ($N$\,=\,50) uses the same conversation structure as training but with held-out conversations, enabling direct comparison of TF vs.\ AR behavior; (2)~the IID GAR diagnostic ($N$\,=\,50) uses a separate sample for ablation studies that require independent measurements; (3)~the large instruction retention set ($N$\,=\,200) provides sufficient statistical power for per-category compliance analysis across 18 constraint types; (4)~the long-conversation set ($N$\,=\,5, 10 turns each) tests scaling behavior beyond the training distribution.
680	
681	\paragraph{Domain diversity.} UltraChat covers a broad range of conversational topics including knowledge Q\&A, creative writing, reasoning, and open-ended discussion. We do not stratify by topic, as our focus is on the architectural mechanism (attention routing) rather than domain-specific performance. The topic diversity serves as implicit regularization against overfitting to specific conversation patterns.
682	
683	\input{../artifacts/appendix_expansion/tab_dataset_stats.tex}
684	
685	\section{Extended GAR Robustness Analysis}\label{sec:appendix-gar-ext}
686	
687	Table~\ref{tab:gar_robustness} and Figure~\ref{fig:gar-robust-grouped} extend the GAR robustness analysis from \S\ref{sec:appendix-gar-robust} with turn-1 GAR and gap ratio metrics across all four token-position variants. We evaluate four ways to select the query token position for gradient attribution: (1)~\textit{Last} (our default): the final token of each assistant turn, which captures the model's ``summary'' attention pattern at the prediction boundary; (2)~\textit{All}: the mean over all assistant tokens, providing a position-averaged view; (3)~\textit{First}: the first assistant token, which reflects initial attention allocation; (4)~\textit{Goal-only}: attention to goal tokens as defined by \citet{dongre2026attention}, which restricts the target set to system-prompt tokens.
688	
689	\paragraph{Position-specific vs.\ broad improvement.} The key finding is a clear dichotomy between ThreadGate and Scheduled Sampling. ThreadGate improvements are restricted to last-token and goal-only positions (the two definitions sharing the query position targeted by the GAR loss): gap ratios drop to 1.21$\times$ and 1.07$\times$ respectively. All-token (5.04$\times$) and first-token (8.24$\times$) GAR remain near base levels, confirming that the learned routing is position-specific. Scheduled Sampling raises all four definitions above 0.36 with gap ratios $\leq$1.83$\times$, demonstrating that distributional robustification builds broad goal attention across token positions rather than overfitting to the position targeted by the loss.
690	
691	\paragraph{Turn-1 vs.\ mid-turn dynamics.} Turn-1 GAR is consistently higher than mid-turn GAR across all definitions and conditions, reflecting the first turn's proximity to the ground-truth prefix in training. The gap ratio quantifies how much of this initial attention survives into later turns. First-token GAR shows the largest gap ratios (Base: 13.3$\times$, TG: 8.2$\times$), indicating that the first-token position is most vulnerable to distributional drift---the initial token's attention pattern is highly dependent on the conditioning context, which diverges most from training under autoregressive generation.
692	
693	\input{../artifacts/appendix_expansion/tab_gar_robustness.tex}
694	
695	\begin{figure}[t]
696	  \centering
697	  \includegraphics[width=\columnwidth]{fig_gar_robustness_grouped.pdf}
698	  \caption{Mid-turn GAR across four token-position definitions. SS raises all four above 0.36; TG only improves last-token and goal-only.}
699	  \label{fig:gar-robust-grouped}
700	\end{figure}
701	
702	\section{MMLU Category Breakdown}\label{sec:appendix-mmlu-ext}
703	
704	Table~\ref{tab:mmlu_detail} breaks down MMLU 5-shot accuracy by category (STEM, Social Sciences, Humanities, Other) for all six Qwen-2.5-7B training configurations. This analysis addresses a potential concern: that auxiliary attention objectives might divert representational capacity from general language understanding, particularly in knowledge-intensive STEM domains.
705	
706	\paragraph{Per-category analysis.} The maximum per-category degradation is 1.2\,pp (ThreadGate on STEM), and no category shows systematic degradation across all variants. Notably, the ordering of variants differs across categories: ThreadGate shows the largest STEM drop but the smallest Humanities drop, while PCGrad shows the smallest overall drop despite having the worst AR GAR. This lack of correlation between GAR performance and MMLU degradation is consistent with GAR and NTP occupying largely orthogonal parameter subspaces---the LoRA adapter capacity (4.2M parameters) is sufficient to accommodate both objectives without interference.
707	
708	\paragraph{Statistical significance.} The per-category differences are small relative to the evaluation noise: with $N$\,=\,14,042 questions total ($\sim$3,500 per category), a 0.8\,pp accuracy difference corresponds to $\sim$28 questions, well within expected stochastic variation for 5-shot in-context learning. A chi-squared test comparing the best (PCGrad, 73.86\%) and worst (Uniform Gate, 73.46\%) variants yields $p$\,=\,0.503, confirming no significant difference. The category-level stability confirms that auxiliary GAR losses and gating do not selectively harm any knowledge domain.
709	
710	Figure~\ref{fig:mmlu-comparison} visualizes the per-category comparison, showing tight clustering across all variants within each category.
711	
712	\input{../artifacts/appendix_expansion/tab_mmlu_detail.tex}
713	
714	\begin{figure}[t]
715	  \centering
716	  \includegraphics[width=\columnwidth]{fig_mmlu_comparison.pdf}
717	  \caption{MMLU 5-shot accuracy by category across training configurations. All variants remain within 1.2\,pp of the LoRA-only baseline across all categories.}
718	  \label{fig:mmlu-comparison}
719	\end{figure}
720	
721	\section{Extended Cross-Scale Results (Qwen-2.5-1.5B)}\label{sec:appendix-1.5b-ext}
722	
723	Table~\ref{tab:qwen15b_results} extends the cross-scale analysis with Phase~1 GAR diagnostics, detailed Phase~2 training results, and $\beta$-steering evaluation on the Qwen-2.5-1.5B-Instruct model.
724	
725	\paragraph{Phase 1: GAR decay.} The 1.5B base model exhibits 79.8\% relative GAR decline from turn~1 to mid-turns, more severe than the 7B model's 70.8\% decline. This scale-dependent decay severity is consistent with smaller models having less redundant attention capacity: with 28 layers but only 1.5B parameters (vs.\ 7B), each layer carries proportionally more of the total representational burden, leaving less room for goal-oriented attention to persist alongside the primary NTP objective.
726	
727	\paragraph{Phase 2: Training.} ThreadGate training on 1.5B converges to TF GAR-ours of 0.498 with PPL of 2.67, closely matching the 7B results (0.504 / 2.78). The gate parameter count scales linearly with layer count (identical architecture, so ${\sim}$57K gate parameters). Training completes in 2.1 hours vs.\ 6.0 hours for 7B, reflecting the smaller model's reduced forward/backward pass cost.
728	
729	\paragraph{Steering evaluation.} At $\beta$\,=\,5, ThreadGate recovers GAR to 0.715 ($p < 0.001$), closely matching the 7B result (0.727). The recovery is essentially scale-independent at the strong steering regime: the attention bias added by $\beta$-steering overwhelms any capacity differences. At $\beta$\,=\,3, the picture differs: the TG--Base difference is not statistically significant ($p$\,=\,0.815) on 1.5B, unlike the significant difference on 7B ($p$\,=\,0.039). This scale-dependent response at intermediate $\beta$ may reflect the 1.5B model's reduced capacity for fine-grained attention routing: with fewer parameters per layer, the model cannot sustain the subtle attention reweighting that $\beta$\,=\,3 attempts.
730	
731	\paragraph{Catastrophic outliers.} Base 1.5B at $\beta$\,=\,3 produces one catastrophic PPL outlier (conversation \#11, PPL $> 10^8$) caused by a degenerate repetition loop. ThreadGate produces zero such outliers across all $\beta$ values, suggesting the gate provides a stabilizing effect on attention distributions even when aggregate GAR is comparable. We report median PPL to avoid this outlier dominating the central tendency estimate.
732	
733	\input{../artifacts/appendix_expansion/tab_qwen15b_results.tex}
734	
735	\section{Extended Statistical Analysis}\label{sec:appendix-stats-ext}
736	
737	Table~\ref{tab:statistical_tests} consolidates all statistical tests reported in this paper, including effect sizes, 95\% bootstrap confidence intervals, and significance levels. This section provides methodological detail beyond the summary in Appendix~\ref{sec:appendix-stats}.
738	
739	\paragraph{Test selection rationale.} All primary comparisons use paired Wilcoxon signed-rank tests on $N$\,=\,39 conversations (those with $\geq$3 turns from the 50-conversation held-out set). We use non-parametric tests because per-conversation GAR distributions are heavily right-skewed (skewness $>$ 2.0 for Base and PCGrad at $\beta$\,=\,0), violating normality assumptions required by parametric alternatives. The pairing structure (same conversations evaluated under different training configurations) controls for conversation-level confounds (topic difficulty, conversation length, system-prompt complexity).
740	
741	\paragraph{Effect size interpretation.} Effect sizes are computed as rank-biserial correlations ($r = Z / \sqrt{N}$), following standard practice. The largest effect is SS vs.\ TG ($r$\,=\,0.869, $p < 0.001$), a large effect by conventional thresholds ($r \geq 0.5$), confirming that scheduled sampling produces a qualitatively different outcome. The TG vs.\ Base effect ($r$\,=\,0.802) is also large, while TG vs.\ LoRA-only ($r$\,=\,0.454) is medium, reflecting the modest incremental benefit of gating over LoRA alone.
742	
743	\paragraph{Steering dose-response pattern.} At $\beta$\,=\,0, all four comparisons are significant ($p \leq 0.004$). At $\beta$\,=\,3 (the phase transition), TG vs.\ Base becomes marginally significant ($p$\,=\,0.039) and SS vs.\ TG remains significant ($p$\,=\,0.010), but TG vs.\ LoRA-only and PCGrad vs.\ TG lose significance ($p > 0.7$). At $\beta$\,=\,5, no pairwise comparison reaches significance---steering dominates and equalizes all variants. This dose-response pattern confirms that the training-time variant effects are real but small relative to the inference-time steering effect.
744	
745	\paragraph{Instruction retention.} The instruction retention analysis uses McNemar's test on $N$\,=\,54 paired constraint evaluations (18 constraint types $\times$ 3 conversations). The marginal significance ($p$\,=\,0.077) reflects the small sample size rather than a null effect: the point-biserial correlation ($r$\,=\,0.200, $p$\,=\,0.007) is significant when treating compliance as a continuous variable, and the per-category breakdown (Table~\ref{tab:ir-results}) shows a clear content-constraint improvement (+23.8\,pp).
746	
747	\paragraph{Multiple comparisons.} We report uncorrected $p$-values for the same reason described in Appendix~\ref{sec:appendix-stats}: comparisons are hypothesis-driven (each tests a specific causal exclusion in the analysis chain), not exploratory. All reported significant results ($p \leq 0.039$) survive Holm-Bonferroni correction for the 4 primary comparisons within each $\beta$ level.
748	
749	\input{../artifacts/appendix_expansion/tab_statistical_tests.tex}
750	
751	\section{Extended Training Dynamics}\label{sec:appendix-training-ext}
752	
753	Figure~\ref{fig:training-6panel} presents the complete training loss landscape for all five Qwen-2.5-7B conditions (ThreadGate, +PCGrad, Uniform Gate, LoRA-only, Scheduled Sampling) plus the base model, showing NTP loss, GAR loss, and total loss across three epochs.
754	
755	\paragraph{NTP loss convergence.} All fine-tuned variants converge to NTP loss ${\sim}$0.93 by epoch~3, with final-epoch values ranging from 0.929 (LoRA-only) to 0.934 (ThreadGate). PCGrad shows marginally higher variance due to gradient projection, but converges to the same terminal value. The uniformity of NTP convergence across variants---including those with auxiliary losses (ThreadGate, PCGrad) and those without (LoRA-only)---confirms that the GAR auxiliary objective does not interfere with the primary language modeling task during training.
756	
757	\paragraph{GAR loss dynamics.} GAR loss collapses to near-zero within the first epoch under teacher forcing across all variants, consistent with the auxiliary objective being easy to optimize when the model conditions on ground-truth context. This rapid convergence is a double-edged sword: while it confirms that the MSE formulation (v7) achieves stable optimization, the ease of convergence also means the model never learns to maintain attention under distributional drift. The scheduled sampling variant shows distinctive dynamics: higher initial GAR loss variance from stochastic context mixing, with occasional spikes when a particularly challenging model-generated context is sampled, followed by convergence to a similar final value.
758	
759	\paragraph{Training-inference disconnect.} The key observation is that training-time convergence is indistinguishable across variants: an observer with access only to training curves could not predict the 5.4$\times$ AR GAR difference between SS and TG. This disconnect reinforces the diagnosis that the failure occurs at the training-to-inference transition, not during optimization, and explains why architectural modifications (gating, PCGrad) that operate during training cannot address the fundamental distributional mismatch.
760	
761	\begin{figure*}[t]
762	  \centering
763	  \includegraphics[width=0.75\textwidth]{fig_training_curves_6panel.pdf}
764	  \caption{Training loss curves for all five Qwen conditions. NTP loss (left) converges to ${\sim}$0.93 across variants; GAR loss (center) collapses within epoch~1; total loss (right) is NTP-dominated. Training-time behavior is indistinguishable; the failure emerges only at inference.}
765	  \label{fig:training-6panel}
766	\end{figure*}
767	
768	\section{Per-$\beta$ Steering Visualization}\label{sec:appendix-steering-viz}
769	
770	Figure~\ref{fig:steering-4panel} visualizes per-turn GAR trajectories under four steering strengths ($\beta$\,=\,0, 3, 5, 10), revealing the turn-level dynamics that underlie the aggregate steering results in Table~\ref{tab:steering-full}.
771	
772	\paragraph{Unsteered baseline ($\beta$\,=\,0).} GAR decays monotonically from 0.12 to 0.02 over five turns, with the steepest decline between turns~1 and~2 ($-$44\%). This trajectory matches the per-turn profiles in Appendix~\ref{sec:appendix-perturn-detail} and confirms that the decay is a smooth, progressive phenomenon rather than a discrete failure at a specific turn.
773	
774	\paragraph{Phase transition ($\beta$\,=\,3).} Turn-1 GAR jumps to ${\sim}$0.55, but per-turn decay persists (${\sim}$15\% decline from turn~1 to turn~5). This indicates that steering partially compensates for the distributional drift but does not eliminate it: the attention bias adds a constant offset to goal-token logits, while the drift compounds multiplicatively across turns. The residual decay at $\beta$\,=\,3 explains why this operating point shows the strongest training-variant effects in the dose-response analysis (Appendix~\ref{sec:appendix-stats-ext}).
775	
776	\paragraph{Sustained recovery ($\beta$\,=\,5).} GAR is sustained above 0.6 throughout, with minimal per-turn decay ($<$5\% decline). At this steering strength, the constant attention bias dominates the per-turn drift, effectively replacing the lost training-time signal with an inference-time substitute. The 9\% PPL cost (1.43 $\to$ 1.77) is modest compared to the order-of-magnitude GAR recovery.
777	
778	\paragraph{Saturation regime ($\beta$\,=\,10).} GAR saturates near 1.0 across all turns but PPL degrades catastrophically ($>$3.5), as the excessive attention bias distorts the attention distribution beyond the model's capacity for coherent generation. This regime is impractical and serves as an upper bound on the steering approach.
779	
780	\paragraph{Operating region.} The region $\beta \in [3, 5]$ balances GAR recovery against PPL cost, and the per-turn profiles confirm that steering must counteract an ongoing distributional drift rather than a one-time initialization failure---a key diagnostic that distinguishes exposure bias from alternative hypotheses (e.g., capacity limitations or optimization failures).
781	
782	\begin{figure}[t]
783	  \centering
784	  \includegraphics[width=\columnwidth]{fig_steering_perturn_4panel.pdf}
785	  \caption{Per-turn GAR under four $\beta$-steering strengths. At $\beta$\,=\,0, monotonic decay; at $\beta$\,=\,3, partial recovery with residual decay; at $\beta$\,=\,5, sustained high GAR; at $\beta$\,=\,10, saturation with catastrophic PPL.}
786	  \label{fig:steering-4panel}
787	\end{figure}
788	
789	\section{Llama-3.1-8B Scheduled Sampling Details}\label{sec:appendix-llama-ss}
790	
791	Llama-3.1-8B-Instruct was trained with scheduled sampling using the same protocol as Qwen (\S\ref{sec:appendix-ss}), with one key difference: training was stopped at 2 epochs (${\sim}$14{,}400 steps) instead of 3, because Llama's per-step wall-clock time was ${\sim}$4$\times$ slower than Qwen on the same hardware (624 steps/h vs.\ ${\sim}$2{,}400 steps/h for Qwen). This is attributable to different vocabulary sizes (Llama 128K vs.\ Qwen 152K tokens) and attention implementation. The 2-epoch checkpoint was selected based on convergence of TF GAR (0.477, within 0.02 of Qwen's 3-epoch value 0.498).
792	
793	\paragraph{$\beta$-steering on Llama SS.}
794	Table~\ref{tab:llama-ss-steering} reports $\beta$-steering results on the Llama SS model. Unlike Qwen, $\beta$\,=\,3 does not trigger recovery on Llama (GAR 0.173 vs.\ 0.166 at $\beta$\,=\,0). At $\beta$\,=\,5, GAR reaches 0.791---higher than Qwen's 0.717---suggesting that Llama's attention distribution is more responsive to the additive bias at higher steering strengths, possibly because the lower baseline AR GAR leaves more headroom for steering to exploit.
795	
796	\begin{table}[t]
797	\centering\small
798	\caption{$\beta$-steering on Llama-3.1-8B SS model ($N$\,=\,50, $T$\,=\,4).}
799	\label{tab:llama-ss-steering}
800	\begin{tabular}{@{}l ccc@{}}
801	\toprule
802	& $\beta$\,=\,0 & $\beta$\,=\,3 & $\beta$\,=\,5 \\
803	\midrule
804	AR GAR & 0.166 & 0.173 & 0.791 \\
805	\bottomrule
806	\end{tabular}
807	\end{table}
808	
809	\paragraph{Cross-model comparison.}
810	Table~\ref{tab:llama-vs-qwen-ss} compares scheduled sampling across both architectures. Both models show large gap compression relative to their ThreadGate baselines, but the residual gap on Llama (2.9$\times$) is larger than Qwen's (1.2$\times$). We attribute this to training duration: Llama received only 2 epochs of scheduled sampling exposure versus Qwen's 3 epochs. Llama reduces its median-based gap by 9.3$\times$ (from 27$\times$ to 2.9$\times$) while Qwen reduces by 6.5$\times$ (from 7.8$\times$ to 1.2$\times$), suggesting that a third epoch would likely narrow the residual gap further. Notably, $\beta$-steering is more effective on Llama (0.791 vs.\ 0.717 at $\beta$\,=\,5), partially compensating for the weaker training-time compression.
811	
812	\paragraph{Architectural differences.}
813	Several architectural differences between Qwen-2.5-7B and Llama-3.1-8B may contribute to the cross-model gap variation. Llama uses Grouped Query Attention (GQA) with 8 KV heads (vs.\ Qwen's full 28-head multi-head attention, MHA), which reduces the number of independently steerable attention heads by 3.5$\times$. Llama also uses Rotary Position Embedding (RoPE) with a longer default context (128K tokens vs.\ Qwen's 32K), which may affect how positional information interacts with goal-token attention at different conversation depths. Despite these differences, the qualitative pattern is identical: TF convergence, AR collapse, and SS-mediated recovery, confirming that exposure bias on auxiliary attention losses is architecture-general rather than an artifact of a specific attention implementation.
814	
815	\paragraph{Training dynamics.}
816	The Llama SS training loss trajectory closely mirrors Qwen's during the first two epochs: NTP loss converges within epoch~1 (final NTP loss 0.62 for Llama vs.\ 0.58 for Qwen), while GAR loss continues to decrease throughout epoch~2. The scheduled sampling ratio reaches ${\sim}$0.20 at the end of epoch~2 (vs.\ 0.30 at end of epoch~3 for Qwen), meaning Llama was exposed to less model-generated context during training. This partial exposure is sufficient to achieve meaningful gap compression (27$\times$ $\to$ 2.9$\times$ by median) but leaves a larger residual gap than Qwen's full 3-epoch schedule.
817	
818	\begin{table}[t]
819	\raggedright\small
820	\caption{Scheduled sampling comparison: Qwen-2.5-7B vs.\ Llama-3.1-8B.}
821	\label{tab:llama-vs-qwen-ss}
822	\begin{tabular}{@{}l cc@{}}
823	\toprule
824	\textbf{Metric} & \textbf{Qwen-7B} & \textbf{Llama-8B} \\
825	\midrule
826	SS epochs & 3 & 2 \\
827	TF GAR & 0.498 & 0.477 \\
828	AR GAR ($\beta$\,=\,0) & 0.401 & 0.166 \\
829	TF/AR gap & 1.2$\times$ & 2.9$\times$ \\
830	Baseline TG gap & 7.8$\times$ & 27$\times$ (median) \\
831	Gap compression & 6.5$\times$ & 9.3$\times$ \\
832	AR GAR ($\beta$\,=\,5) & 0.717 & 0.791 \\
833	TF PPL & 2.78 & 2.82 \\
834	AR PPL & 1.441 & 1.370 \\
835	\bottomrule
836	\end{tabular}
837	\end{table}
838	
839	\section{Use of AI Assistants}\label{sec:appendix-ai}
840	
841	We used Claude (Anthropic) as an AI coding and writing assistant
842	throughout this work. Specifically:
843	\begin{itemize}
844	    \item \textbf{Code:} drafting experiment scripts, data-processing
845	    pipelines, and analysis utilities; debugging and refactoring.
846	    \item \textbf{Writing:} drafting and revising paper sections,
847	    polishing prose, and reformatting LaTeX.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3e413c86-fb09-4fe8-96e5-e9418a3b4dbd",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "1cecde4c-a196-4d89-b475-03ee98e60c4e",
  "sourceToolAssistantUUID": "3e413c86-fb09-4fe8-96e5-e9418a3b4dbd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 28 · 2026-05-25T20:13:36.332Z_

Now let me read the externally-included tables.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1cecde4c-a196-4d89-b475-03ee98e60c4e",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu5R3bguvPoqhY5rzMV",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "6e8444b3-e66e-4630-b239-979d7d60bcfd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CtE91nK3SZ13aL3cikRhf2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9846,
      "cache_read_input_tokens": 44242,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 9846,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-25T20:13:37.989Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01HEsGgY7Voi94tgiGejiPVE`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/artifacts/appendix_expansion"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6e8444b3-e66e-4630-b239-979d7d60bcfd",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu5R3bguvPoqhY5rzMV",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "f6bc7fa4-5b56-4f6e-8cdf-431b4566973c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CtE91nK3SZ13aL3cikRhf2",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9846,
      "cache_read_input_tokens": 44242,
      "output_tokens": 118,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 9846
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 118,
          "cache_read_input_tokens": 44242,
          "cache_creation_input_tokens": 9846,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 9846,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-25T20:13:38.001Z_

<details><summary>↩ Tool result · `toolu_01HEsGgY7Voi94tgiGejiPVE`</summary>

```text
artifacts/appendix_expansion/tab_gar_robustness.tex
artifacts/appendix_expansion/tab_statistical_tests.tex
artifacts/appendix_expansion/tab_perseed_ss.tex
artifacts/appendix_expansion/tab_perseed_tg.tex
artifacts/appendix_expansion/tab_perturn_qwen.tex
artifacts/appendix_expansion/tab_mmlu_detail.tex
artifacts/appendix_expansion/tab_qwen15b_results.tex
artifacts/appendix_expansion/tab_crossmodel_detail.tex
artifacts/appendix_expansion/tab_dataset_stats.tex
artifacts/appendix_expansion/tab_perturn_llama.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f6bc7fa4-5b56-4f6e-8cdf-431b4566973c",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "2181b971-99ee-4194-bf4b-af45d57108b5",
  "sourceToolAssistantUUID": "f6bc7fa4-5b56-4f6e-8cdf-431b4566973c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-25T20:13:45.731Z_

<details open><summary>🔧 Tool call — Read · `toolu_01GxkFX2AZn5kkajM4N8Z1vL`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/artifacts/appendix_expansion/tab_crossmodel_detail.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2181b971-99ee-4194-bf4b-af45d57108b5",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu5k7Zo9EuL7y8oHhXz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "ceba9d17-a510-4972-9cad-c33b6e497fd8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wwc2E1y47hDQfQe93Vqo7C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 294,
      "cache_read_input_tokens": 54088,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 294,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 61,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 32 · 2026-05-25T20:13:45.736Z_

<details><summary>↩ Tool result · `toolu_01GxkFX2AZn5kkajM4N8Z1vL`</summary>

```text
1	% Cross-model detailed comparison: Qwen2.5-7B-Instruct vs Llama-3.1-8B-Instruct
2	% Conditions shared by both models: Base, ThreadGate, LoRA-only
3	% Qwen TF: N=200 held-out; Qwen AR: d048_final_ar N=50 gen beta=0
4	% Llama TF: N=50 held-out T=4; Llama AR: eval_llama_ar_n20 N=20 T=4
5	% Llama SS: p1_llama_ss_eval (epoch_1 checkpoint, N=50)
6	\begin{table*}[t]
7	\centering
8	\caption{Cross-model comparison of goal-adherence metrics on Qwen2.5-7B-Instruct and Llama-3.1-8B-Instruct.
9	Gap ratio = TF GAR / AR GAR; lower is better (less exposure bias).
10	Qwen AR uses $N{=}50$ gen-mode evaluation; Llama AR uses $N{=}20$, $T{=}4$ (SS: $N{=}50$).
11	Llama AR GAR and gaps are mean-based; median-based TG gap is 27$\times$ (\S\ref{subsec:cross-model}).}
12	\label{tab:crossmodel-detail}
13	\small
14	\begin{tabular}{@{}ll ccccc@{}}
15	\toprule
16	\textbf{Model} & \textbf{Condition} & \textbf{TF GAR}$\uparrow$ & \textbf{AR GAR}$\uparrow$ & \textbf{TF PPL}$\downarrow$ & \textbf{AR PPL}$\downarrow$ & \textbf{Gap}$\downarrow$ \\
17	\midrule
18	\multirow{4}{*}{Qwen-7B}
19	  & Base      & 0.013 & 0.019 & 4.34 & 1.447 & 0.7$\times$ \\
20	  & TG        & 0.504 & 0.064 & 2.78 & 1.432 & 7.9$\times$ \\
21	  & LoRA-only & 0.498 & 0.037 & 2.78 & 1.431 & 13.5$\times$ \\
22	  & \textbf{SS} & 0.498 & \textbf{0.401} & 2.78 & 1.441 & \textbf{1.2$\times$} \\
23	\midrule
24	\multirow{4}{*}{Llama-8B}
25	  & Base      & 0.017 & 0.009 & 3.45 & 1.293 & 1.9$\times$ \\
26	  & TG        & 0.484 & 0.043 & 2.57 & 1.437 & 11.2$\times$ \\
27	  & LoRA-only & 0.481 & 0.028 & 2.60 & 1.419 & 17.2$\times$ \\
28	  & \textbf{SS} & 0.477 & \textbf{0.166} & 2.82 & 1.370 & \textbf{2.9$\times$} \\
29	\bottomrule
30	\end{tabular}
31	\end{table*}
32	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ceba9d17-a510-4972-9cad-c33b6e497fd8",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "64ac5d37-bfaa-4228-9a99-8d5561179d62",
  "sourceToolAssistantUUID": "ceba9d17-a510-4972-9cad-c33b6e497fd8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 33 · 2026-05-25T20:13:46.216Z_

<details open><summary>🔧 Tool call — Read · `toolu_01GFgWRBcgT5i92xxrq3pGp7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/artifacts/appendix_expansion/tab_perseed_ss.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "64ac5d37-bfaa-4228-9a99-8d5561179d62",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu5k7Zo9EuL7y8oHhXz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "264a2d2b-5f4f-4dcd-8507-43dd053c7b2c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wwc2E1y47hDQfQe93Vqo7C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 294,
      "cache_read_input_tokens": 54088,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 294,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 61,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 34 · 2026-05-25T20:13:46.226Z_

<details><summary>↩ Tool result · `toolu_01GFgWRBcgT5i92xxrq3pGp7`</summary>

```text
1	% Per-seed detailed results for Scheduled Sampling (SS) — seeds 42, 123, 456
2	% TF eval: N=200, T=3 (teacher-forced on held-out eval_200 set)
3	% AR eval: N=50 gen-mode, beta=0/3/5 (from d048_final_ar)
4	\begin{table}[h]
5	\centering
6	\caption{Per-seed results for Scheduled Sampling (SS) on Qwen2.5-7B-Instruct.
7	TF evaluation uses 200 held-out conversations; AR evaluation uses 50 model-generated conversations in free-form generation mode ($N_{\text{valid}} \approx 39$).}
8	\label{tab:perseed-ss}
9	\resizebox{\columnwidth}{!}{
10	\begin{tabular}{@{}l ccc c@{}}
11	\toprule
12	\textbf{Metric} & \textbf{Seed 42} & \textbf{Seed 123} & \textbf{Seed 456} & \textbf{Mean $\pm$ Std} \\
13	\midrule
14	\multicolumn{5}{@{}l}{\textit{Teacher-Forced (TF)}} \\
15	\quad GAR-ours $\uparrow$   & 0.502 & 0.554 & 0.496 & 0.517 $\pm$ 0.032 \\
16	\quad GAR-Dongre $\uparrow$ & 0.389 & 0.411 & 0.386 & 0.395 $\pm$ 0.014 \\
17	\quad PPL $\downarrow$       & 2.780 & 2.612 & 2.611 & 2.668 $\pm$ 0.097 \\
18	\midrule
19	\multicolumn{5}{@{}l}{\textit{Autoregressive (AR), $\beta = 0$}} \\
20	\quad GAR-ours $\uparrow$   & 0.347 & 0.423 & 0.433 & 0.401 $\pm$ 0.047 \\
21	\quad PPL $\downarrow$       & 1.442 & 1.441 & 1.439 & 1.441 $\pm$ 0.002 \\
22	\midrule
23	\multicolumn{5}{@{}l}{\textit{Autoregressive (AR), $\beta = 3$}} \\
24	\quad GAR-ours $\uparrow$   & 0.593 & 0.590 & 0.605 & 0.596 $\pm$ 0.008 \\
25	\quad PPL $\downarrow$       & 1.564 & 1.607 & 1.587 & 1.586 $\pm$ 0.022 \\
26	\midrule
27	\multicolumn{5}{@{}l}{\textit{Autoregressive (AR), $\beta = 5$}} \\
28	\quad GAR-ours $\uparrow$   & 0.717 & 0.717 & 0.716 & 0.717 $\pm$ 0.001 \\
29	\quad PPL $\downarrow$       & 1.779 & 1.785 & 1.804 & 1.789 $\pm$ 0.013 \\
30	\bottomrule
31	\end{tabular}}
32	\end{table}
33	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "264a2d2b-5f4f-4dcd-8507-43dd053c7b2c",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "8ecfa08d-d013-45a0-be29-be93509108ee",
  "sourceToolAssistantUUID": "264a2d2b-5f4f-4dcd-8507-43dd053c7b2c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 35 · 2026-05-25T20:13:46.296Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LYhZghXXj89pm64EUoFvDp`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/artifacts/appendix_expansion/tab_perseed_tg.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8ecfa08d-d013-45a0-be29-be93509108ee",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu5k7Zo9EuL7y8oHhXz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "f60b16ef-9fec-4500-9f73-407a2ac4c9c6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wwc2E1y47hDQfQe93Vqo7C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 294,
      "cache_read_input_tokens": 54088,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 294,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 61,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 36 · 2026-05-25T20:13:46.300Z_

<details><summary>↩ Tool result · `toolu_01LYhZghXXj89pm64EUoFvDp`</summary>

```text
1	% Per-seed detailed results for ThreadGate (TG) — seeds 42, 123
2	% TF eval: N=200 held-out conversations
3	% AR eval: N=5, T=10 model-generated conversations (original eval protocol)
4	\begin{table}[h]
5	\centering
6	\caption{Per-seed results for ThreadGate (TG) on Qwen2.5-7B-Instruct.
7	TF evaluation uses 200 held-out conversations.
8	AR evaluation uses 5 model-generated conversations with 10 turns each.}
9	\label{tab:perseed-tg}
10	\resizebox{\columnwidth}{!}{
11	\begin{tabular}{@{}l cc c@{}}
12	\toprule
13	\textbf{Metric} & \textbf{Seed 42} & \textbf{Seed 123} & \textbf{Mean $\pm$ Std} \\
14	\midrule
15	\multicolumn{4}{@{}l}{\textit{Teacher-Forced (TF)}} \\
16	\quad GAR-ours $\uparrow$   & 0.504 & 0.505 & 0.504 $\pm$ 0.001 \\
17	\quad GAR-Dongre $\uparrow$ & 0.015 & 0.012 & 0.014 $\pm$ 0.002 \\
18	\quad PPL $\downarrow$       & 2.784 & 2.780 & 2.782 $\pm$ 0.003 \\
19	\midrule
20	\multicolumn{4}{@{}l}{\textit{Autoregressive (AR), $\beta = 0$}} \\
21	\quad GAR-ours $\uparrow$   & 0.016 & 0.017 & 0.016 $\pm$ 0.001 \\
22	\quad GAR-Dongre $\uparrow$ & 0.019 & 0.018 & 0.019 $\pm$ 0.001 \\
23	\quad PPL $\downarrow$       & 1.360 & 1.386 & 1.373 $\pm$ 0.018 \\
24	\midrule
25	\multicolumn{4}{@{}l}{\textit{Derived}} \\
26	\quad Gap ratio (TF/AR GAR-ours) $\downarrow$ & 32.1 & 30.6 & 31.4 $\pm$ 1.1 \\
27	\bottomrule
28	\end{tabular}}
29	\end{table}
30	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f60b16ef-9fec-4500-9f73-407a2ac4c9c6",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "40ebe945-3b1a-4a05-b237-ec09c25f5894",
  "sourceToolAssistantUUID": "f60b16ef-9fec-4500-9f73-407a2ac4c9c6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 37 · 2026-05-25T20:13:46.937Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DXY7YSEd9csJYTJ1tYMGQJ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/artifacts/appendix_expansion/tab_perturn_qwen.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "40ebe945-3b1a-4a05-b237-ec09c25f5894",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu5k7Zo9EuL7y8oHhXz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3bf3672e-41d6-4025-815f-41ed6dae3c3f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wwc2E1y47hDQfQe93Vqo7C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 294,
      "cache_read_input_tokens": 54088,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 294,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 61,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 38 · 2026-05-25T20:13:46.941Z_

<details><summary>↩ Tool result · `toolu_01DXY7YSEd9csJYTJ1tYMGQJ`</summary>

```text
1	% Per-turn AR GAR-ours for Qwen2.5-7B-Instruct, 6-way comparison
2	% Source: d048_final_ar, beta=0, N=50 gen-mode, n_valid~39
3	% Only turns 1--5 shown (later turns have survivor bias from variable-length generation)
4	\begin{table}[t]
5	\centering
6	\caption{Per-turn autoregressive GAR-ours ($\beta{=}0$) on Qwen2.5-7B-Instruct across six training configurations. Values represent average GAR over ${\sim}39$ valid conversations in free-form generation mode.}
7	\label{tab:perturn-qwen}
8	\resizebox{\columnwidth}{!}{
9	\begin{tabular}{@{}l ccccc@{}}
10	\toprule
11	\textbf{Configuration} & \textbf{Turn 1} & \textbf{Turn 2} & \textbf{Turn 3} & \textbf{Turn 4} & \textbf{Turn 5} \\
12	\midrule
13	Base         & .085 & .032 & .021 & .013 & .004 \\
14	ThreadGate   & .130 & .073 & .059 & .043 & .066 \\
15	PCGrad       & .090 & .038 & .028 & .029 & .027 \\
16	UG           & .113 & .056 & .033 & .020 & .016 \\
17	LoRA-only    & .107 & .059 & .030 & .049 & .040 \\
18	SS           & \textbf{.458} & \textbf{.381} & \textbf{.344} & \textbf{.370} & \textbf{.365} \\
19	\bottomrule
20	\end{tabular}}
21	\end{table}
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3bf3672e-41d6-4025-815f-41ed6dae3c3f",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "6d117766-05b9-4467-bce9-79a70bdef098",
  "sourceToolAssistantUUID": "3bf3672e-41d6-4025-815f-41ed6dae3c3f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 39 · 2026-05-25T20:13:47.178Z_

<details open><summary>🔧 Tool call — Read · `toolu_015xMUHGcQGNjunM2rewe4fX`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/artifacts/appendix_expansion/tab_perturn_llama.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6d117766-05b9-4467-bce9-79a70bdef098",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu5k7Zo9EuL7y8oHhXz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "4083a0a9-f084-44a9-9a25-d55aec485980",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wwc2E1y47hDQfQe93Vqo7C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 294,
      "cache_read_input_tokens": 54088,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 294,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 61,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 40 · 2026-05-25T20:13:47.195Z_

<details><summary>↩ Tool result · `toolu_015xMUHGcQGNjunM2rewe4fX`</summary>

```text
1	% Per-turn AR GAR-ours for Llama-3.1-8B-Instruct
2	% Panel (a): N=20, T=4 (eval_llama_ar_n20) — reliable estimates
3	% Panel (b): Base only, N=5, T=10 (llama_phase1_gar_diag) — decay profile
4	\begin{table*}[t]
5	\centering
6	\caption{Per-turn autoregressive GAR-ours ($\beta{=}0$) on Llama-3.1-8B-Instruct.
7	(a)~Three-way comparison using $N{=}20$ conversations ($T{=}4$ turns).
8	(b)~Base model decay profile ($N{=}5$, $T{=}10$).}
9	\label{tab:perturn-llama}
10	\small
11	\begin{subtable}[t]{0.48\textwidth}
12	\centering
13	\caption{$N{=}20$, $T{=}4$}
14	\renewcommand{\arraystretch}{1.3}
15	\begin{tabular}{@{}l cccc@{}}
16	\toprule
17	\textbf{Config.} & \textbf{T1} & \textbf{T2} & \textbf{T3} & \textbf{T4} \\
18	\midrule
19	Base      & .028 & .013 & .009 & .008 \\
20	TG        & .041 & .042 & .049 & .038 \\
21	LoRA-only & .033 & .049 & .025 & .031 \\
22	\bottomrule
23	\end{tabular}
24	\end{subtable}
25	\hfill
26	\begin{subtable}[t]{0.38\textwidth}
27	\centering
28	\caption{Base decay ($N{=}5$, $T{=}10$)}
29	\begin{tabular}{@{}cc@{}}
30	\toprule
31	\textbf{Turn} & \textbf{GAR-ours} \\
32	\midrule
33	1  & .026 \\
34	2  & .018 \\
35	3  & .009 \\
36	4  & .006 \\
37	5  & .006 \\
38	6  & .004 \\
39	7  & .004 \\
40	8  & .004 \\
41	9  & .005 \\
42	10 & .003 \\
43	\bottomrule
44	\end{tabular}
45	\end{subtable}
46	\end{table*}
47	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4083a0a9-f084-44a9-9a25-d55aec485980",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "a9556052-f71b-4bd4-b1e7-eb9cb17dd9d9",
  "sourceToolAssistantUUID": "4083a0a9-f084-44a9-9a25-d55aec485980",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 41 · 2026-05-25T20:13:47.531Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DYividVhgFBvhMTaaiDMhs`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/artifacts/appendix_expansion/tab_dataset_stats.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a9556052-f71b-4bd4-b1e7-eb9cb17dd9d9",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu5k7Zo9EuL7y8oHhXz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "9e9f6a78-088a-490b-9c24-42397aed02be",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wwc2E1y47hDQfQe93Vqo7C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 294,
      "cache_read_input_tokens": 54088,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 294,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 61,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 42 · 2026-05-25T20:13:47.537Z_

<details><summary>↩ Tool result · `toolu_01DYividVhgFBvhMTaaiDMhs`</summary>

```text
1	% Dataset statistics table
2	\begin{table}[t]
3	\centering
4	\small
5	\caption{Dataset statistics. Training and evaluation data are sampled from UltraChat-200K \texttt{train\_sft} split~\citep{ding2023ultrachat}. All conversations contain $\geq 5$ assistant turns.}
6	\label{tab:dataset_stats}
7	\begin{tabular}{@{}lr@{}}
8	\toprule
9	\textbf{Statistic} & \textbf{Value} \\
10	\midrule
11	\multicolumn{2}{@{}l}{\textit{Source}} \\
12	\quad Total conversations & 207{,}865 \\
13	\quad After $\geq 5$ turn filter & 17{,}302 \\
14	\midrule
15	\multicolumn{2}{@{}l}{\textit{Splits}} \\
16	\quad Training & 8{,}000 \\
17	\quad Held-out AR eval & 50 \\
18	\quad IID GAR diagnostic & 50 \\
19	\quad Instruction retention & 200 \\
20	\midrule
21	\multicolumn{2}{@{}l}{\textit{Conversation structure}} \\
22	\quad Avg.\ assistant turns & 5.6 \\
23	\quad Min / Max turns & 5 / 7 \\
24	\bottomrule
25	\end{tabular}
26	\end{table}
27	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9e9f6a78-088a-490b-9c24-42397aed02be",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "8e3a582f-4c8e-4bce-8fd2-768e10f1c2eb",
  "sourceToolAssistantUUID": "9e9f6a78-088a-490b-9c24-42397aed02be",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 43 · 2026-05-25T20:13:47.901Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Wd8MSDcRWmrY5BoEwneAuZ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/artifacts/appendix_expansion/tab_gar_robustness.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8e3a582f-4c8e-4bce-8fd2-768e10f1c2eb",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu5k7Zo9EuL7y8oHhXz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "7f7031cf-12fe-437f-94f9-528bfd1393b5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wwc2E1y47hDQfQe93Vqo7C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 294,
      "cache_read_input_tokens": 54088,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 294,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 61,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 44 · 2026-05-25T20:13:47.906Z_

<details><summary>↩ Tool result · `toolu_01Wd8MSDcRWmrY5BoEwneAuZ`</summary>

```text
1	% GAR definition robustness: 4 token selection strategies x 3 conditions
2	\begin{table*}[t]
3	\centering
4	\small
5	\caption{GAR robustness across token selection strategies. We evaluate four ways to select the token position for gradient attribution: \textbf{Last} (final token of each turn), \textbf{All} (mean over all tokens), \textbf{First} (first token), and \textbf{Goal-only} (goal token as in \citet{dongre2026attention}). Turn-1 and Mid-turn GAR are measured under autoregressive generation on 50 held-out conversations. Gap Ratio = Turn-1 / Mid-turn; lower indicates better gradient preservation across turns.}
6	\label{tab:gar_robustness}
7	\begin{tabular}{@{}ll ccc@{}}
8	\toprule
9	\textbf{Token Selection} & \textbf{Condition} & \textbf{Turn-1 GAR} & \textbf{Mid-turn GAR} & \textbf{Gap Ratio} $\downarrow$ \\
10	\midrule
11	\multirow{3}{*}{Last (ours)}
12	  & Base      & 0.0858 & 0.0152 & 5.64$\times$ \\
13	  & TG        & 0.3938 & 0.3254 & 1.21$\times$ \\
14	  & SS        & 0.5274 & 0.4582 & 1.15$\times$ \\
15	\midrule
16	\multirow{3}{*}{All tokens}
17	  & Base      & 0.1152 & 0.0152 & 7.57$\times$ \\
18	  & TG        & 0.1275 & 0.0253 & 5.04$\times$ \\
19	  & SS        & 0.5043 & 0.3658 & 1.38$\times$ \\
20	\midrule
21	\multirow{3}{*}{First token}
22	  & Base      & 0.2987 & 0.0224 & 13.32$\times$ \\
23	  & TG        & 0.3225 & 0.0392 & 8.24$\times$ \\
24	  & SS        & 0.7549 & 0.4118 & 1.83$\times$ \\
25	\midrule
26	\multirow{3}{*}{Goal-only}
27	  & Base      & 0.0110 & 0.0049 & 2.23$\times$ \\
28	  & TG        & 0.3313 & 0.3103 & 1.07$\times$ \\
29	  & SS        & 0.4528 & 0.4435 & 1.02$\times$ \\
30	\bottomrule
31	\end{tabular}
32	\end{table*}
33	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7f7031cf-12fe-437f-94f9-528bfd1393b5",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "8113c253-5e76-4636-9ff5-7299219f02d3",
  "sourceToolAssistantUUID": "7f7031cf-12fe-437f-94f9-528bfd1393b5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 45 · 2026-05-25T20:13:48.176Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LYH6zWd4GcmVdfeWjSvmQv`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/artifacts/appendix_expansion/tab_statistical_tests.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8113c253-5e76-4636-9ff5-7299219f02d3",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu5k7Zo9EuL7y8oHhXz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "35451a91-a5d8-443d-9264-eaf0b165844e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wwc2E1y47hDQfQe93Vqo7C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 294,
      "cache_read_input_tokens": 54088,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 294,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 61,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 46 · 2026-05-25T20:13:48.180Z_

<details><summary>↩ Tool result · `toolu_01LYH6zWd4GcmVdfeWjSvmQv`</summary>

```text
1	% Item 9: Statistical tests summary table
2	% Wilcoxon signed-rank tests for per-dialogue GAR + McNemar for instruction retention
3	\begin{table*}[t]
4	\centering
5	\caption{Summary of statistical significance tests.
6	  Wilcoxon signed-rank tests compare per-dialogue GAR across training configurations ($N\!=\!39$);
7	  McNemar's test assesses instruction-following retention under steering ($N\!=\!54$ paired instances).
8	  Bootstrap 95\% CIs from 10{,}000 resamples.
9	  Significance: $^{***}\!p<.001$, $^{**}\!p<.01$, $^{*}\!p<.05$.}
10	\label{tab:statistical_tests}
11	\small
12	\setlength{\tabcolsep}{4pt}
13	\begin{tabular}{@{}llcrrccl@{}}
14	\toprule
15	$\beta$ & Comparison & Test & Stat. & $p$ & $r$ & $\overline{\mathrm{GAR}}$\;[95\% CI] & Sig. \\
16	\midrule
17	\multirow{4}{*}{0.0}
18	 & TG vs Base    & Wilcoxon & $W\!=\!31$  & ${<}.001$ & .802 & .064\,[.041,\,.091]\;vs\;.019\,[.014,\,.024] & $^{***}$ \\
19	 & TG vs LoRA    & Wilcoxon & $W\!=\!187$ & .004      & .454 & .064\,[.041,\,.091]\;vs\;.037\,[.027,\,.050] & $^{**}$  \\
20	 & SS vs TG      & Wilcoxon & $W\!=\!1$   & ${<}.001$ & .869 & .347\,[.327,\,.366]\;vs\;.064\,[.041,\,.091] & $^{***}$ \\
21	 & PCGrad vs TG  & Wilcoxon & $W\!=\!176$ & .002      & .478 & .030\,[.023,\,.038]\;vs\;.064\,[.041,\,.091] & $^{**}$  \\
22	\midrule
23	\multirow{4}{*}{3.0}
24	 & TG vs Base    & Wilcoxon & $W\!=\!242$ & .039 & .331 & .556\,[.538,\,.575]\;vs\;.531\,[.514,\,.550] & $^{*}$  \\
25	 & TG vs LoRA    & Wilcoxon & $W\!=\!376$ & .852 & .031 & .556\,[.538,\,.575]\;vs\;.560\,[.541,\,.581] & n.s.    \\
26	 & SS vs TG      & Wilcoxon & $W\!=\!207$ & .010 & .409 & .593\,[.574,\,.613]\;vs\;.556\,[.538,\,.575] & $^{**}$ \\
27	 & PCGrad vs TG  & Wilcoxon & $W\!=\!368$ & .767 & .049 & .559\,[.543,\,.576]\;vs\;.556\,[.538,\,.575] & n.s.    \\
28	\midrule
29	\multirow{4}{*}{5.0}
30	 & TG vs Base    & Wilcoxon & $W\!=\!251$ & .084 & .281 & .727\,[.708,\,.747]\;vs\;.704\,[.679,\,.730] & n.s. \\
31	 & TG vs LoRA    & Wilcoxon & $W\!=\!277$ & .180 & .220 & .727\,[.708,\,.747]\;vs\;.708\,[.687,\,.729] & n.s. \\
32	 & SS vs TG      & Wilcoxon & $W\!=\!314$ & .421 & .133 & .717\,[.696,\,.738]\;vs\;.727\,[.708,\,.747] & n.s. \\
33	 & PCGrad vs TG  & Wilcoxon & $W\!=\!266$ & .133 & .246 & .708\,[.690,\,.727]\;vs\;.727\,[.708,\,.747] & n.s. \\
34	\midrule
35	\multicolumn{8}{@{}l}{\textit{Instruction-following retention} ($\beta\!=\!0 \to 3$, ThreadGate only)} \\[2pt]
36	 & $\beta\!=\!0$ vs $\beta\!=\!3$ & McNemar & $\chi^2\!=\!3.13$ & .077 & $.200^{\dagger}$ & Rate: .759\;vs\;.870\;($N\!=\!54$) & n.s.$^{\ddagger}$ \\
37	\bottomrule
38	\end{tabular}
39	\\[4pt]
40	{\footnotesize
41	$^{\dagger}$\,Point-biserial $r$; associated $p=.007$ (significant).
42	$^{\ddagger}$\,Marginal by McNemar ($p=.077$); significant by point-biserial correlation.
43	}
44	\end{table*}
45	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "35451a91-a5d8-443d-9264-eaf0b165844e",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "c98e239b-fd30-413b-9871-9681fb9ebab4",
  "sourceToolAssistantUUID": "35451a91-a5d8-443d-9264-eaf0b165844e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 47 · 2026-05-25T20:13:48.485Z_

<details open><summary>🔧 Tool call — Read · `toolu_013iTVLPwxMFDH1mEQpZ8vuV`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/artifacts/appendix_expansion/tab_mmlu_detail.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c98e239b-fd30-413b-9871-9681fb9ebab4",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu5k7Zo9EuL7y8oHhXz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a1dae263-018c-4bad-bb67-23f693b958b8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wwc2E1y47hDQfQe93Vqo7C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 294,
      "cache_read_input_tokens": 54088,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 294,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 61,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 48 · 2026-05-25T20:13:48.489Z_

<details><summary>↩ Tool result · `toolu_013iTVLPwxMFDH1mEQpZ8vuV`</summary>

```text
1	% MMLU per-category quality preservation table
2	\begin{table}[t]
3	\centering
4	\footnotesize
5	\caption{MMLU accuracy (\%) by category across training conditions. All models are Qwen2.5-7B-Instruct with LoRA adapters evaluated on the full 57-subject MMLU benchmark (14{,}042 questions). $\Delta$ denotes deviation from Base.}
6	\label{tab:mmlu_detail}
7	\resizebox{\columnwidth}{!}{
8	\begin{tabular}{@{}l cccccc@{}}
9	\toprule
10	\textbf{Category} & \textbf{Base} & \textbf{TG} & \textbf{PCGrad} & \textbf{SS} & \textbf{LoRA-only} & \textbf{UG} \\
11	\midrule
12	STEM           & 70.69 & 69.20 & 69.55 & 69.97 & 70.03 & 69.65 \\
13	Social Sciences & 77.28 & 76.92 & 76.79 & 76.83 & 77.08 & 77.02 \\
14	Humanities     & 83.95 & 83.33 & 84.08 & 83.39 & 83.62 & 83.95 \\
15	Other          & 68.25 & 67.59 & 68.12 & 67.95 & 67.06 & 66.80 \\
16	\midrule
17	\textbf{Overall} & \textbf{74.23} & 73.47 & 73.86 & 73.75 & 73.57 & 73.46 \\
18	$\Delta$ & --- & $-$0.76 & $-$0.37 & $-$0.48 & $-$0.66 & $-$0.77 \\
19	\bottomrule
20	\end{tabular}}
21	\end{table}
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a1dae263-018c-4bad-bb67-23f693b958b8",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "be405129-6b5c-47c1-82d9-94a72395c1db",
  "sourceToolAssistantUUID": "a1dae263-018c-4bad-bb67-23f693b958b8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 49 · 2026-05-25T20:13:48.724Z_

<details open><summary>🔧 Tool call — Read · `toolu_01SftH4vCJoa2tzhiU7GQ1TQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating/artifacts/appendix_expansion/tab_qwen15b_results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "be405129-6b5c-47c1-82d9-94a72395c1db",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu5k7Zo9EuL7y8oHhXz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "575bacdc-7c67-41c8-991a-7703c899432c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wwc2E1y47hDQfQe93Vqo7C",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 294,
      "cache_read_input_tokens": 54088,
      "output_tokens": 822,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 294
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 822,
          "cache_read_input_tokens": 54088,
          "cache_creation_input_tokens": 294,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 294,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 50 · 2026-05-25T20:13:48.728Z_

<details><summary>↩ Tool result · `toolu_01SftH4vCJoa2tzhiU7GQ1TQ`</summary>

```text
1	% Qwen2.5-1.5B cross-scale results
2	\begin{table}[t]
3	\centering
4	\footnotesize
5	\caption{Cross-scale validation on Qwen2.5-1.5B-Instruct. Phase~1 confirms the GAR decay pattern at smaller scale (79.8\% relative drop). Phase~2 shows TG improves AR at $\beta=0$ (unamplified, $p{=}0.005$) and $\beta=5$ (strong amplification, $p{<}0.001$), confirming the mechanism transfers across model sizes.}
6	\label{tab:qwen15b_results}
7	\resizebox{\columnwidth}{!}{
8	\begin{tabular}{@{}ll cc c@{}}
9	\toprule
10	\textbf{Phase} & \textbf{Metric} & \textbf{Base} & \textbf{TG} & \textbf{$p$-value} \\
11	\midrule
12	\multicolumn{5}{@{}l}{\textit{Phase 1: GAR diagnostic}} \\
13	\quad & Turn-1 GAR & 0.0336 & --- & --- \\
14	\quad & Mid-turn GAR & 0.0068 & --- & --- \\
15	\quad & Relative drop & 79.8\% & --- & --- \\
16	\midrule
17	\multicolumn{5}{@{}l}{\textit{Phase 2: TG training ($\beta$-amplified AR)}} \\
18	\quad & AR @ $\beta{=}0$ & 0.0167 {\scriptsize$\pm$0.005} & \textbf{0.0233} {\scriptsize$\pm$0.006} & 0.005$^{**}$ \\
19	\quad & AR @ $\beta{=}3$ & 0.1202 {\scriptsize$\pm$0.032} & 0.1143 {\scriptsize$\pm$0.019} & 0.815 \\
20	\quad & AR @ $\beta{=}5$ & 0.6571 {\scriptsize$\pm$0.020} & \textbf{0.7150} {\scriptsize$\pm$0.017} & $<$0.001$^{***}$ \\
21	\bottomrule
22	\end{tabular}}
23	\vspace{1mm}
24	\begin{flushleft}
25	\scriptsize
26	$\pm$ values are 95\% CI half-widths. Significance via Wilcoxon signed-rank test ($N{=}39$ paired conversations). Effect sizes: $r{=}0.447$ ($\beta{=}0$), $r{=}0.749$ ($\beta{=}5$).
27	\end{flushleft}
28	\end{table}
29	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "575bacdc-7c67-41c8-991a-7703c899432c",
  "isSidechain": true,
  "promptId": "1f7ff205-71d0-4ca7-a71f-3ee7850be97d",
  "agentId": "abd64e66887e6e7f7",
  "type": "user",
  "uuid": "5590931a-0b7c-4748-914f-78ccedba510d",
  "sourceToolAssistantUUID": "575bacdc-7c67-41c8-991a-7703c899432c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 51 · 2026-05-25T20:16:03.688Z_

Here is the complete report of all tables and their verbatim numbers.

---

## Main Text Tables

### Table 1: `tab:five-way` (in `sections/related_work.tex`, lines 12-35)
**Five-way comparison on Qwen-2.5-7B-Instruct.**

| Configuration | IID GAR-O | IID GAR-D | IID PPL | Held-out GAR-O | Held-out GAR-D | Held-out PPL | AR GAR-O | AR 95% CI | g_bar +/- sigma_g |
|---|---|---|---|---|---|---|---|---|---|
| Base | 0.01 | 0.00 | 4.23 | 0.01 | 0.00 | 4.34 | 0.019 | [.014, .024] | --- |
| ThreadGate | 0.50 | **0.02** | 2.78 | 0.50 | **0.02** | 2.78 | **0.064** | [.041, .091] | .93 +/- .05 |
| +PCGrad | 0.50 | 0.01 | 2.78 | 0.50 | 0.01 | 2.78 | 0.030 | [.023, .038] | --- |
| Uniform Gate | 0.49 | 0.01 | 2.78 | **0.51** | 0.01 | 2.78 | 0.033 | [.025, .043] | .96 +/- .05 |
| LoRA-only | 0.50 | 0.01 | 2.78 | 0.50 | 0.01 | 2.78 | 0.037 | [.027, .050] | 1.00 |

### Table 2: `tab:four-way` (in `experiments.tex`, lines 20-37)
**Four-way ablation on Qwen-2.5-7B-Instruct.**

| Configuration | IID GAR-O | IID GAR-D | IID PPL | Held-out GAR-O | Held-out GAR-D | Held-out PPL |
|---|---|---|---|---|---|---|
| Base | 0.01 | 0.00 | 4.23 | 0.01 | 0.00 | 4.34 |
| ThreadGate | 0.49 | 0.02 | 2.63 | 0.50 | 0.02 | 2.78 |
| Uniform Gate | 0.49 | 0.01 | 2.62 | 0.51 | 0.01 | 2.78 |
| LoRA-only | 0.49 | 0.01 | 2.63 | 0.50 | 0.01 | 2.78 |

### Table 3: `tab:grad-conflict` (in `analysis.tex`, lines 9-23)
**Gradient interaction between NTP and GAR.**

| Epoch | cos_sim | neg% | mag_ratio |
|---|---|---|---|
| 0 | -0.089 | 78.6 | 7.5x |
| 1 | -0.054 | 71.4 | 13.7x |
| 2 | -0.042 | 67.9 | 14.7x |

---

## Appendix Tables

### `tab:hyperparams` (appendix, lines 5-33)
**Training hyperparameters:**

| Parameter | Value |
|---|---|
| Base model | Qwen-2.5-7B-Instruct |
| LoRA rank / alpha | 16 / 32 |
| LoRA targets | q_proj, v_proj |
| Optimizer | AdamW (beta1=0.9, beta2=0.999) |
| Learning rate | 2e-4 |
| Gate LR mult | 10x |
| Batch / grad accum | 1 / 8 (eff. 8) |
| Epochs | 3 |
| Max seq length | 2048 |
| Training data | 8K UltraChat convs |
| Seed | 42 (+123 for TG, SS) |
| lambda_GAR / lambda_div | 1.0 / 1.0 |
| GAR target tau | 0.5 |
| Gate init bias | 1.5 (sigma ~= 0.82) |
| Gate hidden dim | 64 |
| Turn embed dim | 16 |
| GPU | RTX PRO 6000 (96 GB) |
| Training time | 6-8 h / variant |

### `tab:loss-iterations` (appendix, lines 47-64)
**Loss formulation iterations:**

| Version | Loss Family | Status | GAR | PPL |
|---|---|---|---|---|
| v1 | Cumulative | fail (GAR loss -> 0) | --- | --- |
| v2 | Cumulative + epsilon | fail (same trajectory) | --- | --- |
| v3 | Maximize (lambda=2) | fail (gate frozen) | --- | --- |
| v3b | Maximize (lambda=10) | fail (identity collapse) | --- | --- |
| v5 | Maximize (lambda=1) | fail (identity collapse) | --- | --- |
| v6 | Smooth saturation | fail (identity collapse) | --- | --- |
| v7 | MSE + gate div | **converged** | 0.50 | 2.78 |

### `tab:ir-results` (appendix, lines 87-103)
**Instruction retention by constraint category (beta=3 steering):**

| Category | beta=0 | beta=3 | Delta |
|---|---|---|---|
| Content | 61.9% | 85.7% | +23.8 pp |
| Position | 66.7% | 73.3% | +6.7 pp |
| Count | 100% | 100% | 0 |
| Format | 100% | 100% | 0 |
| **Overall** | 75.9% | 87.0% | +11.1 pp |

### `tab:n5-ar` (appendix, lines 115-131)
**AR GAR-ours on N=5 ten-turn conversations:**

| Configuration | AR GAR-O | Delta vs Table 1 |
|---|---|---|
| Base | 0.012 | -0.007 |
| ThreadGate | 0.016 | -0.048 |
| +PCGrad | 0.015 | -0.015 |
| Uniform Gate | 0.015 | -0.018 |
| LoRA-only | 0.025 | -0.012 |

### `tab:stat-tests` (appendix, lines 145-167)
**Consolidated statistical tests:**

| Comparison | Test | p | r |
|---|---|---|---|
| *AR GAR-ours (beta=0):* | | | |
| TG vs. Base | Wilcoxon | <0.001 | 0.802 |
| TG vs. LoRA-only | Wilcoxon | 0.004 | 0.454 |
| TG vs. +PCGrad | Wilcoxon | 0.002 | --- |
| SS vs. TG | Wilcoxon | <0.001 | 0.869 |
| *Gate conditioning (28 layers):* | | | |
| Turn 1 vs. Turn 21 | Wilcoxon | 3.7e-8 | 0.975 |
| *Instruction retention:* | | | |
| beta=0 vs. beta=3 | McNemar | 0.077 | --- |
| GAR--compliance | Pearson | 0.007 | 0.200 |

### `tab:llama-full` (appendix, lines 179-196)
**Llama-3.1-8B-Instruct complete results:**

| Config | TF GAR-O | TF PPL | AR GAR-O (mean) | AR GAR-O (median) |
|---|---|---|---|---|
| Base | 0.017 | 3.45 | 0.009 | 0.009 |
| ThreadGate | 0.484 | 2.57 | 0.043 | 0.018 |
| LoRA-only | 0.481 | 2.60 | 0.028 | 0.018 |
| **SS** | 0.477 | 2.82 | **0.166** | --- |

### `tab:gradient-crossmodel` (appendix, lines 219-232)
**Cross-model NTP-GAR gradient interaction:**

| Metric | Qwen-7B | Llama-8B |
|---|---|---|
| Mean cos sim | -0.042 | +0.005 |
| Neg-layer % | 67.9% | 53.1% |
| NTP/GAR mag ratio | 14.7x | 25.7x |

### `tab:steering-full` (appendix, lines 306-329)
**Full attention steering results:**

| beta | N=5 Gen GAR | N=5 Gen PPL | N=50 Gen GAR | N=50 Gen PPL | N=200 TF GAR | N=200 TF PPL |
|---|---|---|---|---|---|---|
| 0 | .028 | 1.41 | .064 +/- .081 | 1.43 +/- .10 | .535 | 2.62 |
| 0.5 | .029 | 1.39 | --- | --- | --- | --- |
| 1 | .035 | 1.36 | --- | --- | --- | --- |
| 2 | .062 | 1.41 | .128 +/- .110 | 1.48 +/- .14 | .611 | 2.69 |
| 3 | --- | --- | .556 +/- .060 | 1.56 +/- .17 | .788 | 2.93 |
| 4 | --- | --- | .644 +/- .061 | 1.67 +/- .22 | .817 | 3.49 |
| **5** | **.680** | **1.91** | **.727 +/- .061** | **1.77 +/- .27** | **.833** | **6.15** |
| 10 | .959 | 4.22 | .961 +/- .015 | 3.45 +/- 1.78 | .977 | 505.2 |

### `tab:gate-profile` (appendix, lines 342-362)
**Per-layer gate values for ThreadGate (seed 123), Qwen-2.5-7B:**

| L0 | L1 | L2 | L3 | L4 | L5 | L6 | L7 |
|---|---|---|---|---|---|---|---|
| .883 | **.793** | .996 | .988 | .984 | **.797** | .961 | .918 |

| L8 | L9 | L10 | L11 | L12 | L13 | L14 | L15 |
|---|---|---|---|---|---|---|---|
| .965 | .934 | .969 | .918 | .926 | .941 | .930 | .965 |

| L16 | L17 | L18 | L19 | L20 | L21 | L22 | L23 |
|---|---|---|---|---|---|---|---|
| .941 | .910 | .961 | .965 | .973 | .988 | .969 | .980 |

| L24 | L25 | L26 | L27 | Summary |
|---|---|---|---|---|
| .980 | .984 | .988 | 1.00 | g_bar=.947, sigma=.051 |

### `tab:cost` (appendix, lines 387-410)
**Computational cost:**

| Config | Params | Time (h) | VRAM | Overhead |
|---|---|---|---|---|
| *Qwen-2.5-7B:* | | | | |
| LoRA-only | 4.2M | 6.0 | 42 GB | baseline |
| ThreadGate | 4.3M | 6.0 | 43 GB | +57K |
| +PCGrad | 4.3M | 8.0 | 43 GB | +33% |
| Uniform Gate | 4.3M | 6.0 | 43 GB | +57K |
| SS (s42) | 4.3M | 6.5 | 43 GB | +8% |
| SS (s123) | 4.3M | 10.8 | 43 GB | +80% |
| SS (s456) | 4.3M | 6.5 | 43 GB | +8% |
| *Llama-3.1-8B:* | | | | |
| LoRA-only | 4.2M | 7.0 | 45 GB | baseline |
| ThreadGate | 4.3M | 7.3 | 46 GB | +65K |

### `tab:examples` (appendix, lines 422-436)
**Qualitative steering examples (4-turn conversation):**

| Turn | beta=0 (unsteered) | beta=3 (steered) |
|---|---|---|
| 1 | check - Three bullet points, on-topic | check - Three bullet points, on-topic |
| 2 | check - Three bullet points, relevant | check - Three bullet points, relevant |
| 3 | ~ - Four bullet points, partially on-topic | check - Three bullet points, on-topic |
| 4 | X - Free-form paragraph, no bullets | check - Three bullet points, on-topic |

### `tab:data-stats` (appendix, lines 470-485)
**Training and evaluation data characteristics:**

| Property | Train | Eval (primary) |
|---|---|---|
| Conversations | 8,000 | 50 |
| Min user turns | 3 | 3 |
| Max sequence length | 2,048 | 2,048 |

### `tab:kl-perhead` (appendix, lines 530-543)
**Per-head TF-AR divergence statistics:**

| Metric | Base | TG |
|---|---|---|
| Mean Delta-GAR | 0.012 | 0.016 |
| Mean KL | 0.043 | 0.054 |
| Corr(TF_GAR, Delta-GAR) | 0.673 | 0.743 |

### `tab:gar-robust` (appendix, lines 555-569)
**Mid-turn GAR under four alternative definitions (N=50):**

| Definition | Base | TG | SS |
|---|---|---|---|
| Ours (last-token) | 0.015 | **0.325** | **0.458** |
| All-token | 0.015 | 0.025 | **0.366** |
| First-token | 0.022 | 0.039 | **0.412** |
| Goal-only | 0.005 | **0.310** | **0.444** |

### `tab:mmlu` (appendix, lines 579-597)
**MMLU 5-shot accuracy on Qwen-2.5-7B-Instruct:**

| Model | Acc (%) | Delta vs Base |
|---|---|---|
| Base (LoRA-only) | 74.23 | --- |
| PCGrad | 73.86 | -0.38 |
| SS | 73.75 | -0.48 |
| LoRA-only | 73.57 | -0.66 |
| ThreadGate | 73.47 | -0.77 |
| Uniform Gate | 73.46 | -0.78 |

### `tab:1.5b-steering` (appendix, lines 607-625)
**Cross-scale beta-steering on Qwen-2.5-1.5B (N=50, AR):**

| Model | beta | AR GAR | PPL (median) |
|---|---|---|---|
| Base | 0 | 0.017 | 1.909 |
| TG | 0 | 0.023 | 1.897 |
| Base | 3 | 0.120 | 2.216 |
| TG | 3 | 0.114 | 1.975 |
| Base | 5 | 0.657 | 2.804 |
| TG | 5 | 0.715 | 2.624 |

### `tab:llama-ss-steering` (appendix, lines 796-807)
**Beta-steering on Llama-3.1-8B SS model (N=50, T=4):**

| | beta=0 | beta=3 | beta=5 |
|---|---|---|---|
| AR GAR | 0.166 | 0.173 | 0.791 |

### `tab:llama-vs-qwen-ss` (appendix, lines 818-837)
**Scheduled sampling comparison: Qwen-7B vs Llama-8B:**

| Metric | Qwen-7B | Llama-8B |
|---|---|---|
| SS epochs | 3 | 2 |
| TF GAR | 0.498 | 0.477 |
| AR GAR (beta=0) | 0.401 | 0.166 |
| TF/AR gap | 1.2x | 2.9x |
| Baseline TG gap | 7.8x | 27x (median) |
| Gap compression | 6.5x | 9.3x |
| AR GAR (beta=5) | 0.717 | 0.791 |
| TF PPL | 2.78 | 2.82 |
| AR PPL | 1.441 | 1.370 |

---

## Externally-Included Tables (from `artifacts/appendix_expansion/`)

### `tab:crossmodel-detail` (tab_crossmodel_detail.tex)
**Cross-model comparison:**

| Model | Condition | TF GAR | AR GAR | TF PPL | AR PPL | Gap |
|---|---|---|---|---|---|---|
| Qwen-7B | Base | 0.013 | 0.019 | 4.34 | 1.447 | 0.7x |
| Qwen-7B | TG | 0.504 | 0.064 | 2.78 | 1.432 | 7.9x |
| Qwen-7B | LoRA-only | 0.498 | 0.037 | 2.78 | 1.431 | 13.5x |
| Qwen-7B | **SS** | 0.498 | **0.401** | 2.78 | 1.441 | **1.2x** |
| Llama-8B | Base | 0.017 | 0.009 | 3.45 | 1.293 | 1.9x |
| Llama-8B | TG | 0.484 | 0.043 | 2.57 | 1.437 | 11.2x |
| Llama-8B | LoRA-only | 0.481 | 0.028 | 2.60 | 1.419 | 17.2x |
| Llama-8B | **SS** | 0.477 | **0.166** | 2.82 | 1.370 | **2.9x** |

### `tab:perseed-ss` (tab_perseed_ss.tex)
**Per-seed SS results on Qwen-2.5-7B:**

| Metric | Seed 42 | Seed 123 | Seed 456 | Mean +/- Std |
|---|---|---|---|---|
| *TF:* | | | | |
| GAR-ours | 0.502 | 0.554 | 0.496 | 0.517 +/- 0.032 |
| GAR-Dongre | 0.389 | 0.411 | 0.386 | 0.395 +/- 0.014 |
| PPL | 2.780 | 2.612 | 2.611 | 2.668 +/- 0.097 |
| *AR beta=0:* | | | | |
| GAR-ours | 0.347 | 0.423 | 0.433 | 0.401 +/- 0.047 |
| PPL | 1.442 | 1.441 | 1.439 | 1.441 +/- 0.002 |
| *AR beta=3:* | | | | |
| GAR-ours | 0.593 | 0.590 | 0.605 | 0.596 +/- 0.008 |
| PPL | 1.564 | 1.607 | 1.587 | 1.586 +/- 0.022 |
| *AR beta=5:* | | | | |
| GAR-ours | 0.717 | 0.717 | 0.716 | 0.717 +/- 0.001 |
| PPL | 1.779 | 1.785 | 1.804 | 1.789 +/- 0.013 |

### `tab:perseed-tg` (tab_perseed_tg.tex)
**Per-seed ThreadGate results on Qwen-2.5-7B:**

| Metric | Seed 42 | Seed 123 | Mean +/- Std |
|---|---|---|---|
| *TF:* | | | |
| GAR-ours | 0.504 | 0.505 | 0.504 +/- 0.001 |
| GAR-Dongre | 0.015 | 0.012 | 0.014 +/- 0.002 |
| PPL | 2.784 | 2.780 | 2.782 +/- 0.003 |
| *AR beta=0:* | | | |
| GAR-ours | 0.016 | 0.017 | 0.016 +/- 0.001 |
| GAR-Dongre | 0.019 | 0.018 | 0.019 +/- 0.001 |
| PPL | 1.360 | 1.386 | 1.373 +/- 0.018 |
| *Derived:* | | | |
| Gap ratio (TF/AR) | 32.1 | 30.6 | 31.4 +/- 1.1 |

### `tab:perturn-qwen` (tab_perturn_qwen.tex)
**Per-turn AR GAR-ours (beta=0) on Qwen-2.5-7B:**

| Config | Turn 1 | Turn 2 | Turn 3 | Turn 4 | Turn 5 |
|---|---|---|---|---|---|
| Base | .085 | .032 | .021 | .013 | .004 |
| ThreadGate | .130 | .073 | .059 | .043 | .066 |
| PCGrad | .090 | .038 | .028 | .029 | .027 |
| UG | .113 | .056 | .033 | .020 | .016 |
| LoRA-only | .107 | .059 | .030 | .049 | .040 |
| SS | **.458** | **.381** | **.344** | **.370** | **.365** |

### `tab:perturn-llama` (tab_perturn_llama.tex)
**Per-turn AR GAR-ours (beta=0) on Llama-3.1-8B:**

*Panel (a): N=20, T=4:*

| Config | T1 | T2 | T3 | T4 |
|---|---|---|---|---|
| Base | .028 | .013 | .009 | .008 |
| TG | .041 | .042 | .049 | .038 |
| LoRA-only | .033 | .049 | .025 | .031 |

*Panel (b): Base decay (N=5, T=10):*

| Turn | GAR-ours |
|---|---|
| 1 | .026 |
| 2 | .018 |
| 3 | .009 |
| 4 | .006 |
| 5 | .006 |
| 6 | .004 |
| 7 | .004 |
| 8 | .004 |
| 9 | .005 |
| 10 | .003 |

### `tab:dataset_stats` (tab_dataset_stats.tex)
**Dataset statistics:**

| Statistic | Value |
|---|---|
| Total conversations | 207,865 |
| After >=5 turn filter | 17,302 |
| Training | 8,000 |
| Held-out AR eval | 50 |
| IID GAR diagnostic | 50 |
| Instruction retention | 200 |
| Avg. assistant turns | 5.6 |
| Min / Max turns | 5 / 7 |

### `tab:gar_robustness` (tab_gar_robustness.tex)
**GAR robustness across token selection strategies (extended version with Turn-1 and Gap Ratio):**

| Token Selection | Condition | Turn-1 GAR | Mid-turn GAR | Gap Ratio |
|---|---|---|---|---|
| Last (ours) | Base | 0.0858 | 0.0152 | 5.64x |
| Last (ours) | TG | 0.3938 | 0.3254 | 1.21x |
| Last (ours) | SS | 0.5274 | 0.4582 | 1.15x |
| All tokens | Base | 0.1152 | 0.0152 | 7.57x |
| All tokens | TG | 0.1275 | 0.0253 | 5.04x |
| All tokens | SS | 0.5043 | 0.3658 | 1.38x |
| First token | Base | 0.2987 | 0.0224 | 13.32x |
| First token | TG | 0.3225 | 0.0392 | 8.24x |
| First token | SS | 0.7549 | 0.4118 | 1.83x |
| Goal-only | Base | 0.0110 | 0.0049 | 2.23x |
| Goal-only | TG | 0.3313 | 0.3103 | 1.07x |
| Goal-only | SS | 0.4528 | 0.4435 | 1.02x |

### `tab:statistical_tests` (tab_statistical_tests.tex)
**Full statistical significance tests (extended version with CIs):**

| beta | Comparison | Test | Stat | p | r | GAR [95% CI] | Sig |
|---|---|---|---|---|---|---|---|
| 0.0 | TG vs Base | Wilcoxon | W=31 | <.001 | .802 | .064[.041,.091] vs .019[.014,.024] | *** |
| 0.0 | TG vs LoRA | Wilcoxon | W=187 | .004 | .454 | .064[.041,.091] vs .037[.027,.050] | ** |
| 0.0 | SS vs TG | Wilcoxon | W=1 | <.001 | .869 | .347[.327,.366] vs .064[.041,.091] | *** |
| 0.0 | PCGrad vs TG | Wilcoxon | W=176 | .002 | .478 | .030[.023,.038] vs .064[.041,.091] | ** |
| 3.0 | TG vs Base | Wilcoxon | W=242 | .039 | .331 | .556[.538,.575] vs .531[.514,.550] | * |
| 3.0 | TG vs LoRA | Wilcoxon | W=376 | .852 | .031 | .556[.538,.575] vs .560[.541,.581] | n.s. |
| 3.0 | SS vs TG | Wilcoxon | W=207 | .010 | .409 | .593[.574,.613] vs .556[.538,.575] | ** |
| 3.0 | PCGrad vs TG | Wilcoxon | W=368 | .767 | .049 | .559[.543,.576] vs .556[.538,.575] | n.s. |
| 5.0 | TG vs Base | Wilcoxon | W=251 | .084 | .281 | .727[.708,.747] vs .704[.679,.730] | n.s. |
| 5.0 | TG vs LoRA | Wilcoxon | W=277 | .180 | .220 | .727[.708,.747] vs .708[.687,.729] | n.s. |
| 5.0 | SS vs TG | Wilcoxon | W=314 | .421 | .133 | .717[.696,.738] vs .727[.708,.747] | n.s. |
| 5.0 | PCGrad vs TG | Wilcoxon | W=266 | .133 | .246 | .708[.690,.727] vs .727[.708,.747] | n.s. |
| --- | beta=0 vs beta=3 | McNemar | chi2=3.13 | .077 | .200 (point-biserial) | Rate: .759 vs .870 (N=54) | n.s. (marginal) |

### `tab:mmlu_detail` (tab_mmlu_detail.tex)
**MMLU accuracy (%) by category:**

| Category | Base | TG | PCGrad | SS | LoRA-only | UG |
|---|---|---|---|---|---|---|
| STEM | 70.69 | 69.20 | 69.55 | 69.97 | 70.03 | 69.65 |
| Social Sciences | 77.28 | 76.92 | 76.79 | 76.83 | 77.08 | 77.02 |
| Humanities | 83.95 | 83.33 | 84.08 | 83.39 | 83.62 | 83.95 |
| Other | 68.25 | 67.59 | 68.12 | 67.95 | 67.06 | 66.80 |
| **Overall** | **74.23** | 73.47 | 73.86 | 73.75 | 73.57 | 73.46 |
| Delta | --- | -0.76 | -0.37 | -0.48 | -0.66 | -0.77 |

### `tab:qwen15b_results` (tab_qwen15b_results.tex)
**Cross-scale validation on Qwen-2.5-1.5B:**

| Phase | Metric | Base | TG | p-value |
|---|---|---|---|---|
| *Phase 1: GAR diagnostic* | | | | |
| | Turn-1 GAR | 0.0336 | --- | --- |
| | Mid-turn GAR | 0.0068 | --- | --- |
| | Relative drop | 79.8% | --- | --- |
| *Phase 2: TG training* | | | | |
| | AR @ beta=0 | 0.0167 +/- 0.005 | **0.0233** +/- 0.006 | 0.005** |
| | AR @ beta=3 | 0.1202 +/- 0.032 | 0.1143 +/- 0.019 | 0.815 |
| | AR @ beta=5 | 0.6571 +/- 0.020 | **0.7150** +/- 0.017 | <0.001*** |

Effect sizes: r=0.447 (beta=0), r=0.749 (beta=5).

---

**Summary of all tables found:**
- **3 main-text tables**: `tab:five-way`, `tab:four-way`, `tab:grad-conflict`
- **18 appendix tables defined inline**: `tab:hyperparams`, `tab:loss-iterations`, `tab:ir-results`, `tab:n5-ar`, `tab:stat-tests`, `tab:llama-full`, `tab:gradient-crossmodel`, `tab:steering-full`, `tab:gate-profile`, `tab:cost`, `tab:examples`, `tab:data-stats`, `tab:kl-perhead`, `tab:gar-robust`, `tab:mmlu`, `tab:1.5b-steering`, `tab:llama-ss-steering`, `tab:llama-vs-qwen-ss`
- **10 externally-included tables** (from `artifacts/appendix_expansion/`): `tab:crossmodel-detail`, `tab:perseed-ss`, `tab:perseed-tg`, `tab:perturn-qwen`, `tab:perturn-llama`, `tab:dataset_stats`, `tab:gar_robustness`, `tab:statistical_tests`, `tab:mmlu_detail`, `tab:qwen15b_results`

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5590931a-0b7c-4748-914f-78ccedba510d",
  "isSidechain": true,
  "agentId": "abd64e66887e6e7f7",
  "requestId": "req_011CbPu6YDVBu4rYzKafKdEs",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "281deb27-7737-4521-8f1c-50cd19ff595a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/turn_residual_gating",
  "sessionId": "d70d7bf3-a76c-4cf3-8f74-bbfe748e5a99",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XiRbi1VPGV2PvtDHgSCLoR",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8967,
      "cache_read_input_tokens": 54382,
      "output_tokens": 8717,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 8967
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 8717,
          "cache_read_input_tokens": 54382,
          "cache_creation_input_tokens": 8967,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 8967,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---
