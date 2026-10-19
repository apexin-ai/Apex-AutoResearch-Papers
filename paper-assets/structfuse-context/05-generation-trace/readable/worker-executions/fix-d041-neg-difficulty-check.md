# fix d041 neg difficulty check

**StructFuse: Structure-Grounded Hard Negative Mining for Contrastive Code Context Retrieval** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 61
- **Recorded user turns:** 0
- **Tool calls:** 20
- **Original source:** `logs/workers/worker_fix_d041-neg-difficulty-check_20260515T021009.log`
- **Structured JSON:** [`0e37b2a2a063ea623365.json`](../../sessions/0e/0e37b2a2a063ea623365.json)

## Before a recorded user message

61 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context",
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
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
  "uuid": "563000bf-92da-4bd1-9c60-25429a93c029",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-5-projects-structfuse-context/memory/"
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
    "resetsAt": 1778825400,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "77e34e42-e4d1-4452-8a46-61550c077ff5",
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d"
}
```

---

### Assistant

_source line 4_

I'll start by reading the two files to check for description inconsistencies.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "09211eee-1d5c-4b38-9c5a-3eeed494712f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Prv7acDmEzoyXeFWGnVdSs",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11951,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11951
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_012fjZ8mji6bXnTMyUc6dNKF`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__save_project_file",
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
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "df5c148f-c927-4b56-af42-66c3fff862a3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Prv7acDmEzoyXeFWGnVdSs",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11951,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11951
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

_source line 6 · 2026-05-15T02:10:21.427Z_

<details><summary>↩ Tool result · `toolu_012fjZ8mji6bXnTMyUc6dNKF`</summary>

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
  "tool_name": "mcp__agent-ml-research__save_project_file"
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
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "56b9a516-26e1-4702-9498-0195138c7ac9",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__save_project_file"
    ],
    "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__save_project_file",
    "total_deferred_tools": 22
  }
}
```

</details>

---

### Assistant

_source line 7_

<details><summary>Logged reasoning block</summary>

```text
Let me read both files to check for inconsistencies.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "b791beeb-fdd5-4d15-9190-c4bd514750b3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PvAymjBiXvvUuNt8tERPgi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 716,
      "cache_read_input_tokens": 23398,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 716
      },
      "output_tokens": 37,
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

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01NbLVW22f3wthv8sy4MnQcN`</summary>

```json
{
  "project": "structfuse-context",
  "file": "discussion_v2.md",
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
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "ead5c88b-8af2-44b3-9e97-5ca98a064efb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PvAymjBiXvvUuNt8tERPgi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 716,
      "cache_read_input_tokens": 23398,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 716
      },
      "output_tokens": 37,
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

_source line 9 · 2026-05-15T02:10:25.568Z_

<details><summary>↩ Tool result · `toolu_01NbLVW22f3wthv8sy4MnQcN`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'discussion_v2.md'\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "25fdc72c-0b21-4b7b-8b68-b1df06e110b3",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'discussion_v2.md'\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'discussion_v2.md'\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 10_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01BTnqVWp35ygigdCPTgeXg1`</summary>

```json
{
  "project": "structfuse-context",
  "file": "related_work_v1.md",
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
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "8f86f866-c631-46db-af24-24a867460f49",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PvAymjBiXvvUuNt8tERPgi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 716,
      "cache_read_input_tokens": 23398,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 716
      },
      "output_tokens": 37,
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

_source line 11 · 2026-05-15T02:10:26.068Z_

<details><summary>↩ Tool result · `toolu_01BTnqVWp35ygigdCPTgeXg1`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'related_work_v1.md'\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "627c8d3b-8956-4c2e-a336-7c79a37abc03",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'related_work_v1.md'\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'related_work_v1.md'\", \"metadata\": {}}"
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
The files `discussion_v2.md` and `related_work_v1.md` aren't in the whitelist for `read_project_file`. They might be in the artifacts directory or somewhere else in the project. Let me check the artifacts directory and the project directory structure.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "288bc008-9092-43d8-a824-ebf374de16eb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01276FsJtjFCtRMAFLPnGKxj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 619,
      "cache_read_input_tokens": 24114,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 619
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

Those files aren't in the whitelist for `read_project_file`. Let me find them on disk.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "ab0bab91-cdb4-4d1d-b951-0fffe3e52fa0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01276FsJtjFCtRMAFLPnGKxj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 619,
      "cache_read_input_tokens": 24114,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 619
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

<details open><summary>🔧 Tool call — Glob · `toolu_01EzVAxbPZSWetUSGPuY2aph`</summary>

```json
{
  "pattern": "**/*discussion*",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "064be307-9c89-4b64-8306-88c26fc30652",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01276FsJtjFCtRMAFLPnGKxj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 619,
      "cache_read_input_tokens": 24114,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 619
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

_source line 15 · 2026-05-15T02:10:32.243Z_

<details><summary>↩ Tool result · `toolu_01EzVAxbPZSWetUSGPuY2aph`</summary>

```text
logs/workers/worker_writing_discussion_draft_20260514T101811.log
logs/workers/worker_writing_discussion_draft_20260514T101811_result.json
logs/workers/worker_fix_discussion_draft_typos_20260514T102249.log
logs/workers/worker_fix_discussion_draft_typos_20260514T102249_result.json
artifacts/_project/paper/discussion_v2.md
logs/workers/worker_writing_plan_017_discussion_20260514T170421.log
logs/workers/worker_writing_plan_017_discussion_20260514T170421_result.json
artifacts/paper_drafts/discussion_v2.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "5b13bf6a-3b52-4d20-87f6-6adecb910676",
  "tool_use_result": {
    "filenames": [
      "logs/workers/worker_writing_discussion_draft_20260514T101811.log",
      "logs/workers/worker_writing_discussion_draft_20260514T101811_result.json",
      "logs/workers/worker_fix_discussion_draft_typos_20260514T102249.log",
      "logs/workers/worker_fix_discussion_draft_typos_20260514T102249_result.json",
      "artifacts/_project/paper/discussion_v2.md",
      "logs/workers/worker_writing_plan_017_discussion_20260514T170421.log",
      "logs/workers/worker_writing_plan_017_discussion_20260514T170421_result.json",
      "artifacts/paper_drafts/discussion_v2.md"
    ],
    "durationMs": 15,
    "numFiles": 8,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 16_

<details open><summary>🔧 Tool call — Glob · `toolu_01FN9BDZ1Umf5nqYk7kthh9W`</summary>

```json
{
  "pattern": "**/*related_work*",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "f148db8a-c90e-49f6-9cf7-160ca7075a1d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01276FsJtjFCtRMAFLPnGKxj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 619,
      "cache_read_input_tokens": 24114,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 619
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

_source line 17 · 2026-05-15T02:10:32.518Z_

<details><summary>↩ Tool result · `toolu_01FN9BDZ1Umf5nqYk7kthh9W`</summary>

```text
logs/workers/worker_research_related_work_refs_20260512T143155.log
logs/workers/worker_research_related_work_refs_20260512T143155_result.json
artifacts/_project/report/related_work_expansion_report.md
artifacts/literature/related_work_expansion_report.md
artifacts/_project/paper/related_work_v1.md
artifacts/_project/paper/related_work_v1_dc54a3.md
artifacts/paper_drafts/related_work_v1.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "6a637cf5-57bc-452e-a560-b7377b06852d",
  "tool_use_result": {
    "filenames": [
      "logs/workers/worker_research_related_work_refs_20260512T143155.log",
      "logs/workers/worker_research_related_work_refs_20260512T143155_result.json",
      "artifacts/_project/report/related_work_expansion_report.md",
      "artifacts/literature/related_work_expansion_report.md",
      "artifacts/_project/paper/related_work_v1.md",
      "artifacts/_project/paper/related_work_v1_dc54a3.md",
      "artifacts/paper_drafts/related_work_v1.md"
    ],
    "durationMs": 13,
    "numFiles": 7,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 18_

<details open><summary>🔧 Tool call — Read · `toolu_0139HtUhxbBx8WSKuU8ia5bu`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/_project/paper/discussion_v2.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "6c447483-7d55-4230-aa34-74560df912f1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YNd6DA6jJtdcRFdHWu2aue",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 638,
      "cache_read_input_tokens": 24733,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 638
      },
      "output_tokens": 53,
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

_source line 19 · 2026-05-15T02:10:35.169Z_

<details><summary>↩ Tool result · `toolu_0139HtUhxbBx8WSKuU8ia5bu`</summary>

```text
1	# 5. Discussion
2	
3	## 5.1 Relationship to Inference-Time Graph Methods
4	
5	A growing body of work leverages code structure graphs at inference time to improve LLM-based software engineering.
6	CodexGraph (Liu et al., NAACL 2025) materializes a code property graph in a Neo4j database that LLM agents query via Cypher; RepoGraph (Ouyang et al., ICLR 2025) provides line-level code graph navigation as a plug-in for SE agents; LocAgent (Chen et al., ACL 2025) and RANGER (Shah et al., 2025) employ graph-guided multi-hop reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder (Liu et al., ASE 2024) and ARISE (Seddik & Fard, 2026) come closest to our work in incorporating data-flow information, but both are limited to intra-procedural scope.
7	
8	Table 5 summarizes the key dimensions of comparison. We highlight two axes along which StructFuse occupies a distinct position:
9	
10	**When structural information enters the pipeline.** Inference-time methods construct and query graphs per request, incurring latency proportional to graph complexity and—for agent-based systems—requiring multiple LLM calls per query. StructFuse amortizes all graph computation to training time: CodeQL extraction costs approximately 8.9 seconds per instance (~110 CPU-hours for 44K instances; Table 4), after which the trained encoder operates at standard embedding-lookup speed with zero graph overhead. For latency-sensitive, high-throughput retrieval scenarios, this cost model is substantially more favorable.
11	
12	**Depth of data-flow analysis.** Most inference-time graph methods use structural relations (call graphs, class hierarchies, import dependencies). GraphCoder incorporates control-flow and data-dependence graphs, and ARISE exposes statement-level def-use edges, but both operate within single procedures. StructFuse leverages CodeQL's bounded inter-procedural taint tracking (2-hop call-graph scope), capturing cross-function data-flow paths—e.g., a sanitizer that transforms data between a source and sink across call boundaries. This deeper semantic signal generates harder, more informative negatives than structural proximity alone.
13	
14	**Complementarity.** We emphasize that StructFuse and inference-time graph methods address different stages of the retrieval pipeline and are composable rather than competing. A StructFuse-trained encoder can serve as a first-stage retriever whose embeddings already encode data-flow semantics, reducing the search space for inference-time graph agents that perform targeted reranking. Conversely, systems like CodexGraph or LocAgent can refine StructFuse retrieval results through explicit graph navigation when maximum precision is required. The two paradigms are complementary: StructFuse internalizes general structural patterns during training, while inference-time methods provide case-specific structural reasoning during deployment.
15	
16	## 5.2 Representation Geometry as a Predictor of Strategy Effectiveness
17	
18	Our negative difficulty analysis (Section 4.4) reveals a practical insight: the pretrained encoder's representation geometry predicts whether structure-grounded negatives will provide benefit beyond embedding-distance mining.
19	
20	When the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This explains the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).
21	
22	When the representation space has healthy separation—as observed for StarCoder2-3B (pos\_sim = 0.799, random margin = 0.194, 2.6× larger than Qwen)—embedding-distance mining alone provides a sufficient difficulty gradient, and dataflow negatives do not yield additional improvement (+1.6pp for embedding vs. random, but −0.5pp for dataflow vs. random; Table 2). The larger margins mean the encoder can still extract useful contrastive signal from text-similarity-based negatives without supplementary structural guidance.
23	
24	This interaction between representation geometry and strategy effectiveness has a practical implication: practitioners can compute pos\_sim on a held-out sample with their pretrained encoder (a single forward pass, requiring no training) to predict whether structure-grounded negatives are worth the extraction cost. We observe that pos\_sim > 0.98 serves as an approximate threshold above which structural negatives provide conditional benefit, though we note this threshold is derived from two encoder observations and should be validated more broadly.
25	
26	## 5.3 Limitations
27	
28	We identify several limitations of the current study that contextualize our findings:
29	
30	**Encoder scope.** Our experiments use two decoder-only 3B-parameter encoders (Qwen2.5-Coder-3B and StarCoder2-3B). While these models differ meaningfully in pretraining corpus and representation geometry—enabling our interaction analysis—generalizing to encoder-only architectures (e.g., CodeBERT), larger scales, or non-code domains requires further investigation.
31	
32	**Single task.** We evaluate on code retrieval with contrastive training. Whether structure-grounded negatives similarly benefit other code understanding tasks (fault localization, code summarization, clone detection) remains an open question, though the underlying principle—that inter-procedural data-flow provides an orthogonal signal to text similarity—is task-agnostic.
33	
34	**Language and tooling dependency.** Our pipeline relies on CodeQL for inter-procedural data-flow extraction and currently supports Python repositories only. Extending to other languages requires language-specific CodeQL queries, and the dependency on a commercial static analysis tool may limit reproducibility. We note that the methodology generalizes to any tool capable of inter-procedural data-flow analysis (e.g., Joern, Soot).
35	
36	**Static mining.** Our negative mining is performed once before training and remains fixed throughout. Dynamic re-mining—where negatives are refreshed each epoch using the current encoder's embeddings—could yield progressively harder negatives as the model improves. We do not evaluate this variant in the current work and acknowledge the static-vs.-dynamic mining confound as a limitation. We plan to address this in future revisions.
37	
38	**Structural data coverage.** CodeQL successfully extracts data-flow information for 36% of instances across 123 repositories (93.9% repo coverage; Table 4). The remaining instances fall back to embedding-distance negatives. While our results demonstrate that even partial structural coverage yields measurable improvements, higher extraction success rates would likely amplify the benefit.
39	
40	## 5.4 Future Work
41	
42	We identify three directions that follow naturally from our findings, while noting that each requires empirical validation before strong claims can be made:
43	
44	**Hybrid retrieval pipelines.** Integrating a StructFuse-trained encoder as the first-stage retriever within inference-time graph systems (e.g., CodexGraph, RANGER) could combine the efficiency of embedding-based retrieval with the precision of runtime graph navigation. Evaluating such pipelines on end-to-end benchmarks like SWE-bench would quantify the practical value of this complementarity.
45	
46	**Representation-guided strategy selection.** Our observation that pos\_sim predicts strategy effectiveness suggests an automated protocol: given a new encoder, compute representation geometry statistics on a calibration set, then select the appropriate negative mining strategy without exhaustive ablation. Validating this protocol across a wider range of encoders and tasks is a natural next step.
47	
48	**Extension to dynamic and multi-lingual settings.** Adapting the pipeline to dynamically re-mine negatives during training, and extending CodeQL queries to languages beyond Python, would address two of our current limitations. For dynamic mining, the key design question is the re-mining frequency—epoch-level re-mining requires repeated CodeQL extraction, and the cost-benefit tradeoff depends on how quickly the encoder's embedding space evolves during training.
49	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "4e7d2dfc-b61a-414f-a009-59f7cd3a5336",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/_project/paper/discussion_v2.md",
      "content": "# 5. Discussion\n\n## 5.1 Relationship to Inference-Time Graph Methods\n\nA growing body of work leverages code structure graphs at inference time to improve LLM-based software engineering.\nCodexGraph (Liu et al., NAACL 2025) materializes a code property graph in a Neo4j database that LLM agents query via Cypher; RepoGraph (Ouyang et al., ICLR 2025) provides line-level code graph navigation as a plug-in for SE agents; LocAgent (Chen et al., ACL 2025) and RANGER (Shah et al., 2025) employ graph-guided multi-hop reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder (Liu et al., ASE 2024) and ARISE (Seddik & Fard, 2026) come closest to our work in incorporating data-flow information, but both are limited to intra-procedural scope.\n\nTable 5 summarizes the key dimensions of comparison. We highlight two axes along which StructFuse occupies a distinct position:\n\n**When structural information enters the pipeline.** Inference-time methods construct and query graphs per request, incurring latency proportional to graph complexity and—for agent-based systems—requiring multiple LLM calls per query. StructFuse amortizes all graph computation to training time: CodeQL extraction costs approximately 8.9 seconds per instance (~110 CPU-hours for 44K instances; Table 4), after which the trained encoder operates at standard embedding-lookup speed with zero graph overhead. For latency-sensitive, high-throughput retrieval scenarios, this cost model is substantially more favorable.\n\n**Depth of data-flow analysis.** Most inference-time graph methods use structural relations (call graphs, class hierarchies, import dependencies). GraphCoder incorporates control-flow and data-dependence graphs, and ARISE exposes statement-level def-use edges, but both operate within single procedures. StructFuse leverages CodeQL's bounded inter-procedural taint tracking (2-hop call-graph scope), capturing cross-function data-flow paths—e.g., a sanitizer that transforms data between a source and sink across call boundaries. This deeper semantic signal generates harder, more informative negatives than structural proximity alone.\n\n**Complementarity.** We emphasize that StructFuse and inference-time graph methods address different stages of the retrieval pipeline and are composable rather than competing. A StructFuse-trained encoder can serve as a first-stage retriever whose embeddings already encode data-flow semantics, reducing the search space for inference-time graph agents that perform targeted reranking. Conversely, systems like CodexGraph or LocAgent can refine StructFuse retrieval results through explicit graph navigation when maximum precision is required. The two paradigms are complementary: StructFuse internalizes general structural patterns during training, while inference-time methods provide case-specific structural reasoning during deployment.\n\n## 5.2 Representation Geometry as a Predictor of Strategy Effectiveness\n\nOur negative difficulty analysis (Section 4.4) reveals a practical insight: the pretrained encoder's representation geometry predicts whether structure-grounded negatives will provide benefit beyond embedding-distance mining.\n\nWhen the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This explains the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).\n\nWhen the representation space has healthy separation—as observed for StarCoder2-3B (pos\\_sim = 0.799, random margin = 0.194, 2.6× larger than Qwen)—embedding-distance mining alone provides a sufficient difficulty gradient, and dataflow negatives do not yield additional improvement (+1.6pp for embedding vs. random, but −0.5pp for dataflow vs. random; Table 2). The larger margins mean the encoder can still extract useful contrastive signal from text-similarity-based negatives without supplementary structural guidance.\n\nThis interaction between representation geometry and strategy effectiveness has a practical implication: practitioners can compute pos\\_sim on a held-out sample with their pretrained encoder (a single forward pass, requiring no training) to predict whether structure-grounded negatives are worth the extraction cost. We observe that pos\\_sim > 0.98 serves as an approximate threshold above which structural negatives provide conditional benefit, though we note this threshold is derived from two encoder observations and should be validated more broadly.\n\n## 5.3 Limitations\n\nWe identify several limitations of the current study that contextualize our findings:\n\n**Encoder scope.** Our experiments use two decoder-only 3B-parameter encoders (Qwen2.5-Coder-3B and StarCoder2-3B). While these models differ meaningfully in pretraining corpus and representation geometry—enabling our interaction analysis—generalizing to encoder-only architectures (e.g., CodeBERT), larger scales, or non-code domains requires further investigation.\n\n**Single task.** We evaluate on code retrieval with contrastive training. Whether structure-grounded negatives similarly benefit other code understanding tasks (fault localization, code summarization, clone detection) remains an open question, though the underlying principle—that inter-procedural data-flow provides an orthogonal signal to text similarity—is task-agnostic.\n\n**Language and tooling dependency.** Our pipeline relies on CodeQL for inter-procedural data-flow extraction and currently supports Python repositories only. Extending to other languages requires language-specific CodeQL queries, and the dependency on a commercial static analysis tool may limit reproducibility. We note that the methodology generalizes to any tool capable of inter-procedural data-flow analysis (e.g., Joern, Soot).\n\n**Static mining.** Our negative mining is performed once before training and remains fixed throughout. Dynamic re-mining—where negatives are refreshed each epoch using the current encoder's embeddings—could yield progressively harder negatives as the model improves. We do not evaluate this variant in the current work and acknowledge the static-vs.-dynamic mining confound as a limitation. We plan to address this in future revisions.\n\n**Structural data coverage.** CodeQL successfully extracts data-flow information for 36% of instances across 123 repositories (93.9% repo coverage; Table 4). The remaining instances fall back to embedding-distance negatives. While our results demonstrate that even partial structural coverage yields measurable improvements, higher extraction success rates would likely amplify the benefit.\n\n## 5.4 Future Work\n\nWe identify three directions that follow naturally from our findings, while noting that each requires empirical validation before strong claims can be made:\n\n**Hybrid retrieval pipelines.** Integrating a StructFuse-trained encoder as the first-stage retriever within inference-time graph systems (e.g., CodexGraph, RANGER) could combine the efficiency of embedding-based retrieval with the precision of runtime graph navigation. Evaluating such pipelines on end-to-end benchmarks like SWE-bench would quantify the practical value of this complementarity.\n\n**Representation-guided strategy selection.** Our observation that pos\\_sim predicts strategy effectiveness suggests an automated protocol: given a new encoder, compute representation geometry statistics on a calibration set, then select the appropriate negative mining strategy without exhaustive ablation. Validating this protocol across a wider range of encoders and tasks is a natural next step.\n\n**Extension to dynamic and multi-lingual settings.** Adapting the pipeline to dynamically re-mine negatives during training, and extending CodeQL queries to languages beyond Python, would address two of our current limitations. For dynamic mining, the key design question is the re-mining frequency—epoch-level re-mining requires repeated CodeQL extraction, and the cost-benefit tradeoff depends on how quickly the encoder's embedding space evolves during training.\n",
      "numLines": 49,
      "startLine": 1,
      "totalLines": 49
    }
  }
}
```

</details>

---

### Tool call

_source line 20_

<details open><summary>🔧 Tool call — Read · `toolu_01Dsymwkz297q52UPV4WF955`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/_project/paper/related_work_v1.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "2e2197df-02b0-42fb-8096-d61c63494053",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YNd6DA6jJtdcRFdHWu2aue",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 638,
      "cache_read_input_tokens": 24733,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 638
      },
      "output_tokens": 53,
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

