# writing restore content

**How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 66
- **Recorded user turns:** 0
- **Tool calls:** 21
- **Original source:** `logs/workers/worker_writing_restore_content_20260516T114015.log`
- **Structured JSON:** [`df6376f90fae1fd83b02.json`](../../sessions/df/df6376f90fae1fd83b02.json)

## Before a recorded user message

66 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est",
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
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
    "mcp__agent-ml-research__edit_paper_section",
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__write_paper_section"
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
  "uuid": "94879d32-762b-4fd2-a966-5074136463e0",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-2-projects-recursive-gen-depth-est/memory/"
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
    "resetsAt": 1778941800,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "a488052d-eabd-4aad-87c9-ebb629c5c98b",
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the current state of the appendix and relevant sections to understand what needs to be moved back.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "b835c172-a41e-4974-9707-3ace25752383",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qxp1tzuEKNeGcYg1NSzDvM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11942,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11942
      },
      "output_tokens": 24,
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

我先读取 appendix 和相关正文部分的当前状态。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "b56ff7fd-4a2c-4075-805c-bf545df42be3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qxp1tzuEKNeGcYg1NSzDvM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11942,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11942
      },
      "output_tokens": 24,
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01FVZvNDj4c97QyAKC8AZB4k`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__edit_paper_section,mcp__agent-ml-research__write_paper_section",
  "max_results": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "866e2231-9c06-4e42-bfd1-c6c08b9be033",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qxp1tzuEKNeGcYg1NSzDvM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11942,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11942
      },
      "output_tokens": 24,
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

_source line 7 · 2026-05-16T11:40:30.170Z_

<details><summary>↩ Tool result · `toolu_01FVZvNDj4c97QyAKC8AZB4k`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_project_file"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__edit_paper_section"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__write_paper_section"
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
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "bf6040b1-7c42-4fc8-8e53-9450eb714f61",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__edit_paper_section",
      "mcp__agent-ml-research__write_paper_section"
    ],
    "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__edit_paper_section,mcp__agent-ml-research__write_paper_section",
    "total_deferred_tools": 24
  }
}
```

</details>

---

### Assistant

_source line 8_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the appendix and the relevant sections to understand what needs to be moved.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "4d9790d2-08ff-4c69-95d0-e4a108b1acec",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JMRkHGn2r2rZWmNGi5RXPh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1311,
      "cache_read_input_tokens": 23783,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1311
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

