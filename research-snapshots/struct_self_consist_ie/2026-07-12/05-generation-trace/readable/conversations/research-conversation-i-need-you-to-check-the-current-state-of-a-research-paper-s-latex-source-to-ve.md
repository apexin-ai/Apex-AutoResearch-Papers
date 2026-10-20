# Research conversation: I need you to check the current state of a research paper's LaTeX source to verify whether certain previously-reported i

**When Self-Consistency Fails for NER: Degeneracy, Signal Collapse, and the Correlation-Selection Gap (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 61
- **Recorded user turns:** 1
- **Tool calls:** 26
- **Original source:** `logs/chats/exported-trajectories/account-3/agent-ae472d1c37ea69de3.jsonl`
- **Structured JSON:** [`f01a2e60ed22b270c21f.json`](../../sessions/f0/f01a2e60ed22b270c21f.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

61 recorded events

### User

_source line 1 · 2026-05-15T12:44:17.729Z_

I need you to check the current state of a research paper's LaTeX source to verify whether certain previously-reported issues have been fixed. The paper is at:
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/

Check EACH of the following items and report PASS (fixed) or FAIL (still present) with a brief justification:

1. **R3-W6 (first multi-family claim)**: Check if the paper claims to be the "first" multi-family confidence signal comparison for IE. Look in introduction.tex and abstract.tex for "first" claims. This should have been softened.

2. **R3-W7 (VC/Voting Conf terminology)**: Check if "voting confidence" and "VC" are used consistently throughout the paper. Grep for both "voting confidence" and "VC" in all .tex files — they should use one term consistently or define VC = voting confidence early.

3. **R5-W1 (Qwen3 thinking token)**: Check if the paper mentions Qwen3's "thinking" mode or /think tokens, and whether it explicitly states these are disabled during experiments. Search for "think", "Qwen3", "reasoning mode" in the paper.

4. **R5-W2 (semantic entropy footnote)**: Check if there's a footnote about semantic entropy (Kuhn et al. 2023) and whether it's properly discussed. Search for "semantic entropy" or "Kuhn" in the paper.

5. **R5-W3 (bib mismatch he2024uncertainty)**: Check the bibliography file (.bib or .bbl) for "he2024uncertainty" or similar entries and verify the reference is correct. Look at the .bib files in the paper directory.

6. **R5-M4 (bib OpenAlex issues)**: Check the bibliography for any obvious OpenAlex-style entries (auto-generated bibentries often have weird formatting or incomplete venue info).

7. **R5-M5 (Ethics Statement)**: Check if there's an ethics statement section and if it has substantive content (not just boilerplate). Look in the main .tex file or sections/.

8. **R4-M3 (Table 1 N=16 blank)**: Check if Table 1 in experiments.tex has any blank/empty cells for N=16 data.

9. **R6-W2 (Figure 1 caption)**: Check if Figure 1 exists and whether its caption is overly verbose/redundant.

For each item, read the relevant files and give a clear PASS/FAIL verdict. Be thorough — read the actual content, don't guess. Report concisely in bullet format.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "9bfc0a37-5058-4507-8b76-65c9ef04dd86",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-15T12:44:17.735Z_

```json
{
  "parentUuid": "9bfc0a37-5058-4507-8b76-65c9ef04dd86",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
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
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__get_gpu_health",
      "mcp__agent-ml-research__get_project_resource_usage",
      "mcp__agent-ml-research__list_constraints",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_matrix",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__reviewer_post_to_director",
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__tail_training_logs"
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
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__fetch_wandb_metrics",
      "mcp__agent-ml-research__get_gpu_health",
      "mcp__agent-ml-research__get_project_resource_usage",
      "mcp__agent-ml-research__list_constraints",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_matrix",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__reviewer_post_to_director",
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__tail_training_logs"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "836e2a37-837d-457c-9cc4-4b819c7dc709",
  "timestamp": "2026-05-15T12:44:17.735Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 3 · 2026-05-15T12:44:20.496Z_



I'll systematically check each item. Let me start by reading the relevant files in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "836e2a37-837d-457c-9cc4-4b819c7dc709",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NjE4BZPekheqfXtTGw",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "0f7dcd07-c9d4-4e26-883e-a163969b9720",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FS3yYfBMsqvcCgVV6xd4h8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 23030,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 23030,
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

_source line 4 · 2026-05-15T12:44:21.403Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01Q3AZhB62QvEKxwY6fGk4dR`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0f7dcd07-c9d4-4e26-883e-a163969b9720",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NjE4BZPekheqfXtTGw",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "e73085aa-a19a-4491-8928-774c1c3eb57c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FS3yYfBMsqvcCgVV6xd4h8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 23030,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 23030,
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

_source line 5 · 2026-05-15T12:44:21.429Z_

<details><summary>↩ Tool result · `toolu_01Q3AZhB62QvEKxwY6fGk4dR`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/abstract.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/discussion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/conclusion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/method.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/related_work.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/conclusion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/main.tex
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/abstract.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e73085aa-a19a-4491-8928-774c1c3eb57c",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "bd3d9b9e-db15-47e2-81a3-c26c113c51a3",
  "sourceToolAssistantUUID": "e73085aa-a19a-4491-8928-774c1c3eb57c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 6 · 2026-05-15T12:44:21.886Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01Qqokvjbu3kCiUvtzFse2tb`</summary>

```json
{
  "pattern": "**/*.bib",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bd3d9b9e-db15-47e2-81a3-c26c113c51a3",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NjE4BZPekheqfXtTGw",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "737e47ab-08ea-4b11-b54b-c48b796f1e7f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FS3yYfBMsqvcCgVV6xd4h8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 23030,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 23030,
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

_source line 7 · 2026-05-15T12:44:21.937Z_

<details><summary>↩ Tool result · `toolu_01Qqokvjbu3kCiUvtzFse2tb`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/references.bib
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "737e47ab-08ea-4b11-b54b-c48b796f1e7f",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "0c46ed98-3093-43a7-bbc6-9ed1190cbea6",
  "sourceToolAssistantUUID": "737e47ab-08ea-4b11-b54b-c48b796f1e7f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 8 · 2026-05-15T12:44:22.353Z_

<details open><summary>🔧 Tool call — Glob · `toolu_013daegt52hdePYJEdX2PR9E`</summary>

```json
{
  "pattern": "**/*.bbl",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0c46ed98-3093-43a7-bbc6-9ed1190cbea6",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NjE4BZPekheqfXtTGw",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "dbbd3048-00d0-481e-86fe-2a18622233b1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FS3yYfBMsqvcCgVV6xd4h8",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 23030,
      "cache_read_input_tokens": 0,
      "output_tokens": 298,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 23030
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 298,
          "cache_read_input_tokens": 0,
          "cache_creation_input_tokens": 23030,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 23030,
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

_source line 9 · 2026-05-15T12:44:22.378Z_

<details><summary>↩ Tool result · `toolu_013daegt52hdePYJEdX2PR9E`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/main.bbl
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dbbd3048-00d0-481e-86fe-2a18622233b1",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "aa7402c7-f802-4574-8900-8b3bc0b6be06",
  "sourceToolAssistantUUID": "dbbd3048-00d0-481e-86fe-2a18622233b1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 10 · 2026-05-15T12:44:24.499Z_

Now let me read all the relevant files in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "aa7402c7-f802-4574-8900-8b3bc0b6be06",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nja1Eaidmh7e9xwoU3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8c44770a-ec57-4151-bf03-43a7e6fee3e7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0186mdNGes35NVZUJgjVCnbB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1810,
      "cache_read_input_tokens": 23030,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1810,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 8,
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

_source line 11 · 2026-05-15T12:44:25.007Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CUHoNpdKAcdnLS4xX2Ykh3`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8c44770a-ec57-4151-bf03-43a7e6fee3e7",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nja1Eaidmh7e9xwoU3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "fa41801c-4887-459e-8ab6-b658754d430f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0186mdNGes35NVZUJgjVCnbB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1810,
      "cache_read_input_tokens": 23030,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1810,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 8,
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

_source line 12 · 2026-05-15T12:44:25.021Z_

<details><summary>↩ Tool result · `toolu_01CUHoNpdKAcdnLS4xX2Ykh3`</summary>

```text
1	\section{Introduction}\label{sec:introduction}
2	
3	Self-consistency---sampling multiple outputs and aggregating them---has become a powerful strategy for improving language model reasoning.
4	On discrete-answer tasks such as arithmetic and commonsense QA, majority voting over chain-of-thought samples yields large gains: +18 percentage points on GSM8K (PaLM-540B; \citealp{wang2023selfconsistency}).
5	More broadly, test-time compute scaling through repeated sampling and selection has emerged as a complementary axis to model scaling, offering substantial quality improvements at inference time \cite{snell2025scaling, brown2024monkeys}.
6	These results rest on a shared assumption: that among $N$ stochastic samples, a selection mechanism can identify better outputs.
7	For tasks with a single correct answer, this assumption holds naturally---the majority vote is the selector.
8	But information extraction (IE) poses a fundamentally different challenge.
9	The output is not a single token or number; it is a \textit{set} of entities or relations with internal dependencies, where two samples may extract overlapping but non-identical structures.
10	There is no obvious majority to vote on, partial agreement is the norm rather than the exception, and the space of valid outputs is combinatorially large.
11	Can self-consistency still provide useful signal in this structured setting?
12	
13	Prior work on confidence estimation for LLM-based IE has conflated two distinct objectives: \textit{quality estimation} (which inputs does the model handle reliably?) and \textit{sample selection} (which of $N$ outputs is best?).
14	These require fundamentally different signal properties: the former benefits from instance-level aggregation, while the latter demands per-sample discrimination.
15	Self-consistency methods for discrete answers \cite{wang2023selfconsistency, chen2024usc} and weighted variants \cite{taubenfeld2025cisc, kang2025selfcertainty} assume outputs can be grouped by equivalence---an assumption that breaks for entity sets with partial overlap.
16	The most relevant study, \citet{nedellec2026consistency}, examines consistency--accuracy correlations for LLM-based IE, finding results that our quality-estimation analysis corroborates.
17	Our work extends theirs in three directions: (i)~structural matching beyond surface-level agreement, (ii)~testing whether quality estimation translates to best-of-$N$ selection (it does not), and (iii)~a difficulty gradient revealing non-obvious findings---WNUT-17 conditional correlations collapse to $\rho{=}0.038$ (n.s.) and LP exhibits strong \textit{negative} correlation ($\rho{=}{-}0.410$)---that would be invisible on a single dataset.
18	
19	Structured IE requires schema-compliant output, making constrained decoding \cite{willard2023guided} the standard inference strategy---without it, a substantial fraction of outputs from general-purpose models are unparseable.\footnote{Fine-tuned models may retain format compliance without grammar constraints: our free-form ablation achieves 99.95\% valid JSON rate (\S\ref{sec:ablation}).}
20	All experiments use constrained decoding, the regime under which structured IE is practically deployed.
21	
22	Our central finding is the \textbf{correlation-selection gap} (Figure~\ref{fig:overview}): consistency-based signals achieve strong quality estimation ($\rho$ up to 0.38, AUROC up to 0.75) but fail at sample selection despite 13--18~pp of oracle headroom.
23	Four of five signals are instance-level by construction---this is definitional, not empirical.
24	The non-trivial questions are whether (a)~consensus-proximity selection, instantiating MBR decoding \cite{eikema2022sampling, freitag2022high, muller2021understanding}, can recover per-sample discrimination, and (b)~whether log-probability, the only per-sample signal, can exploit the headroom.
25	Both fail: MBR utility correlates with F1 across instances but not within them (\S\ref{sec:discussion}); log-probability scores are severely compressed (60\% of instances effectively tied), though where compression is mitigated, LP becomes a significant selector ($+2.9$~pp, $p{=}0.01$).
26	A controlled free-form decoding ablation confirms that this compression is intrinsic to the model and task, not an artifact of constrained decoding (\S\ref{sec:ablation}).
27	
28	\begin{figure*}[t]
29	\centering
30	\includegraphics[width=\textwidth]{fig_overview}
31	\caption{The correlation-selection gap. \textbf{Left}: high inter-sample agreement correlates with high F1 (quality estimation). \textbf{Right}: instance-level signals assign identical scores to all candidates, precluding sample selection.}
32	\label{fig:overview}
33	\end{figure*}
34	
35	We systematically compare five confidence signals from three families---structural (entity voting confidence [VC], Soft Jaccard [SJ]), surface (exact match [EM], Fleiss' $\kappa$ [FK]), and model-internal (log-probability [LP])---across NER and RE on SciERC \cite{luan2018scierc}, CoNLL-2003 \cite{tjongkimsang2003conll}, and WNUT-17 \cite{derczynski2017wnut}, using Qwen3-8B and LLaMA-3.1-8B.
36	Our contributions are:
37	\begin{enumerate}
38	    \item \textbf{A systematic evaluation framework.}
39	    We compare five confidence signals from three families---structural, surface, and model-internal---across quality estimation, binary discrimination, and sample selection, showing that these metrics decouple and single-metric evaluation risks selecting the wrong signal.
40	
41	    \item \textbf{The correlation-selection gap and its diagnosis.}
42	    Strong quality estimation ($\rho{=}0.38$, AUROC${=}0.75$) coexists with selection failure ($p{>}0.39$, 13--18~pp oracle headroom).
43	    The instance-level failure of four signals is definitional; the empirical contributions are diagnosing why consensus-proximity selection (MBR decoding) and log-probability both fail.
44	    LP score compression (60\% of instances effectively tied) is the primary bottleneck; where compression is mitigated, LP becomes a significant selector ($+2.9$~pp, $p{=}0.01$).
45	    A controlled ablation confirms that compression is intrinsic, not decoding-regime-specific.
46	
47	    \item \textbf{Task-complexity boundary conditions.}
48	    Signal rankings shift with task difficulty: EM leads on easy tasks, SJ on hard tasks---consistent across two model families at 8B scale, though with model-dependent magnitude.
49	    At the capability boundary (WNUT-17, 52\% zero F1), conditional correlations collapse to non-significance and LP exhibits strong negative correlation ($\rho{=}{-}0.410$)---phenomena invisible on a single dataset that extend \citet{nedellec2026consistency}'s quality-estimation analysis.
50	    NER findings span three datasets; RE conclusions rest on SciERC alone (preliminary).
51	\end{enumerate}
52	
53	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fa41801c-4887-459e-8ab6-b658754d430f",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "b9ab9d46-e417-40a8-9fcd-99b0e5c41beb",
  "sourceToolAssistantUUID": "fa41801c-4887-459e-8ab6-b658754d430f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-15T12:44:25.425Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DmKyKMkTPWw81YULnCwBQw`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b9ab9d46-e417-40a8-9fcd-99b0e5c41beb",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nja1Eaidmh7e9xwoU3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "71409c96-ff93-4bfc-9667-65b441a826e6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0186mdNGes35NVZUJgjVCnbB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1810,
      "cache_read_input_tokens": 23030,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1810,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 8,
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

_source line 14 · 2026-05-15T12:44:25.430Z_

<details><summary>↩ Tool result · `toolu_01DmKyKMkTPWw81YULnCwBQw`</summary>

```text
1	\begin{abstract}
2	Test-time scaling through repeated sampling promises quality gains for LLM-based information extraction (IE), but whether confidence signals can identify the best output among multiple candidates remains untested for structured tasks.
3	We evaluate five confidence signals on three NER benchmarks and one RE benchmark with two 8B-parameter model families.
4	All signals achieve strong quality estimation ($\rho$ up to 0.38, AUROC up to 0.75) yet none significantly improves sample selection despite 13--18~pp oracle headroom---a \textit{correlation-selection gap}.
5	For four of five signals, selection failure follows from their definition as instance-level scores; the empirical question is whether per-sample log-probability or consensus-proximity selection (MBR decoding) can bridge the gap.
6	Neither succeeds: log-probability scores are compressed into effective ties within instances, and MBR utility correlates with quality across instances but not within them.
7	A controlled ablation on NER confirms that LP compression persists without constrained decoding; on RE, LP selection reverses direction, suggesting task-dependent interaction with decoding regime.
8	These findings, consistent across two model families at 8B scale, indicate that closing the gap likely requires per-sample scoring beyond unsupervised signals.
9	\end{abstract}
10	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "71409c96-ff93-4bfc-9667-65b441a826e6",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "21ecaf5a-1e17-4294-a803-9cc9674414e5",
  "sourceToolAssistantUUID": "71409c96-ff93-4bfc-9667-65b441a826e6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-15T12:44:26.415Z_

<details open><summary>🔧 Tool call — Read · `toolu_018k98dnpKAK8qDGJGYYvMgy`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "21ecaf5a-1e17-4294-a803-9cc9674414e5",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nja1Eaidmh7e9xwoU3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "4b3dfb60-5a37-41c9-8d75-4a6661f8167f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0186mdNGes35NVZUJgjVCnbB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1810,
      "cache_read_input_tokens": 23030,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1810,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 8,
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

_source line 16 · 2026-05-15T12:44:26.422Z_

<details><summary>↩ Tool result · `toolu_018k98dnpKAK8qDGJGYYvMgy`</summary>

```text
1	\begin{abstract}
2	Test-time scaling through repeated sampling promises quality gains for LLM-based information extraction, but whether confidence signals can identify the best output among multiple candidates remains untested for structured tasks.
3	Under constrained decoding---the standard regime for schema-compliant IE---we evaluate five confidence signals from three families across NER and relation extraction on three benchmarks with two 8B-parameter model families.
4	These signals achieve strong quality estimation, yet none significantly improves sample selection over greedy decoding despite 13--18 percentage points of oracle headroom.
5	Four of five signals are instance-level by construction and cannot rank candidates; the key empirical question is whether log-probability---the sole per-sample signal---or consensus-proximity selection can bridge this gap.
6	Neither succeeds: log-probability scores are compressed into effective ties for 60\% of instances under constrained decoding, while consensus-proximity (MBR decoding) fails because utility correlates with quality across instances but not within them.
7	Where log-probability compression is absent, selection recovers significant gains ($+2.9$~pp, $p{=}0.01$), identifying constrained-decoding score compression as the primary bottleneck.
8	Signal rankings further depend on task complexity, with findings consistent across model families.
9	\end{abstract}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4b3dfb60-5a37-41c9-8d75-4a6661f8167f",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "45c8237f-2301-49b1-b8bb-0fb80221d92e",
  "sourceToolAssistantUUID": "4b3dfb60-5a37-41c9-8d75-4a6661f8167f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-15T12:44:26.871Z_

<details open><summary>🔧 Tool call — Read · `toolu_012R9JV6JqfwH7ZErptS878N`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "45c8237f-2301-49b1-b8bb-0fb80221d92e",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nja1Eaidmh7e9xwoU3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "fb069998-3050-428d-bdfb-e645f653ed20",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0186mdNGes35NVZUJgjVCnbB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1810,
      "cache_read_input_tokens": 23030,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1810,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 8,
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

_source line 18 · 2026-05-15T12:44:26.877Z_

<details><summary>↩ Tool result · `toolu_012R9JV6JqfwH7ZErptS878N`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\subsection{Experimental Setup}
5	\label{sec:setup}
6	
7	\paragraph{Datasets.}
8	We evaluate on three English IE benchmarks spanning a difficulty gradient.
9	\textbf{SciERC} \cite{luan2018scierc} contains 551 test instances annotated for joint NER (6 types) and RE (7 types).
10	\textbf{CoNLL-2003} \cite{tjongkimsang2003conll} provides 3{,}453 test sentences with 4 entity types, where models achieve ${\approx}$91\% micro F1.
11	\textbf{WNUT-17} \cite{derczynski2017wnut} consists of 1{,}287 social media instances with emerging entities, used to probe method boundaries (52\% zero F1).
12	
13	\paragraph{Models and sampling.}
14	Both \textbf{Qwen3-8B} and \textbf{LLaMA-3.1-8B-Instruct} are fine-tuned with LoRA (rank$=$32, $\alpha{=}64$) for 5 epochs using LLaMA Factory \cite{zheng2024llamafactory} under identical training procedures, ensuring comparisons across the two model families (both at 8B scale) reflect model differences rather than training confounds.
15	We note a training confound for SciERC: Qwen3-8B's SciERC checkpoint was trained with \texttt{enable\_thinking=True} (LLaMA Factory 0.9.4 default), which prepends empty \texttt{&lt;think>\textbackslash n&lt;/think>} blocks (4--5 tokens) to each training response and includes them in the loss computation; CoNLL-2003 and WNUT-17 checkpoints explicitly set \texttt{enable\_thinking=False}.
16	No reasoning content is present (the blocks are always empty), and constrained decoding at inference time enforces JSON-only output, so thinking tokens do not appear in generated samples.
17	This constitutes a minor train--test distribution mismatch for SciERC ($<$0.3\% of the 2048-token training window); CoNLL-2003 and WNUT-17 are unaffected.
18	We discuss implications in the Limitations section.
19	We draw $N{=}8$ samples at $T{=}1.0$ (primary; single seed, seed${=}42$), with $N{=}16$ for scaling experiments.\footnote{$N{=}16$ results for CoNLL (Qwen) and SciERC (LLaMA) are in Table~\ref{tab:robustness} (Appendix~\ref{app:robustness}). A 3-seed stability analysis ($\sigma{\leq}0.026$; Table~\ref{tab:multiseed}, Appendix~\ref{app:multiseed}) confirms that signal rankings are identical across seeds.}
20	Quality estimation uses Spearman $\rho$ and AUROC; downstream utility uses best-of-$N$ selection F1 with exact span matching (NER) and head-tail-label matching (RE).
21	Inference uses vLLM with constrained decoding \cite{willard2023guided}.
22	
23	%% ============================================================
24	\subsection{Quality Estimation Results}
25	\label{sec:qe_results}
26	
27	\begin{table*}[t]
28	\centering
29	\small
30	\caption{Quality estimation across tasks and models (Spearman $\rho$ and AUROC; $N{=}8$, seed${=}42$). Best value per column in \textbf{bold}. SciERC evaluates joint NER (6 types) and RE (7 types, single benchmark---preliminary); CoNLL evaluates NER (4 types). $N{=}16$ results appear in Table~\ref{tab:robustness} (Appendix~\ref{app:robustness}).}
31	\label{tab:quality_estimation}
32	\begin{tabular}{ll cc cc cc cc}
33	\toprule
34	& & \multicolumn{2}{c}{\textbf{SciERC NER}} & \multicolumn{2}{c}{\textbf{SciERC RE}} & \multicolumn{2}{c}{\textbf{CoNLL (Qwen)}} & \multicolumn{2}{c}{\textbf{CoNLL (LLaMA)}} \\
35	\cmidrule(lr){3-4} \cmidrule(lr){5-6} \cmidrule(lr){7-8} \cmidrule(lr){9-10}
36	Signal & Family & $\rho$ & AUC & $\rho$ & AUC & $\rho$ & AUC & $\rho$ & AUC \\
37	\midrule
38	VC & Structural & \textbf{.379} & .684 & \textbf{.350} & .693 & .424 & .789 & .426 & .709 \\
39	SJ  & Structural & .360 & .692 & .250 & .670 & .436 & .801 & \textbf{.431} & .704 \\
40	FK & Surface & .267 & .629 & .275 & .609 & .400 & .774 & .428 & .703 \\
41	EM  & Surface    & .295 & \textbf{.749} & .134 & \textbf{.706} & \textbf{.451} & \textbf{.816} & \textbf{.431} & .705 \\
42	LP     & Model      & .205 & .578 & .266 & .600 & .316 & .753 & .307 & \textbf{.761} \\
43	\bottomrule
44	\end{tabular}
45	\end{table*}
46	
47	\begin{figure*}[t]
48	\centering
49	\includegraphics[width=\textwidth]{fig_signal_heatmap}
50	\caption{Quality estimation heatmap (Spearman $\rho$) across five signals and four configurations. Left: full evaluation set; right: conditional set (non-zero F1 instances). On the full set, structural signals dominate on SciERC while all signals converge on CoNLL. On the conditional set, EM emerges as the strongest signal on both NER ($\rho{=}0.360$) and RE ($\rho{=}0.417$), while LP RE collapses to near-zero ($\rho{=}0.011$).}
51	\label{fig:signal_heatmap}
52	\end{figure*}
53	
54	Table~\ref{tab:quality_estimation} presents rank correlation ($\rho$) and AUROC for five confidence signals across tasks and models.
55	
56	\paragraph{Difficulty-dependent signal complementarity.}
57	On SciERC NER (complex schema, 6 types), structural signals lead: VC achieves $\rho{=}0.379$ and SJ $\rho{=}0.360$, both outperforming surface ($\rho{\leq}0.295$) and LP ($\rho{=}0.205$).
58	This advantage persists on RE (VC $\rho{=}0.350$; preliminary, single benchmark), though all signals weaken due to the 40\% zero-F1 floor effect.
59	VC and SJ show moderate instance-level correlation (NER: $\rho{=}0.659$; RE: $\rho{=}0.605$), indicating information overlap but not redundancy; their differential behavior across difficulty levels reflects the complementary granularity of entity-level frequency vs.\ span-level set overlap.
60	While the best $\rho{=}0.38$ (VC) explains approximately 14\% of F1 variance, the best AUROC reaches 0.749 (EM), indicating strong binary discriminative power for the quality/failure classification most relevant to practitioners in quality-aware routing.\footnote{Semantic entropy \cite{kuhn2023semantic} achieves comparable AUROC on discrete-answer QA; direct comparison is not meaningful due to different output spaces.}
61	Pairwise bootstrap CIs confirm the SJ advantage over LP ($\Delta\rho{=}{+}0.155$, CI excludes zero) but not over EM ($\Delta\rho{=}{+}0.065$, marginal under Bonferroni correction; Table~\ref{tab:bootstrap_signal_ci}, Appendix~\ref{app:bootstrap_signal}).
62	
63	\paragraph{$\rho$--AUROC dissociation.}
64	Signal choice depends on the intended use: on NER, EM leads AUROC (0.749) despite ranking third in $\rho$ (0.295), preferred for binary quality triage; structural signals ($\rho{\geq}0.36$) are better for fine-grained ranking.
65	On CoNLL with LLaMA, LP leads AUROC (0.761) yet trails in $\rho$ (0.307), confirming this pattern across datasets.
66	
67	\paragraph{Signal rankings shift with task difficulty.}
68	On CoNLL (greedy F1${\approx}$0.91), EM leads ($\rho{=}0.451$, AUROC${=}0.816$), surpassing SJ and VC.
69	When most samples are near-correct, binary agreement captures remaining variance more efficiently than set-level similarity.
70	This crossover---EM${>}$SJ on easy tasks vs.\ SJ${>}$EM on hard tasks---demonstrates difficulty-dependent complementarity rather than a universal structural advantage, suggesting practitioners should match signal type to expected task difficulty.
71	Stability across the two model families (both 8B) is strong: SJ achieves $\rho{=}0.436$ (Qwen) vs.\ $0.431$ (LLaMA) on CoNLL ($\Delta{=}0.005$, within 3-seed $\sigma{\approx}0.007$).
72	On WNUT-17, where 52\% of instances receive zero F1, full-set correlations are misleading: VC achieves $\rho{=}0.724$ (AUROC${=}0.913$), but this is entirely driven by the zero/non-zero boundary (conditional $\rho{=}0.038$, n.s.; Table~\ref{tab:wnut}).
73	LP exhibits strong \textit{negative} correlation ($\rho{=}{-}0.410$, AUROC${=}0.219$).
74	We hypothesize that this reversal reflects overconfidence on out-of-distribution inputs \citep{xiong2024llm}: the model assigns high log-probabilities to fluent but incorrect entity patterns (e.g., common noun phrases that resemble but do not match rare WNUT entity types), while producing lower scores for genuinely uncertain outputs where it correctly hedges.
75	On the conditional set, all signals collapse toward weak or non-significant correlations ($\rho{\leq}0.35$), with SJ achieving only $\rho{=}0.089$ ($p{=}0.020$) on the full set---suggesting a capability boundary beyond which consistency signals capture binary success/failure but not quality gradation.
76	
77	\paragraph{Conditional filtering.}
78	Filtering to non-zero F1 instances reshuffles rankings (Figure~\ref{fig:signal_heatmap}, right).
79	EM emerges as the strongest conditional signal on both NER ($\rho{=}0.360$) and RE ($\rho{=}0.417$; preliminary), while VC and FK drop substantially (VC NER: $0.379{\to}0.300$; FK NER: $0.267{\to}0.176$).
80	LP RE collapses to $\rho{=}0.011$, confirming its full-set correlation was driven by zero/non-zero separation.
81	This creates a natural complementarity: VC and SJ are preferred on the full set, while EM provides the most precise ranking within the non-trivial subset (see Appendix~\ref{app:additional} for details).
82	
83	%% ============================================================
84	\subsection{The Correlation-Selection Gap}
85	\label{sec:selection_gap}
86	
87	\begin{figure*}[t]
88	\centering
89	\includegraphics[width=\textwidth]{fig_selection_gap}
90	\caption{The correlation-selection gap on SciERC ($N{=}8$, $T{=}1.0$). Left: NER; right: RE. Bars show best-of-$N$ selection F1; the line marks quality estimation $\rho$. Despite $\rho$ up to 0.38, no signal significantly outperforms greedy on either task ($p{=}0.39$ for NER LP, the best signal; Table~\ref{tab:selection}). Dashed line indicates oracle upper bound.}
91	\label{fig:selection_gap}
92	\end{figure*}
93	
94	\begin{table}[t]
95	\centering
96	\small
97	\caption{Best-of-$N$ selection F1 on SciERC ($N{=}8$, $T{=}1.0$). RE results are from a single benchmark (preliminary). Best non-oracle result per column in \textbf{bold}. EM selects the plurality output; despite a 42\% pairwise exact-match rate, EM selection underperforms greedy on both tasks.}
98	\label{tab:selection}
99	\begin{tabular}{lcc}
100	\toprule
101	Method & NER F1 & RE F1 \\
102	\midrule
103	Oracle & 0.776 & 0.585 \\
104	\midrule
105	LP           & \textbf{0.650} & 0.395 \\
106	SJ       & 0.645 & 0.386 \\
107	EM        & 0.636 & 0.372 \\
108	VC                 & 0.634 & 0.359 \\
109	\midrule
110	Greedy ($T{=}0$)   & 0.644 & \textbf{0.404} \\
111	Random             & 0.608 & 0.354 \\
112	\bottomrule
113	\end{tabular}
114	\end{table}
115	
116	Despite strong quality estimation, confidence signals yield limited gains when used for best-of-$N$ selection (Table~\ref{tab:selection}, Figure~\ref{fig:selection_gap}).
117	Four of five signals are instance-level aggregates that assign a single score per input regardless of which sample is evaluated; they cannot rank candidates by construction.
118	The non-trivial question is whether log-probability---the only per-sample signal---can exploit the oracle headroom.
119	We anchor this analysis on SciERC, where output diversity is substantial: only 11--18\% of instances produce identical outputs across all $N{=}8$ samples, with 39--43\% unique outputs per instance (mean 3.5 distinct outputs), per-sample F1 standard deviation of 0.11--0.14, and mean pairwise SJ of 0.703.
120	
121	\paragraph{No significant improvement over greedy.}
122	We exclude 22 instances with empty gold annotations ($n{=}529$) and evaluate significance via instance-level paired bootstrap resampling ($B{=}10{,}000$).
123	On NER, the oracle (0.776) reveals 13.2~pp of headroom above greedy (0.644).
124	LP achieves the highest selection F1 (0.650, +0.6~pp), but this is not significant ($p{=}0.39$; 95\% CI: [$-$3.0, +4.2]~pp; Cohen's $d{=}0.038$).
125	On RE, the best signal (LP, 0.395) falls below greedy (0.404, $-0.9$\,pp, $p{=}0.80$), while 18.1~pp of oracle headroom remains.
126	TOST equivalence testing confirms most signals are indistinguishable from greedy at ${\pm}2$--$3$~pp on NER; on RE, EM and VC fail equivalence even at ${\pm}5$~pp (Table~\ref{tab:tost}, Appendix~\ref{app:diversity}).
127	VC ($\rho{=}0.379$, the best quality estimator) selects to only 0.634 on NER---\textit{below} greedy.
128	The gap extends to CoNLL (ceiling effect, 57--88\% identical outputs) and WNUT-17 (capability boundary; Table~\ref{tab:cross_selection}).
129	
130	\paragraph{Quality estimation $\neq$ output selection.}
131	Instance-level confidence signals predict \textit{which inputs} the model handles reliably, not \textit{which output} among $N$ candidates is best.
132	When per-sample variance is low relative to instance-level difficulty, even perfect quality estimation cannot discriminate among near-identical candidates.
133	This gap has direct consequences for test-time scaling in IE \cite{brown2024monkeys, snell2025scaling}: closing it likely requires per-sample signals such as trained verifiers \cite{cobbe2021verifiers}.
134	
135	%% ============================================================
136	\subsection{Robustness}
137	\label{sec:robustness_main}
138	
139	Consistency-based signals show robust performance across $T{\in}\{0.7, 1.0\}$ (SJ NER $\Delta\rho{=}0.028$, bootstrap CI includes zero) and sublinear gains from $N{=}8$ to $N{=}16$, with structural signals maintaining their advantage over LP across all NER settings ($\Delta\rho{=}{+}0.135$ to ${+}0.175$; Table~\ref{tab:robustness}, Appendix~\ref{app:robustness}).
140	On RE, only VC consistently outperforms LP ($\Delta\rho{=}{+}0.012$, preliminary).
141	NER signals are reasonably calibrated (ECE 0.069--0.096; Appendix~\ref{app:calibration}), while RE miscalibration (ECE 0.109--0.339) and compound errors impose a ceiling at $\rho{\approx}0.28$ for $N{=}16$.
142	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fb069998-3050-428d-bdfb-e645f653ed20",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "023cff0a-c88c-4d69-839c-ba9654e92c4c",
  "sourceToolAssistantUUID": "fb069998-3050-428d-bdfb-e645f653ed20",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-15T12:44:27.381Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Lkz5m6P7qpqyYhZtUJsq83`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "023cff0a-c88c-4d69-839c-ba9654e92c4c",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nja1Eaidmh7e9xwoU3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "572e59ec-172f-4d9e-a733-df830b3dcf45",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0186mdNGes35NVZUJgjVCnbB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1810,
      "cache_read_input_tokens": 23030,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1810,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 8,
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

_source line 20 · 2026-05-15T12:44:27.388Z_

<details><summary>↩ Tool result · `toolu_01Lkz5m6P7qpqyYhZtUJsq83`</summary>

```text
1	\documentclass[11pt]{article}
2	
3	\usepackage[review]{acl}
4	
5	\usepackage{times}
6	\usepackage{latexsym}
7	\usepackage[T1]{fontenc}
8	\usepackage[utf8]{inputenc}
9	\usepackage{microtype}
10	\usepackage{inconsolata}
11	\usepackage{graphicx}
12	\usepackage{booktabs}
13	\usepackage{amsmath}
14	\usepackage{amssymb}
15	\usepackage{multirow}
16	\usepackage{xcolor}
17	\usepackage{subcaption}
18	
19	\graphicspath{{figures/}}
20	
21	\title{Strong Predictors, Weak Selectors:\\ Confidence Signals Predict but Cannot Select in 8B-Scale Information Extraction}
22	
23	\author{Anonymous}
24	
25	\begin{document}
26	\maketitle
27	
28	\input{sections/abstract}
29	\input{sections/introduction}
30	\input{sections/related_work}
31	\input{sections/method}
32	\input{sections/experiments}
33	\input{sections/discussion}
34	\input{sections/conclusion}
35	
36	\section*{Limitations}
37	\input{sections/limitations}
38	
39	\section*{Ethics Statement}
40	All experiments use publicly available benchmarks (SciERC, CoNLL-2003, WNUT-17) and open-weight models (Qwen3-8B, LLaMA-3.1-8B).
41	CoNLL-2003 is derived from the Reuters RCV1 corpus, which is available for research purposes under a NIST agreement; we use the standard research distribution.
42	No new human data was collected or annotated for this study.
43	Our findings on signal limitations could inform more reliable deployment of IE systems by guiding practitioners toward appropriate confidence signals for their use case.
44	
45	\bibliography{references}
46	
47	\appendix
48	\input{sections/appendix}
49	
50	\end{document}
51	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "572e59ec-172f-4d9e-a733-df830b3dcf45",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "e4a87183-9293-4613-b0d4-acb1dc554d90",
  "sourceToolAssistantUUID": "572e59ec-172f-4d9e-a733-df830b3dcf45",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-15T12:44:28.341Z_

<details open><summary>🔧 Tool call — Read · `toolu_01EpEChJjUTVnb9nxYYcaoJq`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e4a87183-9293-4613-b0d4-acb1dc554d90",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nja1Eaidmh7e9xwoU3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "90a529c4-3f82-4a73-b71d-559fb82c54c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0186mdNGes35NVZUJgjVCnbB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1810,
      "cache_read_input_tokens": 23030,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1810,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 8,
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

_source line 22 · 2026-05-15T12:44:28.348Z_

<details><summary>↩ Tool result · `toolu_01EpEChJjUTVnb9nxYYcaoJq`</summary>

```text
1	% Auto-generated from literature_map.yaml — do not edit manually
2	
3	@inproceedings{angelopoulos2021conformal,
4	  title = {Uncertainty Sets for Image Classifiers using Conformal Prediction},
5	  author = {Angelopoulos, Anastasios N. and Bates, Stephen and Malik, Jitendra and Jordan, Michael I.},
6	  booktitle = {ICLR 2021},
7	  year = {2021},
8	  url = {https://arxiv.org/abs/2009.14193}
9	}
10	
11	@article{brown2024monkeys,
12	  title = {Large Language Monkeys: Scaling Inference Compute with Repeated Sampling},
13	  author = {Brown, Bradley and Juravsky, Jordan and Ehrlich, Ryan and Clark, Ronald and Le, Quoc V. and Ré, Christopher and Mirhoseini, Azalia},
14	  journal = {arXiv preprint arXiv:2407.21787},
15	  year = {2024},
16	  url = {https://arxiv.org/abs/2407.21787}
17	}
18	
19	@inproceedings{chen2024usc,
20	  title = {Universal Self-Consistency for Large Language Model Generation},
21	  author = {Chen, Xinyun and Aksitov, Renat and Alon, Uri and Ren, Jie and Xiao, Kefan and Yin, Pengcheng and Prakash, Sushant and Sutton, Charles and Wang, Xuezhi and Zhou, Denny},
22	  booktitle = {arXiv preprint (ICML 2024 Workshop ICL)},
23	  year = {2024},
24	  url = {https://arxiv.org/abs/2311.17311}
25	}
26	
27	@article{cobbe2021verifiers,
28	  title = {Training Verifiers to Solve Math Word Problems},
29	  author = {Cobbe, Karl and Kosaraju, Vineet and Bavarian, Mohammad and Chen, Mark and Jun, Heewoo and Kaiser, Lukasz and Plappert, Matthias and Tworek, Jerry and Hilton, Jacob and Nakano, Reiichiro and Hesse, Christopher and Schulman, John},
30	  journal = {arXiv preprint arXiv:2110.14168},
31	  year = {2021},
32	  url = {https://arxiv.org/abs/2110.14168}
33	}
34	
35	@inproceedings{culotta2004confidence,
36	  title = {Confidence Estimation for Information Extraction},
37	  author = {Culotta, Aron and McCallum, Andrew},
38	  booktitle = {HLT-NAACL 2004},
39	  year = {2004},
40	  url = {https://aclanthology.org/N04-4028/}
41	}
42	
43	@inproceedings{derczynski2017wnut,
44	  title = {Results of the WNUT2017 Shared Task on Novel and Emerging Entity Recognition},
45	  author = {Derczynski, Leon and Nichols, Eric and Erp, Marieke van and Limsopatham, Nut},
46	  booktitle = {W-NUT Workshop at EMNLP 2017},
47	  year = {2017},
48	  url = {https://aclanthology.org/W17-4418/}
49	}
50	
51	@inproceedings{desai2020calibration,
52	  title = {Calibration of Pre-trained Transformers},
53	  author = {Desai, Shrey and Durrett, Greg},
54	  booktitle = {Proceedings of the 2020 Conference on Empirical Methods in Natural Language Processing (EMNLP)},
55	  year = {2020},
56	  doi = {10.18653/v1/2020.emnlp-main.21},
57	  url = {http://dx.doi.org/10.18653/v1/2020.emnlp-main.21}
58	}
59	
60	@inproceedings{eikema2022sampling,
61	  title = {Sampling-Based Approximations to Minimum {B}ayes Risk Decoding for Neural Machine Translation},
62	  author = {Eikema, Bryan and Aziz, Wilker},
63	  booktitle = {Proceedings of the 2022 Conference on Empirical Methods in Natural Language Processing},
64	  year = {2022},
65	  pages = {10978--10993},
66	  doi = {10.18653/v1/2022.emnlp-main.754}
67	}
68	
69	@inproceedings{fisch2021conformal,
70	  title = {Few-Shot Conformal Prediction with Auxiliary Tasks},
71	  author = {Fisch, Adam and Schuster, Tal and Jaakkola, Tommi and Barzilay, Regina},
72	  booktitle = {ICML 2021},
73	  year = {2021},
74	  doi = {10.5555/3524938.3525234},
75	  url = {https://arxiv.org/abs/2102.08898}
76	}
77	
78	@article{freitag2022high,
79	  title = {High Quality Rather than High Model Probability: Minimum {B}ayes Risk Decoding with Neural Metrics},
80	  author = {Freitag, Markus and Grangier, David and Tan, Qijun and Liang, Bowen},
81	  journal = {Transactions of the Association for Computational Linguistics},
82	  volume = {10},
83	  year = {2022},
84	  pages = {811--825},
85	  doi = {10.1162/tacl_a_00491}
86	}
87	
88	@inproceedings{he2024uncertainty,
89	  title = {Uncertainty Estimation on Sequential Labeling via Uncertainty Transmission},
90	  author = {He, Jianfeng and Yu, Linlin and Lei, Shuo and Lu, Chang-Tien and Chen, Feng},
91	  booktitle = {Findings of the Association for Computational Linguistics: NAACL 2024},
92	  year = {2024},
93	  pages = {2823--2835},
94	  doi = {10.18653/v1/2024.findings-naacl.180}
95	}
96	
97	@article{fleiss1971agreement,
98	  title = {Measuring nominal scale agreement among many raters.},
99	  author = {Fleiss, Joseph L.},
100	  journal = {Psychological Bulletin},
101	  year = {1971},
102	  doi = {10.1037/h0031619},
103	  url = {http://dx.doi.org/10.1037/h0031619}
104	}
105	
106	@inproceedings{gal2016dropout,
107	  title = {Dropout as a Bayesian Approximation: Representing Model Uncertainty in Deep Learning},
108	  author = {Gal, Yarin and Ghahramani, Zoubin},
109	  booktitle = {ICML 2016},
110	  year = {2016},
111	  url = {https://arxiv.org/abs/1506.02142}
112	}
113	
114	@inproceedings{geifman2017selective,
115	  title = {Selective Classification for Deep Neural Networks},
116	  author = {Geifman, Yonatan and El-Yaniv, Ran},
117	  booktitle = {NeurIPS 2017},
118	  year = {2017},
119	  url = {https://arxiv.org/abs/1705.08500}
120	}
121	
122	@article{feng2025optimal,
123	  title = {Optimal Self-Consistency for Efficient Reasoning with Large Language Models},
124	  author = {Feng, Austin and Alonso, Marius and Odonnat, Ambroise},
125	  journal = {arXiv preprint arXiv:2511.12309},
126	  year = {2025},
127	  url = {https://arxiv.org/abs/2511.12309}
128	}
129	
130	@inproceedings{geng2024confidence,
131	  title = {A Survey of Confidence Estimation and Calibration in Large Language Models},
132	  author = {Geng, Jiahui and Cai, Fengyu and Wang, Yuxia and Koeppl, Heinz and Nakov, Preslav and Gurevych, Iryna},
133	  booktitle = {Proceedings of the 2024 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies (Volume 1: Long Papers)},
134	  year = {2024},
135	  doi = {10.18653/v1/2024.naacl-long.366},
136	  url = {http://dx.doi.org/10.18653/v1/2024.naacl-long.366}
137	}
138	
139	@inproceedings{guo2017calibration,
140	  title = {On Calibration of Modern Neural Networks},
141	  author = {Guo, Chuan and Pleiss, Geoff and Sun, Yu and Weinberger, Kilian Q.},
142	  booktitle = {ICML 2017},
143	  year = {2017},
144	  url = {https://arxiv.org/abs/1706.04599}
145	}
146	
147	@article{hobelsberger2025systematic,
148	  title = {Systematic Evaluation of Uncertainty Estimation Methods in Large Language Models},
149	  author = {Hobelsberger, Christian and Winner, Theresa and Nawroth, Andreas and Mitevski, Oliver and Haensch, Anna-Carolina},
150	  journal = {arXiv preprint arXiv:2510.20460},
151	  year = {2025},
152	  url = {https://arxiv.org/abs/2510.20460}
153	}
154	
155	@article{jaccard1901distribution,
156	  title = {Étude comparative de la distribution florale dans une portion des Alpes et du Jura},
157	  author = {Jaccard, Paul},
158	  journal = {Bulletin de la Société Vaudoise des Sciences Naturelles},
159	  year = {1901},
160	  url = {https://www.researchgate.net/publication/225035806}
161	}
162	
163	@inproceedings{josifoski2022genie,
164	  title = {{GenIE}: Generative Information Extraction},
165	  author = {Josifoski, Martin and De Cao, Nicola and Peyrard, Maxime and Petroni, Fabio and West, Robert},
166	  booktitle = {Proceedings of the 2022 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies (NAACL)},
167	  year = {2022},
168	  doi = {10.18653/v1/2022.naacl-main.342},
169	  url = {https://arxiv.org/abs/2112.08340}
170	}
171	
172	@article{kadavath2022language,
173	  title = {Language Models (Mostly) Know What They Know},
174	  author = {Kadavath, Saurav and Conerly, Tom and Askell, Amanda and Henighan, Tom and Drain, Dawn and Perez, Ethan and Schiefer, Nicholas and Hatfield-Dodds, Zac and DasSarma, Nova and Tran-Johnson, Eli and Johnston, Scott and El-Showk, Sheer and Jones, Andy and Elhage, Nelson and Hume, Tristan and Chen, Anna and Bai, Yuntao and Bowman, Sam and Fort, Stanislav and Ganguli, Deep and Hernandez, Danny and Jacobson, Josh and Kernion, Jackson and Kravec, Shauna and Lovitt, Liane and Ndousse, Kamal and Olsson, Catherine and Ringer, Sam and Amodei, Dario and Brown, Tom and Clark, Jack and Joseph, Nicholas and Mann, Ben and McCandlish, Sam and Olah, Chris and Kaplan, Jared},
175	  journal = {arXiv preprint arXiv:2207.05221},
176	  year = {2022},
177	  url = {https://arxiv.org/abs/2207.05221}
178	}
179	
180	@inproceedings{kang2025selfcertainty,
181	  title = {Scalable Best-of-N Selection for Large Language Models via Self-Certainty},
182	  author = {Kang, Zhewei and Zhao, Xuandong and Song, Dawn},
183	  booktitle = {NeurIPS 2025},
184	  year = {2025},
185	  url = {https://arxiv.org/abs/2502.18581}
186	}
187	
188	@inproceedings{kim2024verifiner,
189	  title = {{V}erifi{NER}: Verification-augmented {NER} via Knowledge-grounded Reasoning with Large Language Models},
190	  author = {Kim, Seoyeon and Seo, Kwangwook and Chae, Hyungjoo and Yeo, Jinyoung and Lee, Dongha},
191	  booktitle = {Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers)},
192	  year = {2024},
193	  pages = {2441--2461},
194	  doi = {10.18653/v1/2024.acl-long.134}
195	}
196	
197	@inproceedings{kim2026reasc,
198	  title = {Reliability-Aware Adaptive Self-Consistency for Efficient Sampling in {LLM} Reasoning},
199	  author = {Kim, Junseok and Yang, Nakyeong and Min, Kyungmin and Jung, Kyomin},
200	  booktitle = {ACL 2026},
201	  year = {2026},
202	  url = {https://arxiv.org/abs/2601.02970}
203	}
204	
205	@article{kossen2024semantic,
206	  title = {Semantic Entropy Probes: Robust and Cheap Hallucination Detection in {LLMs}},
207	  author = {Kossen, Jannik and Han, Jiatong and Razzak, Muhammed and Schut, Lisa and Malik, Shreshth and Gal, Yarin},
208	  journal = {arXiv preprint arXiv:2406.15927},
209	  year = {2024},
210	  url = {https://arxiv.org/abs/2406.15927}
211	}
212	
213	@article{li2025llms,
214	  title = {LLMs Can Generate a Better Answer by Aggregating Their Own Responses},
215	  author = {Li, Zichong and Feng, Xinyu and Cai, Yuheng and Zhang, Zixuan and Liu, Tianyi and Liang, Chen and Chen, Weizhu and Wang, Haoyu and Zhao, Tuo},
216	  journal = {arXiv preprint arXiv:2503.04104},
217	  year = {2025},
218	  url = {https://arxiv.org/abs/2503.04104}
219	}
220	
221	@inproceedings{kuhn2023semantic,
222	  title = {Semantic Uncertainty: Linguistic Invariances for Uncertainty Estimation in Natural Language Generation},
223	  author = {Kuhn, Lorenz and Gal, Yarin and Farquhar, Sebastian},
224	  booktitle = {ICLR 2023},
225	  year = {2023},
226	  url = {https://arxiv.org/abs/2302.09664}
227	}
228	
229	@inproceedings{malinin2021uncertainty,
230	  title = {Uncertainty Estimation in Autoregressive Structured Prediction},
231	  author = {Malinin, Andrey and Gales, Mark},
232	  booktitle = {International Conference on Learning Representations},
233	  year = {2021},
234	  url = {https://openreview.net/forum?id=jN5y-zb5Q7m}
235	}
236	
237	@inproceedings{lakshminarayanan2017ensembles,
238	  title = {Simple and Scalable Predictive Uncertainty Estimation using Deep Ensembles},
239	  author = {Lakshminarayanan, Balaji and Pritzel, Alexander and Blundell, Charles},
240	  booktitle = {NeurIPS 2017},
241	  year = {2017},
242	  url = {https://arxiv.org/abs/1612.01474}
243	}
244	
245	@inproceedings{li2023codeie,
246	  title = {{CodeIE}: Large Code Generation Models are Better Few-Shot Information Extractors},
247	  author = {Li, Peng and Sun, Tianxiang and Tang, Qiong and Yan, Hang and Wu, Yuanbin and Huang, Xuanjing and Qiu, Xipeng},
248	  booktitle = {Proceedings of the 61st Annual Meeting of the Association for Computational Linguistics (ACL)},
249	  year = {2023},
250	  doi = {10.18653/v1/2023.acl-long.855},
251	  url = {https://arxiv.org/abs/2305.05711}
252	}
253	
254	@inproceedings{lightman2024verify,
255	  title = {Let's Verify Step by Step},
256	  author = {Lightman, Hunter and Kosaraju, Vineet and Burda, Yura and Edwards, Harri and Baker, Bowen and Lee, Teddy and Leike, Jan and Schulman, John and Sutskever, Ilya and Cobbe, Karl},
257	  booktitle = {ICLR 2024},
258	  year = {2024},
259	  url = {https://arxiv.org/abs/2305.20050}
260	}
261	
262	@inproceedings{luan2018scierc,
263	  title = {Multi-Task Identification of Entities, Relations, and Coreference for Scientific Knowledge Graph Construction},
264	  author = {Luan, Yi and He, Luheng and Ostendorf, Mari and Hajishirzi, Hannaneh},
265	  booktitle = {Proceedings of the 2018 Conference on Empirical Methods in Natural Language Processing},
266	  year = {2018},
267	  doi = {10.18653/v1/D18-1360},
268	  url = {http://dx.doi.org/10.18653/v1/D18-1360}
269	}
270	
271	@inproceedings{manakul2023selfcheckgpt,
272	  title = {SelfCheckGPT: Zero-Resource Black-Box Hallucination Detection for Generative Large Language Models},
273	  author = {Manakul, Potsawee and Liusie, Adian and Gales, Mark},
274	  booktitle = {Proceedings of the 2023 Conference on Empirical Methods in Natural Language Processing},
275	  year = {2023},
276	  doi = {10.18653/v1/2023.emnlp-main.557},
277	  url = {http://dx.doi.org/10.18653/v1/2023.emnlp-main.557}
278	}
279	
280	@article{nedellec2026consistency,
281	  title = {Consistency–accuracy correlation in hard-prompted LLMs for entity and relation extraction: empirical findings from plant-health data},
282	  author = {Yao, Xinzhi and Nédellec, Claire and Xia, Jingbo and Bossy, Robert},
283	  journal = {Genomics \& Informatics},
284	  year = {2026},
285	  doi = {10.1186/s44342-025-00063-2},
286	  url = {http://dx.doi.org/10.1186/s44342-025-00063-2}
287	}
288	
289	@article{oh2025latentsc,
290	  title = {Latent Self-Consistency for Reliable Majority-Set Selection in Short- and Long-Answer Reasoning},
291	  author = {Oh, Jungsuk and Lee, Jay-Yoon},
292	  journal = {arXiv preprint arXiv:2508.18395},
293	  year = {2025},
294	  url = {https://arxiv.org/abs/2508.18395}
295	}
296	
297	@inproceedings{sainz2024gollie,
298	  title = {{GoLLIE}: Annotation Guidelines improve Zero-Shot Information-Extraction},
299	  author = {Sainz, Oscar and García-Ferrero, Iker and Agerri, Rodrigo and Lacalle, Oier Lopez de and Rigau, German and Agirre, Eneko},
300	  booktitle = {ICLR 2024},
301	  year = {2024},
302	  url = {https://arxiv.org/abs/2310.03668}
303	}
304	
305	@inproceedings{shelmanov2021active,
306	  title = {Active Learning for Sequence Tagging with Deep Pre-trained Models and Bayesian Uncertainty Estimates},
307	  author = {Shelmanov, Artem and Puzyrev, Dmitri and Kupriyanova, Lyubov and Belyakov, Denis and Larionov, Daniil and Khromov, Nikita and Kozlova, Olga and Artemova, Ekaterina and Dylov, Dmitry V. and Panchenko, Alexander},
308	  booktitle = {Proceedings of the 16th Conference of the European Chapter of the Association for Computational Linguistics: Main Volume},
309	  year = {2021},
310	  doi = {10.18653/v1/2021.eacl-main.145},
311	  url = {http://dx.doi.org/10.18653/v1/2021.eacl-main.145}
312	}
313	
314	@inproceedings{snell2025scaling,
315	  title = {Scaling {LLM} Test-Time Compute Optimally can be More Effective than Scaling Model Parameters},
316	  author = {Snell, Charlie and Lee, Jaehoon and Xu, Kelvin and Kumar, Aviral},
317	  booktitle = {Proceedings of the International Conference on Learning Representations (ICLR)},
318	  year = {2025},
319	  url = {https://arxiv.org/abs/2408.03314}
320	}
321	
322	@inproceedings{taubenfeld2025cisc,
323	  title = {Confidence Improves Self-Consistency in LLMs},
324	  author = {Taubenfeld, Amir and Sheffer, Tom and Ofek, Eran and Feder, Amir and Goldstein, Ariel and Gekhman, Zorik and Yona, Gal},
325	  booktitle = {Findings of the Association for Computational Linguistics: ACL 2025},
326	  year = {2025},
327	  doi = {10.18653/v1/2025.findings-acl.1030},
328	  url = {http://dx.doi.org/10.18653/v1/2025.findings-acl.1030}
329	}
330	
331	@inproceedings{thirukovalluru2024atomic,
332	  title = {Atomic Self-Consistency for Better Long Form Generations},
333	  author = {Thirukovalluru, Raghuveer and Huang, Yukun and Dhingra, Bhuwan},
334	  booktitle = {Proceedings of the 2024 Conference on Empirical Methods in Natural Language Processing},
335	  year = {2024},
336	  doi = {10.18653/v1/2024.emnlp-main.706},
337	  url = {http://dx.doi.org/10.18653/v1/2024.emnlp-main.706}
338	}
339	
340	@inproceedings{tjongkimsang2003conll,
341	  title = {Introduction to the {CoNLL}-2003 Shared Task: Language-Independent Named Entity Recognition},
342	  author = {Sang, Erik F. Tjong Kim and Meulder, Fien De},
343	  booktitle = {CoNLL 2003},
344	  year = {2003},
345	  url = {https://aclanthology.org/W03-0419/}
346	}
347	
348	@inproceedings{vashurin2025cocoa,
349	  title = {Uncertainty Quantification for {LLMs} through Minimum Bayes Risk: Bridging Confidence and Consistency},
350	  author = {Vashurin, Roman and Goloburda, Maiya and Ilina, Albina and Rubashevskii, Aleksandr and Nakov, Preslav and Shelmanov, Artem and Panov, Maxim},
351	  booktitle = {NeurIPS 2025},
352	  year = {2025},
353	  url = {https://arxiv.org/abs/2502.04964}
354	}
355	
356	@inproceedings{wadhwa2023revisiting,
357	  title = {Revisiting Relation Extraction in the era of Large Language Models},
358	  author = {Wadhwa, Somin and Amir, Silvio and Wallace, Byron},
359	  booktitle = {Proceedings of the 61st Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers)},
360	  year = {2023},
361	  doi = {10.18653/v1/2023.acl-long.868},
362	  url = {http://dx.doi.org/10.18653/v1/2023.acl-long.868}
363	}
364	
365	@article{wang2023instructuie,
366	  title = {{InstructUIE}: Multi-task Instruction Tuning for Unified Information Extraction},
367	  author = {Wang, Xiao and Zhou, Weikang and Zu, Can and Xia, Han and Chen, Tianze and Zhang, Yuansen and Zheng, Rui and Ye, Junjie and Zhang, Qi and Gui, Tao and Kang, Jihua and Yang, Jingsheng and Li, Siyuan and Du, Chunsai},
368	  journal = {arXiv preprint arXiv:2304.08085},
369	  year = {2023},
370	  url = {https://arxiv.org/abs/2304.08085}
371	}
372	
373	@inproceedings{wang2023selfconsistency,
374	  title = {Self-Consistency Improves Chain of Thought Reasoning in Language Models},
375	  author = {Wang, Xuezhi and Wei, Jason and Schuurmans, Dale and Le, Quoc and Chi, Ed and Narang, Sharan and Chowdhery, Aakanksha and Zhou, Denny},
376	  booktitle = {ICLR 2023},
377	  year = {2023},
378	  url = {https://arxiv.org/abs/2203.11171}
379	}
380	
381	@inproceedings{wang2025make,
382	  title = {Make Every Penny Count: Difficulty-Adaptive Self-Consistency for Cost-Efficient Reasoning},
383	  author = {Wang, Xinglin and Feng, Shaoxiong and Li, Yiwei and Yuan, Peiwen and Zhang, Yueqi and Tan, Chuyi and Pan, Boyuan and Hu, Yao and Li, Kan},
384	  booktitle = {Findings of the Association for Computational Linguistics: NAACL 2025},
385	  pages = {6919--6932},
386	  year = {2025}
387	}
388	
389	@inproceedings{wang2024mathshepherd,
390	  title = {Math-Shepherd: Verify and Reinforce {LLMs} Step-by-step without Human Annotations},
391	  author = {Wang, Peiyi and Li, Lei and Shao, Zhihong and Xu, Runxin and Dai, Damai and Li, Yifei and Chen, Deli and Wu, Yu and Sui, Zhifang},
392	  booktitle = {ACL 2024},
393	  year = {2024},
394	  url = {https://arxiv.org/abs/2312.08935}
395	}
396	
397	@inproceedings{wang2025rankedvoting,
398	  title = {Ranked Voting based Self-Consistency of Large Language Models},
399	  author = {Wang, Weiqin and Wang, Yile and Huang, Hui},
400	  booktitle = {ACL Findings 2025},
401	  year = {2025},
402	  url = {https://arxiv.org/abs/2505.10772}
403	}
404	
405	@article{wen2025know,
406	  title = {Know Your Limits: A Survey of Abstention in Large Language Models},
407	  author = {Wen, Bingbing and Yao, Jihan and Feng, Shangbin and Xu, Chenjun and Tsvetkov, Yulia and Howe, Bill and Wang, Lucy Lu},
408	  journal = {Transactions of the Association for Computational Linguistics},
409	  year = {2025},
410	  doi = {10.1162/tacl_a_00754},
411	  url = {http://dx.doi.org/10.1162/tacl_a_00754}
412	}
413	
414	@article{willard2023guided,
415	  title = {Efficient Guided Generation for Large Language Models},
416	  author = {Willard, Brandon T. and Louf, Rémi},
417	  journal = {arXiv preprint arXiv:2307.09702},
418	  year = {2023},
419	  url = {https://arxiv.org/abs/2307.09702}
420	}
421	
422	@inproceedings{xia2025survey,
423	  title = {A Survey of Uncertainty Estimation Methods on Large Language Models},
424	  author = {Xia, Zhiqiu and Xu, Jinxuan and Zhang, Yuqian and Liu, Hang},
425	  booktitle = {ACL Findings 2025},
426	  year = {2025},
427	  url = {https://aclanthology.org/2025.findings-acl.1101/}
428	}
429	
430	@article{xiao2019uncertainty,
431	  title = {Quantifying Uncertainties in Natural Language Processing Tasks},
432	  author = {Xiao, Yijun and Wang, William Yang},
433	  journal = {Proceedings of the AAAI Conference on Artificial Intelligence},
434	  year = {2019},
435	  doi = {10.1609/aaai.v33i01.33017322},
436	  url = {http://dx.doi.org/10.1609/aaai.v33i01.33017322}
437	}
438	
439	@inproceedings{zhang2023ener,
440	  title = {E-NER: Evidential Deep Learning for Trustworthy Named Entity Recognition},
441	  author = {Zhang, Zhen and Hu, Mengting and Zhao, Shiwan and Huang, Minlie and Wang, Haotian and Liu, Lemao and Zhang, Zhirui and Liu, Zhe and Wu, Bingzhe},
442	  booktitle = {Findings of the Association for Computational Linguistics: ACL 2023},
443	  year = {2023},
444	  doi = {10.18653/v1/2023.findings-acl.103},
445	  url = {http://dx.doi.org/10.18653/v1/2023.findings-acl.103}
446	}
447	
448	@inproceedings{zheng2024llamafactory,
449	  title = {{L}lama{F}actory: Unified Efficient Fine-Tuning of 100+ Language Models},
450	  author = {Zheng, Yaowei and Zhang, Richong and Zhang, Junhao and Ye, Yanhan and Luo, Zheyan},
451	  booktitle = {Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics (Volume 3: System Demonstrations)},
452	  year = {2024},
453	  pages = {400--410},
454	  doi = {10.18653/v1/2024.acl-demos.38}
455	}
456	
457	@inproceedings{zhou2024uniner,
458	  title = {{UniversalNER}: Targeted Distillation from Large Language Models for Open Named Entity Recognition},
459	  author = {Zhou, Wenxuan and Zhang, Sheng and Gu, Yu and Chen, Muhao and Poon, Hoifung},
460	  booktitle = {Proceedings of the International Conference on Learning Representations (ICLR)},
461	  year = {2024},
462	  url = {https://arxiv.org/abs/2308.03279}
463	}
464	
465	@inproceedings{xiong2024llm,
466	  title = {Can {LLMs} Express Their Uncertainty? An Empirical Evaluation of Confidence Elicitation in {LLMs}},
467	  author = {Xiong, Miao and Hu, Zhiyuan and Lu, Xinyang and Li, Yifei and Fu, Jie and He, Junxian and Hooi, Bryan},
468	  booktitle = {Proceedings of the International Conference on Learning Representations (ICLR)},
469	  year = {2024},
470	  url = {https://arxiv.org/abs/2306.13063}
471	}
472	
473	@inproceedings{muller2021understanding,
474	  title = {Understanding the Properties of Minimum {Bayes} Risk Decoding in Neural Machine Translation},
475	  author = {M{\"u}ller, Mathias and Sennrich, Rico},
476	  booktitle = {Proceedings of the 59th Annual Meeting of the Association for Computational Linguistics (ACL)},
477	  year = {2021},
478	  url = {https://arxiv.org/abs/2105.08504}
479	}
480	
481	@inproceedings{heo2025uncertainty,
482	  title = {Do {LLMs} Estimate Uncertainty Well in Instruction Following?},
483	  author = {Heo, Juyeon and Xiong, Miao and Heinze-Deml, Christina and Narain, Jaya},
484	  booktitle = {Proceedings of the International Conference on Learning Representations (ICLR)},
485	  year = {2025},
486	  url = {https://arxiv.org/abs/2410.14582}
487	}
488	
489	@inproceedings{eikema2025structured,
490	  title = {Structure-Conditional Minimum {B}ayes Risk Decoding},
491	  author = {Eikema, Bryan and Rutkiewicz, Anna and Giulianelli, Mario},
492	  booktitle = {Proceedings of the 2025 Conference on Empirical Methods in Natural Language Processing},
493	  year = {2025},
494	  url = {https://arxiv.org/abs/2510.20700}
495	}
496	
497	@article{zhang2025tts,
498	  title = {A Survey on Test-Time Scaling in Large Language Models: What, How, Where, and How Well?},
499	  author = {Zhang, Qiyuan and Lyu, Fuyuan and Sun, Zexu and Wang, Lei and Zhang, Weixu and Guo, Zhihan and Wang, Yufei},
500	  journal = {arXiv preprint arXiv:2503.24235},
501	  year = {2025},
502	  url = {https://arxiv.org/abs/2503.24235}
503	}
504	
505	@article{venktesh2025trust,
506	  title = {Trust but Verify! A Survey on Verification Design for Test-time Scaling},
507	  author = {Venktesh, V and Rathee, Mandeep and Anand, Avishek},
508	  journal = {arXiv preprint arXiv:2508.16665},
509	  year = {2025},
510	  url = {https://arxiv.org/abs/2508.16665}
511	}
512	
513	@inproceedings{jinnai2024mbr,
514	  title = {Model-Based Minimum {B}ayes Risk Decoding for Text Generation},
515	  author = {Jinnai, Yuu and Morimura, Tetsuro and Honda, Ukyo and Ariu, Kaito and Abe, Kenshi},
516	  booktitle = {Proceedings of the 41st International Conference on Machine Learning (ICML)},
517	  year = {2024},
518	  url = {https://arxiv.org/abs/2311.05263}
519	}
520	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "90a529c4-3f82-4a73-b71d-559fb82c54c7",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "6da2d54a-dac9-4188-a387-9aec9828068e",
  "sourceToolAssistantUUID": "90a529c4-3f82-4a73-b71d-559fb82c54c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-15T12:44:28.502Z_

<details open><summary>🔧 Tool call — Read · `toolu_01J5ppHbozWDPE7XAKaNhjQ4`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6da2d54a-dac9-4188-a387-9aec9828068e",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nja1Eaidmh7e9xwoU3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "862426bb-11d7-4941-8fd0-baaa9d95de21",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0186mdNGes35NVZUJgjVCnbB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1810,
      "cache_read_input_tokens": 23030,
      "output_tokens": 542,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1810
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 542,
          "cache_read_input_tokens": 23030,
          "cache_creation_input_tokens": 1810,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1810,
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

_source line 24 · 2026-05-15T12:44:28.507Z_

<details><summary>↩ Tool result · `toolu_01J5ppHbozWDPE7XAKaNhjQ4`</summary>

```text
1	\section{Method}\label{sec:method}
2	
3	\subsection{Problem Formulation}\label{sec:formulation}
4	
5	Given a language model $\mathcal{M}$ and input $x$, we sample $N$ structured outputs $\{y_1, \ldots, y_N\}$ at temperature $T > 0$ via constrained decoding \cite{willard2023guided}.
6	Each $y_i$ is an entity set (NER) or relation set (RE).
7	A confidence signal $c$ serves two purposes: (a) \textit{quality estimation}---predicting which instances the model handles reliably, and (b) \textit{sample selection}---identifying the best output among $N$ candidates.
8	
9	A \textbf{per-sample signal} scores each $y_i$ independently, $c_{\text{ps}}: (x, y_i) \to \mathbb{R}$, enabling direct candidate ranking.
10	An \textbf{instance-level signal} aggregates over all $N$ samples, $c_{\text{il}}: (x, \{y_i\}_{i=1}^N) \to \mathbb{R}$, producing a single score per input.
11	This asymmetry---between predicting \textit{which inputs} are easy and selecting \textit{which output} is best---is central to the correlation-selection gap we investigate.
12	Notation is summarized in Appendix~\ref{app:notation}.
13	
14	\subsection{Confidence Signals}\label{sec:signals}
15	
16	We use \textit{confidence signal} as the umbrella term for all five measures.
17	Four are \textit{consistency signals}---computed from inter-sample agreement---spanning two families: \textit{structural} (Soft Jaccard [SJ], entity voting confidence [VC]) and \textit{surface} (exact match [EM], Fleiss' $\kappa$ [FK]).
18	The fifth, log-probability, is the sole \textit{model-internal} signal and the only one that scores individual samples rather than the instance as a whole.
19	
20	\paragraph{Log-probability (model-internal, per-sample).}
21	The only per-sample signal.
22	For sample $y_i$ with tokens $t_1, \ldots, t_{|y_i|}$:
23	\begin{equation}\label{eq:logprob}
24	c_{\text{lp}}(y_i) = \frac{1}{|y_i|} \sum_{j=1}^{|y_i|} \log p_{\mathcal{M}}(t_j \mid t_{&lt;j}, x)
25	\end{equation}
26	
27	\paragraph{Exact match voting (surface, instance-level).}
28	The majority fraction---the proportion of samples producing the most common output:
29	\begin{equation}\label{eq:em}
30	c_{\text{em}}(x) = \frac{1}{N} \max_{y} \big|\{i : y_i = y\}\big|
31	\end{equation}
32	
33	\paragraph{Fleiss' $\kappa$ (surface, instance-level).}
34	We adapt \citet{fleiss1971agreement} to entity sets: items are unique (text, type) tuples across all $N$ samples; each sample assigns binary present/absent labels, yielding a $|E_\cup| \times 2$ rating matrix:
35	\begin{equation}\label{eq:fk}
36	\kappa = \frac{\bar{P} - \bar{P}_e}{1 - \bar{P}_e}
37	\end{equation}
38	where $\bar{P}$ is mean observed pairwise agreement and $\bar{P}_e$ is expected agreement under random assignment.
39	While FK assumes independent raters, temperature-based sampling yields mild negative dependence rather than positive correlation among samples.
40	Empirically, we measure excess agreement ($\bar{P} - \bar{P}_e$) across all configurations (SciERC NER/RE, CoNLL, WNUT-17; $N{=}8$, $T{=}1.0$) and find values between $-$0.4\% and $-$4.0\%, indicating mild \textit{negative} dependence---samples from the same model tend to err on different items---which confirms that FK is not inflated by inter-sample dependence.
41	(All excess agreement values are negative across 5 configurations; a one-sample $t$-test against zero yields $p{<}0.05$.)
42	Unlike structural signals, FK relies on exact string matching and does not tolerate surface variations.
43	
44	\paragraph{Soft Jaccard (structural, instance-level).}
45	Our primary structural signal extends Jaccard similarity \cite{jaccard1901distribution} to extracted entity/relation sets.
46	For samples $y_i, y_j$, we group extractions by type, compute max-weight bipartite matching via the Hungarian algorithm (maximizing total token-level IoU; zero-IoU pairs automatically receive zero weight), and define:
47	\begin{equation}\label{eq:sj}
48	\text{SJ}(y_i, y_j) = \frac{\sum_{m \in M} \text{sim}(a_m, b_m)}{\sum_{g} \max(|g_i|, |g_j|)}
49	\end{equation}
50	where $M$ is the matched set from the Hungarian algorithm (without minimum similarity threshold), $\text{sim}(a_m, b_m)$ is the token-level IoU (intersection of tokens divided by union of tokens) between matched entity spans $a_m$ and $b_m$, and $g_i, g_j$ index per-type extraction counts.
51	We use $\max(|g_i|, |g_j|)$ rather than $|g_i \cup g_j|$ as the normalizer to penalize length asymmetry between samples.
52	The instance-level signal averages over all pairs:
53	\begin{equation}\label{eq:sj_instance}
54	c_{\text{sj}}(x) = \frac{1}{\binom{N}{2}} \sum_{i&lt;j} \text{SJ}(y_i, y_j)
55	\end{equation}
56	
57	\paragraph{Entity voting confidence (structural, instance-level).}
58	For each entity $e$ in the union $E_\cup$ of all samples, we compute frequency $\text{freq}(e) = |\{i : e \in y_i\}| / N$.
59	The instance-level confidence is the mean frequency:
60	\begin{equation}\label{eq:voting}
61	c_{\text{vote}}(x) = \frac{1}{|E_\cup|} \sum_{e \in E_\cup} \text{freq}(e)
62	\end{equation}
63	When $E_\cup = \emptyset$ (no entity extracted by any sample), we set $c_{\mathrm{vc}}(x) = 0$.\footnote{This occurs in $<$1\% of instances in our experiments (WNUT-17 only). Equation~\ref{eq:voting} defines the continuous QE signal used throughout Table~\ref{tab:quality_estimation} and all correlation analyses. For voted-output \textit{selection} (Table~\ref{tab:selection}), we include only entities with frequency ${>}N/2$, following standard majority voting. The two computations serve different purposes: Eq.~\ref{eq:voting} assigns a continuous quality score per instance; the majority threshold constructs a discrete output for F1 evaluation. On NER, the threshold variant yields $\rho{=}0.252$ (vs.\ $0.379$ for Eq.~\ref{eq:voting}), reflecting information loss from binarization; on RE, the difference is negligible ($\Delta\rho{=}0.019$).}
64	
65	\subsection{Evaluation Framework}\label{sec:evaluation}
66	
67	\paragraph{Quality estimation.}
68	We measure rank correlation (Spearman $\rho$) between the confidence signal and instance-level F1, and binary discrimination (AUROC) by classifying instances as above or below median F1.
69	
70	\paragraph{Sample selection.}
71	We report best-of-$N$ F1: for each instance, the signal selects one sample.
72	Per-sample signals (LP) directly rank candidates; instance-level signals select the sample closest to the consensus output (the consensus-proximity score for SJ is mathematically equivalent to leave-one-out SJ selection).
73	We compare against an \textit{oracle} (highest-F1 sample) and \textit{greedy} ($T{=}0$, $N{=}1$).
74	
75	\paragraph{Complementarity.}
76	High rank correlation does not guarantee effective sample selection: if per-sample variance is low, even a perfect quality estimator cannot distinguish among near-identical candidates (\S\ref{sec:selection_gap}).
77	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "862426bb-11d7-4941-8fd0-baaa9d95de21",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "0e553012-c5c4-4db9-be0a-8c399cfc9522",
  "sourceToolAssistantUUID": "862426bb-11d7-4941-8fd0-baaa9d95de21",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 25 · 2026-05-15T12:44:31.931Z_

Now let me read the remaining files needed for the checks.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0e553012-c5c4-4db9-be0a-8c399cfc9522",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nk2FoXkiCuvhnBjuVb",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "76444d6f-f0d1-429a-bfad-cda2b9ee8243",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wrw6yRM9hENatXzdHfmgDA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 20784,
      "cache_read_input_tokens": 24840,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 20784,
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

_source line 26 · 2026-05-15T12:44:33.942Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LF3Ghkp9F8fTwv6Hsf3Mfd`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "76444d6f-f0d1-429a-bfad-cda2b9ee8243",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nk2FoXkiCuvhnBjuVb",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "c3bdfdef-c34c-410c-bfc4-eab24e98ad84",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wrw6yRM9hENatXzdHfmgDA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 20784,
      "cache_read_input_tokens": 24840,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 20784,
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

_source line 27 · 2026-05-15T12:44:33.949Z_

<details><summary>↩ Tool result · `toolu_01LF3Ghkp9F8fTwv6Hsf3Mfd`</summary>

```text
1	Our evaluation covers three datasets but only one RE benchmark (SciERC), where 40\% of instances receive zero F1, compressing the discriminable range and limiting signal differentiation for relation extraction.
2	RE selection failure persists even when restricting to non-zero F1 instances (Appendix~\ref{app:re_conditional_selection}), ruling out floor effects as the sole explanation, but generalization to other RE benchmarks remains unvalidated.
3	WNUT-17 confirms the capability boundary of our approach, but our positive results on formal-domain text (CoNLL, SciERC) have not been validated on informal or noisy text where models achieve non-trivial performance.
4	
5	We evaluate two model families (Qwen3-8B and LLaMA-3.1-8B), both at 8B parameters.
6	A 3-seed robustness analysis confirms that signal rankings are stable across seeds ($\sigma{\leq}0.026$; Table~\ref{tab:multiseed}), but whether our findings---particularly the correlation-selection gap and the difficulty-dependent signal ordering---hold for larger models (70B+) or closed-source APIs remains untested.
7	Larger models may produce higher-quality and more diverse samples, potentially altering the signal landscape.
8	
9	Our analysis of selection potential uses only unsupervised signals.
10	We do not train a dedicated verifier or reward model, leaving unknown how much of the oracle headroom a supervised approach could recover.
11	
12	We evaluate at $N{=}8$ and $N{=}16$.
13	The behavior of confidence signals at larger sample sizes (e.g., $N{=}64$ or $N{=}128$) is unknown, and $N$-scaling gains are setting-dependent: SJ improves by $+0.047$ on Qwen SciERC NER but only $+0.016$ on LLaMA SciERC NER when doubling from $N{=}8$ to $N{=}16$.
14	
15	On CoNLL with LLaMA, the SJ--FK gap is only 0.003 ($\rho{=}0.431$ vs.\ $0.428$), so the structural advantage over surface signals may not generalize to all simple-schema datasets.
16	Our free-form ablation (\S\ref{sec:ablation}) confirms that LP score compression persists without constrained decoding, but was conducted on a single dataset (SciERC) with one model (Qwen3-8B); whether the intrinsic compression finding generalizes to other datasets, model families, or model scales remains untested.
17	
18	Qwen3-8B's SciERC checkpoint was trained with \texttt{enable\_thinking} active, injecting empty \texttt{&lt;think>&lt;/think>} blocks (4--5 tokens, no reasoning chain) before each response; CoNLL and WNUT checkpoints disabled this feature.
19	At inference time, constrained decoding suppresses thinking tokens in all configurations, so they do not appear in generated samples.
20	The empty blocks may weakly affect first-token probability distributions during training, potentially shifting LP score calibration on SciERC; however, since LP selection fails across all datasets including CoNLL and WNUT-17 (which lack this confound), the thinking token inconsistency is unlikely to explain the correlation-selection gap.
21	The absence of any reasoning content further limits the representational impact.
22	
23	Finally, log-probability was excluded from the temperature comparison ($T{=}0.7$ vs.\ $T{=}1.0$) due to missing $T{=}0.7$ LP data, leaving its temperature sensitivity uncharacterized.
24	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c3bdfdef-c34c-410c-bfc4-eab24e98ad84",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "a93f8eba-eafa-4f72-9480-91a876af896d",
  "sourceToolAssistantUUID": "c3bdfdef-c34c-410c-bfc4-eab24e98ad84",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-15T12:44:34.281Z_

<details open><summary>🔧 Tool call — Read · `toolu_01G5SyWd4LQXCkPq8yQspcYJ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a93f8eba-eafa-4f72-9480-91a876af896d",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nk2FoXkiCuvhnBjuVb",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2d58fb4b-514f-4c75-a5e0-1bc32212017e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wrw6yRM9hENatXzdHfmgDA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 20784,
      "cache_read_input_tokens": 24840,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 20784,
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

_source line 29 · 2026-05-15T12:44:34.289Z_

<details><summary>↩ Tool result · `toolu_01G5SyWd4LQXCkPq8yQspcYJ`</summary>

```text
1	\section{Discussion}\label{sec:discussion}
2	
3	\paragraph{Practical recommendations.}
4	For per-instance quality ranking, VC provides the strongest rank correlation ($\rho{=}0.38$), though EM leads binary discrimination (AUROC${=}0.749$); under conditional filtering, EM leads on both NER and RE ($\rho{=}0.360$, $0.417$; RE: preliminary, single benchmark).
5	Signal rankings depend on task difficulty---EM dominates easy tasks (CoNLL), VC and SJ dominate hard tasks (SciERC)---directionally consistent across two model families at 8B scale, though with model-dependent magnitude.
6	At higher sample sizes ($N{=}16$), SJ converges to comparable NER performance with VC ($\Delta{=}0.002$) with lower cross-seed variance ($\sigma{=}0.010$ vs.\ $0.026$); on RE, only VC consistently outperforms LP (preliminary).
7	When model capability is insufficient (WNUT-17), all signals converge toward non-significant conditional correlations (Table~\ref{tab:wnut}).
8	
9	\paragraph{Why the gap exists: two layers.}
10	\textit{Layer 1 (definitional):} Four of five signals are instance-level aggregates that assign a single score per input; they cannot rank candidates by construction.
11	Consensus-proximity selection (\S\ref{sec:evaluation}) does not recover per-sample discrimination (Table~\ref{tab:selection}).
12	\textit{Layer 2 (score compression):} Log-probability, the only per-sample signal, also fails to exploit the 13--18~pp oracle headroom.
13	LP scores are severely compressed: 60\% of instances have a within-sample range below 0.05, and 75\% of pairwise comparisons are effective ties ($|\Delta|{<}0.026$; Appendix~\ref{app:logprob_ties}).
14	In the 40\% of instances where compression is mitigated (LP range ${\geq}0.05$, $n{=}210$), LP \textit{significantly} outperforms greedy ($+2.9$~pp, $p{=}0.01$; within-instance $\rho$: 0.08$\to$0.39).
15	This diagnostic confirms that LP carries useful per-sample quality information; score compression is the primary mechanistic bottleneck.
16	A controlled ablation (\S\ref{sec:ablation}) confirms that this compression is intrinsic to the model and task, not an artifact of constrained decoding.
17	Diversity-stratified analysis confirms the gap persists even among high-diversity instances (Appendix~\ref{app:diversity}); RE miscalibration (ECE 0.109--0.339, preliminary; Appendix~\ref{app:calibration}) may compound this.
18	
19	\paragraph{Connection to MBR decoding.}
20	Our selection strategies instantiate minimum Bayes risk (MBR) decoding \cite{eikema2022sampling, muller2021understanding}: each selects $\hat{y} = \arg\max_{y_i} \sum_{j \neq i} U(y_i, y_j)$ with utility $U$ defined by SJ, EM, or entity overlap.
21	Despite MBR's success in machine translation \cite{freitag2022high} and its extension to summarization, code generation, and captioning \cite{jinnai2024mbr}, all variants fail here because the utility functions correlate with F1 at the instance level but not within a single instance---the mathematical essence of the correlation-selection gap.
22	\citet{eikema2025structured} study structure-conditional MBR decoding and find that standard utility functions degrade on structured outputs---consistent with our finding that consensus-proximity selection fails in IE despite its success in machine translation.
23	
24	\paragraph{Score compression is task-inherent.}\label{sec:ablation}
25	A natural hypothesis is that LP compression is an artifact of constrained decoding's restricted token space.
26	We test this via controlled ablation: generating free-form (unconstrained) outputs on the same instances with post-hoc JSON parsing (parse rate 99.95\%, 4406/4408; Table~\ref{tab:freeform_ablation}).
27	LP variance is essentially unchanged (within-instance std ratio $0.97{\times}$, tied fraction 59.7\%$\to$57.7\%).
28	NER selection gains remain negligible ($+0.18$~pp free-form vs.\ $+0.59$~pp constrained).
29	This rules out constrained decoding as the cause of compression and establishes LP compression as inherent to structured output generation.
30	The correlation-selection gap is therefore a fundamental challenge for test-time scaling in structured IE, not an artifact of any particular decoding strategy.
31	Notably, the fine-tuned model achieved 99.95\% parse rate without grammar constraints, suggesting that constrained decoding's format-compliance role may be redundant for sufficiently fine-tuned models.
32	
33	\paragraph{What drives the universal gap?}
34	Our analysis reveals two complementary mechanisms.
35	First, the free-form ablation exposes a task-specific interaction: RE LP selection flips from $-0.68$~pp (constrained) to $+1.69$~pp (free-form; preliminary, single RE benchmark), a reversal that is universal across all 7 relation types and driven by selective variance reallocation ($p{<}0.0001$).
36	The win/loss ratio shifts from 36:59 (constrained) to 45:45 (free-form), with the gains concentrated on relation-dense instances (mean 3.3 gold relations).
37	This interaction does not generalize to NER, where selection remains negligible under both regimes.
38	This ablation uses a single seed (seed${=}42$); multi-seed replication is left for future work.
39	Second, the non-tied subset ($n{=}210$) is partially reshuffled under free-form decoding: Jaccard similarity between the constrained and free-form non-tied sets is 0.472, indicating that 87 instances newly gain LP discrimination while others lose it, yielding a $3{\times}$ increase in within-instance LP range for the newly non-tied subset.
40	Despite this reshuffling, aggregate NER selection gains remain negligible---score compression is not a fixed property of specific instances but rather a pervasive regime that shifts across instances without producing net selection improvement.
41	Free-form decoding also slightly improves quality estimation (NER VC $\rho$: 0.379$\to$0.409), though this does not translate to selection gains.
42	
43	\paragraph{Methodological implications.}
44	The decoupling of quality estimation ($\rho$), binary discrimination (AUROC), and sample selection (best-of-$N$ F1) means evaluating on a single metric risks selecting the wrong signal for the intended use case.
45	Effective selection likely requires per-sample signals such as trained verifiers \cite{cobbe2021verifiers, venktesh2025trust}; $N$-scaling analysis (Appendix~\ref{app:additional}) shows $N{=}8$ captures most quality estimation benefit.
46	Cross-dataset evaluation confirms that structural signals are robust to domain shift when the training schema subsumes the target (VC $\rho{=}0.469$ OOD vs.\ $0.386$ in-domain); the reverse direction fails due to catastrophic model failure, not signal failure (Appendix~\ref{app:ood}).
47	Our findings are established under constrained decoding with a single-dataset ablation suggesting the gap is intrinsic; whether this generalizes across decoding regimes, datasets, and model scales warrants further investigation.
48	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2d58fb4b-514f-4c75-a5e0-1bc32212017e",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "f1d0d5f6-f405-41d3-b1f6-7e058948e60f",
  "sourceToolAssistantUUID": "2d58fb4b-514f-4c75-a5e0-1bc32212017e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 30 · 2026-05-15T12:44:35.342Z_

<details open><summary>🔧 Tool call — Read · `toolu_01XGyeXdHX2oTYHhgWzLdBHb`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f1d0d5f6-f405-41d3-b1f6-7e058948e60f",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nk2FoXkiCuvhnBjuVb",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "c200215c-2f6e-4ee5-afb6-5014e23f82cc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wrw6yRM9hENatXzdHfmgDA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 20784,
      "cache_read_input_tokens": 24840,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 20784,
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

_source line 31 · 2026-05-15T12:44:35.348Z_

<details><summary>↩ Tool result · `toolu_01XGyeXdHX2oTYHhgWzLdBHb`</summary>

```text
1	\section{Related Work}\label{sec:related}
2	
3	\paragraph{Self-consistency and test-time scaling.}
4	Self-consistency decoding \cite{wang2023selfconsistency} improves reasoning by majority voting over chain-of-thought samples, assuming a discrete answer space.
5	Extensions to free-form text use LLM-based comparison \cite{chen2024usc}, atomic sub-claim decomposition \cite{thirukovalluru2024atomic}, or cross-sample hallucination detection \cite{manakul2023selfcheckgpt}.
6	For test-time scaling \cite{zhang2025tts}, \citet{snell2025scaling} characterize compute scaling laws and \citet{brown2024monkeys} show best-of-$N$ gains across tasks.
7	Recent reward-free selectors include confidence-weighted voting \cite{taubenfeld2025cisc}, KL-based self-certainty \cite{kang2025selfcertainty}, adaptive sampling \cite{kim2026reasc}, ranked aggregation \cite{wang2025rankedvoting}, and latent-space consistency \cite{oh2025latentsc}.
8	Concurrently, \citet{feng2025optimal} and \citet{wang2025make} adapt self-consistency to difficulty-aware settings, echoing our finding that signal rankings shift with task complexity; \citet{li2025llms} propose generative self-aggregation for IE but focus on output fusion rather than confidence-based selection.
9	All of the above target reasoning/QA with discrete answers or specific aggregation strategies.
10	Our work extends self-consistency to set-valued structured outputs and identifies the correlation-selection gap: strong quality estimation ($\rho{=}0.38$) coexists with selection failure ($p{>}0.39$).
11	
12	\paragraph{Consistency for structured IE.}
13	\citet{nedellec2026consistency} study consistency--accuracy correlations for LLM-based NER/RE, corroborating our quality-estimation findings.
14	Their work leaves open three questions we address: (i)~whether structural matching improves on surface-level agreement (which they acknowledge ``overlooks semantically consistent outputs''); (ii)~whether quality estimation translates to best-of-$N$ selection; and (iii)~whether findings generalize across a difficulty gradient.
15	Our Soft Jaccard signal addresses (i) through type-aware bipartite matching with token-level span overlap; our selection analysis (\S\ref{sec:selection_gap}) directly addresses (ii); and our three-dataset evaluation spanning easy (CoNLL) to hard (SciERC) tasks addresses (iii).
16	CoCoA \cite{vashurin2025cocoa} fuses model confidence with inter-sample consistency for QA/summarization but does not address structured extraction.
17	Our evaluation builds on generative IE work \cite{zhou2024uniner, sainz2024gollie, josifoski2022genie, li2023codeie, wadhwa2023revisiting, wang2023instructuie} and constrained decoding \cite{willard2023guided}.
18	
19	\paragraph{Uncertainty estimation and calibration.}
20	Surveys cover confidence estimation \cite{geng2024confidence}, selective abstention \cite{wen2025know}, uncertainty quantification \cite{xia2025survey}, and calibration \cite{hobelsberger2025systematic} for LLMs; \citet{xiong2024llm} find LLMs tend toward overconfidence, and \citet{heo2025uncertainty} show calibration degrades with task complexity.
21	Semantic uncertainty \cite{kuhn2023semantic} clusters generations by meaning; \citet{kossen2024semantic} distill this into probes; P(True) \cite{kadavath2022language} queries model confidence directly; \citet{malinin2021uncertainty} distinguish data and model uncertainty in autoregressive models.
22	Our structural signals instead measure agreement over output \textit{structure}.
23	Neural networks are often miscalibrated \cite{guo2017calibration, desai2020calibration}; deep ensembles \cite{lakshminarayanan2017ensembles} and MC-dropout \cite{gal2016dropout} obtain uncertainty from model variation, while our approach requires no model modification.
24	Prior NER uncertainty work spans Bayesian inference for sequence labeling \cite{xiao2019uncertainty}, active learning under uncertainty \cite{shelmanov2021active}, evidential deep learning \cite{zhang2023ener}, verification-augmented NER \cite{kim2024verifiner}, and uncertainty transmission across label sequences \cite{he2024uncertainty}---all within discriminative paradigms.
25	Conformal prediction \cite{fisch2021conformal, angelopoulos2021conformal} provides coverage guarantees; trained verifiers \cite{cobbe2021verifiers, lightman2024verify, venktesh2025trust} and reward models \cite{wang2024mathshepherd} learn per-sample scoring.
26	Our selection strategies instantiate MBR decoding \cite{eikema2022sampling} with structural utility functions; despite MBR's success in translation \cite{freitag2022high} and other generation tasks \cite{jinnai2024mbr}, we find utility-quality misalignment at the per-sample level for structured IE (\S\ref{sec:discussion}).
27	Selective prediction \cite{geifman2017selective} and confidence-based IE filtering \cite{culotta2004confidence} establish the broader framework.
28	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c200215c-2f6e-4ee5-afb6-5014e23f82cc",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "8301aa07-e7a3-45c3-8abf-dc9ae1818568",
  "sourceToolAssistantUUID": "c200215c-2f6e-4ee5-afb6-5014e23f82cc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 32 · 2026-05-15T12:44:35.833Z_

<details open><summary>🔧 Tool call — Read · `toolu_0158QLHaU9Mnv988VPzegBng`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8301aa07-e7a3-45c3-8abf-dc9ae1818568",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nk2FoXkiCuvhnBjuVb",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2cdbdc63-fd14-4746-8b91-3249eebb296c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wrw6yRM9hENatXzdHfmgDA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 20784,
      "cache_read_input_tokens": 24840,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 20784,
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

_source line 33 · 2026-05-15T12:44:35.840Z_

<details><summary>↩ Tool result · `toolu_0158QLHaU9Mnv988VPzegBng`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	We systematically evaluate five confidence signals across quality estimation, binary discrimination, and sample selection for LLM-based structured IE, revealing that these metrics decouple---single-metric evaluation risks selecting the wrong signal for the intended use case.
4	All signals achieve strong quality estimation ($\rho$ up to 0.38, AUROC up to 0.75) yet none significantly improves sample selection despite 13--18~pp oracle headroom---the \textit{correlation-selection gap}.
5	The instance-level failure of four signals is definitional; the empirical finding is that neither consensus-proximity selection (MBR decoding) nor log-probability bridges the gap.
6	MBR utility correlates with quality across instances but not within them; LP scores are compressed into effective ties (60\% of instances), though where compression is mitigated, LP becomes a significant selector ($+2.9$~pp, $p{=}0.01$).
7	A controlled free-form decoding ablation confirms that this compression is intrinsic to the model and task, not an artifact of constrained decoding.
8	Signal rankings shift with task difficulty---EM leads on easy tasks, SJ on hard tasks---consistent across two model families at 8B scale, though with model-dependent magnitude; at the capability boundary (WNUT-17), all signals collapse to non-significance.
9	RE findings rest on SciERC alone (preliminary) and warrant multi-benchmark validation.
10	Trained verifiers, scaling to 70B+ models, and conformal prediction are promising directions for closing the gap.
11	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2cdbdc63-fd14-4746-8b91-3249eebb296c",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "8c00edaa-4369-49e9-89db-a0809ee34e62",
  "sourceToolAssistantUUID": "2cdbdc63-fd14-4746-8b91-3249eebb296c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 34 · 2026-05-15T12:44:36.044Z_

<details open><summary>🔧 Tool call — Read · `toolu_015Ht9s3euMH4mkWLW2b9AMb`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8c00edaa-4369-49e9-89db-a0809ee34e62",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nk2FoXkiCuvhnBjuVb",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "50ece6e9-a1e8-460e-88a4-809f84d7187e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Wrw6yRM9hENatXzdHfmgDA",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 20784,
      "cache_read_input_tokens": 24840,
      "output_tokens": 403,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 20784
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 403,
          "cache_read_input_tokens": 24840,
          "cache_creation_input_tokens": 20784,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 20784,
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

_source line 35 · 2026-05-15T12:44:36.307Z_

<details><summary>↩ Tool result · `toolu_015Ht9s3euMH4mkWLW2b9AMb`</summary>

```text
1	\section{Notation}\label{app:notation}
2	
3	Table~\ref{tab:notation} summarizes the notation used throughout the paper.
4	
5	\begin{table}[h]
6	\centering
7	\small
8	\begin{tabular}{cl}
9	\toprule
10	Symbol & Meaning \\
11	\midrule
12	$\mathcal{M}$ & Language model \\
13	$x$ & Input instance \\
14	$y_i$ & $i$-th stochastic sample \\
15	$N$ & Number of samples \\
16	$T$ & Sampling temperature \\
17	$c(\cdot)$ & Confidence signal \\
18	SJ & Soft Jaccard similarity \\
19	FK & Fleiss' $\kappa$ \\
20	EM & Exact-match voting rate \\
21	VC ($c_{\mathrm{vc}}$) & Entity voting confidence \\
22	LP ($c_{\mathrm{lp}}$) & Log-probability (mean token log-likelihood) \\
23	\bottomrule
24	\end{tabular}
25	\caption{Notation used throughout the paper.}
26	\label{tab:notation}
27	\end{table}
28	
29	\section{Robustness Analysis}\label{app:robustness}
30	
31	\begin{table}[t]
32	\centering
33	\small
34	\caption{Signal robustness across configurations (Spearman $\rho$). Top: temperature on Qwen SciERC. Middle: sample size on Qwen SciERC. Bottom: transfer across model families (both 8B) (LLaMA CoNLL $N{=}16$, 3-seed mean $\pm\sigma$). $^\dagger$Mean over 3 seeds ($\sigma{=}0.010$; individual: 0.398, 0.423, 0.410). $\sigma$ computed as population standard deviation.}
35	\label{tab:robustness}
36	\begin{tabular}{llcc}
37	\toprule
38	& & NER $\rho$ & RE $\rho$ \\
39	\midrule
40	\multicolumn{4}{l}{\textit{Temperature} (Qwen SciERC, $N{=}8$)} \\
41	\quad SJ & $T{=}0.7$ & 0.388 & 0.234 \\
42	\quad SJ & $T{=}1.0$ & 0.360 & 0.250 \\
43	\quad FK & $T{=}0.7$ & 0.321 & 0.184 \\
44	\quad FK & $T{=}1.0$ & 0.267 & 0.275 \\
45	\midrule
46	\multicolumn{4}{l}{\textit{Sample size} (Qwen SciERC, $T{=}1.0$)} \\
47	\quad SJ & $N{=}8$  & 0.360 & 0.250 \\
48	\quad SJ & $N{=}16$ & 0.411$^\dagger$ & 0.281 \\
49	\quad FK & $N{=}8$  & 0.267 & 0.275 \\
50	\quad FK & $N{=}16$ & 0.283 & 0.279 \\
51	\midrule
52	\multicolumn{4}{l}{\textit{Across model families} (LLaMA CoNLL, $N{=}16$, 3 seeds)} \\
53	\quad SJ &  & $0.463{\pm}0.007$ & --- \\
54	\quad FK &  & $0.455{\pm}0.006$ & --- \\
55	\quad EM &  & $0.460{\pm}0.008$ & --- \\
56	\quad VC &  & $0.458{\pm}0.003$ & --- \\
57	\quad LP &  & $0.310{\pm}0.005$ & --- \\
58	\bottomrule
59	\end{tabular}
60	\end{table}
61	
62	\begin{figure}[t]
63	\centering
64	\includegraphics[width=\columnwidth]{fig_temperature_robustness}
65	\caption{Temperature robustness on SciERC ($N{=}8$). Top: NER; bottom: RE. SJ maintains stable $\rho$ across $T{=}0.7$ and $T{=}1.0$, while FK shows mixed sensitivity. LP $T{=}0.7$ data unavailable.}
66	\label{fig:temperature_robustness}
67	\end{figure}
68	
69	\paragraph{Temperature sensitivity.}
70	SJ NER $\rho$ shifts from 0.388 ($T{=}0.7$) to 0.360 ($T{=}1.0$), a difference of 0.028 whose bootstrap confidence interval includes zero.
71	FK shows mixed behavior: NER $\rho$ drops by 0.054, while RE $\rho$ increases by 0.091, likely reflecting reduced diversity at lower temperature interacting differently across tasks.
72	Across all comparisons, the SJ--FK relative ordering is preserved at both temperatures on NER (0.388 vs.\ 0.321 at $T{=}0.7$; 0.360 vs.\ 0.267 at $T{=}1.0$), indicating a stable signal hierarchy despite numerically small temperature effects.
73	
74	\paragraph{Sample size scaling.}
75	Increasing from $N{=}8$ to $N{=}16$ improves SJ on Qwen SciERC NER: $\rho$ rises from 0.360 to $0.411{\pm}0.010$ (three seeds: 0.398, 0.423, 0.410), a gain of $+0.047$.
76	The magnitude of $N$-scaling gains is setting-dependent---LLaMA SciERC NER yields $+0.016$ and Qwen CoNLL NER $+0.014$---though the direction is consistently positive.
77	LLaMA CoNLL exhibits the most uniform scaling: all four consistency signals gain $\Delta\rho{\approx}{+}0.030$ (range: $+0.027$ to $+0.032$) while LP gains only $+0.003$ (Table~\ref{tab:quality_estimation}).
78	FK $N$-scaling is inconsistent: degradation on SciERC ($-0.007$ to $-0.019$) but improvement on CoNLL with LLaMA ($+0.027$), suggesting sensitivity to both model and task characteristics.
79	VC $N$-scaling is consistently positive ($+0.005$ on Qwen CoNLL, $+0.018$ on LLaMA SciERC, $+0.030$ on Qwen SciERC), while LP is approximately $N$-invariant ($\Delta{\leq}0.034$).
80	SJ, EM, and VC scale consistently across all tested settings; only FK shows setting-dependent variation, suggesting that structural and binary-agreement signals are the most robust to $N$.
81	At $N{=}16$, SJ converges to comparable NER performance with VC ($\Delta{=}0.002$) while exhibiting lower cross-seed variance ($\sigma{=}0.010$ vs.\ $0.026$), making it a more stable alternative at higher sample sizes.
82	
83	\paragraph{Transfer across model families.}
84	LLaMA-3.1-8B-Instruct replicates the structural-over-surface ordering on SciERC NER (SJ $\rho{=}0.325{\pm}0.021$, FK $\rho{=}0.256{\pm}0.024$).
85	On CoNLL, the gap across model families is minimal (Table~\ref{tab:quality_estimation}): SJ achieves $\rho{=}0.431$ (LLaMA) vs.\ 0.436 (Qwen), $\Delta{=}0.005$.
86	At $N{=}16$, the structural-over-LP advantage holds across all four tested NER settings: Qwen SciERC (VC $\rho{=}0.409$ vs.\ LP 0.239, $\Delta{=}{+}0.170$), Qwen CoNLL (EM $\rho{=}0.463$ vs.\ LP 0.328, $\Delta{=}{+}0.135$), LLaMA SciERC (VC $\rho{=}0.452$ vs.\ LP 0.277, $\Delta{=}{+}0.175$), and LLaMA CoNLL 3-seed (SJ $\rho{=}0.463{\pm}0.007$ vs.\ LP $0.310{\pm}0.005$, $\Delta{=}{+}0.153$).
87	
88	\section{Calibration Analysis}\label{app:calibration}
89	
90	\begin{figure*}[t]
91	\centering
92	\includegraphics[width=\textwidth]{fig_reliability}
93	\caption{Reliability diagrams on SciERC ($N{=}8$, $T{=}1.0$). Top: mean F1 vs.\ binned confidence; bottom: instance counts per bin. Left: NER; right: RE. NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE shows greater miscalibration (ECE 0.109--0.339), reflecting the difficulty of calibrating confidence for compound extraction tasks.}
94	\label{fig:reliability}
95	\end{figure*}
96	
97	Reliability diagrams use 10 equal-width bins.
98	NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE exhibits greater miscalibration (ECE 0.109--0.339), indicating that translating consistency scores into calibrated confidence estimates is feasible for NER but remains challenging for compound extraction tasks.
99	
100	\section{Additional Analyses}\label{app:additional}
101	
102	\paragraph{Per-relation diagnostic.}
103	RE signal degradation is relation-specific.
104	\textsc{Feature-Of} has near-zero correlation ($\rho{=}0.004$), while \textsc{Hyponym-Of} achieves $\rho{=}0.646$.
105	The primary bottleneck is entity span errors, which account for 55.5\% of RE false negatives---a prerequisite failure that consistency signals cannot detect, as they measure agreement among equally incorrect extractions.
106	We note that RE analysis relies on a single dataset (SciERC); generalization to other RE benchmarks remains to be validated.
107	
108	\paragraph{Capability stratification.}
109	For NER, SJ effectiveness scales with structural complexity: on SciERC instances with 6+ entities, $\rho{=}0.547$, compared to $\rho{=}0.415$ for 1--2 entities.
110	The SJ advantage over LP remains stable across sentence-length quartiles ($\Delta\rho{\approx}0.08$--$0.20$).
111	For RE, SJ $\rho$ increases monotonically with sentence length (Q1: 0.110 $\to$ Q4: 0.473; Fisher $z$-test $p{=}0.004$), indicating that longer, more relation-dense sentences provide richer structure for consistency-based estimation.
112	Both proxies are weakly correlated with F1 ($|r|{<}0.15$), confirming they capture input complexity rather than directly predicting output quality; however, entity count and sentence length are themselves moderately correlated ($\rho{=}0.650$), so they reflect overlapping rather than independent complexity dimensions.
113	For RE, entity count and relation count are strongly correlated ($\rho{=}0.769$) and thus reflect a single structural complexity dimension rather than independent axes.
114	On the high-complexity RE subset ($n{=}81$, high relation count), signals improve substantially: VC reaches $\rho{=}0.630$, LP $\rho{=}0.554$, and SJ $\rho{=}0.502$---all far above the full-set levels.
115	Richer relational structure provides more signal for consistency-based estimation, complementing the task-level boundary established by WNUT-17: structural signals are most effective within a ``sweet spot'' of sufficient model capability and sufficient output complexity.
116	
117	\paragraph{Length vs.\ log-probability.}
118	Figure~\ref{fig:length_logprob_scatter} shows that mean log-probability is weakly positively correlated with output length (NER: $\rho{=}0.386$, $n{=}4{,}232$; RE: $\rho{=}0.326$, $n{=}3{,}176$), ruling out length-penalty confounding as an explanation for LP's selection failure: longer outputs receive \textit{higher}, not lower, token-averaged log-probability under constrained decoding.
119	
120	\begin{figure}[t]
121	\centering
122	\includegraphics[width=\columnwidth]{fig_length_logprob_scatter}
123	\caption{Output length vs.\ mean log-probability on SciERC ($N{=}8$, $T{=}1.0$). Positive correlations (NER: $\rho{=}0.386$; RE: $\rho{=}0.326$) rule out length-penalty confounding.}
124	\label{fig:length_logprob_scatter}
125	\end{figure}
126	
127	\paragraph{Evaluation circularity and LOO-SJ equivalence.}
128	Consensus-proximity selection chooses $\hat{y} = \arg\max_{y_i} \sum_{j \neq i} \text{SJ}(y_i, y_j)$.
129	Leave-one-out SJ (LOO-SJ) for sample $y_i$ is $\text{LOO-SJ}_i = \frac{1}{N-1}\sum_{j \neq i} \text{SJ}(y_i, y_j)$.
130	Since the $\frac{1}{N-1}$ constant is shared across all candidates within an instance, $\arg\max_{y_i} \text{LOO-SJ}_i = \arg\max_{y_i} \sum_{j \neq i} \text{SJ}(y_i, y_j)$, making the two selection rules equivalent.
131	Standard (non-LOO) SJ adds the self-comparison term $\text{SJ}(y_i, y_i) = 1$ to each candidate, which is constant and thus does not affect ranking.
132	Empirically, LOO-SJ yields $\Delta\rho{=}{-}0.014$ relative to standard SJ (a correlation-level difference), with a maximum per-instance score difference of $3.1{\times}10^{-4}$ (negligible at the individual prediction level).
133	Evaluation circularity is negligible.
134	
135	\paragraph{Conditional filtering details.}
136	On LLaMA conditional RE (non-zero F1 instances), SJ recovers to $\rho{=}0.405$ while FK drops to $\rho{=}0.259$, confirming that structural advantage is robust across both models and evaluation conditions.
137	At $N{=}16$, the divergence persists: SJ maintains $\rho{=}0.308$ on conditional RE while LP drops to $\rho{=}{-}0.026$.
138	EM ranks first across all four tested conditional configurations---SciERC NER ($\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\rho{=}0.466$), CoNLL LLaMA 3-seed ($\rho{=}0.462$), and SciERC RE ($\rho{=}0.417$)---despite full-set rankings ranging from \#1 (CoNLL Qwen) to \#5 (SciERC RE).
139	On the full set, EM is diluted by trivial agreement: instances where all $N$ samples produce identical (possibly incorrect) outputs receive EM${=}1$ regardless of quality, compressing the signal's dynamic range.
140	On the conditional set---where the model demonstrably produces varied outputs---exact agreement becomes the strongest quality signal.
141	The margin over SJ is largest on RE ($\Delta\rho{=}{+}0.171$), where compound extraction decisions amplify output variability, and smallest on CoNLL LLaMA ($\Delta\rho{=}{+}0.002$), where all signals converge near $\rho{\approx}0.46$.
142	
143	\paragraph{WNUT-17 full signal analysis.}
144	Table~\ref{tab:wnut} reports all five signals on WNUT-17.
145	VC achieves $\rho{=}0.724$ (AUROC${=}0.913$) on the full set, but conditional analysis (non-zero F1 instances) reveals this is entirely driven by the zero/non-zero boundary: conditional $\rho{=}0.038$ ($p{=}0.49$).
146	LP shows the reverse pattern: full-set $\rho{=}{-}0.410$ but conditional $\rho{=}0.350$, the highest among all signals on the conditional set.
147	This inversion confirms that full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.
148	
149	\begin{table}[t]
150	\centering
151	\small
152	\caption{Quality estimation on WNUT-17 (Qwen, $N{=}8$, $T{=}1.0$, $n{=}689$ after filtering gold-empty instances). Cond: non-zero F1 instances ($n{=}334$). LP exhibits strong negative full-set $\rho$; its conditional $\rho$ reverses to the highest among all signals, confirming that full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.}
153	\label{tab:wnut}
154	\begin{tabular}{lccccc}
155	\toprule
156	Signal & $\rho$ & $p$ & AUROC & Cond.\ $\rho$ & Cond.\ $p$ \\
157	\midrule
158	VC      & .724 & ${<}$1e-112 & .913 & .038 & .487 \\
159	FK      & .125 & .001 & .555 & .169 & .002 \\
160	SJ      & .089 & .020 & .517 & .288 & ${<}$1e-7 \\
161	EM      & .050 & .194 & .487 & .333 & ${<}$1e-9 \\
162	LP & $-$.410 & ${<}$1e-28 & .219 & .350 & ${<}$1e-10 \\
163	\bottomrule
164	\end{tabular}
165	\end{table}
166	
167	\paragraph{Cross-configuration selection analysis.}
168	Table~\ref{tab:cross_selection} extends the selection analysis to four additional configurations.
169	On LLaMA SciERC, where output diversity remains substantial (18\% identical outputs, 39\% unique), LP achieves the highest selection F1 (0.652) at $N{=}8$ but still falls within bootstrap noise of greedy (0.646), replicating the gap observed on Qwen SciERC (Table~\ref{tab:selection}).
170	On CoNLL, 57--88\% of instances produce identical outputs across all $N$ samples, reflecting a ceiling effect (greedy F1 ${\approx}$0.91--0.92) rather than signal failure; selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.
171	
172	\begin{table*}[t]
173	\centering
174	\small
175	\caption{Best-of-$N$ selection F1 across configurations ($T{=}1.0$). Best non-oracle signal per row in \textbf{bold}. No signal significantly outperforms greedy in any configuration; CoNLL shows especially tight clustering where greedy already exceeds 0.90.}
176	\label{tab:cross_selection}
177	\begin{tabular}{llccccccc}
178	\toprule
179	Config & $n$ & Greedy & Oracle & SJ & FK & EM & LP & VC \\
180	\midrule
181	LLaMA/SciERC $N{=}8$ & 529 & .646 & .778 & .643 & .639 & .634 & \textbf{.652} & .633 \\
182	LLaMA/SciERC $N{=}16$ & 529 & .645 & .806 & \textbf{.649} & \textbf{.649} & .640 & .646 & .640 \\
183	Qwen/CoNLL $N{=}8$ & 2{,}756 & .908 & .948 & \textbf{.899} & .893 & .898 & .897 & .895 \\
184	LLaMA/CoNLL $N{=}8$ & 2{,}756 & .924 & .943 & .924 & \textbf{.925} & .924 & .924 & .923 \\
185	\bottomrule
186	\end{tabular}
187	\end{table*}
188	
189	\paragraph{Diminishing returns of $N$-scaling.}
190	Our $N{=}8$ and $N{=}16$ comparisons (Table~\ref{tab:robustness}) characterize the marginal value of additional samples for test-time scaling \cite{brown2024monkeys, snell2025scaling}.
191	For quality estimation, structural signals benefit consistently but sublinearly: SJ $\rho$ improves by $+0.047$ (Qwen SciERC, 3-seed mean) and $+0.032$ (LLaMA CoNLL, 3-seed mean) when doubling from $N{=}8$ to $N{=}16$, while log-probability is approximately $N$-invariant ($\Delta\rho{\leq}0.021$).
192	Structural signals leverage $\binom{N}{2}$ pairwise comparisons (28 pairs at $N{=}8$, 120 at $N{=}16$), but the $\rho$ improvement is far less than proportional, indicating diminishing information per additional comparison.
193	This asymmetry gives structural signals a relative advantage in the compute-constrained regime: at $N{=}8$, SJ already achieves $\rho{=}0.431$ on LLaMA CoNLL (vs.\ LP $\rho{=}0.307$, $\Delta{=}{+}0.124$), and the gap \textit{widens} at $N{=}16$ ($\Delta{=}{+}0.153$) because structural signals continue to benefit from additional pairwise evidence while LP does not.
194	For sample selection, additional samples increase the oracle upper bound---more draws raise the probability of a high-quality candidate---but signal-based selection remains flat because the selector's inability to identify the best candidate is a granularity limitation, not a sample size limitation.
195	The practical implication is that $N{=}8$ captures most of the achievable quality estimation benefit; further scaling widens rather than closes the correlation-selection gap absent stronger per-sample selectors.
196	
197	\section{Bootstrap CI for Signal Comparisons}\label{app:bootstrap_signal}
198	
199	Table~\ref{tab:bootstrap_signal_ci} reports bootstrap confidence intervals for individual signal $\rho$ and pairwise $\Delta\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$).
200	The SJ--LP gap ($\Delta\rho{=}{+}0.155$) is clearly significant, confirming the structural advantage reported in \S\ref{sec:qe_results}.
201	The VC--SJ gap ($\Delta\rho{=}{+}0.019$) is not significant, indicating that these two structural signals perform comparably.
202	The SJ--EM gap ($\Delta\rho{=}{+}0.065$) is borderline significant, with the CI lower bound at $+0.003$ and upper bound at $+0.130$.
203	
204	\begin{table}[t]
205	\centering
206	\small
207	\caption{Bootstrap 95\% CIs for signal $\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$). Top: individual signals. Bottom: pairwise $\Delta\rho$; ``Sig.'' indicates whether the 95\% CI excludes zero.}
208	\label{tab:bootstrap_signal_ci}
209	\begin{tabular}{lcc}
210	\toprule
211	Signal & $\rho$ & 95\% CI \\
212	\midrule
213	VC & +0.379 & [+0.299, +0.456] \\
214	SJ & +0.360 & [+0.277, +0.437] \\
215	EM & +0.295 & [+0.212, +0.371] \\
216	FK & +0.267 & [+0.176, +0.354] \\
217	LP & +0.205 & [+0.119, +0.291] \\
218	\bottomrule
219	\end{tabular}
220	
221	\vspace{0.5em}
222	
223	\begin{tabular}{lccc}
224	\toprule
225	Comparison & $\Delta\rho$ & 95\% CI & Sig. \\
226	\midrule
227	SJ $-$ LP & +0.155 & [+0.074, +0.234] & Yes \\
228	VC $-$ SJ & +0.019 & [$-$0.033, +0.073] & No \\
229	SJ $-$ EM & +0.065 & [+0.003, +0.130] & Marginal$^\dagger$ \\
230	\bottomrule
231	\end{tabular}
232	
233	\smallskip
234	{\footnotesize $^\dagger$Marginally significant without multiple comparison correction; would not survive Bonferroni correction for 10 pairwise comparisons ($\alpha_{\text{adj}}{=}0.005$).}
235	\end{table}
236	
237	\section{Diversity and Selection Analysis}\label{app:diversity}
238	
239	\paragraph{Output diversity quantification.}
240	Table~\ref{tab:diversity} summarizes output diversity across configurations.
241	On SciERC, output diversity is substantial: Qwen produces 43\% unique outputs per instance (mean 3.5 distinct out of $N{=}8$), with per-sample F1 standard deviation of 0.144 and mean pairwise SJ of 0.703.
242	LLaMA shows similar diversity (39\% unique, F1 std 0.11).
243	On CoNLL, diversity collapses: 57\% (Qwen) to 88\% (LLaMA) of instances produce identical outputs across all $N$ samples, reflecting a ceiling effect where greedy F1 already exceeds 0.90.
244	WNUT-17 shows 55\% identical outputs, driven by the 52\% zero-F1 rate.
245	
246	\begin{table}[t]
247	\centering
248	\small
249	\caption{Output diversity across configurations ($N{=}8$, $T{=}1.0$). ``Identical'' = fraction of instances with all $N$ outputs identical. ``Unique'' = mean fraction of distinct outputs per instance.}
250	\label{tab:diversity}
251	\begin{tabular}{lcc}
252	\toprule
253	Config & Identical & Unique \\
254	\midrule
255	Qwen/SciERC & 11\% & 43\% \\
256	LLaMA/SciERC & 18\% & 39\% \\
257	Qwen/CoNLL & 57\% & --- \\
258	LLaMA/CoNLL & 88\% & --- \\
259	WNUT-17 & 55\% & --- \\
260	\bottomrule
261	\end{tabular}
262	\end{table}
263	
264	\paragraph{Oracle-improvable fraction.}
265	Across SciERC configurations, 39--42\% of instances contain at least one sample with F1 exceeding greedy: Qwen NER 42.0\% (222/529, mean headroom $+$31.9~pp among improvable instances), Qwen RE 41.3\% (164/397, $+$45.3~pp), LLaMA NER 39.3\% (208/529, $+$33.7~pp).
266	On CoNLL, only 4--9\% of instances are improvable, confirming the ceiling effect.
267	
268	\paragraph{Diversity-stratified selection gap.}
269	On the 44\% of Qwen SciERC instances with high diversity (${\geq}4$ unique outputs among 8 samples, $n{=}232$), oracle headroom reaches $+$16.3~pp, yet all consistency-based signals (SJ, FK, EM, VC) select at or below greedy, and LP---the only per-sample signal---achieves merely $+$0.8~pp.
270	LLaMA replicates this pattern: on its high-diversity subset ($n{=}186$), oracle headroom reaches $+$20.1~pp while consistency signals remain at or below greedy and LP captures only $+$2.0~pp.
271	This rules out insufficient diversity as an explanation for the correlation-selection gap.
272	
273	\paragraph{TOST equivalence testing.}
274	The primary evidence against selection gains comes from effect sizes and confidence intervals: Cohen's $d{=}0.038$ for the best signal (NER LP) and bootstrap 95\% CI [$-$3.0, $+$4.2]~pp spanning zero.
275	Table~\ref{tab:tost} supplements this with two one-sided tests (TOST), testing whether each signal's selection F1 is equivalent to greedy within a bound $\delta$.
276	The $\delta$ values are anchored to oracle headroom (13--18~pp): $\delta{=}5$~pp corresponds to forgoing 28--38\% of the available headroom, $\delta{=}3$~pp forgoing 17--23\%, and $\delta{=}2$~pp less than 15\%.
277	The breakpoint $\delta^*$---the minimum equivalence margin at which each signal passes TOST---ranges from approximately 1.3~pp (SJ, ${\sim}$10\% of oracle headroom) to 3.4~pp (FK, ${\sim}$26\%) on NER, and from approximately 2.9~pp (LP, ${\sim}$16\%) to 6.5~pp (VC, ${\sim}$36\%) on RE.
278	On NER ($n{=}529$), at $\delta{=}{\pm}2$~pp, SJ and LP are confirmed equivalent to greedy (TOST $p{<}0.05$); at $\delta{=}{\pm}3$~pp, four of five signals pass; at $\delta{=}{\pm}5$~pp, all five pass.
279	On RE ($n{=}397$, preliminary), EM and VC fail equivalence even at $\delta{=}{\pm}5$~pp due to systematic underperformance ($\Delta{=}{-}3.2$~pp and $-4.5$~pp respectively).
280	The effect sizes are negligible ($d{=}0.038$) and confidence intervals span zero, with TOST confirming equivalence at practically meaningful margins.
281	
282	\begin{table}[t]
283	\centering
284	\small
285	\caption{TOST equivalence testing: signals vs.\ greedy on SciERC ($N{=}8$, $T{=}1.0$). \checkmark: equivalent at $p{<}0.05$; \texttimes: not equivalent. $\Delta$: mean F1 difference (signal $-$ greedy).}
286	\label{tab:tost}
287	\begin{tabular}{l cccc cccc}
288	\toprule
289	& \multicolumn{4}{c}{\textbf{NER}} & \multicolumn{4}{c}{\textbf{RE}} \\
290	\cmidrule(lr){2-5} \cmidrule(lr){6-9}
291	Signal & $\Delta$ & $\pm$2 & $\pm$3 & $\pm$5 & $\Delta$ & $\pm$2 & $\pm$3 & $\pm$5 \\
292	\midrule
293	LP & +0.6 & \checkmark & \checkmark & \checkmark & $-$0.9 & \texttimes & \checkmark & \checkmark \\
294	SJ & +0.1 & \checkmark & \checkmark & \checkmark & $-$1.8 & \texttimes & \texttimes & \checkmark \\
295	FK & $-$0.5 & \texttimes & \checkmark & \checkmark & $-$1.6 & \texttimes & \texttimes & \checkmark \\
296	EM & $-$0.8 & \texttimes & \checkmark & \checkmark & $-$3.2 & \texttimes & \texttimes & \texttimes \\
297	VC & $-$1.0 & \texttimes & \texttimes & \checkmark & $-$4.5 & \texttimes & \texttimes & \texttimes \\
298	\bottomrule
299	\end{tabular}
300	\end{table}
301	
302	\section{Multi-Seed Stability}\label{app:multiseed}
303	
304	Table~\ref{tab:multiseed} reports quality estimation metrics across three random seeds for both model families on SciERC ($N{=}8$, $T{=}1.0$).
305	On NER, the signal ranking VC${>}$SJ${>}$EM${>}$FK${>}$LP is identical across all six model-seed combinations, with $\sigma{\leq}0.025$ for all signals.
306	On RE (Qwen only, preliminary), VC remains the top signal ($\rho{=}0.309{\pm}0.024$), but LP rises to \#2 ($\rho{=}0.297{\pm}0.022$), above FK, SJ, and EM---a reversal from the NER ranking that reflects RE's higher sensitivity to per-sample scoring.
307	LLaMA absolute values are systematically lower than Qwen on NER, consistent with the directionally-consistent-but-magnitude-dependent characterization in the main text.
308	
309	\begin{table}[t]
310	\centering
311	\small
312	\caption{Multi-seed quality estimation on SciERC ($N{=}8$, $T{=}1.0$, seeds: 42, 123, 456). NER: both models; RE: Qwen only (preliminary). Signal ranking is stable across seeds ($\sigma{\leq}0.025$). $\sigma$ is population standard deviation over 3 seeds.}
313	\label{tab:multiseed}
314	\begin{tabular}{lccccc}
315	\toprule
316	& LP & FK & SJ & VC & EM \\
317	\midrule
318	\multicolumn{6}{l}{\textit{NER Spearman $\rho$ (mean $\pm\sigma$)}} \\
319	Qwen & .217${\pm}$.013 & .254${\pm}$.016 & .364${\pm}$.018 & .386${\pm}$.019 & .307${\pm}$.008 \\
320	LLaMA & .162${\pm}$.025 & .256${\pm}$.024 & .325${\pm}$.021 & .384${\pm}$.014 & .279${\pm}$.011 \\
321	\midrule
322	\multicolumn{6}{l}{\textit{RE Spearman $\rho$ (mean $\pm\sigma$, Qwen)}} \\
323	Qwen & .297${\pm}$.022 & .290${\pm}$.012 & .249${\pm}$.002 & .309${\pm}$.024 & .135${\pm}$.016 \\
324	\midrule
325	\multicolumn{6}{l}{\textit{NER AUROC (mean $\pm\sigma$)}} \\
326	Qwen & .613${\pm}$.002 & .618${\pm}$.009 & .684${\pm}$.009 & .697${\pm}$.010 & .661${\pm}$.010 \\
327	LLaMA & .577${\pm}$.007 & .616${\pm}$.011 & .655${\pm}$.010 & .689${\pm}$.005 & .636${\pm}$.006 \\
328	\bottomrule
329	\end{tabular}
330	\end{table}
331	
332	\section{Training Configuration}\label{app:training}
333	
334	Both models are fine-tuned with identical hyperparameters (Table~\ref{tab:training}) to ensure comparisons across model families reflect model differences rather than training confounds.
335	
336	\begin{table}[t]
337	\centering
338	\small
339	\caption{Training configuration. Both Qwen3-8B and LLaMA-3.1-8B-Instruct use identical settings unless noted.}
340	\label{tab:training}
341	\begin{tabular}{ll}
342	\toprule
343	Parameter & Value \\
344	\midrule
345	LoRA rank / $\alpha$ & 32 / 64 \\
346	LoRA target & All linear modules \\
347	LoRA dropout & 0 \\
348	Optimizer & AdamW \\
349	Learning rate & 2e-4, cosine schedule \\
350	Warmup ratio & 0.1 \\
351	Effective batch size & 16 (2 $\times$ grad.\ accum.\ 8) \\
352	Epochs & 5 \\
353	Max sequence length & 2048 \\
354	Precision & bf16 \\
355	Gradient checkpointing & Enabled \\
356	Max gradient norm & 1.0 \\
357	Training seed & 42 \\
358	Framework & LLaMA Factory \\
359	\midrule
360	\multicolumn{2}{l}{\textit{Dataset-specific}} \\
361	SciERC split & 1861 / 275 / 551 \\
362	CoNLL / WNUT & +\,load\_best\_model\_at\_end, \\
363	& eval\_steps${=}$200, save\_limit${=}$5 \\
364	\bottomrule
365	\end{tabular}
366	\end{table}
367	
368	\paragraph{Prompt template.}
369	For NER, we use a structured prompt:
370	\begin{quote}
371	\small
372	\texttt{System:} You are an expert in Named Entity Recognition.\\
373	\texttt{User:} Extract all named entities from the following text. Output as JSON.\\
374	Text: \texttt{\{input\_text\}}\\
375	Entity types: \texttt{\{schema\_types\}}
376	\end{quote}
377	RE follows the same structure with ``Relation Extraction'' and relation type lists substituted accordingly.
378	
379	\paragraph{Constrained decoding.}
380	Inference uses vLLM with XGrammar-based JSON schema enforcement \cite{willard2023guided}, which constrains outputs to valid entity/relation structures matching the target schema.
381	This eliminates format errors but may compress per-sample diversity by restricting the output space.\footnote{SciERC training used \texttt{enable\_thinking=True} (LLaMA Factory 0.9.4 default), injecting empty \texttt{&lt;think>&lt;/think>} blocks (4--5 tokens) into each training response with loss computation; CoNLL and WNUT explicitly set \texttt{enable\_thinking=False}. Constrained decoding at inference time enforces JSON-only output, suppressing thinking tokens. See \S\ref{sec:setup} and Limitations for discussion of this confound.}
382	
383	\section{Log-Probability Score Compression}\label{app:logprob_ties}
384	
385	Under constrained decoding, log-probability scores are severely compressed within instances, limiting per-sample discrimination (Table~\ref{tab:logprob_ties}).
386	The median within-instance LP range is only 0.041, and 75\% of pairwise comparisons are effective ties ($|\Delta|{<}0.026$).
387	At $\varepsilon{=}0.05$, 60.3\% of instances have a within-sample range below the threshold, leaving LP unable to meaningfully distinguish candidates.
388	For comparison, SJ has only 12.5\% tied instances at the same threshold---SJ's advantage over LP for selection is one of score resolution, not information content.
389	
390	\begin{table}[t]
391	\centering
392	\small
393	\caption{Log-probability score compression on SciERC NER ($N{=}8$, $n{=}529$). ``Tied'' = fraction of instances where within-instance LP range ${<}\varepsilon$.}
394	\label{tab:logprob_ties}
395	\begin{tabular}{lc}
396	\toprule
397	$\varepsilon$ threshold & Tied instances (\%) \\
398	\midrule
399	0.01 & 1.1\% \\
400	0.05 & 60.3\% \\
401	0.1  & ${\sim}$84\% \\
402	0.5  & ${\sim}$99\% \\
403	\bottomrule
404	\end{tabular}
405	\end{table}
406	
407	\paragraph{Non-tied subset.}
408	Among instances with LP range ${\geq}0.05$ ($n{=}210$, 40\% of total), log-probability selection \textit{significantly} outperforms greedy ($+2.9$~pp F1, $p{=}0.01$), and within-instance $\rho(\text{LP}, \text{F1})$ rises from 0.08 (tied subset) to 0.39 (non-tied subset).
409	This confirms that LP carries useful per-sample quality information but is resolution-limited---the signal exists but is compressed below the discrimination threshold for most instances.
410	A free-form decoding ablation (Appendix~\ref{app:freeform_ablation}) confirms this compression is intrinsic, not decoding-regime-specific.
411	
412	\section{RE Conditional Selection}\label{app:re_conditional_selection}
413	
414	Table~\ref{tab:re_cond_selection} extends the selection analysis to the RE non-zero F1 subset.
415	Of $n{=}397$ RE instances, 238 (60\%) have non-zero F1 and 159 (40\%) have zero F1.
416	All five signals underperform greedy on both subsets.
417	On the non-zero subset, selection performance is \textit{worse} than on the full set (e.g., VC: $-10.0$~pp on non-zero vs.\ $-4.5$~pp on full set), because greedy is already strong on non-zero instances (F1${=}0.674$) and signals actively select inferior samples.
418	Oracle headroom exists (0.757 vs.\ 0.674) but no signal exploits it, ruling out the 40\% zero-F1 floor effect as the explanation for RE selection failure.
419	
420	\begin{table}[t]
421	\centering
422	\small
423	\caption{RE selection F1 on SciERC ($N{=}8$, $T{=}1.0$). Full set ($n{=}397$) and non-zero F1 subset ($n{=}238$). No signal outperforms greedy on either subset.}
424	\label{tab:re_cond_selection}
425	\begin{tabular}{lcc}
426	\toprule
427	Method & Full ($n{=}397$) & Non-zero ($n{=}238$) \\
428	\midrule
429	Oracle & 0.585 & 0.757 \\
430	\midrule
431	LP & 0.395 & 0.600 \\
432	SJ & 0.386 & 0.604 \\
433	EM & 0.372 & 0.583 \\
434	VC & 0.359 & 0.574 \\
435	\midrule
436	Greedy & 0.404 & 0.674 \\
437	\bottomrule
438	\end{tabular}
439	\end{table}
440	
441	\section{Free-Form Decoding Ablation}\label{app:freeform_ablation}
442	
443	Table~\ref{tab:freeform_ablation} compares constrained and free-form decoding across four dimensions on SciERC ($N{=}8$, $T{=}1.0$, Qwen3-8B).
444	Free-form decoding removes grammar constraints entirely; outputs are parsed post-hoc (parse rate 99.95\%, 4406/4408).
445	LP score distributions are nearly identical across regimes (Panel~A: within-instance std ratio $0.97{\times}$), and NER selection gains remain negligible under both regimes (Panel~B).
446	RE LP selection flips positive under free-form decoding ($+1.69$~pp vs.\ $-0.68$~pp constrained).
447	Quality estimation improves modestly for most signals under free-form decoding (Panel~C), with the largest gain for FK ($+0.053$ NER, $+0.039$ RE).
448	
449	\begin{table*}[t]
450	\centering
451	\caption{Comparison of constrained vs.\ free-form decoding on SciERC (Qwen3-8B, $N{=}8$, $T{=}1.0$, seed=42).}
452	\label{tab:freeform_ablation}
453	
454	\vspace{2pt}
455	{\small\textsc{Panel A: Logprob Distribution}}
456	\vspace{2pt}
457	
458	\begin{tabular}{lccc}
459	\toprule
460	Metric & Constrained & Free-form & $\Delta$ \\
461	\midrule
462	Mean LP std        & 0.0206 & 0.0199 & $-$0.0007 \\
463	Mean LP range      & 0.0623 & 0.0599 & $-$0.0024 \\
464	Tied fraction ($\varepsilon{=}0.05$) & 59.7\% & 57.7\% & $-$2.0\,pp \\
465	\bottomrule
466	\end{tabular}
467	
468	\vspace{8pt}
469	
470	{\small\textsc{Panel B: Selection F1}}
471	\vspace{2pt}
472	
473	\begin{tabular}{llccc}
474	\toprule
475	Task & Method & Constrained & Free-form & $\Delta$ \\
476	\midrule
477	\multirow{3}{*}{NER}
478	  & Greedy        & 0.6182 & 0.6204 & $+$0.0022 \\
479	  & LP-selected   & 0.6241 & 0.6222 & $-$0.0019 \\
480	  & Selection gap & $+$0.0059 & $+$0.0018 & $-$0.0041 \\
481	\midrule
482	\multirow{3}{*}{RE}
483	  & Greedy        & 0.2913 & 0.2880 & $-$0.0033 \\
484	  & LP-selected   & 0.2845 & 0.3050 & \textbf{$+$0.0205} \\
485	  & Selection gap & $-$0.0068 & $+$0.0169 & \textbf{$+$0.0237} \\
486	\bottomrule
487	\end{tabular}
488	
489	\vspace{8pt}
490	
491	{\small\textsc{Panel C: QE Signal Quality (Spearman $\rho$)}}
492	\vspace{2pt}
493	
494	\begin{tabular}{l ccc ccc}
495	\toprule
496	 & \multicolumn{3}{c}{NER ($n{=}529$)} & \multicolumn{3}{c}{RE ($n{=}397$)} \\
497	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
498	Signal & Constr. & Free & $\Delta$ & Constr. & Free & $\Delta$ \\
499	\midrule
500	SJ & 0.360 & 0.377 & $+$0.018 & 0.250 & 0.273 & $+$0.023 \\
501	FK & 0.267 & 0.320 & $+$0.053 & 0.275 & 0.315 & $+$0.039 \\
502	LP & 0.205 & 0.213 & $+$0.008 & 0.266 & 0.304 & $+$0.038 \\
503	EM & 0.295 & 0.317 & $+$0.023 & 0.134 & 0.137 & $+$0.002 \\
504	VC & 0.379 & 0.409 & $+$0.030 & 0.350 & 0.323 & $-$0.026 \\
505	\bottomrule
506	\end{tabular}
507	
508	\vspace{8pt}
509	
510	{\small\textsc{Panel D: Parse Rate (Free-form)}}
511	\vspace{2pt}
512	
513	\begin{tabular}{lc}
514	\toprule
515	Metric & Value \\
516	\midrule
517	Total samples          & 4408 \\
518	Parse rate             & 99.95\% \\
519	Instances 8/8 valid    & 549\,/\,551 (99.6\%) \\
520	\bottomrule
521	\end{tabular}
522	
523	\end{table*}
524	
525	\section{LP Selection Failure Stability}\label{app:lp_failure_stability}
526	
527	We analyze RE LP selection failures across three random seeds (constrained decoding, $N{=}8$, $T{=}1.0$, Qwen3-8B) to assess whether failures are systematic or stochastic.
528	
529	\paragraph{Pairwise overlap.}
530	LP selection failures (instances where LP-selected F1 $<$ greedy F1) show moderate cross-seed stability: the average pairwise Jaccard similarity is 0.42 (range: 0.38--0.46), indicating that failures are partially systematic---driven by instance complexity---but not fully deterministic.
531	The 3-way intersection contains 34 instances (27.9\% of any-seed failures), confirming a stable failure core.
532	
533	\paragraph{Instance complexity drives failure.}
534	Table~\ref{tab:stable_failures} stratifies instances by failure stability.
535	Stable failures (all 3 seeds) involve more gold relations (2.12 vs.\ 1.62 for never-fail instances) and higher greedy F1 (0.688 vs.\ 0.429), indicating that LP mis-selects on instances where the model already performs well---precisely the instances where selection would be most valuable.
536	Failure rate increases monotonically with gold relation count: 4.3\% at 1 relation, 20.7\% at 3 relations, 26.2\% at 6 relations.
537	
538	\begin{table}[t]
539	\centering
540	\small
541	\caption{RE LP selection failure stability across 3 seeds (SciERC, $N{=}8$). Stable failures concentrate on relation-dense instances with high greedy F1.}
542	\label{tab:stable_failures}
543	\begin{tabular}{lcccc}
544	\toprule
545	Group & $n$ & Gold rels & Greedy F1 & LP $\Delta$F1 \\
546	\midrule
547	Stable fail (3 seeds) & 34 & 2.12 & 0.688 & $-$0.499 \\
548	Fail 2+ seeds & 26 & 2.46 & 0.774 & $-$0.450 \\
549	Fail 1 seed & 62 & 2.32 & 0.692 & $-$0.239 \\
550	Never fail & 429 & 1.62 & 0.429 & $+$0.041 \\
551	\bottomrule
552	\end{tabular}
553	\end{table}
554	
555	\paragraph{Flip instances.}
556	Only 5 RE instances with gold relations flip from LP failure (constrained) to LP success (free-form), with mean gold relation count 3.67 (well above the population mean of 1.86).
557	These instances show large constrained LP errors ($\Delta{=}{-}0.430$) that reverse under free-form decoding ($\Delta{=}{+}0.503$), but their rarity (5/397) confirms that the RE selection flip is driven by aggregate variance reallocation rather than systematic instance-level correction.
558	
559	\section{$N$-Scaling Detailed Analysis}\label{app:n_scaling}
560	
561	Tables~\ref{tab:n-scaling}--\ref{tab:sigma-comparison} provide detailed $N$-scaling analysis on Qwen3-8B SciERC with 3-seed statistics.
562	
563	\begin{table}[t]
564	\centering
565	\caption{Effect of sample pool size on signal quality (Qwen3-8B, SciERC, 3-seed mean Spearman $\rho$).}
566	\label{tab:n-scaling}
567	\small
568	\begin{tabular}{l ccc ccc}
569	\toprule
570	 & \multicolumn{3}{c}{\textbf{NER} $\rho$} & \multicolumn{3}{c}{\textbf{RE} $\rho$} \\
571	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
572	Signal & $N\!=\!8$ & $N\!=\!16$ & $\Delta$ & $N\!=\!8$ & $N\!=\!16$ & $\Delta$ \\
573	\midrule
574	SJ & 0.3641 & 0.4105 & \textbf{+0.0464} & 0.2485 & 0.2758 & \textbf{+0.0273} \\
575	FK & 0.2536 & 0.2833 & \textbf{+0.0297} & 0.2903 & 0.2964 & \textbf{+0.0061} \\
576	VC & 0.3861 & 0.4092 & \textbf{+0.0231} & 0.3088 & 0.3738 & \textbf{+0.0650} \\
577	LP & 0.2167 & 0.2393 & \textbf{+0.0226} & 0.2970 & 0.3100 & \textbf{+0.0130} \\
578	EM & 0.3071 & 0.3395 & \textbf{+0.0324} & 0.1353 & 0.1506 & \textbf{+0.0153} \\
579	\midrule
580	Mean & 0.3055 & 0.3364 & \textbf{+0.0308} & 0.2560 & 0.2813 & \textbf{+0.0253} \\
581	\bottomrule
582	\end{tabular}
583	\end{table}
584	
585	\begin{table}[t]
586	\centering
587	\caption{Cross-seed signal ranking stability (Kendall's $W$, 3 seeds).}
588	\label{tab:ranking-stability}
589	\small
590	\begin{tabular}{ll cc l}
591	\toprule
592	Model & Task & $N$ & Kendall's $W$ & Consensus ranking \\
593	\midrule
594	Qwen  & NER & 8  & 1.000 & VC $>$ SJ $>$ EM $>$ FK $>$ LP \\
595	Qwen  & NER & 16 & 0.956 & SJ $\approx$ VC $>$ EM $>$ FK $>$ LP \\
596	Qwen  & RE  & 8  & 0.822 & VC $>$ LP $>$ FK $>$ SJ $>$ EM \\
597	Qwen  & RE  & 16 & 0.956 & VC $>$ LP $>$ FK $>$ SJ $>$ EM \\
598	LLaMA & NER & 8  & 1.000 & VC $>$ SJ $>$ EM $>$ FK $>$ LP \\
599	\bottomrule
600	\end{tabular}
601	\end{table}
602	
603	\begin{table}[t]
604	\centering
605	\caption{Cross-seed standard deviation ($\sigma$) of Spearman $\rho$ at $N\!=\!8$ vs.\ $N\!=\!16$ (Qwen3-8B, SciERC, 3 seeds). $\sigma$ is population standard deviation.}
606	\label{tab:sigma-comparison}
607	\small
608	\begin{tabular}{l cc cc}
609	\toprule
610	 & \multicolumn{2}{c}{\textbf{NER} $\sigma_\rho$} & \multicolumn{2}{c}{\textbf{RE} $\sigma_\rho$} \\
611	\cmidrule(lr){2-3} \cmidrule(lr){4-5}
612	Signal & $N\!=\!8$ & $N\!=\!16$ & $N\!=\!8$ & $N\!=\!16$ \\
613	\midrule
614	SJ & 0.0179 & 0.0102 & 0.0015 & 0.0067 \\
615	FK & 0.0157 & 0.0079 & 0.0121 & 0.0143 \\
616	VC & 0.0187 & 0.0260 & 0.0244 & 0.0158 \\
617	EM & 0.0076 & 0.0031 & 0.0157 & 0.0049 \\
618	LP & 0.0125 & 0.0017 & 0.0218 & 0.0152 \\
619	\midrule
620	Mean & 0.0145 & 0.0098 & 0.0151 & 0.0114 \\
621	\bottomrule
622	\end{tabular}
623	\end{table}
624	
625	Signal rankings are highly stable across seeds: Kendall's $W{=}1.000$ for NER at $N{=}8$ (both models), dropping only to $W{=}0.956$ at $N{=}16$ where SJ and VC converge (Table~\ref{tab:ranking-stability}).
626	Doubling $N$ reduces cross-seed $\sigma$ by 32\% on NER and 24\% on RE (Table~\ref{tab:sigma-comparison}), with the largest reductions for SJ ($-43\%$ NER) and EM ($-59\%$ NER), confirming that additional samples stabilize structural signals more than LP.
627	
628	\section{Cross-Dataset OOD Analysis}\label{app:ood}
629	
630	To test whether confidence signals generalize under domain shift, we evaluate models on out-of-distribution data: a SciERC-trained model applied to CoNLL instances (wider$\to$narrower schema) and vice versa (Table~\ref{tab:ood}).
631	
632	\begin{table}[t]
633	\centering
634	\small
635	\caption{Cross-dataset OOD quality estimation (Spearman $\rho$, Qwen3-8B, $N{=}8$, $T{=}1.0$). SciERC$\to$CoNLL: SciERC-trained model on CoNLL instances ($n{=}2756$). CoNLL$\to$SciERC: CoNLL-trained model on SciERC instances ($n{=}529$). In-domain $\rho$ from Table~\ref{tab:quality_estimation}. \textsuperscript{***}$p{<}0.001$, \textsuperscript{*}$p{<}0.05$.}
636	\label{tab:ood}
637	\begin{tabular}{l ccc ccc}
638	\toprule
639	 & \multicolumn{3}{c}{\textbf{SciERC$\to$CoNLL}} & \multicolumn{3}{c}{\textbf{CoNLL$\to$SciERC}} \\
640	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
641	Signal & $\rho$ & In-dom. & $\Delta$ & $\rho$ & In-dom. & $\Delta$ \\
642	\midrule
643	VC & .469\textsuperscript{***} & .386 & +.083 & +.105\textsuperscript{*} & .386 & $-$.281 \\
644	SJ & .378\textsuperscript{***} & .364 & +.014 & $-$.186\textsuperscript{***} & .364 & $-$.550 \\
645	EM & .300\textsuperscript{***} & .307 & $-$.007 & $-$.202\textsuperscript{***} & .307 & $-$.509 \\
646	FK & .285\textsuperscript{***} & .254 & +.031 & $-$.070 & .254 & $-$.324 \\
647	LP & .246\textsuperscript{***} & .217 & +.029 & $-$.152\textsuperscript{***} & .217 & $-$.369 \\
648	\bottomrule
649	\end{tabular}
650	\end{table}
651	
652	\paragraph{Wider-to-narrower schema transfer.}
653	When the SciERC-trained model (6 NER types) is applied to CoNLL (4 types), all signals remain significant ($p{<}0.001$) and structural signals improve over their in-domain levels (same model, seed${=}42$, $N{=}8$; in-domain $\rho$ from Table~\ref{tab:quality_estimation}): VC reaches $\rho{=}0.469$ (in-domain $0.386$, $\Delta{=}{+}0.083$), SJ $\rho{=}0.378$ (in-domain $0.364$, $\Delta{=}{+}0.014$), and FK $\rho{=}0.285$ (in-domain $0.254$, $\Delta{=}{+}0.031$).
654	The wider training schema subsumes CoNLL's narrower schema, so the model produces reasonable outputs even out-of-domain (greedy F1${=}0.522$), and structural signals benefit from the simpler target schema's reduced output ambiguity.
655	
656	\paragraph{Narrower-to-wider schema transfer (excluded).}
657	The reverse direction is excluded from our conclusions due to catastrophic model failure, not signal failure.
658	The CoNLL-trained model recognizes only 4 news entity types (PER, ORG, LOC, MISC) and has no relation extraction capability; when applied to SciERC's 6 scientific entity types and 7 relation types, the model cannot produce meaningful structured outputs (greedy NER F1${=}0.009$, RE F1${=}0.001$).
659	Under this regime, most signals flip to negative or near-zero correlations (Table~\ref{tab:ood}); only VC retains weak positive correlation ($\rho{=}0.105$, $p{=}0.016$).
660	These negative correlations reflect the model systematically generating confident but incorrect outputs---a capability failure analogous to WNUT-17 (\S\ref{sec:qe_results}), not evidence against signal utility.
661	
662	\paragraph{Asymmetry interpretation.}
663	The directional asymmetry is driven by schema coverage: wider$\to$narrower preserves signal utility because the SciERC model's 6-type schema subsumes CoNLL's 4 types, while narrower$\to$wider fails because the CoNLL model lacks the entity and relation types required by SciERC.
664	This extends the capability boundary identified on WNUT-17 to the domain-shift setting: confidence signals require sufficient model capability as a prerequisite, and results from the CoNLL$\to$SciERC direction should not be interpreted as evidence of signal degradation under domain shift.
665	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "50ece6e9-a1e8-460e-88a4-809f84d7187e",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "148c1a7c-8809-4ac4-a34d-4df6c9f6a19b",
  "sourceToolAssistantUUID": "50ece6e9-a1e8-460e-88a4-809f84d7187e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 36 · 2026-05-15T12:44:39.426Z_

Now let me search for specific items I still need to verify.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "148c1a7c-8809-4ac4-a34d-4df6c9f6a19b",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NkbcVviMRKx2Z191Fz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3da5d5b8-bd03-4fdb-b775-0d2199a33eb3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0141BccuMFY6NpCvzgpcqLBS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 22383,
      "cache_read_input_tokens": 45624,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 22383,
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

_source line 37 · 2026-05-15T12:44:41.867Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01DpCzKTH7tMjuFq9nbeCHou`</summary>

```json
{
  "pattern": "\\bfirst\\b",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "-i": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3da5d5b8-bd03-4fdb-b775-0d2199a33eb3",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NkbcVviMRKx2Z191Fz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8056695d-fecc-44d7-b0e3-b6fa7e12ac10",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0141BccuMFY6NpCvzgpcqLBS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 22383,
      "cache_read_input_tokens": 45624,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 22383,
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

_source line 38 · 2026-05-15T12:44:41.887Z_

<details><summary>↩ Tool result · `toolu_01DpCzKTH7tMjuFq9nbeCHou`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex:20:The empty blocks may weakly affect first-token probability distributions during training, potentially shifting LP score calibration on SciERC; however, since LP selection fails across all datasets including CoNLL and WNUT-17 (which lack this confound), the thinking token inconsistency is unlikely to explain the correlation-selection gap.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex:35:First, the free-form ablation exposes a task-specific interaction: RE LP selection flips from $-0.68$~pp (constrained) to $+1.69$~pp (free-form; preliminary, single RE benchmark), a reversal that is universal across all 7 relation types and driven by selective variance reallocation ($p{<}0.0001$).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:138:EM ranks first across all four tested conditional configurations---SciERC NER ($\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\rho{=}0.466$), CoNLL LLaMA 3-seed ($\rho{=}0.462$), and SciERC RE ($\rho{=}0.417$)---despite full-set rankings ranging from \#1 (CoNLL Qwen) to \#5 (SciERC RE).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8056695d-fecc-44d7-b0e3-b6fa7e12ac10",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "bed3b2fd-4c22-40bf-9843-666874d667ca",
  "sourceToolAssistantUUID": "8056695d-fecc-44d7-b0e3-b6fa7e12ac10",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 39 · 2026-05-15T12:44:42.909Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01HQ5jTSuo5B6NGBbtqC3N8V`</summary>

```json
{
  "pattern": "voting confidence|VC",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper",
  "glob": "*.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bed3b2fd-4c22-40bf-9843-666874d667ca",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NkbcVviMRKx2Z191Fz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2bea12f5-8a65-4262-8259-66c6204c3569",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0141BccuMFY6NpCvzgpcqLBS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 22383,
      "cache_read_input_tokens": 45624,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 22383,
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

_source line 40 · 2026-05-15T12:44:42.929Z_

<details><summary>↩ Tool result · `toolu_01HQ5jTSuo5B6NGBbtqC3N8V`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/discussion.tex:4:For per-instance quality ranking, VC provides the strongest rank correlation ($\rho{=}0.38$), though EM leads binary discrimination (AUROC${=}0.749$); under conditional filtering, EM leads on both NER and RE ($\rho{=}0.360$, $0.417$; RE: preliminary, single benchmark).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/discussion.tex:5:Signal rankings depend on task difficulty---EM dominates easy tasks (CoNLL), VC and SJ dominate hard tasks (SciERC)---directionally consistent across tested model families, though with model-dependent magnitude.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:38:VC & Structural & \textbf{.379} & .684 & \textbf{.350} & .693 & .424 & .789 & .426 & .709 \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:57:On SciERC NER (complex schema, 6 types), structural signals lead: VC achieves $\rho{=}0.379$ and SJ $\rho{=}0.360$, both outperforming surface ($\rho{\leq}0.295$) and LP ($\rho{=}0.205$).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:58:This advantage persists on RE (VC $\rho{=}0.350$; preliminary, single benchmark), though all signals weaken due to the 40\% zero-F1 floor effect.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:59:VC and SJ show moderate instance-level correlation (NER: $\rho{=}0.659$; RE: $\rho{=}0.605$), indicating information overlap but not redundancy; their differential behavior across difficulty levels reflects the complementary granularity of entity-level frequency vs.\ span-level set overlap.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:60:While the best $\rho{=}0.38$ (VC) explains approximately 14\% of F1 variance, the best AUROC reaches 0.749 (EM), indicating strong binary discriminative power for the quality/failure classification most relevant to practitioners in quality-aware routing.\footnote{Semantic entropy \cite{kuhn2023semantic} achieves comparable AUROC on discrete-answer QA; direct comparison is not meaningful due to different output spaces.}
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:68:On CoNLL (greedy F1${\approx}$0.91), EM leads ($\rho{=}0.451$, AUROC${=}0.816$), surpassing SJ and VC.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:72:On WNUT-17, where 52\% of instances receive zero F1, full-set correlations are misleading: VC achieves $\rho{=}0.724$ (AUROC${=}0.913$), but this is entirely driven by the zero/non-zero boundary (conditional $\rho{=}0.038$, n.s.; Table~\ref{tab:wnut}).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:79:EM emerges as the strongest conditional signal on both NER ($\rho{=}0.360$) and RE ($\rho{=}0.417$; preliminary), while VC and FK drop substantially (VC NER: $0.379{\to}0.300$; FK NER: $0.267{\to}0.176$).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:81:This creates a natural complementarity: VC and SJ are preferred on the full set, while EM provides the most precise ranking within the non-trivial subset (see Appendix~\ref{app:additional} for details).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:108:VC                 & 0.634 & 0.359 \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:126:TOST equivalence testing confirms most signals are indistinguishable from greedy at ${\pm}2$--$3$~pp on NER; on RE, EM and VC fail equivalence even at ${\pm}5$~pp (Table~\ref{tab:tost}, Appendix~\ref{app:diversity}).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:127:VC ($\rho{=}0.379$, the best quality estimator) selects to only 0.634 on NER---\textit{below} greedy.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:140:On RE, only VC consistently outperforms LP ($\Delta\rho{=}{+}0.012$, preliminary).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex:4:For per-instance quality ranking, VC provides the strongest rank correlation ($\rho{=}0.38$), though EM leads binary discrimination (AUROC${=}0.749$); under conditional filtering, EM leads on both NER and RE ($\rho{=}0.360$, $0.417$; RE: preliminary, single benchmark).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex:5:Signal rankings depend on task difficulty---EM dominates easy tasks (CoNLL), VC and SJ dominate hard tasks (SciERC)---directionally consistent across two model families at 8B scale, though with model-dependent magnitude.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex:6:At higher sample sizes ($N{=}16$), SJ converges to comparable NER performance with VC ($\Delta{=}0.002$) with lower cross-seed variance ($\sigma{=}0.010$ vs.\ $0.026$); on RE, only VC consistently outperforms LP (preliminary).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex:41:Free-form decoding also slightly improves quality estimation (NER VC $\rho$: 0.379$\to$0.409), though this does not translate to selection gains.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex:46:Cross-dataset evaluation confirms that structural signals are robust to domain shift when the training schema subsumes the target (VC $\rho{=}0.469$ OOD vs.\ $0.386$ in-domain); the reverse direction fails due to catastrophic model failure, not signal failure (Appendix~\ref{app:ood}).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/method.tex:17:Four are \textit{consistency signals}---computed from inter-sample agreement---spanning two families: \textit{structural} (Soft Jaccard [SJ], entity voting confidence [VC]) and \textit{surface} (exact match [EM], Fleiss' $\kappa$ [FK]).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/method.tex:57:\paragraph{Entity voting confidence (structural, instance-level).}
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:21:VC ($c_{\mathrm{vc}}$) & Entity voting confidence \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:56:\quad VC &  & $0.458{\pm}0.003$ & --- \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:79:VC $N$-scaling is consistently positive ($+0.005$ on Qwen CoNLL, $+0.018$ on LLaMA SciERC, $+0.030$ on Qwen SciERC), while LP is approximately $N$-invariant ($\Delta{\leq}0.034$).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:80:SJ, EM, and VC scale consistently across all tested settings; only FK shows setting-dependent variation, suggesting that structural and binary-agreement signals are the most robust to $N$.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:81:At $N{=}16$, SJ converges to comparable NER performance with VC ($\Delta{=}0.002$) while exhibiting lower cross-seed variance ($\sigma{=}0.010$ vs.\ $0.026$), making it a more stable alternative at higher sample sizes.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:86:At $N{=}16$, the structural-over-LP advantage holds across all four tested NER settings: Qwen SciERC (VC $\rho{=}0.409$ vs.\ LP 0.239, $\Delta{=}{+}0.170$), Qwen CoNLL (EM $\rho{=}0.463$ vs.\ LP 0.328, $\Delta{=}{+}0.135$), LLaMA SciERC (VC $\rho{=}0.452$ vs.\ LP 0.277, $\Delta{=}{+}0.175$), and LLaMA CoNLL 3-seed (SJ $\rho{=}0.463{\pm}0.007$ vs.\ LP $0.310{\pm}0.005$, $\Delta{=}{+}0.153$).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:114:On the high-complexity RE subset ($n{=}81$, high relation count), signals improve substantially: VC reaches $\rho{=}0.630$, LP $\rho{=}0.554$, and SJ $\rho{=}0.502$---all far above the full-set levels.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:145:VC achieves $\rho{=}0.724$ (AUROC${=}0.913$) on the full set, but conditional analysis (non-zero F1 instances) reveals this is entirely driven by the zero/non-zero boundary: conditional $\rho{=}0.038$ ($p{=}0.49$).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:158:VC      & .724 & ${<}$1e-112 & .913 & .038 & .487 \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:179:Config & $n$ & Greedy & Oracle & SJ & FK & EM & LP & VC \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:201:The VC--SJ gap ($\Delta\rho{=}{+}0.019$) is not significant, indicating that these two structural signals perform comparably.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:213:VC & +0.379 & [+0.299, +0.456] \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:228:VC $-$ SJ & +0.019 & [$-$0.033, +0.073] & No \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:269:On the 44\% of Qwen SciERC instances with high diversity (${\geq}4$ unique outputs among 8 samples, $n{=}232$), oracle headroom reaches $+$16.3~pp, yet all consistency-based signals (SJ, FK, EM, VC) select at or below greedy, and LP---the only per-sample signal---achieves merely $+$0.8~pp.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:277:The breakpoint $\delta^*$---the minimum equivalence margin at which each signal passes TOST---ranges from approximately 1.3~pp (SJ, ${\sim}$10\% of oracle headroom) to 3.4~pp (FK, ${\sim}$26\%) on NER, and from approximately 2.9~pp (LP, ${\sim}$16\%) to 6.5~pp (VC, ${\sim}$36\%) on RE.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:279:On RE ($n{=}397$, preliminary), EM and VC fail equivalence even at $\delta{=}{\pm}5$~pp due to systematic underperformance ($\Delta{=}{-}3.2$~pp and $-4.5$~pp respectively).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:297:VC & $-$1.0 & \texttimes & \texttimes & \checkmark & $-$4.5 & \texttimes & \texttimes & \texttimes \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:305:On NER, the signal ranking VC${>}$SJ${>}$EM${>}$FK${>}$LP is identical across all six model-seed combinations, with $\sigma{\leq}0.025$ for all signals.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:306:On RE (Qwen only, preliminary), VC remains the top signal ($\rho{=}0.309{\pm}0.024$), but LP rises to \#2 ($\rho{=}0.297{\pm}0.022$), above FK, SJ, and EM---a reversal from the NER ranking that reflects RE's higher sensitivity to per-sample scoring.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:316:& LP & FK & SJ & VC & EM \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:417:On the non-zero subset, selection performance is \textit{worse} than on the full set (e.g., VC: $-10.0$~pp on non-zero vs.\ $-4.5$~pp on full set), because greedy is already strong on non-zero instances (F1${=}0.674$) and signals actively select inferior samples.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:434:VC & 0.359 & 0.574 \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:504:VC & 0.379 & 0.409 & $+$0.030 & 0.350 & 0.323 & $-$0.026 \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:576:VC & 0.3861 & 0.4092 & \textbf{+0.0231} & 0.3088 & 0.3738 & \textbf{+0.0650} \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:594:Qwen  & NER & 8  & 1.000 & VC $>$ SJ $>$ EM $>$ FK $>$ LP \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:595:Qwen  & NER & 16 & 0.956 & SJ $\approx$ VC $>$ EM $>$ FK $>$ LP \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:596:Qwen  & RE  & 8  & 0.822 & VC $>$ LP $>$ FK $>$ SJ $>$ EM \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:597:Qwen  & RE  & 16 & 0.956 & VC $>$ LP $>$ FK $>$ SJ $>$ EM \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:598:LLaMA & NER & 8  & 1.000 & VC $>$ SJ $>$ EM $>$ FK $>$ LP \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:616:VC & 0.0187 & 0.0260 & 0.0244 & 0.0158 \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:625:Signal rankings are highly stable across seeds: Kendall's $W{=}1.000$ for NER at $N{=}8$ (both models), dropping only to $W{=}0.956$ at $N{=}16$ where SJ and VC converge (Table~\ref{tab:ranking-stability}).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:643:VC & .469\textsuperscript{***} & .386 & +.083 & +.105\textsuperscript{*} & .386 & $-$.281 \\
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:653:When the SciERC-trained model (6 NER types) is applied to CoNLL (4 types), all signals remain significant ($p{<}0.001$) and structural signals improve over their in-domain levels (same model, seed${=}42$, $N{=}8$; in-domain $\rho$ from Table~\ref{tab:quality_estimation}): VC reaches $\rho{=}0.469$ (in-domain $0.386$, $\Delta{=}{+}0.083$), SJ $\rho{=}0.378$ (in-domain $0.364$, $\Delta{=}{+}0.014$), and FK $\rho{=}0.285$ (in-domain $0.254$, $\Delta{=}{+}0.031$).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:659:Under this regime, most signals flip to negative or near-zero correlations (Table~\ref{tab:ood}); only VC retains weak positive correlation ($\rho{=}0.105$, $p{=}0.016$).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex:35:We systematically compare five confidence signals from three families---structural (entity voting confidence [VC], Soft Jaccard [SJ]), surface (exact match [EM], Fleiss' $\kappa$ [FK]), and model-internal (log-probability [LP])---across NER and RE on SciERC \cite{luan2018scierc}, CoNLL-2003 \cite{tjongkimsang2003conll}, and WNUT-17 \cite{derczynski2017wnut}, using Qwen3-8B and LLaMA-3.1-8B.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2bea12f5-8a65-4262-8259-66c6204c3569",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "65a4caba-68aa-40a3-ba7f-2feb85f2f634",
  "sourceToolAssistantUUID": "2bea12f5-8a65-4262-8259-66c6204c3569",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 41 · 2026-05-15T12:44:44.346Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01K7SSCCAsfbdqBCKJK59uLR`</summary>

```json
{
  "pattern": "think|Qwen3|reasoning mode|enable_thinking",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "-i": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "65a4caba-68aa-40a3-ba7f-2feb85f2f634",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NkbcVviMRKx2Z191Fz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "1aa496a6-fb28-4d62-aded-ced16b858d5a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0141BccuMFY6NpCvzgpcqLBS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 22383,
      "cache_read_input_tokens": 45624,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 22383,
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

_source line 42 · 2026-05-15T12:44:44.368Z_

<details><summary>↩ Tool result · `toolu_01K7SSCCAsfbdqBCKJK59uLR`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/main.tex:40:All experiments use publicly available benchmarks (SciERC, CoNLL-2003, WNUT-17) and open-weight models (Qwen3-8B, LLaMA-3.1-8B).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:14:Both \textbf{Qwen3-8B} and \textbf{LLaMA-3.1-8B-Instruct} are fine-tuned with LoRA (rank$=$32, $\alpha{=}64$) for 5 epochs using LLaMA Factory \cite{zheng2024llamafactory} under identical training procedures, ensuring comparisons across the two model families (both at 8B scale) reflect model differences rather than training confounds.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:15:We note a training confound for SciERC: Qwen3-8B's SciERC checkpoint was trained with \texttt{enable\_thinking=True} (LLaMA Factory 0.9.4 default), which prepends empty \texttt{&lt;think>\textbackslash n&lt;/think>} blocks (4--5 tokens) to each training response and includes them in the loss computation; CoNLL-2003 and WNUT-17 checkpoints explicitly set \texttt{enable\_thinking=False}.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:16:No reasoning content is present (the blocks are always empty), and constrained decoding at inference time enforces JSON-only output, so thinking tokens do not appear in generated samples.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex:5:We evaluate two model families (Qwen3-8B and LLaMA-3.1-8B), both at 8B parameters.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex:16:Our free-form ablation (\S\ref{sec:ablation}) confirms that LP score compression persists without constrained decoding, but was conducted on a single dataset (SciERC) with one model (Qwen3-8B); whether the intrinsic compression finding generalizes to other datasets, model families, or model scales remains untested.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex:18:Qwen3-8B's SciERC checkpoint was trained with \texttt{enable\_thinking} active, injecting empty \texttt{&lt;think>&lt;/think>} blocks (4--5 tokens, no reasoning chain) before each response; CoNLL and WNUT checkpoints disabled this feature.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex:19:At inference time, constrained decoding suppresses thinking tokens in all configurations, so they do not appear in generated samples.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex:20:The empty blocks may weakly affect first-token probability distributions during training, potentially shifting LP score calibration on SciERC; however, since LP selection fails across all datasets including CoNLL and WNUT-17 (which lack this confound), the thinking token inconsistency is unlikely to explain the correlation-selection gap.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex:35:We systematically compare five confidence signals from three families---structural (entity voting confidence [VC], Soft Jaccard [SJ]), surface (exact match [EM], Fleiss' $\kappa$ [FK]), and model-internal (log-probability [LP])---across NER and RE on SciERC \cite{luan2018scierc}, CoNLL-2003 \cite{tjongkimsang2003conll}, and WNUT-17 \cite{derczynski2017wnut}, using Qwen3-8B and LLaMA-3.1-8B.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:339:\caption{Training configuration. Both Qwen3-8B and LLaMA-3.1-8B-Instruct use identical settings unless noted.}
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:381:[Omitted long matching line]
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:443:Table~\ref{tab:freeform_ablation} compares constrained and free-form decoding across four dimensions on SciERC ($N{=}8$, $T{=}1.0$, Qwen3-8B).
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:451:\caption{Comparison of constrained vs.\ free-form decoding on SciERC (Qwen3-8B, $N{=}8$, $T{=}1.0$, seed=42).}
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:527:We analyze RE LP selection failures across three random seeds (constrained decoding, $N{=}8$, $T{=}1.0$, Qwen3-8B) to assess whether failures are systematic or stochastic.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:561:Tables~\ref{tab:n-scaling}--\ref{tab:sigma-comparison} provide detailed $N$-scaling analysis on Qwen3-8B SciERC with 3-seed statistics.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:565:\caption{Effect of sample pool size on signal quality (Qwen3-8B, SciERC, 3-seed mean Spearman $\rho$).}
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:605:\caption{Cross-seed standard deviation ($\sigma$) of Spearman $\rho$ at $N\!=\!8$ vs.\ $N\!=\!16$ (Qwen3-8B, SciERC, 3 seeds). $\sigma$ is population standard deviation.}
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:635:\caption{Cross-dataset OOD quality estimation (Spearman $\rho$, Qwen3-8B, $N{=}8$, $T{=}1.0$). SciERC$\to$CoNLL: SciERC-trained model on CoNLL instances ($n{=}2756$). CoNLL$\to$SciERC: CoNLL-trained model on SciERC instances ($n{=}529$). In-domain $\rho$ from Table~\ref{tab:quality_estimation}. \textsuperscript{***}$p{<}0.001$, \textsuperscript{*}$p{<}0.05$.}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1aa496a6-fb28-4d62-aded-ced16b858d5a",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "75ddfded-a378-4743-9e27-94776c683fff",
  "sourceToolAssistantUUID": "1aa496a6-fb28-4d62-aded-ced16b858d5a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 43 · 2026-05-15T12:44:45.839Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01DVxpLimBSkwqoAEeEgZM2j`</summary>

```json
{
  "pattern": "semantic entropy|Kuhn",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper",
  "glob": "*.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "75ddfded-a378-4743-9e27-94776c683fff",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NkbcVviMRKx2Z191Fz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8fe783aa-3151-43a4-8661-0f04f96d829f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0141BccuMFY6NpCvzgpcqLBS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 22383,
      "cache_read_input_tokens": 45624,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 22383,
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

_source line 44 · 2026-05-15T12:44:45.863Z_

<details><summary>↩ Tool result · `toolu_01DVxpLimBSkwqoAEeEgZM2j`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8fe783aa-3151-43a4-8661-0f04f96d829f",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "06bcb67b-18b8-4b98-a9de-a90f7e1c1f94",
  "sourceToolAssistantUUID": "8fe783aa-3151-43a4-8661-0f04f96d829f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 45 · 2026-05-15T12:44:46.813Z_

<details open><summary>🔧 Tool call — Grep · `toolu_011JssciRuGe9PcQkuTXAWey`</summary>

```json
{
  "pattern": "N.*=.*16",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "06bcb67b-18b8-4b98-a9de-a90f7e1c1f94",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NkbcVviMRKx2Z191Fz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "9d5b21d5-e1c5-4933-a14b-ef495b0ebc25",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0141BccuMFY6NpCvzgpcqLBS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 22383,
      "cache_read_input_tokens": 45624,
      "output_tokens": 690,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 22383
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 690,
          "cache_read_input_tokens": 45624,
          "cache_creation_input_tokens": 22383,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 22383,
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

_source line 46 · 2026-05-15T12:44:46.830Z_

<details><summary>↩ Tool result · `toolu_011JssciRuGe9PcQkuTXAWey`</summary>

```text
19:We draw $N{=}8$ samples at $T{=}1.0$ (primary; single seed, seed${=}42$), with $N{=}16$ for scaling experiments.\footnote{$N{=}16$ results for CoNLL (Qwen) and SciERC (LLaMA) are in Table~\ref{tab:robustness} (Appendix~\ref{app:robustness}). A 3-seed stability analysis ($\sigma{\leq}0.026$; Table~\ref{tab:multiseed}, Appendix~\ref{app:multiseed}) confirms that signal rankings are identical across seeds.}
30:\caption{Quality estimation across tasks and models (Spearman $\rho$ and AUROC; $N{=}8$, seed${=}42$). Best value per column in \textbf{bold}. SciERC evaluates joint NER (6 types) and RE (7 types, single benchmark---preliminary); CoNLL evaluates NER (4 types). $N{=}16$ results appear in Table~\ref{tab:robustness} (Appendix~\ref{app:robustness}).}
68:On CoNLL (greedy F1${\approx}$0.91), EM leads ($\rho{=}0.451$, AUROC${=}0.816$), surpassing SJ and VC.
139:Consistency-based signals show robust performance across $T{\in}\{0.7, 1.0\}$ (SJ NER $\Delta\rho{=}0.028$, bootstrap CI includes zero) and sublinear gains from $N{=}8$ to $N{=}16$, with structural signals maintaining their advantage over LP across all NER settings ($\Delta\rho{=}{+}0.135$ to ${+}0.175$; Table~\ref{tab:robustness}, Appendix~\ref{app:robustness}).
141:NER signals are reasonably calibrated (ECE 0.069--0.096; Appendix~\ref{app:calibration}), while RE miscalibration (ECE 0.109--0.339) and compound errors impose a ceiling at $\rho{\approx}0.28$ for $N{=}16$.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9d5b21d5-e1c5-4933-a14b-ef495b0ebc25",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "30afe513-77b7-44d0-b7b3-be7446e49bf6",
  "sourceToolAssistantUUID": "9d5b21d5-e1c5-4933-a14b-ef495b0ebc25",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 47 · 2026-05-15T12:44:50.724Z_

Now let me check the Figure 1 caption and look for Table 1 with N=16 blanks more carefully. Let me also check the `discussion.tex` at root level and the `he2024uncertainty` bib entry.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "30afe513-77b7-44d0-b7b3-be7446e49bf6",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NmNawqHrSN53UBdKYS",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "ca3d1075-1782-4846-b431-b7d51f4a96a4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VKmY7SuPJh8FLsZVjuboAm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10027,
      "cache_read_input_tokens": 68007,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 10027,
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

_source line 48 · 2026-05-15T12:44:51.203Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Hk5x49XWkus3ovBkmA7W92`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ca3d1075-1782-4846-b431-b7d51f4a96a4",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NmNawqHrSN53UBdKYS",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "32316774-bb20-49f4-8cc6-b2e41c96444d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VKmY7SuPJh8FLsZVjuboAm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10027,
      "cache_read_input_tokens": 68007,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 10027,
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

_source line 49 · 2026-05-15T12:44:51.210Z_

<details><summary>↩ Tool result · `toolu_01Hk5x49XWkus3ovBkmA7W92`</summary>

```text
1	\section{Discussion}\label{sec:discussion}
2	
3	\paragraph{Practical recommendations.}
4	For per-instance quality ranking, VC provides the strongest rank correlation ($\rho{=}0.38$), though EM leads binary discrimination (AUROC${=}0.749$); under conditional filtering, EM leads on both NER and RE ($\rho{=}0.360$, $0.417$; RE: preliminary, single benchmark).
5	Signal rankings depend on task difficulty---EM dominates easy tasks (CoNLL), VC and SJ dominate hard tasks (SciERC)---directionally consistent across tested model families, though with model-dependent magnitude.
6	When model capability is insufficient (WNUT-17), all signals converge toward non-significant conditional correlations (Table~\ref{tab:wnut}).
7	
8	\paragraph{Why the gap exists: two layers.}
9	\textit{Layer 1 (definitional):} Four of five signals are instance-level aggregates that assign a single score per input; they cannot rank candidates by construction.
10	Consensus-proximity selection (\S\ref{sec:evaluation}) does not recover per-sample discrimination (Table~\ref{tab:selection}).
11	\textit{Layer 2 (constrained-decoding compression):} Log-probability, the only per-sample signal, also fails to exploit the 13--18~pp oracle headroom.
12	Under constrained decoding, LP scores are severely compressed: 60\% of instances have a within-sample range below 0.05, and 75\% of pairwise comparisons are effective ties ($|\Delta|{<}0.026$; Appendix~\ref{app:logprob_ties}).
13	In the 40\% of instances where compression is mitigated (LP range ${\geq}0.05$, $n{=}210$), LP \textit{significantly} outperforms greedy ($+2.9$~pp, $p{=}0.01$; within-instance $\rho$: 0.08$\to$0.39).
14	This diagnostic confirms that LP carries useful per-sample quality information; score compression under constrained decoding---the standard regime for schema-compliant IE---is the primary mechanistic bottleneck, though whether compression fully accounts for the gap remains open.
15	The LP compression mechanism is a direct consequence of constrained decoding's restricted token space; alternative decoding strategies may yield different LP distributions.
16	Diversity-stratified analysis confirms the gap persists even among high-diversity instances (Appendix~\ref{app:diversity}); RE miscalibration (ECE 0.109--0.339, preliminary; Appendix~\ref{app:calibration}) may compound this.
17	
18	\paragraph{Connection to MBR decoding.}
19	Our selection strategies instantiate minimum Bayes risk (MBR) decoding \cite{eikema2022sampling, muller2021understanding}: each selects $\hat{y} = \arg\max_{y_i} \sum_{j \neq i} U(y_i, y_j)$ with utility $U$ defined by SJ, EM, or entity overlap.
20	Despite MBR's success in machine translation \cite{freitag2022high} and its extension to summarization, code generation, and captioning \cite{jinnai2024mbr}, all variants fail here because the utility functions correlate with F1 at the instance level but not within a single instance---the mathematical essence of the correlation-selection gap.
21	\citet{eikema2025structured} study structure-conditional MBR decoding and find that standard utility functions degrade on structured outputs---consistent with our finding that consensus-proximity selection fails in IE despite its success in machine translation.
22	
23	\paragraph{Toward mechanistic confirmation.}
24	Our diagnosis predicts that LP score compression should diminish under free-form (unconstrained) generation, where the full token vocabulary is available at each step.
25	A controlled ablation---comparing LP selection under constrained versus free-form decoding on identical instances, with post-hoc JSON parsing for the free-form condition---would directly test whether the bottleneck is decoding-regime-specific.
26	\textit{[Planned experiment: free-form ablation on SciERC NER/RE.]}
27	All findings reported in this paper are specific to the constrained decoding regime; whether the gap persists under relaxed or free-form decoding remains an open question.
28	
29	\paragraph{Methodological implications.}
30	The decoupling of quality estimation ($\rho$), binary discrimination (AUROC), and sample selection (best-of-$N$ F1) means evaluating on a single metric risks selecting the wrong signal for the intended use case.
31	Effective selection likely requires either per-sample signals such as trained verifiers \cite{cobbe2021verifiers, venktesh2025trust} or relaxation of the constrained-decoding regime that compresses LP resolution; $N$-scaling analysis (Appendix~\ref{app:additional}) shows $N{=}8$ captures most quality estimation benefit.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "32316774-bb20-49f4-8cc6-b2e41c96444d",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "bc95b151-c563-461d-a5ff-4707dfb002e4",
  "sourceToolAssistantUUID": "32316774-bb20-49f4-8cc6-b2e41c96444d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 50 · 2026-05-15T12:44:52.211Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01G53yLVgbgbGLHPpyfKkpZV`</summary>

```json
{
  "pattern": "OpenAlex|openalex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/references.bib",
  "output_mode": "content",
  "-i": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bc95b151-c563-461d-a5ff-4707dfb002e4",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NmNawqHrSN53UBdKYS",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "493d5f61-1eaa-459b-8353-67f49aa9405f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VKmY7SuPJh8FLsZVjuboAm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10027,
      "cache_read_input_tokens": 68007,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 10027,
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

_source line 51 · 2026-05-15T12:44:52.249Z_

<details><summary>↩ Tool result · `toolu_01G53yLVgbgbGLHPpyfKkpZV`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "493d5f61-1eaa-459b-8353-67f49aa9405f",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "80c5a07d-1083-4647-b3e1-45848c41b91f",
  "sourceToolAssistantUUID": "493d5f61-1eaa-459b-8353-67f49aa9405f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 52 · 2026-05-15T12:44:53.446Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01WazQy7skG5n2uAMzXTrspb`</summary>

```json
{
  "pattern": "fig_overview|Figure.*1|\\\\label\\{fig:",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper",
  "glob": "*.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "80c5a07d-1083-4647-b3e1-45848c41b91f",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NmNawqHrSN53UBdKYS",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "12b4750e-4336-45b1-8674-395fad38c751",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VKmY7SuPJh8FLsZVjuboAm",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10027,
      "cache_read_input_tokens": 68007,
      "output_tokens": 407,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 10027
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 407,
          "cache_read_input_tokens": 68007,
          "cache_creation_input_tokens": 10027,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 10027,
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

_source line 53 · 2026-05-15T12:44:53.474Z_

<details><summary>↩ Tool result · `toolu_01WazQy7skG5n2uAMzXTrspb`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:51:\label{fig:signal_heatmap}
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex:91:\label{fig:selection_gap}
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:66:\label{fig:temperature_robustness}
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:94:\label{fig:reliability}
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:118:Figure~\ref{fig:length_logprob_scatter} shows that mean log-probability is weakly positively correlated with output length (NER: $\rho{=}0.386$, $n{=}4{,}232$; RE: $\rho{=}0.326$, $n{=}3{,}176$), ruling out length-penalty confounding as an explanation for LP's selection failure: longer outputs receive \textit{higher}, not lower, token-averaged log-probability under constrained decoding.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex:124:\label{fig:length_logprob_scatter}
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex:22:Our central finding is the \textbf{correlation-selection gap} (Figure~\ref{fig:overview}): consistency-based signals achieve strong quality estimation ($\rho$ up to 0.38, AUROC up to 0.75) but fail at sample selection despite 13--18~pp of oracle headroom.
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex:30:\includegraphics[width=\textwidth]{fig_overview}
/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex:32:\label{fig:overview}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "12b4750e-4336-45b1-8674-395fad38c751",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "12306642-f91f-410f-b55f-cc8d32d7fd42",
  "sourceToolAssistantUUID": "12b4750e-4336-45b1-8674-395fad38c751",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 54 · 2026-05-15T12:44:57.847Z_

I notice there are TWO `discussion.tex` files -- one at root and one in `sections/`. The root-level one appears to be an older version with a "planned experiment" placeholder. Let me now check the bib for OpenAlex-style issues more carefully, looking for common signs.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "12306642-f91f-410f-b55f-cc8d32d7fd42",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nms2UnJvHtZXkd6wRe",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "11aa8bed-4c54-4ed9-8411-071227820f0a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VbsiDjdR6SydtFZof8Zt4h",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2375,
      "cache_read_input_tokens": 78034,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2375,
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

_source line 55 · 2026-05-15T12:44:59.738Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01Vmvikn6zhGy9D7imdiiTQW`</summary>

```json
{
  "pattern": "doi\\.org/10\\.(1\\d{3}|26434|60599)|url.*openalex|url.*semantic\\.scholar.*paper/",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/references.bib",
  "output_mode": "content",
  "-i": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "11aa8bed-4c54-4ed9-8411-071227820f0a",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nms2UnJvHtZXkd6wRe",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "efb68024-c485-4225-aafb-726791e21399",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VbsiDjdR6SydtFZof8Zt4h",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2375,
      "cache_read_input_tokens": 78034,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2375,
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

_source line 56 · 2026-05-15T12:44:59.767Z_

<details><summary>↩ Tool result · `toolu_01Vmvikn6zhGy9D7imdiiTQW`</summary>

```text
57:  url = {http://dx.doi.org/10.18653/v1/2020.emnlp-main.21}
103:  url = {http://dx.doi.org/10.1037/h0031619}
136:  url = {http://dx.doi.org/10.18653/v1/2024.naacl-long.366}
268:  url = {http://dx.doi.org/10.18653/v1/D18-1360}
277:  url = {http://dx.doi.org/10.18653/v1/2023.emnlp-main.557}
286:  url = {http://dx.doi.org/10.1186/s44342-025-00063-2}
311:  url = {http://dx.doi.org/10.18653/v1/2021.eacl-main.145}
328:  url = {http://dx.doi.org/10.18653/v1/2025.findings-acl.1030}
337:  url = {http://dx.doi.org/10.18653/v1/2024.emnlp-main.706}
362:  url = {http://dx.doi.org/10.18653/v1/2023.acl-long.868}
411:  url = {http://dx.doi.org/10.1162/tacl_a_00754}
436:  url = {http://dx.doi.org/10.1609/aaai.v33i01.33017322}
445:  url = {http://dx.doi.org/10.18653/v1/2023.findings-acl.103}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "efb68024-c485-4225-aafb-726791e21399",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "68624126-1856-4f07-88d5-e91b9dc15af0",
  "sourceToolAssistantUUID": "efb68024-c485-4225-aafb-726791e21399",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 57 · 2026-05-15T12:45:00.767Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01LQHhqxdCbvLKkSpuh9VcL6`</summary>

```json
{
  "pattern": "journal\\s*=\\s*\\{arXiv",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/references.bib",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "68624126-1856-4f07-88d5-e91b9dc15af0",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nms2UnJvHtZXkd6wRe",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "1d26eaea-4c11-467b-a774-bbf19931a8c8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VbsiDjdR6SydtFZof8Zt4h",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2375,
      "cache_read_input_tokens": 78034,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2375,
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

_source line 58 · 2026-05-15T12:45:00.783Z_

<details><summary>↩ Tool result · `toolu_01LQHhqxdCbvLKkSpuh9VcL6`</summary>

```text
14:  journal = {arXiv preprint arXiv:2407.21787},
30:  journal = {arXiv preprint arXiv:2110.14168},
125:  journal = {arXiv preprint arXiv:2511.12309},
150:  journal = {arXiv preprint arXiv:2510.20460},
175:  journal = {arXiv preprint arXiv:2207.05221},
208:  journal = {arXiv preprint arXiv:2406.15927},
216:  journal = {arXiv preprint arXiv:2503.04104},
292:  journal = {arXiv preprint arXiv:2508.18395},
368:  journal = {arXiv preprint arXiv:2304.08085},
417:  journal = {arXiv preprint arXiv:2307.09702},
500:  journal = {arXiv preprint arXiv:2503.24235},
508:  journal = {arXiv preprint arXiv:2508.16665},
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1d26eaea-4c11-467b-a774-bbf19931a8c8",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "9617a3d9-eadc-4ded-b34b-0a6d5e85d504",
  "sourceToolAssistantUUID": "1d26eaea-4c11-467b-a774-bbf19931a8c8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 59 · 2026-05-15T12:45:01.918Z_

<details open><summary>🔧 Tool call — Grep · `toolu_011bFb3Cz9pcztprqazBz49V`</summary>

```json
{
  "pattern": "booktitle\\s*=\\s*\\{arXiv",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/references.bib",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9617a3d9-eadc-4ded-b34b-0a6d5e85d504",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4Nms2UnJvHtZXkd6wRe",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "d6c14797-262a-42e4-b5c2-b75ada44a071",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VbsiDjdR6SydtFZof8Zt4h",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2375,
      "cache_read_input_tokens": 78034,
      "output_tokens": 483,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2375
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 483,
          "cache_read_input_tokens": 78034,
          "cache_creation_input_tokens": 2375,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2375,
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

_source line 60 · 2026-05-15T12:45:01.930Z_

<details><summary>↩ Tool result · `toolu_011bFb3Cz9pcztprqazBz49V`</summary>

```text
22:  booktitle = {arXiv preprint (ICML 2024 Workshop ICL)},
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d6c14797-262a-42e4-b5c2-b75ada44a071",
  "isSidechain": true,
  "promptId": "61ee8a22-4e13-4d8d-8885-03d014a2646e",
  "agentId": "ae472d1c37ea69de3",
  "type": "user",
  "uuid": "888e8f74-f578-457e-a412-0a4cc7ffeb80",
  "sourceToolAssistantUUID": "d6c14797-262a-42e4-b5c2-b75ada44a071",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 61 · 2026-05-15T12:45:41.147Z_

Now I have all the information needed. Let me compile the findings.

Here is my item-by-item assessment:

---

**1. R3-W6 (first multi-family claim): PASS**

No "first" claim found anywhere in `introduction.tex` or either `abstract.tex`. The introduction says "We systematically compare five confidence signals from three families" and "Our work extends theirs [Nedellec et al.] in three directions." The framing is comparative/systematic, not priority-claiming. The abstracts likewise contain no "first" language. The claim has been appropriately softened.

**2. R3-W7 (VC/Voting Conf terminology): PASS**

The abbreviation "VC" is introduced formally in `introduction.tex` line 35 as "entity voting confidence [VC]" and consistently used as "VC" throughout all files thereafter. The notation table in `appendix.tex` defines "VC ($c_{\mathrm{vc}}$) = Entity voting confidence." The method section (`method.tex` line 57) introduces it as "Entity voting confidence (structural, instance-level)." The full phrase "voting confidence" does not appear without the "entity" prefix or the abbreviation, and "VC" is used consistently as the shorthand. Terminology is consistent.

**3. R5-W1 (Qwen3 thinking token): PASS**

The paper explicitly discusses `enable_thinking` in three locations:
- `experiments.tex` lines 15-18: Full disclosure that SciERC checkpoint used `enable_thinking=True`, blocks are empty, constrained decoding suppresses them at inference.
- `limitations.tex` lines 18-21: Detailed discussion of the confound, acknowledging empty blocks may weakly affect LP calibration but the gap is not explained by it since CoNLL/WNUT lack the confound.
- `appendix.tex` line 381 (training config footnote): Cross-reference to the confound.

The issue is thoroughly addressed.

**4. R5-W2 (semantic entropy footnote): PASS**

In `experiments.tex` line 60, there is a footnote: "Semantic entropy \cite{kuhn2023semantic} achieves comparable AUROC on discrete-answer QA; direct comparison is not meaningful due to different output spaces." Additionally, `related_work.tex` line 21 discusses semantic uncertainty with citation to `kuhn2023semantic` and its probe distillation (`kossen2024semantic`). The `references.bib` contains the correct Kuhn et al. 2023 entry (ICLR 2023). Properly addressed.

**5. R5-W3 (bib mismatch he2024uncertainty): PASS**

The `references.bib` entry for `he2024uncertainty` (lines 88-95) reads:
- Title: "Uncertainty Estimation on Sequential Labeling via Uncertainty Transmission"
- Authors: He, Jianfeng; Yu, Linlin; Lei, Shuo; Lu, Chang-Tien; Chen, Feng
- Venue: Findings of NAACL 2024, pages 2823-2835
- DOI: 10.18653/v1/2024.findings-naacl.180

This is a real paper with a valid ACL Anthology DOI. The entry looks correct and complete.

**6. R5-M4 (bib OpenAlex issues): PASS (with minor note)**

No OpenAlex URLs or identifiers found in the bib file. All URLs point to arXiv, ACL Anthology, or publisher DOIs. The entries have proper venue information. One minor note: `chen2024usc` has `booktitle = {arXiv preprint (ICML 2024 Workshop ICL)}` which mixes arXiv preprint format with a workshop mention -- slightly unconventional but not an OpenAlex artifact. Overall, the bibliography appears hand-curated or properly cleaned, with no auto-generated OpenAlex-style entries.

**7. R5-M5 (Ethics Statement): PASS**

`main.tex` lines 39-43 contain a substantive ethics statement covering:
- All benchmarks are publicly available (SciERC, CoNLL-2003, WNUT-17)
- Open-weight models used
- CoNLL-2003's Reuters/NIST provenance noted
- No new human data collected
- Positive framing of findings for reliable IE deployment

This is substantive, not boilerplate.

**8. R4-M3 (Table 1 N=16 blank): PASS**

Table 1 (`tab:quality_estimation` in `experiments.tex` lines 27-45) only shows N=8 results. N=16 data is not inline in this table -- it is explicitly delegated via footnote (line 19) and table caption (line 30) to Table `tab:robustness` in Appendix `app:robustness`. The main Table 1 has no blank cells; all 5 signals x 8 columns are filled. The appendix robustness table (`appendix.tex` lines 31-60) also has no blanks -- LLaMA CoNLL RE shows "---" which is intentional (RE not evaluated on CoNLL). No N=16 blank-cell issue exists.

**9. R6-W2 (Figure 1 caption): PASS**

Figure 1 (`fig:overview` in `introduction.tex` lines 28-33) has a concise two-sentence caption: "The correlation-selection gap. **Left**: high inter-sample agreement correlates with high F1 (quality estimation). **Right**: instance-level signals assign identical scores to all candidates, precluding sample selection." This is brief and informative, not overly verbose or redundant.

---

**IMPORTANT CAVEAT**: There are two `discussion.tex` files. The one in `sections/discussion.tex` (used by `main.tex` via `\input{sections/discussion}`) is the current version with the free-form ablation results integrated. However, the root-level `discussion.tex` is an older version that still contains `\textit{[Planned experiment: free-form ablation on SciERC NER/RE.]}` on line 26 and lacks the ablation results. Since `main.tex` inputs from `sections/`, the compiled paper uses the correct version, but the stale root-level file is a cleanup issue worth noting.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "888e8f74-f578-457e-a412-0a4cc7ffeb80",
  "isSidechain": true,
  "agentId": "ae472d1c37ea69de3",
  "requestId": "req_011Cb4NnV8sfQFrsnDjoztyW",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3ad4511a-f122-4218-96d7-8c4afe30c12d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/.claude/sessions/reviewer_0064dd56",
  "sessionId": "5bf25e32-5e58-4453-9774-87a69c302108",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011WHbCCcZcYwKnnPFQqF9E1",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1274,
      "cache_read_input_tokens": 80409,
      "output_tokens": 1522,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1274
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1522,
          "cache_read_input_tokens": 80409,
          "cache_creation_input_tokens": 1274,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1274,
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
