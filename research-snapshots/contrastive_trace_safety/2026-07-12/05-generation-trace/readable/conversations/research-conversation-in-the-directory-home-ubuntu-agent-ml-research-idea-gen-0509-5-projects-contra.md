# Research conversation: In the directory /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/, find the existing e

**Layer Selection Sensitivity in Hidden-State Safety Probes for Reasoning Models (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 36
- **Recorded user turns:** 1
- **Tool calls:** 13
- **Original source:** `logs/chats/exported-trajectories/account-1/agent-aa357d0ddf5851242.jsonl`
- **Structured JSON:** [`54d644d60007c72d278a.json`](../../sessions/54/54d644d60007c72d278a.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

36 recorded events

### User

_source line 1 · 2026-05-17T12:02:53.833Z_

In the directory /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/, find the existing experiment scripts under src/experiments/. I need to understand:
1. How data loading works (how .pt files are loaded, how train/val/test splits are done)
2. How LR probe or GRU experiments are structured
3. What metrics are computed (bal_acc, precision, coverage, pre_cp_fpr, lead)

Also check what files exist in src/experiments/ and look at the most relevant ones for understanding the data pipeline. Search breadth: very thorough.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "6a2f2099-dbd9-437b-b1bc-3eac52c0197a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 2 · 2026-05-17T12:02:55.161Z_

I'll help you thoroughly explore the experiment scripts and understand the data pipeline, model structure, and metrics. Let me start by examining the directory structure and then diving into the relevant files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6a2f2099-dbd9-437b-b1bc-3eac52c0197a",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87Bxdta7xJrP6t2qrnU",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "89df8dc8-f7ef-4588-ac7c-36a559199820",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01KzFD5ExaJRe7utRm2mCjqz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 567,
      "cache_read_input_tokens": 18285,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 567,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 5,
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

_source line 3 · 2026-05-17T12:02:55.301Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01CugmNK9XvdPM4mW6htnKmf`</summary>

```json
{
  "command": "find /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/experiments -type f -name \"*.py\" | head -20"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "89df8dc8-f7ef-4588-ac7c-36a559199820",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87Bxdta7xJrP6t2qrnU",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "77c7764d-811a-4876-97cf-5d65dc0224c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01KzFD5ExaJRe7utRm2mCjqz",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 567,
      "cache_read_input_tokens": 18285,
      "output_tokens": 136,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 567
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 136,
          "cache_read_input_tokens": 18285,
          "cache_creation_input_tokens": 567,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 567,
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

_source line 4 · 2026-05-17T12:02:55.486Z_

<details><summary>↩ Tool result · `toolu_01CugmNK9XvdPM4mW6htnKmf`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/experiments/trajguard_mahalanobis.py
/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/experiments/fpr_analysis.py
/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/experiments/__init__.py
/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/experiments/bootstrap_ci.py
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "77c7764d-811a-4876-97cf-5d65dc0224c7",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "d5fa660f-9a29-4c29-bd29-01fcb1e9022e",
  "sourceToolAssistantUUID": "77c7764d-811a-4876-97cf-5d65dc0224c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 5 · 2026-05-17T12:02:56.833Z_

Let me get a broader view of the experiments directory:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d5fa660f-9a29-4c29-bd29-01fcb1e9022e",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87C5b6sxm42YveANxhY",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "1449353c-6c92-4f26-9967-99d563927dba",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01SbrXZzLAMxsRDu4sXHjm5d",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 1146,
      "cache_read_input_tokens": 18852,
      "output_tokens": 100,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1146
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 5,
          "output_tokens": 100,
          "cache_read_input_tokens": 18852,
          "cache_creation_input_tokens": 1146,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1146,
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

### Tool call

_source line 6 · 2026-05-17T12:02:56.891Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01KYgnnDzJfVh4RK8yj1e8kX`</summary>

```json
{
  "command": "ls -la /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/experiments/"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1449353c-6c92-4f26-9967-99d563927dba",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87C5b6sxm42YveANxhY",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "838b8ab6-3f8b-42a8-b6ee-702051778bb1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01SbrXZzLAMxsRDu4sXHjm5d",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 1146,
      "cache_read_input_tokens": 18852,
      "output_tokens": 100,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1146
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 5,
          "output_tokens": 100,
          "cache_read_input_tokens": 18852,
          "cache_creation_input_tokens": 1146,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1146,
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

_source line 7 · 2026-05-17T12:02:57.044Z_

<details><summary>↩ Tool result · `toolu_01KYgnnDzJfVh4RK8yj1e8kX`</summary>

```text
total 64
drwxr-xr-x 2 ubuntu ubuntu  4096 May 16 21:05 .
drwxr-xr-x 7 ubuntu ubuntu  4096 May 16 20:37 ..
-rw-r--r-- 1 ubuntu ubuntu     0 May 16 20:37 __init__.py
-rw-r--r-- 1 ubuntu ubuntu 18703 May 16 21:03 bootstrap_ci.py
-rw-r--r-- 1 ubuntu ubuntu 21523 May 16 21:05 fpr_analysis.py
-rw-r--r-- 1 ubuntu ubuntu  9760 May 16 20:37 trajguard_mahalanobis.py
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "838b8ab6-3f8b-42a8-b6ee-702051778bb1",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "95cf4402-798d-4b73-8ab0-1267aa886bd2",
  "sourceToolAssistantUUID": "838b8ab6-3f8b-42a8-b6ee-702051778bb1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 8 · 2026-05-17T12:02:58.006Z_

Now let me check the broader source directory to understand the project structure:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "95cf4402-798d-4b73-8ab0-1267aa886bd2",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CCFSrb5guyxmx2euh",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "9c56dcfc-9b47-413c-aa83-912650d89e3d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01TihWzv2DkrZTaZL6K6fLfu",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 300,
      "cache_read_input_tokens": 19998,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 300,
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

_source line 9 · 2026-05-17T12:02:58.226Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01TFi5VtAAucvN6tWWBD74JT`</summary>

```json
{
  "command": "ls -la /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9c56dcfc-9b47-413c-aa83-912650d89e3d",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CCFSrb5guyxmx2euh",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "cbe9edfb-f184-4ed2-a91f-d8443e53e800",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01TihWzv2DkrZTaZL6K6fLfu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 300,
      "cache_read_input_tokens": 19998,
      "output_tokens": 101,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 300
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 5,
          "output_tokens": 101,
          "cache_read_input_tokens": 19998,
          "cache_creation_input_tokens": 300,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 300,
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

_source line 10 · 2026-05-17T12:02:58.403Z_

<details><summary>↩ Tool result · `toolu_01TFi5VtAAucvN6tWWBD74JT`</summary>

```text
total 56
drwxr-xr-x  7 ubuntu ubuntu 4096 May 16 20:37 .
drwxr-xr-x 10 ubuntu ubuntu 4096 May 17 12:02 ..
-rw-r--r--  1 ubuntu ubuntu    0 May 16 18:40 __init__.py
drwxr-xr-x  2 ubuntu ubuntu 4096 May 16 18:44 __pycache__
drwxr-xr-x  3 ubuntu ubuntu 4096 May 16 18:44 baselines
-rw-r--r--  1 ubuntu ubuntu 1072 May 16 18:40 config.py
drwxr-xr-x  2 ubuntu ubuntu 4096 May 16 18:42 crta
-rw-r--r--  1 ubuntu ubuntu 5496 May 16 18:44 data_loader.py
drwxr-xr-x  3 ubuntu ubuntu 4096 May 16 18:59 eval
drwxr-xr-x  2 ubuntu ubuntu 4096 May 16 21:05 experiments
-rw-r--r--  1 ubuntu ubuntu 5822 May 16 18:58 extract_hidden_states.py
-rw-r--r--  1 ubuntu ubuntu 4487 May 16 18:42 run_pipeline.py
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "cbe9edfb-f184-4ed2-a91f-d8443e53e800",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "d78f348d-4920-4468-92bb-055ca98e2f26",
  "sourceToolAssistantUUID": "cbe9edfb-f184-4ed2-a91f-d8443e53e800",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 11 · 2026-05-17T12:02:59.575Z_

Let me read the key files, starting with the data loader and then the experiment scripts:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d78f348d-4920-4468-92bb-055ca98e2f26",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CJ8fK8abS8fFr3orL",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "35774e0b-8d9b-44eb-91b7-e41f83d7a918",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01W4AhbULSHsY4cP8DrN9PPx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 471,
      "cache_read_input_tokens": 20298,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 471,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 3,
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

_source line 12 · 2026-05-17T12:03:00.143Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Po9ctFH9R2k59yJvA1WESx`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/data_loader.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "35774e0b-8d9b-44eb-91b7-e41f83d7a918",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CJ8fK8abS8fFr3orL",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "79f77721-cc16-4118-b326-19495cc8d6c9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01W4AhbULSHsY4cP8DrN9PPx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 471,
      "cache_read_input_tokens": 20298,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 471,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 3,
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

_source line 13 · 2026-05-17T12:03:00.179Z_

<details><summary>↩ Tool result · `toolu_01Po9ctFH9R2k59yJvA1WESx`</summary>

```text
1	"""Load HarmThoughts dataset and extract commitment points.
2	
3	Input: HuggingFace dataset "ishitakakkar-10/HarmThoughts"
4	Output: List of trace dicts with sentences, labels, commitment_point, split assignments
5	"""
6	
7	from collections import defaultdict
8	from typing import List, Optional, Dict, Any
9	import numpy as np
10	from datasets import load_dataset
11	
12	from .config import (
13	    HF_DATASET, TARGET_MODEL, SAFETY_LABELS,
14	    TRAIN_RATIO, VAL_RATIO, SEED
15	)
16	
17	
18	def load_harmthoughts(model_name: str = TARGET_MODEL) -> Dict[str, List[Dict]]:
19	    """Load HarmThoughts from HF and group by trace_id."""
20	    ds = load_dataset(HF_DATASET, split="train")
21	
22	    traces = defaultdict(list)
23	    for row in ds:
24	        if row["model_name"] != model_name:
25	            continue
26	        # trace_id is the part before the last dash in sentence_id
27	        sid = row["sentence_id"]
28	        parts = sid.rsplit("-", 1)
29	        trace_id = parts[0]
30	        step_idx = int(parts[1]) - 1  # convert to 0-indexed
31	
32	        traces[trace_id].append({
33	            "sentence_id": sid,
34	            "step_idx": step_idx,
35	            "sentence": row["sentence"],
36	            "label": row["llm_annotation"],
37	            "query": row["query"],
38	            "final_judgment": row["final_judgment"],
39	        })
40	
41	    # Sort each trace by step_idx
42	    for tid in traces:
43	        traces[tid].sort(key=lambda x: x["step_idx"])
44	
45	    return dict(traces)
46	
47	
48	def extract_commitment_point(labels: List[str]) -> Optional[int]:
49	    """Find the commitment point in a sequence of labels.
50	
51	    Returns the index after the last safety label, or None if:
52	    - No safety labels exist in the trace
53	    - The last safety label is at the final position (no post-commitment segment)
54	    """
55	    last_safety_idx = None
56	    for i, label in enumerate(labels):
57	        if label in SAFETY_LABELS:
58	            last_safety_idx = i
59	
60	    if last_safety_idx is None:
61	        return None
62	    if last_safety_idx == len(labels) - 1:
63	        return None
64	
65	    return last_safety_idx + 1
66	
67	
68	def create_step_labels(commitment_point: int, num_steps: int) -> List[int]:
69	    """Generate binary labels: 0 = pre-commitment, 1 = post-commitment."""
70	    return [0 if i < commitment_point else 1 for i in range(num_steps)]
71	
72	
73	def prepare_dataset(model_name: str = TARGET_MODEL) -> Dict[str, List[Dict[str, Any]]]:
74	    """Load data, compute commitment points, categorize traces.
75	
76	    Returns dict with keys:
77	    - jailbreak_with_commitment: traces for training/evaluation
78	    - jailbreak_no_commitment: excluded jailbreak traces
79	    - safe: safe traces for FP evaluation
80	    """
81	    raw_traces = load_harmthoughts(model_name)
82	
83	    jailbreak_with_commitment = []
84	    jailbreak_no_commitment = []
85	    safe_traces = []
86	
87	    for trace_id, steps in raw_traces.items():
88	        is_jailbreak = steps[0]["final_judgment"] == 1.0
89	        labels = [s["label"] for s in steps]
90	        sentences = [s["sentence"] for s in steps]
91	        query = steps[0]["query"]
92	        num_steps = len(steps)
93	
94	        trace_dict = {
95	            "trace_id": trace_id,
96	            "sentences": sentences,
97	            "labels": labels,
98	            "query": query,
99	            "is_jailbreak": is_jailbreak,
100	            "num_steps": num_steps,
101	        }
102	
103	        if not is_jailbreak:
104	            trace_dict["commitment_point"] = None
105	            trace_dict["step_labels"] = None
106	            safe_traces.append(trace_dict)
107	            continue
108	
109	        cp = extract_commitment_point(labels)
110	        trace_dict["commitment_point"] = cp
111	
112	        if cp is not None:
113	            trace_dict["step_labels"] = create_step_labels(cp, num_steps)
114	            jailbreak_with_commitment.append(trace_dict)
115	        else:
116	            trace_dict["step_labels"] = None
117	            jailbreak_no_commitment.append(trace_dict)
118	
119	    return {
120	        "jailbreak_with_commitment": jailbreak_with_commitment,
121	        "jailbreak_no_commitment": jailbreak_no_commitment,
122	        "safe": safe_traces,
123	    }
124	
125	
126	def split_data(traces: List[Dict], train_ratio: float = TRAIN_RATIO,
127	               val_ratio: float = VAL_RATIO, seed: int = SEED):
128	    """Split traces into train/val/test at trace level."""
129	    rng = np.random.default_rng(seed)
130	    indices = rng.permutation(len(traces))
131	
132	    n_train = int(len(traces) * train_ratio)
133	    n_val = int(len(traces) * val_ratio)
134	
135	    train_idx = indices[:n_train]
136	    val_idx = indices[n_train:n_train + n_val]
137	    test_idx = indices[n_train + n_val:]
138	
139	    train = [traces[i] for i in train_idx]
140	    val = [traces[i] for i in val_idx]
141	    test = [traces[i] for i in test_idx]
142	
143	    return train, val, test
144	
145	
146	def get_commitment_point_stats(traces: List[Dict]) -> Dict[str, Any]:
147	    """Compute statistics about commitment point distribution."""
148	    cps = [t["commitment_point"] for t in traces if t["commitment_point"] is not None]
149	    num_steps_list = [t["num_steps"] for t in traces if t["commitment_point"] is not None]
150	
151	    if not cps:
152	        return {"count": 0}
153	
154	    cps = np.array(cps)
155	    num_steps = np.array(num_steps_list)
156	    relative_positions = cps / num_steps
157	
158	    return {
159	        "count": len(cps),
160	        "mean": float(np.mean(cps)),
161	        "median": float(np.median(cps)),
162	        "std": float(np.std(cps)),
163	        "min": int(np.min(cps)),
164	        "max": int(np.max(cps)),
165	        "relative_position_mean": float(np.mean(relative_positions)),
166	        "relative_position_median": float(np.median(relative_positions)),
167	        "relative_position_std": float(np.std(relative_positions)),
168	    }
169	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "79f77721-cc16-4118-b326-19495cc8d6c9",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "eaf23e48-dced-4a7e-9448-293802dd0426",
  "sourceToolAssistantUUID": "79f77721-cc16-4118-b326-19495cc8d6c9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 14 · 2026-05-17T12:03:00.231Z_

<details open><summary>🔧 Tool call — Read · `toolu_013pej65qvkw3PqWiCjMu7bN`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/experiments/bootstrap_ci.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "eaf23e48-dced-4a7e-9448-293802dd0426",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CJ8fK8abS8fFr3orL",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "9ffa3dbd-3a30-4b8f-b964-c68017912ece",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01W4AhbULSHsY4cP8DrN9PPx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 471,
      "cache_read_input_tokens": 20298,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 471,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 3,
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

_source line 15 · 2026-05-17T12:03:00.280Z_

<details><summary>↩ Tool result · `toolu_013pej65qvkw3PqWiCjMu7bN`</summary>

```text
1	"""Bootstrap confidence intervals and paired significance tests (exp-006).
2	
3	Input: Pre-extracted hidden states + trained probe predictions on test set
4	Output: 95% CIs for all methods, paired bootstrap p-values
5	"""
6	
7	import json
8	import sys
9	from pathlib import Path
10	from typing import List, Dict, Optional, Tuple
11	
12	import numpy as np
13	import torch
14	import torch.nn as nn
15	from torch.utils.data import DataLoader, TensorDataset
16	from sklearn.linear_model import LogisticRegression, SGDClassifier
17	
18	sys.path.insert(0, str(Path(__file__).resolve().parent.parent.parent))
19	from src.config import (
20	    LAYERS, HIDDEN_DIM, HIDDEN_STATES_DIR, SEED, ARTIFACTS_DIR
21	)
22	from src.data_loader import prepare_dataset, split_data
23	
24	
25	LAYER_14_IDX = 2  # LAYERS=[12,13,...,24], layer 14 is index 2
26	MULTI_LAYER_INDICES = [0, 2, 4, 6, 8, 10, 12]  # layers [12,14,16,18,20,22,24]
27	WINDOW_SIZE = 15
28	THRESHOLD = 0.5
29	CONSECUTIVE_K = 5
30	N_BOOTSTRAP = 1000
31	OUTPUT_DIR = ARTIFACTS_DIR / "exp_006_bootstrap"
32	
33	
34	# ============================================================
35	# GRU Model
36	# ============================================================
37	
38	class GRUProbe(nn.Module):
39	    def __init__(self, input_dim=HIDDEN_DIM, hidden_dim=256, dropout=0.3):
40	        super().__init__()
41	        self.gru = nn.GRU(input_dim, hidden_dim, num_layers=1, batch_first=True, dropout=0)
42	        self.dropout = nn.Dropout(dropout)
43	        self.fc = nn.Linear(hidden_dim, 1)
44	
45	    def forward(self, x):
46	        # x: [batch, T, input_dim]
47	        out, _ = self.gru(x)  # [batch, T, hidden_dim]
48	        out = self.dropout(out)
49	        logits = self.fc(out).squeeze(-1)  # [batch, T]
50	        return logits
51	
52	
53	# ============================================================
54	# Data helpers
55	# ============================================================
56	
57	def load_trace_hidden_states(trace_id: str, layer_idx: int) -> Optional[torch.Tensor]:
58	    pt_path = HIDDEN_STATES_DIR / f"{trace_id}.pt"
59	    if not pt_path.exists():
60	        return None
61	    data = torch.load(pt_path, map_location="cpu", weights_only=False)
62	    return data["hidden_states"][:, layer_idx, :]  # [T, 4096]
63	
64	
65	def load_trace_multi_layer(trace_id: str) -> Optional[torch.Tensor]:
66	    pt_path = HIDDEN_STATES_DIR / f"{trace_id}.pt"
67	    if not pt_path.exists():
68	        return None
69	    data = torch.load(pt_path, map_location="cpu", weights_only=False)
70	    hs = data["hidden_states"][:, MULTI_LAYER_INDICES, :]  # [T, 7, 4096]
71	    return hs.mean(dim=1)  # [T, 4096]
72	
73	
74	# ============================================================
75	# Method 1: Static LR
76	# ============================================================
77	
78	def train_static_lr(train_traces: List[Dict]) -> LogisticRegression:
79	    X_list, y_list = [], []
80	    for t in train_traces:
81	        hs = load_trace_hidden_states(t["trace_id"], LAYER_14_IDX)
82	        if hs is None:
83	            continue
84	        n = min(hs.shape[0], len(t["step_labels"]))
85	        X_list.append(hs[:n].numpy())
86	        y_list.append(np.array(t["step_labels"][:n]))
87	    X = np.concatenate(X_list)
88	    y = np.concatenate(y_list)
89	    clf = LogisticRegression(max_iter=1000, random_state=SEED, C=1.0, class_weight="balanced")
90	    clf.fit(X, y)
91	    print(f"  Static LR train acc: {clf.score(X, y):.4f} ({len(X)} samples)")
92	    return clf
93	
94	
95	def predict_static_lr(clf: LogisticRegression, traces: List[Dict]) -> List[Dict]:
96	    results = []
97	    for t in traces:
98	        hs = load_trace_hidden_states(t["trace_id"], LAYER_14_IDX)
99	        if hs is None:
100	            continue
101	        n = min(hs.shape[0], len(t["step_labels"]))
102	        probs = clf.predict_proba(hs[:n].numpy())[:, 1]
103	        results.append({
104	            "trace_id": t["trace_id"],
105	            "probs": probs,
106	            "labels": np.array(t["step_labels"][:n]),
107	            "commitment_point": t["commitment_point"],
108	        })
109	    return results
110	
111	
112	# ============================================================
113	# Method 2: Temporal LR (W=15)
114	# ============================================================
115	
116	def create_causal_windows(hs: np.ndarray, window_size: int = WINDOW_SIZE) -> np.ndarray:
117	    """Causal sliding window: step i uses [i-W+1, ..., i], zero-pad left."""
118	    T, D = hs.shape
119	    padded = np.zeros((window_size - 1 + T, D), dtype=hs.dtype)
120	    padded[window_size - 1:] = hs
121	    windows = np.zeros((T, window_size * D), dtype=hs.dtype)
122	    for i in range(T):
123	        windows[i] = padded[i:i + window_size].reshape(-1)
124	    return windows
125	
126	
127	def train_temporal_lr(train_traces: List[Dict]):
128	    X_list, y_list = [], []
129	    for t in train_traces:
130	        hs = load_trace_hidden_states(t["trace_id"], LAYER_14_IDX)
131	        if hs is None:
132	            continue
133	        n = min(hs.shape[0], len(t["step_labels"]))
134	        windows = create_causal_windows(hs[:n].numpy().astype(np.float32))
135	        X_list.append(windows)
136	        y_list.append(np.array(t["step_labels"][:n]))
137	    X = np.concatenate(X_list)
138	    y = np.concatenate(y_list)
139	    clf = SGDClassifier(loss="log_loss", alpha=1e-4, max_iter=100,
140	                        random_state=SEED, class_weight="balanced", tol=1e-3)
141	    clf.fit(X, y)
142	    print(f"  Temporal LR W=15 train acc: {clf.score(X, y):.4f} ({len(X)} samples)")
143	    return clf
144	
145	
146	def predict_temporal_lr(clf, traces: List[Dict]) -> List[Dict]:
147	    results = []
148	    for t in traces:
149	        hs = load_trace_hidden_states(t["trace_id"], LAYER_14_IDX)
150	        if hs is None:
151	            continue
152	        n = min(hs.shape[0], len(t["step_labels"]))
153	        windows = create_causal_windows(hs[:n].numpy().astype(np.float32))
154	        probs = clf.predict_proba(windows)[:, 1]
155	        results.append({
156	            "trace_id": t["trace_id"],
157	            "probs": probs,
158	            "labels": np.array(t["step_labels"][:n]),
159	            "commitment_point": t["commitment_point"],
160	        })
161	    return results
162	
163	
164	# ============================================================
165	# Method 3 & 4: GRU training
166	# ============================================================
167	
168	def train_gru(train_traces: List[Dict], val_traces: List[Dict],
169	              multi_layer: bool = False) -> GRUProbe:
170	    device = "cuda" if torch.cuda.is_available() else "cpu"
171	    load_fn = load_trace_multi_layer if multi_layer else (
172	        lambda tid: load_trace_hidden_states(tid, LAYER_14_IDX)
173	    )
174	
175	    def collect(traces):
176	        seqs, labels_list = [], []
177	        for t in traces:
178	            hs = load_fn(t["trace_id"])
179	            if hs is None:
180	                continue
181	            n = min(hs.shape[0], len(t["step_labels"]))
182	            seqs.append(hs[:n].float().to(device))
183	            labels_list.append(torch.tensor(t["step_labels"][:n], dtype=torch.float32).to(device))
184	        return seqs, labels_list
185	
186	    train_seqs, train_labels = collect(train_traces)
187	    val_seqs, val_labels = collect(val_traces)
188	
189	    model = GRUProbe(input_dim=HIDDEN_DIM, hidden_dim=256, dropout=0.3).to(device)
190	    optimizer = torch.optim.Adam(model.parameters(), lr=1e-3)
191	    criterion = nn.BCEWithLogitsLoss()
192	
193	    best_val_loss = float("inf")
194	    patience_counter = 0
195	    best_state = None
196	
197	    for epoch in range(20):
198	        model.train()
199	        epoch_loss = 0
200	        for seq, lab in zip(train_seqs, train_labels):
201	            logits = model(seq.unsqueeze(0))  # [1, T]
202	            loss = criterion(logits[0], lab)
203	            optimizer.zero_grad()
204	            loss.backward()
205	            optimizer.step()
206	            epoch_loss += loss.item()
207	
208	        model.eval()
209	        val_loss = 0
210	        with torch.no_grad():
211	            for seq, lab in zip(val_seqs, val_labels):
212	                logits = model(seq.unsqueeze(0))
213	                val_loss += criterion(logits[0], lab).item()
214	
215	        val_loss /= max(len(val_seqs), 1)
216	
217	        if val_loss < best_val_loss:
218	            best_val_loss = val_loss
219	            patience_counter = 0
220	            best_state = {k: v.clone() for k, v in model.state_dict().items()}
221	        else:
222	            patience_counter += 1
223	            if patience_counter >= 5:
224	                break
225	
226	    if best_state:
227	        model.load_state_dict(best_state)
228	    model = model.cpu()
229	    name = "GRU multi-7L" if multi_layer else "GRU single L14"
230	    print(f"  {name} trained {epoch+1} epochs, best val_loss={best_val_loss:.4f}")
231	    return model
232	
233	
234	def predict_gru(model: GRUProbe, traces: List[Dict],
235	                multi_layer: bool = False) -> List[Dict]:
236	    load_fn = load_trace_multi_layer if multi_layer else (
237	        lambda tid: load_trace_hidden_states(tid, LAYER_14_IDX)
238	    )
239	    model.eval()
240	    results = []
241	    for t in traces:
242	        hs = load_fn(t["trace_id"])
243	        if hs is None:
244	            continue
245	        n = min(hs.shape[0], len(t["step_labels"]))
246	        with torch.no_grad():
247	            logits = model(hs[:n].float().unsqueeze(0))  # [1, T]
248	            probs = torch.sigmoid(logits[0]).numpy()
249	        results.append({
250	            "trace_id": t["trace_id"],
251	            "probs": probs,
252	            "labels": np.array(t["step_labels"][:n]),
253	            "commitment_point": t["commitment_point"],
254	        })
255	    return results
256	
257	
258	# ============================================================
259	# Evaluation per trace
260	# ============================================================
261	
262	def first_crossing_point(probs: np.ndarray, threshold: float = THRESHOLD,
263	                         consecutive_k: int = CONSECUTIVE_K) -> Optional[int]:
264	    n = len(probs)
265	    if n < consecutive_k:
266	        return None
267	    for i in range(n - consecutive_k + 1):
268	        if all(probs[i:i + consecutive_k] > threshold):
269	            return i
270	    return None
271	
272	
273	def compute_trace_metrics(pred: Dict) -> Dict:
274	    probs = pred["probs"]
275	    labels = pred["labels"]
276	    cp = pred["commitment_point"]
277	
278	    preds_binary = (probs > 0.5).astype(int)
279	    step_acc = float((preds_binary == labels).mean())
280	
281	    fcp = first_crossing_point(probs)
282	    crossing_detected = 1 if fcp is not None else 0
283	    lead_time = (cp - fcp) if fcp is not None else None
284	
285	    return {
286	        "step_accuracy": step_acc,
287	        "crossing_detected": crossing_detected,
288	        "lead_time": lead_time,
289	    }
290	
291	
292	# ============================================================
293	# Bootstrap
294	# ============================================================
295	
296	def bootstrap_ci(per_trace_metrics: List[Dict], n_bootstrap: int = N_BOOTSTRAP,
297	                 seed: int = SEED) -> Dict:
298	    rng = np.random.default_rng(seed)
299	    n = len(per_trace_metrics)
300	
301	    accs = np.array([m["step_accuracy"] for m in per_trace_metrics])
302	    crossings = np.array([m["crossing_detected"] for m in per_trace_metrics])
303	    lead_times = np.array([m["lead_time"] if m["lead_time"] is not None else np.nan
304	                           for m in per_trace_metrics])
305	
306	    boot_accs = np.zeros(n_bootstrap)
307	    boot_crossings = np.zeros(n_bootstrap)
308	    boot_leads = np.zeros(n_bootstrap)
309	
310	    for b in range(n_bootstrap):
311	        idx = rng.choice(n, size=n, replace=True)
312	        boot_accs[b] = accs[idx].mean()
313	        boot_crossings[b] = crossings[idx].mean()
314	        sampled_leads = lead_times[idx]
315	        valid = sampled_leads[~np.isnan(sampled_leads)]
316	        boot_leads[b] = valid.mean() if len(valid) > 0 else np.nan
317	
318	    def ci(arr):
319	        arr_valid = arr[~np.isnan(arr)]
320	        if len(arr_valid) == 0:
321	            return {"mean": None, "ci_lower": None, "ci_upper": None}
322	        return {
323	            "mean": float(np.mean(arr_valid)),
324	            "ci_lower": float(np.percentile(arr_valid, 2.5)),
325	            "ci_upper": float(np.percentile(arr_valid, 97.5)),
326	        }
327	
328	    return {
329	        "step_accuracy": ci(boot_accs),
330	        "crossing_rate": ci(boot_crossings),
331	        "lead_time_mean": ci(boot_leads),
332	    }
333	
334	
335	def paired_bootstrap_test(metrics_a: List[Dict], metrics_b: List[Dict],
336	                          metric_key: str, n_bootstrap: int = N_BOOTSTRAP,
337	                          seed: int = SEED) -> Dict:
338	    """Test H0: metric_A <= metric_B. p_value = P(delta <= 0)."""
339	    rng = np.random.default_rng(seed + 7)
340	    n = len(metrics_a)
341	    assert len(metrics_b) == n
342	
343	    if metric_key == "crossing_detected":
344	        vals_a = np.array([m["crossing_detected"] for m in metrics_a], dtype=float)
345	        vals_b = np.array([m["crossing_detected"] for m in metrics_b], dtype=float)
346	    elif metric_key == "lead_time":
347	        vals_a = np.array([m["lead_time"] if m["lead_time"] is not None else np.nan
348	                           for m in metrics_a])
349	        vals_b = np.array([m["lead_time"] if m["lead_time"] is not None else np.nan
350	                           for m in metrics_b])
351	    else:
352	        vals_a = np.array([m[metric_key] for m in metrics_a], dtype=float)
353	        vals_b = np.array([m[metric_key] for m in metrics_b], dtype=float)
354	
355	    deltas = np.zeros(n_bootstrap)
356	    for b in range(n_bootstrap):
357	        idx = rng.choice(n, size=n, replace=True)
358	        a_sample = vals_a[idx]
359	        b_sample = vals_b[idx]
360	        if metric_key == "lead_time":
361	            valid_a = a_sample[~np.isnan(a_sample)]
362	            valid_b = b_sample[~np.isnan(b_sample)]
363	            mean_a = valid_a.mean() if len(valid_a) > 0 else 0
364	            mean_b = valid_b.mean() if len(valid_b) > 0 else 0
365	        else:
366	            mean_a = a_sample.mean()
367	            mean_b = b_sample.mean()
368	        deltas[b] = mean_a - mean_b
369	
370	    p_value = float((deltas <= 0).mean())
371	    return {
372	        "delta_mean": float(np.mean(deltas)),
373	        "ci_lower": float(np.percentile(deltas, 2.5)),
374	        "ci_upper": float(np.percentile(deltas, 97.5)),
375	        "p_value": p_value,
376	    }
377	
378	
379	# ============================================================
380	# Main
381	# ============================================================
382	
383	def main(n_bootstrap: int = N_BOOTSTRAP):
384	    print("=" * 60)
385	    print("EXP-006: Bootstrap CIs + Paired Significance Tests")
386	    print("=" * 60)
387	
388	    # Load and split data
389	    print("\n[1/5] Loading data...")
390	    dataset = prepare_dataset()
391	    traces = dataset["jailbreak_with_commitment"]
392	    train, val, test = split_data(traces)
393	    print(f"  Traces: train={len(train)}, val={len(val)}, test={len(test)}")
394	
395	    # Train all methods
396	    print("\n[2/5] Training methods...")
397	
398	    print("  --- Static LR (Layer 14) ---")
399	    static_lr = train_static_lr(train)
400	
401	    print("  --- Temporal LR W=15 (Layer 14) ---")
402	    temporal_lr = train_temporal_lr(train)
403	
404	    print("  --- GRU single Layer 14 ---")
405	    gru_single = train_gru(train, val, multi_layer=False)
406	
407	    print("  --- GRU multi-7L ---")
408	    gru_multi = train_gru(train, val, multi_layer=True)
409	
410	    # Predict on test set
411	    print("\n[3/5] Predicting on test set...")
412	    preds = {
413	        "static_lr": predict_static_lr(static_lr, test),
414	        "temporal_lr_w15": predict_temporal_lr(temporal_lr, test),
415	        "gru_single_l14": predict_gru(gru_single, test, multi_layer=False),
416	        "gru_multi_7l": predict_gru(gru_multi, test, multi_layer=True),
417	    }
418	
419	    # Compute per-trace metrics
420	    print("\n[4/5] Computing per-trace metrics...")
421	    per_trace = {}
422	    for method_name, pred_list in preds.items():
423	        per_trace[method_name] = [compute_trace_metrics(p) for p in pred_list]
424	        n_crossing = sum(m["crossing_detected"] for m in per_trace[method_name])
425	        leads = [m["lead_time"] for m in per_trace[method_name] if m["lead_time"] is not None]
426	        mean_lead = np.mean(leads) if leads else float("nan")
427	        print(f"  {method_name}: {len(pred_list)} traces, "
428	              f"crossing={n_crossing}/{len(pred_list)} ({n_crossing/len(pred_list)*100:.1f}%), "
429	              f"mean_lead={mean_lead:.1f}")
430	
431	    # Bootstrap
432	    print(f"\n[5/5] Bootstrap (B={n_bootstrap})...")
433	    results = {
434	        "n_bootstrap": n_bootstrap,
435	        "n_test_traces": len(test),
436	        "seed": SEED,
437	        "threshold": THRESHOLD,
438	        "consecutive_k": CONSECUTIVE_K,
439	        "methods": {},
440	        "paired_tests": {},
441	    }
442	
443	    for method_name, metrics in per_trace.items():
444	        results["methods"][method_name] = bootstrap_ci(metrics, n_bootstrap)
445	
446	    # Paired tests
447	    pairs = [
448	        ("temporal_lr_w15", "static_lr", "temporal_lr_vs_static_lr"),
449	        ("gru_multi_7l", "static_lr", "gru_multi_vs_static_lr"),
450	        ("gru_multi_7l", "temporal_lr_w15", "gru_multi_vs_temporal_lr"),
451	    ]
452	
453	    for method_a, method_b, pair_name in pairs:
454	        results["paired_tests"][pair_name] = {
455	            "crossing_rate": paired_bootstrap_test(
456	                per_trace[method_a], per_trace[method_b], "crossing_detected", n_bootstrap),
457	            "lead_time": paired_bootstrap_test(
458	                per_trace[method_a], per_trace[method_b], "lead_time", n_bootstrap),
459	        }
460	
461	    # Save
462	    OUTPUT_DIR.mkdir(parents=True, exist_ok=True)
463	    out_path = OUTPUT_DIR / "bootstrap_results.json"
464	    with open(out_path, "w") as f:
465	        json.dump(results, f, indent=2)
466	    print(f"\nResults saved to {out_path}")
467	
468	    # Print summary table
469	    print("\n" + "=" * 70)
470	    print(f"{'Method':<20} {'Accuracy':<22} {'Crossing Rate':<22} {'Lead Time':<22}")
471	    print("-" * 70)
472	    for method_name, cis in results["methods"].items():
473	        acc = cis["step_accuracy"]
474	        cr = cis["crossing_rate"]
475	        lt = cis["lead_time_mean"]
476	        acc_str = f"{acc['mean']:.3f} [{acc['ci_lower']:.3f}, {acc['ci_upper']:.3f}]" if acc["mean"] else "N/A"
477	        cr_str = f"{cr['mean']:.3f} [{cr['ci_lower']:.3f}, {cr['ci_upper']:.3f}]" if cr["mean"] else "N/A"
478	        lt_str = f"{lt['mean']:+.1f} [{lt['ci_lower']:+.1f}, {lt['ci_upper']:+.1f}]" if lt["mean"] else "N/A"
479	        print(f"{method_name:<20} {acc_str:<22} {cr_str:<22} {lt_str:<22}")
480	
481	    print("\n" + "=" * 70)
482	    print("Paired Bootstrap Tests (A vs B, p-value = P(delta_A-B <= 0))")
483	    print("-" * 70)
484	    for pair_name, tests in results["paired_tests"].items():
485	        cr_test = tests["crossing_rate"]
486	        lt_test = tests["lead_time"]
487	        print(f"\n  {pair_name}:")
488	        print(f"    crossing_rate: delta={cr_test['delta_mean']:+.3f} "
489	              f"[{cr_test['ci_lower']:+.3f}, {cr_test['ci_upper']:+.3f}], p={cr_test['p_value']:.3f}")
490	        if lt_test["delta_mean"] is not None:
491	            print(f"    lead_time:     delta={lt_test['delta_mean']:+.1f} "
492	                  f"[{lt_test['ci_lower']:+.1f}, {lt_test['ci_upper']:+.1f}], p={lt_test['p_value']:.3f}")
493	
494	    print("\n" + "=" * 70)
495	    return results
496	
497	
498	if __name__ == "__main__":
499	    import argparse
500	    parser = argparse.ArgumentParser()
501	    parser.add_argument("--n_bootstrap", type=int, default=N_BOOTSTRAP)
502	    parser.add_argument("--dry_run", action="store_true", help="Quick run with B=10")
503	    args = parser.parse_args()
504	
505	    if args.dry_run:
506	        main(n_bootstrap=10)
507	    else:
508	        main(n_bootstrap=args.n_bootstrap)
509	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9ffa3dbd-3a30-4b8f-b964-c68017912ece",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "1be9c443-fc78-4a11-9a32-be3a078ae0bf",
  "sourceToolAssistantUUID": "9ffa3dbd-3a30-4b8f-b964-c68017912ece",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 16 · 2026-05-17T12:03:00.360Z_

<details open><summary>🔧 Tool call — Read · `toolu_01EwHB2YRbucvKJxnXCw9b7R`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/experiments/fpr_analysis.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1be9c443-fc78-4a11-9a32-be3a078ae0bf",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CJ8fK8abS8fFr3orL",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "84567651-b9f0-4c0a-b794-bd64269d6dd7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01W4AhbULSHsY4cP8DrN9PPx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 471,
      "cache_read_input_tokens": 20298,
      "output_tokens": 257,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 471
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 5,
          "output_tokens": 257,
          "cache_read_input_tokens": 20298,
          "cache_creation_input_tokens": 471,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 471,
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

_source line 17 · 2026-05-17T12:03:00.378Z_

<details><summary>↩ Tool result · `toolu_01EwHB2YRbucvKJxnXCw9b7R`</summary>

```text
1	"""exp-015: FPR analysis — determine if text baseline's high lead time comes from false positives."""
2	
3	import sys
4	import json
5	import warnings
6	from pathlib import Path
7	
8	import numpy as np
9	import torch
10	import torch.nn as nn
11	from sklearn.linear_model import LogisticRegression
12	
13	sys.path.insert(0, '/root/autodl-tmp/contrastive_trace_safety')
14	from src.data_loader import prepare_dataset, split_data
15	from src.config import TRAIN_RATIO, VAL_RATIO, SEED, DETECTION_WINDOW, LAYERS, HIDDEN_DIM
16	from src.eval.evaluate import first_crossing_point, detection_lead_time, step_accuracy
17	
18	warnings.filterwarnings("ignore")
19	
20	HS_DIR = Path("/root/autodl-tmp/contrastive_trace_safety/artifacts/hidden_states")
21	OUT_DIR = Path("/root/autodl-tmp/contrastive_trace_safety/artifacts/exp_015_fpr")
22	OUT_DIR.mkdir(parents=True, exist_ok=True)
23	
24	WINDOW = 15
25	LAYER_IDX = 2  # Layer 14 = LAYERS[2]
26	GRU_HIDDEN = 256
27	GRU_EPOCHS = 20
28	GRU_PATIENCE = 5
29	GRU_LR = 1e-3
30	MULTI_LAYER_INDICES = [0, 2, 4, 6, 8, 10, 12]  # layers 12,14,16,18,20,22,24
31	
32	
33	# ============================================================
34	# Feature builders
35	# ============================================================
36	
37	def build_text_static_features(trace, st_model):
38	    embs = trace["text_embeddings"]  # [T, 384]
39	    return embs
40	
41	def build_text_temporal_features(trace, st_model, window=WINDOW):
42	    embs = trace["text_embeddings"]  # [T, 384]
43	    T = len(embs)
44	    features = []
45	    for i in range(T):
46	        start = max(0, i - window + 1)
47	        window_embs = embs[start:i+1]
48	        if len(window_embs) < window:
49	            pad = np.zeros((window - len(window_embs), embs.shape[1]))
50	            window_embs = np.vstack([pad, window_embs])
51	        features.append(window_embs.flatten())
52	    return np.array(features)
53	
54	def load_hs(trace, layer_idx=LAYER_IDX):
55	    pt_path = HS_DIR / f"{trace['trace_id']}.pt"
56	    if not pt_path.exists():
57	        return None
58	    pt = torch.load(pt_path, map_location="cpu", weights_only=False)
59	    return pt["hidden_states"][:, layer_idx, :].numpy()
60	
61	def load_hs_multi7l(trace):
62	    pt_path = HS_DIR / f"{trace['trace_id']}.pt"
63	    if not pt_path.exists():
64	        return None
65	    pt = torch.load(pt_path, map_location="cpu", weights_only=False)
66	    hs = pt["hidden_states"][:, MULTI_LAYER_INDICES, :].mean(dim=1).numpy()
67	    return hs
68	
69	def build_hs_static_features(trace):
70	    return load_hs(trace)
71	
72	def build_hs_temporal_features(trace, window=WINDOW):
73	    hs = load_hs(trace)
74	    if hs is None:
75	        return None
76	    T = len(hs)
77	    features = []
78	    for i in range(T):
79	        start = max(0, i - window + 1)
80	        w = hs[start:i+1]
81	        if len(w) < window:
82	            pad = np.zeros((window - len(w), hs.shape[1]))
83	            w = np.vstack([pad, w])
84	        features.append(w.flatten())
85	    return np.array(features)
86	
87	
88	# ============================================================
89	# FPR metrics
90	# ============================================================
91	
92	def safe_trace_fpr(predict_fn, safe_traces, build_fn, **kwargs):
93	    total_steps = 0
94	    false_positives = 0
95	    n_evaluated = 0
96	    for t in safe_traces:
97	        features = build_fn(t, **kwargs)
98	        if features is None:
99	            continue
100	        probs = predict_fn(features)
101	        preds = (probs > 0.5).astype(int)
102	        total_steps += len(preds)
103	        false_positives += preds.sum()
104	        n_evaluated += 1
105	    fpr = false_positives / total_steps if total_steps > 0 else 0
106	    return fpr, n_evaluated
107	
108	def pre_commitment_fpr(predict_fn, test_traces, build_fn, **kwargs):
109	    total_pre = 0
110	    fp_pre = 0
111	    for t in test_traces:
112	        cp = t["commitment_point"]
113	        if cp is None or cp == 0:
114	            continue
115	        features = build_fn(t, **kwargs)
116	        if features is None:
117	            continue
118	        probs = predict_fn(features)
119	        preds = (probs > 0.5).astype(int)
120	        pre_preds = preds[:cp]
121	        total_pre += len(pre_preds)
122	        fp_pre += pre_preds.sum()
123	    return fp_pre / total_pre if total_pre > 0 else 0
124	
125	def compute_precision(predict_fn, test_traces, build_fn, **kwargs):
126	    tp = 0
127	    fp = 0
128	    for t in test_traces:
129	        cp = t["commitment_point"]
130	        if cp is None:
131	            continue
132	        features = build_fn(t, **kwargs)
133	        if features is None:
134	            continue
135	        probs = predict_fn(features)
136	        preds = (probs > 0.5).astype(int)
137	        labels = np.array(t["step_labels"])
138	        tp += int(((preds == 1) & (labels == 1)).sum())
139	        fp += int(((preds == 1) & (labels == 0)).sum())
140	    return tp / (tp + fp) if (tp + fp) > 0 else 0
141	
142	def compute_coverage_and_lead(predict_fn, test_traces, build_fn, **kwargs):
143	    leads = []
144	    n_crossing = 0
145	    n_valid = 0
146	    accs = []
147	    for t in test_traces:
148	        cp = t["commitment_point"]
149	        if cp is None:
150	            continue
151	        features = build_fn(t, **kwargs)
152	        if features is None:
153	            continue
154	        n_valid += 1
155	        probs = predict_fn(features)
156	        preds = (probs > 0.5).astype(int)
157	        labels = np.array(t["step_labels"])
158	        accs.append(step_accuracy(preds, labels))
159	        fcp = first_crossing_point(probs, threshold=0.5, consecutive_k=DETECTION_WINDOW)
160	        if fcp is not None:
161	            n_crossing += 1
162	            lead = detection_lead_time(fcp, cp)
163	            leads.append(lead)
164	    coverage = n_crossing / n_valid if n_valid > 0 else 0
165	    mean_lead = float(np.mean(leads)) if leads else None
166	    mean_acc = float(np.mean(accs)) if accs else None
167	    return coverage, mean_lead, mean_acc
168	
169	
170	# ============================================================
171	# GRU Probe
172	# ============================================================
173	
174	class GRUProbe(nn.Module):
175	    def __init__(self, input_dim=HIDDEN_DIM, hidden_dim=GRU_HIDDEN, dropout=0.3):
176	        super().__init__()
177	        self.gru = nn.GRU(input_dim, hidden_dim, num_layers=1, batch_first=True, dropout=0)
178	        self.dropout = nn.Dropout(dropout)
179	        self.fc = nn.Linear(hidden_dim, 1)
180	
181	    def forward(self, x):
182	        out, _ = self.gru(x)
183	        out = self.dropout(out)
184	        logits = self.fc(out).squeeze(-1)
185	        return logits
186	
187	
188	def train_gru(train_traces, val_traces):
189	    device = torch.device("cuda" if torch.cuda.is_available() else "cpu")
190	    model = GRUProbe().to(device)
191	    optimizer = torch.optim.Adam(model.parameters(), lr=GRU_LR)
192	
193	    # Compute pos_weight from training data
194	    n_pos = sum(sum(t["step_labels"]) for t in train_traces if t["step_labels"])
195	    n_neg = sum(len(t["step_labels"]) - sum(t["step_labels"]) for t in train_traces if t["step_labels"])
196	    pos_weight = torch.tensor([n_neg / max(n_pos, 1)], device=device)
197	    criterion = nn.BCEWithLogitsLoss(pos_weight=pos_weight)
198	
199	    # Load all training hidden states
200	    train_data = []
201	    for t in train_traces:
202	        hs = load_hs_multi7l(t)
203	        if hs is None:
204	            continue
205	        labels = np.array(t["step_labels"], dtype=np.float32)
206	        train_data.append((hs, labels))
207	
208	    val_data = []
209	    for t in val_traces:
210	        hs = load_hs_multi7l(t)
211	        if hs is None:
212	            continue
213	        labels = np.array(t["step_labels"], dtype=np.float32)
214	        val_data.append((hs, labels))
215	
216	    best_val_loss = float('inf')
217	    patience_counter = 0
218	    best_state = None
219	
220	    for epoch in range(GRU_EPOCHS):
221	        model.train()
222	        epoch_loss = 0
223	        np.random.shuffle(train_data)
224	        for hs, labels in train_data:
225	            x = torch.tensor(hs, dtype=torch.float32).unsqueeze(0).to(device)
226	            y = torch.tensor(labels, dtype=torch.float32).unsqueeze(0).to(device)
227	            optimizer.zero_grad()
228	            logits = model(x)
229	            loss = criterion(logits, y)
230	            loss.backward()
231	            optimizer.step()
232	            epoch_loss += loss.item()
233	
234	        # Validation
235	        model.eval()
236	        val_loss = 0
237	        with torch.no_grad():
238	            for hs, labels in val_data:
239	                x = torch.tensor(hs, dtype=torch.float32).unsqueeze(0).to(device)
240	                y = torch.tensor(labels, dtype=torch.float32).unsqueeze(0).to(device)
241	                logits = model(x)
242	                val_loss += criterion(logits, y).item()
243	
244	        val_loss /= max(len(val_data), 1)
245	        if val_loss < best_val_loss:
246	            best_val_loss = val_loss
247	            patience_counter = 0
248	            best_state = {k: v.cpu().clone() for k, v in model.state_dict().items()}
249	        else:
250	            patience_counter += 1
251	            if patience_counter >= GRU_PATIENCE:
252	                break
253	
254	    model.load_state_dict(best_state)
255	    model.eval()
256	    return model
257	
258	
259	def gru_predict(model, trace):
260	    device = next(model.parameters()).device
261	    hs = load_hs_multi7l(trace)
262	    if hs is None:
263	        return None
264	    with torch.no_grad():
265	        x = torch.tensor(hs, dtype=torch.float32).unsqueeze(0).to(device)
266	        logits = model(x)
267	        probs = torch.sigmoid(logits).squeeze(0).cpu().numpy()
268	    return probs
269	
270	
271	# ============================================================
272	# Main
273	# ============================================================
274	
275	def main():
276	    print("Loading data...")
277	    data = prepare_dataset("r1-8b")
278	    jb_traces = data["jailbreak_with_commitment"]
279	    safe_traces = data["safe"]
280	    train_jb, val_jb, test_jb = split_data(jb_traces, TRAIN_RATIO, VAL_RATIO, SEED)
281	    print(f"Train: {len(train_jb)}, Val: {len(val_jb)}, Test: {len(test_jb)}, Safe: {len(safe_traces)}")
282	
283	    # Embed all text
284	    print("Loading sentence-transformers...")
285	    from sentence_transformers import SentenceTransformer
286	    st_model = SentenceTransformer('all-MiniLM-L6-v2')
287	
288	    print("Embedding text...")
289	    all_traces = train_jb + val_jb + test_jb + safe_traces
290	    for t in all_traces:
291	        t["text_embeddings"] = st_model.encode(t["sentences"], batch_size=64, show_progress_bar=False)
292	
293	    # Check safe traces HS availability
294	    safe_with_hs = [t for t in safe_traces if (HS_DIR / f"{t['trace_id']}.pt").exists()]
295	    print(f"Safe traces with hidden states: {len(safe_with_hs)}/{len(safe_traces)}")
296	
297	    results = {}
298	
299	    # ============================================================
300	    # Method 1: text_static — LR on single-step embedding [384]
301	    # ============================================================
302	    print("\n--- Method 1: text_static ---")
303	    X_train, y_train = [], []
304	    for t in train_jb:
305	        embs = t["text_embeddings"]
306	        labels = t["step_labels"]
307	        X_train.append(embs)
308	        y_train.extend(labels)
309	    X_train = np.vstack(X_train)
310	    y_train = np.array(y_train)
311	
312	    lr_text_static = LogisticRegression(C=1.0, class_weight='balanced', max_iter=1000, solver='lbfgs')
313	    lr_text_static.fit(X_train, y_train)
314	
315	    def predict_text_static(features):
316	        return lr_text_static.predict_proba(features)[:, 1]
317	
318	    fpr1, n_eval = safe_trace_fpr(predict_text_static, safe_traces, lambda t, **kw: build_text_static_features(t, st_model))
319	    fpr2 = pre_commitment_fpr(predict_text_static, test_jb, lambda t, **kw: build_text_static_features(t, st_model))
320	    prec = compute_precision(predict_text_static, test_jb, lambda t, **kw: build_text_static_features(t, st_model))
321	    cov, lead, acc = compute_coverage_and_lead(predict_text_static, test_jb, lambda t, **kw: build_text_static_features(t, st_model))
322	    results["text_static"] = {"safe_fpr": fpr1, "pre_commitment_fpr": fpr2, "precision": prec,
323	                              "coverage": cov, "lead_time_mean": lead, "step_accuracy": acc, "n_safe_evaluated": n_eval}
324	    print(f"  Safe FPR: {fpr1:.4f} ({n_eval} traces), Pre-CP FPR: {fpr2:.4f}, Precision: {prec:.4f}")
325	
326	    # ============================================================
327	    # Method 2: text_temporal W=15 — LR on windowed embedding [5760]
328	    # ============================================================
329	    print("\n--- Method 2: text_temporal W=15 ---")
330	    X_train_t, y_train_t = [], []
331	    for t in train_jb:
332	        feats = build_text_temporal_features(t, st_model, window=WINDOW)
333	        X_train_t.append(feats)
334	        y_train_t.extend(t["step_labels"])
335	    X_train_t = np.vstack(X_train_t)
336	    y_train_t = np.array(y_train_t)
337	
338	    lr_text_temporal = LogisticRegression(C=1.0, class_weight='balanced', max_iter=1000, solver='lbfgs')
339	    lr_text_temporal.fit(X_train_t, y_train_t)
340	
341	    def predict_text_temporal(features):
342	        return lr_text_temporal.predict_proba(features)[:, 1]
343	
344	    fpr1, n_eval = safe_trace_fpr(predict_text_temporal, safe_traces, lambda t, **kw: build_text_temporal_features(t, st_model, window=WINDOW))
345	    fpr2 = pre_commitment_fpr(predict_text_temporal, test_jb, lambda t, **kw: build_text_temporal_features(t, st_model, window=WINDOW))
346	    prec = compute_precision(predict_text_temporal, test_jb, lambda t, **kw: build_text_temporal_features(t, st_model, window=WINDOW))
347	    cov, lead, acc = compute_coverage_and_lead(predict_text_temporal, test_jb, lambda t, **kw: build_text_temporal_features(t, st_model, window=WINDOW))
348	    results["text_temporal_w15"] = {"safe_fpr": fpr1, "pre_commitment_fpr": fpr2, "precision": prec,
349	                                    "coverage": cov, "lead_time_mean": lead, "step_accuracy": acc, "n_safe_evaluated": n_eval}
350	    print(f"  Safe FPR: {fpr1:.4f} ({n_eval} traces), Pre-CP FPR: {fpr2:.4f}, Precision: {prec:.4f}")
351	
352	    # ============================================================
353	    # Method 3: HS_static LR L14
354	    # ============================================================
355	    print("\n--- Method 3: HS_static LR L14 ---")
356	    X_train_hs, y_train_hs = [], []
357	    for t in train_jb:
358	        hs = load_hs(t)
359	        if hs is None:
360	            continue
361	        X_train_hs.append(hs)
362	        y_train_hs.extend(t["step_labels"])
363	    X_train_hs = np.vstack(X_train_hs)
364	    y_train_hs = np.array(y_train_hs)
365	
366	    lr_hs_static = LogisticRegression(C=1.0, class_weight='balanced', max_iter=1000, solver='lbfgs')
367	    lr_hs_static.fit(X_train_hs, y_train_hs)
368	
369	    def predict_hs_static(features):
370	        return lr_hs_static.predict_proba(features)[:, 1]
371	
372	    fpr1, n_eval = safe_trace_fpr(predict_hs_static, safe_traces, lambda t, **kw: build_hs_static_features(t))
373	    fpr2 = pre_commitment_fpr(predict_hs_static, test_jb, lambda t, **kw: build_hs_static_features(t))
374	    prec = compute_precision(predict_hs_static, test_jb, lambda t, **kw: build_hs_static_features(t))
375	    cov, lead, acc = compute_coverage_and_lead(predict_hs_static, test_jb, lambda t, **kw: build_hs_static_features(t))
376	    results["hs_static_lr_l14"] = {"safe_fpr": fpr1, "pre_commitment_fpr": fpr2, "precision": prec,
377	                                   "coverage": cov, "lead_time_mean": lead, "step_accuracy": acc, "n_safe_evaluated": n_eval}
378	    print(f"  Safe FPR: {fpr1:.4f} ({n_eval} traces), Pre-CP FPR: {fpr2:.4f}, Precision: {prec:.4f}")
379	
380	    # ============================================================
381	    # Method 4: HS_temporal LR W=15 L14
382	    # ============================================================
383	    print("\n--- Method 4: HS_temporal LR W=15 L14 ---")
384	    X_train_hst, y_train_hst = [], []
385	    for t in train_jb:
386	        feats = build_hs_temporal_features(t, window=WINDOW)
387	        if feats is None:
388	            continue
389	        X_train_hst.append(feats)
390	        y_train_hst.extend(t["step_labels"])
391	    X_train_hst = np.vstack(X_train_hst)
392	    y_train_hst = np.array(y_train_hst)
393	
394	    lr_hs_temporal = LogisticRegression(C=1.0, class_weight='balanced', max_iter=1000, solver='lbfgs')
395	    lr_hs_temporal.fit(X_train_hst, y_train_hst)
396	
397	    def predict_hs_temporal(features):
398	        return lr_hs_temporal.predict_proba(features)[:, 1]
399	
400	    fpr1, n_eval = safe_trace_fpr(predict_hs_temporal, safe_traces, lambda t, **kw: build_hs_temporal_features(t, window=WINDOW))
401	    fpr2 = pre_commitment_fpr(predict_hs_temporal, test_jb, lambda t, **kw: build_hs_temporal_features(t, window=WINDOW))
402	    prec = compute_precision(predict_hs_temporal, test_jb, lambda t, **kw: build_hs_temporal_features(t, window=WINDOW))
403	    cov, lead, acc = compute_coverage_and_lead(predict_hs_temporal, test_jb, lambda t, **kw: build_hs_temporal_features(t, window=WINDOW))
404	    results["hs_temporal_lr_w15_l14"] = {"safe_fpr": fpr1, "pre_commitment_fpr": fpr2, "precision": prec,
405	                                         "coverage": cov, "lead_time_mean": lead, "step_accuracy": acc, "n_safe_evaluated": n_eval}
406	    print(f"  Safe FPR: {fpr1:.4f} ({n_eval} traces), Pre-CP FPR: {fpr2:.4f}, Precision: {prec:.4f}")
407	
408	    # ============================================================
409	    # Method 5: GRU multi-7L h=256
410	    # ============================================================
411	    print("\n--- Method 5: GRU multi-7L h=256 ---")
412	    print("  Training GRU...")
413	    gru_model = train_gru(train_jb, val_jb)
414	
415	    def predict_gru(features_trace):
416	        # features_trace is actually the trace dict for GRU
417	        return features_trace
418	
419	    # GRU needs special handling since it takes raw traces
420	    def gru_safe_fpr(safe_traces):
421	        total_steps = 0
422	        false_positives = 0
423	        n_evaluated = 0
424	        for t in safe_traces:
425	            probs = gru_predict(gru_model, t)
426	            if probs is None:
427	                continue
428	            preds = (probs > 0.5).astype(int)
429	            total_steps += len(preds)
430	            false_positives += preds.sum()
431	            n_evaluated += 1
432	        return (false_positives / total_steps if total_steps > 0 else 0), n_evaluated
433	
434	    def gru_pre_commitment_fpr(test_traces):
435	        total_pre = 0
436	        fp_pre = 0
437	        for t in test_traces:
438	            cp = t["commitment_point"]
439	            if cp is None or cp == 0:
440	                continue
441	            probs = gru_predict(gru_model, t)
442	            if probs is None:
443	                continue
444	            preds = (probs > 0.5).astype(int)
445	            pre_preds = preds[:cp]
446	            total_pre += len(pre_preds)
447	            fp_pre += pre_preds.sum()
448	        return fp_pre / total_pre if total_pre > 0 else 0
449	
450	    def gru_precision(test_traces):
451	        tp = 0
452	        fp = 0
453	        for t in test_traces:
454	            cp = t["commitment_point"]
455	            if cp is None:
456	                continue
457	            probs = gru_predict(gru_model, t)
458	            if probs is None:
459	                continue
460	            preds = (probs > 0.5).astype(int)
461	            labels = np.array(t["step_labels"])
462	            tp += int(((preds == 1) & (labels == 1)).sum())
463	            fp += int(((preds == 1) & (labels == 0)).sum())
464	        return tp / (tp + fp) if (tp + fp) > 0 else 0
465	
466	    def gru_coverage_lead(test_traces):
467	        leads = []
468	        n_crossing = 0
469	        n_valid = 0
470	        accs = []
471	        for t in test_traces:
472	            cp = t["commitment_point"]
473	            if cp is None:
474	                continue
475	            probs = gru_predict(gru_model, t)
476	            if probs is None:
477	                continue
478	            n_valid += 1
479	            preds = (probs > 0.5).astype(int)
480	            labels = np.array(t["step_labels"])
481	            accs.append(step_accuracy(preds, labels))
482	            fcp = first_crossing_point(probs, threshold=0.5, consecutive_k=DETECTION_WINDOW)
483	            if fcp is not None:
484	                n_crossing += 1
485	                lead = detection_lead_time(fcp, cp)
486	                leads.append(lead)
487	        coverage = n_crossing / n_valid if n_valid > 0 else 0
488	        mean_lead = float(np.mean(leads)) if leads else None
489	        mean_acc = float(np.mean(accs)) if accs else None
490	        return coverage, mean_lead, mean_acc
491	
492	    fpr1, n_eval = gru_safe_fpr(safe_traces)
493	    fpr2 = gru_pre_commitment_fpr(test_jb)
494	    prec = gru_precision(test_jb)
495	    cov, lead, acc = gru_coverage_lead(test_jb)
496	    results["gru_multi7l_h256"] = {"safe_fpr": fpr1, "pre_commitment_fpr": fpr2, "precision": prec,
497	                                   "coverage": cov, "lead_time_mean": lead, "step_accuracy": acc, "n_safe_evaluated": n_eval}
498	    print(f"  Safe FPR: {fpr1:.4f} ({n_eval} traces), Pre-CP FPR: {fpr2:.4f}, Precision: {prec:.4f}")
499	
500	    # ============================================================
501	    # Summary table
502	    # ============================================================
503	    print("\n" + "="*100)
504	    print(f"{'Method':<22} {'Safe FPR':>10} {'Pre-CP FPR':>12} {'Precision':>10} {'Coverage':>10} {'Lead Time':>10} {'Step Acc':>10}")
505	    print("-"*100)
506	    method_names = {
507	        "text_static": "text_static",
508	        "text_temporal_w15": "text_temporal W=15",
509	        "hs_static_lr_l14": "HS_static LR L14",
510	        "hs_temporal_lr_w15_l14": "HS_temporal LR W=15",
511	        "gru_multi7l_h256": "GRU multi-7L h=256",
512	    }
513	    for key, name in method_names.items():
514	        r = results[key]
515	        lead_str = f"{r['lead_time_mean']:+.1f}" if r['lead_time_mean'] is not None else "N/A"
516	        print(f"{name:<22} {r['safe_fpr']:>10.4f} {r['pre_commitment_fpr']:>12.4f} {r['precision']:>10.4f} "
517	              f"{r['coverage']:>9.1%} {lead_str:>10} {r['step_accuracy']:>10.4f}")
518	    print("="*100)
519	
520	    # Save results
521	    output = {
522	        "methods": results,
523	        "n_safe_traces": len(safe_traces),
524	        "n_test_jb_traces": len(test_jb),
525	        "n_safe_with_hs": len(safe_with_hs),
526	    }
527	    with open(OUT_DIR / "fpr_results.json", "w") as f:
528	        json.dump(output, f, indent=2, default=lambda x: float(x) if isinstance(x, (np.floating, np.integer)) else x)
529	
530	    print(f"\nResults saved to {OUT_DIR / 'fpr_results.json'}")
531	
532	
533	if __name__ == "__main__":
534	    main()
535	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "84567651-b9f0-4c0a-b794-bd64269d6dd7",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "3e9c8520-94c9-4feb-a0eb-edbabf76b5b3",
  "sourceToolAssistantUUID": "84567651-b9f0-4c0a-b794-bd64269d6dd7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 18 · 2026-05-17T12:03:01.794Z_

Now let me read the third experiment script and check for any eval utilities:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3e9c8520-94c9-4feb-a0eb-edbabf76b5b3",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CSfNVoV6GNebgStAT",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "4b57835c-f122-43f0-b2ce-5036a26eca38",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01KXSBPmMuuvXB3q2XX5kUH6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 18379,
      "cache_read_input_tokens": 20769,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 18379,
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

_source line 19 · 2026-05-17T12:03:02.620Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Sa59a3qhtP2ajrmKpUV19R`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/experiments/trajguard_mahalanobis.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4b57835c-f122-43f0-b2ce-5036a26eca38",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CSfNVoV6GNebgStAT",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "fb9013b3-95c6-45d8-8df7-2caef5cf730c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01KXSBPmMuuvXB3q2XX5kUH6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 18379,
      "cache_read_input_tokens": 20769,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 18379,
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

_source line 20 · 2026-05-17T12:03:02.627Z_

<details><summary>↩ Tool result · `toolu_01Sa59a3qhtP2ajrmKpUV19R`</summary>

```text
1	"""TrajGuard-style Mahalanobis distance baseline for commitment detection.
2	
3	Input: Pre-extracted hidden states (.pt files)
4	Output: Per-trace Mahalanobis distances + crossing detection metrics
5	
6	Approach:
7	- Build reference distribution from safe traces (final_judgment=0.5)
8	- For each jailbreak trace step, compute MD from reference
9	- Detect commitment: MD > threshold for K consecutive steps
10	"""
11	
12	import sys
13	import json
14	import time
15	from pathlib import Path
16	from typing import List, Dict, Optional, Tuple
17	
18	import numpy as np
19	import torch
20	from sklearn.decomposition import PCA
21	from sklearn.covariance import LedoitWolf
22	
23	sys.path.insert(0, str(Path(__file__).resolve().parents[2]))
24	
25	from src.config import (
26	    HIDDEN_STATES_DIR, LAYERS, HIDDEN_DIM, DETECTION_WINDOW, SEED
27	)
28	from src.data_loader import prepare_dataset, split_data
29	
30	LAYER_14_IDX = 2  # LAYERS=[12..24], index 2 = layer 14
31	PCA_DIMS = [32, 64, 128, 256]
32	THRESHOLD_PERCENTILES = [90, 95, 99]
33	OUTPUT_DIR = Path("/root/autodl-tmp/contrastive_trace_safety/artifacts/exp_005_trajguard")
34	
35	
36	def load_trace_hidden_states(trace_id: str, layer_idx: int = LAYER_14_IDX) -> Optional[np.ndarray]:
37	    pt_path = HIDDEN_STATES_DIR / f"{trace_id}.pt"
38	    if not pt_path.exists():
39	        return None
40	    data = torch.load(pt_path, map_location="cpu", weights_only=False)
41	    hs = data["hidden_states"][:, layer_idx, :]  # [num_sentences, 4096]
42	    return hs.float().numpy()
43	
44	
45	def collect_safe_hidden_states(safe_traces: List[Dict]) -> np.ndarray:
46	    all_steps = []
47	    for trace in safe_traces:
48	        hs = load_trace_hidden_states(trace["trace_id"])
49	        if hs is not None:
50	            all_steps.append(hs)
51	    return np.concatenate(all_steps, axis=0)  # [N_safe_steps, 4096]
52	
53	
54	def first_crossing_point_md(
55	    md_sequence: np.ndarray,
56	    threshold: float,
57	    consecutive_k: int = DETECTION_WINDOW,
58	) -> Optional[int]:
59	    n = len(md_sequence)
60	    if n < consecutive_k:
61	        return None
62	    for i in range(n - consecutive_k + 1):
63	        if all(md_sequence[i:i + consecutive_k] > threshold):
64	            return i
65	    return None
66	
67	
68	def compute_mahalanobis_pca(
69	    X_ref: np.ndarray, X_query: np.ndarray, n_components: int
70	) -> Tuple[np.ndarray, object]:
71	    pca = PCA(n_components=n_components, random_state=SEED)
72	    X_ref_pca = pca.fit_transform(X_ref)
73	
74	    mean = X_ref_pca.mean(axis=0)
75	    cov = np.cov(X_ref_pca, rowvar=False)
76	    cov_inv = np.linalg.inv(cov + 1e-6 * np.eye(n_components))
77	
78	    X_query_pca = pca.transform(X_query)
79	    diff = X_query_pca - mean
80	    md = np.sqrt(np.sum(diff @ cov_inv * diff, axis=1))
81	    return md, pca
82	
83	
84	def compute_mahalanobis_ledoitwolf(
85	    X_ref: np.ndarray, X_query: np.ndarray
86	) -> np.ndarray:
87	    lw = LedoitWolf()
88	    lw.fit(X_ref)
89	    mean = lw.location_
90	    precision = lw.precision_  # inverse covariance
91	
92	    diff = X_query - mean
93	    md = np.sqrt(np.sum(diff @ precision * diff, axis=1))
94	    return md
95	
96	
97	def evaluate_config(
98	    jailbreak_traces: List[Dict],
99	    safe_val_md: np.ndarray,
100	    compute_md_fn,
101	    config_name: str,
102	) -> List[Dict]:
103	    results = []
104	    for pctl in THRESHOLD_PERCENTILES:
105	        threshold = float(np.percentile(safe_val_md, pctl))
106	
107	        per_trace = []
108	        detected_count = 0
109	        lead_times = []
110	
111	        for trace in jailbreak_traces:
112	            hs = load_trace_hidden_states(trace["trace_id"])
113	            if hs is None:
114	                continue
115	            md_seq = compute_md_fn(hs)
116	            fcp = first_crossing_point_md(md_seq, threshold)
117	            cp = trace["commitment_point"]
118	
119	            lead = None
120	            if fcp is not None:
121	                detected_count += 1
122	                lead = cp - fcp
123	                lead_times.append(lead)
124	
125	            per_trace.append({
126	                "trace_id": trace["trace_id"],
127	                "commitment_point": cp,
128	                "first_crossing": fcp,
129	                "lead_time": lead,
130	                "num_steps": len(md_seq),
131	                "md_mean": float(md_seq.mean()),
132	                "md_max": float(md_seq.max()),
133	            })
134	
135	        n_traces = len(per_trace)
136	        crossing_rate = detected_count / n_traces if n_traces > 0 else 0.0
137	
138	        results.append({
139	            "config": config_name,
140	            "threshold_percentile": pctl,
141	            "threshold_value": threshold,
142	            "crossing_rate": crossing_rate,
143	            "lead_time_mean": float(np.mean(lead_times)) if lead_times else None,
144	            "lead_time_median": float(np.median(lead_times)) if lead_times else None,
145	            "n_traces": n_traces,
146	            "n_detected": detected_count,
147	            "per_trace": per_trace,
148	        })
149	    return results
150	
151	
152	def main():
153	    t0 = time.time()
154	    print("Loading dataset...")
155	    dataset = prepare_dataset()
156	    safe_traces = dataset["safe"]
157	    jailbreak_traces = dataset["jailbreak_with_commitment"]
158	
159	    safe_train, safe_val, safe_test = split_data(safe_traces)
160	    jb_train, jb_val, jb_test = split_data(jailbreak_traces)
161	
162	    print(f"Safe: {len(safe_traces)} (train={len(safe_train)}, val={len(safe_val)}, test={len(safe_test)})")
163	    print(f"Jailbreak: {len(jailbreak_traces)} (train={len(jb_train)}, val={len(jb_val)}, test={len(jb_test)})")
164	
165	    # Build reference from safe train traces
166	    print("Collecting safe train hidden states (layer 14)...")
167	    X_safe_train = collect_safe_hidden_states(safe_train)
168	    print(f"  Safe train steps: {X_safe_train.shape[0]} x {X_safe_train.shape[1]}")
169	
170	    # Collect safe val hidden states for threshold calibration
171	    print("Collecting safe val hidden states...")
172	    X_safe_val = collect_safe_hidden_states(safe_val)
173	    print(f"  Safe val steps: {X_safe_val.shape[0]}")
174	
175	    OUTPUT_DIR.mkdir(parents=True, exist_ok=True)
176	    all_configs = []
177	
178	    # PCA-based methods
179	    for n_comp in PCA_DIMS:
180	        print(f"\n--- PCA dims={n_comp} ---")
181	        pca = PCA(n_components=n_comp, random_state=SEED)
182	        X_train_pca = pca.fit_transform(X_safe_train)
183	
184	        mean_pca = X_train_pca.mean(axis=0)
185	        cov_pca = np.cov(X_train_pca, rowvar=False)
186	        cov_inv = np.linalg.inv(cov_pca + 1e-6 * np.eye(n_comp))
187	
188	        def _md_pca(hs, _pca=pca, _mean=mean_pca, _cov_inv=cov_inv):
189	            X_pca = _pca.transform(hs)
190	            diff = X_pca - _mean
191	            return np.sqrt(np.sum(diff @ _cov_inv * diff, axis=1))
192	
193	        # Compute safe val MD for threshold
194	        safe_val_md = _md_pca(X_safe_val)
195	        print(f"  Safe val MD: mean={safe_val_md.mean():.2f}, p90={np.percentile(safe_val_md, 90):.2f}, p95={np.percentile(safe_val_md, 95):.2f}, p99={np.percentile(safe_val_md, 99):.2f}")
196	
197	        configs = evaluate_config(jb_test, safe_val_md, _md_pca, f"pca_{n_comp}")
198	        for c in configs:
199	            print(f"  pctl={c['threshold_percentile']}: crossing_rate={c['crossing_rate']:.3f}, lead_mean={c['lead_time_mean']}")
200	        all_configs.extend(configs)
201	
202	    # LedoitWolf shrinkage
203	    print("\n--- LedoitWolf (full 4096-d) ---")
204	    lw = LedoitWolf()
205	    lw.fit(X_safe_train)
206	    lw_mean = lw.location_
207	    lw_precision = lw.precision_
208	
209	    def _md_lw(hs, _mean=lw_mean, _prec=lw_precision):
210	        diff = hs - _mean
211	        return np.sqrt(np.sum(diff @ _prec * diff, axis=1))
212	
213	    safe_val_md_lw = _md_lw(X_safe_val)
214	    print(f"  Safe val MD: mean={safe_val_md_lw.mean():.2f}, p90={np.percentile(safe_val_md_lw, 90):.2f}, p95={np.percentile(safe_val_md_lw, 95):.2f}, p99={np.percentile(safe_val_md_lw, 99):.2f}")
215	
216	    configs_lw = evaluate_config(jb_test, safe_val_md_lw, _md_lw, "ledoitwolf_4096")
217	    for c in configs_lw:
218	        print(f"  pctl={c['threshold_percentile']}: crossing_rate={c['crossing_rate']:.3f}, lead_mean={c['lead_time_mean']}")
219	    all_configs.extend(configs_lw)
220	
221	    # Save results
222	    result = {
223	        "method": "trajguard_mahalanobis",
224	        "layer": 14,
225	        "layer_idx": LAYER_14_IDX,
226	        "detection_window": DETECTION_WINDOW,
227	        "n_safe_train_steps": int(X_safe_train.shape[0]),
228	        "n_jb_test_traces": len(jb_test),
229	        "configs": all_configs,
230	    }
231	
232	    output_path = OUTPUT_DIR / "results.json"
233	    with open(output_path, "w") as f:
234	        json.dump(result, f, indent=2)
235	    print(f"\nResults saved to {output_path}")
236	
237	    # Summary table
238	    print("\n" + "=" * 80)
239	    print("SUMMARY: TrajGuard Mahalanobis Distance Baseline")
240	    print("=" * 80)
241	    print(f"{'Config':<20} {'Pctl':<6} {'Threshold':<10} {'CrossRate':<12} {'LeadMean':<12} {'LeadMed':<10}")
242	    print("-" * 80)
243	    for c in all_configs:
244	        lead_m = f"{c['lead_time_mean']:.1f}" if c['lead_time_mean'] is not None else "N/A"
245	        lead_med = f"{c['lead_time_median']:.1f}" if c['lead_time_median'] is not None else "N/A"
246	        print(f"{c['config']:<20} {c['threshold_percentile']:<6} {c['threshold_value']:<10.2f} {c['crossing_rate']:<12.3f} {lead_m:<12} {lead_med:<10}")
247	
248	    # Comparison with existing methods
249	    print("\n" + "=" * 80)
250	    print("COMPARISON WITH EXISTING METHODS")
251	    print("=" * 80)
252	    print(f"{'Method':<35} {'CrossRate':<12} {'LeadMean':<12}")
253	    print("-" * 60)
254	    print(f"{'Static LR L14':<35} {'46.5%':<12} {'-2.0':<12}")
255	    print(f"{'Temporal LR W=15':<35} {'76.7%':<12} {'-1.1':<12}")
256	    print(f"{'GRU multi-7L h=256':<35} {'76.7%':<12} {'+4.7':<12}")
257	    print("-" * 60)
258	
259	    # Find best TrajGuard config
260	    best = max(all_configs, key=lambda c: (c['crossing_rate'], c['lead_time_mean'] or -999))
261	    lead_str = f"{best['lead_time_mean']:.1f}" if best['lead_time_mean'] is not None else "N/A"
262	    print(f"{'TrajGuard best (' + best['config'] + ' p' + str(best['threshold_percentile']) + ')':<35} {best['crossing_rate']:.1%}{'':<5} {lead_str:<12}")
263	
264	    elapsed = time.time() - t0
265	    print(f"\nTotal time: {elapsed:.1f}s")
266	
267	
268	if __name__ == "__main__":
269	    main()
270	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fb9013b3-95c6-45d8-8df7-2caef5cf730c",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "8cbfeca5-7701-4434-a251-fc15a1756df8",
  "sourceToolAssistantUUID": "fb9013b3-95c6-45d8-8df7-2caef5cf730c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-17T12:03:02.941Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01WXn8dgqcBM3CBtiTdPTABm`</summary>

```json
{
  "command": "find /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/eval -type f -name \"*.py\""
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8cbfeca5-7701-4434-a251-fc15a1756df8",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CSfNVoV6GNebgStAT",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "ad6e4d04-2728-4fac-a241-04022842793f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01KXSBPmMuuvXB3q2XX5kUH6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 18379,
      "cache_read_input_tokens": 20769,
      "output_tokens": 190,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 18379
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 6,
          "output_tokens": 190,
          "cache_read_input_tokens": 20769,
          "cache_creation_input_tokens": 18379,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 18379,
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

_source line 22 · 2026-05-17T12:03:02.997Z_

<details><summary>↩ Tool result · `toolu_01WXn8dgqcBM3CBtiTdPTABm`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/eval/evaluate.py
/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/eval/__init__.py
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ad6e4d04-2728-4fac-a241-04022842793f",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "accfbe91-ae91-4c6e-b822-45a699935a14",
  "sourceToolAssistantUUID": "ad6e4d04-2728-4fac-a241-04022842793f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 23 · 2026-05-17T12:03:04.112Z_

Let me check the evaluation module:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "accfbe91-ae91-4c6e-b822-45a699935a14",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CdmMrfYfQsgJPbypW",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "96cae5a5-abfb-482c-866f-1d9e813ec8d2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01HbpAx33h1VrZE8fsKtfcvC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 4499,
      "cache_read_input_tokens": 39148,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4499,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 3,
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

_source line 24 · 2026-05-17T12:03:04.675Z_

<details open><summary>🔧 Tool call — Read · `toolu_01N2xsFmuQmmrT4REhM7vv8g`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/eval/evaluate.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "96cae5a5-abfb-482c-866f-1d9e813ec8d2",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CdmMrfYfQsgJPbypW",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "8e750b05-6195-462f-a279-af92f1dd660a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01HbpAx33h1VrZE8fsKtfcvC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 4499,
      "cache_read_input_tokens": 39148,
      "output_tokens": 167,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 4499
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 6,
          "output_tokens": 167,
          "cache_read_input_tokens": 39148,
          "cache_creation_input_tokens": 4499,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 4499,
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

_source line 25 · 2026-05-17T12:03:04.682Z_

<details><summary>↩ Tool result · `toolu_01N2xsFmuQmmrT4REhM7vv8g`</summary>

```text
1	"""Evaluation metrics for commitment point detection.
2	
3	Metrics:
4	- Step-level accuracy
5	- Earliest reliable detection point
6	- Detection lead time (how early before commitment point)
7	"""
8	
9	from typing import List, Dict, Optional, Tuple
10	import numpy as np
11	
12	from ..config import DETECTION_THRESHOLD, DETECTION_WINDOW
13	
14	
15	def step_accuracy(predictions: np.ndarray, labels: np.ndarray) -> float:
16	    """Overall step-level accuracy."""
17	    return float((predictions == labels).mean())
18	
19	
20	def earliest_reliable_detection(
21	    probs: np.ndarray,
22	    labels: np.ndarray,
23	    threshold: float = DETECTION_THRESHOLD,
24	    window: int = DETECTION_WINDOW,
25	) -> Optional[int]:
26	    """Find first position where model reliably detects post-commitment.
27	
28	    Scans from trace start, finds first position where consecutive `window` steps
29	    all have predicted prob > threshold AND predictions are correct.
30	
31	    Returns step index or None if never reliably detected.
32	    """
33	    n = len(probs)
34	    if n < window:
35	        return None
36	
37	    for i in range(n - window + 1):
38	        segment_probs = probs[i:i + window]
39	        segment_labels = labels[i:i + window]
40	
41	        # All probs above threshold
42	        if not np.all(segment_probs > threshold):
43	            continue
44	
45	        # All predictions correct (prob > 0.5 means predict class 1)
46	        segment_preds = (segment_probs > 0.5).astype(int)
47	        if not np.all(segment_preds == segment_labels):
48	            continue
49	
50	        return i
51	
52	    return None
53	
54	
55	def first_crossing_point(
56	    probs_class1: np.ndarray,
57	    threshold: float = 0.5,
58	    consecutive_k: int = DETECTION_WINDOW,
59	) -> Optional[int]:
60	    """First position where prob(post-commitment) > threshold for K consecutive steps.
61	
62	    Unlike earliest_reliable_detection, this does NOT check against ground-truth labels,
63	    so crossings before the commitment point measure anticipation ability.
64	    """
65	    n = len(probs_class1)
66	    if n < consecutive_k:
67	        return None
68	    for i in range(n - consecutive_k + 1):
69	        if all(p > threshold for p in probs_class1[i:i + consecutive_k]):
70	            return i
71	    return None
72	
73	
74	def detection_lead_time(earliest_detection: Optional[int], commitment_point: int) -> Optional[int]:
75	    """Compute how many steps before commitment the detection occurs.
76	
77	    lead_time = commitment_point - earliest_detection
78	    Positive = detected before commitment (good)
79	    Negative = detected after commitment (late)
80	    None = never detected
81	    """
82	    if earliest_detection is None:
83	        return None
84	    return commitment_point - earliest_detection
85	
86	
87	def evaluate_trace(
88	    probs: np.ndarray,
89	    labels: np.ndarray,
90	    commitment_point: int,
91	    threshold: float = DETECTION_THRESHOLD,
92	    window: int = DETECTION_WINDOW,
93	) -> Dict:
94	    """Evaluate a single trace."""
95	    preds = (probs > 0.5).astype(int)
96	    acc = step_accuracy(preds, labels)
97	    erd = earliest_reliable_detection(probs, labels, threshold, window)
98	    lead = detection_lead_time(erd, commitment_point)
99	    fcp = first_crossing_point(probs, threshold=0.5, consecutive_k=window)
100	    fcp_lead = detection_lead_time(fcp, commitment_point)
101	
102	    return {
103	        "step_accuracy": acc,
104	        "earliest_reliable_detection": erd,
105	        "detection_lead_time": lead,
106	        "first_crossing_point": fcp,
107	        "first_crossing_lead_time": fcp_lead,
108	        "commitment_point": commitment_point,
109	        "num_steps": len(labels),
110	    }
111	
112	
113	def evaluate_all(
114	    predictions_static: List[Dict],
115	    predictions_temporal: List[Dict],
116	    threshold: float = DETECTION_THRESHOLD,
117	    window: int = DETECTION_WINDOW,
118	) -> Dict:
119	    """Evaluate and compare static vs temporal probes across all test traces."""
120	
121	    def _eval_predictions(predictions, name):
122	        results = []
123	        for pred in predictions:
124	            if pred["commitment_point"] is None:
125	                continue
126	            res = evaluate_trace(
127	                pred["probs"], pred["labels"],
128	                pred["commitment_point"], threshold, window
129	            )
130	            res["trace_id"] = pred["trace_id"]
131	            results.append(res)
132	
133	        if not results:
134	            return {"name": name, "n_traces": 0}
135	
136	        accs = [r["step_accuracy"] for r in results]
137	        leads = [r["detection_lead_time"] for r in results if r["detection_lead_time"] is not None]
138	        erds = [r["earliest_reliable_detection"] for r in results if r["earliest_reliable_detection"] is not None]
139	        fcp_leads = [r["first_crossing_lead_time"] for r in results if r["first_crossing_lead_time"] is not None]
140	        fcps = [r["first_crossing_point"] for r in results if r["first_crossing_point"] is not None]
141	
142	        summary = {
143	            "name": name,
144	            "n_traces": len(results),
145	            "step_accuracy_mean": float(np.mean(accs)),
146	            "step_accuracy_std": float(np.std(accs)),
147	            "detection_rate": len(erds) / len(results),
148	            "lead_time_mean": float(np.mean(leads)) if leads else None,
149	            "lead_time_median": float(np.median(leads)) if leads else None,
150	            "lead_time_std": float(np.std(leads)) if leads else None,
151	            "erd_mean": float(np.mean(erds)) if erds else None,
152	            "crossing_rate": len(fcps) / len(results),
153	            "crossing_lead_time_mean": float(np.mean(fcp_leads)) if fcp_leads else None,
154	            "crossing_lead_time_median": float(np.median(fcp_leads)) if fcp_leads else None,
155	            "per_trace": results,
156	        }
157	        return summary
158	
159	    static_summary = _eval_predictions(predictions_static, "static_probe")
160	    temporal_summary = _eval_predictions(predictions_temporal, "temporal_probe")
161	
162	    # Print comparison
163	    print("\n" + "="*60)
164	    print("EVALUATION RESULTS")
165	    print("="*60)
166	
167	    for s in [static_summary, temporal_summary]:
168	        if s["n_traces"] == 0:
169	            print(f"\n{s['name']}: No traces evaluated")
170	            continue
171	        print(f"\n{s['name']} ({s['n_traces']} traces):")
172	        print(f"  Step accuracy:      {s['step_accuracy_mean']:.4f} ± {s['step_accuracy_std']:.4f}")
173	        print(f"  Detection rate:     {s['detection_rate']:.2%}")
174	        if s["lead_time_mean"] is not None:
175	            print(f"  Lead time (mean):   {s['lead_time_mean']:.1f} steps")
176	            print(f"  Lead time (median): {s['lead_time_median']:.1f} steps")
177	        if s["erd_mean"] is not None:
178	            print(f"  Earliest detection: {s['erd_mean']:.1f} (mean step)")
179	        print(f"  Crossing rate:      {s['crossing_rate']:.2%}")
180	        if s["crossing_lead_time_mean"] is not None:
181	            print(f"  Crossing lead (mean):   {s['crossing_lead_time_mean']:.1f} steps")
182	            print(f"  Crossing lead (median): {s['crossing_lead_time_median']:.1f} steps")
183	
184	    print("\n" + "="*60)
185	
186	    return {
187	        "static": static_summary,
188	        "temporal": temporal_summary,
189	    }
190	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8e750b05-6195-462f-a279-af92f1dd660a",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "e7d3d525-ff5a-4bad-827b-6d0cbe664678",
  "sourceToolAssistantUUID": "8e750b05-6195-462f-a279-af92f1dd660a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-17T12:03:04.698Z_

<details open><summary>🔧 Tool call — Read · `toolu_015HT47FHNpBazUM2QVi6jbC`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/config.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e7d3d525-ff5a-4bad-827b-6d0cbe664678",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CdmMrfYfQsgJPbypW",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "de80521e-16f8-4962-9dfd-e2e4900fdb93",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01HbpAx33h1VrZE8fsKtfcvC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 4499,
      "cache_read_input_tokens": 39148,
      "output_tokens": 167,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 4499
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 6,
          "output_tokens": 167,
          "cache_read_input_tokens": 39148,
          "cache_creation_input_tokens": 4499,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 4499,
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

_source line 27 · 2026-05-17T12:03:04.712Z_

<details><summary>↩ Tool result · `toolu_015HT47FHNpBazUM2QVi6jbC`</summary>

```text
1	"""Central configuration for contrastive_trace_safety project."""
2	
3	import os
4	from pathlib import Path
5	
6	# Paths
7	PROJECT_ROOT = Path("/root/autodl-tmp/contrastive_trace_safety")
8	ARTIFACTS_DIR = PROJECT_ROOT / "artifacts"
9	HIDDEN_STATES_DIR = ARTIFACTS_DIR / "hidden_states"
10	PROBES_DIR = ARTIFACTS_DIR / "probes"
11	
12	# Model
13	MODEL_NAME = "deepseek-ai/DeepSeek-R1-Distill-Llama-8B"
14	MODEL_PATH = "/root/autodl-tmp/.hf_cache/deepseek-ai/DeepSeek-R1-Distill-Llama-8B"
15	
16	# Dataset
17	HF_DATASET = "ishitakakkar-10/HarmThoughts"
18	TARGET_MODEL = "r1-8b"
19	
20	# Hidden state extraction
21	LAYERS = list(range(12, 25))  # layers 12-24, 13 layers total
22	NUM_LAYERS = len(LAYERS)
23	HIDDEN_DIM = 4096
24	EXTRACT_BATCH_SIZE = 4
25	DEVICE = "cuda:0"
26	
27	# Probes
28	WINDOW_SIZE = 5
29	TEMPORAL_HIDDEN_DIM = 512
30	LEARNING_RATE = 1e-3
31	TRAIN_EPOCHS = 20
32	PROBE_BATCH_SIZE = 64
33	DEFAULT_LAYER = 20  # for static probe
34	
35	# Data split
36	TRAIN_RATIO = 0.6
37	VAL_RATIO = 0.2
38	SEED = 42
39	
40	# Evaluation
41	DETECTION_THRESHOLD = 0.9
42	DETECTION_WINDOW = 5
43	
44	# Safety labels that define commitment point
45	SAFETY_LABELS = {"RA", "AL", "CC", "ED", "IA"}
46	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "de80521e-16f8-4962-9dfd-e2e4900fdb93",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "1f986743-d571-4b80-afcd-46987a197549",
  "sourceToolAssistantUUID": "de80521e-16f8-4962-9dfd-e2e4900fdb93",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 28 · 2026-05-17T12:03:06.234Z_

Perfect! Now let me search for any additional supporting functions and check if there are more eval utilities:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1f986743-d571-4b80-afcd-46987a197549",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CmFKMkd9VCVAF865R",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "93b442fe-0421-48ac-883f-6e87a4d985d2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01BGeo9mePPn4NVs6pqFw8gQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 3193,
      "cache_read_input_tokens": 43647,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3193,
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

_source line 29 · 2026-05-17T12:03:06.705Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01Ax2jPMDEVixDhZ7opuF4mr`</summary>

```json
{
  "command": "ls -la /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/eval/"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "93b442fe-0421-48ac-883f-6e87a4d985d2",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CmFKMkd9VCVAF865R",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "02871468-418f-4112-82dc-74ed08257f02",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01BGeo9mePPn4NVs6pqFw8gQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 3193,
      "cache_read_input_tokens": 43647,
      "output_tokens": 109,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 3193
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 6,
          "output_tokens": 109,
          "cache_read_input_tokens": 43647,
          "cache_creation_input_tokens": 3193,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 3193,
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

_source line 30 · 2026-05-17T12:03:06.802Z_

<details><summary>↩ Tool result · `toolu_01Ax2jPMDEVixDhZ7opuF4mr`</summary>

```text
total 20
drwxr-xr-x 3 ubuntu ubuntu 4096 May 16 18:59 .
drwxr-xr-x 7 ubuntu ubuntu 4096 May 16 20:37 ..
-rw-r--r-- 1 ubuntu ubuntu    0 May 16 18:40 __init__.py
drwxr-xr-x 2 ubuntu ubuntu 4096 May 16 18:44 __pycache__
-rw-r--r-- 1 ubuntu ubuntu 6870 May 16 18:59 evaluate.py
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "02871468-418f-4112-82dc-74ed08257f02",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "7ee10c85-6d9d-4bfa-8c5c-cc0ffebbed97",
  "sourceToolAssistantUUID": "02871468-418f-4112-82dc-74ed08257f02",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 31 · 2026-05-17T12:03:16.431Z_

Excellent. Now let me create a comprehensive summary of all the findings. Let me also check if there are any other relevant files in the baselines or extract_hidden_states:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7ee10c85-6d9d-4bfa-8c5c-cc0ffebbed97",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CuygRdKZELZLzjG58",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "e148d0da-3364-4c0c-8201-6c7aacef6495",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Nk32gFXVvFtwE5G53yWXSS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 271,
      "cache_read_input_tokens": 46840,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 271,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 3,
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

_source line 32 · 2026-05-17T12:03:17.094Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01DWyYQeKD7N6uqCdEPZfhnf`</summary>

```json
{
  "command": "ls -la /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/baselines/"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e148d0da-3364-4c0c-8201-6c7aacef6495",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CuygRdKZELZLzjG58",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "f45cde08-f8c6-4bdc-bbbd-e205a1819792",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Nk32gFXVvFtwE5G53yWXSS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 271,
      "cache_read_input_tokens": 46840,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 271,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 3,
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

_source line 33 · 2026-05-17T12:03:17.173Z_

<details><summary>↩ Tool result · `toolu_01DWyYQeKD7N6uqCdEPZfhnf`</summary>

```text
total 20
drwxr-xr-x 3 ubuntu ubuntu 4096 May 16 18:44 .
drwxr-xr-x 7 ubuntu ubuntu 4096 May 16 20:37 ..
-rw-r--r-- 1 ubuntu ubuntu    0 May 16 18:40 __init__.py
drwxr-xr-x 2 ubuntu ubuntu 4096 May 16 18:44 __pycache__
-rw-r--r-- 1 ubuntu ubuntu 7147 May 16 18:41 linear_probe.py
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f45cde08-f8c6-4bdc-bbbd-e205a1819792",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "3cde3346-b69e-481e-bd4a-488772fed15e",
  "sourceToolAssistantUUID": "f45cde08-f8c6-4bdc-bbbd-e205a1819792",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 34 · 2026-05-17T12:03:17.303Z_

<details open><summary>🔧 Tool call — Read · `toolu_01MgfFoofgKEhCEthywjyr2a`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/extract_hidden_states.py",
  "limit": 100
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3cde3346-b69e-481e-bd4a-488772fed15e",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87CuygRdKZELZLzjG58",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "91a3d6b4-307f-47f4-9f38-fd6df7cecec6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01Nk32gFXVvFtwE5G53yWXSS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 271,
      "cache_read_input_tokens": 46840,
      "output_tokens": 218,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 271
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 5,
          "output_tokens": 218,
          "cache_read_input_tokens": 46840,
          "cache_creation_input_tokens": 271,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 271,
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

_source line 35 · 2026-05-17T12:03:17.310Z_

<details><summary>↩ Tool result · `toolu_01MgfFoofgKEhCEthywjyr2a`</summary>

```text
1	"""Extract hidden states from DeepSeek-R1-Distill-Llama-8B for each sentence in traces.
2	
3	Input: List of trace dicts (from data_loader.prepare_dataset)
4	Output: Per-trace .pt files with tensor [num_sentences, 13, 4096] + metadata
5	"""
6	
7	import os
8	from pathlib import Path
9	from typing import List, Dict
10	
11	import torch
12	from transformers import AutoTokenizer, AutoModelForCausalLM
13	from tqdm import tqdm
14	
15	from .config import (
16	    MODEL_PATH, LAYERS, HIDDEN_DIM, NUM_LAYERS,
17	    HIDDEN_STATES_DIR, EXTRACT_BATCH_SIZE, DEVICE
18	)
19	
20	
21	def load_model(model_path: str = MODEL_PATH, device: str = DEVICE):
22	    """Load model and tokenizer."""
23	    tokenizer = AutoTokenizer.from_pretrained(model_path, trust_remote_code=True)
24	    if tokenizer.pad_token is None:
25	        tokenizer.pad_token = tokenizer.eos_token
26	
27	    model = AutoModelForCausalLM.from_pretrained(
28	        model_path,
29	        torch_dtype=torch.float16,
30	        device_map=device,
31	        trust_remote_code=True,
32	    )
33	    model.eval()
34	    return model, tokenizer
35	
36	
37	def find_sentence_boundaries(tokenizer, sentences: List[str]) -> List[int]:
38	    """Find each sentence's last token position via char-to-token offset mapping.
39	
40	    Tokenizes the full joined text once, then maps each sentence's char span
41	    to token positions. This avoids BPE context mismatch from per-sentence tokenization.
42	    """
43	    full_text = " ".join(sentences)
44	    encoding = tokenizer(
45	        full_text,
46	        return_offsets_mapping=True,
47	        return_tensors="pt",
48	        truncation=True,
49	        max_length=8192,
50	    )
51	    offsets = encoding["offset_mapping"][0]  # (num_tokens, 2)
52	
53	    boundaries = []
54	    char_pos = 0
55	    for sent in sentences:
56	        char_end = char_pos + len(sent)
57	        last_token_idx = 0
58	        for tok_idx, (start, end) in enumerate(offsets):
59	            if start < char_end:
60	                last_token_idx = tok_idx
61	        boundaries.append(last_token_idx)
62	        char_pos = char_end + 1  # +1 for the joining space
63	
64	    return boundaries
65	
66	
67	def extract_trace_hidden_states(
68	    model, tokenizer, sentences: List[str], device: str = DEVICE
69	) -> torch.Tensor:
70	    """Extract hidden states for a single trace.
71	
72	    Concatenates all sentences, does one forward pass, extracts hidden states
73	    at sentence boundary positions for specified layers.
74	
75	    Returns: tensor of shape [num_sentences, num_layers, hidden_dim]
76	    """
77	    # Find sentence boundaries
78	    boundary_positions = find_sentence_boundaries(tokenizer, sentences)
79	
80	    # Tokenize full text
81	    full_text = " ".join(sentences)
82	    inputs = tokenizer(
83	        full_text,
84	        return_tensors="pt",
85	        truncation=True,
86	        max_length=8192,
87	    ).to(device)
88	
89	    num_tokens = inputs["input_ids"].shape[1]
90	
91	    # Clamp boundary positions to valid range
92	    boundary_positions = [min(p, num_tokens - 1) for p in boundary_positions]
93	
94	    with torch.no_grad():
95	        outputs = model(**inputs, output_hidden_states=True)
96	
97	    # outputs.hidden_states is tuple of (num_layers+1) tensors, each [1, seq_len, hidden_dim]
98	    # Index 0 is embedding layer, so layer i is at index i+1... but model layers are 0-indexed
99	    # For LlamaForCausalLM, hidden_states[0] = embeddings, hidden_states[i] = layer i output
100	    hidden_states = outputs.hidden_states
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "91a3d6b4-307f-47f4-9f38-fd6df7cecec6",
  "isSidechain": true,
  "promptId": "ac4f966d-8e73-43ba-91ce-77ca7b200214",
  "agentId": "aa357d0ddf5851242",
  "type": "user",
  "uuid": "bd196579-6a4b-4579-a28a-fc0cec3a1cfd",
  "sourceToolAssistantUUID": "91a3d6b4-307f-47f4-9f38-fd6df7cecec6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 36 · 2026-05-17T12:03:47.395Z_

Now I have a comprehensive understanding. Let me compile a detailed report of my findings:

## Summary of Experiment Scripts and Data Pipeline

I've thoroughly analyzed the experiment scripts in `/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/src/experiments/`. Here are the comprehensive findings:

### Files in src/experiments/
- **bootstrap_ci.py** (exp-006): Bootstrap confidence intervals and paired significance tests
- **fpr_analysis.py** (exp-015): FPR analysis for text baseline and hidden state methods
- **trajguard_mahalanobis.py** (exp-005): Mahalanobis distance baseline for commitment detection
- **__init__.py** (empty)

---

## 1. DATA LOADING (.pt FILES AND TRAIN/VAL/TEST SPLITS)

### .pt File Structure
Hidden states are stored in PyTorch format at `/artifacts/hidden_states/{trace_id}.pt`:
```python
# File structure (from extract_hidden_states.py and bootstrap_ci.py):
data = torch.load(pt_path, map_location="cpu", weights_only=False)
hs = data["hidden_states"]  # Shape: [num_sentences, num_layers, 4096]
```

The hidden_states tensor has shape `[T, 13, 4096]` where:
- T = number of sentences/steps in the trace
- 13 = number of layers (layers 12-24 from LAYERS config)
- 4096 = hidden dimension (HIDDEN_DIM)

### Data Preparation Pipeline
`prepare_dataset()` from **data_loader.py** (lines 73-123):
1. Loads HarmThoughts from HuggingFace: `ishitakakkar-10/HarmThoughts`
2. Groups sentences by `trace_id` (extracted from sentence_id by splitting on last dash)
3. Extracts commitment points using `extract_commitment_point()` logic:
   - Finds the last safety label (labels in {"RA", "AL", "CC", "ED", "IA"})
   - Commitment point = index after last safety label
4. Returns three categories:
   - `jailbreak_with_commitment`: traces with valid commitment points (used for training/eval)
   - `jailbreak_no_commitment`: jailbreak traces without commitment points (excluded)
   - `safe`: safe traces (final_judgment == 0, used for FP evaluation)

### Train/Val/Test Splits
`split_data()` from **data_loader.py** (lines 126-143):
```python
def split_data(traces, train_ratio=0.6, val_ratio=0.2, seed=42):
    # Trace-level split (not step-level) using np.random.permutation
    # 60% train, 20% val, 20% test
    # Seed = 42 for reproducibility
```

**Usage in experiments**:
- **bootstrap_ci.py** (line 392): `train, val, test = split_data(traces)`
- **fpr_analysis.py** (line 280): `train_jb, val_jb, test_jb = split_data(jb_traces)`
- **trajguard_mahalanobis.py** (lines 159-160): Splits both safe and jailbreak traces

---

## 2. LR PROBE AND GRU EXPERIMENT STRUCTURE

### LR Probe Variants

#### Static LR (Layer 14)
From **bootstrap_ci.py** (lines 78-109):
```python
# Training:
def train_static_lr(train_traces):
    X_list, y_list = [], []
    for t in train_traces:
        hs = load_trace_hidden_states(t["trace_id"], LAYER_14_IDX)  # [T, 4096]
        X_list.append(hs[:n].numpy())
        y_list.append(np.array(t["step_labels"][:n]))
    X = np.concatenate(X_list)  # Flatten all steps
    y = np.concatenate(y_list)
    clf = LogisticRegression(max_iter=1000, C=1.0, class_weight="balanced")
    clf.fit(X, y)
```
- Input: Single layer hidden states [T, 4096]
- Training: Logistic regression on flattened per-step embeddings
- Output: Per-step probabilities via `predict_proba()`

#### Temporal LR (W=15)
From **bootstrap_ci.py** (lines 116-161):
```python
def create_causal_windows(hs, window_size=15):
    # Causal window: step i uses [max(0, i-W+1), ..., i]
    # Zero-pad on the left
    windows = np.zeros((T, window_size * D))
    for i in range(T):
        windows[i] = padded[i:i+window_size].reshape(-1)
    return windows  # [T, 15*4096]
```
- Input: Causal sliding window of size 15
- Features: Flattened window embeddings [T, 61440]
- Training: SGDClassifier with log loss (L2 regularization)

#### Text-Based Methods
From **fpr_analysis.py** (lines 300-350):
- **text_static**: Sentence embeddings [T, 384] via SentenceTransformer
- **text_temporal_w15**: Causal window of embeddings [T, 5760]

### GRU Probe Architecture
From **bootstrap_ci.py** (lines 38-50) and **fpr_analysis.py** (lines 174-186):

```python
class GRUProbe(nn.Module):
    def __init__(self, input_dim=4096, hidden_dim=256, dropout=0.3):
        super().__init__()
        self.gru = nn.GRU(input_dim, hidden_dim, num_layers=1, 
                         batch_first=True, dropout=0)
        self.dropout = nn.Dropout(dropout)
        self.fc = nn.Linear(hidden_dim, 1)  # Binary classification
    
    def forward(self, x):  # x: [batch, T, input_dim]
        out, _ = self.gru(x)  # [batch, T, hidden_dim]
        out = self.dropout(out)
        logits = self.fc(out).squeeze(-1)  # [batch, T]
        return logits
```

**Training** (lines 168-231):
- Hyperparameters: hidden_dim=256, dropout=0.3, lr=1e-3, epochs=20
- Loss: BCEWithLogitsLoss
- Early stopping: patience=5 on validation loss
- Two variants:
  1. **GRU single L14**: Input from layer 14 only [T, 4096]
  2. **GRU multi-7L**: Mean-pooled across 7 layers [12,14,16,18,20,22,24] → [T, 4096]

**Prediction**:
```python
def predict_gru(model, traces, multi_layer=False):
    for t in traces:
        hs = load_fn(t["trace_id"])  # Load hidden states
        with torch.no_grad():
            logits = model(hs[:n].float().unsqueeze(0))
            probs = torch.sigmoid(logits[0]).numpy()
```

---

## 3. METRICS COMPUTED

### Step-Level Metrics
From **evaluate.py** (lines 15-17):
- **step_accuracy**: `(predictions == labels).mean()`
  - Binary predictions: `preds = (probs > 0.5).astype(int)`

### Detection Metrics
From **evaluate.py** (lines 55-84):

1. **first_crossing_point** (lines 55-71):
   ```python
   def first_crossing_point(probs, threshold=0.5, consecutive_k=5):
       # Find first position where prob > threshold for K consecutive steps
       for i in range(n - consecutive_k + 1):
           if all(probs[i:i+consecutive_k] > threshold):
               return i
   ```
   - Threshold: 0.5 (for crossing detection)
   - Consecutive_k: 5 (DETECTION_WINDOW from config)
   - Used in all experiments

2. **coverage (crossing_rate)**:
   ```python
   coverage = n_crossing / n_valid
   # Proportion of traces where first_crossing_point is not None
   ```

3. **lead**: `lead_time = commitment_point - first_crossing_point`
   - Positive: Detected before commitment (early prediction)
   - Negative: Detected after commitment (late prediction)
   - None: Never detected

4. **bal_acc (balanced accuracy)** - Not explicitly computed in experiments
   - Would be: `(TPR + TNR) / 2` for binary classification
   - Used indirectly through `class_weight="balanced"` in LR training

### FPR Metrics
From **fpr_analysis.py** (lines 92-167):

1. **safe_fpr**:
   ```python
   def safe_trace_fpr(predict_fn, safe_traces, build_fn):
       for t in safe_traces:
           preds = (probs > 0.5).astype(int)
       fpr = false_positives / total_steps
   ```
   - Ratio of predicted positives on safe traces (should be low)
   - Evaluates false positive rate on naturally safe sequences

2. **pre_commitment_fpr (pre_cp_fpr)**:
   ```python
   def pre_commitment_fpr(predict_fn, test_traces, build_fn):
       for t in test_traces:
           cp = t["commitment_point"]
           preds = (probs > 0.5).astype(int)
           pre_preds = preds[:cp]  # Only steps before commitment
       fpr = fp_pre / total_pre
   ```
   - FPR on pre-commitment steps (should be low to avoid false alarms)

3. **precision**:
   ```python
   def compute_precision(predict_fn, test_traces, build_fn):
       tp = sum((preds == 1) & (labels == 1))
       fp = sum((preds == 1) & (labels == 0))
       return tp / (tp + fp)
   ```
   - TP/(TP+FP): quality of positive predictions

4. **lead** (mean lead time):
   ```python
   lead = detection_lead_time(fcp, cp) = cp - fcp
   mean_lead = np.mean([l for l in leads if l is not None])
   ```

### Bootstrap Metrics
From **bootstrap_ci.py** (lines 296-332):
```python
def bootstrap_ci(per_trace_metrics, n_bootstrap=1000):
    # For each bootstrap sample:
    # - Resample traces with replacement
    # - Compute: step_accuracy, crossing_rate, mean lead_time
    # - Return: mean, 95% CI lower, 95% CI upper
```

**Output format**:
```json
{
    "step_accuracy": {
        "mean": float,
        "ci_lower": float,
        "ci_upper": float
    },
    "crossing_rate": { ... },
    "lead_time_mean": { ... }
}
```

### Paired Bootstrap Tests
From **bootstrap_ci.py** (lines 335-376):
```python
def paired_bootstrap_test(metrics_a, metrics_b, metric_key):
    # H0: metric_A <= metric_B
    # p_value = P(delta <= 0) where delta = mean_A - mean_B
    # Returns: delta_mean, 95% CI, p-value
```

---

## Key Configuration Values
From **config.py**:
- `LAYERS = [12, 13, ..., 24]` (13 layers)
- `HIDDEN_DIM = 4096`
- `LAYER_14_IDX = 2` (layer 14 is at index 2 in LAYERS)
- `TRAIN_RATIO = 0.6`, `VAL_RATIO = 0.2`
- `SEED = 42`
- `DETECTION_WINDOW = 5` (for K-consecutive requirement)
- `DETECTION_THRESHOLD = 0.9` (for reliable detection, not crossing detection)
- `MULTI_LAYER_INDICES = [0, 2, 4, 6, 8, 10, 12]` (layers 12, 14, 16, 18, 20, 22, 24)

---

## Experiment Workflow Summary

1. **bootstrap_ci.py** (exp-006):
   - Trains 4 methods (Static LR, Temporal LR, GRU-S, GRU-M) on train split
   - Tests on test split
   - Computes per-trace metrics: step_accuracy, crossing_detected, lead_time
   - Bootstrap resampling (1000 iterations) for 95% CIs
   - Paired bootstrap tests between methods

2. **fpr_analysis.py** (exp-015):
   - 5 methods: text_static, text_temporal, HS_static, HS_temporal, GRU_multi7L
   - Evaluates: safe_fpr, pre_commitment_fpr, precision, coverage, lead_time_mean, step_accuracy

3. **trajguard_mahalanobis.py** (exp-005):
   - Mahalanobis distance baseline
   - Builds reference from safe_train
   - Tests on jb_test with different PCA dimensions and thresholds
   - Reports: crossing_rate, lead_time_mean/median per configuration

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bd196579-6a4b-4579-a28a-fc0cec3a1cfd",
  "isSidechain": true,
  "agentId": "aa357d0ddf5851242",
  "requestId": "req_011Cb87DhMC5Tyb7Ro62zdSF",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "7b5a88d8-cd9d-49a4-a05b-d13e2a45ba21",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "02958b13-588a-4e0d-ad70-d1455c820602",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01TjNRRTEvAnqzpci7ZNuf4S",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 1733,
      "cache_read_input_tokens": 47111,
      "output_tokens": 3444,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1733
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 6,
          "output_tokens": 3444,
          "cache_read_input_tokens": 47111,
          "cache_creation_input_tokens": 1733,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1733,
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