_source line 9_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01WgtTQGinyjiSoyH4S4x3WX`</summary>

```json
{
  "project": "recursive_gen_depth_est",
  "file": "section_appendix.tex",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "0ea556d0-3040-411d-a7a9-aaa96eb61566",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JMRkHGn2r2rZWmNGi5RXPh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1311,
      "cache_read_input_tokens": 23783,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1311
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

_source line 10 · 2026-05-16T11:40:33.920Z_

<details><summary>↩ Tool result · `toolu_01WgtTQGinyjiSoyH4S4x3WX`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'section_appendix.tex'\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "a21d8734-5cb7-44b1-936e-742381441f02",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'section_appendix.tex'\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'section_appendix.tex'\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_014nkHS2MX41VSfFNibaAgzF`</summary>

```json
{
  "project": "recursive_gen_depth_est",
  "file": "atlas.tex",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "ed1fe5e5-2699-436e-b1e0-1d7eaea82382",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JMRkHGn2r2rZWmNGi5RXPh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1311,
      "cache_read_input_tokens": 23783,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1311
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

_source line 12 · 2026-05-16T11:40:34.861Z_

<details><summary>↩ Tool result · `toolu_014nkHS2MX41VSfFNibaAgzF`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'atlas.tex'\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "555ac286-ecb1-4bb7-b7f0-6c9ad03f4629",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'atlas.tex'\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'atlas.tex'\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 13_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_016n9ZaUFF29WfSzsruE6HMf`</summary>

```json
{
  "project": "recursive_gen_depth_est",
  "file": "generalization.tex",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "ea66ea8f-3b84-40e8-ba30-a23f8cf1f604",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JMRkHGn2r2rZWmNGi5RXPh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1311,
      "cache_read_input_tokens": 23783,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1311
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

_source line 14 · 2026-05-16T11:40:35.034Z_

<details><summary>↩ Tool result · `toolu_016n9ZaUFF29WfSzsruE6HMf`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'generalization.tex'\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "36cef0c9-f9f9-49d8-9e67-f7bc39fde6a9",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'generalization.tex'\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'generalization.tex'\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 15_

Let me find the paper tex files directly in the artifacts directory.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "9b138d8d-6515-4c6a-bb6f-eb06e0320340",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KWHVbh727KL43kxj3HEZ8a",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 896,
      "cache_read_input_tokens": 25094,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 896
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

_source line 16_

<details open><summary>🔧 Tool call — Glob · `toolu_01M3o59kRXXgiobvhdC58N4K`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "2838c888-82df-47e5-9f33-96cdd023826e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KWHVbh727KL43kxj3HEZ8a",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 896,
      "cache_read_input_tokens": 25094,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 896
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

_source line 17 · 2026-05-16T11:40:39.608Z_

<details><summary>↩ Tool result · `toolu_01M3o59kRXXgiobvhdC58N4K`</summary>

```text
artifacts/dream_reports/dream_20260514T140607/best/paper.tex
artifacts/dream_reports/dream_20260514T140607/median/paper.tex
artifacts/dream_reports/dream_20260514T140607/worst/paper.tex
docs/paper/main.tex
docs/paper/related_work.tex
docs/paper/method.tex
docs/paper/conclusion.tex
docs/paper/atlas.tex
docs/paper/section_appendix.tex
docs/paper/introduction.tex
docs/paper/generalization.tex
docs/paper/abstract.tex
docs/paper/discussion.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "53d9391c-48fc-4c55-8387-f43d6bbb6749",
  "tool_use_result": {
    "filenames": [
      "artifacts/dream_reports/dream_20260514T140607/best/paper.tex",
      "artifacts/dream_reports/dream_20260514T140607/median/paper.tex",
      "artifacts/dream_reports/dream_20260514T140607/worst/paper.tex",
      "docs/paper/main.tex",
      "docs/paper/related_work.tex",
      "docs/paper/method.tex",
      "docs/paper/conclusion.tex",
      "docs/paper/atlas.tex",
      "docs/paper/section_appendix.tex",
      "docs/paper/introduction.tex",
      "docs/paper/generalization.tex",
      "docs/paper/abstract.tex",
      "docs/paper/discussion.tex"
    ],
    "durationMs": 12,
    "numFiles": 13,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 18_

<details open><summary>🔧 Tool call — Read · `toolu_01JyfjeRqq172EuHwAL3sdFt`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "263d17b6-319b-4467-884b-6d4a40c81271",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Rc5oS2zQCCHjjHtazBRPvq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 273,
      "cache_read_input_tokens": 25990,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 273
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

_source line 19 · 2026-05-16T11:40:42.969Z_

<details><summary>↩ Tool result · `toolu_01JyfjeRqq172EuHwAL3sdFt`</summary>

```text
1	\section{Additional Results}
2	\label{app:additional}
3	
4	\subsection{Top-$k$ Feature Trajectories}
5	\label{app:topk_trajectories}
6	
7	Figure~\ref{fig:feature_trajectory} in the main text shows feature trajectories for nucleus ($p{=}0.95$) and temperature ($\tau{=}0.9$) sampling.
8	Top-$k$ ($k{=}50$) trajectories follow the same monotonically decreasing trend for all features but with compressed inter-depth spacing, consistent with the signal attenuation effect discussed in \S\ref{sec:atlas:strategy}.
9	Concretely, the d0$\to$d1 drop in \textsc{p90\_ppl} under top-$k$ is 78\% (vs.\ 87\% for nucleus), and the d2$\to$d3 reduction is 31\% (vs.\ 39\% for nucleus).
10	Despite the magnitude reduction, feature rank ordering across depths is preserved, which explains why ordinal classifiers maintain directionality even under top-$k$ conditions.
11	
12	\subsection{Permutation Importance}
13	\label{app:permutation}
14	
15	To verify that the Gini-based importance rankings in \S\ref{sec:atlas:features} are not an artifact of the impurity measure, we compute permutation importance (5-fold CV, 10 repeats) for all 9 atlas cells.
16	The top-2 features are stable across measures: \textsc{p90\_ppl} ranks in the top 2 in 9/9 cells under both Gini and permutation importance, and \textsc{var\_surprisal} in 8/9 (vs.\ 7/9 for Gini, with the additional cell being OLMo top-$k$; the single SHAP exception is GPT-2~XL top-$k$, where \textsc{p75\_ppl} displaces \textsc{var\_surprisal} to rank 3).
17	Kendall's $W{=}0.90$ across all three methods (Gini, permutation, SHAP) indicates strong concordance ($p{<}0.005$).
18	Pairwise Spearman correlations are: SHAP--Gini $\rho{=}0.93$, SHAP--permutation $\rho{=}0.84$, Gini--permutation $\rho{=}0.76$.
19	Per-cell top-5 overlap between SHAP and permutation importance is 3--4 out of 5 features; the aggregated (mean-across-cells) top-5 sets are identical, confirming that the top features are robust to the choice of importance measure at the aggregate level while per-cell rankings exhibit model-dependent variation.
20	
21	\subsection{Per-Class Recall}
22	\label{app:per_class}
23	
24	Table~\ref{tab:per_class_recall} reports per-class recall across all 9 atlas cells (4-class in-distribution, 5-fold CV).
25	Depth~0 recall exceeds 98\% uniformly.
26	Among generated depths, d2 is the hardest class in every cell; the deficit is most pronounced under top-$k$ sampling (46--53\%), where vocabulary truncation removes the tail tokens that carry depth-discriminative signal.
27	
28	\begin{table}[h]
29	\centering
30	\small
31	\caption{Per-class recall (\%) for all 9 atlas cells. d2 is the lowest-recall class in every cell. Boldface marks the highest d2 recall.}
32	\label{tab:per_class_recall}
33	\begin{tabular}{@{}lcccc@{}}
34	\toprule
35	Cell & d0 & d1 & d2 & d3 \\
36	\midrule
37	Pythia, nuc.       & 99.7 & 81.9 & 58.7 & 72.3 \\
38	Pythia, $\tau$     & 99.7 & 81.3 & 53.9 & 72.1 \\
39	Pythia, top-$k$    & 99.5 & 72.3 & 45.6 & 57.5 \\
40	OLMo, nuc.         & 98.8 & 80.5 & 61.5 & 74.3 \\
41	OLMo, $\tau$       & 99.7 & 87.7 & 66.1 & 77.2 \\
42	OLMo, top-$k$      & 99.5 & 78.5 & 51.2 & 65.6 \\
43	GPT-2~XL, nuc.     & 99.2 & 85.9 & \textbf{73.3} & 77.5 \\
44	GPT-2~XL, $\tau$   & 99.5 & 90.9 & 68.8 & 81.9 \\
45	GPT-2~XL, top-$k$  & 98.5 & 79.5 & 52.5 & 71.1 \\
46	\bottomrule
47	\end{tabular}
48	\end{table}
49	
50	\subsection{DCOL Iteration Details}
51	\label{app:dcol_iterations}
52	
53	Table~\ref{tab:dcol_iterations} summarizes all six DCOL iterations.
54	DeBERTa-v3-large exhibited systematic numerical instability across five configurations; RoBERTa-large resolved stability but could not close the accuracy gap with feature-based methods.
55	
56	\begin{table}[h]
57	\centering
58	\small
59	\caption{DCOL iteration summary. All experiments use Pythia-1.4B nucleus data. RF baseline: 78.2\%.}
60	\label{tab:dcol_iterations}
61	\begin{tabular}{@{}llp{2.2cm}p{2.8cm}@{}}
62	\toprule
63	Ver. & Backbone & Config & Outcome \\
64	\midrule
65	v1 & DeBERTa & FT, m\_lr $10^{-3}$ & Embed.\ collapse (31.5\%) \\
66	v2 & DeBERTa & FT, m\_lr $10^{-4}$ & OOM \\
67	v3 & DeBERTa & FT, m\_lr $10^{-4}$ & Forgetting + OOM \\
68	v4 & DeBERTa & LoRA, m\_lr $10^{-3}$ & Embed.\ collapse \\
69	v5 & DeBERTa & LoRA, m\_lr $10^{-4}$ & NaN gradients \\
70	v6 & RoBERTa & FT, grad clip 1.0 & Stable; 64.5\% ($-$13.7pp) \\
71	\bottomrule
72	\end{tabular}
73	\end{table}
74	
75	\subsection{Zero-Shot LLM Prompt Template}
76	\label{app:zeroshot_prompt}
77	
78	Both DeepSeek V3.2 and Qwen2.5-7B-Instruct use identical prompting.
79	The system message defines recursive generation depth with per-depth descriptions (depth~0: human-written; depth~1--3: successive LLM generation cycles) and lists expected textual patterns at each depth (vocabulary richness, repetition, coherence).
80	The user message presents the passage (truncated to ${\approx}$384 words) and requests a JSON response containing an integer depth prediction (0--3), a confidence score, and a one-sentence reasoning.
81	No in-context examples are provided.
82	
83	\begin{quote}
84	\small
85	\textbf{System:} ``You are an expert at detecting AI-generated text and estimating its generation depth. `Recursive generation depth' refers to how many times a text has been through an LLM generation cycle: Depth~0: Original human-written text [\ldots] Depth~3: Text generated by an LLM given depth-2 text as input. Key patterns by depth: Depth~0 (human): Rich vocabulary [\ldots] Depth~3 (third-gen): Noticeable repetition, formulaic structure [\ldots]''
86	
87	\textbf{User:} ``Analyze the following text and estimate its recursive generation depth (0, 1, 2, or 3). TEXT: \{text\}. Respond with ONLY a JSON object: \{\texttt{"depth"}: $\langle$int 0--3$\rangle$, \texttt{"confidence"}: $\langle$float 0--1$\rangle$, \texttt{"reasoning"}: $\langle$str$\rangle$\}''
88	\end{quote}
89	
90	\subsection{Temperature Robustness}
91	\label{app:multi_tau}
92	
93	The cross-strategy results in \S\ref{sec:gen:crossstrategy} use a single temperature ($\tau{=}0.9$).
94	To test whether depth signal generalizes across temperatures, we repeat the classification pipeline at $\tau \in \{0.5, 0.7, 0.9, 1.1\}$ on Pythia-1.4B.
95	
96	\paragraph{Within-$\tau$ robustness.}
97	For $\tau \in [0.5, 0.9]$, d1-vs-d2 AUC exceeds 0.80 (peak 0.851 at $\tau{=}0.7$, comparable to nucleus $p{=}0.95$'s 0.861) and 4-class accuracy ranges from 75.4\% to 77.3\% (Table~\ref{tab:multi_tau_within}), confirming the depth signal is not an artifact of a single temperature.
98	The same top-5 features (\texttt{var\_surprisal}, \texttt{p90\_ppl}, \texttt{mean\_ppl}, \texttt{mean\_surprisal}, \texttt{p75\_ppl}) dominate across all $\tau$ values with only minor rank-order variation.
99	
100	\paragraph{Collapse at $\tau{=}1.1$: memorization as prerequisite.}
101	At $\tau{=}1.1$, 4-class accuracy drops to 57.2\% and d1v2 AUC falls to 0.528.
102	Training loss reveals the mechanism: at low temperature ($\tau{=}0.5$), fine-tuning loss decreases steeply across recursive depths ($2.27 \to 0.42 \to 0.16$), indicating rapid memorization of the model's own output.
103	At $\tau{=}1.1$, loss remains nearly flat ($2.27 \to 1.91 \to 1.85$)---high-entropy output resists memorization, so depth-dependent distributional shifts do not accumulate.
104	This establishes \emph{memorization as a prerequisite} for detectable depth signal: recursive depth is discriminable only when successive fine-tuning iterations progressively reshape the output distribution.
105	
106	\paragraph{Cross-$\tau$ non-transferability.}
107	Leave-one-$\tau$-out transfer yields mean accuracy of 46.7\% with mean d1v2 AUC of 0.319 (Table~\ref{tab:multi_tau_cross})---worse than cross-strategy transfer (59.1\%; \S\ref{sec:gen:crossstrategy}).
108	Holdout $\tau{=}0.5$ produces inverted d1v2 AUC (0.176), confirming that different temperatures produce surprisal distributions with incompatible shapes.
109	This extends the strategy-specificity finding: even within a single decoding family, the feature space is temperature-specific, reinforcing the need for strategy-conditioned classifiers.
110	
111	\paragraph{Ecological validity.}
112	On WikiText-103 (546 editorial passages), all three model-specific RF classifiers achieve $\geq$98.5\% d0 accuracy despite $+$621\% domain shift in mean perplexity---partly an easy case, as WikiText's higher perplexity places it farther from d1--d3 in feature space.
113	On noisier web-crawl data (5{,}000 C4 passages), FPR ranges from 4.7\% (OLMo) to 22.4\% (GPT-2~XL), concentrated in template/SEO content with high n-gram repetition (Table~\ref{tab:calibration}); deployment on heterogeneous web data requires model-specific calibration.
114	
115	\begin{table}[h]
116	\centering
117	\small
118	\caption{Within-$\tau$ 4-class classification (Pythia-1.4B, 5-fold CV). d$i$v$j$: pairwise AUC for depth $i$ vs.\ depth $j$.}
119	\label{tab:multi_tau_within}
120	\begin{tabular}{@{}lcccc@{}}
121	\toprule
122	$\tau$ & 4-class acc (\%) & d1v2 AUC & d0v1 AUC & d2v3 AUC \\
123	\midrule
124	0.5 & 77.3 & 0.842 & 0.996 & 0.764 \\
125	0.7 & 75.4 & 0.851 & 0.997 & 0.720 \\
126	0.9 & 75.9 & 0.808 & 0.991 & 0.781 \\
127	1.1 & 57.2 & 0.528 & 0.988 & 0.599 \\
128	\bottomrule
129	\end{tabular}
130	\end{table}
131	
132	\begin{table}[h]
133	\centering
134	\small
135	\caption{Cross-$\tau$ leave-one-out transfer (Pythia-1.4B). Train on three temperatures, test on the held-out one.}
136	\label{tab:multi_tau_cross}
137	\begin{tabular}{@{}lcc@{}}
138	\toprule
139	Holdout & Acc (\%) & d1v2 AUC \\
140	\midrule
141	$\tau{=}0.5$ & 52.2 & 0.176 \\
142	$\tau{=}0.7$ & 41.0 & 0.299 \\
143	$\tau{=}0.9$ & 46.4 & 0.277 \\
144	$\tau{=}1.1$ & 47.1 & 0.525 \\
145	\midrule
146	Mean & 46.7 & 0.319 \\
147	\bottomrule
148	\end{tabular}
149	\end{table}
150	
151	\subsection{Feature Overlap Analysis}
152	\label{app:feature_overlap}
153	
154	We probe whether end-to-end PLM representations capture the same depth signals as our statistical features via linear probing of [CLS] representations from DeBERTa-v3-base and RoBERTa-base.
155	PLM representations excel at surface lexical features (TTR: $R^2{=}0.85$, repeated bigrams) but fail to capture perplexity distribution statistics---\textsc{var\_surprisal} and \textsc{p90\_ppl} yield negative $R^2$ under linear probing, indicating these features are not linearly accessible in the pretrained representation space.
156	This confirms that the 19pp accuracy gap between feature-based and end-to-end methods (\S\ref{app:e2e}) stems from complementary---not redundant---representations: PLMs capture lexical patterns while the targeted statistical features capture distributional tail properties that constitute the dominant depth markers.
157	
158	\subsection{End-to-End Learning}
159	\label{app:e2e}
160	
161	DeBERTa-v3-base \cite{he2021_deberta_v3} and RoBERTa-base \cite{liu2019_roberta} finetuned end-to-end achieve 58.3\% ($\pm$4.7\%) and 59.5\% ($\pm$3.2\%) respectively---lagging the RF baseline (78.2\%) by 19.9pp and 18.7pp.
162	The 1.2pp inter-backbone gap rules out architecture bias; Table~\ref{tab:e2e_detail} shows both backbones share the same failure mode---high d0 F1 ($>$0.94) but collapsed d1/d2 performance (F1 $\leq$ 0.42)---while RF achieves 0.596 d2 recall, a $>$2$\times$ advantage at the hardest depth class.
163	
164	\begin{table}[h]
165	\centering
166	\small
167	\caption{Per-class performance for end-to-end PLM classifiers vs.\ RF baseline (Pythia-1.4B nucleus). PLM columns report F1; RF d2 column reports recall (the class with the largest PLM--RF gap). Both PLM backbones share the same failure pattern: collapsed d1/d2 scores despite adequate d0/d3.}
168	\label{tab:e2e_detail}
169	\begin{tabular}{@{}lccccc@{}}
170	\toprule
171	Method & Acc (\%) & d0 & d1 & d2 & d3 \\
172	\midrule
173	DeBERTa-v3 & 58.3\,$\pm$\,4.7 & .947 & .378 & .247 & .656 \\
174	RoBERTa-base & 59.5\,$\pm$\,3.2 & .958 & .416 & .261 & .647 \\
175	\midrule
176	RF (19 feat.) & 78.2 & --- & --- & .596$^\dagger$ & --- \\
177	\bottomrule
178	\multicolumn{6}{@{}l}{\footnotesize $^\dagger$Recall; shown for the depth class with the largest PLM--RF gap.}
179	\end{tabular}
180	\end{table}
181	
182	\paragraph{Feature space divergence.}
183	SHAP TreeExplainer analysis confirms that perplexity and surprisal features account for 88.8\% of RF's total contribution.
184	Three independent importance measures---SHAP, Gini, and permutation---show strong concordance (Kendall's $W{=}0.90$, $p{<}0.005$; pairwise Spearman $\rho$: SHAP--Gini $0.93$, SHAP--permutation $0.84$; \S\ref{app:permutation}), with \texttt{p90\_ppl} appearing in the SHAP top-2 in 9/9 cells and \texttt{var\_surprisal} in 8/9.
185	Linear probing of PLM [CLS] representations yields negative $R^2$ for both \texttt{var\_surprisal} and \texttt{p90\_ppl} (\S\ref{app:feature_overlap}), indicating that pretrained representations lack the linear structure needed to recover perplexity tail statistics---a systematic representational gap rather than a backbone-specific artifact.
186	
187	DCOL \cite{cloc2025} reached 64.5\% (\S\ref{app:dcol_iterations}); all end-to-end approaches (58--65\%) underperform feature-based methods, suggesting depth estimation benefits from targeted statistical features that capture distributional tail properties absent from PLM representations.
188	This comparison is bounded by backbone scale ($\leq$125M parameters); whether larger PLMs (e.g., 7B+) can close the gap via richer internal representations remains an open question.
189	
190	\subsection{Domain Bias Analysis}
191	\label{app:domain_bias}
192	
193	To assess whether the classifier exploits depth-related features or memorizes stylistic cues from individual seed articles, we conduct three sub-experiments.
194	
195	\paragraph{Methodological note.}
196	An initial implementation assigned sample IDs with a global counter across depths, inadvertently correlating seed-group identity with depth (LOGO accuracy 64.0\%, seed-group prediction 20.8\%).
197	We discovered the issue during internal review, corrected to per-depth seed assignment ensuring each group contains equal samples per depth, and re-ran all sub-experiments.
198	The results below use the corrected pipeline; the initial (buggy) numbers are reported for transparency.
199	
200	\paragraph{Sub-A: Standard CV.}
201	Five-fold CV accuracy on 3-class (d1/d2/d3) classification ranges from 59\% to 82\% across the 9 atlas cells (up to 2.5$\times$ above the 33.3\% chance level), confirming that depth signal is the dominant classification factor.
202	
203	\paragraph{Sub-B: LOGO evaluation.}
204	We assign each passage to one of 10 seed-article groups (balanced: each group contains equal samples per depth) and perform leave-one-group-out CV.
205	LOGO mean accuracy is 72.1\% (range 59.5--81.6\%), matching standard CV (72.0\%) within noise (before fix: 64.0\%, reflecting the depth--group confound).
206	Per-cell fold standard deviations range from 0.4pp to 1.4pp, indicating that cross-group generalization is as reliable as within-group classification.
207	
208	\paragraph{Sub-C: Negative control.}
209	We train two classifiers on identical features: one predicting depth, the other predicting seed-group identity (10-class, chance = 10\%).
210	Depth prediction accuracy averages 72.0\%; seed-group prediction averages 10.2\%---indistinguishable from chance (before fix: 20.8\%, inflated by the depth--group confound).
211	The depth-to-seed-group accuracy ratio is 7.1$\times$, confirming that the feature representation encodes depth but not seed-article identity.
212	
213	Taken together, these results show that seed-article grouping has no measurable effect on depth estimation after correcting the group assignment: LOGO accuracy equals standard CV, and seed-group prediction is at chance.
214	
215	\subsection{Wild-Data Calibration}
216	\label{app:calibration}
217	
218	Table~\ref{tab:calibration} reports d0 accuracy and false positive rate (FPR) for all three model-specific nucleus RF classifiers on two out-of-distribution human-text corpora: WikiText-103 (546 editorial passages) and C4 (5{,}000 web-crawl passages).
219	
220	\begin{table}[h]
221	\centering
222	\small
223	\caption{Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+.}
224	\label{tab:calibration}
225	\begin{tabular}{@{}llrcc@{}}
226	\toprule
227	Model & Source & $n$ & d0 (\%) & FPR (\%) \\
228	\midrule
229	Pythia-1.4B & WikiText & 546 & 100.0 & 0.0 \\
230	 & C4 & 5{,}000 & 79.8 & 20.2 \\
231	\addlinespace
232	GPT-2~XL & WikiText & 546 & 99.3 & 0.7 \\
233	 & C4 & 5{,}000 & 77.6 & 22.4 \\
234	\addlinespace
235	OLMo-1B & WikiText & 546 & 98.5 & 1.5 \\
236	 & C4 & 5{,}000 & 95.3 & 4.7 \\
237	\bottomrule
238	\end{tabular}
239	\end{table}
240	
241	On WikiText-103, all three classifiers achieve $\geq$98.5\% d0 accuracy, confirming that editorial text is reliably distinguished from recursive generations across model families.
242	On C4, FPR varies sharply: OLMo (4.7\%) vs.\ Pythia (20.2\%) and GPT-2~XL (22.4\%).
243	C4 misclassifications concentrate in template and SEO content with elevated repetition features (\texttt{rep\_3gram} $+$37\%, \texttt{rep\_4gram} $+$75\% vs.\ correctly classified d0 passages), rather than in random noise.
244	The model gap likely reflects training data composition: OLMo (trained on Dolma, which includes diverse web data) produces d0 features more tolerant of web-crawl variation, while Pythia and GPT-2~XL (trained primarily on Wikipedia/WebText) map template-heavy content into the d1+ region.
245	Among C4 false positives for GPT-2~XL, predictions distribute as d1 (9.0\%), d2 (3.7\%), d3 (9.6\%); for OLMo, d1 (2.9\%), d2 (0.5\%), d3 (1.3\%)---the non-uniform depth distribution suggests the classifier maps specific repetition patterns to particular depth signatures rather than producing random misclassifications.
246	
247	\subsection{Downstream Curation PoC}
248	\label{app:curation_poc}
249	
250	To validate that depth estimation translates to actionable data curation, we conduct a proof-of-concept downstream evaluation.
251	We fine-tune Pythia-410M with LoRA ($r{=}16$, $\alpha{=}32$) for 3 epochs on 8 data conditions derived from the Pythia nucleus depth-estimation corpus, repeating each condition over 5 random seeds.
252	Conditions vary the selection mechanism (RF-predicted depth, oracle depth, random subsampling) and stringency (strict $\approx$25\%, moderate $\approx$50\%, soft threshold).
253	Table~\ref{tab:curation_poc} reports per-condition perplexity; Table~\ref{tab:curation_comparisons} reports pairwise contrasts.
254	
255	\begin{table}[h]
256	\centering
257	\small
258	\caption{Curation PoC: per-condition perplexity (Pythia-410M LoRA, 5 seeds). $\Delta$ is signed so that positive values indicate lower (better) perplexity than unfiltered. $^*$\,: $p<0.05$ (paired $t$-test vs.\ unfiltered).}
259	\label{tab:curation_poc}
260	\resizebox{\columnwidth}{!}{%
261	\begin{tabular}{@{}lcccccc@{}}
262	\toprule
263	Condition & Mean PPL & Std & $n$ & $\Delta$ vs Unfilt. & $p$ & $d_z$ \\
264	\midrule
265	unfiltered        & 15.776 & 0.066 & 10{,}000 & ---      & ---   & ---      \\
266	rf\_soft          & 15.733 & 0.038 &  4{,}422 & +0.043   & 0.407 &  0.41    \\
267	rf\_moderate      & 15.756 & 0.056 &  4{,}940 & +0.021   & 0.492 &  0.34    \\
268	rf\_strict        & 15.810 & 0.061 &  2{,}496 & $-$0.034 & 0.607 & $-$0.25  \\
269	oracle\_moderate  & 15.809 & 0.103 &  5{,}000 & $-$0.033 & 0.485 & $-$0.34  \\
270	oracle\_strict    & 15.879 & 0.128 &  2{,}500 & $-$0.103 & 0.216 & $-$0.66  \\
271	random\_soft      & 16.062 & 0.079 &  4{,}422 & $-$0.286 & ${<}$0.001$^*$ & $-$2.77  \\
272	random\_moderate  & 15.998 & 0.090 &  4{,}940 & $-$0.222 & 0.028$^*$ & $-$1.50  \\
273	random\_strict    & 16.239 & 0.165 &  2{,}496 & $-$0.463 & 0.013$^*$ & $-$1.89  \\
274	\bottomrule
275	\end{tabular}}
276	\end{table}
277	
278	\begin{table}[h]
279	\centering
280	\small
281	\caption{Pairwise comparisons (paired $t$-test, 5 seeds). $^*$\,: $p<0.05$; $^{**}$\,: $p<0.01$.}
282	\label{tab:curation_comparisons}
283	\begin{tabular}{@{}lccc@{}}
284	\toprule
285	Comparison & $\Delta$ PPL & $t$ & $p$ \\
286	\midrule
287	rf\_strict vs random\_strict     & 0.429 & $-$7.05 & 0.002$^{**}$ \\
288	rf\_moderate vs random\_moderate & 0.242 & $-$3.77 & 0.020$^*$    \\
289	rf\_soft vs random\_soft         & 0.328 & $-$17.98 & ${<}$0.001$^{**}$ \\
290	rf\_soft vs unfiltered           & 0.043 &    0.93 & 0.407        \\
291	\bottomrule
292	\end{tabular}
293	\end{table}
294	
295	\subsection{Reference Model Ablation}
296	\label{app:ref_ablation}
297	
298	\begin{table}[h]
299	\centering
300	\caption{Reference model ablation. Classification accuracy (5-fold CV) on Pythia-1.4B generated text (nucleus, d0--d3) using different reference models for feature extraction.}
301	\label{tab:ref_ablation}
302	\begin{tabular}{lcc}
303	\toprule
304	Reference Model & Architecture & Accuracy (\%) \\
305	\midrule
306	Pythia-1.4B (self) & GPT-NeoX & 78.6 $\pm$ 0.6 \\
307	OLMo-1B (cross) & OLMo & 74.5 $\pm$ 0.7 \\
308	\bottomrule
309	\end{tabular}
310	\end{table}
311	
312	\subsection{Cross-Boundary Generalization}
313	\label{app:cross_boundary}
314	
315	The preceding experiments assume a single model family generates all recursive depths.
316	In practice, recursive contamination may traverse model boundaries: text generated by model~A is used to train model~B, whose output trains model~C.
317	We probe whether the depth signal persists under two relaxations of the single-model assumption.
318	
319	\paragraph{Cross-model recursive chains.}
320	We construct a heterogeneous chain: human text (d0) $\to$ Pythia-1.4B generates d1 $\to$ OLMo-1B finetuned on Pythia-d1 generates d2 $\to$ GPT-2~XL finetuned on OLMo-d2 generates d3.
321	Each recursive step uses a \emph{different} model family, eliminating the possibility that depth signal arises from a single model's idiosyncratic behavior.
322	A 4-class Random Forest achieves 84.75\% accuracy (95\% CI $[81.0, 88.25]$), with per-depth F1 scores of 0.98 (d0), 0.88 (d1), 0.76 (d2), and 0.76 (d3).
323	Pairwise AUC remains high: d0-vs-d1 = 0.999 and d2-vs-d3 = 0.841.
324	These results suggest that distributional artifacts of recursive generation persist across model boundaries---providing preliminary evidence that the depth signal is a property of the recursive process itself rather than of any individual generator.
325	
326	\paragraph{Cross-domain transfer.}
327	All prior experiments use WikiText-103 as the seed corpus.
328	To test domain dependence, we repeat the pipeline with arXiv abstracts as the seed text (Pythia-1.4B, nucleus $p{=}0.95$, 500 samples per depth, d0--d3).
329	Five-fold cross-validation yields 74.1\% $\pm$ 2.0\% accuracy, compared to ${\sim}$78\% on the WikiText seed.
330	Per-depth F1 shows the familiar pattern: d0 = 1.00, d1 = 0.78, d2 = 0.52, d3 = 0.66---with d2 remaining the most challenging class.
331	The 4pp accuracy gap relative to WikiText likely reflects the narrower stylistic range of scientific abstracts, which may reduce the distributional contrast between adjacent depths.
332	These results suggest that the depth signal is domain-independent, providing preliminary evidence that the perplexity-based features capture properties of the recursive generation process rather than domain-specific artifacts of the seed corpus.
333	
334	\subsection{Extended Discussion}
335	\label{app:extended_discussion}
336	
337	\paragraph{Depth-graduated curation.}
338	Current data curation operates on a binary human-vs-machine distinction \cite{dsir2023,qurating2024}.
339	Recursive generation depth estimation enables a finer-grained alternative: retain low-depth generations (d1) whose distributional properties remain close to the human source, while down-weighting or filtering high-depth text (d3+) where tail erosion has degraded quality.
340	The 70--85\% in-distribution accuracy and $\mathrm{EDD}_{0.75}{=}4$ suggest depth-graduated filtering is feasible within known model--strategy configurations, though the d1/d2 boundary inversion under cross-strategy transfer (\S\ref{sec:gen:crossstrategy}) means reliable curation requires either known decoding strategy metadata or an upstream strategy-identification step; a small-scale PoC (Appendix~\ref{app:curation_poc}) shows RF-filtered subsets match unfiltered quality with 44\% of the data; large-scale validation remains open.
341	Importance weighting \cite{sugiyama2007_importance_weighting} could further enable continuous depth-aware data selection rather than discrete thresholding.
342	
343	\paragraph{Toward a provenance toolkit.}
344	Depth estimation complements existing provenance methods along orthogonal axes.
345	Watermarking \cite{kirchenbauer2023_watermark} provides high-confidence attribution when the generator cooperates but is inapplicable to unwatermarked text.
346	Source attribution \cite{uchendu2020_attribution} identifies the generating model but not the generation history.
347	Depth estimation characterizes \emph{iterative reuse} regardless of generator cooperation or identity.
348	A layered provenance system combining these three signals---watermark presence, source model, and recursive generation depth---could support more nuanced data auditing than any single method.
349	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "9cb163fe-178f-413b-bd8a-612e4de872bc",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/section_appendix.tex",
      "content": "\\section{Additional Results}\n\\label{app:additional}\n\n\\subsection{Top-$k$ Feature Trajectories}\n\\label{app:topk_trajectories}\n\nFigure~\\ref{fig:feature_trajectory} in the main text shows feature trajectories for nucleus ($p{=}0.95$) and temperature ($\\tau{=}0.9$) sampling.\nTop-$k$ ($k{=}50$) trajectories follow the same monotonically decreasing trend for all features but with compressed inter-depth spacing, consistent with the signal attenuation effect discussed in \\S\\ref{sec:atlas:strategy}.\nConcretely, the d0$\\to$d1 drop in \\textsc{p90\\_ppl} under top-$k$ is 78\\% (vs.\\ 87\\% for nucleus), and the d2$\\to$d3 reduction is 31\\% (vs.\\ 39\\% for nucleus).\nDespite the magnitude reduction, feature rank ordering across depths is preserved, which explains why ordinal classifiers maintain directionality even under top-$k$ conditions.\n\n\\subsection{Permutation Importance}\n\\label{app:permutation}\n\nTo verify that the Gini-based importance rankings in \\S\\ref{sec:atlas:features} are not an artifact of the impurity measure, we compute permutation importance (5-fold CV, 10 repeats) for all 9 atlas cells.\nThe top-2 features are stable across measures: \\textsc{p90\\_ppl} ranks in the top 2 in 9/9 cells under both Gini and permutation importance, and \\textsc{var\\_surprisal} in 8/9 (vs.\\ 7/9 for Gini, with the additional cell being OLMo top-$k$; the single SHAP exception is GPT-2~XL top-$k$, where \\textsc{p75\\_ppl} displaces \\textsc{var\\_surprisal} to rank 3).\nKendall's $W{=}0.90$ across all three methods (Gini, permutation, SHAP) indicates strong concordance ($p{<}0.005$).\nPairwise Spearman correlations are: SHAP--Gini $\\rho{=}0.93$, SHAP--permutation $\\rho{=}0.84$, Gini--permutation $\\rho{=}0.76$.\nPer-cell top-5 overlap between SHAP and permutation importance is 3--4 out of 5 features; the aggregated (mean-across-cells) top-5 sets are identical, confirming that the top features are robust to the choice of importance measure at the aggregate level while per-cell rankings exhibit model-dependent variation.\n\n\\subsection{Per-Class Recall}\n\\label{app:per_class}\n\nTable~\\ref{tab:per_class_recall} reports per-class recall across all 9 atlas cells (4-class in-distribution, 5-fold CV).\nDepth~0 recall exceeds 98\\% uniformly.\nAmong generated depths, d2 is the hardest class in every cell; the deficit is most pronounced under top-$k$ sampling (46--53\\%), where vocabulary truncation removes the tail tokens that carry depth-discriminative signal.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-class recall (\\%) for all 9 atlas cells. d2 is the lowest-recall class in every cell. Boldface marks the highest d2 recall.}\n\\label{tab:per_class_recall}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nCell & d0 & d1 & d2 & d3 \\\\\n\\midrule\nPythia, nuc.       & 99.7 & 81.9 & 58.7 & 72.3 \\\\\nPythia, $\\tau$     & 99.7 & 81.3 & 53.9 & 72.1 \\\\\nPythia, top-$k$    & 99.5 & 72.3 & 45.6 & 57.5 \\\\\nOLMo, nuc.         & 98.8 & 80.5 & 61.5 & 74.3 \\\\\nOLMo, $\\tau$       & 99.7 & 87.7 & 66.1 & 77.2 \\\\\nOLMo, top-$k$      & 99.5 & 78.5 & 51.2 & 65.6 \\\\\nGPT-2~XL, nuc.     & 99.2 & 85.9 & \\textbf{73.3} & 77.5 \\\\\nGPT-2~XL, $\\tau$   & 99.5 & 90.9 & 68.8 & 81.9 \\\\\nGPT-2~XL, top-$k$  & 98.5 & 79.5 & 52.5 & 71.1 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{DCOL Iteration Details}\n\\label{app:dcol_iterations}\n\nTable~\\ref{tab:dcol_iterations} summarizes all six DCOL iterations.\nDeBERTa-v3-large exhibited systematic numerical instability across five configurations; RoBERTa-large resolved stability but could not close the accuracy gap with feature-based methods.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{DCOL iteration summary. All experiments use Pythia-1.4B nucleus data. RF baseline: 78.2\\%.}\n\\label{tab:dcol_iterations}\n\\begin{tabular}{@{}llp{2.2cm}p{2.8cm}@{}}\n\\toprule\nVer. & Backbone & Config & Outcome \\\\\n\\midrule\nv1 & DeBERTa & FT, m\\_lr $10^{-3}$ & Embed.\\ collapse (31.5\\%) \\\\\nv2 & DeBERTa & FT, m\\_lr $10^{-4}$ & OOM \\\\\nv3 & DeBERTa & FT, m\\_lr $10^{-4}$ & Forgetting + OOM \\\\\nv4 & DeBERTa & LoRA, m\\_lr $10^{-3}$ & Embed.\\ collapse \\\\\nv5 & DeBERTa & LoRA, m\\_lr $10^{-4}$ & NaN gradients \\\\\nv6 & RoBERTa & FT, grad clip 1.0 & Stable; 64.5\\% ($-$13.7pp) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Zero-Shot LLM Prompt Template}\n\\label{app:zeroshot_prompt}\n\nBoth DeepSeek V3.2 and Qwen2.5-7B-Instruct use identical prompting.\nThe system message defines recursive generation depth with per-depth descriptions (depth~0: human-written; depth~1--3: successive LLM generation cycles) and lists expected textual patterns at each depth (vocabulary richness, repetition, coherence).\nThe user message presents the passage (truncated to ${\\approx}$384 words) and requests a JSON response containing an integer depth prediction (0--3), a confidence score, and a one-sentence reasoning.\nNo in-context examples are provided.\n\n\\begin{quote}\n\\small\n\\textbf{System:} ``You are an expert at detecting AI-generated text and estimating its generation depth. `Recursive generation depth' refers to how many times a text has been through an LLM generation cycle: Depth~0: Original human-written text [\\ldots] Depth~3: Text generated by an LLM given depth-2 text as input. Key patterns by depth: Depth~0 (human): Rich vocabulary [\\ldots] Depth~3 (third-gen): Noticeable repetition, formulaic structure [\\ldots]''\n\n\\textbf{User:} ``Analyze the following text and estimate its recursive generation depth (0, 1, 2, or 3). TEXT: \\{text\\}. Respond with ONLY a JSON object: \\{\\texttt{\"depth\"}: $\\langle$int 0--3$\\rangle$, \\texttt{\"confidence\"}: $\\langle$float 0--1$\\rangle$, \\texttt{\"reasoning\"}: $\\langle$str$\\rangle$\\}''\n\\end{quote}\n\n\\subsection{Temperature Robustness}\n\\label{app:multi_tau}\n\nThe cross-strategy results in \\S\\ref{sec:gen:crossstrategy} use a single temperature ($\\tau{=}0.9$).\nTo test whether depth signal generalizes across temperatures, we repeat the classification pipeline at $\\tau \\in \\{0.5, 0.7, 0.9, 1.1\\}$ on Pythia-1.4B.\n\n\\paragraph{Within-$\\tau$ robustness.}\nFor $\\tau \\in [0.5, 0.9]$, d1-vs-d2 AUC exceeds 0.80 (peak 0.851 at $\\tau{=}0.7$, comparable to nucleus $p{=}0.95$'s 0.861) and 4-class accuracy ranges from 75.4\\% to 77.3\\% (Table~\\ref{tab:multi_tau_within}), confirming the depth signal is not an artifact of a single temperature.\nThe same top-5 features (\\texttt{var\\_surprisal}, \\texttt{p90\\_ppl}, \\texttt{mean\\_ppl}, \\texttt{mean\\_surprisal}, \\texttt{p75\\_ppl}) dominate across all $\\tau$ values with only minor rank-order variation.\n\n\\paragraph{Collapse at $\\tau{=}1.1$: memorization as prerequisite.}\nAt $\\tau{=}1.1$, 4-class accuracy drops to 57.2\\% and d1v2 AUC falls to 0.528.\nTraining loss reveals the mechanism: at low temperature ($\\tau{=}0.5$), fine-tuning loss decreases steeply across recursive depths ($2.27 \\to 0.42 \\to 0.16$), indicating rapid memorization of the model's own output.\nAt $\\tau{=}1.1$, loss remains nearly flat ($2.27 \\to 1.91 \\to 1.85$)---high-entropy output resists memorization, so depth-dependent distributional shifts do not accumulate.\nThis establishes \\emph{memorization as a prerequisite} for detectable depth signal: recursive depth is discriminable only when successive fine-tuning iterations progressively reshape the output distribution.\n\n\\paragraph{Cross-$\\tau$ non-transferability.}\nLeave-one-$\\tau$-out transfer yields mean accuracy of 46.7\\% with mean d1v2 AUC of 0.319 (Table~\\ref{tab:multi_tau_cross})---worse than cross-strategy transfer (59.1\\%; \\S\\ref{sec:gen:crossstrategy}).\nHoldout $\\tau{=}0.5$ produces inverted d1v2 AUC (0.176), confirming that different temperatures produce surprisal distributions with incompatible shapes.\nThis extends the strategy-specificity finding: even within a single decoding family, the feature space is temperature-specific, reinforcing the need for strategy-conditioned classifiers.\n\n\\paragraph{Ecological validity.}\nOn WikiText-103 (546 editorial passages), all three model-specific RF classifiers achieve $\\geq$98.5\\% d0 accuracy despite $+$621\\% domain shift in mean perplexity---partly an easy case, as WikiText's higher perplexity places it farther from d1--d3 in feature space.\nOn noisier web-crawl data (5{,}000 C4 passages), FPR ranges from 4.7\\% (OLMo) to 22.4\\% (GPT-2~XL), concentrated in template/SEO content with high n-gram repetition (Table~\\ref{tab:calibration}); deployment on heterogeneous web data requires model-specific calibration.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Within-$\\tau$ 4-class classification (Pythia-1.4B, 5-fold CV). d$i$v$j$: pairwise AUC for depth $i$ vs.\\ depth $j$.}\n\\label{tab:multi_tau_within}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n$\\tau$ & 4-class acc (\\%) & d1v2 AUC & d0v1 AUC & d2v3 AUC \\\\\n\\midrule\n0.5 & 77.3 & 0.842 & 0.996 & 0.764 \\\\\n0.7 & 75.4 & 0.851 & 0.997 & 0.720 \\\\\n0.9 & 75.9 & 0.808 & 0.991 & 0.781 \\\\\n1.1 & 57.2 & 0.528 & 0.988 & 0.599 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-$\\tau$ leave-one-out transfer (Pythia-1.4B). Train on three temperatures, test on the held-out one.}\n\\label{tab:multi_tau_cross}\n\\begin{tabular}{@{}lcc@{}}\n\\toprule\nHoldout & Acc (\\%) & d1v2 AUC \\\\\n\\midrule\n$\\tau{=}0.5$ & 52.2 & 0.176 \\\\\n$\\tau{=}0.7$ & 41.0 & 0.299 \\\\\n$\\tau{=}0.9$ & 46.4 & 0.277 \\\\\n$\\tau{=}1.1$ & 47.1 & 0.525 \\\\\n\\midrule\nMean & 46.7 & 0.319 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Feature Overlap Analysis}\n\\label{app:feature_overlap}\n\nWe probe whether end-to-end PLM representations capture the same depth signals as our statistical features via linear probing of [CLS] representations from DeBERTa-v3-base and RoBERTa-base.\nPLM representations excel at surface lexical features (TTR: $R^2{=}0.85$, repeated bigrams) but fail to capture perplexity distribution statistics---\\textsc{var\\_surprisal} and \\textsc{p90\\_ppl} yield negative $R^2$ under linear probing, indicating these features are not linearly accessible in the pretrained representation space.\nThis confirms that the 19pp accuracy gap between feature-based and end-to-end methods (\\S\\ref{app:e2e}) stems from complementary---not redundant---representations: PLMs capture lexical patterns while the targeted statistical features capture distributional tail properties that constitute the dominant depth markers.\n\n\\subsection{End-to-End Learning}\n\\label{app:e2e}\n\nDeBERTa-v3-base \\cite{he2021_deberta_v3} and RoBERTa-base \\cite{liu2019_roberta} finetuned end-to-end achieve 58.3\\% ($\\pm$4.7\\%) and 59.5\\% ($\\pm$3.2\\%) respectively---lagging the RF baseline (78.2\\%) by 19.9pp and 18.7pp.\nThe 1.2pp inter-backbone gap rules out architecture bias; Table~\\ref{tab:e2e_detail} shows both backbones share the same failure mode---high d0 F1 ($>$0.94) but collapsed d1/d2 performance (F1 $\\leq$ 0.42)---while RF achieves 0.596 d2 recall, a $>$2$\\times$ advantage at the hardest depth class.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Per-class performance for end-to-end PLM classifiers vs.\\ RF baseline (Pythia-1.4B nucleus). PLM columns report F1; RF d2 column reports recall (the class with the largest PLM--RF gap). Both PLM backbones share the same failure pattern: collapsed d1/d2 scores despite adequate d0/d3.}\n\\label{tab:e2e_detail}\n\\begin{tabular}{@{}lccccc@{}}\n\\toprule\nMethod & Acc (\\%) & d0 & d1 & d2 & d3 \\\\\n\\midrule\nDeBERTa-v3 & 58.3\\,$\\pm$\\,4.7 & .947 & .378 & .247 & .656 \\\\\nRoBERTa-base & 59.5\\,$\\pm$\\,3.2 & .958 & .416 & .261 & .647 \\\\\n\\midrule\nRF (19 feat.) & 78.2 & --- & --- & .596$^\\dagger$ & --- \\\\\n\\bottomrule\n\\multicolumn{6}{@{}l}{\\footnotesize $^\\dagger$Recall; shown for the depth class with the largest PLM--RF gap.}\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Feature space divergence.}\nSHAP TreeExplainer analysis confirms that perplexity and surprisal features account for 88.8\\% of RF's total contribution.\nThree independent importance measures---SHAP, Gini, and permutation---show strong concordance (Kendall's $W{=}0.90$, $p{<}0.005$; pairwise Spearman $\\rho$: SHAP--Gini $0.93$, SHAP--permutation $0.84$; \\S\\ref{app:permutation}), with \\texttt{p90\\_ppl} appearing in the SHAP top-2 in 9/9 cells and \\texttt{var\\_surprisal} in 8/9.\nLinear probing of PLM [CLS] representations yields negative $R^2$ for both \\texttt{var\\_surprisal} and \\texttt{p90\\_ppl} (\\S\\ref{app:feature_overlap}), indicating that pretrained representations lack the linear structure needed to recover perplexity tail statistics---a systematic representational gap rather than a backbone-specific artifact.\n\nDCOL \\cite{cloc2025} reached 64.5\\% (\\S\\ref{app:dcol_iterations}); all end-to-end approaches (58--65\\%) underperform feature-based methods, suggesting depth estimation benefits from targeted statistical features that capture distributional tail properties absent from PLM representations.\nThis comparison is bounded by backbone scale ($\\leq$125M parameters); whether larger PLMs (e.g., 7B+) can close the gap via richer internal representations remains an open question.\n\n\\subsection{Domain Bias Analysis}\n\\label{app:domain_bias}\n\nTo assess whether the classifier exploits depth-related features or memorizes stylistic cues from individual seed articles, we conduct three sub-experiments.\n\n\\paragraph{Methodological note.}\nAn initial implementation assigned sample IDs with a global counter across depths, inadvertently correlating seed-group identity with depth (LOGO accuracy 64.0\\%, seed-group prediction 20.8\\%).\nWe discovered the issue during internal review, corrected to per-depth seed assignment ensuring each group contains equal samples per depth, and re-ran all sub-experiments.\nThe results below use the corrected pipeline; the initial (buggy) numbers are reported for transparency.\n\n\\paragraph{Sub-A: Standard CV.}\nFive-fold CV accuracy on 3-class (d1/d2/d3) classification ranges from 59\\% to 82\\% across the 9 atlas cells (up to 2.5$\\times$ above the 33.3\\% chance level), confirming that depth signal is the dominant classification factor.\n\n\\paragraph{Sub-B: LOGO evaluation.}\nWe assign each passage to one of 10 seed-article groups (balanced: each group contains equal samples per depth) and perform leave-one-group-out CV.\nLOGO mean accuracy is 72.1\\% (range 59.5--81.6\\%), matching standard CV (72.0\\%) within noise (before fix: 64.0\\%, reflecting the depth--group confound).\nPer-cell fold standard deviations range from 0.4pp to 1.4pp, indicating that cross-group generalization is as reliable as within-group classification.\n\n\\paragraph{Sub-C: Negative control.}\nWe train two classifiers on identical features: one predicting depth, the other predicting seed-group identity (10-class, chance = 10\\%).\nDepth prediction accuracy averages 72.0\\%; seed-group prediction averages 10.2\\%---indistinguishable from chance (before fix: 20.8\\%, inflated by the depth--group confound).\nThe depth-to-seed-group accuracy ratio is 7.1$\\times$, confirming that the feature representation encodes depth but not seed-article identity.\n\nTaken together, these results show that seed-article grouping has no measurable effect on depth estimation after correcting the group assignment: LOGO accuracy equals standard CV, and seed-group prediction is at chance.\n\n\\subsection{Wild-Data Calibration}\n\\label{app:calibration}\n\nTable~\\ref{tab:calibration} reports d0 accuracy and false positive rate (FPR) for all three model-specific nucleus RF classifiers on two out-of-distribution human-text corpora: WikiText-103 (546 editorial passages) and C4 (5{,}000 web-crawl passages).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Wild-data d0 accuracy and FPR for nucleus RF classifiers. All passages are human-written (true d0). FPR = fraction misclassified as d1+.}\n\\label{tab:calibration}\n\\begin{tabular}{@{}llrcc@{}}\n\\toprule\nModel & Source & $n$ & d0 (\\%) & FPR (\\%) \\\\\n\\midrule\nPythia-1.4B & WikiText & 546 & 100.0 & 0.0 \\\\\n & C4 & 5{,}000 & 79.8 & 20.2 \\\\\n\\addlinespace\nGPT-2~XL & WikiText & 546 & 99.3 & 0.7 \\\\\n & C4 & 5{,}000 & 77.6 & 22.4 \\\\\n\\addlinespace\nOLMo-1B & WikiText & 546 & 98.5 & 1.5 \\\\\n & C4 & 5{,}000 & 95.3 & 4.7 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nOn WikiText-103, all three classifiers achieve $\\geq$98.5\\% d0 accuracy, confirming that editorial text is reliably distinguished from recursive generations across model families.\nOn C4, FPR varies sharply: OLMo (4.7\\%) vs.\\ Pythia (20.2\\%) and GPT-2~XL (22.4\\%).\nC4 misclassifications concentrate in template and SEO content with elevated repetition features (\\texttt{rep\\_3gram} $+$37\\%, \\texttt{rep\\_4gram} $+$75\\% vs.\\ correctly classified d0 passages), rather than in random noise.\nThe model gap likely reflects training data composition: OLMo (trained on Dolma, which includes diverse web data) produces d0 features more tolerant of web-crawl variation, while Pythia and GPT-2~XL (trained primarily on Wikipedia/WebText) map template-heavy content into the d1+ region.\nAmong C4 false positives for GPT-2~XL, predictions distribute as d1 (9.0\\%), d2 (3.7\\%), d3 (9.6\\%); for OLMo, d1 (2.9\\%), d2 (0.5\\%), d3 (1.3\\%)---the non-uniform depth distribution suggests the classifier maps specific repetition patterns to particular depth signatures rather than producing random misclassifications.\n\n\\subsection{Downstream Curation PoC}\n\\label{app:curation_poc}\n\nTo validate that depth estimation translates to actionable data curation, we conduct a proof-of-concept downstream evaluation.\nWe fine-tune Pythia-410M with LoRA ($r{=}16$, $\\alpha{=}32$) for 3 epochs on 8 data conditions derived from the Pythia nucleus depth-estimation corpus, repeating each condition over 5 random seeds.\nConditions vary the selection mechanism (RF-predicted depth, oracle depth, random subsampling) and stringency (strict $\\approx$25\\%, moderate $\\approx$50\\%, soft threshold).\nTable~\\ref{tab:curation_poc} reports per-condition perplexity; Table~\\ref{tab:curation_comparisons} reports pairwise contrasts.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Curation PoC: per-condition perplexity (Pythia-410M LoRA, 5 seeds). $\\Delta$ is signed so that positive values indicate lower (better) perplexity than unfiltered. $^*$\\,: $p<0.05$ (paired $t$-test vs.\\ unfiltered).}\n\\label{tab:curation_poc}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lcccccc@{}}\n\\toprule\nCondition & Mean PPL & Std & $n$ & $\\Delta$ vs Unfilt. & $p$ & $d_z$ \\\\\n\\midrule\nunfiltered        & 15.776 & 0.066 & 10{,}000 & ---      & ---   & ---      \\\\\nrf\\_soft          & 15.733 & 0.038 &  4{,}422 & +0.043   & 0.407 &  0.41    \\\\\nrf\\_moderate      & 15.756 & 0.056 &  4{,}940 & +0.021   & 0.492 &  0.34    \\\\\nrf\\_strict        & 15.810 & 0.061 &  2{,}496 & $-$0.034 & 0.607 & $-$0.25  \\\\\noracle\\_moderate  & 15.809 & 0.103 &  5{,}000 & $-$0.033 & 0.485 & $-$0.34  \\\\\noracle\\_strict    & 15.879 & 0.128 &  2{,}500 & $-$0.103 & 0.216 & $-$0.66  \\\\\nrandom\\_soft      & 16.062 & 0.079 &  4{,}422 & $-$0.286 & ${<}$0.001$^*$ & $-$2.77  \\\\\nrandom\\_moderate  & 15.998 & 0.090 &  4{,}940 & $-$0.222 & 0.028$^*$ & $-$1.50  \\\\\nrandom\\_strict    & 16.239 & 0.165 &  2{,}496 & $-$0.463 & 0.013$^*$ & $-$1.89  \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Pairwise comparisons (paired $t$-test, 5 seeds). $^*$\\,: $p<0.05$; $^{**}$\\,: $p<0.01$.}\n\\label{tab:curation_comparisons}\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\nComparison & $\\Delta$ PPL & $t$ & $p$ \\\\\n\\midrule\nrf\\_strict vs random\\_strict     & 0.429 & $-$7.05 & 0.002$^{**}$ \\\\\nrf\\_moderate vs random\\_moderate & 0.242 & $-$3.77 & 0.020$^*$    \\\\\nrf\\_soft vs random\\_soft         & 0.328 & $-$17.98 & ${<}$0.001$^{**}$ \\\\\nrf\\_soft vs unfiltered           & 0.043 &    0.93 & 0.407        \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Reference Model Ablation}\n\\label{app:ref_ablation}\n\n\\begin{table}[h]\n\\centering\n\\caption{Reference model ablation. Classification accuracy (5-fold CV) on Pythia-1.4B generated text (nucleus, d0--d3) using different reference models for feature extraction.}\n\\label{tab:ref_ablation}\n\\begin{tabular}{lcc}\n\\toprule\nReference Model & Architecture & Accuracy (\\%) \\\\\n\\midrule\nPythia-1.4B (self) & GPT-NeoX & 78.6 $\\pm$ 0.6 \\\\\nOLMo-1B (cross) & OLMo & 74.5 $\\pm$ 0.7 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Cross-Boundary Generalization}\n\\label{app:cross_boundary}\n\nThe preceding experiments assume a single model family generates all recursive depths.\nIn practice, recursive contamination may traverse model boundaries: text generated by model~A is used to train model~B, whose output trains model~C.\nWe probe whether the depth signal persists under two relaxations of the single-model assumption.\n\n\\paragraph{Cross-model recursive chains.}\nWe construct a heterogeneous chain: human text (d0) $\\to$ Pythia-1.4B generates d1 $\\to$ OLMo-1B finetuned on Pythia-d1 generates d2 $\\to$ GPT-2~XL finetuned on OLMo-d2 generates d3.\nEach recursive step uses a \\emph{different} model family, eliminating the possibility that depth signal arises from a single model's idiosyncratic behavior.\nA 4-class Random Forest achieves 84.75\\% accuracy (95\\% CI $[81.0, 88.25]$), with per-depth F1 scores of 0.98 (d0), 0.88 (d1), 0.76 (d2), and 0.76 (d3).\nPairwise AUC remains high: d0-vs-d1 = 0.999 and d2-vs-d3 = 0.841.\nThese results suggest that distributional artifacts of recursive generation persist across model boundaries---providing preliminary evidence that the depth signal is a property of the recursive process itself rather than of any individual generator.\n\n\\paragraph{Cross-domain transfer.}\nAll prior experiments use WikiText-103 as the seed corpus.\nTo test domain dependence, we repeat the pipeline with arXiv abstracts as the seed text (Pythia-1.4B, nucleus $p{=}0.95$, 500 samples per depth, d0--d3).\nFive-fold cross-validation yields 74.1\\% $\\pm$ 2.0\\% accuracy, compared to ${\\sim}$78\\% on the WikiText seed.\nPer-depth F1 shows the familiar pattern: d0 = 1.00, d1 = 0.78, d2 = 0.52, d3 = 0.66---with d2 remaining the most challenging class.\nThe 4pp accuracy gap relative to WikiText likely reflects the narrower stylistic range of scientific abstracts, which may reduce the distributional contrast between adjacent depths.\nThese results suggest that the depth signal is domain-independent, providing preliminary evidence that the perplexity-based features capture properties of the recursive generation process rather than domain-specific artifacts of the seed corpus.\n\n\\subsection{Extended Discussion}\n\\label{app:extended_discussion}\n\n\\paragraph{Depth-graduated curation.}\nCurrent data curation operates on a binary human-vs-machine distinction \\cite{dsir2023,qurating2024}.\nRecursive generation depth estimation enables a finer-grained alternative: retain low-depth generations (d1) whose distributional properties remain close to the human source, while down-weighting or filtering high-depth text (d3+) where tail erosion has degraded quality.\nThe 70--85\\% in-distribution accuracy and $\\mathrm{EDD}_{0.75}{=}4$ suggest depth-graduated filtering is feasible within known model--strategy configurations, though the d1/d2 boundary inversion under cross-strategy transfer (\\S\\ref{sec:gen:crossstrategy}) means reliable curation requires either known decoding strategy metadata or an upstream strategy-identification step; a small-scale PoC (Appendix~\\ref{app:curation_poc}) shows RF-filtered subsets match unfiltered quality with 44\\% of the data; large-scale validation remains open.\nImportance weighting \\cite{sugiyama2007_importance_weighting} could further enable continuous depth-aware data selection rather than discrete thresholding.\n\n\\paragraph{Toward a provenance toolkit.}\nDepth estimation complements existing provenance methods along orthogonal axes.\nWatermarking \\cite{kirchenbauer2023_watermark} provides high-confidence attribution when the generator cooperates but is inapplicable to unwatermarked text.\nSource attribution \\cite{uchendu2020_attribution} identifies the generating model but not the generation history.\nDepth estimation characterizes \\emph{iterative reuse} regardless of generator cooperation or identity.\nA layered provenance system combining these three signals---watermark presence, source model, and recursive generation depth---could support more nuanced data auditing than any single method.\n",
      "numLines": 349,
      "startLine": 1,
      "totalLines": 349
    }
  }
}
```

</details>

---

### Tool call

_source line 20_

<details open><summary>🔧 Tool call — Read · `toolu_01941FYEiQ8CDkzFVt7HcHE3`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "fad67d9e-1723-4439-b2b8-83a88850f136",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Rc5oS2zQCCHjjHtazBRPvq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 273,
      "cache_read_input_tokens": 25990,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 273
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

_source line 21 · 2026-05-16T11:40:43.433Z_

<details><summary>↩ Tool result · `toolu_01941FYEiQ8CDkzFVt7HcHE3`</summary>

```text
1	\section{The Depth Degradation Atlas}
2	\label{sec:atlas}
3	
4	We present the Depth Degradation Atlas: a systematic empirical map of how statistical fingerprints evolve across recursive generation depths, models, and decoding strategies.
5	The atlas spans $3 \times 3 = 9$ model--strategy cells evaluated at depths $d \in \{0, 1, 2, 3\}$, with depth extensions to $d{=}5$ for cross-model EDD validation (\S\ref{sec:atlas:edd}).
6	
7	%% ----------------------------------------------------------------
8	\subsection{In-Distribution Performance}
9	\label{sec:atlas:id}
10	
11	Table~\ref{tab:main_matrix} reports four-class Random Forest accuracy (5-fold CV, 200 trees) across all nine cells.
12	Accuracy ranges from 69.6\% (Pythia, top-$k$) to 85.4\% (GPT-2~XL, temperature), all exceeding the 25\% chance baseline by a wide margin.
13	Two axis effects emerge.
14	GPT-2~XL achieves the highest accuracy under every strategy (76.6--85.4\%), followed by OLMo (74.2--82.0\%) and Pythia (69.6--78.2\%).
15	Top-$k$ sampling yields the lowest accuracy in every model.
16	The mean within-model strategy gap is 8.4~pp, comparable to the 7.1~pp mean within-strategy model gap---decoding strategy and model family contribute roughly equally to performance variance.
17	
18	\begin{table}[t]
19	\centering
20	\small
21	\caption{Four-class RF accuracy (\%) across the $3 \times 3$ atlas, with d1--d3 three-class accuracy in parentheses (chance = 25\% / 33\%). Depth-0 recall exceeds 98\% in all cells.}
22	\label{tab:main_matrix}
23	\begin{tabular}{@{}lccc@{}}
24	\toprule
25	& Nucleus & Temp.\ $\tau{=}0.9$ & Top-$k$ \\
26	\midrule
27	Pythia-1.4B  & 78.2\,(71.2) & 76.3\,(70.6) & 69.6\,(58.8) \\
28	OLMo-1B     & 78.8\,(75.0) & 82.0\,(76.3) & 74.2\,(66.1) \\
29	GPT-2~XL    & 83.3\,(79.0) & 85.4\,(82.6) & 76.6\,(69.5) \\
30	\bottomrule
31	\end{tabular}
32	\end{table}
33	
34	\paragraph{Per-class recall distribution.}
35	Depth-0 recall exceeds 98\% in all 9 cells, confirming that human-written text is trivially separable from any generation depth.
36	Among generated depths, d2 consistently yields the lowest recall (46--73\% across cells), followed by d3 (58--82\%) and d1 (72--91\%).
37	For example, Pythia-1.4B nucleus achieves per-class recall of d0$\,{=}\,$99\%, d1$\,{=}\,$82\%, d2$\,{=}\,$59\%, d3$\,{=}\,$72\%.
38	The strongest d2 recall is obtained by GPT-2~XL nucleus (73\%).
39	The d2 trough reflects its position at the center of the depth gradient: d2 features overlap with both the d1 distribution above and d3 below, making it the most confusable class---consistent with the d2-vs-d3 pair being the EDD bottleneck (\S\ref{sec:atlas:edd}).
40	Full per-class recall for all cells appears in Appendix~\ref{app:per_class}.
41	
42	%% ----------------------------------------------------------------
43	\subsection{Feature Consistency Across the Grid}
44	\label{sec:atlas:features}
45	
46	Despite the 15.8~pp accuracy spread across cells, a small feature family dominates in every setting.
47	The 90th-percentile perplexity (\texttt{p90\_ppl}) ranks top-2 by Gini importance in all 9 cells; surprisal variance (\texttt{var\_surprisal}) in 8/9 under SHAP (7/9 under Gini; Appendix~\ref{app:permutation}).
48	Table~\ref{tab:feature_importance} shows the full per-cell ranking.
49	
50	Cross-model feature-rank Spearman correlation averages $\bar{\rho} = 0.868$ (range $[0.619, 0.954]$): models agree on which features carry depth information even when they differ in absolute accuracy.
51	Among strategies, top-$k$ yields the highest cross-model rank correlation ($\rho = 0.811$)---the deterministic vocabulary truncation imposes a more uniform feature landscape across architectures, at the cost of weaker overall signal (\S\ref{sec:atlas:strategy}).
52	
53	Percentile-based features outperform their moment-based counterparts.
54	Token-level perplexity distributions are heavy-tailed: individual outlier passages can dominate the arithmetic mean of their depth class, whereas \texttt{p90\_ppl} is robust to such extremes while still capturing the tail erosion that signals generation depth.
55	
56	Feature ablation confirms this concentration: the top-2 features (\texttt{p90\_ppl} + \texttt{var\_surprisal}) alone reach 91.1\% of full accuracy (71.5\%), and the top-5 features achieve 97.6\% (76.5\% vs.\ 78.4\%), with perplexity statistics alone reaching 76.6\% (vs.\ surprisal 73.2\%, other categories ${\leq}$47\%).
57	Variance inflation analysis reveals VIF${>}$10 for 14--16 of 19 features, placing the effective independent dimensionality at ${\approx}$4--5.
58	Forward selection independently confirms the dominant pair: \texttt{p90\_ppl} is selected first in 6/9 cells, \texttt{var\_surprisal} in 3/9.
59	
60	The feature hierarchy also shifts with depth.
61	At shallow boundaries (d1 vs.\ d2), \texttt{var\_surprisal} dominates importance; at deeper boundaries (d3 vs.\ d4, d4 vs.\ d5), tail perplexity statistics (\texttt{p90\_ppl}, \texttt{kurtosis\_ppl}) take over.
62	This transition aligns with model-collapse dynamics~\cite{shumailov2024_nature}: early recursion narrows the surprisal distribution (captured by its variance), while later steps erode the perplexity tail (captured by upper quantiles and kurtosis).
63	
64	\begin{table}[t]
65	\centering
66	\small
67	\caption{Top-5 features by Gini importance. \textbf{Bold}: top-2. \texttt{p90\_ppl} top-2 in 9/9; \texttt{var\_surprisal} 8/9 under SHAP (7/9 under Gini).}
68	\label{tab:feature_importance}
69	\resizebox{\columnwidth}{!}{%
70	\begin{tabular}{@{}l l@{}}
71	\toprule
72	Cell & Top-5 features (Gini importance, ranked) \\
73	\midrule
74	Pythia, nuc.       & \textbf{var\_surp\,(.17)}, \textbf{p90\_ppl\,(.15)}, m\_ppl\,(.11), var\_ppl\,(.08), p75\,(.07) \\
75	Pythia, $\tau$     & \textbf{var\_surp\,(.17)}, \textbf{p90\_ppl\,(.14)}, m\_ppl\,(.11), p75\,(.07), m\_surp\,(.07) \\
76	Pythia, top-$k$    & \textbf{var\_surp\,(.16)}, \textbf{p90\_ppl\,(.12)}, m\_ppl\,(.11), var\_ppl\,(.07), m\_surp\,(.06) \\
77	GPT-2\,XL, nuc.    & \textbf{var\_surp\,(.21)}, \textbf{p90\_ppl\,(.21)}, p75\,(.10), m\_surp\,(.07), m\_ppl\,(.06) \\
78	GPT-2\,XL, $\tau$  & \textbf{p90\_ppl\,(.25)}, \textbf{p75\,(.15)}, m\_surp\,(.13), var\_surp\,(.12), p50\,(.05) \\
79	GPT-2\,XL, top-$k$ & \textbf{p90\_ppl\,(.24)}, \textbf{p75\,(.12)}, var\_surp\,(.10), m\_surp\,(.09), ttr\,(.04) \\
80	OLMo, nuc.         & \textbf{p90\_ppl\,(.18)}, \textbf{var\_surp\,(.15)}, p75\,(.11), m\_surp\,(.07), ttr\,(.06) \\
81	OLMo, $\tau$       & \textbf{p90\_ppl\,(.21)}, \textbf{var\_surp\,(.16)}, p75\,(.12), m\_surp\,(.09), ttr\,(.05) \\
82	OLMo, top-$k$      & \textbf{p90\_ppl\,(.20)}, \textbf{var\_surp\,(.17)}, p75\,(.10), m\_surp\,(.07), m\_ppl\,(.05) \\
83	\bottomrule
84	\end{tabular}}
85	\end{table}
86	
87	\begin{figure}[t]
88	\centering
89	\includegraphics[width=\columnwidth]{figures/fig_atlas_heatmap.pdf}
90	\caption{Atlas feature importance heatmap. Rows: 19 features grouped by category (\S\ref{sec:method:features}); columns: 9 model--strategy cells. Color intensity encodes RF Gini importance. The perplexity-tail and surprisal-variance blocks maintain high importance across all cells.}
91	\label{fig:atlas_heatmap}
92	\end{figure}
93	
94	%% ----------------------------------------------------------------
95	\subsection{Monotonicity and Inter-Depth Distances}
96	\label{sec:atlas:monotonicity}
97	
98	Depth features exhibit strong monotonic trends: perplexity tail statistics (\texttt{p90\_ppl}, \texttt{mean\_surprisal}) decrease with depth (Spearman $\rho = -1.0$ across cell-level medians) while repetition features increase, reflecting the complementary narrowing and self-repetition of distribution collapse.
99	Inter-depth distances are non-uniform: d0-vs-d1 AUC exceeds 0.99 in all 9 cells, whereas d2-vs-d3 ranges from 0.69 to 0.89---separating adjacent deep generations requires the tail statistics identified in \S\ref{sec:atlas:features}.
100	
101	\begin{figure}[t]
102	\centering
103	\includegraphics[width=\columnwidth]{figures/fig_feature_trajectory.pdf}
104	\caption{Feature trajectories across depths $d{=}0$ to $d{=}3$, stratified by model (columns) and strategy (line style). Top row: \texttt{p90\_ppl} (monotonically decreasing). Middle: \texttt{var\_surprisal} (decreasing). Bottom: \texttt{rep\_3gram} (increasing). Shaded bands: interquartile range. The $d{=}0 \to d{=}1$ gap exceeds all subsequent inter-depth gaps.}
105	\label{fig:feature_trajectory}
106	\end{figure}
107	
108	%% ----------------------------------------------------------------
109	\subsection{EDD Analysis}
110	\label{sec:atlas:edd}
111	
112	We extend the benchmark to depth $d{=}5$ for all three models under nucleus sampling.
113	Each model's depth-3 LoRA checkpoint is used to finetune and generate depth-4 data, and the process repeats for depth~5; feature extraction uses the same reference model (Pythia-1.4B).
114	We train dedicated binary RF classifiers (500 trees) for each adjacent pair, as defined in Eq.~\ref{eq:edd}.
115	
116	\paragraph{AUC decay profile.}
117	Figure~\ref{fig:auc_decay} plots the binary pairwise AUC decay curves.
118	For Pythia-1.4B (nucleus), AUC decays monotonically: d0-vs-d1 $= 0.999$, d1-vs-d2 $= 0.925$, d2-vs-d3 $= 0.823$, d3-vs-d4 $= 0.784$, d4-vs-d5 $= 0.683$.
119	The steepest drop occurs between the d1-vs-d2 and d2-vs-d3 pairs; the curve then flattens as the system approaches an indistinguishable regime gradually rather than crossing a sharp boundary.
120	
121	\paragraph{Cross-model convergence at depth 4--5.}
122	The d3-vs-d4 AUC consistently clusters near the $T{=}0.75$ threshold across all three models (Pythia $0.784$, OLMo $0.765$, GPT-2~XL $0.750$), while d4-vs-d5 uniformly falls below $0.70$ ($0.681$--$0.684$).
123	The directional pattern is consistent, but statistical strength is stratified: bootstrap testing ($10{,}000$ resamples, $H_0{:}\, \mathrm{AUC} \leq 0.75$) yields $p = 0.001$ for Pythia (significant), $p = 0.091$ for OLMo (marginal), and $p = 0.505$ for GPT-2~XL (non-significant).
124	All three models cross the $T{=}0.75$ threshold within the d3--d4 region, establishing a consistent depth-4 decay boundary with graded confidence rather than uniform statistical significance.
125	The d4-vs-d5 saturation is unambiguous across models, supporting the interpretation of d3--d4 as a \emph{transition zone} from discriminable to indistinguishable regime.
126	
127	\paragraph{EDD threshold sensitivity.}
128	Table~\ref{tab:edd_sensitivity} reports $\mathrm{EDD}_T$ across the primary 9-cell benchmark (depths 0--3) at four threshold values.
129	At $T{=}0.65$, all 9 cells achieve $\mathrm{EDD} = 3$; at $T{=}0.75$, 7 of 9 cells maintain $\mathrm{EDD} \geq 3$; at $T{=}0.80$, the count drops to 5 of 9.
130	The cells losing $\mathrm{EDD}{=}3$ first are consistently the top-$k$ configurations (Pythia top-$k$ at $T{=}0.70$, then OLMo top-$k$ at $T{=}0.75$), where the d2-vs-d3 pair is the consistent bottleneck across all 9 cells.
131	
132	\begin{table}[t]
133	\centering
134	\small
135	\caption{Number of atlas cells achieving $\mathrm{EDD} \geq 3$ at each threshold $T$, across 9 model--strategy cells (depths 0--3). The d2-vs-d3 boundary is the bottleneck; top-$k$ cells drop first.}
136	\label{tab:edd_sensitivity}
137	\begin{tabular}{@{}lcccc@{}}
138	\toprule
139	& $T{=}0.65$ & $T{=}0.70$ & $T{=}0.75$ & $T{=}0.80$ \\
140	\midrule
141	Cells with $\mathrm{EDD} \geq 3$ & 9/9 & 8/9 & 7/9 & 5/9 \\
142	\bottomrule
143	\end{tabular}
144	\end{table}
145	
146	\begin{figure}[t]
147	\centering
148	\includegraphics[width=\columnwidth]{figures/fig_auc_decay.pdf}
149	\caption{Binary pairwise AUC decay curves for three models (nucleus sampling, depths 0--5). Horizontal dashed lines mark $T \in \{0.65, 0.70, 0.75, 0.80\}$. All three curves converge below 0.70 at d4-vs-d5, while d3-vs-d4 AUC clusters in the range 0.750--0.784. Shaded bands: bootstrap 95\% CIs.}
150	\label{fig:auc_decay}
151	\end{figure}
152	
153	\paragraph{Decision boundary dilution.}
154	\label{sec:atlas:edd:dilution}
155	EDD uses binary-pair classifiers to avoid \emph{decision boundary dilution}: in Pythia nucleus, d2\,vs.\,d3 AUC degrades from 0.804 (4-class) to 0.689 (6-class)---a 14.3\% relative decline despite identical data---because shared decision boundaries dilute per-pair capacity.
156	Binary classifiers eliminate this confound, isolating true adjacent-pair discriminability.
157	
158	%% ----------------------------------------------------------------
159	\subsection{Strategy-Dependent Trajectories}
160	\label{sec:atlas:strategy}
161	
162	The three decoding strategies induce qualitatively distinct degradation trajectories.
163	Nucleus ($p{=}0.95$) produces the most consistent accuracy (78.2--83.3\%) and serves as the reference trajectory.
164	Temperature ($\tau{=}0.9$) yields the highest accuracy in 2/3 models (GPT-2~XL 85.4\%, OLMo 82.0\%) because uniform logit scaling accelerates convergence to an attractor distribution~\cite{shumailov2024_nature}, amplifying the statistical fingerprint---but this acceleration creates a boundary reversal risk: temperature depth-$N$ features approximate nucleus/top-$k$ depth-$(N{+}1)$ features, causing cross-strategy classifiers to systematically overpredict depth (\S\ref{sec:generalization}).
165	Top-$k$ ($k{=}50$) produces the lowest accuracy (69.6--76.6\%) because hard vocabulary truncation removes depth-discriminative low-probability tokens, though feature direction is preserved (cross-model $\rho = 0.811$).
166	The strategy effect (8.4~pp range) exceeds the model effect (7.1~pp), indicating deployment-time knowledge of the decoding strategy matters at least as much as the generator model.
167	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "9c8826f9-6fa8-4b5c-8039-920c7ef2231a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/atlas.tex",
      "content": "\\section{The Depth Degradation Atlas}\n\\label{sec:atlas}\n\nWe present the Depth Degradation Atlas: a systematic empirical map of how statistical fingerprints evolve across recursive generation depths, models, and decoding strategies.\nThe atlas spans $3 \\times 3 = 9$ model--strategy cells evaluated at depths $d \\in \\{0, 1, 2, 3\\}$, with depth extensions to $d{=}5$ for cross-model EDD validation (\\S\\ref{sec:atlas:edd}).\n\n%% ----------------------------------------------------------------\n\\subsection{In-Distribution Performance}\n\\label{sec:atlas:id}\n\nTable~\\ref{tab:main_matrix} reports four-class Random Forest accuracy (5-fold CV, 200 trees) across all nine cells.\nAccuracy ranges from 69.6\\% (Pythia, top-$k$) to 85.4\\% (GPT-2~XL, temperature), all exceeding the 25\\% chance baseline by a wide margin.\nTwo axis effects emerge.\nGPT-2~XL achieves the highest accuracy under every strategy (76.6--85.4\\%), followed by OLMo (74.2--82.0\\%) and Pythia (69.6--78.2\\%).\nTop-$k$ sampling yields the lowest accuracy in every model.\nThe mean within-model strategy gap is 8.4~pp, comparable to the 7.1~pp mean within-strategy model gap---decoding strategy and model family contribute roughly equally to performance variance.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Four-class RF accuracy (\\%) across the $3 \\times 3$ atlas, with d1--d3 three-class accuracy in parentheses (chance = 25\\% / 33\\%). Depth-0 recall exceeds 98\\% in all cells.}\n\\label{tab:main_matrix}\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\n& Nucleus & Temp.\\ $\\tau{=}0.9$ & Top-$k$ \\\\\n\\midrule\nPythia-1.4B  & 78.2\\,(71.2) & 76.3\\,(70.6) & 69.6\\,(58.8) \\\\\nOLMo-1B     & 78.8\\,(75.0) & 82.0\\,(76.3) & 74.2\\,(66.1) \\\\\nGPT-2~XL    & 83.3\\,(79.0) & 85.4\\,(82.6) & 76.6\\,(69.5) \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Per-class recall distribution.}\nDepth-0 recall exceeds 98\\% in all 9 cells, confirming that human-written text is trivially separable from any generation depth.\nAmong generated depths, d2 consistently yields the lowest recall (46--73\\% across cells), followed by d3 (58--82\\%) and d1 (72--91\\%).\nFor example, Pythia-1.4B nucleus achieves per-class recall of d0$\\,{=}\\,$99\\%, d1$\\,{=}\\,$82\\%, d2$\\,{=}\\,$59\\%, d3$\\,{=}\\,$72\\%.\nThe strongest d2 recall is obtained by GPT-2~XL nucleus (73\\%).\nThe d2 trough reflects its position at the center of the depth gradient: d2 features overlap with both the d1 distribution above and d3 below, making it the most confusable class---consistent with the d2-vs-d3 pair being the EDD bottleneck (\\S\\ref{sec:atlas:edd}).\nFull per-class recall for all cells appears in Appendix~\\ref{app:per_class}.\n\n%% ----------------------------------------------------------------\n\\subsection{Feature Consistency Across the Grid}\n\\label{sec:atlas:features}\n\nDespite the 15.8~pp accuracy spread across cells, a small feature family dominates in every setting.\nThe 90th-percentile perplexity (\\texttt{p90\\_ppl}) ranks top-2 by Gini importance in all 9 cells; surprisal variance (\\texttt{var\\_surprisal}) in 8/9 under SHAP (7/9 under Gini; Appendix~\\ref{app:permutation}).\nTable~\\ref{tab:feature_importance} shows the full per-cell ranking.\n\nCross-model feature-rank Spearman correlation averages $\\bar{\\rho} = 0.868$ (range $[0.619, 0.954]$): models agree on which features carry depth information even when they differ in absolute accuracy.\nAmong strategies, top-$k$ yields the highest cross-model rank correlation ($\\rho = 0.811$)---the deterministic vocabulary truncation imposes a more uniform feature landscape across architectures, at the cost of weaker overall signal (\\S\\ref{sec:atlas:strategy}).\n\nPercentile-based features outperform their moment-based counterparts.\nToken-level perplexity distributions are heavy-tailed: individual outlier passages can dominate the arithmetic mean of their depth class, whereas \\texttt{p90\\_ppl} is robust to such extremes while still capturing the tail erosion that signals generation depth.\n\nFeature ablation confirms this concentration: the top-2 features (\\texttt{p90\\_ppl} + \\texttt{var\\_surprisal}) alone reach 91.1\\% of full accuracy (71.5\\%), and the top-5 features achieve 97.6\\% (76.5\\% vs.\\ 78.4\\%), with perplexity statistics alone reaching 76.6\\% (vs.\\ surprisal 73.2\\%, other categories ${\\leq}$47\\%).\nVariance inflation analysis reveals VIF${>}$10 for 14--16 of 19 features, placing the effective independent dimensionality at ${\\approx}$4--5.\nForward selection independently confirms the dominant pair: \\texttt{p90\\_ppl} is selected first in 6/9 cells, \\texttt{var\\_surprisal} in 3/9.\n\nThe feature hierarchy also shifts with depth.\nAt shallow boundaries (d1 vs.\\ d2), \\texttt{var\\_surprisal} dominates importance; at deeper boundaries (d3 vs.\\ d4, d4 vs.\\ d5), tail perplexity statistics (\\texttt{p90\\_ppl}, \\texttt{kurtosis\\_ppl}) take over.\nThis transition aligns with model-collapse dynamics~\\cite{shumailov2024_nature}: early recursion narrows the surprisal distribution (captured by its variance), while later steps erode the perplexity tail (captured by upper quantiles and kurtosis).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Top-5 features by Gini importance. \\textbf{Bold}: top-2. \\texttt{p90\\_ppl} top-2 in 9/9; \\texttt{var\\_surprisal} 8/9 under SHAP (7/9 under Gini).}\n\\label{tab:feature_importance}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}l l@{}}\n\\toprule\nCell & Top-5 features (Gini importance, ranked) \\\\\n\\midrule\nPythia, nuc.       & \\textbf{var\\_surp\\,(.17)}, \\textbf{p90\\_ppl\\,(.15)}, m\\_ppl\\,(.11), var\\_ppl\\,(.08), p75\\,(.07) \\\\\nPythia, $\\tau$     & \\textbf{var\\_surp\\,(.17)}, \\textbf{p90\\_ppl\\,(.14)}, m\\_ppl\\,(.11), p75\\,(.07), m\\_surp\\,(.07) \\\\\nPythia, top-$k$    & \\textbf{var\\_surp\\,(.16)}, \\textbf{p90\\_ppl\\,(.12)}, m\\_ppl\\,(.11), var\\_ppl\\,(.07), m\\_surp\\,(.06) \\\\\nGPT-2\\,XL, nuc.    & \\textbf{var\\_surp\\,(.21)}, \\textbf{p90\\_ppl\\,(.21)}, p75\\,(.10), m\\_surp\\,(.07), m\\_ppl\\,(.06) \\\\\nGPT-2\\,XL, $\\tau$  & \\textbf{p90\\_ppl\\,(.25)}, \\textbf{p75\\,(.15)}, m\\_surp\\,(.13), var\\_surp\\,(.12), p50\\,(.05) \\\\\nGPT-2\\,XL, top-$k$ & \\textbf{p90\\_ppl\\,(.24)}, \\textbf{p75\\,(.12)}, var\\_surp\\,(.10), m\\_surp\\,(.09), ttr\\,(.04) \\\\\nOLMo, nuc.         & \\textbf{p90\\_ppl\\,(.18)}, \\textbf{var\\_surp\\,(.15)}, p75\\,(.11), m\\_surp\\,(.07), ttr\\,(.06) \\\\\nOLMo, $\\tau$       & \\textbf{p90\\_ppl\\,(.21)}, \\textbf{var\\_surp\\,(.16)}, p75\\,(.12), m\\_surp\\,(.09), ttr\\,(.05) \\\\\nOLMo, top-$k$      & \\textbf{p90\\_ppl\\,(.20)}, \\textbf{var\\_surp\\,(.17)}, p75\\,(.10), m\\_surp\\,(.07), m\\_ppl\\,(.05) \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_atlas_heatmap.pdf}\n\\caption{Atlas feature importance heatmap. Rows: 19 features grouped by category (\\S\\ref{sec:method:features}); columns: 9 model--strategy cells. Color intensity encodes RF Gini importance. The perplexity-tail and surprisal-variance blocks maintain high importance across all cells.}\n\\label{fig:atlas_heatmap}\n\\end{figure}\n\n%% ----------------------------------------------------------------\n\\subsection{Monotonicity and Inter-Depth Distances}\n\\label{sec:atlas:monotonicity}\n\nDepth features exhibit strong monotonic trends: perplexity tail statistics (\\texttt{p90\\_ppl}, \\texttt{mean\\_surprisal}) decrease with depth (Spearman $\\rho = -1.0$ across cell-level medians) while repetition features increase, reflecting the complementary narrowing and self-repetition of distribution collapse.\nInter-depth distances are non-uniform: d0-vs-d1 AUC exceeds 0.99 in all 9 cells, whereas d2-vs-d3 ranges from 0.69 to 0.89---separating adjacent deep generations requires the tail statistics identified in \\S\\ref{sec:atlas:features}.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_feature_trajectory.pdf}\n\\caption{Feature trajectories across depths $d{=}0$ to $d{=}3$, stratified by model (columns) and strategy (line style). Top row: \\texttt{p90\\_ppl} (monotonically decreasing). Middle: \\texttt{var\\_surprisal} (decreasing). Bottom: \\texttt{rep\\_3gram} (increasing). Shaded bands: interquartile range. The $d{=}0 \\to d{=}1$ gap exceeds all subsequent inter-depth gaps.}\n\\label{fig:feature_trajectory}\n\\end{figure}\n\n%% ----------------------------------------------------------------\n\\subsection{EDD Analysis}\n\\label{sec:atlas:edd}\n\nWe extend the benchmark to depth $d{=}5$ for all three models under nucleus sampling.\nEach model's depth-3 LoRA checkpoint is used to finetune and generate depth-4 data, and the process repeats for depth~5; feature extraction uses the same reference model (Pythia-1.4B).\nWe train dedicated binary RF classifiers (500 trees) for each adjacent pair, as defined in Eq.~\\ref{eq:edd}.\n\n\\paragraph{AUC decay profile.}\nFigure~\\ref{fig:auc_decay} plots the binary pairwise AUC decay curves.\nFor Pythia-1.4B (nucleus), AUC decays monotonically: d0-vs-d1 $= 0.999$, d1-vs-d2 $= 0.925$, d2-vs-d3 $= 0.823$, d3-vs-d4 $= 0.784$, d4-vs-d5 $= 0.683$.\nThe steepest drop occurs between the d1-vs-d2 and d2-vs-d3 pairs; the curve then flattens as the system approaches an indistinguishable regime gradually rather than crossing a sharp boundary.\n\n\\paragraph{Cross-model convergence at depth 4--5.}\nThe d3-vs-d4 AUC consistently clusters near the $T{=}0.75$ threshold across all three models (Pythia $0.784$, OLMo $0.765$, GPT-2~XL $0.750$), while d4-vs-d5 uniformly falls below $0.70$ ($0.681$--$0.684$).\nThe directional pattern is consistent, but statistical strength is stratified: bootstrap testing ($10{,}000$ resamples, $H_0{:}\\, \\mathrm{AUC} \\leq 0.75$) yields $p = 0.001$ for Pythia (significant), $p = 0.091$ for OLMo (marginal), and $p = 0.505$ for GPT-2~XL (non-significant).\nAll three models cross the $T{=}0.75$ threshold within the d3--d4 region, establishing a consistent depth-4 decay boundary with graded confidence rather than uniform statistical significance.\nThe d4-vs-d5 saturation is unambiguous across models, supporting the interpretation of d3--d4 as a \\emph{transition zone} from discriminable to indistinguishable regime.\n\n\\paragraph{EDD threshold sensitivity.}\nTable~\\ref{tab:edd_sensitivity} reports $\\mathrm{EDD}_T$ across the primary 9-cell benchmark (depths 0--3) at four threshold values.\nAt $T{=}0.65$, all 9 cells achieve $\\mathrm{EDD} = 3$; at $T{=}0.75$, 7 of 9 cells maintain $\\mathrm{EDD} \\geq 3$; at $T{=}0.80$, the count drops to 5 of 9.\nThe cells losing $\\mathrm{EDD}{=}3$ first are consistently the top-$k$ configurations (Pythia top-$k$ at $T{=}0.70$, then OLMo top-$k$ at $T{=}0.75$), where the d2-vs-d3 pair is the consistent bottleneck across all 9 cells.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Number of atlas cells achieving $\\mathrm{EDD} \\geq 3$ at each threshold $T$, across 9 model--strategy cells (depths 0--3). The d2-vs-d3 boundary is the bottleneck; top-$k$ cells drop first.}\n\\label{tab:edd_sensitivity}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\n& $T{=}0.65$ & $T{=}0.70$ & $T{=}0.75$ & $T{=}0.80$ \\\\\n\\midrule\nCells with $\\mathrm{EDD} \\geq 3$ & 9/9 & 8/9 & 7/9 & 5/9 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_auc_decay.pdf}\n\\caption{Binary pairwise AUC decay curves for three models (nucleus sampling, depths 0--5). Horizontal dashed lines mark $T \\in \\{0.65, 0.70, 0.75, 0.80\\}$. All three curves converge below 0.70 at d4-vs-d5, while d3-vs-d4 AUC clusters in the range 0.750--0.784. Shaded bands: bootstrap 95\\% CIs.}\n\\label{fig:auc_decay}\n\\end{figure}\n\n\\paragraph{Decision boundary dilution.}\n\\label{sec:atlas:edd:dilution}\nEDD uses binary-pair classifiers to avoid \\emph{decision boundary dilution}: in Pythia nucleus, d2\\,vs.\\,d3 AUC degrades from 0.804 (4-class) to 0.689 (6-class)---a 14.3\\% relative decline despite identical data---because shared decision boundaries dilute per-pair capacity.\nBinary classifiers eliminate this confound, isolating true adjacent-pair discriminability.\n\n%% ----------------------------------------------------------------\n\\subsection{Strategy-Dependent Trajectories}\n\\label{sec:atlas:strategy}\n\nThe three decoding strategies induce qualitatively distinct degradation trajectories.\nNucleus ($p{=}0.95$) produces the most consistent accuracy (78.2--83.3\\%) and serves as the reference trajectory.\nTemperature ($\\tau{=}0.9$) yields the highest accuracy in 2/3 models (GPT-2~XL 85.4\\%, OLMo 82.0\\%) because uniform logit scaling accelerates convergence to an attractor distribution~\\cite{shumailov2024_nature}, amplifying the statistical fingerprint---but this acceleration creates a boundary reversal risk: temperature depth-$N$ features approximate nucleus/top-$k$ depth-$(N{+}1)$ features, causing cross-strategy classifiers to systematically overpredict depth (\\S\\ref{sec:generalization}).\nTop-$k$ ($k{=}50$) produces the lowest accuracy (69.6--76.6\\%) because hard vocabulary truncation removes depth-discriminative low-probability tokens, though feature direction is preserved (cross-model $\\rho = 0.811$).\nThe strategy effect (8.4~pp range) exceeds the model effect (7.1~pp), indicating deployment-time knowledge of the decoding strategy matters at least as much as the generator model.\n",
      "numLines": 167,
      "startLine": 1,
      "totalLines": 167
    }
  }
}
```

</details>

---

### Tool call

_source line 22_

<details open><summary>🔧 Tool call — Read · `toolu_01S2ZQYgtCp2DvEeKZFj3Py6`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "33c5b550-73f9-4eb6-9e44-ff1ff6360570",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Rc5oS2zQCCHjjHtazBRPvq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 273,
      "cache_read_input_tokens": 25990,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 273
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

_source line 23 · 2026-05-16T11:40:43.917Z_

<details><summary>↩ Tool result · `toolu_01S2ZQYgtCp2DvEeKZFj3Py6`</summary>

```text
1	\section{Generalization and Robustness}
2	\label{sec:generalization}
3	
4	We test whether the atlas results (69.6--85.4\%) reflect genuine statistical regularities or training artifacts, evaluating generalization along seven axes: four in detail below---classifier choice (\S\ref{sec:gen:baselines}), cross-model transfer (\S\ref{sec:gen:crossmodel}), cross-strategy transfer (\S\ref{sec:gen:crossstrategy}), and cross-scale generalization (\S\ref{sec:gen:crossscale})---and three in the Appendix (end-to-end learning, temperature robustness, and cross-boundary transfer).
5	
6	\subsection{Baseline Comparison}
7	\label{sec:gen:baselines}
8	
9	Table~\ref{tab:baselines} evaluates three classifier families---bagging (RF), gradient boosting (XGBoost, LightGBM)---on the same 19 features across three atlas cells spanning the full accuracy range.
10	Per-cell spread is $\leq$0.4pp, establishing a feature-determined ceiling independent of the learning algorithm.
11	On Pythia nucleus, CORAL ordinal regression \cite{coral2020} (78.1\%) and DivEye \cite{diveye2026} (78.2\%) match the within-cell RF of Table~\ref{tab:main_matrix} within 0.1\,pp (bootstrap $p>0.05$, Bonferroni-corrected); all feature-based methods significantly outperform CE-MLP (74.9\%, $p<0.001$) and logistic regression (75.0\%).
12	Single-feature regression on mean perplexity performs at chance (25.1\%); two zero-shot LLMs---DeepSeek V3.2 (36.2\%, 95\% CI $[32.0, 40.4]$) and Qwen2.5-7B-Instruct (30.4\%, $[26.5, 34.6]$; each 500 samples, prompt template in Appendix~\ref{app:zeroshot_prompt})---both fail to distinguish recursive depth, performing near chance (25\%).
13	The accuracy gap between RF (78.2\%) and both LLMs exceeds 42\,pp---an order of magnitude above the CI half-width (${\approx}$4\,pp)---ensuring this finding is robust at $n{=}500$.
14	
15	\begin{table}[t]
16	\centering
17	\small
18	\caption{Classifier convergence: 4-class accuracy (\%) across three atlas cells. RF (bagging), XGBoost and LightGBM (gradient boosting) operate on the same 19 features; $\Delta_{\max}$: largest per-cell spread. Chance = 25\%. RF values differ from Table~\ref{tab:main_matrix} by $\leq$0.7pp due to matched-fold evaluation.}
19	\label{tab:baselines}
20	\begin{tabular}{@{}lcccc@{}}
21	\toprule
22	Cell & RF & XGB & LGBM & $\Delta_{\max}$ \\
23	\midrule
24	Pythia, nuc. & 78.8 & 79.0 & 78.9 & 0.2 \\
25	GPT-2~XL, $\tau$ & 85.8 & 86.2 & 86.2 & 0.4 \\
26	Pythia, top-$k$ & 68.9 & 68.9 & 68.7 & 0.2 \\
27	\bottomrule
28	\end{tabular}
29	\end{table}
30	
31	Convergence across five structurally different classifiers---spanning bagging, gradient boosting, ordinal regression, and ensemble detection---confirms the signal resides in the features, not the learning algorithm.
32	Figure~\ref{fig:confusion_matrix} shows d0 near-perfectly identified; errors concentrate at d2/d3 in-distribution and spread across d1--d3 under transfer.
33	
34	\begin{figure}[t]
35	\centering
36	\includegraphics[width=\columnwidth]{figures/fig_confusion_matrix.pdf}
37	\caption{Confusion matrices for the best in-distribution setting (GPT-2 XL, temp $\tau{=}0.9$, 85.4\%) and the best cross-model leave-one-out transfer (OLMo holdout, 69.2\%). d0 recall exceeds 99\% in both; errors spread across the d1--d3 range under transfer.}
38	\label{fig:confusion_matrix}
39	\end{figure}
40	
41	\subsection{Cross-Model Transfer}
42	\label{sec:gen:crossmodel}
43	
44	We perform leave-one-model-family-out evaluation: train on two families (nucleus only), test on the held-out third (Table~\ref{tab:cross_model}).
45	
46	\begin{table}[t]
47	\centering
48	\small
49	\caption{Cross-model transfer (leave-one-out, nucleus only). Chance = 25\% / 33\% (d1--d3). d1--d3 bal.\ acc: Pythia 49.9\%, OLMo 59.2\%, GPT-2~XL 57.2\% (mean 55.4\%).}
50	\label{tab:cross_model}
51	\begin{tabular}{lccccc}
52	\toprule
53	Holdout & Acc & d0 & d1 & d2 & d3 \\
54	 & (\%) & Rec. & Rec. & Rec. & Rec. \\
55	\midrule
56	Pythia & 62.4 & 100.0 & 49.3 & 26.8 & 73.6 \\
57	OLMo & \textbf{69.2} & 99.3 & 75.5 & 43.3 & 58.8 \\
58	GPT-2 XL & 67.6 & 98.5 & 74.7 & 52.6 & 44.5 \\
59	\midrule
60	Mean & 66.4 & 99.3 & 66.5 & 40.9 & 59.0 \\
61	\bottomrule
62	\end{tabular}
63	\end{table}
64	
65	Mean transfer accuracy is 66.4\% (2.7$\times$ chance); d0 recall ($>$98\%) inflates the headline while d2 drops to 26.8\% (Pythia holdout).
66	Excluding d0, d1--d3 balanced accuracy averages 55.4\% (chance = 33\%).
67	
68	\subsection{Cross-Strategy Transfer}
69	\label{sec:gen:crossstrategy}
70	
71	We train on two decoding strategies and test on the held-out third (Table~\ref{tab:cross_strategy}).
72	
73	\begin{table}[t]
74	\centering
75	\small
76	\caption{Cross-strategy transfer (leave-one-out). Chance = 25\% / 33\% (d1--d3). d0 recall $\geq$89\% inflates headline; d1--d3 mean: 45.9\%.}
77	\label{tab:cross_strategy}
78	\begin{tabular}{lccc}
79	\toprule
80	Holdout & Pythia & OLMo & GPT-2 XL \\
81	 & Acc (\%) & Acc (\%) & Acc (\%) \\
82	\midrule
83	nucleus & \textbf{69.4} & \textbf{65.4} & \textbf{59.9} \\
84	temp ($\tau{=}0.9$) & 62.8 & 58.2 & 56.1 \\
85	top-$k$ ($k{=}50$) & 51.5 & 54.9 & 53.6 \\
86	\bottomrule
87	\end{tabular}
88	\end{table}
89	
90	Mean cross-strategy accuracy (59.1\%) falls 7pp below cross-model transfer (66.4\%); excluding d0, d1--d3 accuracy drops to 45.9\% (chance = 33\%).
91	d2 recall varies sharply: nucleus holdouts retain 30--54\%, top-$k$ holdouts fall to 8--19\%, and temperature holdouts span 3.7--39.5\% (median 8.9\%).
92	Training on nucleus + top-$k$ and testing on temperature inverts the d1/d2 boundary (d1v2 AUC $<$ 0.5); per-strategy z-score normalization partially recovers it but leaves a residual gap (Limitations).
93	A multi-temperature ablation (Appendix~\ref{app:multi_tau}) confirms that within-$\tau$ depth signal holds for $\tau \leq 0.9$ (d1v2 AUC $>0.80$) but collapses at $\tau{=}1.1$; cross-$\tau$ LOO transfer (mean 46.7\%) is harder than cross-strategy transfer.
94	Temperature variations ($\tau \in [0.5, 0.9]$) do not fundamentally alter depth discriminability within a fixed strategy; classification accuracy remains within 3pp of the $\tau{=}0.7$ baseline across all tested temperatures. Full multi-$\tau$ analysis is provided in Appendix~\ref{app:multi_tau}.
95	
96	End-to-end PLMs (DeBERTa-v3, RoBERTa) achieve only ${\sim}$59\%, lagging RF by 19pp, confirming depth signal resides in perplexity tail statistics inaccessible to standard PLM representations (Appendix~\ref{app:e2e}).
97	
98	%% ----------------------------------------------------------------
99	\subsection{Cross-Scale Analysis}
100	\label{sec:gen:crossscale}
101	
102	The preceding analyses use 1--1.5B parameter models.
103	To test whether depth signal persists in substantially larger generators, we extend the benchmark to two 7--8B models: Qwen2.5-7B-Instruct~\cite{qwen2.5} and Llama-3.1-8B-Instruct~\cite{llama3}, both under 4-bit NF4 QLoRA fine-tuning, generating depths $d \in \{0, 1, \ldots, 5\}$ with nucleus sampling ($p{=}0.95$, 500 samples per depth).
104	Feature extraction uses the same reference model (Pythia-1.4B) and 19-feature pipeline as all prior experiments.
105	
106	\paragraph{Scale comparison.}
107	Table~\ref{tab:cross_scale} contrasts the two 7--8B models with the three 1--1.5B models on matched evaluation (nucleus sampling, depths 0--3).
108	
109	\begin{table}[t]
110	\centering
111	\small
112	\caption{Cross-scale comparison: 4-class RF accuracy (\%, depths 0--3, nucleus), $\mathrm{EDD}_{T{=}0.70}$ (depths 0--5), and d0-vs-d1 AUC. CI: 95\% bootstrap. Chance = 25\%.}
113	\label{tab:cross_scale}
114	\begin{tabular}{@{}lccc@{}}
115	\toprule
116	Model & 4-class acc & $\mathrm{EDD}_{T{=}0.70}$ & d0v1 AUC \\
117	\midrule
118	GPT-2~XL (1.5B) & 83.3 & 4 & 0.999 \\
119	OLMo-1B & 78.8 & 4 & 0.997 \\
120	Pythia-1.4B & 78.2 & 4 & 0.998 \\
121	\midrule
122	Llama-3.1-8B & 70.2\,[68.3, 72.4] & 4 & 0.949 \\
123	Qwen2.5-7B & 60.1\,[58.0, 62.1] & ${>}5$ & 0.969 \\
124	\bottomrule
125	\end{tabular}
126	\end{table}
127	
128	Three findings emerge:
129	
130	\paragraph{(1) Depth signal persists at 7--8B scale.}
131	Both 7--8B models substantially exceed the 25\% chance baseline: Llama-3.1-8B achieves 70.2\% (95\% CI $[68.3, 72.4]$) and Qwen2.5-7B achieves 60.1\% ($[58.0, 62.1]$), confirming that recursive depth remains estimable from perplexity-based features even when the generator is 5--7$\times$ larger than the reference model.
132	Depth-0 separability is preserved in both models: d0v1 AUC is 0.949 (Llama-3.1) and 0.969 (Qwen2.5).
133	
134	\paragraph{(2) EDD at 7--8B scale.}
135	At threshold $T{=}0.70$, Qwen2.5-7B maintains all consecutive-pair AUCs above 0.70 through depth~5 (Table~\ref{tab:cross_scale_auc}), yielding $\mathrm{EDD}_{T{=}0.70} > 5$---exceeding the $\mathrm{EDD}{=}4$ observed at 1--1.5B.
136	Llama-3.1-8B matches the smaller models at $\mathrm{EDD}{=}4$: its monotonic decay causes d4v5 (0.618) to drop below $T$, despite stronger signal at shallower depths.
137	Both larger generators produce weaker per-step signal than the 1--1.5B models (mean consecutive AUC: 0.786 for Llama-3.1, 0.782 for Qwen2.5, vs.\ 0.852 at 1--1.5B).
138	
139	\begin{table}[t]
140	\centering
141	\small
142	\caption{Consecutive binary AUC for 7--8B models (nucleus $p{=}0.95$). Llama-3.1-8B exhibits monotonic decay (d4v5 drops below $T{=}0.70$); Qwen2.5-7B shows a non-monotonic (U-shaped) pattern with all pairs above $T$.}
143	\label{tab:cross_scale_auc}
144	\begin{tabular}{@{}lccccc@{}}
145	\toprule
146	Model & d0v1 & d1v2 & d2v3 & d3v4 & d4v5 \\
147	\midrule
148	Llama-3.1-8B & 0.949 & 0.877 & 0.771 & 0.716 & 0.618 \\
149	Qwen2.5-7B & 0.969 & 0.729 & 0.709 & 0.732 & 0.772 \\
150	\bottomrule
151	\end{tabular}
152	\end{table}
153	
154	\paragraph{(3) Divergent AUC trajectories across architectures.}
155	Llama-3.1-8B exhibits monotonic AUC decay (0.949 $\to$ 0.877 $\to$ 0.771 $\to$ 0.716 $\to$ 0.618), consistent with the pattern observed at 1--1.5B scale.
156	In contrast, Qwen2.5-7B shows a U-shaped recovery beyond d2v3: consecutive AUC drops from 0.969 (d0v1) to a minimum of 0.709 (d2v3), then \emph{rises} to 0.732 (d3v4) and 0.772 (d4v5).
157	This divergence suggests the U-shape observed in Qwen is model-specific---possibly related to its instruction-tuning regime (RLHF/DPO)---rather than a scale-dependent phenomenon.
158	The Llama-3.1 result demonstrates that monotonic decay \emph{does} replicate at 7--8B scale for at least one architecture, strengthening the generality of the decay pattern as the default behavior.
159	
160	\paragraph{Caveats.}
161	For Qwen2.5-7B, the CI lower bound (58.0\%) does not exclude sub-60\% accuracy; Llama-3.1-8B's lower bound (68.3\%) is more comfortably above chance but still below the 75--83\% range at 1--1.5B.
162	The divergent AUC trajectories across two models caution against strong generalizations from only two 7--8B data points: both the monotonic (Llama-3.1) and non-monotonic (Qwen2.5) patterns are single observations, and further architectures are needed to establish which is the dominant regime at this scale.
163	Both models are instruction-tuned, introducing a confound absent in the base-model experiments: RLHF/DPO alignment may independently shape the feature trajectory in ways not fully attributable to recursive depth alone.
164	Cross-model recursive chains (84.75\%) and cross-domain transfer (arXiv 74.1\%) further confirm signal universality (Appendix~\ref{app:cross_boundary}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "5a7508df-06ab-4a29-b141-c831daa8ebd7",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/generalization.tex",
      "content": "\\section{Generalization and Robustness}\n\\label{sec:generalization}\n\nWe test whether the atlas results (69.6--85.4\\%) reflect genuine statistical regularities or training artifacts, evaluating generalization along seven axes: four in detail below---classifier choice (\\S\\ref{sec:gen:baselines}), cross-model transfer (\\S\\ref{sec:gen:crossmodel}), cross-strategy transfer (\\S\\ref{sec:gen:crossstrategy}), and cross-scale generalization (\\S\\ref{sec:gen:crossscale})---and three in the Appendix (end-to-end learning, temperature robustness, and cross-boundary transfer).\n\n\\subsection{Baseline Comparison}\n\\label{sec:gen:baselines}\n\nTable~\\ref{tab:baselines} evaluates three classifier families---bagging (RF), gradient boosting (XGBoost, LightGBM)---on the same 19 features across three atlas cells spanning the full accuracy range.\nPer-cell spread is $\\leq$0.4pp, establishing a feature-determined ceiling independent of the learning algorithm.\nOn Pythia nucleus, CORAL ordinal regression \\cite{coral2020} (78.1\\%) and DivEye \\cite{diveye2026} (78.2\\%) match the within-cell RF of Table~\\ref{tab:main_matrix} within 0.1\\,pp (bootstrap $p>0.05$, Bonferroni-corrected); all feature-based methods significantly outperform CE-MLP (74.9\\%, $p<0.001$) and logistic regression (75.0\\%).\nSingle-feature regression on mean perplexity performs at chance (25.1\\%); two zero-shot LLMs---DeepSeek V3.2 (36.2\\%, 95\\% CI $[32.0, 40.4]$) and Qwen2.5-7B-Instruct (30.4\\%, $[26.5, 34.6]$; each 500 samples, prompt template in Appendix~\\ref{app:zeroshot_prompt})---both fail to distinguish recursive depth, performing near chance (25\\%).\nThe accuracy gap between RF (78.2\\%) and both LLMs exceeds 42\\,pp---an order of magnitude above the CI half-width (${\\approx}$4\\,pp)---ensuring this finding is robust at $n{=}500$.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Classifier convergence: 4-class accuracy (\\%) across three atlas cells. RF (bagging), XGBoost and LightGBM (gradient boosting) operate on the same 19 features; $\\Delta_{\\max}$: largest per-cell spread. Chance = 25\\%. RF values differ from Table~\\ref{tab:main_matrix} by $\\leq$0.7pp due to matched-fold evaluation.}\n\\label{tab:baselines}\n\\begin{tabular}{@{}lcccc@{}}\n\\toprule\nCell & RF & XGB & LGBM & $\\Delta_{\\max}$ \\\\\n\\midrule\nPythia, nuc. & 78.8 & 79.0 & 78.9 & 0.2 \\\\\nGPT-2~XL, $\\tau$ & 85.8 & 86.2 & 86.2 & 0.4 \\\\\nPythia, top-$k$ & 68.9 & 68.9 & 68.7 & 0.2 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nConvergence across five structurally different classifiers---spanning bagging, gradient boosting, ordinal regression, and ensemble detection---confirms the signal resides in the features, not the learning algorithm.\nFigure~\\ref{fig:confusion_matrix} shows d0 near-perfectly identified; errors concentrate at d2/d3 in-distribution and spread across d1--d3 under transfer.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_confusion_matrix.pdf}\n\\caption{Confusion matrices for the best in-distribution setting (GPT-2 XL, temp $\\tau{=}0.9$, 85.4\\%) and the best cross-model leave-one-out transfer (OLMo holdout, 69.2\\%). d0 recall exceeds 99\\% in both; errors spread across the d1--d3 range under transfer.}\n\\label{fig:confusion_matrix}\n\\end{figure}\n\n\\subsection{Cross-Model Transfer}\n\\label{sec:gen:crossmodel}\n\nWe perform leave-one-model-family-out evaluation: train on two families (nucleus only), test on the held-out third (Table~\\ref{tab:cross_model}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-model transfer (leave-one-out, nucleus only). Chance = 25\\% / 33\\% (d1--d3). d1--d3 bal.\\ acc: Pythia 49.9\\%, OLMo 59.2\\%, GPT-2~XL 57.2\\% (mean 55.4\\%).}\n\\label{tab:cross_model}\n\\begin{tabular}{lccccc}\n\\toprule\nHoldout & Acc & d0 & d1 & d2 & d3 \\\\\n & (\\%) & Rec. & Rec. & Rec. & Rec. \\\\\n\\midrule\nPythia & 62.4 & 100.0 & 49.3 & 26.8 & 73.6 \\\\\nOLMo & \\textbf{69.2} & 99.3 & 75.5 & 43.3 & 58.8 \\\\\nGPT-2 XL & 67.6 & 98.5 & 74.7 & 52.6 & 44.5 \\\\\n\\midrule\nMean & 66.4 & 99.3 & 66.5 & 40.9 & 59.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nMean transfer accuracy is 66.4\\% (2.7$\\times$ chance); d0 recall ($>$98\\%) inflates the headline while d2 drops to 26.8\\% (Pythia holdout).\nExcluding d0, d1--d3 balanced accuracy averages 55.4\\% (chance = 33\\%).\n\n\\subsection{Cross-Strategy Transfer}\n\\label{sec:gen:crossstrategy}\n\nWe train on two decoding strategies and test on the held-out third (Table~\\ref{tab:cross_strategy}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-strategy transfer (leave-one-out). Chance = 25\\% / 33\\% (d1--d3). d0 recall $\\geq$89\\% inflates headline; d1--d3 mean: 45.9\\%.}\n\\label{tab:cross_strategy}\n\\begin{tabular}{lccc}\n\\toprule\nHoldout & Pythia & OLMo & GPT-2 XL \\\\\n & Acc (\\%) & Acc (\\%) & Acc (\\%) \\\\\n\\midrule\nnucleus & \\textbf{69.4} & \\textbf{65.4} & \\textbf{59.9} \\\\\ntemp ($\\tau{=}0.9$) & 62.8 & 58.2 & 56.1 \\\\\ntop-$k$ ($k{=}50$) & 51.5 & 54.9 & 53.6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nMean cross-strategy accuracy (59.1\\%) falls 7pp below cross-model transfer (66.4\\%); excluding d0, d1--d3 accuracy drops to 45.9\\% (chance = 33\\%).\nd2 recall varies sharply: nucleus holdouts retain 30--54\\%, top-$k$ holdouts fall to 8--19\\%, and temperature holdouts span 3.7--39.5\\% (median 8.9\\%).\nTraining on nucleus + top-$k$ and testing on temperature inverts the d1/d2 boundary (d1v2 AUC $<$ 0.5); per-strategy z-score normalization partially recovers it but leaves a residual gap (Limitations).\nA multi-temperature ablation (Appendix~\\ref{app:multi_tau}) confirms that within-$\\tau$ depth signal holds for $\\tau \\leq 0.9$ (d1v2 AUC $>0.80$) but collapses at $\\tau{=}1.1$; cross-$\\tau$ LOO transfer (mean 46.7\\%) is harder than cross-strategy transfer.\nTemperature variations ($\\tau \\in [0.5, 0.9]$) do not fundamentally alter depth discriminability within a fixed strategy; classification accuracy remains within 3pp of the $\\tau{=}0.7$ baseline across all tested temperatures. Full multi-$\\tau$ analysis is provided in Appendix~\\ref{app:multi_tau}.\n\nEnd-to-end PLMs (DeBERTa-v3, RoBERTa) achieve only ${\\sim}$59\\%, lagging RF by 19pp, confirming depth signal resides in perplexity tail statistics inaccessible to standard PLM representations (Appendix~\\ref{app:e2e}).\n\n%% ----------------------------------------------------------------\n\\subsection{Cross-Scale Analysis}\n\\label{sec:gen:crossscale}\n\nThe preceding analyses use 1--1.5B parameter models.\nTo test whether depth signal persists in substantially larger generators, we extend the benchmark to two 7--8B models: Qwen2.5-7B-Instruct~\\cite{qwen2.5} and Llama-3.1-8B-Instruct~\\cite{llama3}, both under 4-bit NF4 QLoRA fine-tuning, generating depths $d \\in \\{0, 1, \\ldots, 5\\}$ with nucleus sampling ($p{=}0.95$, 500 samples per depth).\nFeature extraction uses the same reference model (Pythia-1.4B) and 19-feature pipeline as all prior experiments.\n\n\\paragraph{Scale comparison.}\nTable~\\ref{tab:cross_scale} contrasts the two 7--8B models with the three 1--1.5B models on matched evaluation (nucleus sampling, depths 0--3).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Cross-scale comparison: 4-class RF accuracy (\\%, depths 0--3, nucleus), $\\mathrm{EDD}_{T{=}0.70}$ (depths 0--5), and d0-vs-d1 AUC. CI: 95\\% bootstrap. Chance = 25\\%.}\n\\label{tab:cross_scale}\n\\begin{tabular}{@{}lccc@{}}\n\\toprule\nModel & 4-class acc & $\\mathrm{EDD}_{T{=}0.70}$ & d0v1 AUC \\\\\n\\midrule\nGPT-2~XL (1.5B) & 83.3 & 4 & 0.999 \\\\\nOLMo-1B & 78.8 & 4 & 0.997 \\\\\nPythia-1.4B & 78.2 & 4 & 0.998 \\\\\n\\midrule\nLlama-3.1-8B & 70.2\\,[68.3, 72.4] & 4 & 0.949 \\\\\nQwen2.5-7B & 60.1\\,[58.0, 62.1] & ${>}5$ & 0.969 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThree findings emerge:\n\n\\paragraph{(1) Depth signal persists at 7--8B scale.}\nBoth 7--8B models substantially exceed the 25\\% chance baseline: Llama-3.1-8B achieves 70.2\\% (95\\% CI $[68.3, 72.4]$) and Qwen2.5-7B achieves 60.1\\% ($[58.0, 62.1]$), confirming that recursive depth remains estimable from perplexity-based features even when the generator is 5--7$\\times$ larger than the reference model.\nDepth-0 separability is preserved in both models: d0v1 AUC is 0.949 (Llama-3.1) and 0.969 (Qwen2.5).\n\n\\paragraph{(2) EDD at 7--8B scale.}\nAt threshold $T{=}0.70$, Qwen2.5-7B maintains all consecutive-pair AUCs above 0.70 through depth~5 (Table~\\ref{tab:cross_scale_auc}), yielding $\\mathrm{EDD}_{T{=}0.70} > 5$---exceeding the $\\mathrm{EDD}{=}4$ observed at 1--1.5B.\nLlama-3.1-8B matches the smaller models at $\\mathrm{EDD}{=}4$: its monotonic decay causes d4v5 (0.618) to drop below $T$, despite stronger signal at shallower depths.\nBoth larger generators produce weaker per-step signal than the 1--1.5B models (mean consecutive AUC: 0.786 for Llama-3.1, 0.782 for Qwen2.5, vs.\\ 0.852 at 1--1.5B).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Consecutive binary AUC for 7--8B models (nucleus $p{=}0.95$). Llama-3.1-8B exhibits monotonic decay (d4v5 drops below $T{=}0.70$); Qwen2.5-7B shows a non-monotonic (U-shaped) pattern with all pairs above $T$.}\n\\label{tab:cross_scale_auc}\n\\begin{tabular}{@{}lccccc@{}}\n\\toprule\nModel & d0v1 & d1v2 & d2v3 & d3v4 & d4v5 \\\\\n\\midrule\nLlama-3.1-8B & 0.949 & 0.877 & 0.771 & 0.716 & 0.618 \\\\\nQwen2.5-7B & 0.969 & 0.729 & 0.709 & 0.732 & 0.772 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{(3) Divergent AUC trajectories across architectures.}\nLlama-3.1-8B exhibits monotonic AUC decay (0.949 $\\to$ 0.877 $\\to$ 0.771 $\\to$ 0.716 $\\to$ 0.618), consistent with the pattern observed at 1--1.5B scale.\nIn contrast, Qwen2.5-7B shows a U-shaped recovery beyond d2v3: consecutive AUC drops from 0.969 (d0v1) to a minimum of 0.709 (d2v3), then \\emph{rises} to 0.732 (d3v4) and 0.772 (d4v5).\nThis divergence suggests the U-shape observed in Qwen is model-specific---possibly related to its instruction-tuning regime (RLHF/DPO)---rather than a scale-dependent phenomenon.\nThe Llama-3.1 result demonstrates that monotonic decay \\emph{does} replicate at 7--8B scale for at least one architecture, strengthening the generality of the decay pattern as the default behavior.\n\n\\paragraph{Caveats.}\nFor Qwen2.5-7B, the CI lower bound (58.0\\%) does not exclude sub-60\\% accuracy; Llama-3.1-8B's lower bound (68.3\\%) is more comfortably above chance but still below the 75--83\\% range at 1--1.5B.\nThe divergent AUC trajectories across two models caution against strong generalizations from only two 7--8B data points: both the monotonic (Llama-3.1) and non-monotonic (Qwen2.5) patterns are single observations, and further architectures are needed to establish which is the dominant regime at this scale.\nBoth models are instruction-tuned, introducing a confound absent in the base-model experiments: RLHF/DPO alignment may independently shape the feature trajectory in ways not fully attributable to recursive depth alone.\nCross-model recursive chains (84.75\\%) and cross-domain transfer (arXiv 74.1\\%) further confirm signal universality (Appendix~\\ref{app:cross_boundary}).",
      "numLines": 164,
      "startLine": 1,
      "totalLines": 164
    }
  }
}
```

</details>

---

### Assistant

_source line 24_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clear picture of the current state:

1. **Feature trajectory figure** - Already in `atlas.tex` at line 101-106 (fig:feature_trajectory). It's already in the main text!
2. **Atlas main matrix table** - Already in `atlas.tex` at line 18-32 (tab:main_matrix). It's already in the main text!
3. **Cross-Scale AUC table** - Already in `generalization.tex` at line 139-152 (tab:cross_scale_auc). It's already in the main text!


4. **Appendix contents** - The appendix actually contains different items like top-k feature trajectories and permutation importance, not the ones the user mentioned as moved.

So these three items are still in the main text where they should be, not in the appendix as the user indicated. I'm checking whether the items the user wanted restored to the main text are actually already there. Looking at the current files, I can see the atlas matrix table, feature trajectory figure, and cross-scale AUC table are all present in the main sections, so it seems the document may have already been updated since the instruction was issued, or there's a mismatch between what was requested and what's currently in the files. I'm realizing the items the user mentioned are already integrated into the main text—they haven't actually been moved to the appendix. The appendix only contains a text description referencing the figure that's already in the main document, so there's nothing to relocate back. I need to figure out what the user actually wants, since the premise of the task seems to have already been completed or doesn't match the current state of the paper.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "773c098f-6362-49a4-93fc-14ea07fb5960",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MxzYYBRMjnSFFBKRL3nmsf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19451,
      "cache_read_input_tokens": 26263,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19451
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

Looking at the current files, all three items are **already in the main text**:

1. `fig:feature_trajectory` — already in `atlas.tex` (lines 101-106)
2. `tab:main_matrix` (3×3) — already in `atlas.tex` (lines 18-32)
3. `tab:cross_scale_auc` — already in `generalization.tex` (lines 139-152)

The appendix references these in-text. Let me verify by checking the abstract and introduction for items 4-5.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "0a06b70a-54c7-43f0-8b5d-7a161b18dc19",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MxzYYBRMjnSFFBKRL3nmsf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19451,
      "cache_read_input_tokens": 26263,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19451
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

<details open><summary>🔧 Tool call — Read · `toolu_01XU4iZ95cCNngyhA5fZQxzT`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "77fa89c0-0d0b-4168-bde8-b351bdf596a5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MxzYYBRMjnSFFBKRL3nmsf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19451,
      "cache_read_input_tokens": 26263,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19451
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

_source line 27 · 2026-05-16T11:41:17.268Z_

<details><summary>↩ Tool result · `toolu_01XU4iZ95cCNngyhA5fZQxzT`</summary>

```text
1	\begin{abstract}
2	As large language models increasingly train on web text containing their own outputs, a recursive model$\to$data$\to$model loop arises---yet no method estimates how many such iterations a text has undergone.
3	We formalize \emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.
4	From each passage we extract a compact statistical fingerprint---19 candidate features dominated by perplexity tail statistics, with the top 5 achieving 97.6\% of full-set performance---computed against a fixed reference model (Pythia-1.4B).
5	A Random Forest classifier achieves 70--85\% four-class accuracy (chance = 25\%; 58.8--82.6\% when excluding the near-perfectly separable d0 class; a zero-shot LLM baseline reaches only 36.2\%), with 90th-percentile perplexity and surprisal variance emerging as consistent depth markers across the studied $3 \times 3$ grid (top-2 importance in 9/9 and 8/9 cells, respectively).
6	Our \emph{Depth Degradation Atlas} reveals that decoding strategy reshapes degradation trajectories rather than merely attenuating them, and we define the \emph{Effective Discriminable Depth} (EDD) metric, finding $\mathrm{EDD}_{0.75}{=}4$ for extended recursion chains.
7	Cross-model transfer reaches 66.4\% and cross-strategy transfer 59.1\%; temperature sampling induces a d1/d2 AUC inversion that we decompose into a correctable scale component and a residual structural component.
8	Cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\%, and extending to two 7B-scale generators yields 70.2\% accuracy with monotonic AUC decay ($\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.
9	Applied to WikiText-103 (546 passages), all three model-specific classifiers achieve $\geq$98.5\% d0 accuracy despite $+$621\% domain shift in mean perplexity; on C4 web-crawl text, false positive rates range from 4.7\% to 22.4\%, concentrated in template content.
10	\end{abstract}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "10c55cbd-52e9-428b-92ea-a22a302dd831",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex",
      "content": "\\begin{abstract}\nAs large language models increasingly train on web text containing their own outputs, a recursive model$\\to$data$\\to$model loop arises---yet no method estimates how many such iterations a text has undergone.\nWe formalize \\emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.\nFrom each passage we extract a compact statistical fingerprint---19 candidate features dominated by perplexity tail statistics, with the top 5 achieving 97.6\\% of full-set performance---computed against a fixed reference model (Pythia-1.4B).\nA Random Forest classifier achieves 70--85\\% four-class accuracy (chance = 25\\%; 58.8--82.6\\% when excluding the near-perfectly separable d0 class; a zero-shot LLM baseline reaches only 36.2\\%), with 90th-percentile perplexity and surprisal variance emerging as consistent depth markers across the studied $3 \\times 3$ grid (top-2 importance in 9/9 and 8/9 cells, respectively).\nOur \\emph{Depth Degradation Atlas} reveals that decoding strategy reshapes degradation trajectories rather than merely attenuating them, and we define the \\emph{Effective Discriminable Depth} (EDD) metric, finding $\\mathrm{EDD}_{0.75}{=}4$ for extended recursion chains.\nCross-model transfer reaches 66.4\\% and cross-strategy transfer 59.1\\%; temperature sampling induces a d1/d2 AUC inversion that we decompose into a correctable scale component and a residual structural component.\nCross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\\%, and extending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.\nApplied to WikiText-103 (546 passages), all three model-specific classifiers achieve $\\geq$98.5\\% d0 accuracy despite $+$621\\% domain shift in mean perplexity; on C4 web-crawl text, false positive rates range from 4.7\\% to 22.4\\%, concentrated in template content.\n\\end{abstract}",
      "numLines": 10,
      "startLine": 1,
      "totalLines": 10
    }
  }
}
```

</details>

---

### Tool call

_source line 28_

<details open><summary>🔧 Tool call — Read · `toolu_01BQkKcpFejU3pTwVvbUUTN7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "767dd087-3410-4b6b-be68-c0f24953b693",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MxzYYBRMjnSFFBKRL3nmsf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19451,
      "cache_read_input_tokens": 26263,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19451
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