_source line 21 · 2026-05-15T02:10:35.683Z_

<details><summary>↩ Tool result · `toolu_01Dsymwkz297q52UPV4WF955`</summary>

```text
1	# 2. Related Work
2	
3	## 2.1 Code Retrieval Methods
4	
5	Repo-level code retrieval aims to identify relevant files or code spans from large codebases given a bug report or issue description. Classical sparse retrieval via BM25 \cite{robertson2009bm25} remains a competitive baseline in this setting. The dense retrieval paradigm, pioneered by DPR \cite{karpukhin2020dpr} for open-domain question answering, has been increasingly adopted for code. SweRank \cite{reddy2025swerank} trains a retrieve-and-rerank pipeline for software issue localization, achieving state-of-the-art results on SWE-Bench-Lite and LocBench through text-based retrieval. SWE-Fixer \cite{xie2025swefixer} combines BM25 with a learned retriever in a coarse-to-fine file retrieval pipeline, demonstrating that sparse and dense retrieval are complementary. Both systems, however, treat code files as flat text and do not exploit structural relationships between files during training.
6	
7	A parallel line of work leverages code structure graphs at inference time to guide code navigation. LocAgent \cite{chen2025locagent} parses codebases into directed heterogeneous graphs and employs LLM agents for multi-hop graph reasoning during fault localization. RANGER \cite{shah2025ranger} constructs repository knowledge graphs with variable-level nodes and applies MCTS-guided graph exploration for retrieval. CodexGraph \cite{liu2025codexgraph} indexes codebases into graph databases queried via Cypher, while RepoGraph \cite{ouyang2025repograph} provides line-level code graph navigation as a plug-in module for software engineering agents. GraphCoder \cite{liu2024graphcoder} incorporates control-flow and data-dependence edges into code context graphs for coarse-to-fine retrieval, and ARISE \cite{seddik2026arise} exposes statement-level def-use edges for agentic fault localization—though both are limited to intra-procedural scope. These methods demonstrate the value of structural information for code retrieval, yet they incur per-query computational costs and, for agent-based systems, require multiple LLM calls per retrieval step.
8	
9	Critically, all graph-guided methods apply structural information exclusively at inference time; the underlying retrieval encoder is trained without structural signal. The encoder's embedding space is therefore optimized solely on textual similarity, potentially conflating lexically similar but structurally unrelated code. Our work addresses this gap by incorporating inter-procedural data-flow information into the training process through structure-grounded hard negative mining.
10	
11	## 2.2 Contrastive Learning for Code
12	
13	Contrastive learning has proven effective for learning code representations that capture functional semantics beyond surface-level patterns. ContraCode \cite{jain2021contracode} applies compiler-driven transformations to generate functionally equivalent program variants as positive pairs, training the encoder to be invariant to syntactic variation. CodeRetriever \cite{li2022coderetriever} combines unimodal (code-code) and bimodal (code-text) contrastive objectives, achieving strong results across eleven code search benchmarks. \citet{ding2022programcontrasts} leverage program structure and functional attributes to construct contrastive pairs for learning code (dis)similarity representations.
14	
15	Complementary efforts have explored encoding structural information directly into code representations. code2vec \cite{alon2019code2vec} demonstrates that AST path-based representations capture meaningful program properties at scale. GraphCodeBERT \cite{guo2021graphcodebert} incorporates data-flow edges into pre-training, showing that data-flow information improves downstream code understanding tasks. However, GraphCodeBERT uses data-flow as an auxiliary pre-training signal over individual functions, whereas our work uses inter-procedural data-flow to construct hard negatives for contrastive fine-tuning—a fundamentally different application of structural information that operates at the repository level rather than the function level.
16	
17	Despite the progress in contrastive code representation learning, these methods share a common dependency on negative sampling strategy yet few systematically investigate which negatives yield the best representations for code retrieval. Most approaches rely on in-batch negatives \cite{karpukhin2020dpr} or random sampling, leaving the interaction between negative selection strategy and encoder representation geometry unexplored. Our work addresses this gap with a controlled comparison across negative mining strategies on modern decoder-only code encoders.
18	
19	## 2.3 Hard Negative Mining
20	
21	Hard negative mining—selecting negative examples that are challenging for the current model—is well established for improving contrastive learning. In visual representation learning, SimCLR \cite{chen2020simclr} demonstrates the importance of large batch sizes and hard negatives for learning discriminative features. In dense text retrieval, DPR \cite{karpukhin2020dpr} shows that BM25-retrieved passages serve as effective hard negatives beyond in-batch sampling. ANCE \cite{xiong2021ance} advances this by mining negatives from the model's own embedding space via approximate nearest neighbor search, achieving substantial gains over static BM25 negatives. Curriculum-based approaches such as CL-DRD \cite{zeng2022cldrd} progressively increase negative difficulty during training through knowledge distillation.
22	
23	In the code domain, hard negative mining has received comparatively less systematic attention. CoCoHaNeRe \cite{fan2025cocohanere} proposes a differentiable hard negative mechanism for code search contrastive learning, arguing that gradient-based methods yield faster and more effective training than non-differentiable embedding-based negative selection. While CoCoHaNeRe demonstrates the advantages of its gradient-based approach within its experimental setting, it does not evaluate simple static embedding-distance mining—the strategy of selecting hard negatives by nearest-neighbor lookup in the encoder's frozen embedding space—in structural code retrieval settings.
24	
25	Our work provides a systematic comparison that challenges the assumption that expensive gradient-based hard negative methods are necessary for effective code retrieval. We show that simple static embedding-distance mining consistently improves retrieval performance across two decoder-only encoders with distinct representation geometries, without requiring differentiable negative generation mechanisms. Furthermore, we introduce structure-grounded negatives derived from inter-procedural data-flow analysis and show that the relative effectiveness of mining strategies depends on the encoder's pretrained representation geometry—an interaction that existing work does not examine. Together, these findings address a gap at the intersection of graph-guided code methods, which exploit structure only at inference time, and contrastive training methods, which have not systematically leveraged structural signals for negative selection.
26	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "c6c46507-506f-4970-9050-7813c53aa925",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/_project/paper/related_work_v1.md",
      "content": "# 2. Related Work\n\n## 2.1 Code Retrieval Methods\n\nRepo-level code retrieval aims to identify relevant files or code spans from large codebases given a bug report or issue description. Classical sparse retrieval via BM25 \\cite{robertson2009bm25} remains a competitive baseline in this setting. The dense retrieval paradigm, pioneered by DPR \\cite{karpukhin2020dpr} for open-domain question answering, has been increasingly adopted for code. SweRank \\cite{reddy2025swerank} trains a retrieve-and-rerank pipeline for software issue localization, achieving state-of-the-art results on SWE-Bench-Lite and LocBench through text-based retrieval. SWE-Fixer \\cite{xie2025swefixer} combines BM25 with a learned retriever in a coarse-to-fine file retrieval pipeline, demonstrating that sparse and dense retrieval are complementary. Both systems, however, treat code files as flat text and do not exploit structural relationships between files during training.\n\nA parallel line of work leverages code structure graphs at inference time to guide code navigation. LocAgent \\cite{chen2025locagent} parses codebases into directed heterogeneous graphs and employs LLM agents for multi-hop graph reasoning during fault localization. RANGER \\cite{shah2025ranger} constructs repository knowledge graphs with variable-level nodes and applies MCTS-guided graph exploration for retrieval. CodexGraph \\cite{liu2025codexgraph} indexes codebases into graph databases queried via Cypher, while RepoGraph \\cite{ouyang2025repograph} provides line-level code graph navigation as a plug-in module for software engineering agents. GraphCoder \\cite{liu2024graphcoder} incorporates control-flow and data-dependence edges into code context graphs for coarse-to-fine retrieval, and ARISE \\cite{seddik2026arise} exposes statement-level def-use edges for agentic fault localization—though both are limited to intra-procedural scope. These methods demonstrate the value of structural information for code retrieval, yet they incur per-query computational costs and, for agent-based systems, require multiple LLM calls per retrieval step.\n\nCritically, all graph-guided methods apply structural information exclusively at inference time; the underlying retrieval encoder is trained without structural signal. The encoder's embedding space is therefore optimized solely on textual similarity, potentially conflating lexically similar but structurally unrelated code. Our work addresses this gap by incorporating inter-procedural data-flow information into the training process through structure-grounded hard negative mining.\n\n## 2.2 Contrastive Learning for Code\n\nContrastive learning has proven effective for learning code representations that capture functional semantics beyond surface-level patterns. ContraCode \\cite{jain2021contracode} applies compiler-driven transformations to generate functionally equivalent program variants as positive pairs, training the encoder to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal (code-code) and bimodal (code-text) contrastive objectives, achieving strong results across eleven code search benchmarks. \\citet{ding2022programcontrasts} leverage program structure and functional attributes to construct contrastive pairs for learning code (dis)similarity representations.\n\nComplementary efforts have explored encoding structural information directly into code representations. code2vec \\cite{alon2019code2vec} demonstrates that AST path-based representations capture meaningful program properties at scale. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pre-training, showing that data-flow information improves downstream code understanding tasks. However, GraphCodeBERT uses data-flow as an auxiliary pre-training signal over individual functions, whereas our work uses inter-procedural data-flow to construct hard negatives for contrastive fine-tuning—a fundamentally different application of structural information that operates at the repository level rather than the function level.\n\nDespite the progress in contrastive code representation learning, these methods share a common dependency on negative sampling strategy yet few systematically investigate which negatives yield the best representations for code retrieval. Most approaches rely on in-batch negatives \\cite{karpukhin2020dpr} or random sampling, leaving the interaction between negative selection strategy and encoder representation geometry unexplored. Our work addresses this gap with a controlled comparison across negative mining strategies on modern decoder-only code encoders.\n\n## 2.3 Hard Negative Mining\n\nHard negative mining—selecting negative examples that are challenging for the current model—is well established for improving contrastive learning. In visual representation learning, SimCLR \\cite{chen2020simclr} demonstrates the importance of large batch sizes and hard negatives for learning discriminative features. In dense text retrieval, DPR \\cite{karpukhin2020dpr} shows that BM25-retrieved passages serve as effective hard negatives beyond in-batch sampling. ANCE \\cite{xiong2021ance} advances this by mining negatives from the model's own embedding space via approximate nearest neighbor search, achieving substantial gains over static BM25 negatives. Curriculum-based approaches such as CL-DRD \\cite{zeng2022cldrd} progressively increase negative difficulty during training through knowledge distillation.\n\nIn the code domain, hard negative mining has received comparatively less systematic attention. CoCoHaNeRe \\cite{fan2025cocohanere} proposes a differentiable hard negative mechanism for code search contrastive learning, arguing that gradient-based methods yield faster and more effective training than non-differentiable embedding-based negative selection. While CoCoHaNeRe demonstrates the advantages of its gradient-based approach within its experimental setting, it does not evaluate simple static embedding-distance mining—the strategy of selecting hard negatives by nearest-neighbor lookup in the encoder's frozen embedding space—in structural code retrieval settings.\n\nOur work provides a systematic comparison that challenges the assumption that expensive gradient-based hard negative methods are necessary for effective code retrieval. We show that simple static embedding-distance mining consistently improves retrieval performance across two decoder-only encoders with distinct representation geometries, without requiring differentiable negative generation mechanisms. Furthermore, we introduce structure-grounded negatives derived from inter-procedural data-flow analysis and show that the relative effectiveness of mining strategies depends on the encoder's pretrained representation geometry—an interaction that existing work does not examine. Together, these findings address a gap at the intersection of graph-guided code methods, which exploit structure only at inference time, and contrastive training methods, which have not systematically leveraged structural signals for negative selection.\n",
      "numLines": 26,
      "startLine": 1,
      "totalLines": 26
    }
  }
}
```

