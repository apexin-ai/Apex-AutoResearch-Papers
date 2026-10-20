# Research conversation: Read all the LaTeX files in the paper directory for the irt_personfit_contam project. I need to extract every numerical 

**What Can IRT Person-Fit Statistics Reveal About SFT-Stage Benchmark Contamination? (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 33
- **Recorded user turns:** 1
- **Tool calls:** 13
- **Original source:** `logs/chats/exported-trajectories/account-2/agent-afe11dee6ca447a7a.jsonl`
- **Structured JSON:** [`6521bafe3aea41efc0fc.json`](../../sessions/65/6521bafe3aea41efc0fc.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

33 recorded events

### User

_source line 1 · 2026-05-23T11:15:53.441Z_

Read all the LaTeX files in the paper directory for the irt_personfit_contam project. I need to extract every numerical value from the paper.

1. First glob for all .tex files under /home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/
2. Read each .tex file fully, especially:
   - sections/results.tex (contains Table 1, Table 2, Table 3)
   - sections/discussion.tex or any discussion section
   - sections/appendix.tex or any appendix
   - The main paper file
   - Any other section files

For each table, extract every single number. For Table 1 (tab:cohens_d), I need every Cohen's |d| value and CI for each row. For Table 2 (tab:theta_shift), every theta-shift and fixed-theta |d| value. For Table 3 (tab:degradation), every |d| value for lz*, HT, Acc z.

Also look for these specific numbers mentioned in discussion/appendix:
- GRPO MIA AUC values (SFT=0.611, post-RL=0.493)
- GRPO lz* ~3.3
- ARC-C efficacy 0.087/0.285
- theta-shift threshold Δθ>0.2
- 57/60 systematic violations
- n=10 clean seeds
- Qwen clean baseline: mean=8.6838, std=0.7353

Report ALL numbers found with their exact context and location (file:line).


<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "422e51b4-ab1c-4159-82e8-b6ec242f5d4b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 2 · 2026-05-23T11:15:54.749Z_

I'll help you extract all numerical values from the LaTeX files in the paper directory. Let me start by globbing for all .tex files and then reading them systematically.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "422e51b4-ab1c-4159-82e8-b6ec242f5d4b",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQTYss58kMQA7YxnKin",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "b310c611-3af2-4ac3-a8a5-c9451b5aef85",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_013fGx3L9gUufhM4rgue9Dci",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 18152,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 18152,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 7,
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

_source line 3 · 2026-05-23T11:15:55.054Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01VVEQceRwLeqo8Jq6D458hA`</summary>

```json
{
  "pattern": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/**/*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b310c611-3af2-4ac3-a8a5-c9451b5aef85",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQTYss58kMQA7YxnKin",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "bd9d05db-69f9-47ab-ad6c-534781f37340",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_013fGx3L9gUufhM4rgue9Dci",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 18152,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 18152,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 7,
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

_source line 4 · 2026-05-23T11:15:55.067Z_

<details><summary>↩ Tool result · `toolu_01VVEQceRwLeqo8Jq6D458hA`</summary>

```text
paper/sections/experiments.tex
paper/sections/background.tex
paper/sections/sec_empirical.tex
paper/sections/sec_simulation.tex
paper/sections/sec_setup.tex
paper/sections/sec_ctrl_contam.tex
paper/sections/related_work.tex
paper/sections/method.tex
paper/sections/abstract.tex
paper/sections/introduction.tex
paper/sections/results.tex
paper/sections/discussion.tex
paper/sections/appendix.tex
paper/sections/limitations.tex
paper/sections/conclusion.tex
paper/main.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bd9d05db-69f9-47ab-ad6c-534781f37340",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "8a255075-f7bb-41bb-bf7c-dc3727e6bdee",
  "sourceToolAssistantUUID": "bd9d05db-69f9-47ab-ad6c-534781f37340",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-23T11:15:55.208Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01QMJyVUuFnrqRuny5YzSbNV`</summary>

```json
{
  "command": "find /home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper -name \"*.tex\" -type f"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8a255075-f7bb-41bb-bf7c-dc3727e6bdee",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQTYss58kMQA7YxnKin",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "96e0053d-b648-4276-bc04-e661b425bde3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_013fGx3L9gUufhM4rgue9Dci",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 18152,
      "cache_read_input_tokens": 0,
      "output_tokens": 203,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 18152
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 203,
          "cache_read_input_tokens": 0,
          "cache_creation_input_tokens": 18152,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 18152,
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

_source line 6 · 2026-05-23T11:15:55.361Z_

<details><summary>↩ Tool result · `toolu_01QMJyVUuFnrqRuny5YzSbNV`</summary>

```text
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/introduction.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_simulation.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_setup.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/background.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_empirical.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/method.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/sec_ctrl_contam.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/discussion.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/conclusion.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/experiments.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/related_work.tex
/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/main.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "96e0053d-b648-4276-bc04-e661b425bde3",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "5eb28adf-79ec-4519-86e9-e47f74922a3a",
  "sourceToolAssistantUUID": "96e0053d-b648-4276-bc04-e661b425bde3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 7 · 2026-05-23T11:15:56.500Z_

Now let me read the key files. I'll start with the most important ones: main.tex, results.tex, discussion.tex, and appendix.tex.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5eb28adf-79ec-4519-86e9-e47f74922a3a",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQTgxnUehjAAPzpXHyB",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "2c5a5a31-03b7-483f-8484-d63de04c55b3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01MfajhbXAHXaAL1phQSajGV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 1904,
      "cache_read_input_tokens": 18152,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1904,
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

_source line 8 · 2026-05-23T11:15:56.754Z_

<details open><summary>🔧 Tool call — Read · `toolu_01EV69VMHSZNz5KJXGTghTfo`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2c5a5a31-03b7-483f-8484-d63de04c55b3",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQTgxnUehjAAPzpXHyB",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "bb5d3a8f-b257-4a17-bffe-9a4d23bedf3a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01MfajhbXAHXaAL1phQSajGV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 1904,
      "cache_read_input_tokens": 18152,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1904,
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

### Tool result

_source line 9 · 2026-05-23T11:15:56.764Z_

<details><summary>↩ Tool result · reported error · `toolu_01EV69VMHSZNz5KJXGTghTfo`</summary>

```text
File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bb5d3a8f-b257-4a17-bffe-9a4d23bedf3a",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "94657aed-756d-4b4b-b4bb-b0f3334a94f2",
  "toolUseResult": "Error: File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam.",
  "sourceToolAssistantUUID": "bb5d3a8f-b257-4a17-bffe-9a4d23bedf3a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 10 · 2026-05-23T11:15:57.139Z_

<details open><summary>🔧 Tool call — Read · `toolu_015iNXth2Sybg2qtNw5tvBSX`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "94657aed-756d-4b4b-b4bb-b0f3334a94f2",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQTgxnUehjAAPzpXHyB",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "a4ed350a-bd2a-4dce-af91-f3491e5a3925",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01MfajhbXAHXaAL1phQSajGV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 1904,
      "cache_read_input_tokens": 18152,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1904,
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

### Tool result

_source line 11 · 2026-05-23T11:15:57.145Z_

<details><summary>↩ Tool result · `toolu_015iNXth2Sybg2qtNw5tvBSX`</summary>

```text
1	\documentclass[11pt]{article}
2	\usepackage[review]{acl}
3	\usepackage{times}
4	\usepackage{latexsym}
5	\usepackage[T1]{fontenc}
6	\usepackage[utf8]{inputenc}
7	\usepackage{microtype}
8	\usepackage{graphicx}
9	\usepackage{booktabs}
10	\usepackage{amsmath}
11	\usepackage{amssymb}
12	\usepackage{multirow}
13	\usepackage{xcolor}
14	\usepackage{subcaption}
15	\usepackage{enumitem}
16	
17	\newcommand{\irtfit}{\textsc{IRT-FIT}}
18	
19	\graphicspath{{../figures/paper/}}
20	
21	\title{What Can IRT Person-Fit Statistics Reveal About SFT-Stage Benchmark Contamination?}
22	
23	\author{Anonymous}
24	
25	\begin{document}
26	\maketitle
27	
28	\begin{abstract}
29	\input{sections/abstract}
30	\end{abstract}
31	
32	\input{sections/introduction}
33	\input{sections/related_work}
34	\input{sections/method}
35	\input{sections/results}
36	\input{sections/discussion}
37	\input{sections/conclusion}
38	
39	\input{sections/limitations}
40	
41	\section*{Reproducibility Statement}
42	Code and response data will be released upon acceptance.
43	Bootstrap confidence intervals use the percentile method with 10,000 resamples.
44	All three model families use clean baseline seeds 0--9 ($n{=}10$ per family).
45	Pre-calibrated 4PL item parameters are from the publicly available PSN-IRT item bank \citep{psnirt2026}.
46	Training used PyTorch 2.8.0, Transformers 5.8.1, PEFT 0.19.1, and BitsAndBytes 0.49.2.
47	Both benchmarks are publicly available under permissive licenses (MMLU: MIT; ARC-Challenge: CC-BY-SA).
48	
49	\bibliography{references}
50	
51	\appendix
52	\input{sections/appendix}
53	
54	\end{document}
55	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a4ed350a-bd2a-4dce-af91-f3491e5a3925",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "7f14b929-6d70-4918-82f1-fc05047a2d90",
  "sourceToolAssistantUUID": "a4ed350a-bd2a-4dce-af91-f3491e5a3925",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 12 · 2026-05-23T11:15:57.243Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WwbYYPBeAexPxo2aFHNsdt`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7f14b929-6d70-4918-82f1-fc05047a2d90",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQTgxnUehjAAPzpXHyB",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "46c3bc77-1df6-4652-9b05-de6426b2e43f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01MfajhbXAHXaAL1phQSajGV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 1904,
      "cache_read_input_tokens": 18152,
      "output_tokens": 276,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1904
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 6,
          "output_tokens": 276,
          "cache_read_input_tokens": 18152,
          "cache_creation_input_tokens": 1904,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1904,
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

_source line 13 · 2026-05-23T11:15:57.249Z_

<details><summary>↩ Tool result · `toolu_01WwbYYPBeAexPxo2aFHNsdt`</summary>

```text
1	\section{Results}
2	\label{sec:results}
3	
4	\subsection{Detection Signal Across Model Families}
5	\label{sec:detection}
6	
7	Table~\ref{tab:cohens_d} presents Cohen's $d$ effect sizes for $\ell_z^*$ across three model families and two benchmarks.
8	All confidence intervals exclude zero, confirming that $\Delta\ell_z^*$ reliably separates contaminated from clean models at both contamination levels.
9	
10	On MMLU, effect sizes range from $|d|{=}2.27$ (Llama at 15\%) to $|d|{=}7.44$ (Qwen at 25\%), with Qwen at 5\% ($|d|{=}4.15$) confirming detection at the lowest contamination level tested. Llama ($|d|{=}2.27$/$2.97$/$2.50$) and Mistral ($|d|{=}3.01$/$3.50$) show comparable magnitudes.
11	On ARC-C (295 items), Qwen yields $|d|{=}3.16$ at 15\% and $|d|{=}5.30$ at 50\%, demonstrating that detection remains feasible even on small benchmarks when contamination is sufficiently concentrated.
12	
13	Clean-model $\ell_z^*$ baselines diverge substantially across families: Qwen ${+}8.68$ ($\text{SD}{=}0.74$), Mistral ${+}4.02$ ($\text{SD}{=}2.05$), Llama ${+}0.29$ ($\text{SD}{=}1.45$), and ARC-C Qwen ${-}5.42$ ($\text{SD}{=}0.16$).
14	Absolute $\ell_z^*$ thresholds would produce contradictory results: Qwen's contaminated $\ell_z^*$ at 15\% (${+}3.85$) is still positive.
15	The $\Delta\ell_z^*$ design normalizes these divergent baselines: Cohen's $d$ yields comparable effect sizes ($|d|{=}2.27$--$7.44$) despite order-of-magnitude differences.
16	Figure~\ref{fig:heatmap} provides a visual summary.
17	
18	\begin{table}[t]
19	\centering
20	\caption{Cohen's $d$ for $\Delta\ell_z^*$ across model families ($n{=}10$ clean seeds). Single-seed conditions: percentile bootstrap 95\% CI (10,000 resamples) reflecting clean-seed variability. Qwen MMLU 15\%/25\%/50\%: multi-seed mean $\pm$ SD ($n{=}3$ independent contamination runs). All exclude zero.}
21	\label{tab:cohens_d}
22	\footnotesize
23	\resizebox{\columnwidth}{!}{%
24	\begin{tabular}{@{}llrrrr@{}}
25	\toprule
26	Model & Bench. & $d$ (5\%) [CI] & $d$ (15\%) [CI] & $d$ (25\%) [CI] & $d$ (50\%) [CI] \\
27	\midrule
28	Qwen$^{\dagger}$ & MMLU & $-4.15$ [$-9.9$, $-2.7$] & $-5.36$ ($\pm$1.10) & $-7.44$ ($\pm$1.86) & $-5.08$ ($\pm$3.02) \\
29	Llama & MMLU & --- & $-2.27$ [$-4.6$, $-1.6$] & $-2.97$ [$-6.1$, $-2.0$] & $-2.50$ [$-5.0$, $-1.8$] \\
30	Mistral & MMLU & --- & $-3.01$ [$-8.2$, $-1.8$] & --- & $-3.50$ [$-9.4$, $-2.1$] \\
31	Qwen$^{\dagger}$ & ARC-C & --- & $+3.16$ [$2.0$, $9.5$] & --- & $+5.30$ [$3.6$, $15.2$] \\
32	\bottomrule
33	\multicolumn{6}{@{}l}{\scriptsize $^{\dagger}$15\%/25\%/50\%: multi-seed means ($n{=}3$ QLoRA runs); 5\%: single seed. Per-seed values in Appendix~\ref{app:reproducibility}.}
34	\end{tabular}}
35	\end{table}
36	
37	\begin{figure*}[t]
38	  \centering
39	  \includegraphics[width=\textwidth]{fig_heatmap.pdf}
40	  \caption{Cohen's $|d|$ heatmap (single-seed values; multi-seed means in Table~\ref{tab:cohens_d}). Blue intensity reflects effect-size magnitude. Grey cells: conditions not tested.}
41	  \label{fig:heatmap}
42	\end{figure*}
43	
44	\subsection{Model-Specific $\theta$-Shift Dynamics}
45	\label{sec:theta_dynamics}
46	
47	Contamination raises overall accuracy, which inflates $\hat{\theta}_{\text{MLE}}$; a higher $\hat{\theta}$ ``explains away'' anomalous successes on hard items, absorbing the contamination signal into the ability estimate.
48	We term this \emph{$\theta$-shift absorption}.
49	The magnitude of $\theta$-shift absorption varies across models: Qwen ($\Delta\theta{=}0.47$ at 50\%) absorbs substantially more signal than Llama ($\Delta\theta{=}0.09$), predicting that fixed-$\theta$ estimation should differentially amplify detection for high-absorption models.
50	Figure~\ref{fig:theta_scatter} plots baseline accuracy against Cohen's $|d|$ for all model-benchmark combinations.
51	
52	$\theta$-shift absorption is the dominant source of detection variability for high-ability models at high contamination:
53	(i) fixed-$\theta$ estimation amplifies Qwen's multi-seed $|d|$ by 2.4$\times$ at 50\% ($5.08 \to 12.32$; Table~\ref{tab:theta_fixed}), while Llama shows no amplification ($0.3\times$);
54	(ii) $\theta$-anchoring reduces Qwen's inter-seed CV from 60\% to 19\%, confirming that training-run variance is driven by $\theta$-shift stochasticity rather than true signal variance;
55	(iii) the cross-model ranking under free-$\theta$ is seed-dependent at 50\%, making $\theta$-anchoring a necessary condition for reliable detection of high-ability models at high contamination.
56	
57	ARC-C reverses this pattern.
58	Despite Qwen's high baseline accuracy on ARC-C (90.0\%), contamination produces larger, not smaller, effect sizes ($|d|{=}3.16$ at 15\%, $|d|{=}5.30$ at 50\%).
59	This reversal reflects a ceiling effect: with only 295 items and 90.0\% baseline accuracy, the already-correct items offer minimal room for further $\theta$ inflation, so contamination manifests primarily as anomalous successes on the few remaining hard items.
60	The small item count amplifies this concentration, producing a disproportionately large $\ell_z^*$ shift per contaminated item.
61	
62	The baseline $\ell_z^*$ for ARC-C is negative ($-5.42$), reflecting the 4PL model's expectation of near-perfect performance; contamination pushes $\ell_z^*$ toward zero, producing the positive Cohen's $d$ values in Table~\ref{tab:cohens_d}.
63	
64	These findings indicate that detection sensitivity is not a fixed property of $\ell_z^*$ but depends on the interaction between model ability and benchmark characteristics, a consideration absent from standard person-fit applications.
65	
66	\paragraph{Fixed-$\theta$ estimation.}
67	Table~\ref{tab:theta_fixed} compares free-$\theta$ and fixed-$\theta$ Cohen's $d$ across all three families.
68	The benefit of fixed-$\theta$ is strongly modulated by baseline ability and $\theta$-shift magnitude.
69	Qwen (67.8\% accuracy, $\Delta\theta{=}0.47$) shows the largest multi-seed amplification (2.4$\times$ at 50\%), because the high baseline provides substantial $\theta$-shift headroom that free estimation exploits.
70	Mistral (52.4\%) shows moderate amplification (1.7$\times$ at 50\%).
71	Llama (59.4\%) shows no benefit: its high cross-seed $\ell_z^*$ variance ($\text{SD}{=}1.45$) inflates the denominator, and its minimal $\theta$-shift ($\Delta\theta{=}0.09$) leaves little absorption to eliminate.
72	Fixed-$\theta$ is thus indicated for models with stable clean baselines and substantial $\theta$-shift ($\Delta\theta > 0.2$), not as a universal remedy.
73	
74	\begin{table}[t]
75	\centering
76	\caption{Free-$\theta$ vs.\ fixed-$\theta$ Cohen's $|d|$ on MMLU (bootstrap 95\% CI). Fixed-$\theta$ anchors $\hat{\theta}$ at the clean-model mean, eliminating $\theta$-shift absorption.}
77	\label{tab:theta_fixed}
78	\footnotesize
79	\begin{tabular}{@{}lcccc@{}}
80	\toprule
81	Model & $|d_{\text{free}}|$ & $|d_{\text{fixed}}|$ & Ratio & Fixed CI \\
82	\midrule
83	\multicolumn{5}{@{}l}{\textit{5\% contamination}} \\
84	Qwen & 4.15 & 3.52 & 0.8$\times$ & [2.9, 5.7] \\
85	\addlinespace
86	\multicolumn{5}{@{}l}{\textit{15\% contamination}} \\
87	Qwen$^{\S}$ & 5.36 & 6.85 & 1.3$\times$ & ($\pm$1.80) \\
88	Llama & 2.27 & 0.58 & 0.3$\times$ & [0, 2.37]$^{\dagger}$ \\
89	Mistral$^{\ddagger}$ & 3.01 & 2.69 & 0.9$\times$ & [1.45, 9.00] \\
90	\addlinespace
91	\multicolumn{5}{@{}l}{\textit{50\% contamination}} \\
92	Qwen$^{\S}$ & 5.08 & 12.32 & 2.4$\times$ & ($\pm$2.38) \\
93	Llama & 2.50 & 0.84 & 0.3$\times$ & [0.17, 2.97] \\
94	Mistral$^{\ddagger}$ & 3.50 & 5.80 & 1.7$\times$ & [3.71, 18.16] \\
95	\bottomrule
96	\multicolumn{5}{@{}l}{\scriptsize $^{\dagger}$CI includes zero.} \\
97	\multicolumn{5}{@{}l}{\scriptsize $^{\S}$Multi-seed mean ($n{=}3$); CI column shows $\pm$SD of fixed-$\theta$ $|d|$.} \\
98	\multicolumn{5}{@{}l}{\scriptsize $^{\ddagger}$Fixed-$\theta$: 6 seeds (4--7 response vectors not retained in pipeline); free-$\theta$ uses all 10.}
99	\end{tabular}
100	\end{table}
101	
102	\begin{figure}[t]
103	  \centering
104	  \includegraphics[width=\columnwidth]{fig_theta_scatter.pdf}
105	  \caption{Baseline accuracy vs.\ Cohen's $|d|$ for all model-benchmark combinations (single-seed values; multi-seed means in Table~\ref{tab:cohens_d}). Diamonds: 5\%; triangles: 15\%; squares: 25\%; circles: 50\%. ARC-C reversal reflects a ceiling effect.}
106	  \label{fig:theta_scatter}
107	\end{figure}
108	
109	\subsection{Detection-Diagnosis Tradeoff}
110	\label{sec:degradation}
111	
112	A natural question is whether the full 4PL IRT framework is necessary for contamination detection, or whether simpler statistics suffice.
113	Table~\ref{tab:degradation} compares three statistics at decreasing levels of information access: $\ell_z^*$ (requires 4PL parameters $a, b, c, d$), the HT statistic (requires only difficulty $b$), and an accuracy $z$-score (requires no item parameters).
114	
115	The comparison reveals a detection-diagnosis tradeoff.
116	For pure detection, simpler statistics are more powerful: accuracy $z$-scores yield $|d|$ values several-fold to over an order of magnitude larger than person-fit statistics (Table~\ref{tab:degradation}), because cross-seed accuracy variance is near-zero in controlled settings.
117	HT generally exceeds $\ell_z^*$ in detection strength, since HT is not attenuated by the Snijders correction for $\theta$ estimation uncertainty.
118	Both person-fit statistics exhibit seed-dependent non-monotonicity under free-$\theta$ estimation (Table~\ref{tab:degradation}), confirming that $\theta$-shift absorption affects all statistics conditioned on ability, not $\ell_z^*$ specifically.
119	
120	Yet the diagnostic power reverses.
121	Full IRT parameterization is unnecessary for mere detection, but the value of $\ell_z^*$ lies in three capabilities that HT and $z$-scores lack:
122	(a) \emph{seen/unseen decomposition}: $\ell_z^*$ can be computed separately on seen and unseen item subsets, though item-level detection is near-random (AUROC $\approx 0.53$; Appendix~\ref{app:item_auroc}), confirming that the contamination signal is diffuse and requires model-level aggregation;
123	(b) \emph{$\theta$-shift mechanism}: the ability parameter exposes why detection sensitivity depends on model ability (\S\ref{sec:theta_dynamics}), a mechanistic insight inaccessible to non-parametric statistics;
124	(c) \emph{structural sensitivity}: on real leaderboard data, $\ell_z^*$ flags 57/60 model-benchmark cells as aberrant---evidence of systematic IRT assumption violations that motivates the $\Delta\ell_z^*$ matched-difference design (\S\ref{sec:did}).
125	Accuracy $z$-scores flag only 4/60 cells, making them insensitive to the response-pattern structure that $\ell_z^*$ exploits for within-model diagnosis.
126	While such patterns have theoretical antecedents in person-fit literature \citep{stonge2011}, the specific magnitude and model-dependence we observe are new empirical findings in the LLM domain; nonparametric alternatives \citep{tendeiro2014} may complement $\ell_z^*$ where 4PL calibration is unavailable.
127	
128	In practice, a two-stage workflow follows: screen using accuracy $z$-scores (Table~\ref{tab:degradation}), then apply $\ell_z^*$ to characterize whether the signal reflects $\theta$-shift absorption (indicating fixed-$\theta$ anchoring is needed) or uniform aberrance (suggesting direct memorization).
129	
130	Within the IRT family, the 4PL specification matters: simulation ablations show a mean $+$27.3pp power gain over 3PL on MMLU, because 46\% of MMLU items have upper asymptote $d < 0.95$, and the 3PL model (which assumes $d{=}1$) misattributes slip-related response patterns as aberrance (Appendix~\ref{app:4pl_ablation}).
131	
132	\begin{table}[t]
133	\centering
134	\caption{Detection-diagnosis tradeoff on MMLU: Cohen's $|d|$ across three statistics. Simpler statistics detect more powerfully; $\ell_z^*$ provides unique diagnostic capabilities (\S\ref{sec:degradation}).}
135	\label{tab:degradation}
136	\footnotesize
137	\begin{tabular}{@{}llrr@{}}
138	\toprule
139	Model & Statistic & $|d|$ (15\%) & $|d|$ (50\%) \\
140	\midrule
141	Qwen$^\dagger$ & $\ell_z^*$ & $5.36$ ($\pm$1.10) & $5.08$ ($\pm$3.02) \\
142	     & HT & $5.83$ ($\pm$1.30) & $5.29$ ($\pm$3.41) \\
143	     & Acc.\ $z$ & $45.0$ ($\pm$2.5) & $70.0$ ($\pm$1.1) \\
144	\addlinespace
145	Llama & $\ell_z^*$ & $2.27$ [$1.6$, $4.6$] & $2.50$ [$1.8$, $5.2$] \\
146	      & HT & $2.45$ [$1.5$, $4.3$] & $3.07$ [$1.9$, $5.3$] \\
147	      & Acc.\ $z$ & $22.5$ [$13.6$, $47.0$] & $32.8$ [$19.8$, $68.6$] \\
148	\addlinespace
149	Mistral & $\ell_z^*$ & $3.01$ [$1.8$, $8.2$] & $3.50$ [$2.1$, $9.4$] \\
150	      & HT & $4.36$ [$1.2$, $7.0$] & $5.89$ [$1.9$, $9.4$] \\
151	      & Acc.\ $z$ & $7.81$ [$4.4$, $14.4$] & $16.6$ [$9.7$, $34.6$] \\
152	\bottomrule
153	\multicolumn{4}{@{}p{0.9\columnwidth}}{\scriptsize $^\dagger$Qwen values are means across $n{=}3$ independent seeds (42, 123, 456); per-seed values in Appendix~\ref{app:reproducibility}. Llama and Mistral are single-seed with bootstrap CIs.}
154	\end{tabular}
155	\end{table}
156	
157	\subsection{Ability-Dependent Non-Monotonic Dose-Response}
158	\label{sec:inverted_u}
159	
160	As an exploratory observation, the free-$\theta$ dose-response is non-monotonic for Qwen.
161	The multi-seed mean trajectory ($|d|$: $4.15 \to 5.36 \to 7.44 \to 5.08$ at 5\%/15\%/25\%/50\%; Appendix~\ref{app:reproducibility}) shows signal peaking at 25\% before declining at 50\%, but the decline is attenuated relative to single-seed estimates and the inter-seed variance at 50\% is high (CV${=}$60\%, range $[1.90, 7.91]$).
162	This non-monotonicity is a $\theta$-estimation artifact: fixed-$\theta$ analysis eliminates the inverted-U and reveals a strong positive dose-response (mean $|d|$: $5.89$ at 25\% vs.\ $12.32$ at 50\%, no seed-level overlap), while reducing the 50\% CV to 19\%.
163	Llama shows an attenuated, statistically non-significant pattern ($|d|{=}2.27 \to 2.97 \to 2.50$), consistent with its smaller $\theta$-shift ($\Delta\theta{=}0.09$ vs.\ $0.47$ for Qwen).
164	The mechanism is predictable from simulation (Appendix~\ref{app:simulation}): at moderate contamination, aberrant responses dominate; at high contamination, inflated $\hat{\theta}$ absorbs the anomaly---but the magnitude is highly seed-dependent.
165	
166	A simulated power analysis corroborates these findings: two-sided testing (flagging both large negative and large positive $\ell_z^*$) achieves ${>}$93\% power on MMLU at all contamination levels, with the theoretical power function yielding $R^2 {=} 0.957$ against simulated values (Appendix~\ref{app:simulation}).
167	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "46c3bc77-1df6-4652-9b05-de6426b2e43f",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "90c98b89-2181-4656-b77a-24c42a342f44",
  "sourceToolAssistantUUID": "46c3bc77-1df6-4652-9b05-de6426b2e43f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 14 · 2026-05-23T11:15:58.721Z_

Now let me read the discussion.tex and appendix.tex files:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "90c98b89-2181-4656-b77a-24c42a342f44",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQTqB9QYXb1FoeKyWGN",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "83f7599c-ec2a-412e-afce-0c5244cf04d5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_018Di9ejaFxb4otYjR7gNUxd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 6585,
      "cache_read_input_tokens": 20056,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6585,
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

_source line 15 · 2026-05-23T11:15:59.562Z_

<details open><summary>🔧 Tool call — Read · `toolu_011r4KPySW9VD8BHson5g8Hz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "83f7599c-ec2a-412e-afce-0c5244cf04d5",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQTqB9QYXb1FoeKyWGN",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "6b39156b-c6f3-4e4d-96e9-983e5a388d12",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_018Di9ejaFxb4otYjR7gNUxd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 6585,
      "cache_read_input_tokens": 20056,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6585,
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

### Tool result

_source line 16 · 2026-05-23T11:15:59.568Z_

<details><summary>↩ Tool result · `toolu_011r4KPySW9VD8BHson5g8Hz`</summary>

```text
1	\section{Discussion}\label{sec:discussion}
2	
3	Our findings reveal both the strengths and boundaries of IRT person-fit for contamination detection: $\ell_z^*$ reliably detects SFT-stage contamination across model families, but three boundary conditions constrain its practical utility.
4	
5	\paragraph{Characterization over tool.}
6	The detection-diagnosis tradeoff (\S\ref{sec:degradation}) shows that simpler statistics detect contamination more powerfully than $\ell_z^*$: accuracy $z$-scores yield $|d|$ values several-fold to over an order of magnitude larger, and HT generally exceeds $\ell_z^*$.
7	The value of the IRT framework lies not in detection power but in mechanistic understanding: the $\theta$-shift analysis reveals \emph{why} detection sensitivity varies across models and contamination levels, the seen/unseen decomposition identifies \emph{what fraction} of items are memorized, and the 4PL parameterization captures item-level ceiling effects that 3PL misattributes as aberrance.
8	These diagnostic capabilities are invisible to accuracy $z$-scores or HT.
9	Findings~1--2 are theoretically predictable from IRT principles; our contribution lies in quantifying these effects in the LLM setting, where the magnitude and boundary conditions are not derivable from theory alone.
10	
11	\paragraph{Practical implications.}
12	Two results have immediate consequences.
13	Free-$\theta$ estimation produces seed-dependent dose-response curves (CV up to 60\%); anchoring $\theta$ to a pre-contamination baseline stabilizes detection and amplifies the signal for models with substantial $\theta$-shift ($\Delta\theta > 0.2$).
14	The benchmark size boundary means $\ell_z^*$ is most informative for large benchmarks ($n > 7{,}000$ items for 80\% power at 15\% contamination); on small benchmarks like ARC-C (295 items), detection relies on concentrated contamination effects.
15	
16	\paragraph{Scope and calibration.}
17	Universal baseline misfit (57/60 cells flagged) confirms systematic IRT violations; the $\Delta\ell_z^*$ design turns this into a feature through within-model differencing.
18	PSN-IRT provides pre-calibrated 4PL parameters \citep{psnirt2026}, but classical calibration fails on contaminated data ($r_a{=}0.127$; Appendix~\ref{app:mml_em}); the calibration sample (13,000+ models) may itself include contaminated ones, though individual contamination effects are diluted across models.
19	The robustness analysis (Appendix~\ref{app:param_perturb}) provides partial reassurance (${\pm}10\%$ noise tolerance).
20	\paragraph{Information requirements and method positioning.}
21	$\ell_z^*$ sits below MIA \citep[logits;][]{minkprob2024} and ConStat \citep[multi-benchmark scores;][]{constat2024} in an information-requirements hierarchy, needing only single-benchmark binary patterns and an external item bank---suited to retrospective audits where logits are unavailable. Our GRPO pilot directly confirms this advantage: Min-K\% AUC degrades from $0.611$ (SFT) to $0.493$ (post-RL), indistinguishable from chance, while $\ell_z^*$ signal persists (${\sim}3.3$; Figure~\ref{fig:grpo}), demonstrating that response-pattern anomalies survive RL alignment that eliminates memorization-based features \citep{wang2025fragility}.
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6b39156b-c6f3-4e4d-96e9-983e5a388d12",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "511601dc-372b-491b-baa8-82847e0ecb3d",
  "sourceToolAssistantUUID": "6b39156b-c6f3-4e4d-96e9-983e5a388d12",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-23T11:15:59.860Z_

<details open><summary>🔧 Tool call — Read · `toolu_017PpfMjQXTAHFAnPW4pHj3D`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "511601dc-372b-491b-baa8-82847e0ecb3d",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQTqB9QYXb1FoeKyWGN",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "dec0c98c-6e64-472f-a18b-136eb65c838f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_018Di9ejaFxb4otYjR7gNUxd",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 6585,
      "cache_read_input_tokens": 20056,
      "output_tokens": 184,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 6585
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 6,
          "output_tokens": 184,
          "cache_read_input_tokens": 20056,
          "cache_creation_input_tokens": 6585,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 6585,
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

_source line 18 · 2026-05-23T11:15:59.869Z_

<details><summary>↩ Tool result · `toolu_017PpfMjQXTAHFAnPW4pHj3D`</summary>

```text
1	\section{Simulation Validation}
2	\label{app:simulation}
3	
4	Under the null (no contamination), bootstrap $\ell_z^*$ tracks $\mathcal{N}(0,1)$: mean bias 0.041 and standard deviation 1.003 on MMLU.
5	Kolmogorov--Smirnov rejection rates vary with benchmark size: 8.3\% for MMLU and HellaSwag ($n > 10{,}000$), 50.0\% for GSM8K ($n = 1{,}319$), 58.3\% for ARC-C ($n = 295$), and 75.0\% for HumanEval ($n = 164$).
6	$\ell_z^*$ is well-calibrated for benchmarks with $n \geq 10{,}000$ items; smaller benchmarks show increasing finite-sample deviations from normality.
7	
8	Two-sided testing eliminates the inverted-U artifact: MMLU achieves 97.8\% power at 15\% contamination and sustains ${>}$93\% at all levels.
9	Power scales with $\sqrt{n}$, as predicted by the noncentrality parameter $\delta \propto \sqrt{n}$.
10	The empirical power function, derived via Gauss--Hermite quadrature ($K=30$) over the ability distribution, achieves $R^2 = 0.957$ against simulated values, with approximate minimum benchmark size of $n \geq 7{,}958$ items for 80\% power at 15\% contamination under MMLU item parameters.
11	
12	\section{4PL vs.\ 3PL Ablation Details}
13	\label{app:4pl_ablation}
14	
15	Table~\ref{tab:4pl_3pl_power} reports detection power (proportion of 2{,}000 simulation replicates rejecting $H_0$ at $\alpha{=}0.05$, two-sided) for 4PL and 3PL parameterizations across five benchmarks and seven contamination levels.
16	The 4PL model yields higher power than 3PL at every non-trivial contamination level on every benchmark.
17	The advantage is largest on MMLU and HellaSwag, where upper-asymptote ($d < 1$) violations are most prevalent, and smallest on ARC-Challenge and HumanEval, where limited item counts constrain power under both parameterizations.
18	
19	Power is non-monotonic at 75\% contamination under 4PL on four of five benchmarks (e.g., MMLU: $.952 \to .938$; GSM8K: $.846 \to .802$).
20	This reflects the $\theta$-shift boundary condition described in \S\ref{sec:inverted_u}: at high contamination fractions, re-estimated $\hat{\theta}$ absorbs part of the aberrance signal, reducing $|\ell_z^*|$.
21	At 100\% contamination, all items are seen and power reaches 1.000 trivially.
22	The 4PL advantage over 3PL depends on accurate estimation of the upper asymptote $d$; with estimation error exceeding ${\sim}10\%$, the effective model behavior approaches 3PL ($d{=}1$) and the power gain diminishes.
23	PSN-IRT's large calibration sample ($12{+}$ models per item) typically yields $d$ standard errors well below this threshold.
24	
25	\begin{table*}[t]
26	\centering
27	\caption{Detection power (proportion rejecting $H_0$ at $\alpha{=}0.05$) under 4PL and 3PL parameterizations across benchmarks and contamination levels ($n{=}2{,}000$ replicates per cell). Bold indicates the 4PL advantage exceeds 5\,pp.}
28	\label{tab:4pl_3pl_power}
29	\small
30	\begin{tabular}{@{}llccccccc@{}}
31	\toprule
32	Benchmark & IRT & 5\% & 10\% & 15\% & 25\% & 50\% & 75\% & 100\% \\
33	\midrule
34	MMLU & 4PL & \textbf{.476} & \textbf{.848} & \textbf{.969} & \textbf{.983} & \textbf{.952} & \textbf{.938} & 1.00 \\
35	     & 3PL & .227 & .340 & .412 & .521 & .676 & .770 & 1.00 \\
36	\addlinespace
37	HellaSwag & 4PL & \textbf{.251} & \textbf{.454} & \textbf{.656} & \textbf{.915} & \textbf{.939} & \textbf{.919} & 1.00 \\
38	          & 3PL & .167 & .241 & .313 & .368 & .508 & .642 & 1.00 \\
39	\addlinespace
40	GSM8K & 4PL & \textbf{.156} & \textbf{.309} & \textbf{.492} & \textbf{.737} & \textbf{.846} & \textbf{.802} & 1.00 \\
41	      & 3PL & .102 & .172 & .285 & .396 & .567 & .577 & 1.00 \\
42	\addlinespace
43	ARC-C & 4PL & .057 & .075 & .087 & \textbf{.130} & \textbf{.285} & \textbf{.493} & 1.00 \\
44	      & 3PL & .054 & .062 & .071 & .076 & .110 & .102 & 1.00 \\
45	\addlinespace
46	HumanEval & 4PL & .076 & .121 & \textbf{.197} & \textbf{.302} & \textbf{.554} & \textbf{.521} & 1.00 \\
47	          & 3PL & .063 & .086 & .120 & .182 & .281 & .315 & 1.00 \\
48	\bottomrule
49	\end{tabular}
50	\end{table*}
51	
52	\section{Seed Sensitivity Analysis}
53	\label{app:seed_sensitivity}
54	
55	\paragraph{Clean-baseline variability.}
56	Table~\ref{tab:seed_sensitivity} reports $\ell_z^*$, accuracy, and $\hat{\theta}_{\text{MLE}}$ across three independent QLoRA runs (seeds 42, 123, 456).
57	For Qwen2.5-7B, $\ell_z^*$ ranges from $7.05$ (seed 123) to $9.53$ (seed 456); the lower value of seed 123 likely reflects seed-specific training dynamics (random initialization, data ordering), but all three seeds produce $\ell_z^* \gg 1.96$, confirming that the elevated baseline reflects systematic model--benchmark misfit rather than seed-specific artifacts.
58	Llama-3.1-8B shows $\ell_z^*$ near zero ($-0.14 \pm 0.97$), consistent with lower baseline misfit.
59	Accuracy variability is negligible for both families (CV $< 0.004$).
60	
61	\begin{table}[t]
62	\centering
63	\caption{Seed sensitivity analysis for clean baseline across three independent runs (seeds 42, 123, 456). CV = coefficient of variation ($\mathrm{std}/|\mathrm{mean}|$). These $n{=}3$ pilot results are superseded by the $n{=}10$ analysis in \S\ref{sec:detection}; retained for methodological transparency.}
64	\label{tab:seed_sensitivity}
65	\footnotesize
66	\resizebox{\columnwidth}{!}{%
67	\begin{tabular}{@{}llcccc@{}}
68	\toprule
69	Model & Metric & Mean & Std & Range & CV \\
70	\midrule
71	Qwen2.5-7B & $\ell_z^*$ & 8.684 & 1.412 & 2.475 & 0.163 \\
72	 & Accuracy & 0.679 & 0.000 & 0.001 & 0.001 \\
73	 & $\hat{\theta}_{\mathrm{MLE}}$ & $-$0.097 & 0.012 & 0.023 & 0.119 \\
74	\midrule
75	Llama-3.1-8B & $\ell_z^*$ & $-$0.141 & 0.965 & 1.929 & 6.860 \\
76	 & Accuracy & 0.594 & 0.002 & 0.004 & 0.004 \\
77	 & $\hat{\theta}_{\mathrm{MLE}}$ & $-$0.645 & 0.019 & 0.036 & 0.029 \\
78	\bottomrule
79	\end{tabular}}
80	\end{table}
81	
82	\paragraph{Cohen's $d$ confidence intervals.}
83	Table~\ref{tab:cohens_d_ci} reports Cohen's $d$ effect sizes with both analytic and bootstrap 95\% confidence intervals.
84	Analytic CIs use $d \pm t_{0.025,\,\text{df}=2} \cdot \text{SE}_d$; with only $n{=}3$ clean seeds (df${=}2$), the critical value $t_{0.025,2} = 4.303$ produces intervals wide enough to cross zero in all four conditions.
85	This is a known limitation of small-sample $t$-based intervals rather than evidence of null effects.
86	Bootstrap CIs (10{,}000 resamples with replacement from the three clean seeds) provide a nonparametric alternative: all four bootstrap intervals exclude zero, supporting the conclusion that contamination produces a reliably detectable signal despite the small reference sample.
87	
88	\begin{table}[t]
89	\centering
90	\caption{Cohen's $d$ with 95\% confidence intervals for contaminated conditions relative to clean baselines ($n{=}3$ seeds). Analytic CIs use $t_{0.025, \text{df}=2}$; bootstrap CIs use 10{,}000 resamples. These $n{=}3$ pilot results are superseded by the $n{=}10$ analysis in \S\ref{sec:detection}; retained for methodological transparency.}
91	\label{tab:cohens_d_ci}
92	\footnotesize
93	\resizebox{\columnwidth}{!}{%
94	\begin{tabular}{@{}llccc@{}}
95	\toprule
96	Model & Cond. & $d$ & Analytic CI & Bootstrap CI \\
97	\midrule
98	Qwen & 15\% & $-$3.42 & [$-$9.92, 3.08] & [$-$3.45, $-$2.82] \\
99	 & 50\% & $-$0.99 & [$-$4.02, 2.04] & [$-$0.99, $-$0.41] \\
100	\midrule
101	Llama & 15\% & $-$2.95 & [$-$8.70, 2.80] & [$-$5.89, $-$2.29] \\
102	 & 50\% & $-$3.31 & [$-$9.63, 3.01] & [$-$6.47, $-$2.59] \\
103	\bottomrule
104	\end{tabular}}
105	\end{table}
106	
107	\paragraph{Cross-family consistency.}
108	Table~\ref{tab:cross_family} confirms that both model families produce large negative Cohen's $d$ under contamination.
109	The $|\Delta d| = 2.32$ gap at 50\% contamination reflects Qwen's non-monotonic dose-response (the $\theta$-shift boundary condition; \S\ref{sec:inverted_u}), not a failure of detection robustness---both families remain well above conventional large-effect thresholds ($|d| > 0.8$) at both contamination levels.
110	
111	\begin{table}[t]
112	\centering
113	\caption{Cross-family consistency of contamination detection ($n{=}3$ pilot). Both families show large negative $d$ under contamination. Superseded by $n{=}10$ results in \S\ref{sec:detection}; retained for methodological transparency.}
114	\label{tab:cross_family}
115	\small
116	\begin{tabular}{@{}lcccl@{}}
117	\toprule
118	Condition & Qwen $d$ & Llama $d$ & $|\Delta d|$ & Consistent? \\
119	\midrule
120	15\% contam. & $-$3.42 & $-$2.95 & 0.47 & Yes \\
121	50\% contam. & $-$0.99 & $-$3.31 & 2.32 & Yes \\
122	\bottomrule
123	\end{tabular}
124	\end{table}
125	
126	\section{Baseline $\ell_z^*$ Interpretation}
127	\label{app:baseline_meaning}
128	
129	The baseline $\ell_z^*$ value reflects a model's difficulty-ordering consistency under the 4PL model, not its accuracy alone.
130	In the empirical data, Mistral ($\text{acc}{=}0.514$, lowest among the 12 models) exhibits $\ell_z^*{=}{+}5.42$ (second highest), because its response pattern follows the IRT-predicted difficulty ordering more closely than higher-accuracy models whose responses violate the assumed item structure.
131	This dissociation explains why Mistral produces the strongest contamination signal despite the lowest accuracy: its lower baseline ability ($\hat{\theta}{=}{-}1.16$) provides greater $\theta$-shift headroom.
132	
133	\section{Item-Level Detection Results}
134	\label{app:item_auroc}
135	
136	Table~\ref{tab:item_auroc} reports item-level contamination detection performance at 15\% contamination on MMLU.
137	All methods perform near random (AUROC $\leq 0.63$), confirming that contamination is diffuse across the response pattern and that model-level aggregation via $\ell_z^*$ is essential.
138	
139	An accuracy $z$-score baseline yields $z{=}160$ at 15\% contamination, but this reflects near-zero cross-seed accuracy variance ($\text{std}{=}0.0003$), not genuine discriminability.
140	In deployment, accuracy variability from prompt format, evaluation harness, and hardware differences inflates the denominator, collapsing the $z$-score.
141	
142	\begin{table}[t]
143	\centering
144	\caption{Item-level contamination detection (AUROC) at 15\% contamination on MMLU.}
145	\label{tab:item_auroc}
146	\footnotesize
147	\begin{tabular}{@{}lc@{}}
148	\toprule
149	Method & AUROC \\
150	\midrule
151	Random baseline & 0.50 \\
152	$\ell_z^*$ itemwise & 0.53 \\
153	LR cross-model & 0.59 \\
154	RF cross-model & 0.63 \\
155	\bottomrule
156	\end{tabular}
157	\end{table}
158	
159	\section{Robustness Analysis}
160	\label{app:robustness}
161	
162	\subsection{$\Delta\ell_z^*$ Under Local Dependence}
163	\label{app:local_dep}
164	
165	IRT person-fit statistics assume local independence---conditional on $\theta$, item responses are independent.
166	LLM benchmarks violate this assumption through topical clustering (e.g., MMLU subjects); resampling-based approaches can provide valid person-fit assessment even under such violations \citep{sinharay2016}.
167	We evaluate whether the $\Delta\ell_z^*$ matched-difference design is robust to local dependence (LD) via two simulation scenarios on 14,042 MMLU items with 1,000 replications each.
168	
169	\paragraph{Shared LD.}
170	Clean and contaminated conditions share identical testlet structure (${\sim}200$ testlets of ${\sim}70$ items, random effect $\gamma_t \sim \mathcal{N}(0, \sigma_\tau)$).
171	Table~\ref{tab:ld_shared} reports absolute $\ell_z^*$ Type~I error and the ratio of $\Delta\ell_z^*$ effect size ($d$) to the no-LD baseline.
172	While absolute $\ell_z^*$ Type~I error inflates severely under LD (0.043$\to$0.939 at $\sigma{=}1.0$), the $\Delta\ell_z^*$ design maintains detection power: $d_{\text{ratio}} \geq 0.93$ for $\sigma_\tau \leq 0.5$ (realistic range), confirming that shared misfit is cancelled by the matched-difference design.
173	
174	\begin{table}[t]
175	\centering
176	\caption{Robustness of $\Delta\ell_z^*$ to shared local dependence (1,000 replications, MMLU). $d_{\text{ratio}}$: effect size relative to the $\sigma_\tau{=}0$ baseline.}
177	\label{tab:ld_shared}
178	\footnotesize
179	\begin{tabular}{@{}lccc@{}}
180	\toprule
181	$\sigma_\tau$ & Abs.\ $\ell_z^*$ Type~I & $d_{\text{ratio}}$ (15\%) & $d_{\text{ratio}}$ (50\%) \\
182	\midrule
183	0.0 & 0.043 & 1.000 & 1.000 \\
184	0.3 & 0.110 & 1.002 & 1.038 \\
185	0.5 & 0.454 & 0.934 & 1.028 \\
186	1.0 & 0.939 & 0.705 & 1.061 \\
187	\bottomrule
188	\end{tabular}
189	\end{table}
190	
191	\paragraph{Asymmetric LD.}
192	In the second scenario, contaminated models' seen items share an additional memory factor ($\gamma_{\text{mem}} \sim \mathcal{N}(0, \sigma_{\text{mem}})$), simulating contamination-specific LD not present in clean conditions ($\sigma_\tau{=}0.5$ fixed).
193	Table~\ref{tab:ld_asym} shows that $\Delta\ell_z^*$ maintains ${\geq}98.5\%$ power across all conditions, even when contamination introduces asymmetric dependence among seen items.
194	
195	\begin{table}[t]
196	\centering
197	\caption{$\Delta\ell_z^*$ detection under asymmetric local dependence ($\sigma_\tau{=}0.5$, contamination-specific memory factor $\sigma_{\text{mem}}$; 1,000 replications, MMLU).}
198	\label{tab:ld_asym}
199	\footnotesize
200	\begin{tabular}{@{}lcccc@{}}
201	\toprule
202	$\sigma_{\text{mem}}$ & Power (15\%) & $d$ (15\%) & Power (50\%) & $d$ (50\%) \\
203	\midrule
204	0.5 & 0.987 & $-$2.107 & 0.991 & $-$2.337 \\
205	1.0 & 0.993 & $-$2.104 & 0.985 & $-$1.587 \\
206	\bottomrule
207	\end{tabular}
208	\end{table}
209	
210	\subsection{Sensitivity to Item Parameter Estimation Error}
211	\label{app:param_perturb}
212	
213	PSN-IRT item parameters carry estimation error from the calibration sample.
214	We evaluate detection sensitivity by adding joint noise to all four parameters: multiplicative perturbation $p' = p \cdot (1 + \mathcal{N}(0, \sigma))$ for $a$, $c$, and $d$; additive perturbation $b' = b + \sigma \cdot \mathcal{N}(0, 1)$ for difficulty.
215	Tables~\ref{tab:param_noise_free} and \ref{tab:param_noise_fixed} report results over 100 trials using Qwen MMLU response vectors.
216	
217	Detection of 15\% contamination is robust to parameter noise under free-$\theta$ (17.4\% bias at $\sigma{=}10\%$, $|d|$ still ${>}5$; Table~\ref{tab:param_noise_free}).
218	The 50\% contamination condition under free-$\theta$ is fragile---consistent with its already-weak signal due to $\theta$-shift absorption (\S\ref{sec:inverted_u}).
219	
220	Under $\theta$-fixed estimation (Table~\ref{tab:param_noise_fixed}), detection is highly robust: 10\% perturbation produces ${<}4\%$ bias in Cohen's $d$, with worst-case $|d| = 3.73$ (15\% contamination) and $12.20$ (50\%)---both far exceeding conventional thresholds.
221	This contrasts sharply with free-$\theta$ estimation, where 50\% contamination Cohen's $d$ collapses to near zero under 10\% noise.
222	The complementarity is clear: conditions where free-$\theta$ detection is fragile (high-baseline-accuracy models with $\theta$-shift absorption) are precisely where $\theta$-fixed anchoring provides the strongest and most noise-robust signal.
223	
224	\begin{table}[t]
225	\centering
226	\caption{Sensitivity of detection to item parameter noise (100 trials, Qwen MMLU, free-$\theta$). \% bias relative to noise-free $d$.}
227	\label{tab:param_noise_free}
228	\footnotesize
229	\begin{tabular}{@{}lcccc@{}}
230	\toprule
231	Noise $\sigma$ & $d$ (15\%) & \% bias & $d$ (50\%) & \% bias \\
232	\midrule
233	0\% & $-$6.575 & --- & $-$1.897 & --- \\
234	5\% & $-$6.010 & 8.6 & $-$0.925 & 51.2 \\
235	10\% & $-$5.433 & 17.4 & $-$0.014 & 99.3 \\
236	\bottomrule
237	\end{tabular}
238	\end{table}
239	
240	\begin{table}[t]
241	\centering
242	\caption{Sensitivity of detection to item parameter noise (100 trials, Qwen MMLU, $\theta$-fixed). Worst-case $|d|$ over 100 trials in parentheses.}
243	\label{tab:param_noise_fixed}
244	\footnotesize
245	\resizebox{\columnwidth}{!}{%
246	\begin{tabular}{@{}lcccc@{}}
247	\toprule
248	Noise $\sigma$ & $d_{\text{fixed}}$ (15\%) & \% bias & $d_{\text{fixed}}$ (50\%) & \% bias \\
249	\midrule
250	0\% & 4.77 & --- & 14.52 & --- \\
251	5\% & 5.07 $\pm$ 0.24 & 6.3 & 14.76 $\pm$ 0.44 & 1.6 \\
252	10\% & 4.95 $\pm$ 0.43 (3.73) & 3.7 & 14.45 $\pm$ 0.85 (12.20) & 0.5 \\
253	\bottomrule
254	\end{tabular}}
255	\end{table}
256	
257	\section{BCa Bootstrap Sensitivity Check}
258	\label{app:bca}
259	
260	As a sensitivity check, we computed bias-corrected and accelerated (BCa) bootstrap confidence intervals for all Cohen's $d$ estimates.
261	BCa CIs were uniformly narrower than the percentile CIs reported in the main text (mean reduction 22\%), confirming that our reported intervals are conservative.
262	The single condition where BCa widens the zero-crossing set---Llama fixed-$\theta$ at 50\% contamination, BCa CI [$-$0.13, 2.21] vs.\ percentile CI [0.17, 2.97]---is already characterized as ineffective in \S\ref{sec:theta_dynamics}.
263	
264	\section{Classical IRT Refit from Leaderboard Data}
265	\label{app:mml_em}
266	
267	To assess whether item parameters can be recovered without PSN-IRT's neural calibration, we applied classical MML-EM estimation (Gauss--Hermite quadrature, $Q{=}31$ nodes) to binary response data from $N{=}178$ models on the Open LLM Leaderboard v1.
268	With 14,042 MMLU items and an examinee-to-item ratio of $N{:}J = 0.013$---far below the $N{>}500$ typically required for stable 3PL estimation---discrimination parameters are severely under-determined.
269	
270	Table~\ref{tab:mml_em} reports parameter correlations between MML-EM-fitted and PSN-IRT parameters.
271	Difficulty shows moderate agreement ($r_b{=}0.663$), but discrimination is essentially unrecovered ($r_a{=}0.127$).
272	Using these MML-EM parameters produces miscalibrated $\ell_z^*$ statistics (mean$\,{=}\,$11.2, expected ${\approx}\,$0), confirming that the refitted model does not capture the data-generating process.
273	This motivates the dependence on PSN-IRT's externally calibrated item bank (\S\ref{sec:framework}).
274	
275	\begin{table}[t]
276	\centering
277	\caption{Parameter correlation between classical MML-EM refit ($N{=}178$ models) and PSN-IRT on MMLU ($n{=}10{,}558$ matched items).}
278	\label{tab:mml_em}
279	\footnotesize
280	\begin{tabular}{@{}llcc@{}}
281	\toprule
282	Model & Parameter & Pearson $r$ & Spearman $\rho$ \\
283	\midrule
284	3PL & $a$ (discrim.) & 0.127 & 0.135 \\
285	3PL & $b$ (difficulty) & 0.663 & 0.684 \\
286	2PL & $a$ (discrim.) & $-$0.029 & 0.050 \\
287	2PL & $b$ (difficulty) & 0.608 & 0.656 \\
288	\bottomrule
289	\end{tabular}
290	\end{table}
291	
292	\section{Post-RL Preliminary Observation}
293	\label{app:post_rl}
294	
295	\citet{wang2025fragility} show that all MIA-based detectors fail after RL post-training.
296	In a single-model pilot ($N{=}1$, Qwen, GRPO), we applied GRPO \citep{shao2024} for 1,500 steps to a contaminated model (15\% MMLU) and evaluated at three checkpoints.
297	GRPO erases the accuracy gap between seen and unseen items ($11.4\text{pp} \to 2.1\text{pp}$), but the $\ell_z^*$ response-pattern gap persists (${\sim}3.3$; Figure~\ref{fig:grpo}), suggesting structural traces of contamination may survive RL alignment.
298	Min-K\% membership inference confirms this dissociation: while SFT yields a weak MIA signal (AUC-ROC${=}0.611$), GRPO training drives AUC to $0.493$ (step~500), $0.493$ (step~1000), and $0.493$ (step~1500)---indistinguishable from random chance ($0.50$) as RL erases memorization-based features while the response-pattern anomaly that $\ell_z^*$ detects persists.
299	This $N{=}1$ observation requires validation across model families, RL methods, and contamination levels before any conclusions can be drawn.
300	
301	\begin{figure}[t]
302	  \centering
303	  \includegraphics[width=\columnwidth]{fig_grpo.pdf}
304	  \caption{Post-RL trajectory for Qwen contaminated at 15\% on MMLU. Left axis: accuracy on seen (solid) and unseen (dashed) items. Right axis: $\ell_z^*$ seen-unseen gap (green diamonds). GRPO erases the accuracy gap ($11.4\text{pp} \to 2.1\text{pp}$) while the response-pattern gap persists (${\sim}3.3$). $N{=}1$, single model and RL method; no statistical inference is drawn.}
305	  \label{fig:grpo}
306	\end{figure}
307	
308	\section{QLoRA Training Hyperparameters}
309	\label{app:hyperparams}
310	
311	Table~\ref{tab:hyperparams} reports the QLoRA fine-tuning hyperparameters used across all experiments.
312	
313	\begin{table}[t]
314	\centering
315	\caption{QLoRA fine-tuning hyperparameters (shared across all model families and contamination conditions).}
316	\label{tab:hyperparams}
317	\footnotesize
318	\resizebox{\columnwidth}{!}{%
319	\begin{tabular}{@{}ll@{}}
320	\toprule
321	Hyperparameter & Value \\
322	\midrule
323	Quantization & 4-bit NF4 \\
324	LoRA rank & 16 \\
325	LoRA $\alpha$ & 32 \\
326	LoRA dropout & 0.05 \\
327	Target modules & \texttt{q\_proj}, \texttt{k\_proj}, \texttt{v\_proj}, \texttt{o\_proj} \\
328	Learning rate & $2 \times 10^{-4}$ \\
329	Optimizer & AdamW \\
330	Warmup ratio & 0.1 \\
331	Epochs & 3 \\
332	Per-device batch size & 4 \\
333	Gradient accumulation steps & 4 \\
334	Effective batch size & 16 \\
335	Max sequence length & 512 \\
336	Data mixing & Contaminated items shuffled into training set \\
337	\bottomrule
338	\end{tabular}}
339	\end{table}
340	
341	\section{Contamination Run Reproducibility}\label{app:reproducibility}
342	
343	\begin{table}[h]
344	\centering
345	\caption{Reproducibility of contamination effect sizes across independent QLoRA runs (Qwen2.5-7B-Instruct, MMLU). Each row shows Cohen's $|d|$ from an independent training seed against the shared $n{=}10$ clean baseline ($\bar{\ell}_z^* = 8.68$, $s = 0.74$). All runs use identical hyperparameters; only the random seed differs.}
346	\footnotesize
347	\begin{tabular}{@{}lcccccc@{}}
348	\toprule
349	& \multicolumn{3}{c}{Free-$\theta$ $|d|$} & \multicolumn{3}{c}{Fixed-$\theta$ $|d|$} \\
350	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
351	Seed & 15\% & 25\% & 50\% & 15\% & 25\% & 50\% \\
352	\midrule
353	42 (original) & 6.57 & 8.22 & 1.90 & 4.77 & 4.96 & 14.52 \\
354	123 & 5.09 & 8.78 & 5.42 & 7.79 & 5.37 & 12.64 \\
355	456 & 4.41 & 5.31 & 7.91 & 7.99 & 7.34 & 9.80 \\
356	\addlinespace
357	Mean & 5.36 & 7.44 & 5.08 & 6.85 & 5.89 & 12.32 \\
358	SD & 1.10 & 1.86 & 3.02 & 1.80 & 1.27 & 2.38 \\
359	CV (\%) & 20.3 & 25.2 & 59.6 & 26.3 & 21.7 & 19.3 \\
360	\bottomrule
361	\end{tabular}
362	\vspace{0.5em}
363	
364	\noindent\textit{Note.} Fixed-$\theta$ estimation anchors $\hat{\theta}$ at the clean-baseline mean ($\theta{=}{-}0.102$), removing $\theta$-shift absorption. The 50\% free-$\theta$ column exhibits high CV (59.6\%), reflecting seed-dependent $\theta$-shift magnitude; fixed-$\theta$ reduces this to 19.3\%, confirming that cross-seed variability at high contamination is driven by ability-estimate instability rather than true signal variance.
365	\end{table}
366	
367	\begin{table}[h]
368	\centering
369	\caption{Multi-seed Cohen's $|d|$ for HT and accuracy $z$-score statistics (Qwen2.5-7B-Instruct, MMLU), computed using the chi-squared ratio HT statistic and bootstrap Cohen's $d$ (10{,}000 resamples). These supplement the $\ell_z^*$ values in Table~\ref{tab:degradation}.}
370	\label{tab:ht_acc_multiseed}
371	\footnotesize
372	\begin{tabular}{@{}lcccccc@{}}
373	\toprule
374	& \multicolumn{3}{c}{HT $|d|$} & \multicolumn{3}{c}{Acc.\ $z$ $|d|$} \\
375	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
376	Seed & 15\% & 25\% & 50\% & 15\% & 25\% & 50\% \\
377	\midrule
378	42 (original) & 7.26 & 8.90 & 1.66 & 42.3 & 49.8 & 68.7 \\
379	123 & 5.52 & 9.51 & 5.80 & 47.3 & 53.4 & 70.8 \\
380	456 & 4.72 & 5.10 & 8.41 & 45.4 & 51.3 & 70.4 \\
381	\addlinespace
382	Mean & 5.83 & 7.84 & 5.29 & 45.0 & 51.5 & 70.0 \\
383	SD & 1.30 & 2.39 & 3.41 & 2.5 & 1.8 & 1.1 \\
384	\bottomrule
385	\end{tabular}
386	\vspace{0.5em}
387	
388	\noindent\textit{Note.} HT exhibits high cross-seed variance at 50\% (SD${=}3.41$), mirroring the $\ell_z^*$ pattern: the non-monotonicity observed in seed 42 ($|d|{=}1.66$) does not generalize across seeds. Accuracy $z$-scores are highly stable (CV $< 6\%$) and monotonically increasing with contamination level.
389	\end{table}
390	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dec0c98c-6e64-472f-a18b-136eb65c838f",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "dcb3ae36-cf0d-4c67-98f5-15beba114840",
  "sourceToolAssistantUUID": "dec0c98c-6e64-472f-a18b-136eb65c838f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 19 · 2026-05-23T11:16:01.188Z_

Now let me read the other section files to ensure I capture all numerical values:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dcb3ae36-cf0d-4c67-98f5-15beba114840",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQU2NayhLRLSnStpPq7",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "8cda8927-5f5d-4c2f-9c56-3448cecf634d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Qwe1ZQfuE5JrrmCUsBWEn9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 10922,
      "cache_read_input_tokens": 26641,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 10922,
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

_source line 20 · 2026-05-23T11:16:02.253Z_

<details open><summary>🔧 Tool call — Read · `toolu_015frFDqhY5TWnSqcYGpQi5q`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8cda8927-5f5d-4c2f-9c56-3448cecf634d",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQU2NayhLRLSnStpPq7",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "24257546-8931-4438-ab17-63fd319bf2fe",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Qwe1ZQfuE5JrrmCUsBWEn9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 10922,
      "cache_read_input_tokens": 26641,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 10922,
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

### Tool result

_source line 21 · 2026-05-23T11:16:02.260Z_

<details><summary>↩ Tool result · `toolu_015frFDqhY5TWnSqcYGpQi5q`</summary>

```text
1	Benchmark contamination in Large Language Models (LLMs) undermines evaluation validity, yet most detection methods require privileged access to training data, model internals, or output probabilities.
2	We present the first controlled characterization of IRT person-fit statistics for detecting SFT-stage contamination: the framework requires only binary response patterns from the target model---no access to weights, gradients, logits, or training data---combined with externally calibrated 4PL item parameters from a large-scale item bank; diagnostic $\theta$-anchoring additionally requires a clean baseline.
3	A contaminated LLM produces aberrant response patterns analogous to a test-taker with item preknowledge.
4	Using $\ell_z^*$ in a matched-difference design ($\Delta\ell_z^*$) across three 7--8B model families ($n{=}10$ clean baseline seeds per model family) on MMLU (14,042 items) and ARC-Challenge (295 items), we identify three behavior boundaries:
5	(1) model-specific $\theta$-shift dynamics, where contamination-induced ability inflation absorbs the person-fit signal; $\theta$-anchoring is necessary for reliable detection of high-ability models at high contamination (2.4$\times$ amplification, inter-seed CV reduced from 60\% to 19\%);
6	(2) a detection-diagnosis tradeoff where simpler statistics yield stronger detection but lack $\ell_z^*$'s diagnostic capabilities (seen/unseen decomposition, mechanistic $\theta$-shift analysis);
7	and (3, exploratory) ability-dependent non-monotonic dose-response under free-$\theta$ estimation, driven by $\theta$-shift absorption; $\theta$-anchored analysis reveals stable detection with a strong positive dose-response at higher contamination levels.
8	These findings establish when and why binary response patterns carry contamination information beyond aggregate accuracy.
9	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "24257546-8931-4438-ab17-63fd319bf2fe",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "ee1e230d-faee-457c-8f52-801466bb65c6",
  "sourceToolAssistantUUID": "24257546-8931-4438-ab17-63fd319bf2fe",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 22 · 2026-05-23T11:16:02.585Z_

<details open><summary>🔧 Tool call — Read · `toolu_01NSTX255z4677EEKPdqZNQn`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ee1e230d-faee-457c-8f52-801466bb65c6",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQU2NayhLRLSnStpPq7",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "9bc90be9-ff8d-4a7d-b05f-5059196f92f3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Qwe1ZQfuE5JrrmCUsBWEn9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 10922,
      "cache_read_input_tokens": 26641,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 10922,
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

### Tool result

_source line 23 · 2026-05-23T11:16:02.597Z_

<details><summary>↩ Tool result · `toolu_01NSTX255z4677EEKPdqZNQn`</summary>

```text
1	\section{Introduction}\label{sec:introduction}
2	
3	Benchmark contamination, the unintended inclusion of evaluation data in training corpora, poses a growing threat to the integrity of large language model (LLM) evaluation \citep{dodge2021, magar2022, sainz2023}.
4	As training corpora and public benchmarks both expand, the probability of overlap increases structurally \citep{jacovi2023, chang2024survey}.
5	When contamination occurs, benchmark scores no longer reflect genuine capability, undermining the primary mechanism by which the community compares and selects models.
6	
7	A range of detection methods have been proposed, but all require some form of privileged access beyond the binary response record.
8	N-gram overlap methods need the training corpus \citep{dodge2021, magar2022}.
9	Membership inference approaches require token-level probabilities \citep{minkprob2024, deng2024}.
10	Probing methods rely on crafted prompts \citep{golchin2024, oren2024}.
11	Performance-based methods require multiple test variants or output logits \citep{constat2024, codec2026}.
12	These methods form a detection frontier ordered by information access.
13	No existing method operates using only binary response patterns, without model weights, gradients, logits, or training data---though, as we show, effective detection additionally requires externally calibrated item parameters.
14	
15	In this work, we focus on SFT-stage contamination---where benchmark answers are explicitly included in fine-tuning data---for three reasons.
16	First, controlled experiments require known ground-truth contamination sets, achievable through fine-tuning with specific benchmark items.
17	Second, SFT-stage contamination is increasingly relevant as fine-tuning-as-a-service platforms proliferate, creating new pathways for benchmark data to enter training mixtures.
18	Third, SFT provides a methodologically clean setting to characterize detection boundaries before extending to noisier pretraining scenarios.
19	
20	The need for detection from binary response patterns grows more pressing as models evolve.
21	\citet{wang2025fragility} show that all ten log-probability-based methods they evaluate perform at chance level on models trained with reinforcement learning (RL), because RL reshapes internal token distributions while preserving binary correctness patterns.
22	This motivates a fundamental question: \emph{what can binary response patterns reveal about contamination, and under what conditions?}
23	
24	We observe that a contaminated LLM is functionally analogous to a test-taker with item preknowledge: both produce response patterns in which difficult items are answered correctly through memorization rather than genuine ability.
25	This connection points to person-fit statistics, developed over four decades for cheating detection in educational testing \citep{drasgow1985, meijer2001, karabatsos2003, sinharay2017}.
26	The standardized statistic $\ell_z^*$ \citep{snijders2001} measures how well a response pattern conforms to Item Response Theory (IRT) model predictions.
27	Figure~\ref{fig:motivation} illustrates this analogy.
28	Despite the natural correspondence, no prior work has applied person-fit statistics to LLM benchmark contamination.
29	
30	\begin{figure}[t]
31	  \centering
32	  \includegraphics[width=\columnwidth]{fig_1_response_pattern.pdf}
33	  \caption{A clean model's responses track the IRT-predicted probability curve (left); a contaminated model shows anomalous successes on hard items (right, red diamonds), producing a large $|\Delta\ell_z^*|$ signal.}
34	  \label{fig:motivation}
35	\end{figure}
36	
37	Rather than proposing $\ell_z^*$ as a ready-to-deploy detection tool, we characterize the behavior boundaries of IRT person-fit statistics for LLM contamination detection.
38	Our framework operates at three layers: (i) pre-calibrated 4PL item parameters from the PSN-IRT item bank \citep{psnirt2026}, an external resource derived from 13,000+ models; (ii) binary response patterns obtained from the target model without access to weights or logits; and (iii) retrospective statistical inference requiring no model modification.
39	Using controlled contamination experiments across three 7--8B model families (Qwen2.5-7B, Llama-3.1-8B, Mistral-7B; $n{=}10$ clean seeds each) with pre-calibrated 4PL item parameters from PSN-IRT \citep{psnirt2026}, we identify three IRT-specific findings on MMLU \citep{hendrycks2021mmlu} and ARC-Challenge:
40	
41	\begin{enumerate}[leftmargin=*,nosep]
42	\item \textbf{Model-specific $\theta$-shift dynamics.} Contamination inflates ability estimates ($\hat{\theta}$), absorbing the person-fit signal; $\theta$-anchoring amplifies Qwen's multi-seed $|d|$ by 2.4$\times$ at 50\% contamination while reducing inter-seed CV from 60\% to 19\%, establishing $\theta$-anchoring as a necessary condition for reliable detection of high-ability models at high contamination. ARC-C reverses through a ceiling effect.
43	
44	\item \textbf{Detection-diagnosis tradeoff.} Simpler statistics yield stronger detection: accuracy $z$-scores produce $|d|$ values several-fold to over an order of magnitude larger than person-fit statistics, and HT generally exceeds $\ell_z^*$. Yet the diagnostic power reverses: only $\ell_z^*$ supports seen/unseen decomposition, mechanistic $\theta$-shift analysis, and sensitivity to response-pattern structure (57/60 vs.\ 4/60 flagged cells on real-world data).
45	
46	\item \textbf{Non-monotonic dose-response under free-$\theta$ (exploratory).} Multi-seed Qwen trajectory ($|d|$: $4.15 \to 5.36 \to 7.44 \to 5.08$ at 5\%/15\%/25\%/50\%) shows attenuated non-monotonicity; $\theta$-anchoring eliminates the pattern and reveals strong positive dose-response ($|d|{=}12.32$ at 50\%). The non-monotonicity is a $\theta$-estimation artifact, not a detection boundary.
47	\end{enumerate}
48	
49	Our contributions are threefold:
50	(1) We provide the first empirical characterization of IRT person-fit behavior for LLM contamination, quantifying theoretically predicted phenomena ($\theta$-shift absorption, detection-diagnosis tradeoff) whose magnitudes and boundary conditions are not derivable from IRT theory alone.
51	(2) We establish that $\Delta\ell_z^*$ reliably detects SFT-stage contamination across three model families (all bootstrap 95\% CIs exclude zero, $n{=}10$).
52	(3) We document the detection-diagnosis tradeoff, clarifying what binary response patterns can and cannot reveal.
53	Findings~1--2 are confirmatory (pre-planned 15\%/50\% $\times$ 3 families); Finding~3 is exploratory (5\%/25\% added post-hoc).
54	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9bc90be9-ff8d-4a7d-b05f-5059196f92f3",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "02e9ce31-9acf-4452-a81c-5dfef972f0b9",
  "sourceToolAssistantUUID": "9bc90be9-ff8d-4a7d-b05f-5059196f92f3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-23T11:16:02.654Z_

<details open><summary>🔧 Tool call — Read · `toolu_01BoxxuMbjt4gPr5S2awesx3`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "02e9ce31-9acf-4452-a81c-5dfef972f0b9",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQU2NayhLRLSnStpPq7",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "560d7254-f0e9-4276-9d5b-bf07f45a2270",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Qwe1ZQfuE5JrrmCUsBWEn9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 10922,
      "cache_read_input_tokens": 26641,
      "output_tokens": 259,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 10922
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 6,
          "output_tokens": 259,
          "cache_read_input_tokens": 26641,
          "cache_creation_input_tokens": 10922,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 10922,
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

_source line 25 · 2026-05-23T11:16:02.673Z_

<details><summary>↩ Tool result · `toolu_01BoxxuMbjt4gPr5S2awesx3`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{IRT Person-Fit Framework}
5	\label{sec:framework}
6	
7	We adopt the four-parameter logistic (4PL) IRT model to characterize contamination-induced aberrance in LLM response patterns.
8	The 4PL model defines the probability that a model with ability $\theta$ answers item $i$ correctly:
9	\begin{equation}
10	  P_i(\theta) = c_i + (d_i - c_i)\,\frac{1}{1 + e^{-a_i(\theta - b_i)}}
11	  \label{eq:4pl}
12	\end{equation}
13	where $a_i$ is discrimination, $b_i$ difficulty, $c_i$ the lower asymptote (guessing), and $d_i$ the upper asymptote (slip).
14	Item parameters are pre-calibrated by PSN-IRT \citep{psnirt2026} from a large-scale leaderboard dataset; we use these external parameters rather than re-estimating from potentially contaminated data, since our MML-EM refit shows discrimination recovery degrades to $r_a{=}0.127$ on contaminated leaderboard data.
15	
16	Given item parameters and a binary response vector $\mathbf{x} = (x_1, \ldots, x_n)$, we compute the person-fit statistic $\ell_z^*$ \citep{snijders2001}, a standardized log-likelihood residual quantifying deviation between observed and expected response patterns.
17	The Snijders correction accounts for estimation uncertainty in $\hat{\theta}_{\text{MLE}}$, so that $\ell_z^* \sim \mathcal{N}(0,1)$ under the null \citep{drasgow1985, snijders2001}; \citet{magis2012} provide a detailed treatment of how response model selection and ability estimation affect $\ell_z^*$.
18	Large negative $\ell_z^*$ indicates aberrant responding (unexpected failures on easy items or unexpected successes on hard items); large positive values indicate over-consistent patterns.
19	
20	\subsection{$\Delta\ell_z^*$ Matched-Difference Design}
21	\label{sec:did}
22	
23	LLM response patterns systematically violate IRT assumptions of local independence and unidimensionality.
24	In our empirical data, 57 of 60 model-benchmark cells yield $|\ell_z^*| > 1.96$ even absent contamination, rendering absolute thresholds uninformative.
25	We address this through a matched-difference design.
26	
27	For controlled experiments with clean baselines, we compute:
28	\begin{equation}
29	  \Delta\ell_z^* = \ell_{z,\text{contam}}^{*} - \bar{\ell}_{z,\text{clean}}^{*}
30	  \label{eq:delta_lz}
31	\end{equation}
32	where $\bar{\ell}_{z,\text{clean}}^{*}$ averages over $n{=}10$ clean seeds.
33	The shared model misfit cancels, isolating contamination-specific aberrance.
34	We quantify effect sizes as $d = (\ell_{z,\text{contam}}^{*} - \bar{\ell}_{z,\text{clean}}^{*})\,/\,s_{\text{clean}}$, where $s_{\text{clean}}$ is the SD of the $n{=}10$ clean-seed $\ell_z^*$ values; with a single contaminated observation per condition, $d$ is a standardized departure rather than a two-sample effect size (Hedges' $g = J \cdot d$, $J \approx 0.914$ for $n{=}10$; \citealp{hedges1981}).
35	We report percentile bootstrap 95\% CIs (10,000 resamples) reflecting clean-seed variability only; BCa correction (Appendix~\ref{app:bca}) generally confirms conservative coverage; multi-seed contamination-run variance appears in Appendix~\ref{app:reproducibility}.
36	
37	For deployment without clean baselines, cross-benchmark comparison provides the reference: the target benchmark's $\ell_z^*$ is compared against benchmarks presumed clean from the same model.
38	Significance thresholds derive from a nonparametric bootstrap null rather than the asymptotic $\mathcal{N}(0,1)$ reference, accommodating residual model misspecification.
39	Simulation analysis (Appendix~\ref{app:local_dep}) confirms that the matched-difference design is robust to local dependence at realistic levels ($d_{\text{ratio}} \geq 0.93$ for $\sigma_\tau \leq 0.5$) and maintains ${\geq}98.5\%$ power even under contamination-specific asymmetric dependence.
40	
41	\subsection{Experimental Setup}
42	\label{sec:setup}
43	
44	\paragraph{Models and contamination.}
45	We validate on three 7--8B model families: Qwen2.5-7B-Instruct, Llama-3.1-8B-Instruct, and Mistral-7B-Instruct-v0.3.
46	Each is fine-tuned with QLoRA (rank\,$=$\,16, $\alpha$\,$=$\,32) under clean and contaminated conditions at varying levels: at $X\%$ contamination, $X\%$ of SFT training examples are benchmark items (questions paired with gold answers in the standard evaluation format), with the remainder drawn from a general instruction-following dataset.
47	All three families are tested at 15\% and 50\% contamination.
48	Following initial observation of non-monotonic dose-response for Qwen, we added 5\% and 25\% conditions for Qwen to trace the full dose-response curve.
49	The 25\% condition was subsequently extended to Llama to test whether the pattern generalizes; Mistral was not tested at 5\% or 25\% due to computational constraints.
50	We train $n{=}10$ independent clean seeds per model to establish baseline variability and construct bootstrap confidence intervals.
51	Reported CIs reflect variability across $n$ clean baseline seeds; for Qwen, each contamination level (15\%/25\%/50\%) was additionally replicated with $n{=}3$ independent QLoRA seeds to assess training-run variance (Appendix~\ref{app:reproducibility}).
52	
53	\paragraph{Benchmarks.}
54	We evaluate on MMLU \citep{hendrycks2021mmlu} (14,042 items) and ARC-Challenge \citep{clark2018arc} (295 items), spanning two orders of magnitude in benchmark size.
55	All 4PL item parameters are from \citet{psnirt2026}.
56	ARC-Challenge experiments were conducted on Qwen only, as the primary evaluation of cross-benchmark generalizability; extending to additional families was constrained by computational budget.
57	
58	\paragraph{Post-RL extension.}
59	To probe behavior boundaries beyond SFT, we apply Group Relative Policy Optimization (GRPO; \citealp{shao2024}) to one contaminated Qwen model (15\% MMLU) for 1,500 steps, evaluating at three checkpoints.
60	This extension is $N{=}1$ (single model family, single contamination level).
61	
62	\paragraph{Contamination model.}
63	QLoRA SFT on benchmark items serves as a controlled proxy for SFT-stage contamination, where benchmark data is explicitly included in fine-tuning mixtures---analogous to a test-taker with item preknowledge.
64	Our findings are scoped to SFT-based contamination and may not generalize to pretraining contamination, which operates through different learning dynamics.
65	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "560d7254-f0e9-4276-9d5b-bf07f45a2270",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "6e039a87-399b-47f0-95a0-3b4747d00e8c",
  "sourceToolAssistantUUID": "560d7254-f0e9-4276-9d5b-bf07f45a2270",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 26 · 2026-05-23T11:16:03.824Z_

Now let me check the remaining section files to ensure comprehensive coverage:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6e039a87-399b-47f0-95a0-3b4747d00e8c",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQUEMAdK1tUGfGBGfWJ",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "04aa755c-677b-4b8d-8a41-169134c605bd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Pp5SwKqsr1pd6wRuVwrF2A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 4632,
      "cache_read_input_tokens": 37563,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4632,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 2,
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

_source line 27 · 2026-05-23T11:16:04.703Z_

<details open><summary>🔧 Tool call — Read · `toolu_01UytSDWz3KfW8MRMu4NZSBU`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "04aa755c-677b-4b8d-8a41-169134c605bd",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQUEMAdK1tUGfGBGfWJ",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "e1ada87a-8c2e-4ca2-8e8e-7e42e8731594",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Pp5SwKqsr1pd6wRuVwrF2A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 4632,
      "cache_read_input_tokens": 37563,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4632,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 2,
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

_source line 28 · 2026-05-23T11:16:04.715Z_

<details><summary>↩ Tool result · `toolu_01UytSDWz3KfW8MRMu4NZSBU`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	We characterized IRT person-fit statistics for LLM contamination detection across three 7--8B model families, establishing reliable SFT-stage detection while identifying boundary conditions: $\theta$-shift absorption necessitating $\theta$-anchored estimation for high-ability models, a detection-diagnosis tradeoff, and non-monotonic dose-response as a $\theta$-estimation artifact.
4	For practitioners, we recommend a two-stage workflow: accuracy $z$-scores for efficient screening, followed by $\ell_z^*$ analysis when mechanistic understanding is needed---distinguishing \emph{which} items drive aberrance rather than merely flagging contamination.
5	Beyond detection, our characterization reveals that person-fit statistics capture structural response-pattern anomalies that persist even after RL post-training erases memorization-based signals, suggesting a complementary role to logit-based methods in the evaluation integrity toolkit.
6	Future work should address pretraining-stage signatures, broader model scales, and cross-benchmark generalization with larger item banks.
7	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e1ada87a-8c2e-4ca2-8e8e-7e42e8731594",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "6eb6aff0-b986-4e32-9b58-48a55ef24402",
  "sourceToolAssistantUUID": "e1ada87a-8c2e-4ca2-8e8e-7e42e8731594",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-23T11:16:04.942Z_

<details open><summary>🔧 Tool call — Read · `toolu_01M5Yv8XseyawJkocM3MVaqv`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6eb6aff0-b986-4e32-9b58-48a55ef24402",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQUEMAdK1tUGfGBGfWJ",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "f488778d-ea30-493c-a4f4-26ca84c064d1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Pp5SwKqsr1pd6wRuVwrF2A",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 4632,
      "cache_read_input_tokens": 37563,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4632,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 2,
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

_source line 30 · 2026-05-23T11:16:04.961Z_

<details><summary>↩ Tool result · `toolu_01M5Yv8XseyawJkocM3MVaqv`</summary>

```text
1	\section*{Limitations}
2	
3	Our controlled experiments cover three 7--8B model families with QLoRA fine-tuning; generalization to larger scales, mixture-of-experts architectures, full-parameter fine-tuning, and pretraining-stage contamination remains untested.
4	Most contamination conditions use a single training run, and multi-seed replication (available for Qwen) reveals high seed dependence at 50\% contamination (CV${=}$60\%), partially resolved by $\theta$-anchoring; the post-RL characterization is $N{=}1$.
5	The framework depends on pre-calibrated 4PL item parameters from PSN-IRT, whose calibration sample may include contaminated models, and we do not provide head-to-head comparison with logit-based methods (MIA, ConStat) that operate at a different information level.
6	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f488778d-ea30-493c-a4f4-26ca84c064d1",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "2530799e-c476-4aaa-aa2e-c6c897882cc1",
  "sourceToolAssistantUUID": "f488778d-ea30-493c-a4f4-26ca84c064d1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-23T11:16:05.184Z_

<details open><summary>🔧 Tool call — Read · `toolu_01MS8X8VAKKkhcMYLgsZimU6`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam/paper/sections/background.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2530799e-c476-4aaa-aa2e-c6c897882cc1",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQUEMAdK1tUGfGBGfWJ",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "81f3e80b-95be-4303-974a-d3ba1391267f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Pp5SwKqsr1pd6wRuVwrF2A",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 4632,
      "cache_read_input_tokens": 37563,
      "output_tokens": 256,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 4632
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 6,
          "output_tokens": 256,
          "cache_read_input_tokens": 37563,
          "cache_creation_input_tokens": 4632,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 4632,
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

_source line 32 · 2026-05-23T11:16:05.195Z_

<details><summary>↩ Tool result · `toolu_01MS8X8VAKKkhcMYLgsZimU6`</summary>

```text
1	\section{Background and Related Work}\label{sec:background}
2	
3	\subsection{IRT and Person-Fit Statistics}\label{sec:irt_background}
4	
5	Item Response Theory (IRT) models the probability that an examinee answers a test item correctly as a function of the examinee's latent ability $\theta$ and item-level parameters \citep{lord1980, embretson2000}.
6	The four-parameter logistic (4PL) model, formalized in \S\ref{sec:framework} (Eq.~\ref{eq:4pl}), extends the classical three-parameter model \citep{birnbaum1968} with an upper asymptote $d$ that captures the probability of error even at high ability \citep{barton1981}.
7	This parameter matters for LLMs: \citet{psnirt2026} find that 46\% of MMLU items have $d < 0.95$, meaning ceiling effects are pervasive and a model without the $d$ parameter systematically misestimates item characteristics.
8	
9	Given calibrated item parameters, person-fit statistics measure whether an examinee's \emph{pattern} of correct and incorrect responses is consistent with the IRT model at the estimated ability level.
10	The key intuition is that a test-taker with ability $\theta$ should get hard items wrong and easy items right at rates the model predicts; systematic deviations signal aberrant behavior.
11	\citet{drasgow1985} introduced $\ell_z$, a standardized log-likelihood residual that aggregates per-item deviations into a single score.
12	\citet{snijders2001} corrected the variance of $\ell_z$ for uncertainty in the estimated $\hat{\theta}$, yielding $\ell_z^*$ with the property that $\ell_z^* \sim \mathcal{N}(0,1)$ under the null hypothesis of model-consistent responding.
13	Negative values indicate \emph{aberrant} patterns (unexpected errors on easy items or unexpected successes on hard items), while positive values indicate \emph{over-consistent} patterns (responses too predictable given the model).
14	We defer the formal definition to \S\ref{sec:framework}.
15	
16	In psychometrics, person-fit statistics have a long history in detecting test fraud and item preknowledge.
17	\citet{karabatsos2003} compared 36 person-fit statistics and found $\ell_z$ among the most powerful for detecting cheating.
18	\citet{sinharay2017} showed that $\ell_z^*$ is particularly effective when the compromised item set is known, a setting analogous to benchmark contamination where the ``compromised'' items are those memorized during pretraining.
19	\citet{meijer2001} provide a comprehensive review of the broader person-fit literature.
20	Our work transfers this psychometric toolkit to LLM evaluation, treating each model as an examinee whose response pattern may reveal memorization.
21	
22	\subsection{Benchmark Contamination Detection}\label{sec:contamination_related}
23	
24	\begin{table}[t]
25	\centering
26	\small
27	\caption{Detection frontier ordered by information access level. RL column: robustness to RL post-training ($\times$ = fails, -- = untested).}
28	\label{tab:frontier}
29	\begin{tabular}{@{}llc@{}}
30	\toprule
31	Information Required & Method & RL \\
32	\midrule
33	Training corpus & N-gram overlap \citep{dodge2021} & N/A \\
34	Log-probabilities & Min-K\%++ \citep{minkprob2024} & $\times$\,$^{a}$ \\
35	Generated text & Rephrased probing \citep{golchin2024} & -- \\
36	Perf.\ (multi-form) & ConStat \citep{constat2024} & -- \\
37	\textbf{Binary only} & \textbf{\irtfit{} (ours)} & $^{b}$ \\
38	\bottomrule
39	\end{tabular}
40	
41	{\raggedright\scriptsize $^{a}$\citet{wang2025fragility}: 10 methods fail post-RL.
42	$^{b}$Structurally invariant; empirical verification future work.\par}
43	\end{table}
44	
45	Contamination detection methods vary in what information they require from the model under test.
46	Table~\ref{tab:frontier} organizes the detection frontier by information access, from most to least demanding.
47	At the high end, corpus-search methods match benchmark items against pretraining data \citep{dodge2021, magar2022}, but require full corpus access, which is unavailable for closed models.
48	Membership inference attacks (MIA) use token-level log-probabilities to distinguish training examples from unseen ones \citep{minkprob2024, deng2024}.
49	Generation-based probes elicit benchmark content via prompting \citep{golchin2024, oren2024}.
50	Performance-based methods such as ConStat \citep{constat2024} and CoDeC \citep{codec2026} compare a model's accuracy on the target benchmark against accuracy on perturbed or reference sets, requiring either multiple evaluations or in-context learning passes.
51	\citet{sainz2023} propose overlapping-split analysis using time-stamped data.
52	
53	A critical limitation unites all log-probability methods: \citet{wang2025fragility} demonstrate that reinforcement learning (RL) post-training renders MIA-based detectors (including Min-K\%++) no better than random across 10 methods and 4 benchmarks.
54	RL reshapes token-level output distributions while largely preserving binary correctness patterns, so token-level statistics lose signal while binary response patterns remain available for analysis.
55	\citet{selfcritique2026} and \citet{zhang2026rlvr} propose RL-specific solutions but require generation-level access.
56	
57	\irtfit{} operates at the bottom of this frontier: it requires only binary responses (correct/incorrect), making it applicable to any model accessible through a standard evaluation API.
58	Recent work applies IRT to LLM evaluation for ability estimation \citep{martinezplumed2019, polo2024tinybenchmarks}, adaptive testing \citep{atlas2025}, and benchmark diagnostics \citep{psnirt2026}, but none use \emph{person-fit} statistics for contamination detection.
59	Our work bridges this gap.
60	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "81f3e80b-95be-4303-974a-d3ba1391267f",
  "isSidechain": true,
  "promptId": "2361ea5e-4d8f-4fbc-959e-b4f93a7e61ba",
  "agentId": "afe11dee6ca447a7a",
  "type": "user",
  "uuid": "733bd691-2cf6-492c-af9a-8f8f7b78eff1",
  "sourceToolAssistantUUID": "81f3e80b-95be-4303-974a-d3ba1391267f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 33 · 2026-05-23T11:16:53.686Z_

Perfect! Now I have all the LaTeX files. Let me compile the comprehensive list of all numerical values found in the paper, organized by location.

## COMPREHENSIVE EXTRACTION OF NUMERICAL VALUES FROM irt_personfit_contam PAPER

Based on my complete reading of all LaTeX files in the paper directory, here is every numerical value found with exact location (file:line):

### **MAIN RESULTS - TABLE 1 (Tab: cohens_d)**
**File: sections/results.tex**

- Line 7-8: Cohen's d for lz* across model families
- Line 10: Qwen MMLU 5% |d|=4.15, 15% |d|=5.36, 25% |d|=7.44, 50% |d|=5.08
- Line 10: Llama MMLU 15% |d|=2.27, 25% |d|=2.97, 50% |d|=2.50
- Line 10: Mistral MMLU 15% |d|=3.01, 50% |d|=3.50
- Line 11: Qwen ARC-C 15% |d|=3.16, 50% |d|=5.30
- Line 13: Clean-model lz* baselines:
  - Qwen: +8.68 (SD=0.74)
  - Mistral: +4.02 (SD=2.05)
  - Llama: +0.29 (SD=1.45)
  - ARC-C Qwen: -5.42 (SD=0.16)
- Line 14: Qwen contaminated lz* at 15%: +3.85
- Line 28: Qwen MMLU 5% d=-4.15 [CI: -9.9, -2.7]
- Line 28: Qwen MMLU 15% d=-5.36 (±1.10)
- Line 28: Qwen MMLU 25% d=-7.44 (±1.86)
- Line 28: Qwen MMLU 50% d=-5.08 (±3.02)
- Line 29: Llama MMLU 15% d=-2.27 [CI: -4.6, -1.6]
- Line 29: Llama MMLU 25% d=-2.97 [CI: -6.1, -2.0]
- Line 29: Llama MMLU 50% d=-2.50 [CI: -5.0, -1.8]
- Line 30: Mistral MMLU 15% d=-3.01 [CI: -8.2, -1.8]
- Line 30: Mistral MMLU 50% d=-3.50 [CI: -9.4, -2.1]
- Line 31: Qwen ARC-C 15% d=+3.16 [2.0, 9.5]
- Line 31: Qwen ARC-C 50% d=+5.30 [3.6, 15.2]

### **TABLE 2 (Tab: theta_fixed) - Free vs Fixed Theta**
**File: sections/results.tex**

- Line 49: Qwen Δθ=0.47 at 50%; Llama Δθ=0.09
- Line 53: Fixed-θ amplifies Qwen's |d| by 2.4× at 50% (5.08 → 12.32)
- Line 54: Qwen inter-seed CV reduced from 60% to 19%
- Line 58: Qwen ARC-C baseline accuracy 90.0%
- Line 58: Qwen ARC-C |d|=3.16 at 15%, |d|=5.30 at 50%
- Line 69: Qwen accuracy 67.8%, Δθ=0.47
- Line 70: Mistral 52.4% accuracy, 1.7× amplification at 50%
- Line 71: Llama 59.4% accuracy, SD=1.45, Δθ=0.09
- Line 72: Fixed-θ indicated for Δθ > 0.2
- Line 84: Qwen 5% contam: free |d|=4.15, fixed |d|=3.52, ratio 0.8×, CI [2.9, 5.7]
- Line 87: Qwen 15% contam: free |d|=5.36, fixed |d|=6.85, ratio 1.3×, CI (±1.80)
- Line 88: Llama 15% contam: free |d|=2.27, fixed |d|=0.58, ratio 0.3×, CI [0, 2.37]
- Line 89: Mistral 15% contam: free |d|=3.01, fixed |d|=2.69, ratio 0.9×, CI [1.45, 9.00]
- Line 92: Qwen 50% contam: free |d|=5.08, fixed |d|=12.32, ratio 2.4×, CI (±2.38)
- Line 93: Llama 50% contam: free |d|=2.50, fixed |d|=0.84, ratio 0.3×, CI [0.17, 2.97]
- Line 94: Mistral 50% contam: free |d|=3.50, fixed |d|=5.80, ratio 1.7×, CI [3.71, 18.16]

### **TABLE 3 (Tab: degradation) - Detection-Diagnosis Tradeoff**
**File: sections/results.tex**

- Line 116: Accuracy z-scores produce |d| several-fold to over order of magnitude larger
- Line 122: Item-level detection AUROC ≈ 0.53
- Line 124: 57/60 model-benchmark cells flagged as aberrant
- Line 125: Accuracy z-scores flag only 4/60 cells
- Line 130: 4PL vs 3PL mean +27.3pp power gain on MMLU; 46% of MMLU items have d < 0.95
- Line 141: Qwen lz* 15%: 5.36 (±1.10), 50%: 5.08 (±3.02)
- Line 142: Qwen HT 15%: 5.83 (±1.30), 50%: 5.29 (±3.41)
- Line 143: Qwen Acc z 15%: 45.0 (±2.5), 50%: 70.0 (±1.1)
- Line 145: Llama lz* 15%: 2.27 [1.6, 4.6], 50%: 2.50 [1.8, 5.2]
- Line 146: Llama HT 15%: 2.45 [1.5, 4.3], 50%: 3.07 [1.9, 5.3]
- Line 147: Llama Acc z 15%: 22.5 [13.6, 47.0], 50%: 32.8 [19.8, 68.6]
- Line 149: Mistral lz* 15%: 3.01 [1.8, 8.2], 50%: 3.50 [2.1, 9.4]
- Line 150: Mistral HT 15%: 4.36 [1.2, 7.0], 50%: 5.89 [1.9, 9.4]
- Line 151: Mistral Acc z 15%: 7.81 [4.4, 14.4], 50%: 16.6 [9.7, 34.6]

### **NON-MONOTONIC DOSE-RESPONSE & POWER ANALYSIS**
**File: sections/results.tex**

- Line 160-161: Qwen multi-seed trajectory |d|: 4.15 → 5.36 → 7.44 → 5.08 at 5%/15%/25%/50%
- Line 162: Fixed-θ mean |d|: 5.89 at 25% vs 12.32 at 50%, no seed-level overlap
- Line 162: 50% CV reduced to 19%
- Line 163: Llama |d|=2.27 → 2.97 → 2.50, Δθ=0.09 vs 0.47 for Qwen
- Line 166: >93% power on MMLU at all contamination levels
- Line 166: Power function R² = 0.957

### **APPENDIX - SIMULATION VALIDATION (Sec: app:simulation)**
**File: sections/appendix.tex**

- Line 4: Mean bias 0.041, standard deviation 1.003 on MMLU
- Line 5: KS rejection rates: MMLU 8.3%, HellaSwag 8.3%, GSM8K 50.0%, ARC-C 58.3%, HumanEval 75.0%
- Line 5: Benchmark sizes: MMLU n>10,000, HellaSwag n>10,000, GSM8K n=1,319, ARC-C n=295, HumanEval n=164
- Line 8: MMLU 97.8% power at 15% contamination, >93% at all levels
- Line 10: n ≥ 7,958 items minimum for 80% power at 15% contamination
- Line 10: Power function R² = 0.957

### **4PL vs 3PL ABLATION (Sec: app:4pl_ablation)**
**File: sections/appendix.tex**

- Line 25-50: Table tab:4pl_3pl_power with power values:

**MMLU:**
- 4PL: 5%=.476, 10%=.848, 15%=.969, 25%=.983, 50%=.952, 75%=.938, 100%=1.00
- 3PL: 5%=.227, 10%=.340, 15%=.412, 25%=.521, 50%=.676, 75%=.770, 100%=1.00

**HellaSwag:**
- 4PL: 5%=.251, 10%=.454, 15%=.656, 25%=.915, 50%=.939, 75%=.919, 100%=1.00
- 3PL: 5%=.167, 10%=.241, 15%=.313, 25%=.368, 50%=.508, 75%=.642, 100%=1.00

**GSM8K:**
- 4PL: 5%=.156, 10%=.309, 15%=.492, 25%=.737, 50%=.846, 75%=.802, 100%=1.00
- 3PL: 5%=.102, 10%=.172, 15%=.285, 25%=.396, 50%=.567, 75%=.577, 100%=1.00

**ARC-C:**
- 4PL: 5%=.057, 10%=.075, 15%=.087, 25%=.130, 50%=.285, 75%=.493, 100%=1.00
- 3PL: 5%=.054, 10%=.062, 15%=.071, 25%=.076, 50%=.110, 75%=.102, 100%=1.00

**HumanEval:**
- 4PL: 5%=.076, 10%=.121, 15%=.197, 25%=.302, 50%=.554, 75%=.521, 100%=1.00
- 3PL: 5%=.063, 10%=.086, 15%=.120, 25%=.182, 50%=.281, 75%=.315, 100%=1.00

### **SEED SENSITIVITY ANALYSIS (Sec: app:seed_sensitivity)**
**File: sections/appendix.tex**

- Line 56: Seeds 42, 123, 456
- Line 57: Qwen lz* ranges 7.05 to 9.53
- Line 71: Qwen lz*: mean=8.684, std=1.412, range=2.475, CV=0.163
- Line 72: Qwen accuracy: std=0.000, range=0.001, CV=0.001
- Line 73: Qwen θ_MLE: -0.097, std=0.012, range=0.023, CV=0.119
- Line 75: Llama lz*: mean=-0.141, std=0.965, range=1.929, CV=6.860
- Line 76: Llama accuracy: std=0.002, range=0.004, CV=0.004
- Line 77: Llama θ_MLE: -0.645, std=0.019, range=0.036, CV=0.029
- Line 84: t critical value t_0.025,2 = 4.303
- Line 98: Qwen 15% d=-3.42, Bootstrap CI [-3.45, -2.82]
- Line 99: Qwen 50% d=-0.99, Bootstrap CI [-0.99, -0.41]
- Line 101: Llama 15% d=-2.95, Bootstrap CI [-5.89, -2.29]
- Line 102: Llama 50% d=-3.31, Bootstrap CI [-6.47, -2.59]
- Line 109: |Δd|=2.32 gap at 50% contamination

### **BASELINE lz* INTERPRETATION (Sec: app:baseline_meaning)**
**File: sections/appendix.tex**

- Line 130: Mistral acc=0.514, lz*=+5.42, θ=-1.16

### **ITEM-LEVEL DETECTION (Sec: app:item_auroc)**
**File: sections/appendix.tex**

- Line 139: Accuracy z-score z=160 at 15% contamination, std=0.0003

### **LOCAL DEPENDENCE ROBUSTNESS (Sec: app:local_dep)**
**File: sections/appendix.tex**

- Line 167: 14,042 MMLU items, ~200 testlets of ~70 items
- Line 172: d_ratio ≥ 0.93 for σ_τ ≤ 0.5
- Line 182-186: Type I error and d_ratio by σ_τ:
  - σ=0.0: Type I=0.043, d_ratio 15%=1.000, d_ratio 50%=1.000
  - σ=0.3: Type I=0.110, d_ratio 15%=1.002, d_ratio 50%=1.038
  - σ=0.5: Type I=0.454, d_ratio 15%=0.934, d_ratio 50%=1.028
  - σ=1.0: Type I=0.939, d_ratio 15%=0.705, d_ratio 50%=1.061
- Line 193: ≥98.5% power across conditions
- Line 202-205: Asymmetric LD results:
  - σ_mem=0.5: Power 15%=0.987, d=-2.107, Power 50%=0.991, d=-2.337
  - σ_mem=1.0: Power 15%=0.993, d=-2.104, Power 50%=0.985, d=-1.587

### **PARAMETER PERTURBATION ROBUSTNESS (Sec: app:param_perturb)**
**File: sections/appendix.tex**

- Line 232: d (15%) at 0%=−6.575, 5%=−6.010 (8.6% bias), 10%=−5.433 (17.4% bias)
- Line 233: d (50%) at 0%=−1.897, 5%=−0.925 (51.2% bias), 10%=−0.014 (99.3% bias)
- Line 249: d_fixed (15%) at 0%=4.77, 5%=5.07±0.24 (6.3% bias), 10%=4.95±0.43 (3.7% bias, worst 3.73)
- Line 250: d_fixed (50%) at 0%=14.52, 5%=14.76±0.44 (1.6% bias), 10%=14.45±0.85 (0.5% bias, worst 12.20)

### **BCa BOOTSTRAP SENSITIVITY (Sec: app:bca)**
**File: sections/appendix.tex**

- Line 261: BCa CIs uniformly narrower, mean reduction 22%
- Line 262: Llama fixed-θ 50% BCa CI [-0.13, 2.21] vs percentile CI [0.17, 2.97]

### **CLASSICAL IRT REFIT (Sec: app:mml_em)**
**File: sections/appendix.tex**

- Line 267: N=178 models, Q=31 nodes, N:J ratio=0.013
- Line 268: N>500 typically required for stable 3PL estimation
- Line 271: 3PL r_b=0.663, r_a=0.127
- Line 272: 2PL r_b=0.608, r_a=−0.029
- Line 272: Miscalibrated lz* mean=11.2
- Line 284-286: Parameter correlations with PSN-IRT

### **POST-RL PRELIMINARY (Sec: app:post_rl)**
**File: sections/appendix.tex**

- Line 296: N=1, GRPO 1,500 steps
- Line 297: Accuracy gap: 11.4pp → 2.1pp
- Line 297: lz* response-pattern gap: ~3.3
- Line 298: Min-K% AUC: SFT=0.611
- Line 298: GRPO AUC at step 500, 1000, 1500: 0.493 (all equal, chance 0.50)

### **HYPERPARAMETERS (Sec: app:hyperparams)**
**File: sections/appendix.tex**

- Line 322: 4-bit NF4 quantization
- Line 323: LoRA rank=16, α=32, dropout=0.05
- Line 328: Learning rate: 2×10^-4
- Line 330: Warmup ratio=0.1
- Line 331: Epochs=3
- Line 332: Per-device batch size=4
- Line 333: Gradient accumulation steps=4
- Line 334: Effective batch size=16
- Line 335: Max sequence length=512

### **REPRODUCIBILITY TABLE (Sec: app:reproducibility)**
**File: sections/appendix.tex**

- Line 345: Qwen baseline: mean lz*=8.68, s=0.74, n=10
- Line 353: Seed 42: Free 15%=6.57, 25%=8.22, 50%=1.90; Fixed 15%=4.77, 25%=4.96, 50%=14.52
- Line 354: Seed 123: Free 15%=5.09, 25%=8.78, 50%=5.42; Fixed 15%=7.79, 25%=5.37, 50%=12.64
- Line 355: Seed 456: Free 15%=4.41, 25%=5.31, 50%=7.91; Fixed 15%=7.99, 25%=7.34, 50%=9.80
- Line 357: Mean: Free 15%=5.36, 25%=7.44, 50%=5.08; Fixed 15%=6.85, 25%=5.89, 50%=12.32
- Line 358: SD: Free 15%=1.10, 25%=1.86, 50%=3.02; Fixed 15%=1.80, 25%=1.27, 50%=2.38
- Line 359: CV: Free 15%=20.3%, 25%=25.2%, 50%=59.6%; Fixed 15%=26.3%, 25%=21.7%, 50%=19.3%
- Line 364: 50% free CV=59.6%, fixed CV=19.3%
- Line 376-381: HT and Accuracy z for seeds 42, 123, 456:
  - Seed 42 HT: 15%=7.26, 25%=8.90, 50%=1.66; Acc z: 15%=42.3, 25%=49.8, 50%=68.7
  - Seed 123 HT: 15%=5.52, 25%=9.51, 50%=5.80; Acc z: 15%=47.3, 25%=53.4, 50%=70.8
  - Seed 456 HT: 15%=4.72, 25%=5.10, 50%=8.41; Acc z: 15%=45.4, 25%=51.3, 50%=70.4
  - Mean HT: 15%=5.83, 25%=7.84, 50%=5.29; Mean Acc z: 15%=45.0, 25%=51.5, 50%=70.0
  - SD HT: 15%=1.30, 25%=2.39, 50%=3.41; SD Acc z: 15%=2.5, 25%=1.8, 50%=1.1

### **MAIN TEXT ADDITIONAL NUMBERS**
**File: sections/main.tex**

- Line 43: Bootstrap confidence intervals with 10,000 resamples
- Line 44: n=10 clean baseline seeds per family

### **DISCUSSION SECTION**
**File: sections/discussion.tex**

- Line 13: CV up to 60% for free-θ; Δθ > 0.2 threshold
- Line 14: n > 7,000 items for 80% power at 15% contamination
- Line 18: r_a=0.127 (calibration failure on contaminated data)
- Line 21: GRPO Min-K% AUC: SFT=0.611, post-RL=0.493
- Line 21: GRPO lz* ~3.3

### **ABSTRACT & INTRODUCTION**
**File: sections/abstract.tex**

- Line 5: 2.4× amplification at 50% contamination
- Line 5: Inter-seed CV reduced from 60% to 19%
- Lines 6-7: Qwen trajectory 4.15 → 5.36 → 7.44 → 5.08

**File: sections/introduction.tex**

- Line 39: 13,000+ models in PSN-IRT calibration
- Line 42: 2.4× amplification at 50%, CV 60% to 19%
- Line 44: 57/60 vs 4/60 cells flagged
- Line 46: 4.15 → 5.36 → 7.44 → 5.08 trajectory; mean 5.89 vs 12.32; no seed-level overlap

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "733bd691-2cf6-492c-af9a-8f8f7b78eff1",
  "isSidechain": true,
  "agentId": "afe11dee6ca447a7a",
  "requestId": "req_011CbKQUS3d8p1XJNU8U5VTx",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "0e47db0d-d558-46a9-bb05-a601260672bb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0519-3/projects/irt_personfit_contam",
  "sessionId": "86fcc0db-d877-4917-809d-2d4a59d9abb1",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_018XeQKimsBJboRrbB7GRS3e",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 2470,
      "cache_read_input_tokens": 42195,
      "output_tokens": 6034,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2470
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 6,
          "output_tokens": 6034,
          "cache_read_input_tokens": 42195,
          "cache_creation_input_tokens": 2470,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2470,
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