_source line 29 · 2026-05-16T11:41:17.741Z_

<details><summary>↩ Tool result · `toolu_01BQkKcpFejU3pTwVvbUUTN7`</summary>

```text
1	\section{Introduction}
2	\label{sec:intro}
3	
4	The text on which large language models are trained increasingly contains their own outputs.
5	As synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \cite{shumailov2024_nature,alemohammad2024_mad}.
6	This model$\to$data$\to$model cycle is no longer hypothetical---it is already occurring in the wild---yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \cite{dohmatob2024_tale_of_tails}.
7	
8	Existing tools address adjacent but distinct problems.
9	Binary detectors such as Binoculars \cite{binoculars2024}, Fast-DetectGPT \cite{fast_detectgpt2024}, and DivEye \cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \geq 1$ into a single category.
10	Watermarking \cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.
11	The model collapse literature \cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.
12	No existing method estimates the ordinal recursive generation depth of a text passage from its content alone.
13	
14	Our key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints are \textbf{universal and scale-variant} across the three model families and three decoding strategies studied.
15	Specifically, perplexity tail statistics---the 90th-percentile perplexity (\textsc{p90\_ppl}) and surprisal variance (\textsc{var\_surprisal})---emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 8/9 model--strategy configurations, respectively.
16	Surprisingly, in one of two 7B models the AUC trajectory becomes non-monotonic, suggesting that instruction tuning may alter degradation dynamics rather than scale alone driving a qualitative shift.
17	
18	We formalize recursive generation depth estimation as an ordinal classification task and introduce a lightweight pipeline to solve it.
19	Given a text passage, we compute a feature vector from reference-model perplexity statistics---19 candidates capturing distributional location, spread, tail behavior, and lexical diversity, though high multicollinearity concentrates the signal in ${\approx}$4--5 effective dimensions (\S\ref{sec:atlas:features})---and classify it with a Random Forest into one of $K{+}1$ depth classes ($d{=}0$ for human text through $d{=}K$ for $K$-th generation text).
20	To systematically characterize how recursive generation reshapes these features, we construct the \emph{Depth Degradation Atlas}: a $3 \times 3$ grid of model families (Pythia-1.4B, OLMo-1B, GPT-2~XL) and decoding strategies (nucleus $p{=}0.95$, temperature $\tau{=}0.9$, top-$k$ $k{=}50$), each spanning 4 generation depths, totaling 180K samples.
21	The atlas reveals strategy-dependent degradation trajectories---temperature sampling accelerates convergence toward a low-entropy attractor, while top-$k$ attenuates the depth signal---and we introduce the \emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.
22	
23	Our contributions are:
24	
25	\begin{itemize}
26	    \item \textbf{Task formalization and benchmark.} We define recursive generation depth estimation as ordinal classification, introduce the EDD metric, and construct a 180K-sample benchmark spanning 3 model families $\times$ 3 decoding strategies $\times$ 4 depths.
27	
28	    \item \textbf{Depth Degradation Atlas.} A systematic $3 \times 3$ characterization reveals that \textsc{p90\_ppl} and \textsc{var\_surprisal} are universal depth markers (top-2 in 9/9 and 8/9 cells), decoding strategy reshapes degradation trajectories qualitatively, and depth discrimination persists through $\mathrm{EDD}_{0.75}{=}4$ recursive steps.
29	
30	    \item \textbf{Generalization across seven axes (four in main text; three in appendix).} We demonstrate robustness beyond the training grid: cross-model recursive chains (84.75\%---depth signal accumulates across heterogeneous model boundaries), cross-scale to two 7B architectures (70.2\% and 60.1\%, with divergent AUC trajectories), cross-domain transfer to arXiv (74.1\%), temperature robustness ($\tau \in [0.5, 0.9]$), and reference model independence ($\Delta{=}4$\,pp). End-to-end transformers achieve only ${\sim}$59\% (19pp below feature-based), confirming that perplexity tail features encode signal inaccessible to standard PLM representations.
31	\end{itemize}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "2d03c9c4-0209-4360-9348-16b6ac21ecd6",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:intro}\n\nThe text on which large language models are trained increasingly contains their own outputs.\nAs synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \\cite{shumailov2024_nature,alemohammad2024_mad}.\nThis model$\\to$data$\\to$model cycle is no longer hypothetical---it is already occurring in the wild---yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \\cite{dohmatob2024_tale_of_tails}.\n\nExisting tools address adjacent but distinct problems.\nBinary detectors such as Binoculars \\cite{binoculars2024}, Fast-DetectGPT \\cite{fast_detectgpt2024}, and DivEye \\cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \\geq 1$ into a single category.\nWatermarking \\cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.\nThe model collapse literature \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \\citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.\nNo existing method estimates the ordinal recursive generation depth of a text passage from its content alone.\n\nOur key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints are \\textbf{universal and scale-variant} across the three model families and three decoding strategies studied.\nSpecifically, perplexity tail statistics---the 90th-percentile perplexity (\\textsc{p90\\_ppl}) and surprisal variance (\\textsc{var\\_surprisal})---emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 8/9 model--strategy configurations, respectively.\nSurprisingly, in one of two 7B models the AUC trajectory becomes non-monotonic, suggesting that instruction tuning may alter degradation dynamics rather than scale alone driving a qualitative shift.\n\nWe formalize recursive generation depth estimation as an ordinal classification task and introduce a lightweight pipeline to solve it.\nGiven a text passage, we compute a feature vector from reference-model perplexity statistics---19 candidates capturing distributional location, spread, tail behavior, and lexical diversity, though high multicollinearity concentrates the signal in ${\\approx}$4--5 effective dimensions (\\S\\ref{sec:atlas:features})---and classify it with a Random Forest into one of $K{+}1$ depth classes ($d{=}0$ for human text through $d{=}K$ for $K$-th generation text).\nTo systematically characterize how recursive generation reshapes these features, we construct the \\emph{Depth Degradation Atlas}: a $3 \\times 3$ grid of model families (Pythia-1.4B, OLMo-1B, GPT-2~XL) and decoding strategies (nucleus $p{=}0.95$, temperature $\\tau{=}0.9$, top-$k$ $k{=}50$), each spanning 4 generation depths, totaling 180K samples.\nThe atlas reveals strategy-dependent degradation trajectories---temperature sampling accelerates convergence toward a low-entropy attractor, while top-$k$ attenuates the depth signal---and we introduce the \\emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.\n\nOur contributions are:\n\n\\begin{itemize}\n    \\item \\textbf{Task formalization and benchmark.} We define recursive generation depth estimation as ordinal classification, introduce the EDD metric, and construct a 180K-sample benchmark spanning 3 model families $\\times$ 3 decoding strategies $\\times$ 4 depths.\n\n    \\item \\textbf{Depth Degradation Atlas.} A systematic $3 \\times 3$ characterization reveals that \\textsc{p90\\_ppl} and \\textsc{var\\_surprisal} are universal depth markers (top-2 in 9/9 and 8/9 cells), decoding strategy reshapes degradation trajectories qualitatively, and depth discrimination persists through $\\mathrm{EDD}_{0.75}{=}4$ recursive steps.\n\n    \\item \\textbf{Generalization across seven axes (four in main text; three in appendix).} We demonstrate robustness beyond the training grid: cross-model recursive chains (84.75\\%---depth signal accumulates across heterogeneous model boundaries), cross-scale to two 7B architectures (70.2\\% and 60.1\\%, with divergent AUC trajectories), cross-domain transfer to arXiv (74.1\\%), temperature robustness ($\\tau \\in [0.5, 0.9]$), and reference model independence ($\\Delta{=}4$\\,pp). End-to-end transformers achieve only ${\\sim}$59\\% (19pp below feature-based), confirming that perplexity tail features encode signal inaccessible to standard PLM representations.\n\\end{itemize}",
      "numLines": 31,
      "startLine": 1,
      "totalLines": 31
    }
  }
}
```