</details>

---

### Assistant

_source line 22_

<details><summary>Logged reasoning block</summary>

```text
Let me analyze both files for any description inconsistencies regarding the dataflow-aware negative mining strategy.

**Discussion v2:**

In §5.2, the text says:
- "the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection)" — this is fine, it describes the concept.
- "dataflow-aware negatives" — this is mentioned but doesn't specify the selection method explicitly.
- The text doesn't explicitly say dataflow-aware uses embedding similarity for selection, which is good.

But let me look more carefully...

In §5.2:
- "embedding-distance mining alone provides a sufficient difficulty gradient" — this refers to the embedding-distance strategy, separate from dataflow-aware. Good.


- "dataflow negatives do not yield additional improvement" — this is about the dataflow strategy. OK.

I don't see an explicit incorrect statement saying dataflow-aware uses embedding similarity for selection. The text seems to correctly distinguish between the strategies. But let me check for any implicit conflation.

In §5.2:
> "all text-similarity-based negatives are clustered near the positive"

This seems to group all non-structural negatives as "text-similarity-based." The dataflow-aware strategy is not text-similarity-based, so this seems fine — it's contrasting random and embedding strategies with the dataflow one. Let me re-read more carefully to see if there's any subtle mischaracterization I'm missing.

The passage describes how representation saturation compresses margins between positive and negative pairs, making text-similarity-based negatives cluster near positives. It identifies the need for negatives from an orthogonal signal—structural disconnection—but doesn't explicitly explain how dataflow-aware negatives are selected. The framing is vague about the mechanism but not technically incorrect.

Looking at the next thinking, it contrasts embedding-distance mining with dataflow negatives, suggesting the latter doesn't provide additional improvement beyond what embedding-distance alone achieves. This seems to contradict the earlier emphasis on needing structurally-grounded negatives in saturated regimes. The tension here is whether dataflow negatives are actually necessary or just redundant with embedding-distance mining. I need to check whether §5.2 clearly distinguishes between the selection method (how negatives are chosen: random, embedding-distance, or dataflow-aware) and the evaluation metric (how difficulty is measured using pretrained encoder cosine similarity). The section currently describes metrics like mean positive-pair similarity and margin between pairs without explicitly labeling these as evaluation metrics rather than selection criteria, so I should clarify that distinction. The key issue is that §5.2 conflates the evaluation metric (pretrained cosine similarity) with the selection methods themselves—especially problematic for embedding-distance negatives where cosine similarity does double duty. I need to add a clarifying statement upfront that all margin measurements use pretrained encoder cosine similarity as a uniform evaluation metric, separate from how each strategy actually selects its negatives, and then specify that dataflow-aware uses BM25 ranking within structural constraints rather than embedding distance.

I'm also noticing there are two copies of the discussion file in different directories, and since `save_project_file` doesn't whitelist discussion_v2.md, I'll need to use the Write tool directly to save the revisions.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "78837d18-6f91-412f-8345-ba18678e72b4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014aUjnTXohygoDPKzH7B8Qq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3788,
      "cache_read_input_tokens": 25371,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3788
      },
      "output_tokens": 11,
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

_source line 23_

Let me check if there are dedicated paper section editing tools, since `save_project_file` doesn't allow writing paper sections directly.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "838bdb22-fe22-4222-b1ec-936aebb47eec",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014aUjnTXohygoDPKzH7B8Qq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3788,
      "cache_read_input_tokens": 25371,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3788
      },
      "output_tokens": 11,
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

_source line 24_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01H3qC8os5KSK83f6eA1A79P`</summary>

```json
{
  "query": "edit_paper_section write_paper_section",
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
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "669c7eff-d92a-4615-8b4b-6528b60a201e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014aUjnTXohygoDPKzH7B8Qq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3788,
      "cache_read_input_tokens": 25371,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3788
      },
      "output_tokens": 11,
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

_source line 25 · 2026-05-15T02:11:23.820Z_

<details><summary>↩ Tool result · `toolu_01H3qC8os5KSK83f6eA1A79P`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__save_project_file"
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
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "574003ee-9b6a-4e94-82fc-54c815fe8cb8",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__save_project_file"
    ],
    "query": "edit_paper_section write_paper_section",
    "total_deferred_tools": 22
  }
}
```

</details>

---

### Tool call

_source line 26_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01S9wStvB9MkgwsGPACdd94c`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__edit_paper_section,mcp__agent-ml-research__write_paper_section",
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
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "38b9a809-ec41-45ad-be51-2a4b1cb59daa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LyrE6Ufw5qVEwxZ5LJQBLW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2310,
      "cache_read_input_tokens": 29159,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2310
      },
      "output_tokens": 42,
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

_source line 27 · 2026-05-15T02:11:28.807Z_

<details><summary>↩ Tool result · `toolu_01S9wStvB9MkgwsGPACdd94c`</summary>

```text
No matching deferred tools found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "2df280d6-17ef-4718-bc15-5359c5b0fdc7",
  "tool_use_result": {
    "matches": [],
    "query": "select:mcp__agent-ml-research__edit_paper_section,mcp__agent-ml-research__write_paper_section",
    "total_deferred_tools": 22
  }
}
```

</details>

---

### Assistant

_source line 28_

<details><summary>Logged reasoning block</summary>

```text
The dedicated paper section tools aren't available as deferred tools. Let me search more broadly.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "4ac16afe-b3c5-4fac-a469-aad85af118a6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PNuxXfXSeqsT5DaLA65ret",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 123,
      "cache_read_input_tokens": 31469,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 123
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

_source line 29_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01VRZexCDF5Jj9wKkyNsZPRn`</summary>

```json
{
  "query": "paper section edit write",
  "max_results": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "12fc8832-5f3d-47b6-8a13-9046e80a8f80",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PNuxXfXSeqsT5DaLA65ret",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 123,
      "cache_read_input_tokens": 31469,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 123
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

_source line 30 · 2026-05-15T02:11:32.153Z_

<details><summary>↩ Tool result · `toolu_01VRZexCDF5Jj9wKkyNsZPRn`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "NotebookEdit"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "TodoWrite"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__save_project_file"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "Monitor"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "WebSearch"
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
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "9df7ace3-cbab-4448-9621-06ef73f20a10",
  "tool_use_result": {
    "matches": [
      "NotebookEdit",
      "TodoWrite",
      "mcp__agent-ml-research__save_project_file",
      "Monitor",
      "WebSearch"
    ],
    "query": "paper section edit write",
    "total_deferred_tools": 22
  }
}
```

</details>

---

### Assistant

_source line 31_

<details><summary>Logged reasoning block</summary>

```text
The dedicated `write_paper_section` / `edit_paper_section` tools aren't available as deferred tools. I'll need to write the files directly using the `Write` tool to the artifacts paths.

Let me also check if there's a second copy in `artifacts/paper_drafts/` that might differ.

Now let me analyze the content I've already read:

**discussion_v2.md analysis:**

§5.2 "Representation Geometry as a Predictor of Strategy Effectiveness":

Key passages to check:
1. "the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017)" — "embedding margin" refers to the margin of negatives selected by embedding-distance mining. 

The evaluation metric here is cosine similarity applied to those negatives, which could be clearer but isn't technically incorrect.

2. "all text-similarity-based negatives are clustered near the positive" — This groups random and embedding-distance as "text-similarity-based," while correctly excluding dataflow-aware since it operates on a different signal.

3. "the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection)" — The signal is correctly identified as structural, though the mechanism (BM25 within structural filtering) isn't explicitly stated.

4. "embedding-distance mining alone provides a sufficient difficulty gradient, and dataflow negatives do not yield additional improvement" — This accurately distinguishes embedding-distance mining from other approaches.

The real issue is that the section conflates the selection method with the evaluation metric—it doesn't clearly state that cosine similarity values are how we measure difficulty, not how we select negatives. There's also no mention of BM25 as the actual selection mechanism for dataflow-aware negatives, and "embedding margin" could mislead readers into thinking embedding similarity is used for selection across all strategies. I need to add a clarifying sentence to §5.2 that separates these concepts.

Looking at the related work, it mentions BM25-retrieved passages as hard negatives in DPR but doesn't connect that to StructFuse, and it references structure-grounded negatives from inter-procedural data-flow analysis without fully explaining the distinction.

The key changes I should make: clarify that cosine similarity is the evaluation metric applied uniformly across all strategies, explain that the three strategies differ in their selection methods (random sampling, embedding-distance ranking, and dataflow-aware with BM25 ranking within CodeQL-identified structurally connected files), and make explicit that cosine similarity serves double duty as both a selection criterion for embedding-distance mining and the evaluation metric for all approaches.

I'll add this clarification right at the start of §5.2, but I need to keep it concise—the current draft is too wordy. The core insight is that the selection method and evaluation metric are independent, so I should tighten the language around that distinction. I'm checking whether the files have any existing markers for Claim 2 wording fixes—I don't see any in either version, so I need to be careful not to inadvertently revert any changes that might have been made. Let me also verify that the paper_drafts copies match the current versions.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "36087cce-58d8-48c9-8a65-7411281e226c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PsFEoFiHQBVe8HHoTBYGFL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 5373,
      "cache_read_input_tokens": 31592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5373
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

_source line 32_

Let me also check the `paper_drafts` copies to see if they differ.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "f23f1b5b-9612-4e12-a9e6-2e620d7c253e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PsFEoFiHQBVe8HHoTBYGFL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 5373,
      "cache_read_input_tokens": 31592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5373
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

_source line 33_

<details open><summary>🔧 Tool call — Bash · `toolu_012mbtczk2CKSnfSui3XDzsi`</summary>

```json
{
  "command": "diff /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/_project/paper/discussion_v2.md /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/discussion_v2.md 2>&1 | head -20",
  "description": "Compare two copies of discussion_v2.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "61554550-e2e9-42ec-b35d-b3dda67798f6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PsFEoFiHQBVe8HHoTBYGFL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 5373,
      "cache_read_input_tokens": 31592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5373
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

_source line 34 · 2026-05-15T02:12:16.681Z_

<details><summary>↩ Tool result · `toolu_012mbtczk2CKSnfSui3XDzsi`</summary>

```text
16c16
< ## 5.2 Representation Geometry as a Predictor of Strategy Effectiveness
---
> ## 5.2 Representation Geometry and Strategy Effectiveness: An Exploratory Analysis
18c18
< Our negative difficulty analysis (Section 4.4) reveals a practical insight: the pretrained encoder's representation geometry predicts whether structure-grounded negatives will provide benefit beyond embedding-distance mining.
---
> We present the following analysis as an exploratory observation derived from two encoders, not a validated mechanism.
20c20,22
< When the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This explains the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).
---
> Our negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining.
> 
> When the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This is consistent with the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).
46c48
< **Representation-guided strategy selection.** Our observation that pos\_sim predicts strategy effectiveness suggests an automated protocol: given a new encoder, compute representation geometry statistics on a calibration set, then select the appropriate negative mining strategy without exhaustive ablation. Validating this protocol across a wider range of encoders and tasks is a natural next step.
---
> **Representation-guided strategy selection.** Our observation that pos\_sim appears to correlate with strategy effectiveness suggests an automated protocol: given a new encoder, compute representation geometry statistics on a calibration set, then select the appropriate negative mining strategy without exhaustive ablation. Validating this protocol across a wider range of encoders and tasks is a natural next step.
48a51,52
>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "91a70906-ed31-4893-8c19-a7582ca90cc3",
  "tool_use_result": {
    "stdout": "16c16\n< ## 5.2 Representation Geometry as a Predictor of Strategy Effectiveness\n---\n> ## 5.2 Representation Geometry and Strategy Effectiveness: An Exploratory Analysis\n18c18\n< Our negative difficulty analysis (Section 4.4) reveals a practical insight: the pretrained encoder's representation geometry predicts whether structure-grounded negatives will provide benefit beyond embedding-distance mining.\n---\n> We present the following analysis as an exploratory observation derived from two encoders, not a validated mechanism.\n20c20,22\n< When the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This explains the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).\n---\n> Our negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining.\n> \n> When the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This is consistent with the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).\n46c48\n< **Representation-guided strategy selection.** Our observation that pos\\_sim predicts strategy effectiveness suggests an automated protocol: given a new encoder, compute representation geometry statistics on a calibration set, then select the appropriate negative mining strategy without exhaustive ablation. Validating this protocol across a wider range of encoders and tasks is a natural next step.\n---\n> **Representation-guided strategy selection.** Our observation that pos\\_sim appears to correlate with strategy effectiveness suggests an automated protocol: given a new encoder, compute representation geometry statistics on a calibration set, then select the appropriate negative mining strategy without exhaustive ablation. Validating this protocol across a wider range of encoders and tasks is a natural next step.\n48a51,52\n>",
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

_source line 35_

<details open><summary>🔧 Tool call — Bash · `toolu_01SenaDNS9izBCfxoFzLuDp5`</summary>

```json
{
  "command": "diff /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/_project/paper/related_work_v1.md /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md 2>&1 | head -20",
  "description": "Compare two copies of related_work_v1.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "d68df9c3-c366-40e6-8429-7172402594ea",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PsFEoFiHQBVe8HHoTBYGFL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 5373,
      "cache_read_input_tokens": 31592,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5373
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

_source line 36 · 2026-05-15T02:12:17.761Z_

<details><summary>↩ Tool result · `toolu_01SenaDNS9izBCfxoFzLuDp5`</summary>

```text
9c9
< Critically, all graph-guided methods apply structural information exclusively at inference time; the underlying retrieval encoder is trained without structural signal. The encoder's embedding space is therefore optimized solely on textual similarity, potentially conflating lexically similar but structurally unrelated code. Our work addresses this gap by incorporating inter-procedural data-flow information into the training process through structure-grounded hard negative mining.
---
> Critically, these graph-guided methods apply structural information exclusively at inference time; the underlying retrieval encoder is trained without structural signal. The encoder's embedding space is therefore optimized solely on textual similarity, potentially conflating lexically similar but structurally unrelated code. Our work addresses this gap by incorporating inter-procedural data-flow information into the training process through structure-grounded hard negative mining.
13c13
< Contrastive learning has proven effective for learning code representations that capture functional semantics beyond surface-level patterns. ContraCode \cite{jain2021contracode} applies compiler-driven transformations to generate functionally equivalent program variants as positive pairs, training the encoder to be invariant to syntactic variation. CodeRetriever \cite{li2022coderetriever} combines unimodal (code-code) and bimodal (code-text) contrastive objectives, achieving strong results across eleven code search benchmarks. \citet{ding2022programcontrasts} leverage program structure and functional attributes to construct contrastive pairs for learning code (dis)similarity representations.
---
> Building on the success of Sentence-BERT \cite{reimers2019sentencebert} in learning dense sentence representations via siamese contrastive objectives, contrastive learning has proven effective for learning code representations that capture functional semantics beyond surface-level patterns. ContraCode \cite{jain2021contracode} applies compiler-driven transformations to generate functionally equivalent program variants as positive pairs, training the encoder to be invariant to syntactic variation. CodeRetriever \cite{li2022coderetriever} combines unimodal (code-code) and bimodal (code-text) contrastive objectives, achieving strong results across eleven code search benchmarks. \citet{ding2022programcontrasts} leverage program structure and functional attributes to construct contrastive pairs for learning code (dis)similarity representations.
25c25,27
< Our work provides a systematic comparison that challenges the assumption that expensive gradient-based hard negative methods are necessary for effective code retrieval. We show that simple static embedding-distance mining consistently improves retrieval performance across two decoder-only encoders with distinct representation geometries, without requiring differentiable negative generation mechanisms. Furthermore, we introduce structure-grounded negatives derived from inter-procedural data-flow analysis and show that the relative effectiveness of mining strategies depends on the encoder's pretrained representation geometry—an interaction that existing work does not examine. Together, these findings address a gap at the intersection of graph-guided code methods, which exploit structure only at inference time, and contrastive training methods, which have not systematically leveraged structural signals for negative selection.
---
> Our work provides a systematic comparison that challenges the assumption that expensive gradient-based hard negative methods are necessary for effective code retrieval. We show that simple static embedding-distance mining consistently improves (pilot evidence; pending M2 full confirmation) retrieval performance across two decoder-only encoders with distinct representation geometries, without requiring differentiable negative generation mechanisms. Furthermore, we introduce structure-grounded negatives derived from inter-procedural data-flow analysis and observe that the relative effectiveness of mining strategies appears to depend on the encoder's pretrained representation geometry—an interaction that existing work does not examine. Together, these findings address a gap at the intersection of graph-guided code methods, which exploit structure only at inference time, and contrastive training methods, which have not systematically leveraged structural signals for negative selection.
> 
> &lt;!-- Claim 2 wording fix: 2026-05-15 -->
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "11467fbb-854f-4919-b858-91a87d76cd04",
  "tool_use_result": {
    "stdout": "9c9\n< Critically, all graph-guided methods apply structural information exclusively at inference time; the underlying retrieval encoder is trained without structural signal. The encoder's embedding space is therefore optimized solely on textual similarity, potentially conflating lexically similar but structurally unrelated code. Our work addresses this gap by incorporating inter-procedural data-flow information into the training process through structure-grounded hard negative mining.\n---\n> Critically, these graph-guided methods apply structural information exclusively at inference time; the underlying retrieval encoder is trained without structural signal. The encoder's embedding space is therefore optimized solely on textual similarity, potentially conflating lexically similar but structurally unrelated code. Our work addresses this gap by incorporating inter-procedural data-flow information into the training process through structure-grounded hard negative mining.\n13c13\n< Contrastive learning has proven effective for learning code representations that capture functional semantics beyond surface-level patterns. ContraCode \\cite{jain2021contracode} applies compiler-driven transformations to generate functionally equivalent program variants as positive pairs, training the encoder to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal (code-code) and bimodal (code-text) contrastive objectives, achieving strong results across eleven code search benchmarks. \\citet{ding2022programcontrasts} leverage program structure and functional attributes to construct contrastive pairs for learning code (dis)similarity representations.\n---\n> Building on the success of Sentence-BERT \\cite{reimers2019sentencebert} in learning dense sentence representations via siamese contrastive objectives, contrastive learning has proven effective for learning code representations that capture functional semantics beyond surface-level patterns. ContraCode \\cite{jain2021contracode} applies compiler-driven transformations to generate functionally equivalent program variants as positive pairs, training the encoder to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal (code-code) and bimodal (code-text) contrastive objectives, achieving strong results across eleven code search benchmarks. \\citet{ding2022programcontrasts} leverage program structure and functional attributes to construct contrastive pairs for learning code (dis)similarity representations.\n25c25,27\n< Our work provides a systematic comparison that challenges the assumption that expensive gradient-based hard negative methods are necessary for effective code retrieval. We show that simple static embedding-distance mining consistently improves retrieval performance across two decoder-only encoders with distinct representation geometries, without requiring differentiable negative generation mechanisms. Furthermore, we introduce structure-grounded negatives derived from inter-procedural data-flow analysis and show that the relative effectiveness of mining strategies depends on the encoder's pretrained representation geometry—an interaction that existing work does not examine. Together, these findings address a gap at the intersection of graph-guided code methods, which exploit structure only at inference time, and contrastive training methods, which have not systematically leveraged structural signals for negative selection.\n---\n> Our work provides a systematic comparison that challenges the assumption that expensive gradient-based hard negative methods are necessary for effective code retrieval. We show that simple static embedding-distance mining consistently improves (pilot evidence; pending M2 full confirmation) retrieval performance across two decoder-only encoders with distinct representation geometries, without requiring differentiable negative generation mechanisms. Furthermore, we introduce structure-grounded negatives derived from inter-procedural data-flow analysis and observe that the relative effectiveness of mining strategies appears to depend on the encoder's pretrained representation geometry—an interaction that existing work does not examine. Together, these findings address a gap at the intersection of graph-guided code methods, which exploit structure only at inference time, and contrastive training methods, which have not systematically leveraged structural signals for negative selection.\n> \n> &lt;!-- Claim 2 wording fix: 2026-05-15 -->",
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

_source line 37_

<details><summary>Logged reasoning block</summary>

```text
Now I see the picture clearly. The `paper_drafts/` versions are the more recent ones with the Claim 2 wording fix applied. The `_project/paper/` versions are older.

The `paper_drafts/related_work_v1.md` has `&lt;!-- Claim 2 wording fix: 2026-05-15 -->` marker. The `paper_drafts/discussion_v2.md` has the Claim 2 downgrade changes (exploratory language).

So I should work with the `paper_drafts/` versions as the base, since they have the latest Claim 2 fixes.


Let me go through the paper_drafts files to see what I'm working with.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "5f2d665e-ecdf-47b3-ad47-85e87be2d96e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WqLC2wCjgeczELJzKv5tw6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3324,
      "cache_read_input_tokens": 36965,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3324
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

_source line 38_

The `paper_drafts/` copies are newer — they have the Claim 2 wording fixes. I need to work from those versions. Let me read them in full.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "eb159f77-8b35-4577-8c17-ba48902f6388",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WqLC2wCjgeczELJzKv5tw6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3324,
      "cache_read_input_tokens": 36965,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3324
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

_source line 39_

<details open><summary>🔧 Tool call — Read · `toolu_01CVwLuXbcWGXFTf4PPTArNm`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/discussion_v2.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "5769603e-70b0-4193-bbe5-f021cbe5d25f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WqLC2wCjgeczELJzKv5tw6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3324,
      "cache_read_input_tokens": 36965,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3324
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

_source line 40 · 2026-05-15T02:12:27.640Z_

<details><summary>↩ Tool result · `toolu_01CVwLuXbcWGXFTf4PPTArNm`</summary>

```text
1	# 5. Discussion
2	
3	## 5.1 Relationship to Inference-Time Graph Methods
4	
5	A growing body of work leverages code structure graphs at inference time to improve LLM-based software engineering.
6	CodexGraph (Liu et al., NAACL 2025) materializes a code property graph in a Neo4j database that LLM agents query via Cypher; RepoGraph (Ouyang et al., ICLR 2025) provides line-level code graph navigation as a plug-in for SE agents; LocAgent (Chen et al., ACL 2025) and RANGER (Shah et al., 2025) employ graph-guided multi-hop reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder (Liu et al., ASE 2024) and ARISE (Seddik & Fard, 2026) come closest to our work in incorporating data-flow information, but both are limited to intra-procedural scope.
7	
8	Table 5 summarizes the key dimensions of comparison. We highlight two axes along which StructFuse occupies a distinct position:
9	
10	**When structural information enters the pipeline.** Inference-time methods construct and query graphs per request, incurring latency proportional to graph complexity and—for agent-based systems—requiring multiple LLM calls per query. StructFuse amortizes all graph computation to training time: CodeQL extraction costs approximately 8.9 seconds per instance (~110 CPU-hours for 44K instances; Table 4), after which the trained encoder operates at standard embedding-lookup speed with zero graph overhead. For latency-sensitive, high-throughput retrieval scenarios, this cost model is substantially more favorable.
11	
12	**Depth of data-flow analysis.** Most inference-time graph methods use structural relations (call graphs, class hierarchies, import dependencies). GraphCoder incorporates control-flow and data-dependence graphs, and ARISE exposes statement-level def-use edges, but both operate within single procedures. StructFuse leverages CodeQL's bounded inter-procedural taint tracking (2-hop call-graph scope), capturing cross-function data-flow paths—e.g., a sanitizer that transforms data between a source and sink across call boundaries. This deeper semantic signal generates harder, more informative negatives than structural proximity alone.
13	
14	**Complementarity.** We emphasize that StructFuse and inference-time graph methods address different stages of the retrieval pipeline and are composable rather than competing. A StructFuse-trained encoder can serve as a first-stage retriever whose embeddings already encode data-flow semantics, reducing the search space for inference-time graph agents that perform targeted reranking. Conversely, systems like CodexGraph or LocAgent can refine StructFuse retrieval results through explicit graph navigation when maximum precision is required. The two paradigms are complementary: StructFuse internalizes general structural patterns during training, while inference-time methods provide case-specific structural reasoning during deployment.
15	
16	## 5.2 Representation Geometry and Strategy Effectiveness: An Exploratory Analysis
17	
18	We present the following analysis as an exploratory observation derived from two encoders, not a validated mechanism.
19	
20	Our negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining.
21	
22	When the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This is consistent with the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).
23	
24	When the representation space has healthy separation—as observed for StarCoder2-3B (pos\_sim = 0.799, random margin = 0.194, 2.6× larger than Qwen)—embedding-distance mining alone provides a sufficient difficulty gradient, and dataflow negatives do not yield additional improvement (+1.6pp for embedding vs. random, but −0.5pp for dataflow vs. random; Table 2). The larger margins mean the encoder can still extract useful contrastive signal from text-similarity-based negatives without supplementary structural guidance.
25	
26	This interaction between representation geometry and strategy effectiveness has a practical implication: practitioners can compute pos\_sim on a held-out sample with their pretrained encoder (a single forward pass, requiring no training) to predict whether structure-grounded negatives are worth the extraction cost. We observe that pos\_sim > 0.98 serves as an approximate threshold above which structural negatives provide conditional benefit, though we note this threshold is derived from two encoder observations and should be validated more broadly.
27	
28	## 5.3 Limitations
29	
30	We identify several limitations of the current study that contextualize our findings:
31	
32	**Encoder scope.** Our experiments use two decoder-only 3B-parameter encoders (Qwen2.5-Coder-3B and StarCoder2-3B). While these models differ meaningfully in pretraining corpus and representation geometry—enabling our interaction analysis—generalizing to encoder-only architectures (e.g., CodeBERT), larger scales, or non-code domains requires further investigation.
33	
34	**Single task.** We evaluate on code retrieval with contrastive training. Whether structure-grounded negatives similarly benefit other code understanding tasks (fault localization, code summarization, clone detection) remains an open question, though the underlying principle—that inter-procedural data-flow provides an orthogonal signal to text similarity—is task-agnostic.
35	
36	**Language and tooling dependency.** Our pipeline relies on CodeQL for inter-procedural data-flow extraction and currently supports Python repositories only. Extending to other languages requires language-specific CodeQL queries, and the dependency on a commercial static analysis tool may limit reproducibility. We note that the methodology generalizes to any tool capable of inter-procedural data-flow analysis (e.g., Joern, Soot).
37	
38	**Static mining.** Our negative mining is performed once before training and remains fixed throughout. Dynamic re-mining—where negatives are refreshed each epoch using the current encoder's embeddings—could yield progressively harder negatives as the model improves. We do not evaluate this variant in the current work and acknowledge the static-vs.-dynamic mining confound as a limitation. We plan to address this in future revisions.
39	
40	**Structural data coverage.** CodeQL successfully extracts data-flow information for 36% of instances across 123 repositories (93.9% repo coverage; Table 4). The remaining instances fall back to embedding-distance negatives. While our results demonstrate that even partial structural coverage yields measurable improvements, higher extraction success rates would likely amplify the benefit.
41	
42	## 5.4 Future Work
43	
44	We identify three directions that follow naturally from our findings, while noting that each requires empirical validation before strong claims can be made:
45	
46	**Hybrid retrieval pipelines.** Integrating a StructFuse-trained encoder as the first-stage retriever within inference-time graph systems (e.g., CodexGraph, RANGER) could combine the efficiency of embedding-based retrieval with the precision of runtime graph navigation. Evaluating such pipelines on end-to-end benchmarks like SWE-bench would quantify the practical value of this complementarity.
47	
48	**Representation-guided strategy selection.** Our observation that pos\_sim appears to correlate with strategy effectiveness suggests an automated protocol: given a new encoder, compute representation geometry statistics on a calibration set, then select the appropriate negative mining strategy without exhaustive ablation. Validating this protocol across a wider range of encoders and tasks is a natural next step.
49	
50	**Extension to dynamic and multi-lingual settings.** Adapting the pipeline to dynamically re-mine negatives during training, and extending CodeQL queries to languages beyond Python, would address two of our current limitations. For dynamic mining, the key design question is the re-mining frequency—epoch-level re-mining requires repeated CodeQL extraction, and the cost-benefit tradeoff depends on how quickly the encoder's embedding space evolves during training.
51	
52	&lt;!-- Claim 2 wording fix: 2026-05-15 -->
53	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "bf6e991d-41d4-4e53-b792-4fcc131b9741",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/discussion_v2.md",
      "content": "# 5. Discussion\n\n## 5.1 Relationship to Inference-Time Graph Methods\n\nA growing body of work leverages code structure graphs at inference time to improve LLM-based software engineering.\nCodexGraph (Liu et al., NAACL 2025) materializes a code property graph in a Neo4j database that LLM agents query via Cypher; RepoGraph (Ouyang et al., ICLR 2025) provides line-level code graph navigation as a plug-in for SE agents; LocAgent (Chen et al., ACL 2025) and RANGER (Shah et al., 2025) employ graph-guided multi-hop reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder (Liu et al., ASE 2024) and ARISE (Seddik & Fard, 2026) come closest to our work in incorporating data-flow information, but both are limited to intra-procedural scope.\n\nTable 5 summarizes the key dimensions of comparison. We highlight two axes along which StructFuse occupies a distinct position:\n\n**When structural information enters the pipeline.** Inference-time methods construct and query graphs per request, incurring latency proportional to graph complexity and—for agent-based systems—requiring multiple LLM calls per query. StructFuse amortizes all graph computation to training time: CodeQL extraction costs approximately 8.9 seconds per instance (~110 CPU-hours for 44K instances; Table 4), after which the trained encoder operates at standard embedding-lookup speed with zero graph overhead. For latency-sensitive, high-throughput retrieval scenarios, this cost model is substantially more favorable.\n\n**Depth of data-flow analysis.** Most inference-time graph methods use structural relations (call graphs, class hierarchies, import dependencies). GraphCoder incorporates control-flow and data-dependence graphs, and ARISE exposes statement-level def-use edges, but both operate within single procedures. StructFuse leverages CodeQL's bounded inter-procedural taint tracking (2-hop call-graph scope), capturing cross-function data-flow paths—e.g., a sanitizer that transforms data between a source and sink across call boundaries. This deeper semantic signal generates harder, more informative negatives than structural proximity alone.\n\n**Complementarity.** We emphasize that StructFuse and inference-time graph methods address different stages of the retrieval pipeline and are composable rather than competing. A StructFuse-trained encoder can serve as a first-stage retriever whose embeddings already encode data-flow semantics, reducing the search space for inference-time graph agents that perform targeted reranking. Conversely, systems like CodexGraph or LocAgent can refine StructFuse retrieval results through explicit graph navigation when maximum precision is required. The two paradigms are complementary: StructFuse internalizes general structural patterns during training, while inference-time methods provide case-specific structural reasoning during deployment.\n\n## 5.2 Representation Geometry and Strategy Effectiveness: An Exploratory Analysis\n\nWe present the following analysis as an exploratory observation derived from two encoders, not a validated mechanism.\n\nOur negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining.\n\nWhen the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This is consistent with the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).\n\nWhen the representation space has healthy separation—as observed for StarCoder2-3B (pos\\_sim = 0.799, random margin = 0.194, 2.6× larger than Qwen)—embedding-distance mining alone provides a sufficient difficulty gradient, and dataflow negatives do not yield additional improvement (+1.6pp for embedding vs. random, but −0.5pp for dataflow vs. random; Table 2). The larger margins mean the encoder can still extract useful contrastive signal from text-similarity-based negatives without supplementary structural guidance.\n\nThis interaction between representation geometry and strategy effectiveness has a practical implication: practitioners can compute pos\\_sim on a held-out sample with their pretrained encoder (a single forward pass, requiring no training) to predict whether structure-grounded negatives are worth the extraction cost. We observe that pos\\_sim > 0.98 serves as an approximate threshold above which structural negatives provide conditional benefit, though we note this threshold is derived from two encoder observations and should be validated more broadly.\n\n## 5.3 Limitations\n\nWe identify several limitations of the current study that contextualize our findings:\n\n**Encoder scope.** Our experiments use two decoder-only 3B-parameter encoders (Qwen2.5-Coder-3B and StarCoder2-3B). While these models differ meaningfully in pretraining corpus and representation geometry—enabling our interaction analysis—generalizing to encoder-only architectures (e.g., CodeBERT), larger scales, or non-code domains requires further investigation.\n\n**Single task.** We evaluate on code retrieval with contrastive training. Whether structure-grounded negatives similarly benefit other code understanding tasks (fault localization, code summarization, clone detection) remains an open question, though the underlying principle—that inter-procedural data-flow provides an orthogonal signal to text similarity—is task-agnostic.\n\n**Language and tooling dependency.** Our pipeline relies on CodeQL for inter-procedural data-flow extraction and currently supports Python repositories only. Extending to other languages requires language-specific CodeQL queries, and the dependency on a commercial static analysis tool may limit reproducibility. We note that the methodology generalizes to any tool capable of inter-procedural data-flow analysis (e.g., Joern, Soot).\n\n**Static mining.** Our negative mining is performed once before training and remains fixed throughout. Dynamic re-mining—where negatives are refreshed each epoch using the current encoder's embeddings—could yield progressively harder negatives as the model improves. We do not evaluate this variant in the current work and acknowledge the static-vs.-dynamic mining confound as a limitation. We plan to address this in future revisions.\n\n**Structural data coverage.** CodeQL successfully extracts data-flow information for 36% of instances across 123 repositories (93.9% repo coverage; Table 4). The remaining instances fall back to embedding-distance negatives. While our results demonstrate that even partial structural coverage yields measurable improvements, higher extraction success rates would likely amplify the benefit.\n\n## 5.4 Future Work\n\nWe identify three directions that follow naturally from our findings, while noting that each requires empirical validation before strong claims can be made:\n\n**Hybrid retrieval pipelines.** Integrating a StructFuse-trained encoder as the first-stage retriever within inference-time graph systems (e.g., CodexGraph, RANGER) could combine the efficiency of embedding-based retrieval with the precision of runtime graph navigation. Evaluating such pipelines on end-to-end benchmarks like SWE-bench would quantify the practical value of this complementarity.\n\n**Representation-guided strategy selection.** Our observation that pos\\_sim appears to correlate with strategy effectiveness suggests an automated protocol: given a new encoder, compute representation geometry statistics on a calibration set, then select the appropriate negative mining strategy without exhaustive ablation. Validating this protocol across a wider range of encoders and tasks is a natural next step.\n\n**Extension to dynamic and multi-lingual settings.** Adapting the pipeline to dynamically re-mine negatives during training, and extending CodeQL queries to languages beyond Python, would address two of our current limitations. For dynamic mining, the key design question is the re-mining frequency—epoch-level re-mining requires repeated CodeQL extraction, and the cost-benefit tradeoff depends on how quickly the encoder's embedding space evolves during training.\n\n&lt;!-- Claim 2 wording fix: 2026-05-15 -->\n",
      "numLines": 53,
      "startLine": 1,
      "totalLines": 53
    }
  }
}
```

</details>

---

### Tool call

_source line 41_

<details open><summary>🔧 Tool call — Read · `toolu_01EJt7JhGZjZmrH8XULofdcu`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "f41f394b-f8ca-42f4-93d8-72c8faf74553",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WqLC2wCjgeczELJzKv5tw6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3324,
      "cache_read_input_tokens": 36965,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3324
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

_source line 42 · 2026-05-15T02:12:28.171Z_

<details><summary>↩ Tool result · `toolu_01EJt7JhGZjZmrH8XULofdcu`</summary>

```text
1	# 2. Related Work
2	
3	## 2.1 Code Retrieval Methods
4	
5	Repo-level code retrieval aims to identify relevant files or code spans from large codebases given a bug report or issue description. Classical sparse retrieval via BM25 \cite{robertson2009bm25} remains a competitive baseline in this setting. The dense retrieval paradigm, pioneered by DPR \cite{karpukhin2020dpr} for open-domain question answering, has been increasingly adopted for code. SweRank \cite{reddy2025swerank} trains a retrieve-and-rerank pipeline for software issue localization, achieving state-of-the-art results on SWE-Bench-Lite and LocBench through text-based retrieval. SWE-Fixer \cite{xie2025swefixer} combines BM25 with a learned retriever in a coarse-to-fine file retrieval pipeline, demonstrating that sparse and dense retrieval are complementary. Both systems, however, treat code files as flat text and do not exploit structural relationships between files during training.
6	
7	A parallel line of work leverages code structure graphs at inference time to guide code navigation. LocAgent \cite{chen2025locagent} parses codebases into directed heterogeneous graphs and employs LLM agents for multi-hop graph reasoning during fault localization. RANGER \cite{shah2025ranger} constructs repository knowledge graphs with variable-level nodes and applies MCTS-guided graph exploration for retrieval. CodexGraph \cite{liu2025codexgraph} indexes codebases into graph databases queried via Cypher, while RepoGraph \cite{ouyang2025repograph} provides line-level code graph navigation as a plug-in module for software engineering agents. GraphCoder \cite{liu2024graphcoder} incorporates control-flow and data-dependence edges into code context graphs for coarse-to-fine retrieval, and ARISE \cite{seddik2026arise} exposes statement-level def-use edges for agentic fault localization—though both are limited to intra-procedural scope. These methods demonstrate the value of structural information for code retrieval, yet they incur per-query computational costs and, for agent-based systems, require multiple LLM calls per retrieval step.
8	
9	Critically, these graph-guided methods apply structural information exclusively at inference time; the underlying retrieval encoder is trained without structural signal. The encoder's embedding space is therefore optimized solely on textual similarity, potentially conflating lexically similar but structurally unrelated code. Our work addresses this gap by incorporating inter-procedural data-flow information into the training process through structure-grounded hard negative mining.
10	
11	## 2.2 Contrastive Learning for Code
12	
13	Building on the success of Sentence-BERT \cite{reimers2019sentencebert} in learning dense sentence representations via siamese contrastive objectives, contrastive learning has proven effective for learning code representations that capture functional semantics beyond surface-level patterns. ContraCode \cite{jain2021contracode} applies compiler-driven transformations to generate functionally equivalent program variants as positive pairs, training the encoder to be invariant to syntactic variation. CodeRetriever \cite{li2022coderetriever} combines unimodal (code-code) and bimodal (code-text) contrastive objectives, achieving strong results across eleven code search benchmarks. \citet{ding2022programcontrasts} leverage program structure and functional attributes to construct contrastive pairs for learning code (dis)similarity representations.
14	
15	Complementary efforts have explored encoding structural information directly into code representations. code2vec \cite{alon2019code2vec} demonstrates that AST path-based representations capture meaningful program properties at scale. GraphCodeBERT \cite{guo2021graphcodebert} incorporates data-flow edges into pre-training, showing that data-flow information improves downstream code understanding tasks. However, GraphCodeBERT uses data-flow as an auxiliary pre-training signal over individual functions, whereas our work uses inter-procedural data-flow to construct hard negatives for contrastive fine-tuning—a fundamentally different application of structural information that operates at the repository level rather than the function level.
16	
17	Despite the progress in contrastive code representation learning, these methods share a common dependency on negative sampling strategy yet few systematically investigate which negatives yield the best representations for code retrieval. Most approaches rely on in-batch negatives \cite{karpukhin2020dpr} or random sampling, leaving the interaction between negative selection strategy and encoder representation geometry unexplored. Our work addresses this gap with a controlled comparison across negative mining strategies on modern decoder-only code encoders.
18	
19	## 2.3 Hard Negative Mining
20	
21	Hard negative mining—selecting negative examples that are challenging for the current model—is well established for improving contrastive learning. In visual representation learning, SimCLR \cite{chen2020simclr} demonstrates the importance of large batch sizes and hard negatives for learning discriminative features. In dense text retrieval, DPR \cite{karpukhin2020dpr} shows that BM25-retrieved passages serve as effective hard negatives beyond in-batch sampling. ANCE \cite{xiong2021ance} advances this by mining negatives from the model's own embedding space via approximate nearest neighbor search, achieving substantial gains over static BM25 negatives. Curriculum-based approaches such as CL-DRD \cite{zeng2022cldrd} progressively increase negative difficulty during training through knowledge distillation.
22	
23	In the code domain, hard negative mining has received comparatively less systematic attention. CoCoHaNeRe \cite{fan2025cocohanere} proposes a differentiable hard negative mechanism for code search contrastive learning, arguing that gradient-based methods yield faster and more effective training than non-differentiable embedding-based negative selection. While CoCoHaNeRe demonstrates the advantages of its gradient-based approach within its experimental setting, it does not evaluate simple static embedding-distance mining—the strategy of selecting hard negatives by nearest-neighbor lookup in the encoder's frozen embedding space—in structural code retrieval settings.
24	
25	Our work provides a systematic comparison that challenges the assumption that expensive gradient-based hard negative methods are necessary for effective code retrieval. We show that simple static embedding-distance mining consistently improves (pilot evidence; pending M2 full confirmation) retrieval performance across two decoder-only encoders with distinct representation geometries, without requiring differentiable negative generation mechanisms. Furthermore, we introduce structure-grounded negatives derived from inter-procedural data-flow analysis and observe that the relative effectiveness of mining strategies appears to depend on the encoder's pretrained representation geometry—an interaction that existing work does not examine. Together, these findings address a gap at the intersection of graph-guided code methods, which exploit structure only at inference time, and contrastive training methods, which have not systematically leveraged structural signals for negative selection.
26	
27	&lt;!-- Claim 2 wording fix: 2026-05-15 -->
28	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "7bde37a8-026e-47bf-bcae-b82fb051952a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
      "content": "# 2. Related Work\n\n## 2.1 Code Retrieval Methods\n\nRepo-level code retrieval aims to identify relevant files or code spans from large codebases given a bug report or issue description. Classical sparse retrieval via BM25 \\cite{robertson2009bm25} remains a competitive baseline in this setting. The dense retrieval paradigm, pioneered by DPR \\cite{karpukhin2020dpr} for open-domain question answering, has been increasingly adopted for code. SweRank \\cite{reddy2025swerank} trains a retrieve-and-rerank pipeline for software issue localization, achieving state-of-the-art results on SWE-Bench-Lite and LocBench through text-based retrieval. SWE-Fixer \\cite{xie2025swefixer} combines BM25 with a learned retriever in a coarse-to-fine file retrieval pipeline, demonstrating that sparse and dense retrieval are complementary. Both systems, however, treat code files as flat text and do not exploit structural relationships between files during training.\n\nA parallel line of work leverages code structure graphs at inference time to guide code navigation. LocAgent \\cite{chen2025locagent} parses codebases into directed heterogeneous graphs and employs LLM agents for multi-hop graph reasoning during fault localization. RANGER \\cite{shah2025ranger} constructs repository knowledge graphs with variable-level nodes and applies MCTS-guided graph exploration for retrieval. CodexGraph \\cite{liu2025codexgraph} indexes codebases into graph databases queried via Cypher, while RepoGraph \\cite{ouyang2025repograph} provides line-level code graph navigation as a plug-in module for software engineering agents. GraphCoder \\cite{liu2024graphcoder} incorporates control-flow and data-dependence edges into code context graphs for coarse-to-fine retrieval, and ARISE \\cite{seddik2026arise} exposes statement-level def-use edges for agentic fault localization—though both are limited to intra-procedural scope. These methods demonstrate the value of structural information for code retrieval, yet they incur per-query computational costs and, for agent-based systems, require multiple LLM calls per retrieval step.\n\nCritically, these graph-guided methods apply structural information exclusively at inference time; the underlying retrieval encoder is trained without structural signal. The encoder's embedding space is therefore optimized solely on textual similarity, potentially conflating lexically similar but structurally unrelated code. Our work addresses this gap by incorporating inter-procedural data-flow information into the training process through structure-grounded hard negative mining.\n\n## 2.2 Contrastive Learning for Code\n\nBuilding on the success of Sentence-BERT \\cite{reimers2019sentencebert} in learning dense sentence representations via siamese contrastive objectives, contrastive learning has proven effective for learning code representations that capture functional semantics beyond surface-level patterns. ContraCode \\cite{jain2021contracode} applies compiler-driven transformations to generate functionally equivalent program variants as positive pairs, training the encoder to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal (code-code) and bimodal (code-text) contrastive objectives, achieving strong results across eleven code search benchmarks. \\citet{ding2022programcontrasts} leverage program structure and functional attributes to construct contrastive pairs for learning code (dis)similarity representations.\n\nComplementary efforts have explored encoding structural information directly into code representations. code2vec \\cite{alon2019code2vec} demonstrates that AST path-based representations capture meaningful program properties at scale. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pre-training, showing that data-flow information improves downstream code understanding tasks. However, GraphCodeBERT uses data-flow as an auxiliary pre-training signal over individual functions, whereas our work uses inter-procedural data-flow to construct hard negatives for contrastive fine-tuning—a fundamentally different application of structural information that operates at the repository level rather than the function level.\n\nDespite the progress in contrastive code representation learning, these methods share a common dependency on negative sampling strategy yet few systematically investigate which negatives yield the best representations for code retrieval. Most approaches rely on in-batch negatives \\cite{karpukhin2020dpr} or random sampling, leaving the interaction between negative selection strategy and encoder representation geometry unexplored. Our work addresses this gap with a controlled comparison across negative mining strategies on modern decoder-only code encoders.\n\n## 2.3 Hard Negative Mining\n\nHard negative mining—selecting negative examples that are challenging for the current model—is well established for improving contrastive learning. In visual representation learning, SimCLR \\cite{chen2020simclr} demonstrates the importance of large batch sizes and hard negatives for learning discriminative features. In dense text retrieval, DPR \\cite{karpukhin2020dpr} shows that BM25-retrieved passages serve as effective hard negatives beyond in-batch sampling. ANCE \\cite{xiong2021ance} advances this by mining negatives from the model's own embedding space via approximate nearest neighbor search, achieving substantial gains over static BM25 negatives. Curriculum-based approaches such as CL-DRD \\cite{zeng2022cldrd} progressively increase negative difficulty during training through knowledge distillation.\n\nIn the code domain, hard negative mining has received comparatively less systematic attention. CoCoHaNeRe \\cite{fan2025cocohanere} proposes a differentiable hard negative mechanism for code search contrastive learning, arguing that gradient-based methods yield faster and more effective training than non-differentiable embedding-based negative selection. While CoCoHaNeRe demonstrates the advantages of its gradient-based approach within its experimental setting, it does not evaluate simple static embedding-distance mining—the strategy of selecting hard negatives by nearest-neighbor lookup in the encoder's frozen embedding space—in structural code retrieval settings.\n\nOur work provides a systematic comparison that challenges the assumption that expensive gradient-based hard negative methods are necessary for effective code retrieval. We show that simple static embedding-distance mining consistently improves (pilot evidence; pending M2 full confirmation) retrieval performance across two decoder-only encoders with distinct representation geometries, without requiring differentiable negative generation mechanisms. Furthermore, we introduce structure-grounded negatives derived from inter-procedural data-flow analysis and observe that the relative effectiveness of mining strategies appears to depend on the encoder's pretrained representation geometry—an interaction that existing work does not examine. Together, these findings address a gap at the intersection of graph-guided code methods, which exploit structure only at inference time, and contrastive training methods, which have not systematically leveraged structural signals for negative selection.\n\n&lt;!-- Claim 2 wording fix: 2026-05-15 -->\n",
      "numLines": 28,
      "startLine": 1,
      "totalLines": 28
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
Now I have the full content of both files with the Claim 2 fixes already applied.