</details>

---

### Assistant

_source line 30_

<details><summary>Logged reasoning block</summary>

```text
So all three items (1-3) are already in the main text. Let me report this to the user and ask what to do. Looking more carefully:

1. `fig:feature_trajectory` is in atlas.tex at lines 101-106 — already in main text
2. `tab:main_matrix` is in atlas.tex at lines 18-32 — already in main text (3×3 table)
3. `tab:cross_scale_auc` is in generalization.tex at lines 139-152 — already in main text

The appendix doesn't contain these items as "moved" content — instead it references the main text figure. 

Now for items 4 and 5: the abstract needs emphasis added to the cross-model recursive chains result at line 8, and the contribution bullet at line 30 needs the inference speed detail about the Random Forest and millisecond-scale performance without GPU. Since the first three are already handled, I should focus on these two modifications and see if there's anything else worth adding.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "57430d13-9660-405a-8fbe-fe6066694a35",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013U7LnKH5dEN7CxCYNjJGi3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3668,
      "cache_read_input_tokens": 45714,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3668
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

_source line 31_

Items 1-3 are already in the main text. Let me check the overall page structure to understand why it's at ~6 pages.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "8c2beffe-0a20-49e5-801b-5d52c8de2c04",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013U7LnKH5dEN7CxCYNjJGi3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3668,
      "cache_read_input_tokens": 45714,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3668
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

_source line 32_

<details open><summary>🔧 Tool call — Read · `toolu_018iKDQ661yH4a9Fa3YjtsiM`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "774dda06-088e-4470-bc48-c9de29b3ad59",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013U7LnKH5dEN7CxCYNjJGi3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3668,
      "cache_read_input_tokens": 45714,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3668
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

_source line 33 · 2026-05-16T11:41:27.858Z_

<details><summary>↩ Tool result · `toolu_018iKDQ661yH4a9Fa3YjtsiM`</summary>

```text
1	% How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints
2	% Target: EMNLP 2026 (ARR May cycle)
3	\documentclass[11pt]{article}
4	\usepackage[review]{acl}
5	\usepackage{times}
6	\usepackage{latexsym}
7	\usepackage{graphicx}
8	\usepackage{booktabs}
9	\usepackage{amsmath}
10	\usepackage{amssymb}
11	\usepackage{multirow}
12	\usepackage{xcolor}
13	\usepackage{subcaption}
14	\usepackage[T1]{fontenc}
15	\usepackage[utf8]{inputenc}
16	\usepackage{microtype}
17	\usepackage{amsthm}
18	
19	\theoremstyle{definition}
20	\newtheorem{definition}{Definition}
21	
22	\title{How Deep Is Your Data? Estimating Recursive Generation Depth\\via Statistical Fingerprints}
23	
24	\author{Anonymous}
25	
26	\begin{document}
27	\maketitle
28	
29	\input{abstract}
30	
31	\input{introduction}
32	
33	\input{related_work}
34	
35	\input{method}
36	
37	\input{atlas}
38	
39	\input{generalization}
40	
41	\input{discussion}
42	
43	\input{conclusion}
44	
45	\bibliography{references}
46	
47	\appendix
48	\input{section_appendix}
49	
50	\end{document}
51	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "9d0b3ea7-e425-42b2-82a0-3947a8e516f9",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/main.tex",
      "content": "% How Deep Is Your Data? Estimating Recursive Generation Depth via Statistical Fingerprints\n% Target: EMNLP 2026 (ARR May cycle)\n\\documentclass[11pt]{article}\n\\usepackage[review]{acl}\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{multirow}\n\\usepackage{xcolor}\n\\usepackage{subcaption}\n\\usepackage[T1]{fontenc}\n\\usepackage[utf8]{inputenc}\n\\usepackage{microtype}\n\\usepackage{amsthm}\n\n\\theoremstyle{definition}\n\\newtheorem{definition}{Definition}\n\n\\title{How Deep Is Your Data? Estimating Recursive Generation Depth\\\\via Statistical Fingerprints}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\input{abstract}\n\n\\input{introduction}\n\n\\input{related_work}\n\n\\input{method}\n\n\\input{atlas}\n\n\\input{generalization}\n\n\\input{discussion}\n\n\\input{conclusion}\n\n\\bibliography{references}\n\n\\appendix\n\\input{section_appendix}\n\n\\end{document}\n",
      "numLines": 51,
      "startLine": 1,
      "totalLines": 51
    }
  }
}
```

</details>

---

### Assistant

_source line 34_

<details><summary>Logged reasoning block</summary>

```text
Now let me check what's in the discussion section (it might be empty or minimal) and the conclusion.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "c2adadca-dff6-4dc2-b5be-48af01f79220",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01S3nQ2PFqooJdeZ756ZbNyo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 926,
      "cache_read_input_tokens": 49382,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 926
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

<details open><summary>🔧 Tool call — Read · `toolu_01UsoMCE2NvA8vX3mCMKTDnZ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "a303e9d5-be82-43b3-870c-ff03c69110d0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01S3nQ2PFqooJdeZ756ZbNyo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 926,
      "cache_read_input_tokens": 49382,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 926
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

_source line 36 · 2026-05-16T11:41:31.683Z_

<details><summary>↩ Tool result · `toolu_01UsoMCE2NvA8vX3mCMKTDnZ`</summary>

```text
1	\section{Discussion and Conclusion}
2	\label{sec:discussion}
3	
4	We formalized recursive generation depth estimation and showed that a compact feature set dominated by perplexity tail statistics achieves 70--85\% four-class accuracy ($\mathrm{EDD}_{0.75}{=}4$ across models; \S\ref{sec:atlas:edd}), with five features sufficing for 97.6\% of full performance and classifier-agnostic convergence within $\leq$0.4pp.
5	The dominant pair (\texttt{p90\_ppl} top-2 in 9/9 cells, \texttt{var\_surprisal} in 8/9 under SHAP) generalizes across the three studied model families without retraining, making depth estimation a candidate early-warning signal for model collapse~\cite{shumailov2024_nature} within this experimental scope.
6	Recent work corroborates this connection, identifying entropy decline as a measurable signal of recursive degradation that parallels the tail erosion our features capture~\cite{shi2025_closer_look}.
7	Zero-shot LLM baselines reinforce this view: DeepSeek V3.2 (36.2\%) and Qwen2.5-7B (30.4\%) exhibit complementary failure modes---the former predicts nearly all samples as d0 while the latter is biased toward d1---yet both perform near chance, confirming that depth discrimination requires the targeted statistical features our pipeline extracts rather than general language understanding.
8	
9	Cross-strategy transfer remains the primary bottleneck (59.1\% vs.\ 66.4\% cross-model), with the temperature-induced d1/d2 AUC inversion making single-classifier deployment across unknown decoding strategies infeasible.
10	A multi-temperature ablation ($\tau \in [0.5, 1.1]$, Pythia-1.4B; Appendix~\ref{app:multi_tau}) reinforces this: within-$\tau$ depth discrimination is robust for $\tau \leq 0.9$ (d1v2 AUC $>0.80$), but cross-$\tau$ transfer (mean 46.7\%) is harder than cross-strategy transfer (59.1\%), confirming that strategy-conditioned classifiers are necessary.
11	A two-stage pipeline---first identifying the decoding strategy, then applying a strategy-conditioned depth classifier---could address this.
12	Different strategies produce distinguishable perplexity signatures (top-$k$ yields narrower distributions; temperature sampling produces heavier tails), suggesting that automatic strategy identification is technically feasible, though independent validation on held-out strategy sets is needed.
13	As an alternative, when deployment is restricted to a single platform or API provider, the decoding strategy is typically known a priori, and a strategy-conditioned classifier can be applied directly.
14	
15	\paragraph{Depth-graduated data curation.}
16	Current data curation operates on a binary human-vs-machine distinction~\cite{dsir2023,qurating2024}.
17	Depth estimation enables a finer-grained alternative: retain low-depth generations (d1) while filtering high-depth text (d3+) where tail erosion has degraded quality.
18	A proof-of-concept LoRA fine-tuning experiment shows RF depth-based filtering matches unfiltered performance with 44\% of the data, significantly outperforming size-matched random subsampling at all stringency tiers (Appendix~\ref{app:curation_poc}).
19	Cross-strategy deployment would first require strategy identification to avoid boundary inversion (\S\ref{sec:gen:crossstrategy}).
20	
21	\paragraph{Toward a provenance toolkit.}
22	Depth estimation complements existing provenance methods---watermarking~\cite{kirchenbauer2023_watermark} (requires generator cooperation) and source attribution~\cite{uchendu2020_attribution} (identifies model, not history)---by characterizing \emph{iterative reuse} regardless of generator identity~\cite{bevendorff2025_two_paradigms}.
23	A layered system combining watermark presence, source model, and recursive depth could support more nuanced data auditing than any single method.
24	
25	\paragraph{Mixed-depth documents.}
26	Sliding-window depth estimation at the segment level (256--512 tokens) could extend the approach to mixed-depth documents, enabling paragraph-level curation even from partially contaminated content.
27	
28	\paragraph{Adversarial robustness.}
29	Perplexity tail statistics exhibit inherent resistance to surface-level transformations (paraphrasing, back-translation) that preserve surprisal structure, though robustness to targeted distribution-aware attacks remains unverified.
30	
31	\paragraph{Scaling behavior.}
32	Our cross-scale experiments (\S\ref{sec:gen:crossscale}) confirm that depth signal persists at 7--8B scale (Llama-3.1-8B: 70.2\%, Qwen2.5-7B: 60.1\%).
33	Llama-3.1-8B matches the smaller models at $\mathrm{EDD}{=}4$ with monotonic AUC decay, while Qwen2.5-7B achieves $\mathrm{EDD}_{T{=}0.70} > 5$ via a non-monotonic (U-shaped) trajectory---exceeding the $\mathrm{EDD}{=}4$ at 1--1.5B.
34	Per-step signal strength decreases (mean consecutive AUC ${\approx}$0.78 vs.\ ${\approx}$0.85 at 1--1.5B), consistent with larger models generating more fluent text with narrower perplexity distributions.
35	The divergent AUC trajectories (monotonic for Llama-3.1 vs.\ U-shaped for Qwen2.5-Instruct) suggest that instruction tuning may alter degradation dynamics at high recursion depth, an observation warranting further investigation with controlled base/instruct pairs.
36	Tail erosion is driven by retraining on one's own output distribution rather than model capacity per se, explaining why the signal attenuates but does not vanish; further scaling beyond 8B may require richer feature sets (e.g., attention entropy or generation diversity metrics) to maintain discriminability.
37	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "d1d66dab-ba25-45ef-ae70-b8ac0733fe59",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/discussion.tex",
      "content": "\\section{Discussion and Conclusion}\n\\label{sec:discussion}\n\nWe formalized recursive generation depth estimation and showed that a compact feature set dominated by perplexity tail statistics achieves 70--85\\% four-class accuracy ($\\mathrm{EDD}_{0.75}{=}4$ across models; \\S\\ref{sec:atlas:edd}), with five features sufficing for 97.6\\% of full performance and classifier-agnostic convergence within $\\leq$0.4pp.\nThe dominant pair (\\texttt{p90\\_ppl} top-2 in 9/9 cells, \\texttt{var\\_surprisal} in 8/9 under SHAP) generalizes across the three studied model families without retraining, making depth estimation a candidate early-warning signal for model collapse~\\cite{shumailov2024_nature} within this experimental scope.\nRecent work corroborates this connection, identifying entropy decline as a measurable signal of recursive degradation that parallels the tail erosion our features capture~\\cite{shi2025_closer_look}.\nZero-shot LLM baselines reinforce this view: DeepSeek V3.2 (36.2\\%) and Qwen2.5-7B (30.4\\%) exhibit complementary failure modes---the former predicts nearly all samples as d0 while the latter is biased toward d1---yet both perform near chance, confirming that depth discrimination requires the targeted statistical features our pipeline extracts rather than general language understanding.\n\nCross-strategy transfer remains the primary bottleneck (59.1\\% vs.\\ 66.4\\% cross-model), with the temperature-induced d1/d2 AUC inversion making single-classifier deployment across unknown decoding strategies infeasible.\nA multi-temperature ablation ($\\tau \\in [0.5, 1.1]$, Pythia-1.4B; Appendix~\\ref{app:multi_tau}) reinforces this: within-$\\tau$ depth discrimination is robust for $\\tau \\leq 0.9$ (d1v2 AUC $>0.80$), but cross-$\\tau$ transfer (mean 46.7\\%) is harder than cross-strategy transfer (59.1\\%), confirming that strategy-conditioned classifiers are necessary.\nA two-stage pipeline---first identifying the decoding strategy, then applying a strategy-conditioned depth classifier---could address this.\nDifferent strategies produce distinguishable perplexity signatures (top-$k$ yields narrower distributions; temperature sampling produces heavier tails), suggesting that automatic strategy identification is technically feasible, though independent validation on held-out strategy sets is needed.\nAs an alternative, when deployment is restricted to a single platform or API provider, the decoding strategy is typically known a priori, and a strategy-conditioned classifier can be applied directly.\n\n\\paragraph{Depth-graduated data curation.}\nCurrent data curation operates on a binary human-vs-machine distinction~\\cite{dsir2023,qurating2024}.\nDepth estimation enables a finer-grained alternative: retain low-depth generations (d1) while filtering high-depth text (d3+) where tail erosion has degraded quality.\nA proof-of-concept LoRA fine-tuning experiment shows RF depth-based filtering matches unfiltered performance with 44\\% of the data, significantly outperforming size-matched random subsampling at all stringency tiers (Appendix~\\ref{app:curation_poc}).\nCross-strategy deployment would first require strategy identification to avoid boundary inversion (\\S\\ref{sec:gen:crossstrategy}).\n\n\\paragraph{Toward a provenance toolkit.}\nDepth estimation complements existing provenance methods---watermarking~\\cite{kirchenbauer2023_watermark} (requires generator cooperation) and source attribution~\\cite{uchendu2020_attribution} (identifies model, not history)---by characterizing \\emph{iterative reuse} regardless of generator identity~\\cite{bevendorff2025_two_paradigms}.\nA layered system combining watermark presence, source model, and recursive depth could support more nuanced data auditing than any single method.\n\n\\paragraph{Mixed-depth documents.}\nSliding-window depth estimation at the segment level (256--512 tokens) could extend the approach to mixed-depth documents, enabling paragraph-level curation even from partially contaminated content.\n\n\\paragraph{Adversarial robustness.}\nPerplexity tail statistics exhibit inherent resistance to surface-level transformations (paraphrasing, back-translation) that preserve surprisal structure, though robustness to targeted distribution-aware attacks remains unverified.\n\n\\paragraph{Scaling behavior.}\nOur cross-scale experiments (\\S\\ref{sec:gen:crossscale}) confirm that depth signal persists at 7--8B scale (Llama-3.1-8B: 70.2\\%, Qwen2.5-7B: 60.1\\%).\nLlama-3.1-8B matches the smaller models at $\\mathrm{EDD}{=}4$ with monotonic AUC decay, while Qwen2.5-7B achieves $\\mathrm{EDD}_{T{=}0.70} > 5$ via a non-monotonic (U-shaped) trajectory---exceeding the $\\mathrm{EDD}{=}4$ at 1--1.5B.\nPer-step signal strength decreases (mean consecutive AUC ${\\approx}$0.78 vs.\\ ${\\approx}$0.85 at 1--1.5B), consistent with larger models generating more fluent text with narrower perplexity distributions.\nThe divergent AUC trajectories (monotonic for Llama-3.1 vs.\\ U-shaped for Qwen2.5-Instruct) suggest that instruction tuning may alter degradation dynamics at high recursion depth, an observation warranting further investigation with controlled base/instruct pairs.\nTail erosion is driven by retraining on one's own output distribution rather than model capacity per se, explaining why the signal attenuates but does not vanish; further scaling beyond 8B may require richer feature sets (e.g., attention entropy or generation diversity metrics) to maintain discriminability.\n",
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