**Analysis of discussion_v2.md (paper_drafts version):**

§5.2 issues:
1. The section talks about "negative difficulty analysis" and reports margins measured by cosine similarity, but never explicitly states that cosine similarity is the *evaluation metric* applied uniformly, distinct from the *selection methods*.
2. "embedding margin = 0.017" — the term "embedding margin" refers to the margin of negatives selected by embedding-distance mining (measured by cosine sim). It doesn't explicitly conflate dataflow with embedding selection, but the distinction could be clearer.


3. The claim that "all text-similarity-based negatives are clustered near the positive" correctly excludes dataflow-aware from that category, though it doesn't spell out how dataflow actually selects negatives.
4. There's no explicit statement that dataflow-aware uses embedding similarity for selection, so while there's no outright error, the separation between selection method and evaluation metric remains implicit rather than stated.

**Analysis of related_work_v1.md (paper_drafts version):**
- "structure-grounded negatives derived from inter-procedural data-flow analysis" is vague but accurate, and doesn't claim embedding-based selection.
- No conflation issues detected.

**Changes needed:**

For discussion_v2.md, I need to clarify the distinction between how negatives are selected versus how they're evaluated, making explicit that dataflow-aware uses embedding similarity for selection just like the other methods.

For related_work_v1.md, I don't see any actual conflation, but I should still add the D041 marker to document that I've checked it.