_source line 37_

<details open><summary>🔧 Tool call — Read · `toolu_01T7Kb9dZdWDfWjzCpgMTyuf`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "ecae9462-c235-466a-9c56-39bf706cf696",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01S3nQ2PFqooJdeZ756ZbNyo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 926,
      "cache_read_input_tokens": 49382,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 926
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

_source line 38 · 2026-05-16T11:41:32.202Z_

<details><summary>↩ Tool result · `toolu_01T7Kb9dZdWDfWjzCpgMTyuf`</summary>

```text
1	\section*{Limitations}
2	\label{sec:limitations}
3	
4	\paragraph{Cross-strategy deployment constraint.}
5	Cross-strategy transfer induces a d1/d2 boundary inversion under temperature sampling.
6	Per-strategy z-score normalization partially corrects the inversion under logistic regression (GPT-2~XL d1v2 AUC $0.24{\to}0.56$, OLMo $0.19{\to}0.70$) but yields negligible improvement for the Random Forest classifier used throughout the main experiments ($\Delta < 0.02$\,pp), and even in the best case (logistic regression) leaves a residual gap relative to within-strategy performance (${\sim}0.83$), indicating that a two-stage pipeline (strategy identification + strategy-conditioned classification) is needed for reliable cross-strategy deployment.
7	
8	\paragraph{d0 inflation of headline metrics.}
9	Depth~0 (human-written text) is near-perfectly separable (recall $>$98\% across all nine model--strategy settings), inflating headline accuracy.
10	Cross-model transfer accuracy of 66.4\% is substantially driven by d0; d2 recall drops to 26.8\% in the worst case (Pythia holdout).
11	
12	\paragraph{Controlled vs.\ ecological setting.}
13	The primary benchmark uses Wikipedia seed text with controlled recursive generation (LoRA fine-tuning, 1--1.5B parameter models); cross-scale experiments extend to 7--8B instruction-tuned models (\S\ref{sec:gen:crossscale}).
14	This protocol isolates the recursive depth variable but diverges from wild recursive contamination, where models are pretrained on mixed corpora containing prior-generation outputs at unknown proportions; the fingerprints we identify may attenuate or shift under such diffuse exposure.
15	Depth signal is the dominant classification factor (5-fold CV 59--82\%, up to 2.5$\times$ chance): LOGO accuracy (72.1\%) matches standard CV (72.0\%), and seed-group prediction is at chance (10.2\% vs.\ 10\%; Appendix~\ref{app:domain_bias}).
16	The 7--8B experiments use instruction-tuned models only; whether base models at this scale exhibit the same signal profile remains open.
17	Real-world documents may also interleave segments at different recursive generation depths; extending to segment-level estimation introduces a granularity--statistical-power tradeoff.
18	
19	\paragraph{Domain-dependent false positive rate.}
20	On editorial text (WikiText-103), all classifiers achieve $\geq$98.5\% d0 accuracy, but on web-crawl data (C4, 5{,}000 passages), FPR ranges from 4.7\% (OLMo) to 22.4\% (GPT-2~XL).
21	Misclassifications concentrate in template/SEO content with elevated repetition features (\texttt{rep\_3gram} $+$37\%, \texttt{rep\_4gram} $+$75\% vs.\ correctly classified d0); the model gap likely reflects training data composition (OLMo's Dolma includes diverse web data vs.\ Pythia/GPT-2~XL's Wikipedia/WebText).
22	Deployment on heterogeneous web corpora requires model- and domain-specific calibration.
23	
24	\paragraph{Adversarial robustness.}
25	Adversarial paraphrasing \cite{sadasivan2023_paraphrase} could disrupt the perplexity tail features that drive classification; depth estimation's robustness under such attacks is untested.
26	
27	\paragraph{EDD monotonicity assumption.}
28	Our EDD definition (Eq.~\ref{eq:edd}) requires all pairwise AUCs up to depth $d^*$ to exceed $T$, which is well-behaved when AUC decays monotonically---as observed in all our configurations.
29	However, \citet{bakshi2026_collapse_improvement} show that early recursion can temporarily \emph{improve} model quality, which could produce non-monotonic AUC profiles (e.g., a dip at d1/d2 followed by recovery at d2/d3).
30	Our cross-strategy transfer results provide an empirical example: training on nucleus + top-$k$ and testing on temperature yields d1-vs-d2 AUC as low as 0.129 (GPT-2~XL) and 0.253 (OLMo), violating the monotonicity assumption.
31	In such cases EDD would conservatively report a lower value than the deepest discriminable pair, potentially underestimating the true discriminable range; extending EDD to handle non-contiguous discriminable regions is future work.
32	The choice of threshold $T$ is also application-dependent: at $T{=}0.80$, several cells lose one depth level relative to $T{=}0.75$.
33	
34	\paragraph{Reference model dependency.}
35	Surprisal-based features are computed relative to Pythia-1.4B, which coincides with one of the three generators.
36	For the Pythia pipeline this constitutes self-model feature extraction, while OLMo and GPT-2~XL measurements are cross-model.
37	Empirically, the self-model configuration does not yield the highest accuracy (Pythia 78.2\% vs.\ GPT-2~XL 85.4\%), suggesting the overlap does not confer a systematic advantage.
38	An ablation with OLMo-1B as reference model shows $\Delta$=4.0pp (\S2.3), suggesting moderate robustness; however, both reference models share similar scale (${\sim}$1B) and autoregressive architecture, so validation with architecturally distinct references (e.g., encoder-only or larger-scale models) remains open.
39	The choice of reference model affects feature values; a different reference model may shift absolute feature magnitudes and potentially alter discriminability at depth boundaries.
40	
41	\paragraph{Additional caveats.}
42	Detection features degrade under domain shift \cite{pudasaini2026_detection_fails}; our depth features are likely susceptible.
43	\citet{falahati2026_curated} show that curated synthetic data need not trigger collapse, attenuating the fingerprints we exploit.
44	
45	\section*{Ethics Statement}
46	
47	This work uses publicly available pretrained language models (Pythia-1.4B, OLMo-1B, GPT-2~XL) and Wikipedia text as seed data.
48	No human subjects were involved, no private or sensitive data were collected, and no new models were released.
49	Our method is intended to support data provenance and training-data auditing; we acknowledge that depth estimation tools could in principle be misused to circumvent content moderation, though such risks are shared with all detection-oriented research.
50	Code and data will be released upon acceptance.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "e43c7c7c-5552-4e29-8499-c57472ceee0a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/conclusion.tex",
      "content": "\\section*{Limitations}\n\\label{sec:limitations}\n\n\\paragraph{Cross-strategy deployment constraint.}\nCross-strategy transfer induces a d1/d2 boundary inversion under temperature sampling.\nPer-strategy z-score normalization partially corrects the inversion under logistic regression (GPT-2~XL d1v2 AUC $0.24{\\to}0.56$, OLMo $0.19{\\to}0.70$) but yields negligible improvement for the Random Forest classifier used throughout the main experiments ($\\Delta < 0.02$\\,pp), and even in the best case (logistic regression) leaves a residual gap relative to within-strategy performance (${\\sim}0.83$), indicating that a two-stage pipeline (strategy identification + strategy-conditioned classification) is needed for reliable cross-strategy deployment.\n\n\\paragraph{d0 inflation of headline metrics.}\nDepth~0 (human-written text) is near-perfectly separable (recall $>$98\\% across all nine model--strategy settings), inflating headline accuracy.\nCross-model transfer accuracy of 66.4\\% is substantially driven by d0; d2 recall drops to 26.8\\% in the worst case (Pythia holdout).\n\n\\paragraph{Controlled vs.\\ ecological setting.}\nThe primary benchmark uses Wikipedia seed text with controlled recursive generation (LoRA fine-tuning, 1--1.5B parameter models); cross-scale experiments extend to 7--8B instruction-tuned models (\\S\\ref{sec:gen:crossscale}).\nThis protocol isolates the recursive depth variable but diverges from wild recursive contamination, where models are pretrained on mixed corpora containing prior-generation outputs at unknown proportions; the fingerprints we identify may attenuate or shift under such diffuse exposure.\nDepth signal is the dominant classification factor (5-fold CV 59--82\\%, up to 2.5$\\times$ chance): LOGO accuracy (72.1\\%) matches standard CV (72.0\\%), and seed-group prediction is at chance (10.2\\% vs.\\ 10\\%; Appendix~\\ref{app:domain_bias}).\nThe 7--8B experiments use instruction-tuned models only; whether base models at this scale exhibit the same signal profile remains open.\nReal-world documents may also interleave segments at different recursive generation depths; extending to segment-level estimation introduces a granularity--statistical-power tradeoff.\n\n\\paragraph{Domain-dependent false positive rate.}\nOn editorial text (WikiText-103), all classifiers achieve $\\geq$98.5\\% d0 accuracy, but on web-crawl data (C4, 5{,}000 passages), FPR ranges from 4.7\\% (OLMo) to 22.4\\% (GPT-2~XL).\nMisclassifications concentrate in template/SEO content with elevated repetition features (\\texttt{rep\\_3gram} $+$37\\%, \\texttt{rep\\_4gram} $+$75\\% vs.\\ correctly classified d0); the model gap likely reflects training data composition (OLMo's Dolma includes diverse web data vs.\\ Pythia/GPT-2~XL's Wikipedia/WebText).\nDeployment on heterogeneous web corpora requires model- and domain-specific calibration.\n\n\\paragraph{Adversarial robustness.}\nAdversarial paraphrasing \\cite{sadasivan2023_paraphrase} could disrupt the perplexity tail features that drive classification; depth estimation's robustness under such attacks is untested.\n\n\\paragraph{EDD monotonicity assumption.}\nOur EDD definition (Eq.~\\ref{eq:edd}) requires all pairwise AUCs up to depth $d^*$ to exceed $T$, which is well-behaved when AUC decays monotonically---as observed in all our configurations.\nHowever, \\citet{bakshi2026_collapse_improvement} show that early recursion can temporarily \\emph{improve} model quality, which could produce non-monotonic AUC profiles (e.g., a dip at d1/d2 followed by recovery at d2/d3).\nOur cross-strategy transfer results provide an empirical example: training on nucleus + top-$k$ and testing on temperature yields d1-vs-d2 AUC as low as 0.129 (GPT-2~XL) and 0.253 (OLMo), violating the monotonicity assumption.\nIn such cases EDD would conservatively report a lower value than the deepest discriminable pair, potentially underestimating the true discriminable range; extending EDD to handle non-contiguous discriminable regions is future work.\nThe choice of threshold $T$ is also application-dependent: at $T{=}0.80$, several cells lose one depth level relative to $T{=}0.75$.\n\n\\paragraph{Reference model dependency.}\nSurprisal-based features are computed relative to Pythia-1.4B, which coincides with one of the three generators.\nFor the Pythia pipeline this constitutes self-model feature extraction, while OLMo and GPT-2~XL measurements are cross-model.\nEmpirically, the self-model configuration does not yield the highest accuracy (Pythia 78.2\\% vs.\\ GPT-2~XL 85.4\\%), suggesting the overlap does not confer a systematic advantage.\nAn ablation with OLMo-1B as reference model shows $\\Delta$=4.0pp (\\S2.3), suggesting moderate robustness; however, both reference models share similar scale (${\\sim}$1B) and autoregressive architecture, so validation with architecturally distinct references (e.g., encoder-only or larger-scale models) remains open.\nThe choice of reference model affects feature values; a different reference model may shift absolute feature magnitudes and potentially alter discriminability at depth boundaries.\n\n\\paragraph{Additional caveats.}\nDetection features degrade under domain shift \\cite{pudasaini2026_detection_fails}; our depth features are likely susceptible.\n\\citet{falahati2026_curated} show that curated synthetic data need not trigger collapse, attenuating the fingerprints we exploit.\n\n\\section*{Ethics Statement}\n\nThis work uses publicly available pretrained language models (Pythia-1.4B, OLMo-1B, GPT-2~XL) and Wikipedia text as seed data.\nNo human subjects were involved, no private or sensitive data were collected, and no new models were released.\nOur method is intended to support data provenance and training-data auditing; we acknowledge that depth estimation tools could in principle be misused to circumvent content moderation, though such risks are shared with all detection-oriented research.\nCode and data will be released upon acceptance.",
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

_source line 39_

<details open><summary>🔧 Tool call — Read · `toolu_01MKNCiRxBrxLuZw5EBiA68R`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "0c283582-15c7-4051-bda7-c79531063671",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01S3nQ2PFqooJdeZ756ZbNyo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 926,
      "cache_read_input_tokens": 49382,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 926
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

_source line 40 · 2026-05-16T11:41:32.687Z_

<details><summary>↩ Tool result · `toolu_01MKNCiRxBrxLuZw5EBiA68R`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Problem Definition}
5	\label{sec:method:problem}
6	
7	Let $f_\theta$ denote a language model and $\mathcal{D}_0$ a corpus of human-written seed text.
8	We define a \emph{recursive generation chain} of depth $K$ as the sequence $\mathcal{D}_0, \mathcal{D}_1, \dots, \mathcal{D}_K$, where each $\mathcal{D}_k$ ($k \geq 1$) is produced by finetuning $f_\theta$ on $\mathcal{D}_{k-1}$ and sampling from the resulting model.
9	Depth $d{=}0$ denotes human-written text; depth $d{=}k$ ($k \geq 1$) denotes text generated by a model trained on depth-$(k{-}1)$ data.
10	
11	Given a text passage $x$, the task is to estimate its recursive generation depth $d \in \{0, 1, \dots, K\}$.
12	This is an ordinal classification problem: depths carry a natural ordering, and $d{=}1$ is structurally closer to $d{=}0$ than $d{=}3$ is, since each generation step compounds distributional drift.
13	
14	\subsection{Multi-Generational Benchmark Construction}
15	\label{sec:method:benchmark}
16	
17	We construct a benchmark spanning three axes: model family, decoding strategy, and generation depth.
18	
19	\paragraph{Model families.}
20	We select three 1--1.5B-parameter models with diverse pretraining corpora and architectures: Pythia-1.4B (EleutherAI), OLMo-1B (AI2), and GPT-2~XL (OpenAI, 1.5B).
21	Restricting to a narrow parameter range isolates the effect of architecture and training data from scale.
22	
23	\paragraph{Decoding strategies.}
24	Each model is paired with three decoding strategies: nucleus sampling ($p{=}0.95$) \cite{holtzman2020_nucleus}, temperature sampling ($\tau{=}0.9$), and top-$k$ sampling ($k{=}50$).
25	These span the dominant modes of open-ended generation and induce qualitatively different entropy profiles.
26	Our findings on feature importance and discriminability are limited to this grid; transfer to untested models, scales, or strategies is not established.
27	
28	\paragraph{Depth and scale.}
29	The primary benchmark covers depths d0--d3 across all $3 \times 3 = 9$ model--strategy cells, with 5{,}000 samples per depth per cell (180K samples total).
30	For depth extension experiments (\S\ref{sec:atlas}), we extend one pipeline (Pythia-1.4B, nucleus) to d0--d5.
31	
32	\paragraph{Generation pipeline.}
33	Starting from a Wikipedia subset as seed text ($\mathcal{D}_0$), each generation cycle proceeds in three steps: (1)~LoRA finetuning \cite{hu2022lora} on $\mathcal{D}_{k-1}$, freezing base model weights and training low-rank update matrices ($<$1\% additional parameters; $r{=}16$, $\alpha{=}32$, lr $2{\times}10^{-4}$, batch size 8, 3 epochs, dropout $0.05$, architecture-specific targets); (2)~sampling 5{,}000 passages from the LoRA-finetuned model (max 512 tokens, BOS-seeded, no prompt conditioning) under the specified decoding strategy; (3)~the generated corpus becomes $\mathcal{D}_k$ for the next cycle.
34	Each depth is produced by a model explicitly trained on the prior depth's data---not by sampling from the unmodified base model.
35	There is no per-passage lineage across depths, ensuring cross-validation splits do not introduce information leakage.
36	
37	\paragraph{Reference model.}
38	All statistical features (\S\ref{sec:method:features}) are computed using a fixed reference model---Pythia-1.4B---providing a consistent perplexity reference across all generation conditions.
39	We select Pythia-1.4B because it is the smallest of the three generators, and its training corpus (The Pile) partially overlaps with those of OLMo and GPT-2~XL, keeping perplexity values in a comparable range.
40	For the Pythia pipeline, feature extraction constitutes self-model measurement; for OLMo and GPT-2~XL, it is cross-model.
41	Empirically, the Pythia pipeline's 4-class accuracy (78.2\%) does not exceed GPT-2~XL (85.4\%), indicating that self-model measurement does not confer a systematic advantage.
42	In cross-model leave-one-out evaluation (\S\ref{sec:generalization}), the reference model remains fixed regardless of which generator is held out; the implications of sharing the reference model with one generator are discussed in Limitations.
43	An ablation replacing Pythia-1.4B with OLMo-1B as reference model yields 74.5\% vs 78.5\%, suggesting that depth signal detection is not critically dependent on the specific reference model ($\Delta$=4.0pp, within the 5pp robustness threshold; Appendix~\ref{tab:ref_ablation}).
44	
45	\subsection{Statistical Feature Design}
46	\label{sec:method:features}
47	
48	We extract a feature vector $\mathbf{f}(x)$ comprising 19 candidate features from the reference-model perplexity distribution over each passage $x$; ablation (\S\ref{sec:atlas:features}) shows the top 5 achieve 97.6\% of full-set performance, and variance inflation analysis reveals VIF${>}$10 for 14--16 features, placing the effective independent dimensionality at ${\approx}$4--5.
49	The features fall into four categories (Table~\ref{tab:features}).
50	
51	\begin{table}[t]
52	\centering
53	\small
54	\caption{The 19 statistical features comprising $\mathbf{f}(x)$, grouped by category. All perplexity and surprisal features are computed from the reference model (Pythia-1.4B).}
55	\label{tab:features}
56	\begin{tabular}{@{}llr@{}}
57	\toprule
58	Category & Features & $n$ \\
59	\midrule
60	Perplexity & mean, var, skewness, kurtosis, & 9 \\
61	statistics & p10, p25, p50, p75, p90 & \\
62	\addlinespace
63	Surprisal & mean, var, entropy & 3 \\
64	statistics & & \\
65	\addlinespace
66	Lexical & type--token ratio, hapax ratio, & 4 \\
67	diversity & bigram entropy, trigram entropy & \\
68	\addlinespace
69	Repetition & repeated 2/3/4-gram fractions & 3 \\
70	\bottomrule
71	\end{tabular}
72	\end{table}
73	
74	\emph{Perplexity statistics} (9 features) capture the per-token perplexity distribution via moments (mean, variance, skewness, kurtosis) and quantiles (p10--p90); tail quantiles prove especially informative as recursive finetuning erodes the high-perplexity tail (\S\ref{sec:atlas}).
75	\emph{Surprisal statistics} (3 features): mean, variance, and entropy of $-\log p(\text{token})$; surprisal variance captures second-order structure not redundant with perplexity moments.
76	\emph{Lexical diversity} (4 features): type--token ratio, hapax ratio, bigram/trigram entropy.
77	\emph{Repetition} (3 features): repeated $n$-gram fractions for $n \in \{2, 3, 4\}$.
78	
79	\subsection{Effective Discriminable Depth}
80	\label{sec:method:edd}
81	
82	Aggregate multi-class accuracy obscures whether discriminability degrades at specific depth boundaries.
83	We introduce the \emph{Effective Discriminable Depth} (EDD) to formalize the frontier beyond which adjacent depths become statistically indistinguishable.
84	
85	\paragraph{Pairwise discriminability.}
86	Let $\mathcal{D} = \{0, 1, \dots, K\}$ denote the depth set and $T \in (0.5, 1.0]$ a discrimination threshold.
87	For each adjacent pair $(d, d{+}1)$, we define the pairwise discriminability $\mathrm{AUC}(d, d{+}1)$ as the area under the ROC curve of a dedicated binary Random Forest classifier (500 trees, $\lfloor\sqrt{19}\rfloor$ candidate features per split) trained on class-balanced data from $\mathbf{f}(x)$ (\S\ref{sec:method:features}) to distinguish depth-$d$ from depth-$(d{+}1)$ samples, evaluated via 5-fold stratified cross-validation.
88	Each pair uses an independent classifier, avoiding the decision boundary dilution that arises in multi-class settings (\S\ref{sec:atlas:edd}).
89	
90	\begin{definition}[Effective Discriminable Depth]
91	\label{def:edd}
92	The \emph{Effective Discriminable Depth} at threshold $T$ is:
93	\begin{equation}
94	\mathrm{EDD}_T = \max \bigl\{ d^*{+}1 \,:\, \forall\, d' \leq d^*,\; \mathrm{AUC}(d', d'{+}1) \geq T \bigr\}
95	\label{eq:edd}
96	\end{equation}
97	where $d^* \in \{0, \dots, K{-}1\}$. If\, $\mathrm{AUC}(0,1) < T$, then $\mathrm{EDD}_T = 0$.
98	\end{definition}
99	
100	$\mathrm{EDD}_T$ is the deepest depth $d$ such that every adjacent pair from $(0,1)$ through $(d{-}1, d)$ remains discriminable at level $T$.
101	The universal quantifier ensures EDD reports the longest \emph{contiguous} discriminable prefix rather than an isolated high-AUC pair at greater depth.\footnote{Our AUC profiles are empirically monotonically decreasing (\S\ref{sec:atlas}), so in practice $\mathrm{EDD}_T = \max\{d'{+}1 : \mathrm{AUC}(d', d'{+}1) \geq T\}$. For non-monotonic profiles, the contiguous formulation is more conservative (see Limitations).}
102	We set $T{=}0.75$ as default; sensitivity at $T \in \{0.65, 0.70, 0.75, 0.80\}$ is reported in \S\ref{sec:atlas}.
103	
104	\paragraph{Classifiers.}
105	Our primary classifier is a Random Forest (200 trees, unconstrained depth, 5-fold stratified cross-validation).
106	We compare against CORAL ordinal regression \cite{coral2020}, DivEye \cite{diveye2026}, a 2-layer cross-entropy MLP, logistic regression, and a single-feature baseline using mean perplexity alone; results appear in \S\ref{sec:generalization}.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "95a9193f-a962-446d-9c4b-479dfe3d39a7",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\subsection{Problem Definition}\n\\label{sec:method:problem}\n\nLet $f_\\theta$ denote a language model and $\\mathcal{D}_0$ a corpus of human-written seed text.\nWe define a \\emph{recursive generation chain} of depth $K$ as the sequence $\\mathcal{D}_0, \\mathcal{D}_1, \\dots, \\mathcal{D}_K$, where each $\\mathcal{D}_k$ ($k \\geq 1$) is produced by finetuning $f_\\theta$ on $\\mathcal{D}_{k-1}$ and sampling from the resulting model.\nDepth $d{=}0$ denotes human-written text; depth $d{=}k$ ($k \\geq 1$) denotes text generated by a model trained on depth-$(k{-}1)$ data.\n\nGiven a text passage $x$, the task is to estimate its recursive generation depth $d \\in \\{0, 1, \\dots, K\\}$.\nThis is an ordinal classification problem: depths carry a natural ordering, and $d{=}1$ is structurally closer to $d{=}0$ than $d{=}3$ is, since each generation step compounds distributional drift.\n\n\\subsection{Multi-Generational Benchmark Construction}\n\\label{sec:method:benchmark}\n\nWe construct a benchmark spanning three axes: model family, decoding strategy, and generation depth.\n\n\\paragraph{Model families.}\nWe select three 1--1.5B-parameter models with diverse pretraining corpora and architectures: Pythia-1.4B (EleutherAI), OLMo-1B (AI2), and GPT-2~XL (OpenAI, 1.5B).\nRestricting to a narrow parameter range isolates the effect of architecture and training data from scale.\n\n\\paragraph{Decoding strategies.}\nEach model is paired with three decoding strategies: nucleus sampling ($p{=}0.95$) \\cite{holtzman2020_nucleus}, temperature sampling ($\\tau{=}0.9$), and top-$k$ sampling ($k{=}50$).\nThese span the dominant modes of open-ended generation and induce qualitatively different entropy profiles.\nOur findings on feature importance and discriminability are limited to this grid; transfer to untested models, scales, or strategies is not established.\n\n\\paragraph{Depth and scale.}\nThe primary benchmark covers depths d0--d3 across all $3 \\times 3 = 9$ model--strategy cells, with 5{,}000 samples per depth per cell (180K samples total).\nFor depth extension experiments (\\S\\ref{sec:atlas}), we extend one pipeline (Pythia-1.4B, nucleus) to d0--d5.\n\n\\paragraph{Generation pipeline.}\nStarting from a Wikipedia subset as seed text ($\\mathcal{D}_0$), each generation cycle proceeds in three steps: (1)~LoRA finetuning \\cite{hu2022lora} on $\\mathcal{D}_{k-1}$, freezing base model weights and training low-rank update matrices ($<$1\\% additional parameters; $r{=}16$, $\\alpha{=}32$, lr $2{\\times}10^{-4}$, batch size 8, 3 epochs, dropout $0.05$, architecture-specific targets); (2)~sampling 5{,}000 passages from the LoRA-finetuned model (max 512 tokens, BOS-seeded, no prompt conditioning) under the specified decoding strategy; (3)~the generated corpus becomes $\\mathcal{D}_k$ for the next cycle.\nEach depth is produced by a model explicitly trained on the prior depth's data---not by sampling from the unmodified base model.\nThere is no per-passage lineage across depths, ensuring cross-validation splits do not introduce information leakage.\n\n\\paragraph{Reference model.}\nAll statistical features (\\S\\ref{sec:method:features}) are computed using a fixed reference model---Pythia-1.4B---providing a consistent perplexity reference across all generation conditions.\nWe select Pythia-1.4B because it is the smallest of the three generators, and its training corpus (The Pile) partially overlaps with those of OLMo and GPT-2~XL, keeping perplexity values in a comparable range.\nFor the Pythia pipeline, feature extraction constitutes self-model measurement; for OLMo and GPT-2~XL, it is cross-model.\nEmpirically, the Pythia pipeline's 4-class accuracy (78.2\\%) does not exceed GPT-2~XL (85.4\\%), indicating that self-model measurement does not confer a systematic advantage.\nIn cross-model leave-one-out evaluation (\\S\\ref{sec:generalization}), the reference model remains fixed regardless of which generator is held out; the implications of sharing the reference model with one generator are discussed in Limitations.\nAn ablation replacing Pythia-1.4B with OLMo-1B as reference model yields 74.5\\% vs 78.5\\%, suggesting that depth signal detection is not critically dependent on the specific reference model ($\\Delta$=4.0pp, within the 5pp robustness threshold; Appendix~\\ref{tab:ref_ablation}).\n\n\\subsection{Statistical Feature Design}\n\\label{sec:method:features}\n\nWe extract a feature vector $\\mathbf{f}(x)$ comprising 19 candidate features from the reference-model perplexity distribution over each passage $x$; ablation (\\S\\ref{sec:atlas:features}) shows the top 5 achieve 97.6\\% of full-set performance, and variance inflation analysis reveals VIF${>}$10 for 14--16 features, placing the effective independent dimensionality at ${\\approx}$4--5.\nThe features fall into four categories (Table~\\ref{tab:features}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{The 19 statistical features comprising $\\mathbf{f}(x)$, grouped by category. All perplexity and surprisal features are computed from the reference model (Pythia-1.4B).}\n\\label{tab:features}\n\\begin{tabular}{@{}llr@{}}\n\\toprule\nCategory & Features & $n$ \\\\\n\\midrule\nPerplexity & mean, var, skewness, kurtosis, & 9 \\\\\nstatistics & p10, p25, p50, p75, p90 & \\\\\n\\addlinespace\nSurprisal & mean, var, entropy & 3 \\\\\nstatistics & & \\\\\n\\addlinespace\nLexical & type--token ratio, hapax ratio, & 4 \\\\\ndiversity & bigram entropy, trigram entropy & \\\\\n\\addlinespace\nRepetition & repeated 2/3/4-gram fractions & 3 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\emph{Perplexity statistics} (9 features) capture the per-token perplexity distribution via moments (mean, variance, skewness, kurtosis) and quantiles (p10--p90); tail quantiles prove especially informative as recursive finetuning erodes the high-perplexity tail (\\S\\ref{sec:atlas}).\n\\emph{Surprisal statistics} (3 features): mean, variance, and entropy of $-\\log p(\\text{token})$; surprisal variance captures second-order structure not redundant with perplexity moments.\n\\emph{Lexical diversity} (4 features): type--token ratio, hapax ratio, bigram/trigram entropy.\n\\emph{Repetition} (3 features): repeated $n$-gram fractions for $n \\in \\{2, 3, 4\\}$.\n\n\\subsection{Effective Discriminable Depth}\n\\label{sec:method:edd}\n\nAggregate multi-class accuracy obscures whether discriminability degrades at specific depth boundaries.\nWe introduce the \\emph{Effective Discriminable Depth} (EDD) to formalize the frontier beyond which adjacent depths become statistically indistinguishable.\n\n\\paragraph{Pairwise discriminability.}\nLet $\\mathcal{D} = \\{0, 1, \\dots, K\\}$ denote the depth set and $T \\in (0.5, 1.0]$ a discrimination threshold.\nFor each adjacent pair $(d, d{+}1)$, we define the pairwise discriminability $\\mathrm{AUC}(d, d{+}1)$ as the area under the ROC curve of a dedicated binary Random Forest classifier (500 trees, $\\lfloor\\sqrt{19}\\rfloor$ candidate features per split) trained on class-balanced data from $\\mathbf{f}(x)$ (\\S\\ref{sec:method:features}) to distinguish depth-$d$ from depth-$(d{+}1)$ samples, evaluated via 5-fold stratified cross-validation.\nEach pair uses an independent classifier, avoiding the decision boundary dilution that arises in multi-class settings (\\S\\ref{sec:atlas:edd}).\n\n\\begin{definition}[Effective Discriminable Depth]\n\\label{def:edd}\nThe \\emph{Effective Discriminable Depth} at threshold $T$ is:\n\\begin{equation}\n\\mathrm{EDD}_T = \\max \\bigl\\{ d^*{+}1 \\,:\\, \\forall\\, d' \\leq d^*,\\; \\mathrm{AUC}(d', d'{+}1) \\geq T \\bigr\\}\n\\label{eq:edd}\n\\end{equation}\nwhere $d^* \\in \\{0, \\dots, K{-}1\\}$. If\\, $\\mathrm{AUC}(0,1) < T$, then $\\mathrm{EDD}_T = 0$.\n\\end{definition}\n\n$\\mathrm{EDD}_T$ is the deepest depth $d$ such that every adjacent pair from $(0,1)$ through $(d{-}1, d)$ remains discriminable at level $T$.\nThe universal quantifier ensures EDD reports the longest \\emph{contiguous} discriminable prefix rather than an isolated high-AUC pair at greater depth.\\footnote{Our AUC profiles are empirically monotonically decreasing (\\S\\ref{sec:atlas}), so in practice $\\mathrm{EDD}_T = \\max\\{d'{+}1 : \\mathrm{AUC}(d', d'{+}1) \\geq T\\}$. For non-monotonic profiles, the contiguous formulation is more conservative (see Limitations).}\nWe set $T{=}0.75$ as default; sensitivity at $T \\in \\{0.65, 0.70, 0.75, 0.80\\}$ is reported in \\S\\ref{sec:atlas}.\n\n\\paragraph{Classifiers.}\nOur primary classifier is a Random Forest (200 trees, unconstrained depth, 5-fold stratified cross-validation).\nWe compare against CORAL ordinal regression \\cite{coral2020}, DivEye \\cite{diveye2026}, a 2-layer cross-entropy MLP, logistic regression, and a single-feature baseline using mean perplexity alone; results appear in \\S\\ref{sec:generalization}.",
      "numLines": 106,
      "startLine": 1,
      "totalLines": 106
    }
  }
}
```

</details>

---

### Tool call

_source line 41_

<details open><summary>🔧 Tool call — Read · `toolu_01Y1WJJGWCiA8jDHVX1KQhmG`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "5b9d259e-9cbd-4d0f-8f8d-775a55caddb7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01S3nQ2PFqooJdeZ756ZbNyo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 926,
      "cache_read_input_tokens": 49382,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 926
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

_source line 42 · 2026-05-16T11:41:33.153Z_

<details><summary>↩ Tool result · `toolu_01Y1WJJGWCiA8jDHVX1KQhmG`</summary>

```text
1	\section{Related Work}
2	\label{sec:related}
3	
4	\paragraph{Model Collapse Theory.}
5	\citet{shumailov2024_nature} demonstrate that recursive training on model outputs erodes distributional tails, collapsing the output distribution.
6	\citet{dohmatob2024_tale_of_tails} formalize this via scaling laws distinguishing tail \emph{narrowing} from \emph{cutting}; \citet{dohmatob2025_strong_collapse} establish strong collapse guarantees, and \citet{dohmatob2024_demystified} analyze the regression case.
7	The MAD framework \cite{alemohammad2024_mad} extends this to self-consuming models and quantifies the precision--recall tradeoff.
8	Mitigation strategies include retaining real data \cite{gerstgrasser2024_accumulate} and filtering via detection \cite{drayson2025_detection_prevents_collapse}.
9	Recent work identifies non-monotonic dynamics \cite{bakshi2026_collapse_improvement}, fixed-point convergence \cite{marchi2024_heat_death}, contamination bounds \cite{wang2026_contamination}, curated pipelines \cite{falahati2026_curated}, knowledge collapse \cite{knowledge_collapse2025}, spectral signatures \cite{sigma2026_spectral}, and self-improving loops \cite{synthetic_eggs2026}.
10	These works characterize degradation but assume depth is known a priori; we address the inverse problem of estimating depth from text alone.
11	
12	\paragraph{AI Text Detection.}
13	The detection literature, recently surveyed by \citet{wu2025_detection_survey}, spans statistical, model-based, and watermarking paradigms.
14	DetectGPT \cite{mitchell2023_detectgpt} introduced probability curvature as a zero-shot detection signal; Fast-DetectGPT \cite{fast_detectgpt2024} improves efficiency via surrogate-model conditional curvature.
15	Binoculars \cite{binoculars2024} exploits perplexity ratios between related models, DivEye \cite{diveye2026} leverages surprisal diversity, and GLTR \cite{gehrmann2019_gltr} visualizes per-token likelihood ranks.
16	Fundamental limits exist: paraphrasing reduces detection to near chance \cite{sadasivan2023_paraphrase}, detection degrades under distribution shift \cite{pudasaini2026_detection_fails}, and a generator barrier bounds performance when the generator is unknown \cite{pu2026_generator_barrier}.
17	Ghostbuster \cite{verma2024_ghostbuster} trains classifiers on statistical features for binary detection, sharing our feature-engineering philosophy but not addressing depth; M4-SemEval \cite{wang2024_m4_semeval} benchmarks multilingual detection, and DNA-GPT \cite{yang2024_dnagpt} uses divergent $n$-gram analysis.
18	Watermarking \cite{kirchenbauer2023_watermark} embeds detectable signals but requires proactive deployment.
19	All these methods perform binary classification, discarding ordinal depth information; our approach outputs ordinal depth labels, complementing rather than replacing binary detection.
20	
21	\paragraph{Adjacent Tasks.}
22	EditLens \cite{editlens2026} estimates editing extent but does not model recursive chains.
23	\citet{uchendu2020_attribution} classify \emph{which} model generated text rather than generation depth.
24	LOKI \cite{loki2025} benchmarks synthetic data detection across modalities but evaluates binary detection only.
25	\citet{mohamed2025_broken_telephone} study iterative generation as a ``broken telephone'' effect, measuring forward degradation; our task performs the inverse, classifying depth from text alone.
26	
27	\paragraph{Ordinal Classification.}
28	CORAL \cite{coral2020} enforces rank consistency via ordered binary tasks; CLOC \cite{cloc2025} extends contrastive learning with multi-margin ordinal losses.
29	We adopt both as baselines (\S\ref{sec:generalization}) to confirm the signal is accessible to principled ordinal methods.
30	
31	\paragraph{Decoding Strategy Effects.}
32	Decoding strategies shape text statistics in ways that interact with depth signals: nucleus sampling maintains diversity \cite{holtzman2020_nucleus}, decoding parameters affect evaluation non-trivially \cite{finlayson2024_closing}, and strategy effects are model-dependent \cite{garces_arias2025_decoding_decoded}.
33	\citet{wiher2022_decoding} systematically compare methods on surface-level properties, and Mirostat \cite{basu2021_mirostat} regulates output entropy via perplexity control.
34	Our Depth Degradation Atlas (\S\ref{sec:atlas}) reveals that these strategies induce qualitatively different degradation trajectories under recursive generation---temperature sampling accelerates convergence to a low-entropy attractor while top-$k$ attenuates the depth signal---effects beyond single-pass text quality.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "054f368e-22d7-45ce-bab9-e432e55c8117",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related}\n\n\\paragraph{Model Collapse Theory.}\n\\citet{shumailov2024_nature} demonstrate that recursive training on model outputs erodes distributional tails, collapsing the output distribution.\n\\citet{dohmatob2024_tale_of_tails} formalize this via scaling laws distinguishing tail \\emph{narrowing} from \\emph{cutting}; \\citet{dohmatob2025_strong_collapse} establish strong collapse guarantees, and \\citet{dohmatob2024_demystified} analyze the regression case.\nThe MAD framework \\cite{alemohammad2024_mad} extends this to self-consuming models and quantifies the precision--recall tradeoff.\nMitigation strategies include retaining real data \\cite{gerstgrasser2024_accumulate} and filtering via detection \\cite{drayson2025_detection_prevents_collapse}.\nRecent work identifies non-monotonic dynamics \\cite{bakshi2026_collapse_improvement}, fixed-point convergence \\cite{marchi2024_heat_death}, contamination bounds \\cite{wang2026_contamination}, curated pipelines \\cite{falahati2026_curated}, knowledge collapse \\cite{knowledge_collapse2025}, spectral signatures \\cite{sigma2026_spectral}, and self-improving loops \\cite{synthetic_eggs2026}.\nThese works characterize degradation but assume depth is known a priori; we address the inverse problem of estimating depth from text alone.\n\n\\paragraph{AI Text Detection.}\nThe detection literature, recently surveyed by \\citet{wu2025_detection_survey}, spans statistical, model-based, and watermarking paradigms.\nDetectGPT \\cite{mitchell2023_detectgpt} introduced probability curvature as a zero-shot detection signal; Fast-DetectGPT \\cite{fast_detectgpt2024} improves efficiency via surrogate-model conditional curvature.\nBinoculars \\cite{binoculars2024} exploits perplexity ratios between related models, DivEye \\cite{diveye2026} leverages surprisal diversity, and GLTR \\cite{gehrmann2019_gltr} visualizes per-token likelihood ranks.\nFundamental limits exist: paraphrasing reduces detection to near chance \\cite{sadasivan2023_paraphrase}, detection degrades under distribution shift \\cite{pudasaini2026_detection_fails}, and a generator barrier bounds performance when the generator is unknown \\cite{pu2026_generator_barrier}.\nGhostbuster \\cite{verma2024_ghostbuster} trains classifiers on statistical features for binary detection, sharing our feature-engineering philosophy but not addressing depth; M4-SemEval \\cite{wang2024_m4_semeval} benchmarks multilingual detection, and DNA-GPT \\cite{yang2024_dnagpt} uses divergent $n$-gram analysis.\nWatermarking \\cite{kirchenbauer2023_watermark} embeds detectable signals but requires proactive deployment.\nAll these methods perform binary classification, discarding ordinal depth information; our approach outputs ordinal depth labels, complementing rather than replacing binary detection.\n\n\\paragraph{Adjacent Tasks.}\nEditLens \\cite{editlens2026} estimates editing extent but does not model recursive chains.\n\\citet{uchendu2020_attribution} classify \\emph{which} model generated text rather than generation depth.\nLOKI \\cite{loki2025} benchmarks synthetic data detection across modalities but evaluates binary detection only.\n\\citet{mohamed2025_broken_telephone} study iterative generation as a ``broken telephone'' effect, measuring forward degradation; our task performs the inverse, classifying depth from text alone.\n\n\\paragraph{Ordinal Classification.}\nCORAL \\cite{coral2020} enforces rank consistency via ordered binary tasks; CLOC \\cite{cloc2025} extends contrastive learning with multi-margin ordinal losses.\nWe adopt both as baselines (\\S\\ref{sec:generalization}) to confirm the signal is accessible to principled ordinal methods.\n\n\\paragraph{Decoding Strategy Effects.}\nDecoding strategies shape text statistics in ways that interact with depth signals: nucleus sampling maintains diversity \\cite{holtzman2020_nucleus}, decoding parameters affect evaluation non-trivially \\cite{finlayson2024_closing}, and strategy effects are model-dependent \\cite{garces_arias2025_decoding_decoded}.\n\\citet{wiher2022_decoding} systematically compare methods on surface-level properties, and Mirostat \\cite{basu2021_mirostat} regulates output entropy via perplexity control.\nOur Depth Degradation Atlas (\\S\\ref{sec:atlas}) reveals that these strategies induce qualitatively different degradation trajectories under recursive generation---temperature sampling accelerates convergence to a low-entropy attractor while top-$k$ attenuates the depth signal---effects beyond single-pass text quality.",
      "numLines": 34,
      "startLine": 1,
      "totalLines": 34
    }
  }
}
```

</details>

---

### Assistant

_source line 43_

<details><summary>Logged reasoning block</summary>