Now I'm making the edits. In discussion_v2.md §5.2, I'll insert a clarifying sentence right after the introductory lines to explicitly separate the selection methods—random sampling, embedding-distance ranking, and dataflow-aware BM25 ranking—from the uniform evaluation metric using pretrained encoder cosine similarity. This disambiguates what each strategy does versus how we measure the results.

Looking at line 22, I notice "text-similarity-based negatives" could be misread as including dataflow-aware, since BM25 operates on text. But the paper uses "text-similarity-based" to mean embedding-based, not lexical-based, so I should clarify that distinction when I revise.

The margin values themselves are clear in context—random margin versus embedding-distance margin, both evaluated by cosine similarity. Adding a sentence that explicitly breaks down the three selection methods will resolve any ambiguity.

Now I'm ready to draft the specific edits for discussion_v2.md.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "5395e102-54e1-4657-9f3b-ee716eac13d4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0117MRz7HJW1ZH5uwgsmPBAx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4136,
      "cache_read_input_tokens": 40289,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4136
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

Analysis complete. Here's what I found:

**discussion_v2.md §5.2**: No outright incorrect claim (e.g., "dataflow-aware selects by embedding similarity"), but the section doesn't explicitly distinguish the *selection method* of each strategy from the *evaluation metric* (cosine similarity) used uniformly. This could lead readers to conflate the two, especially since embedding-distance mining uses cosine similarity for both selection AND evaluation.

**related_work_v1.md**: Clean — says "structure-grounded negatives derived from inter-procedural data-flow analysis," no conflation.

I'll add a disambiguating sentence to §5.2 and mark both files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "8a2981f7-dd3a-45ab-a10f-f527899fdf5a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0117MRz7HJW1ZH5uwgsmPBAx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4136,
      "cache_read_input_tokens": 40289,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4136
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

<details open><summary>🔧 Tool call — Edit · `toolu_011JSYuvbQYswYcUg6hZTsW8`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/discussion_v2.md",
  "old_string": "Our negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining.\n\nWhen the pretrained representation space is saturated",
  "new_string": "Our negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining. Importantly, the three strategies differ in *selection method*—random sampling, cosine-similarity ranking in the pretrained embedding space (embedding-distance), and BM25 lexical ranking within CodeQL-identified structurally connected files (dataflow-aware)—while the analysis *evaluates* the resulting negatives' difficulty uniformly via pretrained encoder cosine similarity as a common metric.\n\nWhen the pretrained representation space is saturated"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "e4fe0f06-ea1d-42ce-a030-ef1303a6759b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0117MRz7HJW1ZH5uwgsmPBAx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4136,
      "cache_read_input_tokens": 40289,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4136
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

_source line 46 · 2026-05-15T02:13:12.004Z_