```text
Now I have a full picture of the paper. The items 1-3 that the user wanted moved back from appendix are ALREADY in the main text. The paper is currently at ~6 pages and needs content expansion.

Let me count what's in each section approximately (in ACL format, 2-column):
- Abstract: ~0.3 pages
- Introduction: ~1.0 page
- Related Work: ~0.7 pages
- Method: ~1.5 pages
- Atlas (§4): ~2.0 pages (multiple tables and figures)


- Generalization (§5): ~1.5 pages (tables and figures)
- Discussion & Conclusion: ~0.7 pages
- Limitations: ~0.7 pages
- Ethics: ~0.1 pages

That adds up to around 8.5 pages, but the user says it's ~6. I think the discrepancy comes from how figures and tables compress in 2-column format, or maybe the Limitations and Ethics sections don't count toward the official page count. In ACL format, those sections are typically excluded from the page limit anyway, so the actual countable content would be Introduction through Discussion, which comes to roughly 6 pages.

The user wants to expand to 7-7.5 pages, and they mentioned restoring some figures and tables that were previously moved to the appendix—the feature trajectory figure, atlas matrix table, and cross-scale AUC table. But looking at the current draft, these seem to already be in the main text, so either the restoration was already done or I need to verify what's actually missing.

Since items 1-3 are already handled, I should focus on the remaining expansion tasks: emphasizing the abstract and adding contribution bullets. Let me check what still needs to be done to reach the target page count. I'm realizing the three items the user mentioned are already present in the main text, so I should focus on items 4 and 5 instead. Let me think about what other content might have been compressed that could be expanded to reach the target page count, and I'll report back to the user about the status of items 1-3 while proceeding with what I can actually do.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "3d9258d8-d7fe-49d4-be68-a8e9cad49902",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LnRmXTh6zu2EUT7SpJok4y",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7985,
      "cache_read_input_tokens": 50308,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7985
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

_source line 44_

Items 1-3 are already in the main text:
- `fig:feature_trajectory` → atlas.tex line 101-106
- `tab:main_matrix` (3×3) → atlas.tex line 18-32
- `tab:cross_scale_auc` → generalization.tex line 139-152

These were never actually moved to the appendix (the appendix references them but doesn't contain copies). I'll proceed with items 4 and 5.

**Item 4**: Making 84.75% more prominent in the abstract.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "31c7bf83-b594-4222-826b-5359c119cdb2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LnRmXTh6zu2EUT7SpJok4y",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7985,
      "cache_read_input_tokens": 50308,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7985
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

_source line 45_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__edit_paper_section · `toolu_0196xmBtToDzhceh2BcdK2EC`</summary>

```json
{
  "project": "recursive_gen_depth_est",
  "section": "abstract",
  "old_text": "Cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75%, and extending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.",
  "new_text": "Notably, cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\\% accuracy, demonstrating that the depth signal is a property of the recursive process itself rather than of any individual generator.\nExtending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "1f1735c7-cb8a-4085-a08f-0ba7330ee57b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LnRmXTh6zu2EUT7SpJok4y",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7985,
      "cache_read_input_tokens": 50308,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7985
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

_source line 46 · 2026-05-16T11:42:10.301Z_

<details><summary>↩ Tool result · `toolu_0196xmBtToDzhceh2BcdK2EC`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"old_text not found in section (whitespace-normalized comparison)\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "1414f59a-3980-421e-be9b-ba1eb765758a",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"old_text not found in section (whitespace-normalized comparison)\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"old_text not found in section (whitespace-normalized comparison)\", \"metadata\": {}}"
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
The edit_paper_section tool didn't find the text. Let me try a shorter string to match.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "11c5a274-9f6f-4fce-93c4-f1282a0c5bb2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XizWkGPjU9DaWaN8erUZ2M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1779,
      "cache_read_input_tokens": 58293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1779
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

Let me try with a shorter match string.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "1b3e0895-05d0-488c-b57a-70a8f5af9de3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XizWkGPjU9DaWaN8erUZ2M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1779,
      "cache_read_input_tokens": 58293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1779
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__edit_paper_section · `toolu_01VtEm1rVWQEnrzyHkq7SNMi`</summary>

```json
{
  "project": "recursive_gen_depth_est",
  "section": "abstract",
  "old_text": "Cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75%,",
  "new_text": "Notably, cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\\% accuracy, demonstrating that the depth signal is a property of the recursive process rather than any individual generator. Extending"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "20420de8-180d-43dc-9c2f-1332b3a1f4a4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XizWkGPjU9DaWaN8erUZ2M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1779,
      "cache_read_input_tokens": 58293,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1779
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

_source line 50 · 2026-05-16T11:42:15.088Z_

<details><summary>↩ Tool result · `toolu_01VtEm1rVWQEnrzyHkq7SNMi`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"old_text not found in section (whitespace-normalized comparison)\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "a72b3a4f-4ced-434c-87ab-d4efdf170861",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"old_text not found in section (whitespace-normalized comparison)\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"old_text not found in section (whitespace-normalized comparison)\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 51_

<details><summary>Logged reasoning block</summary>

```text
The tool seems to have trouble matching the text. Let me try editing the file directly using the Edit tool instead.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "11771ee8-08b6-40ce-9980-da6e1a25aca1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LmAWctXGHfjqGkDGFjw2Mw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 296,
      "cache_read_input_tokens": 60072,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 296
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

_source line 52_

Let me edit the files directly instead.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "15ec9df6-518f-46ff-a9d4-39dad886c22b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LmAWctXGHfjqGkDGFjw2Mw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 296,
      "cache_read_input_tokens": 60072,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 296
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

_source line 53_

<details open><summary>🔧 Tool call — Edit · `toolu_01XseukAQdsUfZWGy4eeUegq`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex",
  "old_string": "Cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75%, and extending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.",
  "new_string": "Notably, cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\\% accuracy, demonstrating that the depth signal is a property of the recursive process itself rather than of any individual generator.\nExtending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "f3bc48dc-0ca3-4ccc-a8c8-597339e36a30",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LmAWctXGHfjqGkDGFjw2Mw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 296,
      "cache_read_input_tokens": 60072,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 296
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

_source line 54 · 2026-05-16T11:42:22.844Z_

<details><summary>↩ Tool result · reported error · `toolu_01XseukAQdsUfZWGy4eeUegq`</summary>

```text
&lt;tool_use_error>String to replace not found in file.
String: Cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75%, and extending to two 7B-scale generators yields 70.2\% accuracy with monotonic AUC decay ($\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.&lt;/tool_use_error>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "c39c97c2-2e65-4063-ad7d-5317a4ef8a9d",
  "tool_use_result": "Error: String to replace not found in file.\nString: Cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75%, and extending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects."
}
```

</details>

---

### Assistant

_source line 55_

<details><summary>Logged reasoning block</summary>

```text
Let me re-read the abstract file more carefully to see the exact text.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "aa55fea6-2c42-4e79-9e35-6973105773b6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015dpTpBntnqRHCPBcDDTgNQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 553,
      "cache_read_input_tokens": 60368,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 553
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

_source line 56_

<details open><summary>🔧 Tool call — Bash · `toolu_01U8vvtnvEHWY51iV2E51uqA`</summary>

```json
{
  "command": "cat -A /home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex | head -20",
  "description": "Show hidden characters in abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "45c9327e-f907-443e-8f6c-8deffdc8d570",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015dpTpBntnqRHCPBcDDTgNQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 553,
      "cache_read_input_tokens": 60368,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 553
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

_source line 57 · 2026-05-16T11:42:27.402Z_

<details><summary>↩ Tool result · `toolu_01U8vvtnvEHWY51iV2E51uqA`</summary>

```text
\begin{abstract}$
As large language models increasingly train on web text containing their own outputs, a recursive model$\to$data$\to$model loop arises---yet no method estimates how many such iterations a text has undergone.$
We formalize \emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.$
From each passage we extract a compact statistical fingerprint---19 candidate features dominated by perplexity tail statistics, with the top 5 achieving 97.6\% of full-set performance---computed against a fixed reference model (Pythia-1.4B).$
A Random Forest classifier achieves 70--85\% four-class accuracy (chance = 25\%; 58.8--82.6\% when excluding the near-perfectly separable d0 class; a zero-shot LLM baseline reaches only 36.2\%), with 90th-percentile perplexity and surprisal variance emerging as consistent depth markers across the studied $3 \times 3$ grid (top-2 importance in 9/9 and 8/9 cells, respectively).$
Our \emph{Depth Degradation Atlas} reveals that decoding strategy reshapes degradation trajectories rather than merely attenuating them, and we define the \emph{Effective Discriminable Depth} (EDD) metric, finding $\mathrm{EDD}_{0.75}{=}4$ for extended recursion chains.$
Cross-model transfer reaches 66.4\% and cross-strategy transfer 59.1\%; temperature sampling induces a d1/d2 AUC inversion that we decompose into a correctable scale component and a residual structural component.$
Cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\%, and extending to two 7B-scale generators yields 70.2\% accuracy with monotonic AUC decay ($\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.$
Applied to WikiText-103 (546 passages), all three model-specific classifiers achieve $\geq$98.5\% d0 accuracy despite $+$621\% domain shift in mean perplexity; on C4 web-crawl text, false positive rates range from 4.7\% to 22.4\%, concentrated in template content.$
\end{abstract}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "c031b4d1-a0b9-438f-8c07-dab92492aac0",
  "tool_use_result": {
    "stdout": "\\begin{abstract}$\nAs large language models increasingly train on web text containing their own outputs, a recursive model$\\to$data$\\to$model loop arises---yet no method estimates how many such iterations a text has undergone.$\nWe formalize \\emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.$\nFrom each passage we extract a compact statistical fingerprint---19 candidate features dominated by perplexity tail statistics, with the top 5 achieving 97.6\\% of full-set performance---computed against a fixed reference model (Pythia-1.4B).$\nA Random Forest classifier achieves 70--85\\% four-class accuracy (chance = 25\\%; 58.8--82.6\\% when excluding the near-perfectly separable d0 class; a zero-shot LLM baseline reaches only 36.2\\%), with 90th-percentile perplexity and surprisal variance emerging as consistent depth markers across the studied $3 \\times 3$ grid (top-2 importance in 9/9 and 8/9 cells, respectively).$\nOur \\emph{Depth Degradation Atlas} reveals that decoding strategy reshapes degradation trajectories rather than merely attenuating them, and we define the \\emph{Effective Discriminable Depth} (EDD) metric, finding $\\mathrm{EDD}_{0.75}{=}4$ for extended recursion chains.$\nCross-model transfer reaches 66.4\\% and cross-strategy transfer 59.1\\%; temperature sampling induces a d1/d2 AUC inversion that we decompose into a correctable scale component and a residual structural component.$\nCross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\\%, and extending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.$\nApplied to WikiText-103 (546 passages), all three model-specific classifiers achieve $\\geq$98.5\\% d0 accuracy despite $+$621\\% domain shift in mean perplexity; on C4 web-crawl text, false positive rates range from 4.7\\% to 22.4\\%, concentrated in template content.$\n\\end{abstract}",
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

_source line 58_

<details><summary>Logged reasoning block</summary>

```text
I see the issue - the file uses `---` (em dash) and I need to match exactly. Let me try again with the exact content from line 8.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "8161285b-cc67-49a0-ae20-c02b9550580a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UkA8qSfHFV8GygDGqAnmDU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 763,
      "cache_read_input_tokens": 60921,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 763
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

_source line 59_

<details open><summary>🔧 Tool call — Edit · `toolu_01YD2mz5kx9bP2qYdV42AXRB`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex",
  "old_string": "Cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\\%, and extending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.",
  "new_string": "Notably, cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\\% accuracy, demonstrating that the depth signal is a property of the recursive process itself rather than of any individual generator.\nExtending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "99a8bafb-9dd2-4e97-b27b-3bbd5b0a822a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UkA8qSfHFV8GygDGqAnmDU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 763,
      "cache_read_input_tokens": 60921,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 763
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

_source line 60 · 2026-05-16T11:42:33.853Z_

<details><summary>↩ Tool result · `toolu_01YD2mz5kx9bP2qYdV42AXRB`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "422d3834-8f79-4afb-9956-d9451d2e86ec",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/abstract.tex",
    "oldString": "Cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\\%, and extending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.",
    "newString": "Notably, cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\\% accuracy, demonstrating that the depth signal is a property of the recursive process itself rather than of any individual generator.\nExtending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.",
    "originalFile": "\\begin{abstract}\nAs large language models increasingly train on web text containing their own outputs, a recursive model$\\to$data$\\to$model loop arises---yet no method estimates how many such iterations a text has undergone.\nWe formalize \\emph{recursive generation depth estimation} as ordinal classification and construct a benchmark of 180K passages spanning 3 model families, 3 decoding strategies, and 4 generation depths.\nFrom each passage we extract a compact statistical fingerprint---19 candidate features dominated by perplexity tail statistics, with the top 5 achieving 97.6\\% of full-set performance---computed against a fixed reference model (Pythia-1.4B).\nA Random Forest classifier achieves 70--85\\% four-class accuracy (chance = 25\\%; 58.8--82.6\\% when excluding the near-perfectly separable d0 class; a zero-shot LLM baseline reaches only 36.2\\%), with 90th-percentile perplexity and surprisal variance emerging as consistent depth markers across the studied $3 \\times 3$ grid (top-2 importance in 9/9 and 8/9 cells, respectively).\nOur \\emph{Depth Degradation Atlas} reveals that decoding strategy reshapes degradation trajectories rather than merely attenuating them, and we define the \\emph{Effective Discriminable Depth} (EDD) metric, finding $\\mathrm{EDD}_{0.75}{=}4$ for extended recursion chains.\nCross-model transfer reaches 66.4\\% and cross-strategy transfer 59.1\\%; temperature sampling induces a d1/d2 AUC inversion that we decompose into a correctable scale component and a residual structural component.\nCross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\\%, and extending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.\nApplied to WikiText-103 (546 passages), all three model-specific classifiers achieve $\\geq$98.5\\% d0 accuracy despite $+$621\\% domain shift in mean perplexity; on C4 web-crawl text, false positive rates range from 4.7\\% to 22.4\\%, concentrated in template content.\n\\end{abstract}",
    "structuredPatch": [
      {
        "oldStart": 5,
        "oldLines": 6,
        "newStart": 5,
        "newLines": 7,
        "lines": [
          " A Random Forest classifier achieves 70--85\\% four-class accuracy (chance = 25\\%; 58.8--82.6\\% when excluding the near-perfectly separable d0 class; a zero-shot LLM baseline reaches only 36.2\\%), with 90th-percentile perplexity and surprisal variance emerging as consistent depth markers across the studied $3 \\times 3$ grid (top-2 importance in 9/9 and 8/9 cells, respectively).",
          " Our \\emph{Depth Degradation Atlas} reveals that decoding strategy reshapes degradation trajectories rather than merely attenuating them, and we define the \\emph{Effective Discriminable Depth} (EDD) metric, finding $\\mathrm{EDD}_{0.75}{=}4$ for extended recursion chains.",
          " Cross-model transfer reaches 66.4\\% and cross-strategy transfer 59.1\\%; temperature sampling induces a d1/d2 AUC inversion that we decompose into a correctable scale component and a residual structural component.",
          "-Cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\\%, and extending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.",
          "+Notably, cross-model recursive chains---where each depth is generated by a different architecture---achieve 84.75\\% accuracy, demonstrating that the depth signal is a property of the recursive process itself rather than of any individual generator.",
          "+Extending to two 7B-scale generators yields 70.2\\% accuracy with monotonic AUC decay ($\\mathrm{EDD}{=}4$), while a second 7B architecture exhibits $\\mathrm{EDD}{>}5$ with a non-monotonic trajectory possibly linked to instruction-tuning effects.",
          " Applied to WikiText-103 (546 passages), all three model-specific classifiers achieve $\\geq$98.5\\% d0 accuracy despite $+$621\\% domain shift in mean perplexity; on C4 web-crawl text, false positive rates range from 4.7\\% to 22.4\\%, concentrated in template content.",
          " \\end{abstract}",
          "\\ No newline at end of file"
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

_source line 61_

Now **Item 5**: Adding the lightweight inference claim to the contribution bullets.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "71445776-fb6a-4962-b351-4ea3db7f5a40",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018RWVqgZjP821DmaqnWyifY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 472,
      "cache_read_input_tokens": 61684,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 472
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

_source line 62_

<details open><summary>🔧 Tool call — Edit · `toolu_01FRvsFTBLFu3cPSy37apVoj`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex",
  "old_string": "    \\item \\textbf{Generalization across seven axes (four in main text; three in appendix).} We demonstrate robustness beyond the training grid: cross-model recursive chains (84.75\\%---depth signal accumulates across heterogeneous model boundaries), cross-scale to two 7B architectures (70.2\\% and 60.1\\%, with divergent AUC trajectories), cross-domain transfer to arXiv (74.1\\%), temperature robustness ($\\tau \\in [0.5, 0.9]$), and reference model independence ($\\Delta{=}4$\\,pp). End-to-end transformers achieve only ${\\sim}$59\\% (19pp below feature-based), confirming that perplexity tail features encode signal inaccessible to standard PLM representations.",
  "new_string": "    \\item \\textbf{Generalization across seven axes (four in main text; three in appendix).} We demonstrate robustness beyond the training grid: cross-model recursive chains (84.75\\%---depth signal accumulates across heterogeneous model boundaries), cross-scale to two 7B architectures (70.2\\% and 60.1\\%, with divergent AUC trajectories), cross-domain transfer to arXiv (74.1\\%), temperature robustness ($\\tau \\in [0.5, 0.9]$), and reference model independence ($\\Delta{=}4$\\,pp). End-to-end transformers achieve only ${\\sim}$59\\% (19pp below feature-based), confirming that perplexity tail features encode signal inaccessible to standard PLM representations---while requiring only 19 features and a Random Forest for millisecond-scale, GPU-free inference."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "b39db660-f9ec-4c42-b700-2f6d8a2687be",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018RWVqgZjP821DmaqnWyifY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 472,
      "cache_read_input_tokens": 61684,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 472
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

_source line 63 · 2026-05-16T11:42:46.288Z_

<details><summary>↩ Tool result · `toolu_01FRvsFTBLFu3cPSy37apVoj`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "d697da53-39d9-4cfa-a50d-3de135830e9e",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_2/projects/recursive_gen_depth_est/docs/paper/introduction.tex",
    "oldString": "    \\item \\textbf{Generalization across seven axes (four in main text; three in appendix).} We demonstrate robustness beyond the training grid: cross-model recursive chains (84.75\\%---depth signal accumulates across heterogeneous model boundaries), cross-scale to two 7B architectures (70.2\\% and 60.1\\%, with divergent AUC trajectories), cross-domain transfer to arXiv (74.1\\%), temperature robustness ($\\tau \\in [0.5, 0.9]$), and reference model independence ($\\Delta{=}4$\\,pp). End-to-end transformers achieve only ${\\sim}$59\\% (19pp below feature-based), confirming that perplexity tail features encode signal inaccessible to standard PLM representations.",
    "newString": "    \\item \\textbf{Generalization across seven axes (four in main text; three in appendix).} We demonstrate robustness beyond the training grid: cross-model recursive chains (84.75\\%---depth signal accumulates across heterogeneous model boundaries), cross-scale to two 7B architectures (70.2\\% and 60.1\\%, with divergent AUC trajectories), cross-domain transfer to arXiv (74.1\\%), temperature robustness ($\\tau \\in [0.5, 0.9]$), and reference model independence ($\\Delta{=}4$\\,pp). End-to-end transformers achieve only ${\\sim}$59\\% (19pp below feature-based), confirming that perplexity tail features encode signal inaccessible to standard PLM representations---while requiring only 19 features and a Random Forest for millisecond-scale, GPU-free inference.",
    "originalFile": "\\section{Introduction}\n\\label{sec:intro}\n\nThe text on which large language models are trained increasingly contains their own outputs.\nAs synthetic content proliferates across the web, a recursive loop emerges: models trained on web corpora ingest text generated by earlier models, and their outputs feed into the next generation's training data \\cite{shumailov2024_nature,alemohammad2024_mad}.\nThis model$\\to$data$\\to$model cycle is no longer hypothetical---it is already occurring in the wild---yet we lack the ability to determine how many recursive iterations a given text has undergone, a distinction that matters because first-generation synthetic text may be benign or even beneficial for training, while deeply recursive text drives the distributional collapse that degrades model quality \\cite{dohmatob2024_tale_of_tails}.\n\nExisting tools address adjacent but distinct problems.\nBinary detectors such as Binoculars \\cite{binoculars2024}, Fast-DetectGPT \\cite{fast_detectgpt2024}, and DivEye \\cite{diveye2026} classify text as human-written or machine-generated, collapsing all depths $d \\geq 1$ into a single category.\nWatermarking \\cite{kirchenbauer2023_watermark} requires proactive embedding and cannot be applied retroactively.\nThe model collapse literature \\cite{shumailov2024_nature,dohmatob2024_tale_of_tails} assumes depth is known a priori; \\citet{drayson2025_detection_prevents_collapse} filter synthetic data via binary detection without distinguishing depths.\nNo existing method estimates the ordinal recursive generation depth of a text passage from its content alone.\n\nOur key insight is that recursive generation leaves quantifiable statistical fingerprints in text, and these fingerprints are \\textbf{universal and scale-variant} across the three model families and three decoding strategies studied.\nSpecifically, perplexity tail statistics---the 90th-percentile perplexity (\\textsc{p90\\_ppl}) and surprisal variance (\\textsc{var\\_surprisal})---emerge as dominant depth indicators, ranking in the top two features by importance in 9/9 and 8/9 model--strategy configurations, respectively.\nSurprisingly, in one of two 7B models the AUC trajectory becomes non-monotonic, suggesting that instruction tuning may alter degradation dynamics rather than scale alone driving a qualitative shift.\n\nWe formalize recursive generation depth estimation as an ordinal classification task and introduce a lightweight pipeline to solve it.\nGiven a text passage, we compute a feature vector from reference-model perplexity statistics---19 candidates capturing distributional location, spread, tail behavior, and lexical diversity, though high multicollinearity concentrates the signal in ${\\approx}$4--5 effective dimensions (\\S\\ref{sec:atlas:features})---and classify it with a Random Forest into one of $K{+}1$ depth classes ($d{=}0$ for human text through $d{=}K$ for $K$-th generation text).\nTo systematically characterize how recursive generation reshapes these features, we construct the \\emph{Depth Degradation Atlas}: a $3 \\times 3$ grid of model families (Pythia-1.4B, OLMo-1B, GPT-2~XL) and decoding strategies (nucleus $p{=}0.95$, temperature $\\tau{=}0.9$, top-$k$ $k{=}50$), each spanning 4 generation depths, totaling 180K samples.\nThe atlas reveals strategy-dependent degradation trajectories---temperature sampling accelerates convergence toward a low-entropy attractor, while top-$k$ attenuates the depth signal---and we introduce the \\emph{Effective Discriminable Depth} (EDD) metric to quantify how far into the recursion chain adjacent depths remain distinguishable.\n\nOur contributions are:\n\n\\begin{itemize}\n    \\item \\textbf{Task formalization and benchmark.} We define recursive generation depth estimation as ordinal classification, introduce the EDD metric, and construct a 180K-sample benchmark spanning 3 model families $\\times$ 3 decoding strategies $\\times$ 4 depths.\n\n    \\item \\textbf{Depth Degradation Atlas.} A systematic $3 \\times 3$ characterization reveals that \\textsc{p90\\_ppl} and \\textsc{var\\_surprisal} are universal depth markers (top-2 in 9/9 and 8/9 cells), decoding strategy reshapes degradation trajectories qualitatively, and depth discrimination persists through $\\mathrm{EDD}_{0.75}{=}4$ recursive steps.\n\n    \\item \\textbf{Generalization across seven axes (four in main text; three in appendix).} We demonstrate robustness beyond the training grid: cross-model recursive chains (84.75\\%---depth signal accumulates across heterogeneous model boundaries), cross-scale to two 7B architectures (70.2\\% and 60.1\\%, with divergent AUC trajectories), cross-domain transfer to arXiv (74.1\\%), temperature robustness ($\\tau \\in [0.5, 0.9]$), and reference model independence ($\\Delta{=}4$\\,pp). End-to-end transformers achieve only ${\\sim}$59\\% (19pp below feature-based), confirming that perplexity tail features encode signal inaccessible to standard PLM representations.\n\\end{itemize}",
    "structuredPatch": [
      {
        "oldStart": 27,
        "oldLines": 5,
        "newStart": 27,
        "newLines": 5,
        "lines": [
          " ",
          "     \\item \\textbf{Depth Degradation Atlas.} A systematic $3 \\times 3$ characterization reveals that \\textsc{p90\\_ppl} and \\textsc{var\\_surprisal} are universal depth markers (top-2 in 9/9 and 8/9 cells), decoding strategy reshapes degradation trajectories qualitatively, and depth discrimination persists through $\\mathrm{EDD}_{0.75}{=}4$ recursive steps.",
          " ",
          "-    \\item \\textbf{Generalization across seven axes (four in main text; three in appendix).} We demonstrate robustness beyond the training grid: cross-model recursive chains (84.75\\%---depth signal accumulates across heterogeneous model boundaries), cross-scale to two 7B architectures (70.2\\% and 60.1\\%, with divergent AUC trajectories), cross-domain transfer to arXiv (74.1\\%), temperature robustness ($\\tau \\in [0.5, 0.9]$), and reference model independence ($\\Delta{=}4$\\,pp). End-to-end transformers achieve only ${\\sim}$59\\% (19pp below feature-based), confirming that perplexity tail features encode signal inaccessible to standard PLM representations.",
          "+    \\item \\textbf{Generalization across seven axes (four in main text; three in appendix).} We demonstrate robustness beyond the training grid: cross-model recursive chains (84.75\\%---depth signal accumulates across heterogeneous model boundaries), cross-scale to two 7B architectures (70.2\\% and 60.1\\%, with divergent AUC trajectories), cross-domain transfer to arXiv (74.1\\%), temperature robustness ($\\tau \\in [0.5, 0.9]$), and reference model independence ($\\Delta{=}4$\\,pp). End-to-end transformers achieve only ${\\sim}$59\\% (19pp below feature-based), confirming that perplexity tail features encode signal inaccessible to standard PLM representations---while requiring only 19 features and a Random Forest for millisecond-scale, GPU-free inference.",
          " \\end{itemize}",
          "\\ No newline at end of file"
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

_source line 64_

<details><summary>Logged reasoning block</summary>

```text
Good, items 4 and 5 are done. Now I need to think about what else can be done to expand the paper from ~6 pages to 7-7.5 pages. Since items 1-3 were already present, the paper is still at ~6 pages. The additions from items 4-5 are minimal (a few extra words/one sentence).

The user's original instruction says "如果还有空间（判断加回上述 3 项后是否约 7-7.5 页）" - meaning items 4-5 are optional and only needed if there's room. 

But the core issue remains: items 1-3 are already in the main text, so the paper hasn't grown much from the additions. I should let the user know that we're still around 6 pages and may need to explore other ways to reach the 7-7.5 page target.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "554a331c-e0e6-4c45-95a2-ee531f245df8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YQWjLZrR4GYRVtqZmRoHdv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 613,
      "cache_read_input_tokens": 62156,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 613
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

_source line 65_

Done with items 4-5. Here's the status:

**Items 1-3**: Already in the main text — no action needed:
- `fig:feature_trajectory` is in `atlas.tex` (§3.3 Monotonicity)
- `tab:main_matrix` (3×3) is in `atlas.tex` (§3.1 In-Distribution Performance)
- `tab:cross_scale_auc` is in `generalization.tex` (§4.4 Cross-Scale)

**Item 4** (done): Split the 84.75% cross-chain result into its own sentence with "Notably" emphasis and explicit interpretation ("...a property of the recursive process itself rather than of any individual generator").

**Item 5** (done): Appended "---while requiring only 19 features and a Random Forest for millisecond-scale, GPU-free inference" to contribution bullet 3.

Since items 1-3 were already in place, these two additions alone won't bring the paper from ~6 to 7-7.5 pages. The page gap likely comes from something else that was previously cut. Do you want me to identify what content might have been removed during the compression, or do you have specific sections you'd like expanded?

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "uuid": "3fff377b-b54b-424b-95b7-48f817e2c2fc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YQWjLZrR4GYRVtqZmRoHdv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 613,
      "cache_read_input_tokens": 62156,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 613
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

_source line 66_

Done with items 4-5. Here's the status:

**Items 1-3**: Already in the main text — no action needed:
- `fig:feature_trajectory` is in `atlas.tex` (§3.3 Monotonicity)
- `tab:main_matrix` (3×3) is in `atlas.tex` (§3.1 In-Distribution Performance)
- `tab:cross_scale_auc` is in `generalization.tex` (§4.4 Cross-Scale)

**Item 4** (done): Split the 84.75% cross-chain result into its own sentence with "Notably" emphasis and explicit interpretation ("...a property of the recursive process itself rather than of any individual generator").

**Item 5** (done): Appended "---while requiring only 19 features and a Random Forest for millisecond-scale, GPU-free inference" to contribution bullet 3.

Since items 1-3 were already in place, these two additions alone won't bring the paper from ~6 to 7-7.5 pages. The page gap likely comes from something else that was previously cut. Do you want me to identify what content might have been removed during the compression, or do you have specific sections you'd like expanded?

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 155581,
  "duration_api_ms": 156383,
  "num_turns": 22,
  "stop_reason": "end_turn",
  "session_id": "80ecd0ff-009f-4715-b90f-ee897ec7a4bc",
  "total_cost_usd": 0.8112815,
  "usage": {
    "input_tokens": 18,
    "cache_creation_input_tokens": 50928,
    "cache_read_input_tokens": 621869,
    "output_tokens": 7202,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 50928,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 548,
        "cache_read_input_tokens": 62156,
        "cache_creation_input_tokens": 613,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 613
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1777,
      "outputTokens": 26,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.0019069999999999998,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 18,
      "outputTokens": 7202,
      "cacheReadInputTokens": 621869,
      "cacheCreationInputTokens": 50928,
      "webSearchRequests": 0,
      "costUSD": 0.8093745,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "51d58503-594c-4c7f-a5c5-a82d1c1125ba"
}
```

</details>

---