<details><summary>↩ Tool result · `toolu_011JSYuvbQYswYcUg6hZTsW8`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/discussion_v2.md has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "eadd6a6e-24a2-4490-b366-a07b9357116d",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/discussion_v2.md",
    "oldString": "Our negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining.\n\nWhen the pretrained representation space is saturated",
    "newString": "Our negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining. Importantly, the three strategies differ in *selection method*—random sampling, cosine-similarity ranking in the pretrained embedding space (embedding-distance), and BM25 lexical ranking within CodeQL-identified structurally connected files (dataflow-aware)—while the analysis *evaluates* the resulting negatives' difficulty uniformly via pretrained encoder cosine similarity as a common metric.\n\nWhen the pretrained representation space is saturated",
    "originalFile": "# 5. Discussion\n\n## 5.1 Relationship to Inference-Time Graph Methods\n\nA growing body of work leverages code structure graphs at inference time to improve LLM-based software engineering.\nCodexGraph (Liu et al., NAACL 2025) materializes a code property graph in a Neo4j database that LLM agents query via Cypher; RepoGraph (Ouyang et al., ICLR 2025) provides line-level code graph navigation as a plug-in for SE agents; LocAgent (Chen et al., ACL 2025) and RANGER (Shah et al., 2025) employ graph-guided multi-hop reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder (Liu et al., ASE 2024) and ARISE (Seddik & Fard, 2026) come closest to our work in incorporating data-flow information, but both are limited to intra-procedural scope.\n\nTable 5 summarizes the key dimensions of comparison. We highlight two axes along which StructFuse occupies a distinct position:\n\n**When structural information enters the pipeline.** Inference-time methods construct and query graphs per request, incurring latency proportional to graph complexity and—for agent-based systems—requiring multiple LLM calls per query. StructFuse amortizes all graph computation to training time: CodeQL extraction costs approximately 8.9 seconds per instance (~110 CPU-hours for 44K instances; Table 4), after which the trained encoder operates at standard embedding-lookup speed with zero graph overhead. For latency-sensitive, high-throughput retrieval scenarios, this cost model is substantially more favorable.\n\n**Depth of data-flow analysis.** Most inference-time graph methods use structural relations (call graphs, class hierarchies, import dependencies). GraphCoder incorporates control-flow and data-dependence graphs, and ARISE exposes statement-level def-use edges, but both operate within single procedures. StructFuse leverages CodeQL's bounded inter-procedural taint tracking (2-hop call-graph scope), capturing cross-function data-flow paths—e.g., a sanitizer that transforms data between a source and sink across call boundaries. This deeper semantic signal generates harder, more informative negatives than structural proximity alone.\n\n**Complementarity.** We emphasize that StructFuse and inference-time graph methods address different stages of the retrieval pipeline and are composable rather than competing. A StructFuse-trained encoder can serve as a first-stage retriever whose embeddings already encode data-flow semantics, reducing the search space for inference-time graph agents that perform targeted reranking. Conversely, systems like CodexGraph or LocAgent can refine StructFuse retrieval results through explicit graph navigation when maximum precision is required. The two paradigms are complementary: StructFuse internalizes general structural patterns during training, while inference-time methods provide case-specific structural reasoning during deployment.\n\n## 5.2 Representation Geometry and Strategy Effectiveness: An Exploratory Analysis\n\nWe present the following analysis as an exploratory observation derived from two encoders, not a validated mechanism.\n\nOur negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining.\n\nWhen the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This is consistent with the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).\n\nWhen the representation space has healthy separation—as observed for StarCoder2-3B (pos\\_sim = 0.799, random margin = 0.194, 2.6× larger than Qwen)—embedding-distance mining alone provides a sufficient difficulty gradient, and dataflow negatives do not yield additional improvement (+1.6pp for embedding vs. random, but −0.5pp for dataflow vs. random; Table 2). The larger margins mean the encoder can still extract useful contrastive signal from text-similarity-based negatives without supplementary structural guidance.\n\nThis interaction between representation geometry and strategy effectiveness has a practical implication: practitioners can compute pos\\_sim on a held-out sample with their pretrained encoder (a single forward pass, requiring no training) to predict whether structure-grounded negatives are worth the extraction cost. We observe that pos\\_sim > 0.98 serves as an approximate threshold above which structural negatives provide conditional benefit, though we note this threshold is derived from two encoder observations and should be validated more broadly.\n\n## 5.3 Limitations\n\nWe identify several limitations of the current study that contextualize our findings:\n\n**Encoder scope.** Our experiments use two decoder-only 3B-parameter encoders (Qwen2.5-Coder-3B and StarCoder2-3B). While these models differ meaningfully in pretraining corpus and representation geometry—enabling our interaction analysis—generalizing to encoder-only architectures (e.g., CodeBERT), larger scales, or non-code domains requires further investigation.\n\n**Single task.** We evaluate on code retrieval with contrastive training. Whether structure-grounded negatives similarly benefit other code understanding tasks (fault localization, code summarization, clone detection) remains an open question, though the underlying principle—that inter-procedural data-flow provides an orthogonal signal to text similarity—is task-agnostic.\n\n**Language and tooling dependency.** Our pipeline relies on CodeQL for inter-procedural data-flow extraction and currently supports Python repositories only. Extending to other languages requires language-specific CodeQL queries, and the dependency on a commercial static analysis tool may limit reproducibility. We note that the methodology generalizes to any tool capable of inter-procedural data-flow analysis (e.g., Joern, Soot).\n\n**Static mining.** Our negative mining is performed once before training and remains fixed throughout. Dynamic re-mining—where negatives are refreshed each epoch using the current encoder's embeddings—could yield progressively harder negatives as the model improves. We do not evaluate this variant in the current work and acknowledge the static-vs.-dynamic mining confound as a limitation. We plan to address this in future revisions.\n\n**Structural data coverage.** CodeQL successfully extracts data-flow information for 36% of instances across 123 repositories (93.9% repo coverage; Table 4). The remaining instances fall back to embedding-distance negatives. While our results demonstrate that even partial structural coverage yields measurable improvements, higher extraction success rates would likely amplify the benefit.\n\n## 5.4 Future Work\n\nWe identify three directions that follow naturally from our findings, while noting that each requires empirical validation before strong claims can be made:\n\n**Hybrid retrieval pipelines.** Integrating a StructFuse-trained encoder as the first-stage retriever within inference-time graph systems (e.g., CodexGraph, RANGER) could combine the efficiency of embedding-based retrieval with the precision of runtime graph navigation. Evaluating such pipelines on end-to-end benchmarks like SWE-bench would quantify the practical value of this complementarity.\n\n**Representation-guided strategy selection.** Our observation that pos\\_sim appears to correlate with strategy effectiveness suggests an automated protocol: given a new encoder, compute representation geometry statistics on a calibration set, then select the appropriate negative mining strategy without exhaustive ablation. Validating this protocol across a wider range of encoders and tasks is a natural next step.\n\n**Extension to dynamic and multi-lingual settings.** Adapting the pipeline to dynamically re-mine negatives during training, and extending CodeQL queries to languages beyond Python, would address two of our current limitations. For dynamic mining, the key design question is the re-mining frequency—epoch-level re-mining requires repeated CodeQL extraction, and the cost-benefit tradeoff depends on how quickly the encoder's embedding space evolves during training.\n\n&lt;!-- Claim 2 wording fix: 2026-05-15 -->\n",
    "structuredPatch": [
      {
        "oldStart": 17,
        "oldLines": 7,
        "newStart": 17,
        "newLines": 7,
        "lines": [
          " ",
          " We present the following analysis as an exploratory observation derived from two encoders, not a validated mechanism.",
          " ",
          "-Our negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining.",
          "+Our negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining. Importantly, the three strategies differ in *selection method*—random sampling, cosine-similarity ranking in the pretrained embedding space (embedding-distance), and BM25 lexical ranking within CodeQL-identified structurally connected files (dataflow-aware)—while the analysis *evaluates* the resulting negatives' difficulty uniformly via pretrained encoder cosine similarity as a common metric.",
          " ",
          " When the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This is consistent with the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).",
          " "
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

_source line 47_

<details open><summary>🔧 Tool call — Edit · `toolu_018mFYZg4aEBUeUfXRuFbScJ`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/discussion_v2.md",
  "old_string": "&lt;!-- Claim 2 wording fix: 2026-05-15 -->",
  "new_string": "&lt;!-- Claim 2 wording fix: 2026-05-15 -->\n&lt;!-- D041 dataflow-aware BM25 fix: 2026-05-15 -->"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "ead98fe2-e158-45c4-8856-3f0b3479c547",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BPCrbdwniwG3Ndt9XPK68N",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1976,
      "cache_read_input_tokens": 44425,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1976
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

_source line 48 · 2026-05-15T02:13:15.362Z_

<details><summary>↩ Tool result · `toolu_018mFYZg4aEBUeUfXRuFbScJ`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/discussion_v2.md has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "3084d4b0-264c-4ece-83a6-65e852dbd12b",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/discussion_v2.md",
    "oldString": "&lt;!-- Claim 2 wording fix: 2026-05-15 -->",
    "newString": "&lt;!-- Claim 2 wording fix: 2026-05-15 -->\n&lt;!-- D041 dataflow-aware BM25 fix: 2026-05-15 -->",
    "originalFile": "# 5. Discussion\n\n## 5.1 Relationship to Inference-Time Graph Methods\n\nA growing body of work leverages code structure graphs at inference time to improve LLM-based software engineering.\nCodexGraph (Liu et al., NAACL 2025) materializes a code property graph in a Neo4j database that LLM agents query via Cypher; RepoGraph (Ouyang et al., ICLR 2025) provides line-level code graph navigation as a plug-in for SE agents; LocAgent (Chen et al., ACL 2025) and RANGER (Shah et al., 2025) employ graph-guided multi-hop reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder (Liu et al., ASE 2024) and ARISE (Seddik & Fard, 2026) come closest to our work in incorporating data-flow information, but both are limited to intra-procedural scope.\n\nTable 5 summarizes the key dimensions of comparison. We highlight two axes along which StructFuse occupies a distinct position:\n\n**When structural information enters the pipeline.** Inference-time methods construct and query graphs per request, incurring latency proportional to graph complexity and—for agent-based systems—requiring multiple LLM calls per query. StructFuse amortizes all graph computation to training time: CodeQL extraction costs approximately 8.9 seconds per instance (~110 CPU-hours for 44K instances; Table 4), after which the trained encoder operates at standard embedding-lookup speed with zero graph overhead. For latency-sensitive, high-throughput retrieval scenarios, this cost model is substantially more favorable.\n\n**Depth of data-flow analysis.** Most inference-time graph methods use structural relations (call graphs, class hierarchies, import dependencies). GraphCoder incorporates control-flow and data-dependence graphs, and ARISE exposes statement-level def-use edges, but both operate within single procedures. StructFuse leverages CodeQL's bounded inter-procedural taint tracking (2-hop call-graph scope), capturing cross-function data-flow paths—e.g., a sanitizer that transforms data between a source and sink across call boundaries. This deeper semantic signal generates harder, more informative negatives than structural proximity alone.\n\n**Complementarity.** We emphasize that StructFuse and inference-time graph methods address different stages of the retrieval pipeline and are composable rather than competing. A StructFuse-trained encoder can serve as a first-stage retriever whose embeddings already encode data-flow semantics, reducing the search space for inference-time graph agents that perform targeted reranking. Conversely, systems like CodexGraph or LocAgent can refine StructFuse retrieval results through explicit graph navigation when maximum precision is required. The two paradigms are complementary: StructFuse internalizes general structural patterns during training, while inference-time methods provide case-specific structural reasoning during deployment.\n\n## 5.2 Representation Geometry and Strategy Effectiveness: An Exploratory Analysis\n\nWe present the following analysis as an exploratory observation derived from two encoders, not a validated mechanism.\n\nOur negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining. Importantly, the three strategies differ in *selection method*—random sampling, cosine-similarity ranking in the pretrained embedding space (embedding-distance), and BM25 lexical ranking within CodeQL-identified structurally connected files (dataflow-aware)—while the analysis *evaluates* the resulting negatives' difficulty uniformly via pretrained encoder cosine similarity as a common metric.\n\nWhen the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This is consistent with the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).\n\nWhen the representation space has healthy separation—as observed for StarCoder2-3B (pos\\_sim = 0.799, random margin = 0.194, 2.6× larger than Qwen)—embedding-distance mining alone provides a sufficient difficulty gradient, and dataflow negatives do not yield additional improvement (+1.6pp for embedding vs. random, but −0.5pp for dataflow vs. random; Table 2). The larger margins mean the encoder can still extract useful contrastive signal from text-similarity-based negatives without supplementary structural guidance.\n\nThis interaction between representation geometry and strategy effectiveness has a practical implication: practitioners can compute pos\\_sim on a held-out sample with their pretrained encoder (a single forward pass, requiring no training) to predict whether structure-grounded negatives are worth the extraction cost. We observe that pos\\_sim > 0.98 serves as an approximate threshold above which structural negatives provide conditional benefit, though we note this threshold is derived from two encoder observations and should be validated more broadly.\n\n## 5.3 Limitations\n\nWe identify several limitations of the current study that contextualize our findings:\n\n**Encoder scope.** Our experiments use two decoder-only 3B-parameter encoders (Qwen2.5-Coder-3B and StarCoder2-3B). While these models differ meaningfully in pretraining corpus and representation geometry—enabling our interaction analysis—generalizing to encoder-only architectures (e.g., CodeBERT), larger scales, or non-code domains requires further investigation.\n\n**Single task.** We evaluate on code retrieval with contrastive training. Whether structure-grounded negatives similarly benefit other code understanding tasks (fault localization, code summarization, clone detection) remains an open question, though the underlying principle—that inter-procedural data-flow provides an orthogonal signal to text similarity—is task-agnostic.\n\n**Language and tooling dependency.** Our pipeline relies on CodeQL for inter-procedural data-flow extraction and currently supports Python repositories only. Extending to other languages requires language-specific CodeQL queries, and the dependency on a commercial static analysis tool may limit reproducibility. We note that the methodology generalizes to any tool capable of inter-procedural data-flow analysis (e.g., Joern, Soot).\n\n**Static mining.** Our negative mining is performed once before training and remains fixed throughout. Dynamic re-mining—where negatives are refreshed each epoch using the current encoder's embeddings—could yield progressively harder negatives as the model improves. We do not evaluate this variant in the current work and acknowledge the static-vs.-dynamic mining confound as a limitation. We plan to address this in future revisions.\n\n**Structural data coverage.** CodeQL successfully extracts data-flow information for 36% of instances across 123 repositories (93.9% repo coverage; Table 4). The remaining instances fall back to embedding-distance negatives. While our results demonstrate that even partial structural coverage yields measurable improvements, higher extraction success rates would likely amplify the benefit.\n\n## 5.4 Future Work\n\nWe identify three directions that follow naturally from our findings, while noting that each requires empirical validation before strong claims can be made:\n\n**Hybrid retrieval pipelines.** Integrating a StructFuse-trained encoder as the first-stage retriever within inference-time graph systems (e.g., CodexGraph, RANGER) could combine the efficiency of embedding-based retrieval with the precision of runtime graph navigation. Evaluating such pipelines on end-to-end benchmarks like SWE-bench would quantify the practical value of this complementarity.\n\n**Representation-guided strategy selection.** Our observation that pos\\_sim appears to correlate with strategy effectiveness suggests an automated protocol: given a new encoder, compute representation geometry statistics on a calibration set, then select the appropriate negative mining strategy without exhaustive ablation. Validating this protocol across a wider range of encoders and tasks is a natural next step.\n\n**Extension to dynamic and multi-lingual settings.** Adapting the pipeline to dynamically re-mine negatives during training, and extending CodeQL queries to languages beyond Python, would address two of our current limitations. For dynamic mining, the key design question is the re-mining frequency—epoch-level re-mining requires repeated CodeQL extraction, and the cost-benefit tradeoff depends on how quickly the encoder's embedding space evolves during training.\n\n&lt;!-- Claim 2 wording fix: 2026-05-15 -->\n",
    "structuredPatch": [
      {
        "oldStart": 50,
        "oldLines": 3,
        "newStart": 50,
        "newLines": 4,
        "lines": [
          " **Extension to dynamic and multi-lingual settings.** Adapting the pipeline to dynamically re-mine negatives during training, and extending CodeQL queries to languages beyond Python, would address two of our current limitations. For dynamic mining, the key design question is the re-mining frequency—epoch-level re-mining requires repeated CodeQL extraction, and the cost-benefit tradeoff depends on how quickly the encoder's embedding space evolves during training.",
          " ",
          " &lt;!-- Claim 2 wording fix: 2026-05-15 -->",
          "+&lt;!-- D041 dataflow-aware BM25 fix: 2026-05-15 -->"
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

_source line 49_

<details open><summary>🔧 Tool call — Edit · `toolu_014nMKXFNLYfU1ATcByP7VWQ`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
  "old_string": "&lt;!-- Claim 2 wording fix: 2026-05-15 -->",
  "new_string": "&lt;!-- Claim 2 wording fix: 2026-05-15 -->\n&lt;!-- D041 dataflow-aware BM25 fix: 2026-05-15 -->"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "0fb46b59-15cc-4825-abac-39ddeaa614a0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WCuQSCW4ko2aeU7uzoapdH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 269,
      "cache_read_input_tokens": 46401,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 269
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

_source line 50 · 2026-05-15T02:13:19.762Z_

<details><summary>↩ Tool result · `toolu_014nMKXFNLYfU1ATcByP7VWQ`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "2a84b732-ab62-4a67-a5c2-336c87e249e1",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
    "oldString": "&lt;!-- Claim 2 wording fix: 2026-05-15 -->",
    "newString": "&lt;!-- Claim 2 wording fix: 2026-05-15 -->\n&lt;!-- D041 dataflow-aware BM25 fix: 2026-05-15 -->",
    "originalFile": "# 2. Related Work\n\n## 2.1 Code Retrieval Methods\n\nRepo-level code retrieval aims to identify relevant files or code spans from large codebases given a bug report or issue description. Classical sparse retrieval via BM25 \\cite{robertson2009bm25} remains a competitive baseline in this setting. The dense retrieval paradigm, pioneered by DPR \\cite{karpukhin2020dpr} for open-domain question answering, has been increasingly adopted for code. SweRank \\cite{reddy2025swerank} trains a retrieve-and-rerank pipeline for software issue localization, achieving state-of-the-art results on SWE-Bench-Lite and LocBench through text-based retrieval. SWE-Fixer \\cite{xie2025swefixer} combines BM25 with a learned retriever in a coarse-to-fine file retrieval pipeline, demonstrating that sparse and dense retrieval are complementary. Both systems, however, treat code files as flat text and do not exploit structural relationships between files during training.\n\nA parallel line of work leverages code structure graphs at inference time to guide code navigation. LocAgent \\cite{chen2025locagent} parses codebases into directed heterogeneous graphs and employs LLM agents for multi-hop graph reasoning during fault localization. RANGER \\cite{shah2025ranger} constructs repository knowledge graphs with variable-level nodes and applies MCTS-guided graph exploration for retrieval. CodexGraph \\cite{liu2025codexgraph} indexes codebases into graph databases queried via Cypher, while RepoGraph \\cite{ouyang2025repograph} provides line-level code graph navigation as a plug-in module for software engineering agents. GraphCoder \\cite{liu2024graphcoder} incorporates control-flow and data-dependence edges into code context graphs for coarse-to-fine retrieval, and ARISE \\cite{seddik2026arise} exposes statement-level def-use edges for agentic fault localization—though both are limited to intra-procedural scope. These methods demonstrate the value of structural information for code retrieval, yet they incur per-query computational costs and, for agent-based systems, require multiple LLM calls per retrieval step.\n\nCritically, these graph-guided methods apply structural information exclusively at inference time; the underlying retrieval encoder is trained without structural signal. The encoder's embedding space is therefore optimized solely on textual similarity, potentially conflating lexically similar but structurally unrelated code. Our work addresses this gap by incorporating inter-procedural data-flow information into the training process through structure-grounded hard negative mining.\n\n## 2.2 Contrastive Learning for Code\n\nBuilding on the success of Sentence-BERT \\cite{reimers2019sentencebert} in learning dense sentence representations via siamese contrastive objectives, contrastive learning has proven effective for learning code representations that capture functional semantics beyond surface-level patterns. ContraCode \\cite{jain2021contracode} applies compiler-driven transformations to generate functionally equivalent program variants as positive pairs, training the encoder to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal (code-code) and bimodal (code-text) contrastive objectives, achieving strong results across eleven code search benchmarks. \\citet{ding2022programcontrasts} leverage program structure and functional attributes to construct contrastive pairs for learning code (dis)similarity representations.\n\nComplementary efforts have explored encoding structural information directly into code representations. code2vec \\cite{alon2019code2vec} demonstrates that AST path-based representations capture meaningful program properties at scale. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pre-training, showing that data-flow information improves downstream code understanding tasks. However, GraphCodeBERT uses data-flow as an auxiliary pre-training signal over individual functions, whereas our work uses inter-procedural data-flow to construct hard negatives for contrastive fine-tuning—a fundamentally different application of structural information that operates at the repository level rather than the function level.\n\nDespite the progress in contrastive code representation learning, these methods share a common dependency on negative sampling strategy yet few systematically investigate which negatives yield the best representations for code retrieval. Most approaches rely on in-batch negatives \\cite{karpukhin2020dpr} or random sampling, leaving the interaction between negative selection strategy and encoder representation geometry unexplored. Our work addresses this gap with a controlled comparison across negative mining strategies on modern decoder-only code encoders.\n\n## 2.3 Hard Negative Mining\n\nHard negative mining—selecting negative examples that are challenging for the current model—is well established for improving contrastive learning. In visual representation learning, SimCLR \\cite{chen2020simclr} demonstrates the importance of large batch sizes and hard negatives for learning discriminative features. In dense text retrieval, DPR \\cite{karpukhin2020dpr} shows that BM25-retrieved passages serve as effective hard negatives beyond in-batch sampling. ANCE \\cite{xiong2021ance} advances this by mining negatives from the model's own embedding space via approximate nearest neighbor search, achieving substantial gains over static BM25 negatives. Curriculum-based approaches such as CL-DRD \\cite{zeng2022cldrd} progressively increase negative difficulty during training through knowledge distillation.\n\nIn the code domain, hard negative mining has received comparatively less systematic attention. CoCoHaNeRe \\cite{fan2025cocohanere} proposes a differentiable hard negative mechanism for code search contrastive learning, arguing that gradient-based methods yield faster and more effective training than non-differentiable embedding-based negative selection. While CoCoHaNeRe demonstrates the advantages of its gradient-based approach within its experimental setting, it does not evaluate simple static embedding-distance mining—the strategy of selecting hard negatives by nearest-neighbor lookup in the encoder's frozen embedding space—in structural code retrieval settings.\n\nOur work provides a systematic comparison that challenges the assumption that expensive gradient-based hard negative methods are necessary for effective code retrieval. We show that simple static embedding-distance mining consistently improves (pilot evidence; pending M2 full confirmation) retrieval performance across two decoder-only encoders with distinct representation geometries, without requiring differentiable negative generation mechanisms. Furthermore, we introduce structure-grounded negatives derived from inter-procedural data-flow analysis and observe that the relative effectiveness of mining strategies appears to depend on the encoder's pretrained representation geometry—an interaction that existing work does not examine. Together, these findings address a gap at the intersection of graph-guided code methods, which exploit structure only at inference time, and contrastive training methods, which have not systematically leveraged structural signals for negative selection.\n\n&lt;!-- Claim 2 wording fix: 2026-05-15 -->\n",
    "structuredPatch": [
      {
        "oldStart": 25,
        "oldLines": 3,
        "newStart": 25,
        "newLines": 4,
        "lines": [
          " Our work provides a systematic comparison that challenges the assumption that expensive gradient-based hard negative methods are necessary for effective code retrieval. We show that simple static embedding-distance mining consistently improves (pilot evidence; pending M2 full confirmation) retrieval performance across two decoder-only encoders with distinct representation geometries, without requiring differentiable negative generation mechanisms. Furthermore, we introduce structure-grounded negatives derived from inter-procedural data-flow analysis and observe that the relative effectiveness of mining strategies appears to depend on the encoder's pretrained representation geometry—an interaction that existing work does not examine. Together, these findings address a gap at the intersection of graph-guided code methods, which exploit structure only at inference time, and contrastive training methods, which have not systematically leveraged structural signals for negative selection.",
          " ",
          " &lt;!-- Claim 2 wording fix: 2026-05-15 -->",
          "+&lt;!-- D041 dataflow-aware BM25 fix: 2026-05-15 -->"
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

_source line 51_

Now sync the `_project/paper/` copies to match. I need to update those with the same content.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "f65089ae-0f09-4c1d-92b3-ea4fd2ef1648",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CQ1HajPseENu7rz7scm3kx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 273,
      "cache_read_input_tokens": 46670,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 273
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

_source line 52_

<details open><summary>🔧 Tool call — Read · `toolu_01YS7XB7A6jZHa7gc5TmK8Fy`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/discussion_v2.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "891a4fef-58b0-4a89-b33d-c031164b2487",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CQ1HajPseENu7rz7scm3kx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 273,
      "cache_read_input_tokens": 46670,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 273
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

_source line 53 · 2026-05-15T02:13:23.442Z_

<details><summary>↩ Tool result · `toolu_01YS7XB7A6jZHa7gc5TmK8Fy`</summary>

```text
1	# 5. Discussion
2	
3	## 5.1 Relationship to Inference-Time Graph Methods
4	
5	A growing body of work leverages code structure graphs at inference time to improve LLM-based software engineering.
6	CodexGraph (Liu et al., NAACL 2025) materializes a code property graph in a Neo4j database that LLM agents query via Cypher; RepoGraph (Ouyang et al., ICLR 2025) provides line-level code graph navigation as a plug-in for SE agents; LocAgent (Chen et al., ACL 2025) and RANGER (Shah et al., 2025) employ graph-guided multi-hop reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder (Liu et al., ASE 2024) and ARISE (Seddik & Fard, 2026) come closest to our work in incorporating data-flow information, but both are limited to intra-procedural scope.
7	
8	Table 5 summarizes the key dimensions of comparison. We highlight two axes along which StructFuse occupies a distinct position:
9	
10	**When structural information enters the pipeline.** Inference-time methods construct and query graphs per request, incurring latency proportional to graph complexity and—for agent-based systems—requiring multiple LLM calls per query. StructFuse amortizes all graph computation to training time: CodeQL extraction costs approximately 8.9 seconds per instance (~110 CPU-hours for 44K instances; Table 4), after which the trained encoder operates at standard embedding-lookup speed with zero graph overhead. For latency-sensitive, high-throughput retrieval scenarios, this cost model is substantially more favorable.
11	
12	**Depth of data-flow analysis.** Most inference-time graph methods use structural relations (call graphs, class hierarchies, import dependencies). GraphCoder incorporates control-flow and data-dependence graphs, and ARISE exposes statement-level def-use edges, but both operate within single procedures. StructFuse leverages CodeQL's bounded inter-procedural taint tracking (2-hop call-graph scope), capturing cross-function data-flow paths—e.g., a sanitizer that transforms data between a source and sink across call boundaries. This deeper semantic signal generates harder, more informative negatives than structural proximity alone.
13	
14	**Complementarity.** We emphasize that StructFuse and inference-time graph methods address different stages of the retrieval pipeline and are composable rather than competing. A StructFuse-trained encoder can serve as a first-stage retriever whose embeddings already encode data-flow semantics, reducing the search space for inference-time graph agents that perform targeted reranking. Conversely, systems like CodexGraph or LocAgent can refine StructFuse retrieval results through explicit graph navigation when maximum precision is required. The two paradigms are complementary: StructFuse internalizes general structural patterns during training, while inference-time methods provide case-specific structural reasoning during deployment.
15	
16	## 5.2 Representation Geometry and Strategy Effectiveness: An Exploratory Analysis
17	
18	We present the following analysis as an exploratory observation derived from two encoders, not a validated mechanism.
19	
20	Our negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining. Importantly, the three strategies differ in *selection method*—random sampling, cosine-similarity ranking in the pretrained embedding space (embedding-distance), and BM25 lexical ranking within CodeQL-identified structurally connected files (dataflow-aware)—while the analysis *evaluates* the resulting negatives' difficulty uniformly via pretrained encoder cosine similarity as a common metric.
21	
22	When the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This is consistent with the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).
23	
24	When the representation space has healthy separation—as observed for StarCoder2-3B (pos\_sim = 0.799, random margin = 0.194, 2.6× larger than Qwen)—embedding-distance mining alone provides a sufficient difficulty gradient, and dataflow negatives do not yield additional improvement (+1.6pp for embedding vs. random, but −0.5pp for dataflow vs. random; Table 2). The larger margins mean the encoder can still extract useful contrastive signal from text-similarity-based negatives without supplementary structural guidance.
25	
26	This interaction between representation geometry and strategy effectiveness has a practical implication: practitioners can compute pos\_sim on a held-out sample with their pretrained encoder (a single forward pass, requiring no training) to predict whether structure-grounded negatives are worth the extraction cost. We observe that pos\_sim > 0.98 serves as an approximate threshold above which structural negatives provide conditional benefit, though we note this threshold is derived from two encoder observations and should be validated more broadly.
27	
28	## 5.3 Limitations
29	
30	We identify several limitations of the current study that contextualize our findings:
31	
32	**Encoder scope.** Our experiments use two decoder-only 3B-parameter encoders (Qwen2.5-Coder-3B and StarCoder2-3B). While these models differ meaningfully in pretraining corpus and representation geometry—enabling our interaction analysis—generalizing to encoder-only architectures (e.g., CodeBERT), larger scales, or non-code domains requires further investigation.
33	
34	**Single task.** We evaluate on code retrieval with contrastive training. Whether structure-grounded negatives similarly benefit other code understanding tasks (fault localization, code summarization, clone detection) remains an open question, though the underlying principle—that inter-procedural data-flow provides an orthogonal signal to text similarity—is task-agnostic.
35	
36	**Language and tooling dependency.** Our pipeline relies on CodeQL for inter-procedural data-flow extraction and currently supports Python repositories only. Extending to other languages requires language-specific CodeQL queries, and the dependency on a commercial static analysis tool may limit reproducibility. We note that the methodology generalizes to any tool capable of inter-procedural data-flow analysis (e.g., Joern, Soot).
37	
38	**Static mining.** Our negative mining is performed once before training and remains fixed throughout. Dynamic re-mining—where negatives are refreshed each epoch using the current encoder's embeddings—could yield progressively harder negatives as the model improves. We do not evaluate this variant in the current work and acknowledge the static-vs.-dynamic mining confound as a limitation. We plan to address this in future revisions.
39	
40	**Structural data coverage.** CodeQL successfully extracts data-flow information for 36% of instances across 123 repositories (93.9% repo coverage; Table 4). The remaining instances fall back to embedding-distance negatives. While our results demonstrate that even partial structural coverage yields measurable improvements, higher extraction success rates would likely amplify the benefit.
41	
42	## 5.4 Future Work
43	
44	We identify three directions that follow naturally from our findings, while noting that each requires empirical validation before strong claims can be made:
45	
46	**Hybrid retrieval pipelines.** Integrating a StructFuse-trained encoder as the first-stage retriever within inference-time graph systems (e.g., CodexGraph, RANGER) could combine the efficiency of embedding-based retrieval with the precision of runtime graph navigation. Evaluating such pipelines on end-to-end benchmarks like SWE-bench would quantify the practical value of this complementarity.
47	
48	**Representation-guided strategy selection.** Our observation that pos\_sim appears to correlate with strategy effectiveness suggests an automated protocol: given a new encoder, compute representation geometry statistics on a calibration set, then select the appropriate negative mining strategy without exhaustive ablation. Validating this protocol across a wider range of encoders and tasks is a natural next step.
49	
50	**Extension to dynamic and multi-lingual settings.** Adapting the pipeline to dynamically re-mine negatives during training, and extending CodeQL queries to languages beyond Python, would address two of our current limitations. For dynamic mining, the key design question is the re-mining frequency—epoch-level re-mining requires repeated CodeQL extraction, and the cost-benefit tradeoff depends on how quickly the encoder's embedding space evolves during training.
51	
52	&lt;!-- Claim 2 wording fix: 2026-05-15 -->
53	&lt;!-- D041 dataflow-aware BM25 fix: 2026-05-15 -->
54	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "4aa19fba-678a-4360-98a3-f42d9544fd8b",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/discussion_v2.md",
      "content": "# 5. Discussion\n\n## 5.1 Relationship to Inference-Time Graph Methods\n\nA growing body of work leverages code structure graphs at inference time to improve LLM-based software engineering.\nCodexGraph (Liu et al., NAACL 2025) materializes a code property graph in a Neo4j database that LLM agents query via Cypher; RepoGraph (Ouyang et al., ICLR 2025) provides line-level code graph navigation as a plug-in for SE agents; LocAgent (Chen et al., ACL 2025) and RANGER (Shah et al., 2025) employ graph-guided multi-hop reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder (Liu et al., ASE 2024) and ARISE (Seddik & Fard, 2026) come closest to our work in incorporating data-flow information, but both are limited to intra-procedural scope.\n\nTable 5 summarizes the key dimensions of comparison. We highlight two axes along which StructFuse occupies a distinct position:\n\n**When structural information enters the pipeline.** Inference-time methods construct and query graphs per request, incurring latency proportional to graph complexity and—for agent-based systems—requiring multiple LLM calls per query. StructFuse amortizes all graph computation to training time: CodeQL extraction costs approximately 8.9 seconds per instance (~110 CPU-hours for 44K instances; Table 4), after which the trained encoder operates at standard embedding-lookup speed with zero graph overhead. For latency-sensitive, high-throughput retrieval scenarios, this cost model is substantially more favorable.\n\n**Depth of data-flow analysis.** Most inference-time graph methods use structural relations (call graphs, class hierarchies, import dependencies). GraphCoder incorporates control-flow and data-dependence graphs, and ARISE exposes statement-level def-use edges, but both operate within single procedures. StructFuse leverages CodeQL's bounded inter-procedural taint tracking (2-hop call-graph scope), capturing cross-function data-flow paths—e.g., a sanitizer that transforms data between a source and sink across call boundaries. This deeper semantic signal generates harder, more informative negatives than structural proximity alone.\n\n**Complementarity.** We emphasize that StructFuse and inference-time graph methods address different stages of the retrieval pipeline and are composable rather than competing. A StructFuse-trained encoder can serve as a first-stage retriever whose embeddings already encode data-flow semantics, reducing the search space for inference-time graph agents that perform targeted reranking. Conversely, systems like CodexGraph or LocAgent can refine StructFuse retrieval results through explicit graph navigation when maximum precision is required. The two paradigms are complementary: StructFuse internalizes general structural patterns during training, while inference-time methods provide case-specific structural reasoning during deployment.\n\n## 5.2 Representation Geometry and Strategy Effectiveness: An Exploratory Analysis\n\nWe present the following analysis as an exploratory observation derived from two encoders, not a validated mechanism.\n\nOur negative difficulty analysis (Section 4.4) suggests a hypothesis worth further investigation: the pretrained encoder's representation geometry may predict whether structure-grounded negatives will provide benefit beyond embedding-distance mining. Importantly, the three strategies differ in *selection method*—random sampling, cosine-similarity ranking in the pretrained embedding space (embedding-distance), and BM25 lexical ranking within CodeQL-identified structurally connected files (dataflow-aware)—while the analysis *evaluates* the resulting negatives' difficulty uniformly via pretrained encoder cosine similarity as a common metric.\n\nWhen the pretrained representation space is saturated—as observed for Qwen2.5-Coder-3B, where mean positive-pair cosine similarity reaches 0.986—the margin between positive and negative pairs is compressed (random margin = 0.074; embedding margin = 0.017). In this regime, all text-similarity-based negatives are clustered near the positive, and the encoder requires negatives drawn from an orthogonal signal dimension (structural disconnection) to learn meaningful discrimination. This is consistent with the +0.8pp R@1 improvement from dataflow-aware negatives over random baselines for Qwen (Table 2).\n\nWhen the representation space has healthy separation—as observed for StarCoder2-3B (pos\\_sim = 0.799, random margin = 0.194, 2.6× larger than Qwen)—embedding-distance mining alone provides a sufficient difficulty gradient, and dataflow negatives do not yield additional improvement (+1.6pp for embedding vs. random, but −0.5pp for dataflow vs. random; Table 2). The larger margins mean the encoder can still extract useful contrastive signal from text-similarity-based negatives without supplementary structural guidance.\n\nThis interaction between representation geometry and strategy effectiveness has a practical implication: practitioners can compute pos\\_sim on a held-out sample with their pretrained encoder (a single forward pass, requiring no training) to predict whether structure-grounded negatives are worth the extraction cost. We observe that pos\\_sim > 0.98 serves as an approximate threshold above which structural negatives provide conditional benefit, though we note this threshold is derived from two encoder observations and should be validated more broadly.\n\n## 5.3 Limitations\n\nWe identify several limitations of the current study that contextualize our findings:\n\n**Encoder scope.** Our experiments use two decoder-only 3B-parameter encoders (Qwen2.5-Coder-3B and StarCoder2-3B). While these models differ meaningfully in pretraining corpus and representation geometry—enabling our interaction analysis—generalizing to encoder-only architectures (e.g., CodeBERT), larger scales, or non-code domains requires further investigation.\n\n**Single task.** We evaluate on code retrieval with contrastive training. Whether structure-grounded negatives similarly benefit other code understanding tasks (fault localization, code summarization, clone detection) remains an open question, though the underlying principle—that inter-procedural data-flow provides an orthogonal signal to text similarity—is task-agnostic.\n\n**Language and tooling dependency.** Our pipeline relies on CodeQL for inter-procedural data-flow extraction and currently supports Python repositories only. Extending to other languages requires language-specific CodeQL queries, and the dependency on a commercial static analysis tool may limit reproducibility. We note that the methodology generalizes to any tool capable of inter-procedural data-flow analysis (e.g., Joern, Soot).\n\n**Static mining.** Our negative mining is performed once before training and remains fixed throughout. Dynamic re-mining—where negatives are refreshed each epoch using the current encoder's embeddings—could yield progressively harder negatives as the model improves. We do not evaluate this variant in the current work and acknowledge the static-vs.-dynamic mining confound as a limitation. We plan to address this in future revisions.\n\n**Structural data coverage.** CodeQL successfully extracts data-flow information for 36% of instances across 123 repositories (93.9% repo coverage; Table 4). The remaining instances fall back to embedding-distance negatives. While our results demonstrate that even partial structural coverage yields measurable improvements, higher extraction success rates would likely amplify the benefit.\n\n## 5.4 Future Work\n\nWe identify three directions that follow naturally from our findings, while noting that each requires empirical validation before strong claims can be made:\n\n**Hybrid retrieval pipelines.** Integrating a StructFuse-trained encoder as the first-stage retriever within inference-time graph systems (e.g., CodexGraph, RANGER) could combine the efficiency of embedding-based retrieval with the precision of runtime graph navigation. Evaluating such pipelines on end-to-end benchmarks like SWE-bench would quantify the practical value of this complementarity.\n\n**Representation-guided strategy selection.** Our observation that pos\\_sim appears to correlate with strategy effectiveness suggests an automated protocol: given a new encoder, compute representation geometry statistics on a calibration set, then select the appropriate negative mining strategy without exhaustive ablation. Validating this protocol across a wider range of encoders and tasks is a natural next step.\n\n**Extension to dynamic and multi-lingual settings.** Adapting the pipeline to dynamically re-mine negatives during training, and extending CodeQL queries to languages beyond Python, would address two of our current limitations. For dynamic mining, the key design question is the re-mining frequency—epoch-level re-mining requires repeated CodeQL extraction, and the cost-benefit tradeoff depends on how quickly the encoder's embedding space evolves during training.\n\n&lt;!-- Claim 2 wording fix: 2026-05-15 -->\n&lt;!-- D041 dataflow-aware BM25 fix: 2026-05-15 -->\n",
      "numLines": 54,
      "startLine": 1,
      "totalLines": 54
    }
  }
}
```

</details>

---

### Assistant

_source line 54_

<details><summary>Logged reasoning block</summary>

```text
Good, the discussion_v2.md in paper_drafts looks correct. Now let me copy this content to the _project/paper/ version. The _project/paper/ version is the older one without Claim 2 fixes. I should overwrite it with the paper_drafts version which has both fixes.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "567800a2-d040-4c81-9e32-471f087e2774",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ci2Xwd51emVHCWyB2pcXSW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2281,
      "cache_read_input_tokens": 46943,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2281
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

_source line 55_

Now copy the updated content to the `_project/paper/` copies.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "415af14e-e8c4-4ceb-9539-2a4fbc026d88",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ci2Xwd51emVHCWyB2pcXSW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2281,
      "cache_read_input_tokens": 46943,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2281
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

<details open><summary>🔧 Tool call — Bash · `toolu_017vKd1ND31hsRggDYokwWwS`</summary>

```json
{
  "command": "cp /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/discussion_v2.md /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/_project/paper/discussion_v2.md",
  "description": "Sync discussion_v2.md to _project/paper/"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "be464777-b8da-44cd-b3b3-843d4356dc3c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ci2Xwd51emVHCWyB2pcXSW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2281,
      "cache_read_input_tokens": 46943,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2281
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

_source line 57 · 2026-05-15T02:13:31.470Z_

<details><summary>↩ Tool result · `toolu_017vKd1ND31hsRggDYokwWwS`</summary>

```text
(Bash completed with no output)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "16812c42-70bb-47b0-bbc0-d845e09c3fa1",
  "tool_use_result": {
    "stdout": "",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": true
  }
}
```

</details>

---

### Tool call

_source line 58_

<details open><summary>🔧 Tool call — Bash · `toolu_01TK6v8bdU93HRqAhWXT8RXN`</summary>

```json
{
  "command": "cp /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/_project/paper/related_work_v1.md",
  "description": "Sync related_work_v1.md to _project/paper/"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "a6e3ae49-3beb-4ba6-8ba6-81c29e28397a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ci2Xwd51emVHCWyB2pcXSW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2281,
      "cache_read_input_tokens": 46943,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2281
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

_source line 59 · 2026-05-15T02:13:32.459Z_

<details><summary>↩ Tool result · `toolu_01TK6v8bdU93HRqAhWXT8RXN`</summary>

```text
(Bash completed with no output)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "b3c6819a-afae-449e-b5d5-0d46d0d1b173",
  "tool_use_result": {
    "stdout": "",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": true
  }
}
```

</details>

---

### Assistant

_source line 60_

修改完成。

**discussion_v2.md §5.2** — 在分析开头增加了一句，明确区分三种策略的 *选样本方法* 和 *评估难度方法*：

> "the three strategies differ in *selection method*—random sampling, cosine-similarity ranking in the pretrained embedding space (embedding-distance), and BM25 lexical ranking within CodeQL-identified structurally connected files (dataflow-aware)—while the analysis *evaluates* the resulting negatives' difficulty uniformly via pretrained encoder cosine similarity as a common metric."

**related_work_v1.md** — 无混淆问题（描述为 "structure-grounded negatives derived from inter-procedural data-flow analysis"，准确且不涉及选样本机制细节）。

两个文件均已添加 `&lt;!-- D041 dataflow-aware BM25 fix: 2026-05-15 -->` 标记，Claim 2 修改未被回退。`_project/paper/` 副本已同步。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "uuid": "ad568b23-233d-461a-bdd7-234f63f31523",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KtrMHRSWyhtGarY2kz8xMK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 488,
      "cache_read_input_tokens": 49224,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 488
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

_source line 61_

修改完成。

**discussion_v2.md §5.2** — 在分析开头增加了一句，明确区分三种策略的 *选样本方法* 和 *评估难度方法*：

> "the three strategies differ in *selection method*—random sampling, cosine-similarity ranking in the pretrained embedding space (embedding-distance), and BM25 lexical ranking within CodeQL-identified structurally connected files (dataflow-aware)—while the analysis *evaluates* the resulting negatives' difficulty uniformly via pretrained encoder cosine similarity as a common metric."

**related_work_v1.md** — 无混淆问题（描述为 "structure-grounded negatives derived from inter-procedural data-flow analysis"，准确且不涉及选样本机制细节）。

两个文件均已添加 `&lt;!-- D041 dataflow-aware BM25 fix: 2026-05-15 -->` 标记，Claim 2 修改未被回退。`_project/paper/` 副本已同步。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 204100,
  "duration_api_ms": 204877,
  "num_turns": 21,
  "stop_reason": "end_turn",
  "session_id": "ad2fcb25-ffc1-4279-8060-d216590dd34d",
  "total_cost_usd": 0.6996872500000001,
  "usage": {
    "input_tokens": 23,
    "cache_creation_input_tokens": 38265,
    "cache_read_input_tokens": 512200,
    "output_tokens": 8112,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 38265,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 271,
        "cache_read_input_tokens": 49224,
        "cache_creation_input_tokens": 488,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 488
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1421,
      "outputTokens": 19,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.001516,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 23,
      "outputTokens": 8112,
      "cacheReadInputTokens": 512200,
      "cacheCreationInputTokens": 38265,
      "webSearchRequests": 0,
      "costUSD": 0.69817125,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "564402dd-62f7-4a7e-a6b6-abe20320130c"
}
```

</details>

---
