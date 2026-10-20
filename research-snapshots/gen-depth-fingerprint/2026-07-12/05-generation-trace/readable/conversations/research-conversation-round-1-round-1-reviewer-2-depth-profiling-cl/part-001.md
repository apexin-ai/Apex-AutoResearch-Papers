# Research conversation: [Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 2 **你的审查侧重：新颖性 + 论文完整性 + 写作质量 + 格式合规** ### 论文信息 - **标题**: Depth Profiling: Cl — Part 1 of 5

**Depth Profiling: Classifying Recursive Generation Depth in Base-Model LLM Text (July export snapshot)** · Conversation logs

[Transcript overview](../research-conversation-round-1-round-1-reviewer-2-depth-profiling-cl.md) · [Part 2 →](part-002.md) · [Structured JSON](../../../sessions/76/76518a3f87d494b03daa.json)

## Before a recorded user message

## Before a recorded user message

2 recorded events


### Runtime record

_source line 1 · 2026-05-19T06:15:24.567Z_

````json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-19T06:15:24.567Z",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "content": "[Round 1 审稿请求]:\n## Round 1 审稿任务 — Reviewer 2\n\n**你的审查侧重：新颖性 + 论文完整性 + 写作质量 + 格式合规**\n\n### 论文信息\n- **标题**: Depth Profiling: Classifying Recursive Generation Depth in Base LLM Text Chains\n- **路径**: `projects/gen-depth-fingerprint/artifacts/_project/paper/main.tex`\n- **目标 Venue**: EMNLP 2026（通过 ACL Rolling Review 提交）\n- **截止日期**: 2026-05-25\n\n### Venue 格式要求（实时搜索确认）\n- **页数限制**: Long paper 8 页正文 + unlimited references/appendix\n- **模板**: Official ACL style template (acl-org/acl-style-files)，必须使用 `[review]` 选项\n- **匿名规则**: Double-blind（作者不可见审稿人，反之亦然）\n- **Limitations section**: 必须有，不计入页数限制\n- **Responsible NLP Checklist**: 必须填写，不完整可能 desk reject\n- **附录**: 放在 references 之后，不计入页数，必须 double-column 格式\n- **Ethics section**: 可选，不计入页数\n- **2025年1月起更新**: 图表字体≥7pt，limitations/ethics 不计入页数，附录必须 double-column\n\n### EMNLP 2026 评分标准（ARR 统一审稿）\n5 = Consider for Award（约前2.5%），4.5 = Borderline Award，4 = Conference（可被主会议接收），3.5 = Borderline Conference，3 = Findings（可被Findings接收），2.5 = Borderline Findings，2 = Resubmit next cycle，1.5 = Resubmit after next cycle，1 = Do not resubmit\n\n### 你的审查重点\n\n1. **新颖性评估**：\n   - \"Generation depth classification\" 作为任务定义的新颖性如何？\n   - DDR（Differential Depth Response）作为 empirical finding 的贡献程度？\n   - 与三篇并行工作（Broken Telephone, Markovian Chains, Attractor Cycles）的区分度？\n   - DDR 是否只是已知 location-shift 现象的重新命名？\n   - 对于 EMNLP Findings 是否有足够的贡献？\n\n2. **论文完整性**：\n   - Abstract → Introduction → Method → Results → Discussion → Conclusion 叙事主线是否一致？\n   - Contribution claims 是否都有对应实验支撑？\n   - Related Work 覆盖是否充分？是否有重要遗漏？\n   - Limitations 是否诚实全面？\n   - 附录内容是否在正文中被引用且融入叙事？\n\n3. **写作质量**（按 CLAUDE.md paper-writing-norms 严格审查）：\n   - 是否有 AI 写作痕迹？（em-dash/en-dash、-ing 短语结尾、过度分段、过渡词堆叠）\n   - 专有名词是否首次出现即定义？\n   - Abstract 是否在 150-250 words？四个必答问题是否回答？\n   - Introduction 五段结构是否完整？\n   - 每条 Contribution 是否有对应 section/table 支撑？\n\n4. **格式合规**：\n   - 正文是否在 8 页以内？\n   - 模板是否正确（`\\usepackage[review]{acl}`）？\n   - 匿名化是否完整（作者 \"Anonymous\"，无自引泄露）？\n   - 行号是否开启？\n   - 参考文献格式是否一致？\n   - 图表字体是否 ≥ 7pt？\n   - 附录是否 double-column？\n\n5. **引用充足度**：\n   - 直接相关方法、baseline 论文、评测 benchmark 论文、理论基础是否都有引用？\n   - 引用数量是否与 EMNLP 录用论文量级一致？\n\n请按以下格式输出审稿报告：\n```\n## Summary\n[2-3句概述]\n\n## Strengths\n[逐条列出，标注 S1, S2, ...]\n\n## Weaknesses\n[逐条列出，标注 W1, W2, ...，按严重程度排序]\n[每条标注严重级别：[Critical] / [Major] / [Minor]]\n\n## Questions\n[需要作者澄清的问题，标注 Q1, Q2, ...]\n\n## Missing References\n[遗漏的重要相关工作]\n\n## Overall Assessment\n[评分 + 置信度 + 简要理由]\n\n## Detailed Comments\n[逐节详细意见]\n```"
}
````

---


### Runtime record

_source line 2 · 2026-05-19T06:15:24.570Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-19T06:15:24.570Z",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


## Round 1

## Round 1

152 recorded events


### User

_source line 3 · 2026-05-19T06:15:24.602Z_

[Round 1 审稿请求]:
## Round 1 审稿任务 — Reviewer 2

**你的审查侧重：新颖性 + 论文完整性 + 写作质量 + 格式合规**

### 论文信息
- **标题**: Depth Profiling: Classifying Recursive Generation Depth in Base LLM Text Chains
- **路径**: `projects/gen-depth-fingerprint/artifacts/_project/paper/main.tex`
- **目标 Venue**: EMNLP 2026（通过 ACL Rolling Review 提交）
- **截止日期**: 2026-05-25

### Venue 格式要求（实时搜索确认）
- **页数限制**: Long paper 8 页正文 + unlimited references/appendix
- **模板**: Official ACL style template (acl-org/acl-style-files)，必须使用 `[review]` 选项
- **匿名规则**: Double-blind（作者不可见审稿人，反之亦然）
- **Limitations section**: 必须有，不计入页数限制
- **Responsible NLP Checklist**: 必须填写，不完整可能 desk reject
- **附录**: 放在 references 之后，不计入页数，必须 double-column 格式
- **Ethics section**: 可选，不计入页数
- **2025年1月起更新**: 图表字体≥7pt，limitations/ethics 不计入页数，附录必须 double-column

### EMNLP 2026 评分标准（ARR 统一审稿）
5 = Consider for Award（约前2.5%），4.5 = Borderline Award，4 = Conference（可被主会议接收），3.5 = Borderline Conference，3 = Findings（可被Findings接收），2.5 = Borderline Findings，2 = Resubmit next cycle，1.5 = Resubmit after next cycle，1 = Do not resubmit

### 你的审查重点

1. **新颖性评估**：
   - "Generation depth classification" 作为任务定义的新颖性如何？
   - DDR（Differential Depth Response）作为 empirical finding 的贡献程度？
   - 与三篇并行工作（Broken Telephone, Markovian Chains, Attractor Cycles）的区分度？
   - DDR 是否只是已知 location-shift 现象的重新命名？
   - 对于 EMNLP Findings 是否有足够的贡献？

2. **论文完整性**：
   - Abstract → Introduction → Method → Results → Discussion → Conclusion 叙事主线是否一致？
   - Contribution claims 是否都有对应实验支撑？
   - Related Work 覆盖是否充分？是否有重要遗漏？
   - Limitations 是否诚实全面？
   - 附录内容是否在正文中被引用且融入叙事？

3. **写作质量**（按 CLAUDE.md paper-writing-norms 严格审查）：
   - 是否有 AI 写作痕迹？（em-dash/en-dash、-ing 短语结尾、过度分段、过渡词堆叠）
   - 专有名词是否首次出现即定义？
   - Abstract 是否在 150-250 words？四个必答问题是否回答？
   - Introduction 五段结构是否完整？
   - 每条 Contribution 是否有对应 section/table 支撑？

4. **格式合规**：
   - 正文是否在 8 页以内？
   - 模板是否正确（`\usepackage[review]{acl}`）？
   - 匿名化是否完整（作者 "Anonymous"，无自引泄露）？
   - 行号是否开启？
   - 参考文献格式是否一致？
   - 图表字体是否 ≥ 7pt？
   - 附录是否 double-column？

5. **引用充足度**：
   - 直接相关方法、baseline 论文、评测 benchmark 论文、理论基础是否都有引用？
   - 引用数量是否与 EMNLP 录用论文量级一致？

请按以下格式输出审稿报告：
```
## Summary
[2-3句概述]

## Strengths
[逐条列出，标注 S1, S2, ...]

## Weaknesses
[逐条列出，标注 W1, W2, ...，按严重程度排序]
[每条标注严重级别：[Critical] / [Major] / [Minor]]

## Questions
[需要作者澄清的问题，标注 Q1, Q2, ...]

## Missing References
[遗漏的重要相关工作]

## Overall Assessment
[评分 + 置信度 + 简要理由]

## Detailed Comments
[逐节详细意见]
```

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "010b0237-c736-455d-9459-c6f3cb7df071",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Runtime record

_source line 4 · 2026-05-19T06:15:24.601Z_

```json
{
  "parentUuid": "010b0237-c736-455d-9459-c6f3cb7df071",
  "isSidechain": false,
  "attachment": {
    "type": "deferred_tools_delta",
    "addedNames": [
      "AskUserQuestion",
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterPlanMode",
      "EnterWorktree",
      "ExitPlanMode",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskOutput",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director",
      "mcp__agent-ml-research__verify_references"
    ],
    "addedLines": [
      "AskUserQuestion",
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterPlanMode",
      "EnterWorktree",
      "ExitPlanMode",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskOutput",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director",
      "mcp__agent-ml-research__verify_references"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "e34683dc-bd8e-4c55-bbad-7e69d2658c57",
  "timestamp": "2026-05-19T06:15:24.601Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---


### Runtime record

_source line 5 · 2026-05-19T06:15:24.601Z_

```json
{
  "parentUuid": "e34683dc-bd8e-4c55-bbad-7e69d2658c57",
  "isSidechain": false,
  "attachment": {
    "type": "mcp_instructions_delta",
    "addedNames": [
      "agent-ml-research"
    ],
    "addedBlocks": [
      "## agent-ml-research\nML research experiment management tools"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "58c0ea8d-6cb5-4d83-88b3-9e2facbb04f6",
  "timestamp": "2026-05-19T06:15:24.601Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---


### Runtime record

_source line 6 · 2026-05-19T06:15:24.601Z_

```json
{
  "parentUuid": "58c0ea8d-6cb5-4d83-88b3-9e2facbb04f6",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "6e5aac00-1bbe-4233-b717-8ca9d40f3ea9",
  "timestamp": "2026-05-19T06:15:24.601Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---


### Runtime record

_source line 7_

```json
{
  "type": "ai-title",
  "aiTitle": "Review depth profiling LLM paper for EMNLP",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Assistant

_source line 8 · 2026-05-19T06:15:27.939Z_

我开始审稿。先加载 session 启动 skill，然后读取论文并搜索 reviewer guidelines。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6e5aac00-1bbe-4233-b717-8ca9d40f3ea9",
  "isSidechain": false,
  "requestId": "req_011CbBSJuQqSPC1ykvoxZieK",
  "type": "assistant",
  "uuid": "d21c32d2-d048-4dfc-b04a-e573574582d8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01M1Bpbd2B2sdMTdimrdaiKk",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17196,
      "cache_read_input_tokens": 11841,
      "output_tokens": 130,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17196,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 130,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 17196,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17196
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

_source line 9 · 2026-05-19T06:15:29.469Z_

<details open><summary>🔧 Tool call — Read · `toolu_01JCBfzwi3jPH4roZbKx3jza`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/skills/review-reviewer-session-start.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d21c32d2-d048-4dfc-b04a-e573574582d8",
  "isSidechain": false,
  "requestId": "req_011CbBSJuQqSPC1ykvoxZieK",
  "type": "assistant",
  "uuid": "17e7d3ff-c7d9-4f14-a19d-1ab833b30613",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01M1Bpbd2B2sdMTdimrdaiKk",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 17196,
      "cache_read_input_tokens": 11841,
      "output_tokens": 130,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 17196,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 130,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 17196,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 17196
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

_source line 10 · 2026-05-19T06:15:29.487Z_

<details><summary>↩ Tool result · reported error · `toolu_01JCBfzwi3jPH4roZbKx3jza`</summary>

```text
File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "17e7d3ff-c7d9-4f14-a19d-1ab833b30613",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "90781dcb-cf07-4ad7-9153-6ab84c20e5ba",
  "toolUseResult": "Error: File does not exist. Note: your current working directory is /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41.",
  "sourceToolAssistantUUID": "17e7d3ff-c7d9-4f14-a19d-1ab833b30613",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 11 · 2026-05-19T06:15:32.472Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01Ky5yN2mL18FgCm7n74Ea8s`</summary>

```json
{
  "pattern": "**/review-reviewer-session-start.skill.md",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "90781dcb-cf07-4ad7-9153-6ab84c20e5ba",
  "isSidechain": false,
  "requestId": "req_011CbBSKGP9x8zTSCkupoLwu",
  "type": "assistant",
  "uuid": "3313b697-bcd3-4f99-8306-161cb5adbe14",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Cq2dzSCfv4RxnQNEghmrbx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 208,
      "cache_read_input_tokens": 29037,
      "output_tokens": 99,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 208,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 99,
          "cache_read_input_tokens": 29037,
          "cache_creation_input_tokens": 208,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 208
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 12 · 2026-05-19T06:15:32.511Z_

<details><summary>↩ Tool result · `toolu_01Ky5yN2mL18FgCm7n74Ea8s`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3313b697-bcd3-4f99-8306-161cb5adbe14",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "bef0becc-48e7-4575-b9eb-a15b2c5dee9e",
  "toolUseResult": {
    "filenames": [],
    "durationMs": 32,
    "numFiles": 0,
    "truncated": false
  },
  "sourceToolAssistantUUID": "3313b697-bcd3-4f99-8306-161cb5adbe14",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 13 · 2026-05-19T06:15:38.772Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01ToJRKpn783bC4HgHBVJzZi`</summary>

```json
{
  "pattern": "**/*.skill.md",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bef0becc-48e7-4575-b9eb-a15b2c5dee9e",
  "isSidechain": false,
  "requestId": "req_011CbBSKV8s2fpCbKzfmbP8k",
  "type": "assistant",
  "uuid": "0141b5ea-9b84-4e66-a6cc-594211b2f4ad",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LHtbiXjLHfWSfqAmHf3LdD",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 322,
      "cache_read_input_tokens": 29037,
      "output_tokens": 91,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 322,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 91,
          "cache_read_input_tokens": 29037,
          "cache_creation_input_tokens": 322,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 322
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "previous_message_not_found"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 14 · 2026-05-19T06:15:38.830Z_

<details><summary>↩ Tool result · `toolu_01ToJRKpn783bC4HgHBVJzZi`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0141b5ea-9b84-4e66-a6cc-594211b2f4ad",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "2c7d916f-97d3-4dcf-aff0-59f411aaf002",
  "toolUseResult": {
    "filenames": [],
    "durationMs": 54,
    "numFiles": 0,
    "truncated": false
  },
  "sourceToolAssistantUUID": "0141b5ea-9b84-4e66-a6cc-594211b2f4ad",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Assistant

_source line 15 · 2026-05-19T06:15:42.891Z_

<details><summary>Logged reasoning block</summary>

```text
The skill files don't exist. Let me proceed directly with the review task. I need to:

1. Read the paper (main.tex)
2. Search for ACL ARR reviewer guidelines
3. Check the paper PDF images for visual review

Let me start by reading the paper and searching for guidelines.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2c7d916f-97d3-4dcf-aff0-59f411aaf002",
  "isSidechain": false,
  "requestId": "req_011CbBSKxFGiBn3Xjo3Adrx1",
  "type": "assistant",
  "uuid": "38386aea-0373-40c5-82a1-63af1dcdc135",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PFaBnC6beBPLjcFXjQUmS3",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 106,
      "cache_read_input_tokens": 29359,
      "output_tokens": 240,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 106,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 240,
          "cache_read_input_tokens": 29359,
          "cache_creation_input_tokens": 106,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 106
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


### Assistant

_source line 16 · 2026-05-19T06:15:43.870Z_

Skill 文件不存在，直接开始审稿。先并行读取论文和搜索 reviewer guidelines。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "38386aea-0373-40c5-82a1-63af1dcdc135",
  "isSidechain": false,
  "requestId": "req_011CbBSKxFGiBn3Xjo3Adrx1",
  "type": "assistant",
  "uuid": "70727083-1320-4f46-9142-fc17ef698bb7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PFaBnC6beBPLjcFXjQUmS3",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 106,
      "cache_read_input_tokens": 29359,
      "output_tokens": 240,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 106,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 240,
          "cache_read_input_tokens": 29359,
          "cache_creation_input_tokens": 106,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 106
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

_source line 17 · 2026-05-19T06:15:45.473Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_017Vt1Uh793LdkWtzMN1wB8A`</summary>

```json
{
  "query": "select:WebSearch,WebFetch,mcp__agent-ml-research__pdf_to_images,mcp__agent-ml-research__review_reviewer_post_to_director,mcp__agent-ml-research__verify_references",
  "max_results": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "70727083-1320-4f46-9142-fc17ef698bb7",
  "isSidechain": false,
  "requestId": "req_011CbBSKxFGiBn3Xjo3Adrx1",
  "type": "assistant",
  "uuid": "1a0a284c-057f-462e-967f-35fb9ece1134",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PFaBnC6beBPLjcFXjQUmS3",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 106,
      "cache_read_input_tokens": 29359,
      "output_tokens": 240,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 106,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 240,
          "cache_read_input_tokens": 29359,
          "cache_creation_input_tokens": 106,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 106
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

_source line 18 · 2026-05-19T06:15:45.482Z_

<details><summary>↩ Tool result · `toolu_017Vt1Uh793LdkWtzMN1wB8A`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "WebSearch"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "WebFetch"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__pdf_to_images"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__review_reviewer_post_to_director"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__verify_references"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1a0a284c-057f-462e-967f-35fb9ece1134",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "677539cb-5a1d-4006-92a9-c90253494e23",
  "toolUseResult": {
    "matches": [
      "WebSearch",
      "WebFetch",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__review_reviewer_post_to_director",
      "mcp__agent-ml-research__verify_references"
    ],
    "query": "select:WebSearch,WebFetch,mcp__agent-ml-research__pdf_to_images,mcp__agent-ml-research__review_reviewer_post_to_director,mcp__agent-ml-research__verify_references",
    "total_deferred_tools": 23
  },
  "sourceToolAssistantUUID": "1a0a284c-057f-462e-967f-35fb9ece1134",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Assistant

_source line 19 · 2026-05-19T06:15:57.357Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the paper and search for reviewer guidelines in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "677539cb-5a1d-4006-92a9-c90253494e23",
  "isSidechain": false,
  "requestId": "req_011CbBSLSmGLrpoQKTGeRAcS",
  "type": "assistant",
  "uuid": "74361c05-f745-4912-9adb-d025a30e0dc9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017n2TN3YoPYyccqqdYYvggc",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2235,
      "cache_read_input_tokens": 29465,
      "output_tokens": 295,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2235,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 295,
          "cache_read_input_tokens": 29465,
          "cache_creation_input_tokens": 2235,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2235
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


### Assistant

_source line 20 · 2026-05-19T06:15:58.313Z_

开始并行读取论文、搜索 reviewer guidelines、验证引用。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "74361c05-f745-4912-9adb-d025a30e0dc9",
  "isSidechain": false,
  "requestId": "req_011CbBSLSmGLrpoQKTGeRAcS",
  "type": "assistant",
  "uuid": "eedaf40c-95bb-4c5a-b0f9-8006076d7e5f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017n2TN3YoPYyccqqdYYvggc",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2235,
      "cache_read_input_tokens": 29465,
      "output_tokens": 295,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2235,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 295,
          "cache_read_input_tokens": 29465,
          "cache_creation_input_tokens": 2235,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2235
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

_source line 21 · 2026-05-19T06:16:00.199Z_

<details open><summary>🔧 Tool call — Read · `toolu_0181xEyjVgZz2yD9dsUw2LEK`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "eedaf40c-95bb-4c5a-b0f9-8006076d7e5f",
  "isSidechain": false,
  "requestId": "req_011CbBSLSmGLrpoQKTGeRAcS",
  "type": "assistant",
  "uuid": "300909e6-8e03-4dfc-a031-da13d3a979b9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017n2TN3YoPYyccqqdYYvggc",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2235,
      "cache_read_input_tokens": 29465,
      "output_tokens": 295,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2235,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 295,
          "cache_read_input_tokens": 29465,
          "cache_creation_input_tokens": 2235,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2235
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

_source line 22 · 2026-05-19T06:16:00.210Z_

<details><summary>↩ Tool result · `toolu_0181xEyjVgZz2yD9dsUw2LEK`</summary>

```text
1	% EMNLP 2026 ARR Submission — ACL 2023 Template
2	\documentclass[11pt]{article}
3	\usepackage[review]{acl}
4	\usepackage{times}
5	\usepackage{latexsym}
6	\usepackage{graphicx}
7	\usepackage{booktabs}
8	\usepackage{enumitem}
9	\usepackage{amsmath}
10	\usepackage{amssymb}
11	\usepackage{lineno}
12	\usepackage{placeins}
13	\usepackage{multirow}
14	\linenumbers
15	
16	\graphicspath{{../chart/}}
17	
18	\title{Depth Profiling: Classifying Recursive Generation Depth\\in Base LLM Text Chains}
19	
20	\author{Anonymous}
21	
22	\begin{document}
23	\maketitle
24	
25	\input{abstract}
26	
27	\input{introduction}
28	\input{related_work}
29	\input{method}
30	\input{results}
31	
32	\input{discussion}
33	\input{conclusion}
34	\input{limitations}
35	\input{ethics}
36	
37	\bibliography{references}
38	
39	\appendix
40	
41	\noindent\textbf{Note:} Unless otherwise stated, appendix experiments use the original six-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B/8B).
42	Main paper results (\S\ref{sec:results}) use the full eight-generator set (adding Llama-3.2-3B and Mistral-7B-v0.3).
43	
44	\input{appendix_dataset_stats}
45	\FloatBarrier
46	
47	\section{Length Confound Analysis}
48	\label{app:length}
49	\input{appendix_length}
50	\FloatBarrier
51	
52	\section{Prompt Type Generalization}
53	\label{app:prompt-type}
54	\input{appendix_prompt_type}
55	\FloatBarrier
56	
57	\section{Finer-Grained Depth Classification}
58	\label{app:finer-depth}
59	\input{appendix_finer_depth}
60	\FloatBarrier
61	
62	\section{End-to-End Depth Classification (QLoRA)}
63	\label{app:qlora}
64	\input{appendix_qlora}
65	\FloatBarrier
66	
67	\section{Leave-One-Feature-Out Analysis}
68	\label{app:lofo}
69	\input{appendix_lofo}
70	\FloatBarrier
71	
72	\section{Confusion Matrix}
73	\label{app:confusion}
74	\input{appendix_confusion_matrix}
75	\FloatBarrier
76	
77	\section{Classifier Sensitivity}
78	\label{app:classifier}
79	\input{appendix_classifier}
80	\FloatBarrier
81	
82	\section{Robustness to Text Perturbation}
83	\label{app:human-edit}
84	\input{appendix_human_edit}
85	\FloatBarrier
86	
87	\section{Cross-Domain Generalization}
88	\label{app:domain}
89	\input{appendix_domain}
90	\FloatBarrier
91	
92	\section{Instruction-Tuned Model Analysis}
93	\label{app:instruct}
94	\input{appendix_instruct}
95	\FloatBarrier
96	
97	\section{Error Analysis of Binary Classification}
98	\label{app:error-analysis}
99	\input{appendix_error_analysis}
100	\FloatBarrier
101	
102	\section{Downstream Utility}
103	\label{app:downstream}
104	\input{appendix_downstream}
105	\FloatBarrier
106	
107	\section{Cross-Model Chain Per-Class Detail}
108	\label{app:cross-model-detail}
109	\input{appendix_cross_model_detail}
110	\FloatBarrier
111	
112	\section{Feature Distribution Analysis}
113	\label{app:feature-distributions}
114	\input{appendix_feature_distributions}
115	\FloatBarrier
116	
117	\section{Cross-Temperature Transfer}
118	\label{app:cross-temp}
119	\input{appendix_cross_temp}
120	\FloatBarrier
121	
122	\section{Feature Ablation}
123	\label{app:ablation-table}
124	\input{appendix_ablation}
125	
126	\begin{figure}[h]
127	\centering
128	\includegraphics[width=\columnwidth]{fig3_baseline_comparison.pdf}
129	\caption{LOGO binary F1 (gen-1 vs.\ gen-2+, 8-gen pooled) with inference cost. Ensembles achieve marginally higher F1 at 2.4$\times$ inference time and 3.2$\times$ GPU memory; individual detectors vary widely when repurposed for depth.}
130	\label{fig:baseline-ci}
131	\end{figure}
132	\FloatBarrier
133	
134	\input{appendix_feature_correlation}
135	\FloatBarrier
136	
137	\section{Cross-Family Reference Models}
138	\label{app:cross-ref}
139	\input{table4}
140	\FloatBarrier
141	
142	\input{appendix_seed_control}
143	\FloatBarrier
144	
145	\input{appendix_tost}
146	\FloatBarrier
147	
148	\section{DDR Partition Validation}
149	\label{app:ddr-validation}
150	\input{appendix_ddr_validation}
151	\FloatBarrier
152	
153	\section{Generator Subset Summary}
154	\label{app:gen-subsets-section}
155	\input{appendix_generator_subsets}
156	\FloatBarrier
157	
158	\input{appendix_qualitative_examples}
159	
160	\end{document}
161	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "300909e6-8e03-4dfc-a031-da13d3a979b9",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "eb724374-30dc-4e1b-b3be-cee840e48074",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.tex",
      "content": "% EMNLP 2026 ARR Submission — ACL 2023 Template\n\\documentclass[11pt]{article}\n\\usepackage[review]{acl}\n\\usepackage{times}\n\\usepackage{latexsym}\n\\usepackage{graphicx}\n\\usepackage{booktabs}\n\\usepackage{enumitem}\n\\usepackage{amsmath}\n\\usepackage{amssymb}\n\\usepackage{lineno}\n\\usepackage{placeins}\n\\usepackage{multirow}\n\\linenumbers\n\n\\graphicspath{{../chart/}}\n\n\\title{Depth Profiling: Classifying Recursive Generation Depth\\\\in Base LLM Text Chains}\n\n\\author{Anonymous}\n\n\\begin{document}\n\\maketitle\n\n\\input{abstract}\n\n\\input{introduction}\n\\input{related_work}\n\\input{method}\n\\input{results}\n\n\\input{discussion}\n\\input{conclusion}\n\\input{limitations}\n\\input{ethics}\n\n\\bibliography{references}\n\n\\appendix\n\n\\noindent\\textbf{Note:} Unless otherwise stated, appendix experiments use the original six-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B/8B).\nMain paper results (\\S\\ref{sec:results}) use the full eight-generator set (adding Llama-3.2-3B and Mistral-7B-v0.3).\n\n\\input{appendix_dataset_stats}\n\\FloatBarrier\n\n\\section{Length Confound Analysis}\n\\label{app:length}\n\\input{appendix_length}\n\\FloatBarrier\n\n\\section{Prompt Type Generalization}\n\\label{app:prompt-type}\n\\input{appendix_prompt_type}\n\\FloatBarrier\n\n\\section{Finer-Grained Depth Classification}\n\\label{app:finer-depth}\n\\input{appendix_finer_depth}\n\\FloatBarrier\n\n\\section{End-to-End Depth Classification (QLoRA)}\n\\label{app:qlora}\n\\input{appendix_qlora}\n\\FloatBarrier\n\n\\section{Leave-One-Feature-Out Analysis}\n\\label{app:lofo}\n\\input{appendix_lofo}\n\\FloatBarrier\n\n\\section{Confusion Matrix}\n\\label{app:confusion}\n\\input{appendix_confusion_matrix}\n\\FloatBarrier\n\n\\section{Classifier Sensitivity}\n\\label{app:classifier}\n\\input{appendix_classifier}\n\\FloatBarrier\n\n\\section{Robustness to Text Perturbation}\n\\label{app:human-edit}\n\\input{appendix_human_edit}\n\\FloatBarrier\n\n\\section{Cross-Domain Generalization}\n\\label{app:domain}\n\\input{appendix_domain}\n\\FloatBarrier\n\n\\section{Instruction-Tuned Model Analysis}\n\\label{app:instruct}\n\\input{appendix_instruct}\n\\FloatBarrier\n\n\\section{Error Analysis of Binary Classification}\n\\label{app:error-analysis}\n\\input{appendix_error_analysis}\n\\FloatBarrier\n\n\\section{Downstream Utility}\n\\label{app:downstream}\n\\input{appendix_downstream}\n\\FloatBarrier\n\n\\section{Cross-Model Chain Per-Class Detail}\n\\label{app:cross-model-detail}\n\\input{appendix_cross_model_detail}\n\\FloatBarrier\n\n\\section{Feature Distribution Analysis}\n\\label{app:feature-distributions}\n\\input{appendix_feature_distributions}\n\\FloatBarrier\n\n\\section{Cross-Temperature Transfer}\n\\label{app:cross-temp}\n\\input{appendix_cross_temp}\n\\FloatBarrier\n\n\\section{Feature Ablation}\n\\label{app:ablation-table}\n\\input{appendix_ablation}\n\n\\begin{figure}[h]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig3_baseline_comparison.pdf}\n\\caption{LOGO binary F1 (gen-1 vs.\\ gen-2+, 8-gen pooled) with inference cost. Ensembles achieve marginally higher F1 at 2.4$\\times$ inference time and 3.2$\\times$ GPU memory; individual detectors vary widely when repurposed for depth.}\n\\label{fig:baseline-ci}\n\\end{figure}\n\\FloatBarrier\n\n\\input{appendix_feature_correlation}\n\\FloatBarrier\n\n\\section{Cross-Family Reference Models}\n\\label{app:cross-ref}\n\\input{table4}\n\\FloatBarrier\n\n\\input{appendix_seed_control}\n\\FloatBarrier\n\n\\input{appendix_tost}\n\\FloatBarrier\n\n\\section{DDR Partition Validation}\n\\label{app:ddr-validation}\n\\input{appendix_ddr_validation}\n\\FloatBarrier\n\n\\section{Generator Subset Summary}\n\\label{app:gen-subsets-section}\n\\input{appendix_generator_subsets}\n\\FloatBarrier\n\n\\input{appendix_qualitative_examples}\n\n\\end{document}\n",
      "numLines": 161,
      "startLine": 1,
      "totalLines": 161
    }
  },
  "sourceToolAssistantUUID": "300909e6-8e03-4dfc-a031-da13d3a979b9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 23 · 2026-05-19T06:16:01.180Z_

<details open><summary>🔧 Tool call — WebSearch · `toolu_01G5BRVEkMeDFyhTdM5h3z8s`</summary>

```json
{
  "query": "ACL ARR 2025 2026 reviewer guidelines review form criteria dimensions"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "eb724374-30dc-4e1b-b3be-cee840e48074",
  "isSidechain": false,
  "requestId": "req_011CbBSLSmGLrpoQKTGeRAcS",
  "type": "assistant",
  "uuid": "fd6f9420-34ba-4bf1-abe9-57a4aa6465c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017n2TN3YoPYyccqqdYYvggc",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2235,
      "cache_read_input_tokens": 29465,
      "output_tokens": 295,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2235,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 295,
          "cache_read_input_tokens": 29465,
          "cache_creation_input_tokens": 2235,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2235
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

_source line 24 · 2026-05-19T06:16:01.522Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__verify_references · `toolu_01HhP5NwhXwiZFFWVxhaLNX8`</summary>

```json
{
  "paper_dir": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper",
  "project": "gen-depth-fingerprint"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fd6f9420-34ba-4bf1-abe9-57a4aa6465c7",
  "isSidechain": false,
  "requestId": "req_011CbBSLSmGLrpoQKTGeRAcS",
  "type": "assistant",
  "uuid": "669ed31a-97e7-4887-bd15-8b2a96168a96",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017n2TN3YoPYyccqqdYYvggc",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2235,
      "cache_read_input_tokens": 29465,
      "output_tokens": 295,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2235,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 295,
          "cache_read_input_tokens": 29465,
          "cache_creation_input_tokens": 2235,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2235
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


### Runtime record

_source line 25_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 2  **你的审查侧重：新颖性 + 论文完整性 + 写作质量 + 格式合规**  ### 论文信息 - **标题**: Depth Profiling: Classifying Recursive Generation Depth in Base LLM Text Chains - **路径**: `projec…",
  "leafUuid": "669ed31a-97e7-4887-bd15-8b2a96168a96",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Runtime record

_source line 26_

```json
{
  "type": "ai-title",
  "aiTitle": "Review depth profiling LLM paper for EMNLP",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Tool result

_source line 27 · 2026-05-19T06:16:08.635Z_

<details><summary>↩ Tool result · `toolu_01G5BRVEkMeDFyhTdM5h3z8s`</summary>

```text
Web search results for query: "ACL ARR 2025 2026 reviewer guidelines review form criteria dimensions"

Links: [{"title":"CALL FOR PAPERS – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/cfp"},{"title":"aclrollingreview/cfp.md at main · acl-org/aclrollingreview","url":"https://github.com/acl-org/aclrollingreview/blob/main/cfp.md"},{"title":"ARR Reviewer Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/reviewerguidelines"},{"title":"ARR Area Chair Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/acguidelines"},{"title":"Incentives 2026 – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/incentives2026"},{"title":"Authors Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/authors"},{"title":"ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"https://aclrollingreview.org/"},{"title":"Dates and Venues – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics","url":"http://aclrollingreview.org/dates"}]

Based on the search results, here's what I found about ACL ARR 2025-2026 reviewer guidelines:

## Review Scoring Dimensions

Starting with February 2025, ARR reviewers are asked to provide three scores: soundness, excitement, and overall recommendation.

## Reviewer Guidelines and Requirements

All reviewers must familiarize themselves with the latest version of the ARR reviewer guidelines and perform the reviews on time and in line with ARR requirements.

## Quality Standards

All papers recommended for Findings or main conference are expected to be sound and reproducible.

## Policies on Irresponsible Reviews

The program chairs and ARR EiCs will consider the egregious cases reported by chairs (on their own judgement or based on author reports), including the cases of extremely terse reviews, unprofessional tone, and LLM-generated reviews.

## 2026 Review Timeline

For the 2026 cycle, reviewer checklists must be completed by Jan 21st, the deadline for reviews is February 7th, and for meta-reviews March 3rd.

The search results reference the guidelines but don't provide extensive detail on all the specific review form criteria and dimensions. For the complete review form and detailed criteria, you may want to visit the official ARR reviewer guidelines page at aclrollingreview.org/reviewerguidelines directly.


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fd6f9420-34ba-4bf1-abe9-57a4aa6465c7",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "2d232634-997e-4fc7-988d-09f14cca9b37",
  "toolUseResult": {
    "query": "ACL ARR 2025 2026 reviewer guidelines review form criteria dimensions",
    "results": [
      {
        "tool_use_id": "srvtoolu_016YTu7DGgvaa6GSgqehwiMK",
        "content": [
          {
            "title": "CALL FOR PAPERS – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/cfp"
          },
          {
            "title": "aclrollingreview/cfp.md at main · acl-org/aclrollingreview",
            "url": "https://github.com/acl-org/aclrollingreview/blob/main/cfp.md"
          },
          {
            "title": "ARR Reviewer Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/reviewerguidelines"
          },
          {
            "title": "ARR Area Chair Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/acguidelines"
          },
          {
            "title": "Incentives 2026 – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/incentives2026"
          },
          {
            "title": "Authors Guidelines – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/authors"
          },
          {
            "title": "ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "https://aclrollingreview.org/"
          },
          {
            "title": "Dates and Venues – ACL Rolling Review – A peer review platform for the Association for Computational Linguistics",
            "url": "http://aclrollingreview.org/dates"
          }
        ]
      },
      "Based on the search results, here's what I found about ACL ARR 2025-2026 reviewer guidelines:\n\n## Review Scoring Dimensions\n\nStarting with February 2025, ARR reviewers are asked to provide three scores: soundness, excitement, and overall recommendation.\n\n## Reviewer Guidelines and Requirements\n\nAll reviewers must familiarize themselves with the latest version of the ARR reviewer guidelines and perform the reviews on time and in line with ARR requirements.\n\n## Quality Standards\n\nAll papers recommended for Findings or main conference are expected to be sound and reproducible.\n\n## Policies on Irresponsible Reviews\n\nThe program chairs and ARR EiCs will consider the egregious cases reported by chairs (on their own judgement or based on author reports), including the cases of extremely terse reviews, unprofessional tone, and LLM-generated reviews.\n\n## 2026 Review Timeline\n\nFor the 2026 cycle, reviewer checklists must be completed by Jan 21st, the deadline for reviews is February 7th, and for meta-reviews March 3rd.\n\nThe search results reference the guidelines but don't provide extensive detail on all the specific review form criteria and dimensions. For the complete review form and detailed criteria, you may want to visit the official ARR reviewer guidelines page at aclrollingreview.org/reviewerguidelines directly."
    ],
    "durationSeconds": 7.447034297000005
  },
  "sourceToolAssistantUUID": "fd6f9420-34ba-4bf1-abe9-57a4aa6465c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool result

_source line 28 · 2026-05-19T06:17:25.847Z_

<details><summary>↩ Tool result · `toolu_01HhP5NwhXwiZFFWVxhaLNX8`</summary>

```text
&lt;persisted-output>
Output too large (54.7KB). Full output saved to: /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint--claude-sessions-review-reviewer-2-3f564e41/34cea30f-783a-4e65-9506-a050519fc721/tool-results/toolu_01HhP5NwhXwiZFFWVxhaLNX8.txt

Preview (first 2KB):
{"result":"{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 71, \"total_citations\": 96, \"unique_cited_keys\": 71, \"orphan_bib\": 0, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 57, \"online_not_found\": 9, \"online_mismatch\": 5}, \"cross_check\": {\"orphan_bib\": [], \"missing_bib\": [], \"orphan_count\": 0, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"mccarthy2010mtld\", \"type\": \"article\", \"title\": \"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\", \"authors\": \"McCarthy, Philip M. and Jarvis, Scott\", \"year\": \"2010\", \"venue\": \"Behavior Research Methods\"}, {\"key\": \"covington2010mattr\", \"type\": \"article\", \"title\": \"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\", \"authors\": \"Covington, Michael A. and McFall, Joe D.\", \"year\": \"2010\", \"venue\": \"Journal of Quantitative Linguistics\"}, {\"key\": \"oren2024proving\", \"type\": \"inproceedings\", \"title\": \"Proving Test Set Contamination in Black Box Language Models\", \"authors\": \"Oren, Yonatan and Meister, Nicole and Chatterji, Niladri and Laber, Faisal and S...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"golchin2024time\", \"type\": \"inproceedings\", \"title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"authors\": \"Golchin, Shahriar and Surdeanu, Mihai\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"longpre2024data\", \"type\": \"inproceedings\", \"title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"authors\": \"Longpre, Shayne and Mahari, Robert and Lee, Naana and Luccioni, Sasha and Jernit...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\
...
&lt;/persisted-output>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "669ed31a-97e7-4887-bd15-8b2a96168a96",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "625140a3-1aac-4aa3-b18c-51137aec5276",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"summary\\\": {\\\"total_bib_entries\\\": 71, \\\"total_citations\\\": 96, \\\"unique_cited_keys\\\": 71, \\\"orphan_bib\\\": 0, \\\"missing_bib\\\": 0, \\\"duplicate_keys\\\": 0, \\\"online_verified\\\": 57, \\\"online_not_found\\\": 9, \\\"online_mismatch\\\": 5}, \\\"cross_check\\\": {\\\"orphan_bib\\\": [], \\\"missing_bib\\\": [], \\\"orphan_count\\\": 0, \\\"missing_count\\\": 0}, \\\"bib_entries\\\": [{\\\"key\\\": \\\"mccarthy2010mtld\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\\\", \\\"authors\\\": \\\"McCarthy, Philip M. and Jarvis, Scott\\\", \\\"year\\\": \\\"2010\\\", \\\"venue\\\": \\\"Behavior Research Methods\\\"}, {\\\"key\\\": \\\"covington2010mattr\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\\\", \\\"authors\\\": \\\"Covington, Michael A. and McFall, Joe D.\\\", \\\"year\\\": \\\"2010\\\", \\\"venue\\\": \\\"Journal of Quantitative Linguistics\\\"}, {\\\"key\\\": \\\"oren2024proving\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Proving Test Set Contamination in Black Box Language Models\\\", \\\"authors\\\": \\\"Oren, Yonatan and Meister, Nicole and Chatterji, Niladri and Laber, Faisal and S...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"golchin2024time\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\\\", \\\"authors\\\": \\\"Golchin, Shahriar and Surdeanu, Mihai\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"longpre2024data\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\\\", \\\"authors\\\": \\\"Longpre, Shayne and Mahari, Robert and Lee, Naana and Luccioni, Sasha and Jernit...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"type\\\": \\\"book\\\", \\\"title\\\": \\\"Statistical Power Analysis for the Behavioral Sciences\\\", \\\"authors\\\": \\\"Cohen, Jacob\\\", \\\"year\\\": \\\"1988\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"tang2024science\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"The Science of Detecting LLM-Generated Text\\\", \\\"authors\\\": \\\"Tang, Ruixiang and Chuang, Yu-Neng and Hu, Xia\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Communications of the ACM\\\"}, {\\\"key\\\": \\\"neal2017surveying\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Surveying Stylometry Techniques and Applications\\\", \\\"authors\\\": \\\"Neal, Tempestt and Sundararajan, Kalaivani and Fatima, Aneez and Yan, Yiming and...\\\", \\\"year\\\": \\\"2017\\\", \\\"venue\\\": \\\"ACM Computing Surveys\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"authors\\\": \\\"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"gltr\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"authors\\\": \\\"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"dna_gpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"authors\\\": \\\"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"authors\\\": \\\"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"authors\\\": \\\"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\\\", \\\"authors\\\": \\\"Narayanasamy, Priyadarshan and Agrawal, Swastik and Faber, Klint and Alam, Fardi...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2605.01647\\\"}, {\\\"key\\\": \\\"intrinsic_dimension\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"authors\\\": \\\"Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavsk...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"diveye\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"authors\\\": \\\"Basani, Advik Raj and Chen, Pin-Yu\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Transactions on Machine Learning Research\\\"}, {\\\"key\\\": \\\"generator_barrier\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"authors\\\": \\\"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2604.13692\\\"}, {\\\"key\\\": \\\"feat_aug_transformer\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\\\", \\\"authors\\\": \\\"Mady, Mohamed and Reschke, Johannes and Schuller, Bj\\\\\\\\\\\\\\\"orn\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2605.03969\\\"}, {\\\"key\\\": \\\"reliable_detection\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\\\", \\\"authors\\\": \\\"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Transactions on Machine Learning Research\\\"}, {\\\"key\\\": \\\"paraphrase_evades\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\\\", \\\"authors\\\": \\\"Krishna, Kalpesh and Song, Yixiao and Karpinska, Marzena and Wieting, John and I...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"detection_possibilities\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Position: On the Possibilities of AI-Generated Text Detection\\\", \\\"authors\\\": \\\"Chakraborty, Souradip and Bedi, Amrit Singh and Zhu, Sicheng and An, Bang and Ma...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"grover\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Defending Against Neural Fake News\\\", \\\"authors\\\": \\\"Zellers, Rowan and Holtzman, Ari and Rashkin, Hannah and Bisk, Yonatan and Farha...\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"release_strategies\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Release Strategies and the Social Impacts of Language Models\\\", \\\"authors\\\": \\\"Solaiman, Irene and Brundage, Miles and Clark, Jack and Askell, Amanda and Herbe...\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:1908.09203\\\"}, {\\\"key\\\": \\\"beyond_binary\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\\\", \\\"authors\\\": \\\"Cheng, Zihao and Zhou, Li and Jiang, Feng and Wang, Benyou and Li, Haizhou\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the ACM Web Conference\\\"}, {\\\"key\\\": \\\"semeval2024_task8\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"authors\\\": \\\"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Workshop on Semantic Evaluation\\\"}, {\\\"key\\\": \\\"abburi_multifaceted\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\\\", \\\"authors\\\": \\\"Abburi, Harika and Bhattacharya, Sanmitra and Bowen, Edward and Pudota, Nirmala\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2505.11550\\\"}, {\\\"key\\\": \\\"defactify_dataset\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Comprehensive Dataset for Human vs.\\\\\\\\ AI Generated Text Detection\\\", \\\"authors\\\": \\\"Roy, Rajarshi and Imanpour, Nasrin and Aziz, Ashhar and Bajpai, Shashwat and Sin...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2510.22874\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"authors\\\": \\\"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"authors\\\": \\\"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Nature\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"model_collapse_avoidable\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"authors\\\": \\\"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the First Conference on Language Modeling (COLM)\\\"}, {\\\"key\\\": \\\"self_rewarding_lms\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Self-Rewarding Language Models\\\", \\\"authors\\\": \\\"Yuan, Weizhe and Pang, Richard Yuanzhe and Cho, Kyunghyun and Sukhbaatar, Sainba...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2401.10020\\\"}, {\\\"key\\\": \\\"spin\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"authors\\\": \\\"Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the 41st International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"qlora\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"QLoRA: Efficient Finetuning of Quantized Language Models\\\", \\\"authors\\\": \\\"Dettmers, Tim and Pagnoni, Artidoro and Holtzman, Ari and Zettlemoyer, Luke\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"authors\\\": \\\"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"qurating\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"authors\\\": \\\"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"authors\\\": \\\"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the Language Resources and Evaluation Conference\\\"}, {\\\"key\\\": \\\"watermark_llm\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"authors\\\": \\\"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"synthid_text\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Scalable Watermarking for Identifying Large Language Model Outputs\\\", \\\"authors\\\": \\\"Dathathri, Sumanth and See, Abigail and Ghaisas, Sumedh and Huang, Po-Sen and Mc...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Nature\\\"}, {\\\"key\\\": \\\"aaronson_watermark\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Watermarking GPT Outputs\\\", \\\"authors\\\": \\\"Aaronson, Scott and Kirchner, Hendrik\\\", \\\"year\\\": \\\"2022\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"chainwash\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\\\", \\\"authors\\\": \\\"Ameen, Mohd Ruhul and Islam, Akif and Mahmud, Nadim and Hamid, Md. Ekramul\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2605.05503\\\"}, {\\\"key\\\": \\\"curious_decline\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"authors\\\": \\\"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\\\\\'e\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Findings of the Association for Computational Linguistics: NAACL\\\"}, {\\\"key\\\": \\\"writing_diversity\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"authors\\\": \\\"Padmakumar, Vishakh and He, He\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"nucleus_sampling\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"authors\\\": \\\"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"stamatatos_survey\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Survey of Modern Authorship Attribution Methods\\\", \\\"authors\\\": \\\"Stamatatos, Efstathios\\\", \\\"year\\\": \\\"2009\\\", \\\"venue\\\": \\\"Journal of the American Society for Information Science and Technology\\\"}, {\\\"key\\\": \\\"koppel_authorship\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Computational Methods in Authorship Attribution\\\", \\\"authors\\\": \\\"Koppel, Moshe and Schler, Jonathan and Argamon, Shlomo\\\", \\\"year\\\": \\\"2009\\\", \\\"venue\\\": \\\"Journal of the American Society for Information Science and Technology\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"authors\\\": \\\"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\\\"}, {\\\"key\\\": \\\"munir_looking_glass\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\\\", \\\"authors\\\": \\\"Munir, Shaoor and Batool, Brishna and Shafiq, Zubair and Srinivasan, Padmini and...\\\", \\\"year\\\": \\\"2021\\\", \\\"venue\\\": \\\"Proceedings of the Conference of the European Chapter of the Association for Com...\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"authors\\\": \\\"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"attractor_cycles\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\\\", \\\"authors\\\": \\\"Wang, Yibo and Wu, Congying and Li, Yanan and Cai, Yi\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Markovian Generation Chains in Large Language Models\\\", \\\"authors\\\": \\\"Geng, Mingmeng and Mohamed, Amr and Shang, Guokan and Vazirgiannis, Michalis and...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2603.11228\\\"}, {\\\"key\\\": \\\"min_k_percent\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"authors\\\": \\\"Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Da...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"wu_survey_2025\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"authors\\\": \\\"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Computational Linguistics\\\"}, {\\\"key\\\": \\\"jawahar_survey\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Automatic Detection of Machine Generated Text: A Critical Survey\\\", \\\"authors\\\": \\\"Jawahar, Ganesh and Abdul-Mageed, Muhammad and Lakshmanan, Laks V.S.\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Computational Linguistics\\\"}, {\\\"key\\\": \\\"pythia\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\\\", \\\"authors\\\": \\\"Biderman, Stella and Schoelkopf, Hailey and Anthony, Quentin Gregory and Bradley...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"olmo\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"OLMo: Accelerating the Science of Language Models\\\", \\\"authors\\\": \\\"Groeneveld, Dirk and Beltagy, Iz and Walsh, Evan and Bhagia, Akshita and Kinney,...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"qwen3\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Qwen3 Technical Report\\\", \\\"authors\\\": \\\"Qwen Team\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2505.09388\\\"}, {\\\"key\\\": \\\"ghostbuster\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"authors\\\": \\\"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Jurafsky, Dan\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"two_birds\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\\\", \\\"authors\\\": \\\"Rao, Harika and Vashistha, Adaku Jane and Jain, Aaryan and Garg, Naman\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2508.14190\\\"}, {\\\"key\\\": \\\"beyond_final_actor\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\\\", \\\"authors\\\": \\\"Li, Ziang and Gao, Guan-Yu and Yang, Songlin and Yu, Ning and Fritz, Mario and M...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Proceedings of the Association for Computational Linguistics\\\"}, {\\\"key\\\": \\\"gutierrez_ordinal_survey\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"authors\\\": \\\"Guti\\\\\\\\'errez, Pedro Antonio and P\\\\\\\\'erez-Ortiz, Mar\\\\\\\\'ia and S\\\\\\\\'anchez-Monedero, Ja...\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"IEEE Transactions on Knowledge and Data Engineering\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"authors\\\": \\\"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Pattern Recognition Letters\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"authors\\\": \\\"Frank, Eibe and Hall, Mark\\\", \\\"year\\\": \\\"2001\\\", \\\"venue\\\": \\\"Proceedings of the European Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"pang_opinion_mining\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\\\", \\\"authors\\\": \\\"Pang, Bo and Lee, Lillian\\\", \\\"year\\\": \\\"2005\\\", \\\"venue\\\": \\\"Proceedings of the 43rd Annual Meeting of the Association for Computational Ling...\\\"}, {\\\"key\\\": \\\"taghipour_neural_essay\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Neural Approach to Automated Essay Scoring\\\", \\\"authors\\\": \\\"Taghipour, Kaveh and Ng, Hwee Tou\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"Proceedings of the 2016 Conference on Empirical Methods in Natural Language Proc...\\\"}, {\\\"key\\\": \\\"corn_ordinal\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\\\", \\\"authors\\\": \\\"Shi, Xintong and Cao, Wenzhi and Raschka, Sebastian\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Pattern Analysis and Applications\\\"}, {\\\"key\\\": \\\"xgboost\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"XGBoost: A Scalable Tree Boosting System\\\", \\\"authors\\\": \\\"Chen, Tianqi and Guestrin, Carlos\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"Proceedings of the ACM SIGKDD International Conference on Knowledge Discovery an...\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\\\", \\\"authors\\\": \\\"Lakens, Dani\\\\\\\\\\\\\\\"el\\\", \\\"year\\\": \\\"2017\\\", \\\"venue\\\": \\\"Social Psychological and Personality Science\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"authors\\\": \\\"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2407.21783\\\"}, {\\\"key\\\": \\\"mistral7b\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Mistral 7B\\\", \\\"authors\\\": \\\"Jiang, Albert Q. and Sablayrolles, Alexandre and Mensch, Arthur and Bamford, Chr...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2310.06825\\\"}, {\\\"key\\\": \\\"strobl_conditional_2008\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Conditional Variable Importance for Random Forests\\\", \\\"authors\\\": \\\"Strobl, Carolin and Boulesteix, Anne-Laure and Kneib, Thomas and Augustin, Thoma...\\\", \\\"year\\\": \\\"2008\\\", \\\"venue\\\": \\\"BMC Bioinformatics\\\"}], \\\"tex_citations\\\": [{\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gltr\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"grover\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"release_strategies\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dna_gpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ghostbuster\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"feat_aug_transformer\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"abburi_multifaceted\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"reliable_detection\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"intrinsic_dimension\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"generator_barrier\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"tang2024science\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"wu_survey_2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"jawahar_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"beyond_binary\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"two_birds\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"beyond_final_actor\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"semeval2024_task8\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"defactify_dataset\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"paraphrase_evades\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 15, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"detection_possibilities\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 15, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gutierrez_ordinal_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"corn_ordinal\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"pang_opinion_mining\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"taghipour_neural_essay\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 17, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"munir_looking_glass\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 17, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"model_collapse_avoidable\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"self_rewarding_lms\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 24, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"spin\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 24, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 25, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 25, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 28, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"attractor_cycles\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 30, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 32, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 32, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curious_decline\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 37, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"writing_diversity\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 37, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"stamatatos_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 38, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"koppel_authorship\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 38, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"neal2017surveying\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 38, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mccarthy2010mtld\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 38, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"covington2010mattr\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 38, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 39, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"nucleus_sampling\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 39, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 44, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qurating\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 44, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 44, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"oren2024proving\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 44, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"golchin2024time\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 44, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"longpre2024data\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 44, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"watermark_llm\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 46, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"synthid_text\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 46, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"aaronson_watermark\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 46, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"chainwash\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 46, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"min_k_percent\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 47, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"pythia\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"olmo\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qwen3\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mistral7b\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"xgboost\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 75, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 77, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"corn_ordinal\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 77, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 77, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 86, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 86, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 86, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"file\\\": \\\"results.tex\\\", \\\"line\\\": 72, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strobl_conditional_2008\\\", \\\"file\\\": \\\"results.tex\\\", \\\"line\\\": 90, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 25, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 25, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qlora\\\", \\\"file\\\": \\\"appendix_qlora.tex\\\", \\\"line\\\": 1, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"file\\\": \\\"appendix_classifier.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"file\\\": \\\"appendix_classifier.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"file\\\": \\\"appendix_downstream.tex\\\", \\\"line\\\": 41, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"file\\\": \\\"appendix_tost.tex\\\", \\\"line\\\": 4, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"file\\\": \\\"appendix_tost.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}], \\\"online_verification\\\": [{\\\"key\\\": \\\"mccarthy2010mtld\\\", \\\"title\\\": \\\"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"MTLD, vocd-D, and HD-D: A validation study of sophisticated approaches to lexical diversity assessment\\\", \\\"matched_year\\\": \\\"2010\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"covington2010mattr\\\", \\\"title\\\": \\\"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.986, \\\"matched_title\\\": \\\"Cutting the Gordian Knot: The Moving-Average Type–Token Ratio (MATTR)\\\", \\\"matched_year\\\": \\\"2010\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"oren2024proving\\\", \\\"title\\\": \\\"Proving Test Set Contamination in Black Box Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Proving Test Set Contamination in Black Box Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"golchin2024time\\\", \\\"title\\\": \\\"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"longpre2024data\\\", \\\"title\\\": \\\"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"title\\\": \\\"Statistical Power Analysis for the Behavioral Sciences\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Statistical Power Analysis for the Behavioral Sciences\\\", \\\"matched_year\\\": \\\"1989\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=cohen vs api=muller\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"tang2024science\\\", \\\"title\\\": \\\"The Science of Detecting LLM-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Science of Detecting LLM-Generated Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"neal2017surveying\\\", \\\"title\\\": \\\"Surveying Stylometry Techniques and Applications\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Surveying Stylometry Techniques and Applications\\\", \\\"matched_year\\\": \\\"2017\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.382, \\\"matched_title\\\": \\\"Regulating ChatGPT and other Large Generative AI Models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.38 below threshold 0.82\\\"}, {\\\"key\\\": \\\"gltr\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dna_gpt\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"title\\\": \\\"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"intrinsic_dimension\\\", \\\"title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"diveye\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"generator_barrier\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"feat_aug_transformer\\\", \\\"title\\\": \\\"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"reliable_detection\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.344, \\\"matched_title\\\": \\\"2015 ESC Guidelines for the management of acute coronary syndromes in patients presenting without persistent ST-segment elevation\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.34 below threshold 0.82\\\"}, {\\\"key\\\": \\\"paraphrase_evades\\\", \\\"title\\\": \\\"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Paraphrasing evades detectors of AI-generated text, but retrieval is an effective defense\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"detection_possibilities\\\", \\\"title\\\": \\\"Position: On the Possibilities of AI-Generated Text Detection\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.253, \\\"matched_title\\\": \\\"Review of deep learning: concepts, CNN architectures, challenges, applications, future directions\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.25 below threshold 0.82\\\"}, {\\\"key\\\": \\\"grover\\\", \\\"title\\\": \\\"Defending Against Neural Fake News\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Defending Against Neural Fake News\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"release_strategies\\\", \\\"title\\\": \\\"Release Strategies and the Social Impacts of Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Release Strategies and the Social Impacts of Language Models\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"beyond_binary\\\", \\\"title\\\": \\\"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"semeval2024_task8\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"abburi_multifaceted\\\", \\\"title\\\": \\\"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"defactify_dataset\\\", \\\"title\\\": \\\"A Comprehensive Dataset for Human vs.\\\\\\\\ AI Generated Text Detection\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.355, \\\"matched_title\\\": \\\"Performance of ChatGPT on USMLE: Potential for AI-assisted medical education using large language models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.36 below threshold 0.82\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Consuming Generative Models go MAD\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=alemohammad vs api=casco-rodriguez\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Strong Model Collapse\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"model_collapse_avoidable\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"self_rewarding_lms\\\", \\\"title\\\": \\\"Self-Rewarding Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Rewarding Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"spin\\\", \\\"title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qlora\\\", \\\"title\\\": \\\"QLoRA: Efficient Finetuning of Quantized Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.871, \\\"matched_title\\\": \\\"QLoRA: Efficient Finetuning of Quantized LLMs\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qurating\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"watermark_llm\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Watermark for Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"synthid_text\\\", \\\"title\\\": \\\"Scalable Watermarking for Identifying Large Language Model Outputs\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Scalable watermarking for identifying large language model outputs\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"aaronson_watermark\\\", \\\"title\\\": \\\"Watermarking GPT Outputs\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.418, \\\"matched_title\\\": \\\"Undetectable Watermarks for Language Models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.42 below threshold 0.82\\\"}, {\\\"key\\\": \\\"chainwash\\\", \\\"title\\\": \\\"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"curious_decline\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"writing_diversity\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"nucleus_sampling\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"stamatatos_survey\\\", \\\"title\\\": \\\"A Survey of Modern Authorship Attribution Methods\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A survey of modern authorship attribution methods\\\", \\\"matched_year\\\": \\\"2008\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"koppel_authorship\\\", \\\"title\\\": \\\"Computational Methods in Authorship Attribution\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Computational methods in authorship attribution\\\", \\\"matched_year\\\": \\\"2008\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"munir_looking_glass\\\", \\\"title\\\": \\\"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\\\", \\\"matched_year\\\": \\\"2021\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"attractor_cycles\\\", \\\"title\\\": \\\"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"title\\\": \\\"Markovian Generation Chains in Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Markovian Generation Chains in Large Language Models\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"min_k_percent\\\", \\\"title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wu_survey_2025\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"jawahar_survey\\\", \\\"title\\\": \\\"Automatic Detection of Machine Generated Text: A Critical Survey\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Automatic Detection of Machine Generated Text: A Critical Survey\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pythia\\\", \\\"title\\\": \\\"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.497, \\\"matched_title\\\": \\\"The TRIPOD-LLM reporting guideline for studies using large language models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.50 below threshold 0.82\\\"}, {\\\"key\\\": \\\"olmo\\\", \\\"title\\\": \\\"OLMo: Accelerating the Science of Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"OLMo: Accelerating the Science of Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qwen3\\\", \\\"title\\\": \\\"Qwen3 Technical Report\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Qwen3 Technical Report\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=team vs api=yang\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"ghostbuster\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"two_birds\\\", \\\"title\\\": \\\"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.32, \\\"matched_title\\\": \\\"Large AI Models in Health Informatics: Applications, Challenges, and the Future\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.32 below threshold 0.82\\\"}, {\\\"key\\\": \\\"beyond_final_actor\\\", \\\"title\\\": \\\"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.722, \\\"matched_title\\\": \\\"Beyond the Final Actor: Modeling the Dual Roles of Creator and Editor for Fine-Grained LLM-Generated Text Detection\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.72 below threshold 0.82\\\"}, {\\\"key\\\": \\\"gutierrez_ordinal_survey\\\", \\\"title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"matched_year\\\": \\\"2015\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=guti\\\\\\\\'errez vs api=gutiérrez\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Rank consistent ordinal regression for neural networks with application to age estimation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"matched_year\\\": \\\"2001\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pang_opinion_mining\\\", \\\"title\\\": \\\"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Seeing stars: Exploiting class relationships for sentiment categorization with respect to rating scales\\\", \\\"matched_year\\\": \\\"2005\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"taghipour_neural_essay\\\", \\\"title\\\": \\\"A Neural Approach to Automated Essay Scoring\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Neural Approach to Automated Essay Scoring\\\", \\\"matched_year\\\": \\\"2016\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"corn_ordinal\\\", \\\"title\\\": \\\"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Deep neural networks for rank-consistent ordinal regression based on conditional probabilities\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"xgboost\\\", \\\"title\\\": \\\"XGBoost: A Scalable Tree Boosting System\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.298, \\\"matched_title\\\": \\\"XGBoost\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.30 below threshold 0.82\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"title\\\": \\\"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.976, \\\"matched_title\\\": \\\"Equivalence Tests: A Practical Primer for t-Tests, Correlations, and Meta-Analyses\\\", \\\"matched_year\\\": \\\"2016\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Llama 3 herd of models\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=grattafiori vs api=aaron\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mistral7b\\\", \\\"title\\\": \\\"Mistral 7B\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Mistral 7B\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"strobl_conditional_2008\\\", \\\"title\\\": \\\"Conditional Variable Importance for Random Forests\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Conditional variable importance for random forests\\\", \\\"matched_year\\\": \\\"2008\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}]}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 71, \"total_citations\": 96, \"unique_cited_keys\": 71, \"orphan_bib\": 0, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 57, \"online_not_found\": 9, \"online_mismatch\": 5}, \"cross_check\": {\"orphan_bib\": [], \"missing_bib\": [], \"orphan_count\": 0, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"mccarthy2010mtld\", \"type\": \"article\", \"title\": \"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\", \"authors\": \"McCarthy, Philip M. and Jarvis, Scott\", \"year\": \"2010\", \"venue\": \"Behavior Research Methods\"}, {\"key\": \"covington2010mattr\", \"type\": \"article\", \"title\": \"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\", \"authors\": \"Covington, Michael A. and McFall, Joe D.\", \"year\": \"2010\", \"venue\": \"Journal of Quantitative Linguistics\"}, {\"key\": \"oren2024proving\", \"type\": \"inproceedings\", \"title\": \"Proving Test Set Contamination in Black Box Language Models\", \"authors\": \"Oren, Yonatan and Meister, Nicole and Chatterji, Niladri and Laber, Faisal and S...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"golchin2024time\", \"type\": \"inproceedings\", \"title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"authors\": \"Golchin, Shahriar and Surdeanu, Mihai\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"longpre2024data\", \"type\": \"inproceedings\", \"title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"authors\": \"Longpre, Shayne and Mahari, Robert and Lee, Naana and Luccioni, Sasha and Jernit...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"cohen1988statistical\", \"type\": \"book\", \"title\": \"Statistical Power Analysis for the Behavioral Sciences\", \"authors\": \"Cohen, Jacob\", \"year\": \"1988\", \"venue\": \"\"}, {\"key\": \"tang2024science\", \"type\": \"article\", \"title\": \"The Science of Detecting LLM-Generated Text\", \"authors\": \"Tang, Ruixiang and Chuang, Yu-Neng and Hu, Xia\", \"year\": \"2024\", \"venue\": \"Communications of the ACM\"}, {\"key\": \"neal2017surveying\", \"type\": \"article\", \"title\": \"Surveying Stylometry Techniques and Applications\", \"authors\": \"Neal, Tempestt and Sundararajan, Kalaivani and Fatima, Aneez and Yan, Yiming and...\", \"year\": \"2017\", \"venue\": \"ACM Computing Surveys\"}, {\"key\": \"detectgpt\", \"type\": \"inproceedings\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"authors\": \"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"gltr\", \"type\": \"inproceedings\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"authors\": \"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\", \"year\": \"2019\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"dna_gpt\", \"type\": \"inproceedings\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"authors\": \"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"binoculars\", \"type\": \"inproceedings\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"authors\": \"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"fast_detectgpt\", \"type\": \"inproceedings\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"authors\": \"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"ld_score\", \"type\": \"article\", \"title\": \"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\", \"authors\": \"Narayanasamy, Priyadarshan and Agrawal, Swastik and Faber, Klint and Alam, Fardi...\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2605.01647\"}, {\"key\": \"intrinsic_dimension\", \"type\": \"inproceedings\", \"title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"authors\": \"Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavsk...\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"diveye\", \"type\": \"article\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"authors\": \"Basani, Advik Raj and Chen, Pin-Yu\", \"year\": \"2026\", \"venue\": \"Transactions on Machine Learning Research\"}, {\"key\": \"generator_barrier\", \"type\": \"article\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"authors\": \"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2604.13692\"}, {\"key\": \"feat_aug_transformer\", \"type\": \"article\", \"title\": \"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\", \"authors\": \"Mady, Mohamed and Reschke, Johannes and Schuller, Bj\\\\\\\"orn\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2605.03969\"}, {\"key\": \"reliable_detection\", \"type\": \"article\", \"title\": \"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\", \"authors\": \"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\", \"year\": \"2025\", \"venue\": \"Transactions on Machine Learning Research\"}, {\"key\": \"paraphrase_evades\", \"type\": \"inproceedings\", \"title\": \"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\", \"authors\": \"Krishna, Kalpesh and Song, Yixiao and Karpinska, Marzena and Wieting, John and I...\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"detection_possibilities\", \"type\": \"inproceedings\", \"title\": \"Position: On the Possibilities of AI-Generated Text Detection\", \"authors\": \"Chakraborty, Souradip and Bedi, Amrit Singh and Zhu, Sicheng and An, Bang and Ma...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"grover\", \"type\": \"inproceedings\", \"title\": \"Defending Against Neural Fake News\", \"authors\": \"Zellers, Rowan and Holtzman, Ari and Rashkin, Hannah and Bisk, Yonatan and Farha...\", \"year\": \"2019\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"release_strategies\", \"type\": \"article\", \"title\": \"Release Strategies and the Social Impacts of Language Models\", \"authors\": \"Solaiman, Irene and Brundage, Miles and Clark, Jack and Askell, Amanda and Herbe...\", \"year\": \"2019\", \"venue\": \"arXiv preprint arXiv:1908.09203\"}, {\"key\": \"beyond_binary\", \"type\": \"inproceedings\", \"title\": \"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\", \"authors\": \"Cheng, Zihao and Zhou, Li and Jiang, Feng and Wang, Benyou and Li, Haizhou\", \"year\": \"2025\", \"venue\": \"Proceedings of the ACM Web Conference\"}, {\"key\": \"semeval2024_task8\", \"type\": \"inproceedings\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"authors\": \"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Workshop on Semantic Evaluation\"}, {\"key\": \"abburi_multifaceted\", \"type\": \"article\", \"title\": \"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\", \"authors\": \"Abburi, Harika and Bhattacharya, Sanmitra and Bowen, Edward and Pudota, Nirmala\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2505.11550\"}, {\"key\": \"defactify_dataset\", \"type\": \"article\", \"title\": \"A Comprehensive Dataset for Human vs.\\\\ AI Generated Text Detection\", \"authors\": \"Roy, Rajarshi and Imanpour, Nasrin and Aziz, Ashhar and Bajpai, Shashwat and Sin...\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2510.22874\"}, {\"key\": \"self_consuming_mad\", \"type\": \"inproceedings\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"authors\": \"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"curse_of_recursion\", \"type\": \"article\", \"title\": \"AI models collapse when trained on recursively generated data\", \"authors\": \"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"strong_model_collapse\", \"type\": \"inproceedings\", \"title\": \"Strong Model Collapse\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"model_collapse_avoidable\", \"type\": \"inproceedings\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"authors\": \"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\", \"year\": \"2024\", \"venue\": \"Proceedings of the First Conference on Language Modeling (COLM)\"}, {\"key\": \"self_rewarding_lms\", \"type\": \"article\", \"title\": \"Self-Rewarding Language Models\", \"authors\": \"Yuan, Weizhe and Pang, Richard Yuanzhe and Cho, Kyunghyun and Sukhbaatar, Sainba...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2401.10020\"}, {\"key\": \"spin\", \"type\": \"inproceedings\", \"title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"authors\": \"Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan\", \"year\": \"2024\", \"venue\": \"Proceedings of the 41st International Conference on Machine Learning\"}, {\"key\": \"qlora\", \"type\": \"inproceedings\", \"title\": \"QLoRA: Efficient Finetuning of Quantized Language Models\", \"authors\": \"Dettmers, Tim and Pagnoni, Artidoro and Holtzman, Ari and Zettlemoyer, Luke\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"dsir\", \"type\": \"inproceedings\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"authors\": \"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"qurating\", \"type\": \"inproceedings\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"authors\": \"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"ccnet\", \"type\": \"inproceedings\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"authors\": \"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\", \"year\": \"2020\", \"venue\": \"Proceedings of the Language Resources and Evaluation Conference\"}, {\"key\": \"watermark_llm\", \"type\": \"inproceedings\", \"title\": \"A Watermark for Large Language Models\", \"authors\": \"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"synthid_text\", \"type\": \"article\", \"title\": \"Scalable Watermarking for Identifying Large Language Model Outputs\", \"authors\": \"Dathathri, Sumanth and See, Abigail and Ghaisas, Sumedh and Huang, Po-Sen and Mc...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"aaronson_watermark\", \"type\": \"misc\", \"title\": \"Watermarking GPT Outputs\", \"authors\": \"Aaronson, Scott and Kirchner, Hendrik\", \"year\": \"2022\", \"venue\": \"\"}, {\"key\": \"chainwash\", \"type\": \"article\", \"title\": \"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\", \"authors\": \"Ameen, Mohd Ruhul and Islam, Akif and Mahmud, Nadim and Hamid, Md. Ekramul\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2605.05503\"}, {\"key\": \"curious_decline\", \"type\": \"inproceedings\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"authors\": \"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\'e\", \"year\": \"2024\", \"venue\": \"Findings of the Association for Computational Linguistics: NAACL\"}, {\"key\": \"writing_diversity\", \"type\": \"inproceedings\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"authors\": \"Padmakumar, Vishakh and He, He\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"nucleus_sampling\", \"type\": \"inproceedings\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"authors\": \"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\", \"year\": \"2020\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"stamatatos_survey\", \"type\": \"article\", \"title\": \"A Survey of Modern Authorship Attribution Methods\", \"authors\": \"Stamatatos, Efstathios\", \"year\": \"2009\", \"venue\": \"Journal of the American Society for Information Science and Technology\"}, {\"key\": \"koppel_authorship\", \"type\": \"article\", \"title\": \"Computational Methods in Authorship Attribution\", \"authors\": \"Koppel, Moshe and Schler, Jonathan and Argamon, Shlomo\", \"year\": \"2009\", \"venue\": \"Journal of the American Society for Information Science and Technology\"}, {\"key\": \"uchendu_attribution\", \"type\": \"inproceedings\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"authors\": \"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\", \"year\": \"2020\", \"venue\": \"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\"}, {\"key\": \"munir_looking_glass\", \"type\": \"inproceedings\", \"title\": \"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\", \"authors\": \"Munir, Shaoor and Batool, Brishna and Shafiq, Zubair and Srinivasan, Padmini and...\", \"year\": \"2021\", \"venue\": \"Proceedings of the Conference of the European Chapter of the Association for Com...\"}, {\"key\": \"broken_telephone\", \"type\": \"inproceedings\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"authors\": \"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\", \"year\": \"2025\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"attractor_cycles\", \"type\": \"inproceedings\", \"title\": \"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\", \"authors\": \"Wang, Yibo and Wu, Congying and Li, Yanan and Cai, Yi\", \"year\": \"2025\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"markovian_chains\", \"type\": \"article\", \"title\": \"Markovian Generation Chains in Large Language Models\", \"authors\": \"Geng, Mingmeng and Mohamed, Amr and Shang, Guokan and Vazirgiannis, Michalis and...\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2603.11228\"}, {\"key\": \"min_k_percent\", \"type\": \"inproceedings\", \"title\": \"Detecting Pretraining Data from Large Language Models\", \"authors\": \"Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Da...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"wu_survey_2025\", \"type\": \"article\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"authors\": \"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\", \"year\": \"2025\", \"venue\": \"Computational Linguistics\"}, {\"key\": \"jawahar_survey\", \"type\": \"inproceedings\", \"title\": \"Automatic Detection of Machine Generated Text: A Critical Survey\", \"authors\": \"Jawahar, Ganesh and Abdul-Mageed, Muhammad and Lakshmanan, Laks V.S.\", \"year\": \"2020\", \"venue\": \"Proceedings of the International Conference on Computational Linguistics\"}, {\"key\": \"pythia\", \"type\": \"inproceedings\", \"title\": \"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\", \"authors\": \"Biderman, Stella and Schoelkopf, Hailey and Anthony, Quentin Gregory and Bradley...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"olmo\", \"type\": \"inproceedings\", \"title\": \"OLMo: Accelerating the Science of Language Models\", \"authors\": \"Groeneveld, Dirk and Beltagy, Iz and Walsh, Evan and Bhagia, Akshita and Kinney,...\", \"year\": \"2024\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"qwen3\", \"type\": \"article\", \"title\": \"Qwen3 Technical Report\", \"authors\": \"Qwen Team\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2505.09388\"}, {\"key\": \"ghostbuster\", \"type\": \"inproceedings\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"authors\": \"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Jurafsky, Dan\", \"year\": \"2024\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"two_birds\", \"type\": \"article\", \"title\": \"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\", \"authors\": \"Rao, Harika and Vashistha, Adaku Jane and Jain, Aaryan and Garg, Naman\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2508.14190\"}, {\"key\": \"beyond_final_actor\", \"type\": \"inproceedings\", \"title\": \"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\", \"authors\": \"Li, Ziang and Gao, Guan-Yu and Yang, Songlin and Yu, Ning and Fritz, Mario and M...\", \"year\": \"2026\", \"venue\": \"Proceedings of the Association for Computational Linguistics\"}, {\"key\": \"gutierrez_ordinal_survey\", \"type\": \"article\", \"title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"authors\": \"Guti\\\\'errez, Pedro Antonio and P\\\\'erez-Ortiz, Mar\\\\'ia and S\\\\'anchez-Monedero, Ja...\", \"year\": \"2016\", \"venue\": \"IEEE Transactions on Knowledge and Data Engineering\"}, {\"key\": \"coral_ordinal\", \"type\": \"article\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"authors\": \"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\", \"year\": \"2020\", \"venue\": \"Pattern Recognition Letters\"}, {\"key\": \"frank_hall_ordinal\", \"type\": \"inproceedings\", \"title\": \"A Simple Approach to Ordinal Classification\", \"authors\": \"Frank, Eibe and Hall, Mark\", \"year\": \"2001\", \"venue\": \"Proceedings of the European Conference on Machine Learning\"}, {\"key\": \"pang_opinion_mining\", \"type\": \"inproceedings\", \"title\": \"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\", \"authors\": \"Pang, Bo and Lee, Lillian\", \"year\": \"2005\", \"venue\": \"Proceedings of the 43rd Annual Meeting of the Association for Computational Ling...\"}, {\"key\": \"taghipour_neural_essay\", \"type\": \"inproceedings\", \"title\": \"A Neural Approach to Automated Essay Scoring\", \"authors\": \"Taghipour, Kaveh and Ng, Hwee Tou\", \"year\": \"2016\", \"venue\": \"Proceedings of the 2016 Conference on Empirical Methods in Natural Language Proc...\"}, {\"key\": \"corn_ordinal\", \"type\": \"article\", \"title\": \"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\", \"authors\": \"Shi, Xintong and Cao, Wenzhi and Raschka, Sebastian\", \"year\": \"2023\", \"venue\": \"Pattern Analysis and Applications\"}, {\"key\": \"xgboost\", \"type\": \"inproceedings\", \"title\": \"XGBoost: A Scalable Tree Boosting System\", \"authors\": \"Chen, Tianqi and Guestrin, Carlos\", \"year\": \"2016\", \"venue\": \"Proceedings of the ACM SIGKDD International Conference on Knowledge Discovery an...\"}, {\"key\": \"lakens_equivalence\", \"type\": \"article\", \"title\": \"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\", \"authors\": \"Lakens, Dani\\\\\\\"el\", \"year\": \"2017\", \"venue\": \"Social Psychological and Personality Science\"}, {\"key\": \"llama3\", \"type\": \"article\", \"title\": \"The Llama 3 Herd of Models\", \"authors\": \"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2407.21783\"}, {\"key\": \"mistral7b\", \"type\": \"article\", \"title\": \"Mistral 7B\", \"authors\": \"Jiang, Albert Q. and Sablayrolles, Alexandre and Mensch, Arthur and Bamford, Chr...\", \"year\": \"2023\", \"venue\": \"arXiv preprint arXiv:2310.06825\"}, {\"key\": \"strobl_conditional_2008\", \"type\": \"article\", \"title\": \"Conditional Variable Importance for Random Forests\", \"authors\": \"Strobl, Carolin and Boulesteix, Anne-Laure and Kneib, Thomas and Augustin, Thoma...\", \"year\": \"2008\", \"venue\": \"BMC Bioinformatics\"}], \"tex_citations\": [{\"key\": \"curse_of_recursion\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"self_consuming_mad\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"binoculars\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"ld_score\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"detectgpt\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"curse_of_recursion\", \"file\": \"introduction.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"self_consuming_mad\", \"file\": \"introduction.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"gltr\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"grover\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"release_strategies\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"detectgpt\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"binoculars\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"dna_gpt\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"ghostbuster\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"feat_aug_transformer\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"abburi_multifaceted\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"reliable_detection\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"ld_score\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"intrinsic_dimension\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"diveye\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"generator_barrier\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"tang2024science\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"citet\"}, {\"key\": \"wu_survey_2025\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"citet\"}, {\"key\": \"jawahar_survey\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"citet\"}, {\"key\": \"beyond_binary\", \"file\": \"related_work.tex\", \"line\": 11, \"command\": \"citet\"}, {\"key\": \"two_birds\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"citet\"}, {\"key\": \"beyond_final_actor\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"citet\"}, {\"key\": \"semeval2024_task8\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"defactify_dataset\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"paraphrase_evades\", \"file\": \"related_work.tex\", \"line\": 15, \"command\": \"cite\"}, {\"key\": \"detection_possibilities\", \"file\": \"related_work.tex\", \"line\": 15, \"command\": \"cite\"}, {\"key\": \"gutierrez_ordinal_survey\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"coral_ordinal\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"corn_ordinal\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"frank_hall_ordinal\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"pang_opinion_mining\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"taghipour_neural_essay\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"uchendu_attribution\", \"file\": \"related_work.tex\", \"line\": 17, \"command\": \"cite\"}, {\"key\": \"munir_looking_glass\", \"file\": \"related_work.tex\", \"line\": 17, \"command\": \"cite\"}, {\"key\": \"self_consuming_mad\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"curse_of_recursion\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"model_collapse_avoidable\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"strong_model_collapse\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"self_rewarding_lms\", \"file\": \"related_work.tex\", \"line\": 24, \"command\": \"cite\"}, {\"key\": \"spin\", \"file\": \"related_work.tex\", \"line\": 24, \"command\": \"cite\"}, {\"key\": \"curse_of_recursion\", \"file\": \"related_work.tex\", \"line\": 25, \"command\": \"cite\"}, {\"key\": \"strong_model_collapse\", \"file\": \"related_work.tex\", \"line\": 25, \"command\": \"cite\"}, {\"key\": \"broken_telephone\", \"file\": \"related_work.tex\", \"line\": 28, \"command\": \"citet\"}, {\"key\": \"markovian_chains\", \"file\": \"related_work.tex\", \"line\": 29, \"command\": \"citet\"}, {\"key\": \"attractor_cycles\", \"file\": \"related_work.tex\", \"line\": 30, \"command\": \"citet\"}, {\"key\": \"markovian_chains\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"broken_telephone\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"curious_decline\", \"file\": \"related_work.tex\", \"line\": 37, \"command\": \"cite\"}, {\"key\": \"writing_diversity\", \"file\": \"related_work.tex\", \"line\": 37, \"command\": \"cite\"}, {\"key\": \"stamatatos_survey\", \"file\": \"related_work.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"koppel_authorship\", \"file\": \"related_work.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"neal2017surveying\", \"file\": \"related_work.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"mccarthy2010mtld\", \"file\": \"related_work.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"covington2010mattr\", \"file\": \"related_work.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"uchendu_attribution\", \"file\": \"related_work.tex\", \"line\": 39, \"command\": \"cite\"}, {\"key\": \"nucleus_sampling\", \"file\": \"related_work.tex\", \"line\": 39, \"command\": \"cite\"}, {\"key\": \"dsir\", \"file\": \"related_work.tex\", \"line\": 44, \"command\": \"cite\"}, {\"key\": \"qurating\", \"file\": \"related_work.tex\", \"line\": 44, \"command\": \"cite\"}, {\"key\": \"ccnet\", \"file\": \"related_work.tex\", \"line\": 44, \"command\": \"cite\"}, {\"key\": \"oren2024proving\", \"file\": \"related_work.tex\", \"line\": 44, \"command\": \"cite\"}, {\"key\": \"golchin2024time\", \"file\": \"related_work.tex\", \"line\": 44, \"command\": \"cite\"}, {\"key\": \"longpre2024data\", \"file\": \"related_work.tex\", \"line\": 44, \"command\": \"cite\"}, {\"key\": \"watermark_llm\", \"file\": \"related_work.tex\", \"line\": 46, \"command\": \"cite\"}, {\"key\": \"synthid_text\", \"file\": \"related_work.tex\", \"line\": 46, \"command\": \"cite\"}, {\"key\": \"aaronson_watermark\", \"file\": \"related_work.tex\", \"line\": 46, \"command\": \"cite\"}, {\"key\": \"chainwash\", \"file\": \"related_work.tex\", \"line\": 46, \"command\": \"cite\"}, {\"key\": \"min_k_percent\", \"file\": \"related_work.tex\", \"line\": 47, \"command\": \"citet\"}, {\"key\": \"pythia\", \"file\": \"method.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"olmo\", \"file\": \"method.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"qwen3\", \"file\": \"method.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"llama3\", \"file\": \"method.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"mistral7b\", \"file\": \"method.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"xgboost\", \"file\": \"method.tex\", \"line\": 75, \"command\": \"cite\"}, {\"key\": \"coral_ordinal\", \"file\": \"method.tex\", \"line\": 77, \"command\": \"cite\"}, {\"key\": \"corn_ordinal\", \"file\": \"method.tex\", \"line\": 77, \"command\": \"cite\"}, {\"key\": \"frank_hall_ordinal\", \"file\": \"method.tex\", \"line\": 77, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt\", \"file\": \"method.tex\", \"line\": 86, \"command\": \"cite\"}, {\"key\": \"binoculars\", \"file\": \"method.tex\", \"line\": 86, \"command\": \"cite\"}, {\"key\": \"ld_score\", \"file\": \"method.tex\", \"line\": 86, \"command\": \"cite\"}, {\"key\": \"cohen1988statistical\", \"file\": \"results.tex\", \"line\": 72, \"command\": \"cite\"}, {\"key\": \"strobl_conditional_2008\", \"file\": \"results.tex\", \"line\": 90, \"command\": \"cite\"}, {\"key\": \"curse_of_recursion\", \"file\": \"discussion.tex\", \"line\": 25, \"command\": \"cite\"}, {\"key\": \"strong_model_collapse\", \"file\": \"discussion.tex\", \"line\": 25, \"command\": \"cite\"}, {\"key\": \"qlora\", \"file\": \"appendix_qlora.tex\", \"line\": 1, \"command\": \"cite\"}, {\"key\": \"coral_ordinal\", \"file\": \"appendix_classifier.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"frank_hall_ordinal\", \"file\": \"appendix_classifier.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"lakens_equivalence\", \"file\": \"appendix_downstream.tex\", \"line\": 41, \"command\": \"cite\"}, {\"key\": \"lakens_equivalence\", \"file\": \"appendix_tost.tex\", \"line\": 4, \"command\": \"cite\"}, {\"key\": \"cohen1988statistical\", \"file\": \"appendix_tost.tex\", \"line\": 5, \"command\": \"cite\"}], \"online_verification\": [{\"key\": \"mccarthy2010mtld\", \"title\": \"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"MTLD, vocd-D, and HD-D: A validation study of sophisticated approaches to lexical diversity assessment\", \"matched_year\": \"2010\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"covington2010mattr\", \"title\": \"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\", \"status\": \"verified\", \"confidence\": 0.986, \"matched_title\": \"Cutting the Gordian Knot: The Moving-Average Type–Token Ratio (MATTR)\", \"matched_year\": \"2010\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"oren2024proving\", \"title\": \"Proving Test Set Contamination in Black Box Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Proving Test Set Contamination in Black Box Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"golchin2024time\", \"title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"longpre2024data\", \"title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"cohen1988statistical\", \"title\": \"Statistical Power Analysis for the Behavioral Sciences\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Statistical Power Analysis for the Behavioral Sciences\", \"matched_year\": \"1989\", \"mismatch_fields\": [\"first_author: bib=cohen vs api=muller\"], \"note\": \"\"}, {\"key\": \"tang2024science\", \"title\": \"The Science of Detecting LLM-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Science of Detecting LLM-Generated Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"neal2017surveying\", \"title\": \"Surveying Stylometry Techniques and Applications\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Surveying Stylometry Techniques and Applications\", \"matched_year\": \"2017\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"detectgpt\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"status\": \"not_found\", \"confidence\": 0.382, \"matched_title\": \"Regulating ChatGPT and other Large Generative AI Models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.38 below threshold 0.82\"}, {\"key\": \"gltr\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dna_gpt\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"binoculars\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"fast_detectgpt\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"ld_score\", \"title\": \"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"intrinsic_dimension\", \"title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"diveye\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Diversity Boosts AI-Generated Text Detection\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"generator_barrier\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"feat_aug_transformer\", \"title\": \"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"reliable_detection\", \"title\": \"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\", \"status\": \"not_found\", \"confidence\": 0.344, \"matched_title\": \"2015 ESC Guidelines for the management of acute coronary syndromes in patients presenting without persistent ST-segment elevation\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.34 below threshold 0.82\"}, {\"key\": \"paraphrase_evades\", \"title\": \"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Paraphrasing evades detectors of AI-generated text, but retrieval is an effective defense\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"detection_possibilities\", \"title\": \"Position: On the Possibilities of AI-Generated Text Detection\", \"status\": \"not_found\", \"confidence\": 0.253, \"matched_title\": \"Review of deep learning: concepts, CNN architectures, challenges, applications, future directions\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.25 below threshold 0.82\"}, {\"key\": \"grover\", \"title\": \"Defending Against Neural Fake News\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Defending Against Neural Fake News\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"release_strategies\", \"title\": \"Release Strategies and the Social Impacts of Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Release Strategies and the Social Impacts of Language Models\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"beyond_binary\", \"title\": \"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"semeval2024_task8\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"abburi_multifaceted\", \"title\": \"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"defactify_dataset\", \"title\": \"A Comprehensive Dataset for Human vs.\\\\ AI Generated Text Detection\", \"status\": \"not_found\", \"confidence\": 0.355, \"matched_title\": \"Performance of ChatGPT on USMLE: Potential for AI-assisted medical education using large language models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.36 below threshold 0.82\"}, {\"key\": \"self_consuming_mad\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Self-Consuming Generative Models go MAD\", \"matched_year\": \"2023\", \"mismatch_fields\": [\"first_author: bib=alemohammad vs api=casco-rodriguez\"], \"note\": \"\"}, {\"key\": \"curse_of_recursion\", \"title\": \"AI models collapse when trained on recursively generated data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"AI models collapse when trained on recursively generated data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"strong_model_collapse\", \"title\": \"Strong Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Strong Model Collapse\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"model_collapse_avoidable\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"self_rewarding_lms\", \"title\": \"Self-Rewarding Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Self-Rewarding Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"spin\", \"title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qlora\", \"title\": \"QLoRA: Efficient Finetuning of Quantized Language Models\", \"status\": \"verified\", \"confidence\": 0.871, \"matched_title\": \"QLoRA: Efficient Finetuning of Quantized LLMs\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dsir\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Data Selection for Language Models via Importance Resampling\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qurating\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"ccnet\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"watermark_llm\", \"title\": \"A Watermark for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Watermark for Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"synthid_text\", \"title\": \"Scalable Watermarking for Identifying Large Language Model Outputs\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Scalable watermarking for identifying large language model outputs\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"aaronson_watermark\", \"title\": \"Watermarking GPT Outputs\", \"status\": \"not_found\", \"confidence\": 0.418, \"matched_title\": \"Undetectable Watermarks for Language Models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.42 below threshold 0.82\"}, {\"key\": \"chainwash\", \"title\": \"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"curious_decline\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"writing_diversity\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"nucleus_sampling\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Case of Neural Text Degeneration\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"stamatatos_survey\", \"title\": \"A Survey of Modern Authorship Attribution Methods\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A survey of modern authorship attribution methods\", \"matched_year\": \"2008\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"koppel_authorship\", \"title\": \"Computational Methods in Authorship Attribution\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Computational methods in authorship attribution\", \"matched_year\": \"2008\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"uchendu_attribution\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Authorship Attribution for Neural Text Generation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"munir_looking_glass\", \"title\": \"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\", \"matched_year\": \"2021\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"broken_telephone\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"attractor_cycles\", \"title\": \"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"markovian_chains\", \"title\": \"Markovian Generation Chains in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Markovian Generation Chains in Large Language Models\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"min_k_percent\", \"title\": \"Detecting Pretraining Data from Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Detecting Pretraining Data from Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wu_survey_2025\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"jawahar_survey\", \"title\": \"Automatic Detection of Machine Generated Text: A Critical Survey\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Automatic Detection of Machine Generated Text: A Critical Survey\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pythia\", \"title\": \"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\", \"status\": \"not_found\", \"confidence\": 0.497, \"matched_title\": \"The TRIPOD-LLM reporting guideline for studies using large language models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.50 below threshold 0.82\"}, {\"key\": \"olmo\", \"title\": \"OLMo: Accelerating the Science of Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"OLMo: Accelerating the Science of Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qwen3\", \"title\": \"Qwen3 Technical Report\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Qwen3 Technical Report\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=team vs api=yang\"], \"note\": \"\"}, {\"key\": \"ghostbuster\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"two_birds\", \"title\": \"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\", \"status\": \"not_found\", \"confidence\": 0.32, \"matched_title\": \"Large AI Models in Health Informatics: Applications, Challenges, and the Future\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.32 below threshold 0.82\"}, {\"key\": \"beyond_final_actor\", \"title\": \"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\", \"status\": \"not_found\", \"confidence\": 0.722, \"matched_title\": \"Beyond the Final Actor: Modeling the Dual Roles of Creator and Editor for Fine-Grained LLM-Generated Text Detection\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.72 below threshold 0.82\"}, {\"key\": \"gutierrez_ordinal_survey\", \"title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"matched_year\": \"2015\", \"mismatch_fields\": [\"first_author: bib=guti\\\\'errez vs api=gutiérrez\"], \"note\": \"\"}, {\"key\": \"coral_ordinal\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Rank consistent ordinal regression for neural networks with application to age estimation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"frank_hall_ordinal\", \"title\": \"A Simple Approach to Ordinal Classification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Simple Approach to Ordinal Classification\", \"matched_year\": \"2001\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pang_opinion_mining\", \"title\": \"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Seeing stars: Exploiting class relationships for sentiment categorization with respect to rating scales\", \"matched_year\": \"2005\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"taghipour_neural_essay\", \"title\": \"A Neural Approach to Automated Essay Scoring\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Neural Approach to Automated Essay Scoring\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"corn_ordinal\", \"title\": \"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Deep neural networks for rank-consistent ordinal regression based on conditional probabilities\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"xgboost\", \"title\": \"XGBoost: A Scalable Tree Boosting System\", \"status\": \"not_found\", \"confidence\": 0.298, \"matched_title\": \"XGBoost\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.30 below threshold 0.82\"}, {\"key\": \"lakens_equivalence\", \"title\": \"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\", \"status\": \"verified\", \"confidence\": 0.976, \"matched_title\": \"Equivalence Tests: A Practical Primer for t-Tests, Correlations, and Meta-Analyses\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"llama3\", \"title\": \"The Llama 3 Herd of Models\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"The Llama 3 herd of models\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=grattafiori vs api=aaron\"], \"note\": \"\"}, {\"key\": \"mistral7b\", \"title\": \"Mistral 7B\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mistral 7B\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"strobl_conditional_2008\", \"title\": \"Conditional Variable Importance for Random Forests\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Conditional variable importance for random forests\", \"matched_year\": \"2008\", \"mismatch_fields\": [], \"note\": \"\"}]}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "669ed31a-97e7-4887-bd15-8b2a96168a96",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Runtime record

_source line 29 · 2026-05-19T06:17:25.953Z_

```json
{
  "parentUuid": "625140a3-1aac-4aa3-b18c-51137aec5276",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "6c414b1d-faf1-46d2-9d7f-ed14af35b00a",
  "timestamp": "2026-05-19T06:17:25.953Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---


### Runtime record

_source line 30_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 2  **你的审查侧重：新颖性 + 论文完整性 + 写作质量 + 格式合规**  ### 论文信息 - **标题**: Depth Profiling: Classifying Recursive Generation Depth in Base LLM Text Chains - **路径**: `projec…",
  "leafUuid": "6c414b1d-faf1-46d2-9d7f-ed14af35b00a",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Runtime record

_source line 31_

```json
{
  "type": "ai-title",
  "aiTitle": "Review depth profiling LLM paper for EMNLP",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Assistant

_source line 32 · 2026-05-19T06:17:28.931Z_

<details><summary>Logged reasoning block</summary>

```text
Let me read the full reference verification results and fetch the ARR reviewer guidelines. Also need to read all the paper sections.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6c414b1d-faf1-46d2-9d7f-ed14af35b00a",
  "isSidechain": false,
  "requestId": "req_011CbBSTrDbwZzahyESiLTBV",
  "type": "assistant",
  "uuid": "06805f99-131d-4afb-824a-0dc9fecc527b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRnxsSQBR2khGm9XsTaGLu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3705,
      "cache_read_input_tokens": 31700,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3705,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 3705,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3705
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Assistant

_source line 33 · 2026-05-19T06:17:30.906Z_

论文主框架已读取，引用验证完成（71 条引用，0 orphan，0 missing）。现在并行读取各 section 和 ARR reviewer guidelines。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "06805f99-131d-4afb-824a-0dc9fecc527b",
  "isSidechain": false,
  "requestId": "req_011CbBSTrDbwZzahyESiLTBV",
  "type": "assistant",
  "uuid": "c430d134-95ba-45ca-a618-eb3ad5be556d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRnxsSQBR2khGm9XsTaGLu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3705,
      "cache_read_input_tokens": 31700,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3705,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 3705,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3705
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Tool call

_source line 34 · 2026-05-19T06:17:33.409Z_

<details open><summary>🔧 Tool call — WebFetch · `toolu_01HDt2zWwruNVH7wWq649C2G`</summary>

```json
{
  "url": "https://aclrollingreview.org/reviewerguidelines",
  "prompt": "Extract the complete review form dimensions, scoring criteria, and scale descriptions. I need: 1) All scoring dimensions (soundness, excitement, overall, etc.) with their scale descriptions. 2) What each score level means. 3) Any specific guidelines about what reviewers should evaluate."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c430d134-95ba-45ca-a618-eb3ad5be556d",
  "isSidechain": false,
  "requestId": "req_011CbBSTrDbwZzahyESiLTBV",
  "type": "assistant",
  "uuid": "c485135b-ce29-4bf9-a8b5-e1e58989473f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRnxsSQBR2khGm9XsTaGLu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3705,
      "cache_read_input_tokens": 31700,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3705,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 3705,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3705
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 35 · 2026-05-19T06:17:39.097Z_

<details><summary>↩ Tool result · `toolu_01HnqqPw3dmxjzK9KEwzmLe2`</summary>

```text
1	\section*{Ethics Statement}
2	\label{sec:ethics}
3	
4	All texts analyzed in this work are LLM-generated from publicly available Wikipedia seeds; no personal or sensitive data is involved.
5	Our method estimates the generation depth of a text passage (how many recursive generation steps it has undergone), not the identity of its author.
6	Individual authorship attribution is outside both the scope and the capability of this approach; privacy implications are minimal.
7	We acknowledge that depth estimation tools could in principle be used to selectively suppress machine-generated text in contexts where such content is legitimate (e.g., accessibility tools, assistive writing).
8	We encourage deployment in data governance pipelines where provenance transparency, rather than content removal, is the objective.
9	All code, data, and trained models will be released upon publication.
10	
11	\paragraph{Licenses.}
12	All generator models are publicly available under permissive licenses (Apache 2.0 for Pythia, OLMo, and Mistral; Qwen License for Qwen3; Llama Community License for Llama 3.2).
13	Wikipedia seed passages are distributed under CC BY-SA 3.0.
14	
15	\paragraph{Compute budget.}
16	All experiments were conducted on 4$\times$ NVIDIA RTX 5090 GPUs (32\,GB each), totaling approximately 62 GPU-hours.
17	
18	\paragraph{Software.}
19	Experiments used Python 3.12.3, PyTorch 2.10.0 (CUDA 12.8), Transformers 4.57.6, XGBoost 3.2.0, scikit-learn 1.8.0, NumPy 2.2.6, pandas 3.0.2, and SciPy 1.17.1.
20	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "838a4ffe-5ff3-417e-9138-cd772e58c9c6",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "8bbdd5c5-eca4-4a96-99ff-5594df69cbd5",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/ethics.tex",
      "content": "\\section*{Ethics Statement}\n\\label{sec:ethics}\n\nAll texts analyzed in this work are LLM-generated from publicly available Wikipedia seeds; no personal or sensitive data is involved.\nOur method estimates the generation depth of a text passage (how many recursive generation steps it has undergone), not the identity of its author.\nIndividual authorship attribution is outside both the scope and the capability of this approach; privacy implications are minimal.\nWe acknowledge that depth estimation tools could in principle be used to selectively suppress machine-generated text in contexts where such content is legitimate (e.g., accessibility tools, assistive writing).\nWe encourage deployment in data governance pipelines where provenance transparency, rather than content removal, is the objective.\nAll code, data, and trained models will be released upon publication.\n\n\\paragraph{Licenses.}\nAll generator models are publicly available under permissive licenses (Apache 2.0 for Pythia, OLMo, and Mistral; Qwen License for Qwen3; Llama Community License for Llama 3.2).\nWikipedia seed passages are distributed under CC BY-SA 3.0.\n\n\\paragraph{Compute budget.}\nAll experiments were conducted on 4$\\times$ NVIDIA RTX 5090 GPUs (32\\,GB each), totaling approximately 62 GPU-hours.\n\n\\paragraph{Software.}\nExperiments used Python 3.12.3, PyTorch 2.10.0 (CUDA 12.8), Transformers 4.57.6, XGBoost 3.2.0, scikit-learn 1.8.0, NumPy 2.2.6, pandas 3.0.2, and SciPy 1.17.1.\n",
      "numLines": 20,
      "startLine": 1,
      "totalLines": 20
    }
  },
  "sourceToolAssistantUUID": "838a4ffe-5ff3-417e-9138-cd772e58c9c6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 36 · 2026-05-19T06:17:34.782Z_

<details open><summary>🔧 Tool call — Read · `toolu_01VjHKTEkLgVdEgreRZFB8S1`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c485135b-ce29-4bf9-a8b5-e1e58989473f",
  "isSidechain": false,
  "requestId": "req_011CbBSTrDbwZzahyESiLTBV",
  "type": "assistant",
  "uuid": "06e95a05-8090-4828-8145-f8f481c21153",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRnxsSQBR2khGm9XsTaGLu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3705,
      "cache_read_input_tokens": 31700,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3705,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 3705,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3705
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 37 · 2026-05-19T06:17:34.789Z_

<details><summary>↩ Tool result · `toolu_01VjHKTEkLgVdEgreRZFB8S1`</summary>

```text
1	% Abstract — Depth Profiling of Recursive LLM Generation Chains
2	\begin{abstract}
3	Text generated by large language models (LLMs) increasingly re-enters the web and seeds subsequent generation, producing recursive chains that progressively diverge from human-written text.
4	We study this phenomenon in base (pretrained) models and ask whether the drift is structured enough to classify how many generation steps a text has undergone, framing this as \emph{generation depth classification} (gen-0\,/\,gen-1\,/\,gen-2+ rather than binary real-vs-synthetic).
5	Across eight base models from five families (0.6B--8B parameters), we identify a \emph{differential depth response} (DDR): features partition into drifting ($d{=}0.76$--$1.17$), intermediate, and near-stationary ($d < 0.10$) groups, consistent with recursive generation shifting the NLL location while distributional shape remains stable.
6	A 7-feature ensemble achieves leak-free binary F1\,=\,0.694 under leave-one-generator-out evaluation, generalizing across model families.
7	The depth signal degrades substantially under instruction tuning, restricting current applicability to base models.
8	\end{abstract}
9	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "06e95a05-8090-4828-8145-f8f481c21153",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "a37b53e4-f827-4b27-aebe-a4696ea91a02",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex",
      "content": "% Abstract — Depth Profiling of Recursive LLM Generation Chains\n\\begin{abstract}\nText generated by large language models (LLMs) increasingly re-enters the web and seeds subsequent generation, producing recursive chains that progressively diverge from human-written text.\nWe study this phenomenon in base (pretrained) models and ask whether the drift is structured enough to classify how many generation steps a text has undergone, framing this as \\emph{generation depth classification} (gen-0\\,/\\,gen-1\\,/\\,gen-2+ rather than binary real-vs-synthetic).\nAcross eight base models from five families (0.6B--8B parameters), we identify a \\emph{differential depth response} (DDR): features partition into drifting ($d{=}0.76$--$1.17$), intermediate, and near-stationary ($d < 0.10$) groups, consistent with recursive generation shifting the NLL location while distributional shape remains stable.\nA 7-feature ensemble achieves leak-free binary F1\\,=\\,0.694 under leave-one-generator-out evaluation, generalizing across model families.\nThe depth signal degrades substantially under instruction tuning, restricting current applicability to base models.\n\\end{abstract}\n",
      "numLines": 9,
      "startLine": 1,
      "totalLines": 9
    }
  },
  "sourceToolAssistantUUID": "06e95a05-8090-4828-8145-f8f481c21153",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 38 · 2026-05-19T06:17:35.170Z_

<details open><summary>🔧 Tool call — Read · `toolu_017KxeBrbKjZxTsewRucVP7X`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a37b53e4-f827-4b27-aebe-a4696ea91a02",
  "isSidechain": false,
  "requestId": "req_011CbBSTrDbwZzahyESiLTBV",
  "type": "assistant",
  "uuid": "2ca1a511-e729-425c-8eff-41ad86af7c9d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRnxsSQBR2khGm9XsTaGLu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3705,
      "cache_read_input_tokens": 31700,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3705,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 3705,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3705
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 39 · 2026-05-19T06:17:35.175Z_

<details><summary>↩ Tool result · `toolu_017KxeBrbKjZxTsewRucVP7X`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	When LLM outputs are fed back as inputs to subsequent generation, the resulting recursive chains form a dynamical system whose distributional properties evolve with each step.
5	Characterizing the structure of this evolution is fundamental to understanding how base language models transform distributions under iterative conditioning, with relevance to understanding model collapse dynamics \cite{curse_of_recursion, self_consuming_mad}.
6	Yet binary detection decisions \cite{fast_detectgpt,binoculars,ld_score,detectgpt} obscure this structure: a first-generation continuation retains much of the source distribution's lexical properties, while deeper recursive text exhibits measurably reduced vocabulary diversity and compressed perplexity.
7	
8	We formulate \emph{generation depth classification}, classifying text by generation depth (gen-0\,/\,gen-1\,/\,gen-2+) rather than a binary label, and term this \emph{depth profiling}.
9	No existing method provides a feature-level decomposition of depth signal in non-paraphrastic continuation chains.
10	
11	The key finding is a \emph{differential depth response} (DDR) with a three-way partition: when we measure how eight base-model generators from five families (Pythia, OLMo, Qwen, Llama, Mistral; 0.6B--8B parameters) transform text across recursive depths, three \emph{drifting} features (reference-model mean entropy, type-token ratio, hapax ratio) shift monotonically (Cohen's $d > 0.75$), one \emph{intermediate} feature (entropy std) shows a non-monotonic level shift ($d{=}0.55$), and three \emph{near-stationary} features (entropy max, tail decay, entropy min) exhibit negligible depth effects ($d < 0.10$).
12	This is consistent with recursive generation shifting the NLL location while distributional shape remains stable under fixed sampling parameters.
13	While distributional drift under recursive generation is documented in the model collapse literature \cite{curse_of_recursion, self_consuming_mad}, the structured tri-partition and its exploitation for depth classification have not been previously reported.
14	We restrict to base (pretrained) models: by isolating the generation mechanism from instruction-tuning effects, base models provide a controlled setting in which to study whether recursive distributional drift exhibits systematic structure (\S\ref{sec:discussion}).
15	
16	A 7-feature ensemble combining all three groups achieves leak-free binary F1\,=\,0.694 under eight-generator leave-one-generator-out (LOGO) evaluation and 0.764 on cross-model chains, using a single 410M-parameter reference model (\S\ref{sec:results-baselines}).
17	
18	Our contributions are empirical rather than methodological:
19	\begin{enumerate}[nosep,leftmargin=*]
20	    \item We formulate generation depth classification, moving beyond binary real-vs-synthetic detection to classify text as gen-0\,/\,gen-1\,/\,gen-2+, and construct an evaluation suite of 37{,}058 texts from eight base-model generators spanning five families (0.6B--8B parameters).
21	    \item We identify a \emph{differential depth response} (DDR) in base models: data-driven analysis reveals a primary drifting/non-drifting partition ($k{=}2$, silhouette\,=\,0.632); domain-informed criteria further resolve a 3/1/3 characterization (three drifting features, $|\rho| > 0.60$, $d{=}0.76$--$1.17$; one intermediate, $d{=}0.55$; three near-stationary, $d < 0.10$) with a ${\geq}9.5\times$ effect-size gap confirmed under heteroscedasticity-robust metrics (Appendix~\ref{app:ddr-validation}).
22	    \item We map DDR's boundary conditions: the depth signal is robust within $t \in [0.5, 0.7]$ but attenuates at higher temperatures ($-9.3$ to $-26.0$\,pp at $t{=}0.9$). Instruction tuning compresses the DDR partition structure (silhouette: $0.632 \rightarrow 0.338$) rather than simply reversing feature directions; domain-specific retraining partially recovers within-model classification ($+$7--27\,pp) but cross-generator transfer remains weak (\S\ref{sec:discussion}).
23	\end{enumerate}
24	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2ca1a511-e729-425c-8eff-41ad86af7c9d",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "ed0136a9-f9ee-4c94-b761-7463f425bc45",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nWhen LLM outputs are fed back as inputs to subsequent generation, the resulting recursive chains form a dynamical system whose distributional properties evolve with each step.\nCharacterizing the structure of this evolution is fundamental to understanding how base language models transform distributions under iterative conditioning, with relevance to understanding model collapse dynamics \\cite{curse_of_recursion, self_consuming_mad}.\nYet binary detection decisions \\cite{fast_detectgpt,binoculars,ld_score,detectgpt} obscure this structure: a first-generation continuation retains much of the source distribution's lexical properties, while deeper recursive text exhibits measurably reduced vocabulary diversity and compressed perplexity.\n\nWe formulate \\emph{generation depth classification}, classifying text by generation depth (gen-0\\,/\\,gen-1\\,/\\,gen-2+) rather than a binary label, and term this \\emph{depth profiling}.\nNo existing method provides a feature-level decomposition of depth signal in non-paraphrastic continuation chains.\n\nThe key finding is a \\emph{differential depth response} (DDR) with a three-way partition: when we measure how eight base-model generators from five families (Pythia, OLMo, Qwen, Llama, Mistral; 0.6B--8B parameters) transform text across recursive depths, three \\emph{drifting} features (reference-model mean entropy, type-token ratio, hapax ratio) shift monotonically (Cohen's $d > 0.75$), one \\emph{intermediate} feature (entropy std) shows a non-monotonic level shift ($d{=}0.55$), and three \\emph{near-stationary} features (entropy max, tail decay, entropy min) exhibit negligible depth effects ($d < 0.10$).\nThis is consistent with recursive generation shifting the NLL location while distributional shape remains stable under fixed sampling parameters.\nWhile distributional drift under recursive generation is documented in the model collapse literature \\cite{curse_of_recursion, self_consuming_mad}, the structured tri-partition and its exploitation for depth classification have not been previously reported.\nWe restrict to base (pretrained) models: by isolating the generation mechanism from instruction-tuning effects, base models provide a controlled setting in which to study whether recursive distributional drift exhibits systematic structure (\\S\\ref{sec:discussion}).\n\nA 7-feature ensemble combining all three groups achieves leak-free binary F1\\,=\\,0.694 under eight-generator leave-one-generator-out (LOGO) evaluation and 0.764 on cross-model chains, using a single 410M-parameter reference model (\\S\\ref{sec:results-baselines}).\n\nOur contributions are empirical rather than methodological:\n\\begin{enumerate}[nosep,leftmargin=*]\n    \\item We formulate generation depth classification, moving beyond binary real-vs-synthetic detection to classify text as gen-0\\,/\\,gen-1\\,/\\,gen-2+, and construct an evaluation suite of 37{,}058 texts from eight base-model generators spanning five families (0.6B--8B parameters).\n    \\item We identify a \\emph{differential depth response} (DDR) in base models: data-driven analysis reveals a primary drifting/non-drifting partition ($k{=}2$, silhouette\\,=\\,0.632); domain-informed criteria further resolve a 3/1/3 characterization (three drifting features, $|\\rho| > 0.60$, $d{=}0.76$--$1.17$; one intermediate, $d{=}0.55$; three near-stationary, $d < 0.10$) with a ${\\geq}9.5\\times$ effect-size gap confirmed under heteroscedasticity-robust metrics (Appendix~\\ref{app:ddr-validation}).\n    \\item We map DDR's boundary conditions: the depth signal is robust within $t \\in [0.5, 0.7]$ but attenuates at higher temperatures ($-9.3$ to $-26.0$\\,pp at $t{=}0.9$). Instruction tuning compresses the DDR partition structure (silhouette: $0.632 \\rightarrow 0.338$) rather than simply reversing feature directions; domain-specific retraining partially recovers within-model classification ($+$7--27\\,pp) but cross-generator transfer remains weak (\\S\\ref{sec:discussion}).\n\\end{enumerate}\n",
      "numLines": 24,
      "startLine": 1,
      "totalLines": 24
    }
  },
  "sourceToolAssistantUUID": "2ca1a511-e729-425c-8eff-41ad86af7c9d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 40 · 2026-05-19T06:17:36.133Z_

<details open><summary>🔧 Tool call — Read · `toolu_01M5GztXvmi5vyQ71nyE22Bh`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ed0136a9-f9ee-4c94-b761-7463f425bc45",
  "isSidechain": false,
  "requestId": "req_011CbBSTrDbwZzahyESiLTBV",
  "type": "assistant",
  "uuid": "0e6b202b-c122-4ca4-b2aa-f3c58212e90f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRnxsSQBR2khGm9XsTaGLu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3705,
      "cache_read_input_tokens": 31700,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3705,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 3705,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3705
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 41 · 2026-05-19T06:17:36.137Z_

<details><summary>↩ Tool result · `toolu_01M5GztXvmi5vyQ71nyE22Bh`</summary>

```text
1	\section{Related Work}
2	\label{sec:related}
3	
4	\subsection{AI-Generated Text Detection}
5	\label{sec:related-detection}
6	
7	Methods for distinguishing human-written from machine-generated text have evolved from statistical tests \cite{gltr,grover,release_strategies} to zero-shot reference-model approaches \cite{detectgpt,fast_detectgpt,binoculars,dna_gpt} and learned classifiers that combine handcrafted features with neural architectures \cite{ghostbuster,feat_aug_transformer,abburi_multifaceted,reliable_detection,ld_score}.
8	Recent work pursues diverse signals including intrinsic dimensionality \cite{intrinsic_dimension}, surprisal diversity \cite{diveye}, and distributional gap measures \cite{generator_barrier}; see \citet{tang2024science}, \citet{wu_survey_2025}, and \citet{jawahar_survey} for surveys.
9	A persistent limitation is that these methods produce binary (real vs.\ synthetic) decisions.
10	Recent work moves beyond binary detection along several axes.
11	\citet{beyond_binary} classify text into four roles (human-only, LLM-polished, LLM-expanded, LLM-only) via involvement measurement, discriminating production \emph{modes} rather than recursive depth.
12	\citet{two_birds} jointly detect machine-generated text and attribute it to specific LLMs, and \citet{beyond_final_actor} distinguish dual creator-editor roles across four production modes.
13	Multi-generator attribution, including generator-level classification in SemEval 2024 Task 8 Subtask B \cite{semeval2024_task8} and the DeFactify dataset \cite{defactify_dataset}, discriminates among different \emph{sources}.
14	All these approaches classify text by its production process or authorship, while our depth classification tracks how many recursive generation steps a text has undergone, an orthogonal axis.
15	Even when detection scores correlate with depth, they exhibit high cross-generator variance as ordinal predictors (binary F1 from 0.52 to 0.71; Table~\ref{tab:baselines}), because each captures a single distributional property that generalizes inconsistently \cite{paraphrase_evades,detection_possibilities}.
16	Our contribution is not a new detection method but the task formulation (generation depth classification, framed within the ordinal classification literature \cite{gutierrez_ordinal_survey,coral_ordinal,corn_ordinal,frank_hall_ordinal}; ordinal approaches have been applied to sentiment analysis \cite{pang_opinion_mining} and essay scoring \cite{taghipour_neural_essay}) and the finding that combining drifting, intermediate, and near-stationary features yields consistent cross-generator performance.
17	This is orthogonal to source attribution \cite{uchendu_attribution,munir_looking_glass}, which identifies \emph{which} model generated text; our LOGO evaluation decouples generator identity from depth.
18	
19	\subsection{Model Collapse and Iterative Generation}
20	\label{sec:related-collapse}
21	
22	Iterative generation can degrade text quality through two distinct mechanisms: \emph{training-loop} drift, where models retrained on their own outputs progressively lose distributional coverage, and \emph{inference-chain} drift, where a fixed model generates text conditioned on its own prior output without retraining.
23	Self-consuming generative models progressively lose distributional coverage \cite{self_consuming_mad}, and model collapse is inevitable without fresh human data \cite{curse_of_recursion}, though careful data mixing can mitigate this \cite{model_collapse_avoidable,strong_model_collapse}.
24	Self-training and self-play approaches \cite{self_rewarding_lms,spin} also involve iterative self-generation but optimize a training objective; these studies focus on training-loop degradation, whereas our setting studies inference chains.
25	The distinction extends beyond setting: model collapse erodes distributional tail coverage irreversibly as training progresses \cite{curse_of_recursion,strong_model_collapse}. In contrast, the inference-chain drift we observe is fully reversible under fixed parameters, and distributional shape exhibits negligible depth effects (Cohen's $d < 0.10$; \S\ref{sec:results-differential}).
26	The drifting/intermediate/near-stationary tri-partition central to our analysis has no analogue in model collapse studies, which track aggregate divergence without separating location from shape components.
27	Three concurrent works are most directly relevant.
28	\citet{broken_telephone} analyze paraphrasing and translation chains, showing progressive information loss under semantic-preservation constraints that confine depth signal to surface-level lexical decay.
29	\citet{markovian_chains} demonstrate that such constraints induce Markovian attractor dynamics bounding distinguishable depth to approximately three classes.
30	\citet{attractor_cycles} provide a dynamical-systems analysis of successive paraphrasing, identifying attractor cycles that characterize convergence behavior; our work extends the attractor perspective to non-paraphrastic continuation chains with a feature-level decomposition.
31	All three study paraphrastic chains; we differ in three respects: (i) non-paraphrastic continuation chains permit richer drift (both semantic and distributional); (ii) handcrafted features enable the DDR decomposition into drifting, intermediate, and near-stationary components; and (iii) our tri-partition reveals \emph{what} converges (location) versus what remains stable (shape), while their analyses characterize \emph{that} convergence occurs.
32	That all three works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same ceiling: Markovian attractor dynamics in semantic space \cite{markovian_chains}, surface-level lexical decay under paraphrastic constraints \cite{broken_telephone}, and feature-space compression in continuation chains (inter-class KS drops from 0.28 to 0.09 after depth 2; this work).
33	
34	\subsection{Vocabulary Diversity and Stylometry}
35	\label{sec:related-diversity}
36	
37	Declining lexical diversity in LLM-generated text is documented in both training \cite{curious_decline} and deployment \cite{writing_diversity} settings.
38	Our surface features (TTR and hapax ratio) are classical stylometric measures \cite{stamatatos_survey,koppel_authorship,neal2017surveying}; more sophisticated alternatives exist (MTLD, HD-D \cite{mccarthy2010mtld}; MATTR \cite{covington2010mattr}) but TTR and hapax ratio suffice for depth discrimination.
39	We push beyond generator identity \cite{uchendu_attribution} to the \emph{depth} dimension under top-$p$ sampling \cite{nucleus_sampling}.
40	
41	\subsection{Data Quality and Provenance}
42	\label{sec:related-provenance}
43	
44	Scalable data curation relies on quality signals \cite{dsir,qurating,ccnet}, and recent work highlights the challenge of detecting training data contamination \cite{oren2024proving,golchin2024time} and maintaining data provenance at scale \cite{longpre2024data}.
45	Generation depth is a complementary provenance signal characterizing \emph{how many steps removed} text is from a human source.
46	Proactive watermarking \cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \cite{chainwash}, which motivates passive post-hoc methods like ours.
47	At the feature level, our NLL analysis connects to \citet{min_k_percent}, who use the probability tail for membership inference; we analyze the full NLL distribution for generation depth classification.
48	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0e6b202b-c122-4ca4-b2aa-f3c58212e90f",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "d71b5ec1-9179-4454-974a-fc446086ff06",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex",
      "content": "\\section{Related Work}\n\\label{sec:related}\n\n\\subsection{AI-Generated Text Detection}\n\\label{sec:related-detection}\n\nMethods for distinguishing human-written from machine-generated text have evolved from statistical tests \\cite{gltr,grover,release_strategies} to zero-shot reference-model approaches \\cite{detectgpt,fast_detectgpt,binoculars,dna_gpt} and learned classifiers that combine handcrafted features with neural architectures \\cite{ghostbuster,feat_aug_transformer,abburi_multifaceted,reliable_detection,ld_score}.\nRecent work pursues diverse signals including intrinsic dimensionality \\cite{intrinsic_dimension}, surprisal diversity \\cite{diveye}, and distributional gap measures \\cite{generator_barrier}; see \\citet{tang2024science}, \\citet{wu_survey_2025}, and \\citet{jawahar_survey} for surveys.\nA persistent limitation is that these methods produce binary (real vs.\\ synthetic) decisions.\nRecent work moves beyond binary detection along several axes.\n\\citet{beyond_binary} classify text into four roles (human-only, LLM-polished, LLM-expanded, LLM-only) via involvement measurement, discriminating production \\emph{modes} rather than recursive depth.\n\\citet{two_birds} jointly detect machine-generated text and attribute it to specific LLMs, and \\citet{beyond_final_actor} distinguish dual creator-editor roles across four production modes.\nMulti-generator attribution, including generator-level classification in SemEval 2024 Task 8 Subtask B \\cite{semeval2024_task8} and the DeFactify dataset \\cite{defactify_dataset}, discriminates among different \\emph{sources}.\nAll these approaches classify text by its production process or authorship, while our depth classification tracks how many recursive generation steps a text has undergone, an orthogonal axis.\nEven when detection scores correlate with depth, they exhibit high cross-generator variance as ordinal predictors (binary F1 from 0.52 to 0.71; Table~\\ref{tab:baselines}), because each captures a single distributional property that generalizes inconsistently \\cite{paraphrase_evades,detection_possibilities}.\nOur contribution is not a new detection method but the task formulation (generation depth classification, framed within the ordinal classification literature \\cite{gutierrez_ordinal_survey,coral_ordinal,corn_ordinal,frank_hall_ordinal}; ordinal approaches have been applied to sentiment analysis \\cite{pang_opinion_mining} and essay scoring \\cite{taghipour_neural_essay}) and the finding that combining drifting, intermediate, and near-stationary features yields consistent cross-generator performance.\nThis is orthogonal to source attribution \\cite{uchendu_attribution,munir_looking_glass}, which identifies \\emph{which} model generated text; our LOGO evaluation decouples generator identity from depth.\n\n\\subsection{Model Collapse and Iterative Generation}\n\\label{sec:related-collapse}\n\nIterative generation can degrade text quality through two distinct mechanisms: \\emph{training-loop} drift, where models retrained on their own outputs progressively lose distributional coverage, and \\emph{inference-chain} drift, where a fixed model generates text conditioned on its own prior output without retraining.\nSelf-consuming generative models progressively lose distributional coverage \\cite{self_consuming_mad}, and model collapse is inevitable without fresh human data \\cite{curse_of_recursion}, though careful data mixing can mitigate this \\cite{model_collapse_avoidable,strong_model_collapse}.\nSelf-training and self-play approaches \\cite{self_rewarding_lms,spin} also involve iterative self-generation but optimize a training objective; these studies focus on training-loop degradation, whereas our setting studies inference chains.\nThe distinction extends beyond setting: model collapse erodes distributional tail coverage irreversibly as training progresses \\cite{curse_of_recursion,strong_model_collapse}. In contrast, the inference-chain drift we observe is fully reversible under fixed parameters, and distributional shape exhibits negligible depth effects (Cohen's $d < 0.10$; \\S\\ref{sec:results-differential}).\nThe drifting/intermediate/near-stationary tri-partition central to our analysis has no analogue in model collapse studies, which track aggregate divergence without separating location from shape components.\nThree concurrent works are most directly relevant.\n\\citet{broken_telephone} analyze paraphrasing and translation chains, showing progressive information loss under semantic-preservation constraints that confine depth signal to surface-level lexical decay.\n\\citet{markovian_chains} demonstrate that such constraints induce Markovian attractor dynamics bounding distinguishable depth to approximately three classes.\n\\citet{attractor_cycles} provide a dynamical-systems analysis of successive paraphrasing, identifying attractor cycles that characterize convergence behavior; our work extends the attractor perspective to non-paraphrastic continuation chains with a feature-level decomposition.\nAll three study paraphrastic chains; we differ in three respects: (i) non-paraphrastic continuation chains permit richer drift (both semantic and distributional); (ii) handcrafted features enable the DDR decomposition into drifting, intermediate, and near-stationary components; and (iii) our tri-partition reveals \\emph{what} converges (location) versus what remains stable (shape), while their analyses characterize \\emph{that} convergence occurs.\nThat all three works independently converge on approximately three distinguishable classes reflects different mechanisms reaching the same ceiling: Markovian attractor dynamics in semantic space \\cite{markovian_chains}, surface-level lexical decay under paraphrastic constraints \\cite{broken_telephone}, and feature-space compression in continuation chains (inter-class KS drops from 0.28 to 0.09 after depth 2; this work).\n\n\\subsection{Vocabulary Diversity and Stylometry}\n\\label{sec:related-diversity}\n\nDeclining lexical diversity in LLM-generated text is documented in both training \\cite{curious_decline} and deployment \\cite{writing_diversity} settings.\nOur surface features (TTR and hapax ratio) are classical stylometric measures \\cite{stamatatos_survey,koppel_authorship,neal2017surveying}; more sophisticated alternatives exist (MTLD, HD-D \\cite{mccarthy2010mtld}; MATTR \\cite{covington2010mattr}) but TTR and hapax ratio suffice for depth discrimination.\nWe push beyond generator identity \\cite{uchendu_attribution} to the \\emph{depth} dimension under top-$p$ sampling \\cite{nucleus_sampling}.\n\n\\subsection{Data Quality and Provenance}\n\\label{sec:related-provenance}\n\nScalable data curation relies on quality signals \\cite{dsir,qurating,ccnet}, and recent work highlights the challenge of detecting training data contamination \\cite{oren2024proving,golchin2024time} and maintaining data provenance at scale \\cite{longpre2024data}.\nGeneration depth is a complementary provenance signal characterizing \\emph{how many steps removed} text is from a human source.\nProactive watermarking \\cite{watermark_llm,synthid_text,aaronson_watermark} embeds identifiable patterns, but watermark strength decays across multi-step chains \\cite{chainwash}, which motivates passive post-hoc methods like ours.\nAt the feature level, our NLL analysis connects to \\citet{min_k_percent}, who use the probability tail for membership inference; we analyze the full NLL distribution for generation depth classification.\n",
      "numLines": 48,
      "startLine": 1,
      "totalLines": 48
    }
  },
  "sourceToolAssistantUUID": "0e6b202b-c122-4ca4-b2aa-f3c58212e90f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 42 · 2026-05-19T06:17:36.621Z_

<details open><summary>🔧 Tool call — Read · `toolu_01EFfRRgv3w4UQs7ULWvP7cH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d71b5ec1-9179-4454-974a-fc446086ff06",
  "isSidechain": false,
  "requestId": "req_011CbBSTrDbwZzahyESiLTBV",
  "type": "assistant",
  "uuid": "6490d361-9978-4a06-9db2-5910aed21ad4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRnxsSQBR2khGm9XsTaGLu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3705,
      "cache_read_input_tokens": 31700,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3705,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 3705,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3705
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 43 · 2026-05-19T06:17:36.626Z_

<details><summary>↩ Tool result · `toolu_01EFfRRgv3w4UQs7ULWvP7cH`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Task Formulation}
5	\label{sec:task}
6	
7	Given a text $x$, the goal is to predict its \emph{generation depth} $d \in \{0, 1, 2{+}\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.
8	Formally, let $\mathcal{C}_0$ be a reference corpus of human-written text.
9	A generation chain of depth $k$ is defined recursively: $x^{(0)} \sim \mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.
10	We frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection; this allows finer-grained provenance characterization.
11	Depths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\S\ref{sec:results-differential}).
12	
13	\subsection{Generation Chain Construction}
14	\label{sec:generation}
15	
16	We construct generation chains using eight generators spanning five model families: \textbf{Pythia} (2.8B, 1B) \cite{pythia}, \textbf{OLMo} (OLMo-2-1B) \cite{olmo}, \textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \cite{qwen3}, \textbf{Llama} (Llama-3.2-3B) \cite{llama3}, and \textbf{Mistral} (Mistral-7B-v0.3) \cite{mistral7b}.
17	This selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which allows evaluation of cross-generator and cross-scale generalization.
18	
19	For each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\mathcal{C}_0$.
20	The same pool of seed passages serves as gen-0 for all generators.
21	We use shared seeds across generators so that cross-generator comparisons control for input content and isolate the effect of the generation model from source text variation.
22	In LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.
23	We address this with a supplementary binary evaluation excluding gen-0 entirely (\S\ref{sec:results-baselines}).
24	Each seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\texttt{Continue the following text: \{text\}}''.
25	All generation uses temperature $\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.
26	The theoretical yield is $8 \times {\sim}1{,}000 \times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\ref{app:dataset-stats}).
27	For classification, depths 2--4 are collapsed into the $2{+}$ class.
28	
29	\subsection{Feature Extraction}
30	\label{sec:features}
31	
32	The seven features are motivated by two complementary views of distributional drift.
33	Reference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.
34	Together, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes).
35	We use interpretable distributional statistics rather than learned representations so that the DDR tri-partition (our primary contribution) remains transparent; neural features would yield a black-box classifier.
36	This two-pronged design is validated through leave-one-feature-out analysis (Appendix~\ref{app:lofo}) and cross-group ablation (\S\ref{sec:results-differential}); both analyses confirm that the two feature groups contribute to depth discrimination.
37	
38	We extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.
39	
40	\paragraph{Reference-model features.}
41	A held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.
42	We use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.
43	Although Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\S\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\leq$0.013 across Pythia, OLMo, and Qwen references).
44	From the resulting NLL sequence, we extract five statistics:
45	\begin{itemize}[nosep,leftmargin=*]
46	    \item \textbf{entropy\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;
47	    \item \textbf{entropy\_std}: standard deviation of token-level NLL, which measures the spread of per-token surprise;
48	    \item \textbf{entropy\_max}: maximum token-level NLL, which captures the most surprising token;
49	    \item \textbf{entropy\_min}: minimum token-level NLL, capturing the reference model's confidence floor on the most predictable token;
50	    \item \textbf{tail\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000), capturing how steeply probability mass decays beyond high-frequency tokens.
51	\end{itemize}
52	
53	\paragraph{Surface features.}
54	Two features capture lexical diversity without requiring a reference model:
55	\begin{itemize}[nosep,leftmargin=*]
56	    \item \textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);
57	    \item \textbf{hapax\_ratio}: proportion of words appearing exactly once (\emph{hapax legomena}).
58	\end{itemize}
59	
60	\paragraph{Feature complementarity.}
61	The seven features were selected a priori from two complementary perspectives (reference-model NLL distribution and surface lexical diversity) to enable interpretable decomposition of depth signal; exploring richer feature spaces (syntactic complexity, semantic coherence) may improve classification but at the cost of the location/shape analysis that is the paper's primary contribution.
62	These features exhibit a \emph{differential depth response} (DDR) into drifting, intermediate, and near-stationary groups (\S\ref{sec:results-differential}), motivating their combination (pairwise correlations in Appendix~\ref{sec:appendix-feature-correlation}).
63	TTR and hapax ratio are strongly correlated ($r = 0.97$); both are retained for marginal LOFO gains.
64	
65	\subsection{Evaluation Protocol}
66	\label{sec:evaluation}
67	
68	\paragraph{Cross-validation.}
69	Our experiments use three overlapping generator subsets reflecting chronological expansion: the original 5-generator set (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B) for cross-model chains, a 6-generator set (adding Qwen3-8B) for appendix analyses, and the full 8-generator set (adding Llama-3.2-3B and Mistral-7B-v0.3) for single-generator LOGO. Each table notes its subset.
70	To evaluate generalization to unseen generators, we use \textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators.
71	LOGO holds out individual generators but does not isolate family effects (e.g., when Pythia-1B is held out, Pythia-2.8B remains in training).
72	\textbf{Leave-One-Family-Out (LOFO)} addresses this by holding out entire model families; cross-family generalization holds (average binary F1\,=\,0.686; \S\ref{sec:results-classification}).
73	
74	\paragraph{Classifier.}
75	We use XGBoost \cite{xgboost} throughout ($n\_\text{estimators}{=}200$, $\max\_\text{depth}{=}6$, learning rate $0.1$; standard defaults), with identical hyperparameters across all methods in Table~\ref{tab:baselines}.
76	LOGO F1 is stable across random seeds (std\,$<$\,0.001 over 5 seeds); this near-zero variance reflects the deterministic LOGO splits (each generator held out exactly once) with seeds controlling only XGBoost's internal stochasticity. Bootstrap CIs on held-out folds provide the relevant generalization uncertainty.
77	Alternative classifiers and ordinal-specific methods (CORAL \cite{coral_ordinal}, CORN \cite{corn_ordinal}, Frank-Hall \cite{frank_hall_ordinal}) yield comparable performance (Appendix~\ref{app:classifier}); discriminative power therefore resides in the features, not the classifier.
78	
79	\paragraph{Metrics and statistical testing.}
80	The primary metric is \textbf{macro-averaged F1} over the three depth classes.
81	We report 95\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.
82	All $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\times$ 3 depth-group pairs, \S\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\S\ref{sec:results-baselines}).
83	Feature--depth correlations (\S\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.
84	
85	\paragraph{Baselines.}
86	We compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \cite{fast_detectgpt}, Binoculars \cite{binoculars}, and LD-Score \cite{ld_score}.
87	Each baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation to ensure a controlled comparison.
88	
89	\paragraph{Length confound control.}
90	Since TTR and hapax\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\S\ref{sec:results-classification}; Appendix~\ref{app:length}).
91	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6490d361-9978-4a06-9db2-5910aed21ad4",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "6fc586d4-0eb6-4b42-b308-0656f720c813",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\subsection{Task Formulation}\n\\label{sec:task}\n\nGiven a text $x$, the goal is to predict its \\emph{generation depth} $d \\in \\{0, 1, 2{+}\\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.\nFormally, let $\\mathcal{C}_0$ be a reference corpus of human-written text.\nA generation chain of depth $k$ is defined recursively: $x^{(0)} \\sim \\mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \\geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.\nWe frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection; this allows finer-grained provenance characterization.\nDepths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\\S\\ref{sec:results-differential}).\n\n\\subsection{Generation Chain Construction}\n\\label{sec:generation}\n\nWe construct generation chains using eight generators spanning five model families: \\textbf{Pythia} (2.8B, 1B) \\cite{pythia}, \\textbf{OLMo} (OLMo-2-1B) \\cite{olmo}, \\textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \\cite{qwen3}, \\textbf{Llama} (Llama-3.2-3B) \\cite{llama3}, and \\textbf{Mistral} (Mistral-7B-v0.3) \\cite{mistral7b}.\nThis selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which allows evaluation of cross-generator and cross-scale generalization.\n\nFor each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\\mathcal{C}_0$.\nThe same pool of seed passages serves as gen-0 for all generators.\nWe use shared seeds across generators so that cross-generator comparisons control for input content and isolate the effect of the generation model from source text variation.\nIn LOGO evaluation, gen-0 samples from the held-out generator's chains also appear (with the same text) in the training generators' chains, creating a potential train--test overlap for the gen-0 class.\nWe address this with a supplementary binary evaluation excluding gen-0 entirely (\\S\\ref{sec:results-baselines}).\nEach seed is iteratively fed through the generator to produce a chain of depth 4 (i.e., gen-0 through gen-4), using the prompt ``\\texttt{Continue the following text: \\{text\\}}''.\nAll generation uses temperature $\\tau{=}0.7$, nucleus sampling with $p{=}0.9$, and maximum length of 256 new tokens.\nThe theoretical yield is $8 \\times {\\sim}1{,}000 \\times 5 = 39{,}815$ texts; after removing 2{,}746 chain breaks (empty or degenerate outputs at intermediate depths that prevented deeper generation) and 11 passages too short for feature extraction, 37{,}058 texts remain (Appendix~\\ref{app:dataset-stats}).\nFor classification, depths 2--4 are collapsed into the $2{+}$ class.\n\n\\subsection{Feature Extraction}\n\\label{sec:features}\n\nThe seven features are motivated by two complementary views of distributional drift.\nReference-model features capture how the text's token-level surprise distribution shifts relative to a fixed model; surface features capture how lexical diversity contracts under recursive generation.\nTogether, they span both the generative mechanism (what the model produces) and the surface manifestation (how the vocabulary changes).\nWe use interpretable distributional statistics rather than learned representations so that the DDR tri-partition (our primary contribution) remains transparent; neural features would yield a black-box classifier.\nThis two-pronged design is validated through leave-one-feature-out analysis (Appendix~\\ref{app:lofo}) and cross-group ablation (\\S\\ref{sec:results-differential}); both analyses confirm that the two feature groups contribute to depth discrimination.\n\nWe extract seven distributional features per text, organized into two groups based on what they measure rather than how they are computed.\n\n\\paragraph{Reference-model features.}\nA held-out reference model (Pythia-410M, chosen to be smaller than all generators) computes per-token negative log-likelihood (NLL) for each text.\nWe use ``entropy'' as shorthand for token-level NLL throughout, following convention in prior detection work; these are point-wise NLL values, not Shannon entropy of the full distribution.\nAlthough Pythia-410M shares the GPT-NeoX architecture with two of the eight generators, cross-family reference model experiments (\\S\\ref{sec:results-differential}) confirm that depth features are not reference-specific (LOGO F1 varies by $\\leq$0.013 across Pythia, OLMo, and Qwen references).\nFrom the resulting NLL sequence, we extract five statistics:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{entropy\\_mean}: mean token-level NLL, which captures the average predictability of the text under the reference model;\n    \\item \\textbf{entropy\\_std}: standard deviation of token-level NLL, which measures the spread of per-token surprise;\n    \\item \\textbf{entropy\\_max}: maximum token-level NLL, which captures the most surprising token;\n    \\item \\textbf{entropy\\_min}: minimum token-level NLL, capturing the reference model's confidence floor on the most predictable token;\n    \\item \\textbf{tail\\_decay}: slope of the vocabulary-level averaged log-probability distribution in the mid-rank region (ranks 100--1000), capturing how steeply probability mass decays beyond high-frequency tokens.\n\\end{itemize}\n\n\\paragraph{Surface features.}\nTwo features capture lexical diversity without requiring a reference model:\n\\begin{itemize}[nosep,leftmargin=*]\n    \\item \\textbf{TTR}: type-token ratio (number of unique word types divided by total tokens);\n    \\item \\textbf{hapax\\_ratio}: proportion of words appearing exactly once (\\emph{hapax legomena}).\n\\end{itemize}\n\n\\paragraph{Feature complementarity.}\nThe seven features were selected a priori from two complementary perspectives (reference-model NLL distribution and surface lexical diversity) to enable interpretable decomposition of depth signal; exploring richer feature spaces (syntactic complexity, semantic coherence) may improve classification but at the cost of the location/shape analysis that is the paper's primary contribution.\nThese features exhibit a \\emph{differential depth response} (DDR) into drifting, intermediate, and near-stationary groups (\\S\\ref{sec:results-differential}), motivating their combination (pairwise correlations in Appendix~\\ref{sec:appendix-feature-correlation}).\nTTR and hapax ratio are strongly correlated ($r = 0.97$); both are retained for marginal LOFO gains.\n\n\\subsection{Evaluation Protocol}\n\\label{sec:evaluation}\n\n\\paragraph{Cross-validation.}\nOur experiments use three overlapping generator subsets reflecting chronological expansion: the original 5-generator set (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B) for cross-model chains, a 6-generator set (adding Qwen3-8B) for appendix analyses, and the full 8-generator set (adding Llama-3.2-3B and Mistral-7B-v0.3) for single-generator LOGO. Each table notes its subset.\nTo evaluate generalization to unseen generators, we use \\textbf{Leave-One-Generator-Out (LOGO)} cross-validation over all eight generators.\nLOGO holds out individual generators but does not isolate family effects (e.g., when Pythia-1B is held out, Pythia-2.8B remains in training).\n\\textbf{Leave-One-Family-Out (LOFO)} addresses this by holding out entire model families; cross-family generalization holds (average binary F1\\,=\\,0.686; \\S\\ref{sec:results-classification}).\n\n\\paragraph{Classifier.}\nWe use XGBoost \\cite{xgboost} throughout ($n\\_\\text{estimators}{=}200$, $\\max\\_\\text{depth}{=}6$, learning rate $0.1$; standard defaults), with identical hyperparameters across all methods in Table~\\ref{tab:baselines}.\nLOGO F1 is stable across random seeds (std\\,$<$\\,0.001 over 5 seeds); this near-zero variance reflects the deterministic LOGO splits (each generator held out exactly once) with seeds controlling only XGBoost's internal stochasticity. Bootstrap CIs on held-out folds provide the relevant generalization uncertainty.\nAlternative classifiers and ordinal-specific methods (CORAL \\cite{coral_ordinal}, CORN \\cite{corn_ordinal}, Frank-Hall \\cite{frank_hall_ordinal}) yield comparable performance (Appendix~\\ref{app:classifier}); discriminative power therefore resides in the features, not the classifier.\n\n\\paragraph{Metrics and statistical testing.}\nThe primary metric is \\textbf{macro-averaged F1} over the three depth classes.\nWe report 95\\% confidence intervals via percentile bootstrap ($n{=}1{,}000$), McNemar tests for pairwise comparisons, and paired bootstrap for baseline comparisons.\nAll $p$-values are two-sided; Bonferroni correction is applied within each family of simultaneous tests: the 21 distributional comparisons (7 features $\\times$ 3 depth-group pairs, \\S\\ref{sec:results-differential}) and the 4 pairwise baseline comparisons (\\S\\ref{sec:results-baselines}).\nFeature--depth correlations (\\S\\ref{sec:results-differential}) use class-balanced subsamples to control for depth-class imbalance.\n\n\\paragraph{Baselines.}\nWe compare the 7-feature ensemble against four single-score detection methods repurposed as depth predictors: Avg-LogProb, FastDetectGPT \\cite{fast_detectgpt}, Binoculars \\cite{binoculars}, and LD-Score \\cite{ld_score}.\nEach baseline score is used as a univariate feature in the same XGBoost framework under LOGO cross-validation to ensure a controlled comparison.\n\n\\paragraph{Length confound control.}\nSince TTR and hapax\\_ratio are mechanically length-dependent, we verify depth signal is not a length artifact via length-matched subsampling that equalizes length distributions across depth classes (\\S\\ref{sec:results-classification}; Appendix~\\ref{app:length}).\n",
      "numLines": 91,
      "startLine": 1,
      "totalLines": 91
    }
  },
  "sourceToolAssistantUUID": "6490d361-9978-4a06-9db2-5910aed21ad4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 44 · 2026-05-19T06:17:37.127Z_

<details open><summary>🔧 Tool call — Read · `toolu_018nTnaWuFdFxUYp2nkEihdh`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6fc586d4-0eb6-4b42-b308-0656f720c813",
  "isSidechain": false,
  "requestId": "req_011CbBSTrDbwZzahyESiLTBV",
  "type": "assistant",
  "uuid": "8cac35ad-302d-4204-a994-3c7735fdd896",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRnxsSQBR2khGm9XsTaGLu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3705,
      "cache_read_input_tokens": 31700,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3705,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 3705,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3705
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 45 · 2026-05-19T06:17:37.131Z_

<details><summary>↩ Tool result · `toolu_018nTnaWuFdFxUYp2nkEihdh`</summary>

```text
1	\section{Results}
2	\label{sec:results}
3	
4	\subsection{Depth Classification Performance}
5	\label{sec:results-classification}
6	
7	The 7-feature ensemble achieves 3-class LOGO F1\,=\,0.762 (95\% CI [0.758, 0.766]; $N$\,=\,37{,}058) across eight generators from five families (Table~\ref{tab:logo-results}).
8	Because gen-0 seeds are shared across generators (\S\ref{sec:generation}), gen-0 classification is near-perfect (per-class F1\,$\approx$\,0.94) and the 3-class metric is inflated by this overlap.
9	We therefore adopt leak-free binary F1 (gen-1 vs.\ gen-2+)\,=\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.
10	Per-generator binary F1 ranges from 0.633 (Mistral-7B) to 0.724 (Pythia-2.8B), with the primary difficulty being gen-1 vs.\ gen-2+ discrimination (Appendix~\ref{app:confusion}).
11	
12	\paragraph{Cross-model generalization.}
13	Cross-model chains (randomly selected generator per step) yield binary F1\,=\,0.764 under 5-fold CV.\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation. Sample-level CV is used because each chain contains multiple generators, making generator-level held-out splits inapplicable.}
14	The higher cross-model F1 (vs.\ 0.694 single-generator LOGO) may reflect generator heterogeneity amplifying depth-correlated distributional shifts; generator identity information in mixed chains could partially confound the depth signal.
15	Leave-one-family-out (LOFO) evaluation yields binary F1\,=\,0.686, consistent with cross-family transfer.
16	A scale effect emerges: Pythia generators achieve the highest binary F1 (0.718--0.724), while larger models show degradation (Mistral-7B: 0.633), partly reflecting same-family affinity with the Pythia-410M reference model (cross-reference spread $\leq$0.013; \S\ref{sec:results-differential}).
17	Preliminary cross-domain evaluation suggests the signal persists with variation, though a domain$\times$temperature interaction exists (Appendix~\ref{app:domain}).
18	An end-to-end QLoRA classifier achieves 3-class F1\,=\,0.905 ($+$11.6\,pp; Appendix~\ref{app:qlora}), which indicates that richer representations capture additional depth signal beyond the 7-feature set.
19	
20	\paragraph{Length confound control.}
21	Length-matched subsampling yields binary F1\,=\,0.724 (vs.\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\ref{app:length}).
22	
23	\paragraph{Seed-sharing control.}
24	Seed-level demeaning (F1\,=\,0.701) and an independent-seed experiment with disjoint seed pools (F1\,=\,0.680; Appendix~\ref{app:seed-control}) both confirm the classifier captures generative degradation, not seed-specific content.
25	
26	\begin{table}[t]
27	\centering
28	\footnotesize
29	\resizebox{\columnwidth}{!}{%
30	\begin{tabular}{llcccc}
31	\toprule
32	\textbf{Model} & \textbf{Family} & \textbf{Params} & \textbf{Bin F1} & \textbf{95\% CI} & \textbf{3-cl F1}$^{\dagger}$ \\
33	\midrule
34	Pythia-2.8B     & Pythia  & 2.8B & \textbf{0.724} & [.707, .742] & 0.798 \\
35	Pythia-1B       & Pythia  & 1.0B & 0.718 & [.700, .735] & \textbf{0.806} \\
36	Qwen3-1.7B     & Qwen    & 1.7B & 0.709 & [.693, .726] & 0.772 \\
37	Llama-3.2-3B   & Llama   & 3.2B & 0.697 & [.680, .713] & 0.775 \\
38	OLMo-2-1B      & OLMo    & 1.5B & 0.695 & [.679, .711] & 0.781 \\
39	Qwen3-8B       & Qwen    & 8.2B & 0.692 & [.674, .708] & 0.714 \\
40	Qwen3-0.6B     & Qwen    & 0.6B & 0.691 & [.673, .709] & 0.780 \\
41	Mistral-7B     & Mistral & 7.0B & 0.633 & [.617, .648] & 0.682 \\
42	\midrule
43	\multicolumn{3}{l}{\textbf{Average (8-gen LOGO)}} & \textbf{0.694} & [.688, .700] & \textbf{0.762} \\
44	\multicolumn{3}{l}{\textbf{LOFO (family-level)}} & 0.686 & --- & --- \\
45	\bottomrule
46	\end{tabular}}
47	\caption{8-generator LOGO macro-F1 for the 7-feature ensemble (bootstrap 95\% CIs, $n$\,=\,1000). Binary F1 (gen-1 vs.\ gen-2+) is the primary metric; it excludes gen-0 entirely and is unaffected by seed sharing. $^{\dagger}$3-class F1 carries upward bias because gen-0 seeds are shared across generators (\S\ref{sec:generation}); independent-seed controls confirm the depth signal (F1\,=\,0.680; Appendix~\ref{app:seed-control}).}
48	\label{tab:logo-results}
49	\end{table}
50	
51	\subsection{Differential Depth Response}
52	\label{sec:results-differential}
53	
54	Features exhibit a continuous gradient of depth sensitivity, with a data-driven binary partition as the strongest structure: $k{=}2$ clustering in standardized $(|\rho|, d)$ space yields silhouette\,=\,0.632 (Appendix~\ref{app:ddr-validation}), separating \emph{drifting} features (entropy mean, TTR, hapax ratio; $|\rho| > 0.60$, $d{=}0.76$--$1.17$) from \emph{non-drifting} ones.
55	We use the shorthand \emph{differential depth response} (DDR) for this partition and further resolve a 3/1/3 characterization using domain-informed criteria: entropy std occupies a sole \emph{intermediate} position (large level shift $d{=}0.55$, low monotonicity $|\rho|{=}0.16$); the remaining three \emph{near-stationary} features (entropy max, tail decay, entropy min) show negligible depth effects ($d < 0.10$; CV shift $<$3\% vs.\ $>$15\% for drifting).
56	This partition is robust under heteroscedasticity-corrected metrics (below).
57	
58	\begin{figure}[t]
59	\centering
60	\includegraphics[width=\columnwidth]{fig1_differential_response.pdf}
61	\caption{Differential depth response: Spearman correlations between individual features and generation depth. Drifting features (hapax ratio, TTR, entropy mean) show $|\rho| > 0.60$; entropy std ($|\rho|{=}0.16$, $d{=}0.55$) is the sole intermediate feature; near-stationary features (entropy max, tail decay, entropy min) show $d < 0.10$ for gen-1 vs.\ gen-2+ (entropy min's elevated pooled $|\rho|$ reflects the gen-0/gen-1 boundary; \S\ref{sec:results-differential}).}
62	\label{fig:feature-drift}
63	\end{figure}
64	
65	Pooled class-balanced Spearman correlations with depth confirm the split (Figure~\ref{fig:feature-drift}):
66	drifting features show substantial monotonic trends (hapax ratio $\rho = -0.64$, TTR $\rho = -0.63$, entropy mean $\rho = -0.60$),
67	while shape features remain near-stationary (tail decay $|\rho| = 0.04$; per-depth distributions in Appendix~\ref{app:feature-distributions}).
68	The six-fold magnitude gap between drifting ($|\rho| > 0.60$) and near-stationary features ($|\rho| < 0.10$) defines the DDR partition, with entropy std ($|\rho| = 0.16$, $d{=}0.55$) as the sole intermediate member; the 3/1/3 partition is stable across $d$ thresholds in $[0.56, 0.75]$: the drifting boundary reflects the natural gap between hapax ratio ($d{=}0.76$) and entropy std ($d{=}0.55$), and lowering it below 0.56 would reclassify entropy std as drifting despite its non-monotonic behavior ($|\rho|{=}0.16$). Data-driven clustering confirms the primary drifting/non-drifting split as the strongest structure ($k{=}2$, silhouette\,=\,0.632); the 3/1/3 refinement incorporates domain-informed criteria (binary-task Cohen's $d$) for entropy min's boundary status (Appendix~\ref{app:ddr-validation}).
69	
70	\paragraph{Distributional shift quantification.}
71	Two-sample KS tests confirm the split: drifting-feature statistics (0.516--0.537) are ${\sim}10\times$ larger than shape-feature statistics (0.043--0.052; all $p \approx 0$ after Bonferroni correction).
72	Cohen's $d$ \cite{cohen1988statistical} (pooled, class-balanced) converges with $\rho$: drifting features show large effects (entropy mean $d{=}1.17$, TTR $d{=}0.88$, hapax ratio $d{=}0.76$), while shape features are near zero (entropy max $d{=}0.08$, tail decay $d{=}0.08$).
73	Levene tests reject strict equal-variance ($p < 10^{-10}$); Glass's $\Delta$ (using gen-1 SD) amplifies drifting effects (entropy mean $\Delta{=}1.41$, hapax $\Delta{=}0.94$) while near-stationary features remain negligible ($\Delta \leq 0.10$), yielding a ${\geq}9.5\times$ gap. Cliff's $\delta$ corroborates the partition (Appendix~\ref{app:ddr-validation}).
74	Shape-feature CV shift ($<$3\% vs.\ $>$15\% for drifting features) supports ``near-stationary'' as a practical characterization.
75	Five features fall cleanly into the drifting or near-stationary groups under both $\rho$ and $d$; the remaining two require qualification: entropy min's pooled $|\rho|$ (0.40) reflects change concentrated at the gen-0/gen-1 boundary, but for gen-1 vs.\ gen-2+ it is near-stationary ($d{=}0.03$), placing it in the near-stationary group; entropy std shows a substantial level shift ($d{=}0.55$) despite low monotonicity ($|\rho|{=}0.16$), making it the sole intermediate feature.
76	The location/shape decomposition rests on the convergence of $\rho$, Levene, CV shift, and $d$, not the omnibus KS statistic alone.
77	Per-generator TOST equivalence testing confirms the partition is not a pooling artifact: entropy min passes equivalence ($|d| < 0.20$) for all eight generators, entropy max for six of eight, and tail decay for four of eight; all drifting features exceed the bound uniformly (Appendix~\ref{app:tost}).
78	Tail decay is near-stationary at the aggregate level ($d{=}0.08$, CV shift $<$3\%) with generator-dependent variation: the four non-passing generators show $d{=}0.15$--$0.22$, still far below the drifting threshold ($d > 0.75$).
79	Even reclassifying tail decay as intermediate (yielding a 3/2/2 partition) preserves the core drifting/non-drifting split and does not change classification performance.
80	Holdout generator validation (two 4/4 splits with swapped extreme-value generators) confirms partition stability: under simple joint thresholds the holdout produces a 3/2/2 partition (entropy min classified as intermediate due to elevated pooled $|\rho|$), but five of seven features are unambiguously classified, and entropy min's boundary status ($d < 0.06$ across all splits) is consistently resolved by the binary-task criterion (Appendix~\ref{app:tost}).
81	
82	\paragraph{Feature complementarity.}
83	The full 7-feature set (F1\,=\,0.773) outperforms surface-only (0.688) and reference-only (0.713; McNemar $p \approx 0$; Appendix~\ref{app:ablation-table}).
84	Permutation importance: hapax ratio (0.35), entropy mean (0.23), TTR (0.18).
85	PCA confirms that the three drifting features share a single latent dimension: a single principal component explains 92.3\% of their joint variance, with near-uniform loadings (0.56--0.59; Appendix~\ref{sec:appendix-feature-correlation}).
86	The DDR partition thus distinguishes which features track this drifting dimension from those that remain depth-invariant, rather than claiming three independent depth signals.
87	Replacing the three drifting features with their PC1 score costs only 1.1\,pp binary F1 (0.840\,$\rightarrow$\,0.829); the dominant shared dimension thus accounts for nearly all classification-relevant variance, with marginal residual signal.
88	DDR's scientific contribution is identifying which distributional properties (NLL location vs.\ shape) are depth-sensitive; individual features are necessary for this decomposition. PC scores achieve equivalent classification but obscure which specific properties drift, reducing the analysis to a black-box predictor.
89	Direct ablation corroborates the effective dimensionality: retaining any single drifting feature alongside the four non-drifting features yields binary F1\,=\,0.692 (vs.\ 0.701 for all seven), with the 0.9\,pp gap falling within bootstrap CI overlap.
90	TTR and hapax ratio are strongly correlated ($r = 0.97$); their permutation importance difference (0.35 vs.\ 0.18) reflects feature masking in tree-based ensembles \cite{strobl_conditional_2008}.
91	All three are retained for marginal LOFO gains (Appendix~\ref{app:lofo}).
92	
93	\paragraph{Cross-family reference models.}
94	Alternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\ref{tab:cross-ref} in Appendix~\ref{app:cross-ref}), with consistently negative entropy drift.
95	Pythia generators' highest F1 (0.718--0.724) may partly reflect same-family affinity with the Pythia-410M reference model, but the 0.013 cross-reference spread bounds this effect; depth features are robust to reference model choice, though this does not alone establish DDR as a fundamental property of recursive generation.
96	
97	\paragraph{Temperature and prompt-type sensitivity.}
98	The depth signal is modulated by decoding parameters and prompt type (Appendices~\ref{app:sampling-sensitivity},~\ref{app:prompt-type}).
99	All four tested generators degrade at $t{=}0.9$ ($-9.3$ to $-26.0$\,pp binary F1); low-temperature improvement is model-family-dependent ($+7$--$9$\,pp for Pythia/OLMo at $t{=}0.5$, negligible for Qwen).
100	Continuation chains show the strongest drift (binary F1\,=\,0.781), with cross-prompt-type transfer confirming shared signal (LOPTO F1\,=\,0.753).
101	
102	
103	\subsection{Comparison with Detection Baselines}
104	\label{sec:results-baselines}
105	
106	To contextualize depth discrimination ability rather than claim competitive advantage over detection-optimized methods, we repurpose four detection scores as ordinal depth predictors using the same XGBoost framework and LOGO splits (Table~\ref{tab:baselines}).
107	
108	\begin{table}[t]
109	\centering
110	\footnotesize
111	\begin{tabular}{lcccc}
112	\toprule
113	\textbf{Method} & \textbf{Feat.} & \textbf{3-cl F1} & \textbf{Bin F1} & \textbf{ms/text} \\
114	\midrule
115	4-det.\ + surface     & 6 & \textbf{0.795} & \textbf{0.708} & 22.8 \\
116	4-detector ens.\      & 4 & 0.785 & 0.700 & 22.8 \\
117	7-feature (ours)      & 7 & 0.774 & 0.705 & \textbf{9.7} \\
118	Avg-LogProb           & 1 & 0.707 & 0.673 & N/A \\
119	FastDetectGPT         & 1 & 0.660 & 0.569 & N/A \\
120	LD-Score              & 1 & 0.630 & 0.675 & N/A \\
121	Binoculars            & 1 & 0.411 & 0.539 & N/A \\
122	\bottomrule
123	\end{tabular}
124	\caption{Depth classification (8-gen LOGO, pooled evaluation; slightly higher than per-generator macro average in Table~\ref{tab:logo-results}). Identical XGBoost configuration. 7-feature: one 410M model (905\,MB); 4-det ensembles: two models, 1.4B params (2{,}868\,MB). Individual detection scores (N/A) share the reference-model forward pass; per-method timing is not separately profiled.}
125	\label{tab:baselines}
126	\end{table}
127	
128	The 7-feature ensemble exceeds all individual baselines in 3-class F1 ($\Delta$\,=\,6.7--36.3\,pp).
129	Multi-detector ensembles achieve marginally higher binary F1 (0.708 vs.\ 0.705) at 2.4$\times$ inference cost; that detection scores achieve comparable depth discrimination suggests depth information is implicitly encoded in distributional divergence measures, while our DDR decomposition makes this structure explicit.
130	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8cac35ad-302d-4204-a994-3c7735fdd896",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "93d879d7-10b9-44b7-836a-7f32aceccc24",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex",
      "content": "\\section{Results}\n\\label{sec:results}\n\n\\subsection{Depth Classification Performance}\n\\label{sec:results-classification}\n\nThe 7-feature ensemble achieves 3-class LOGO F1\\,=\\,0.762 (95\\% CI [0.758, 0.766]; $N$\\,=\\,37{,}058) across eight generators from five families (Table~\\ref{tab:logo-results}).\nBecause gen-0 seeds are shared across generators (\\S\\ref{sec:generation}), gen-0 classification is near-perfect (per-class F1\\,$\\approx$\\,0.94) and the 3-class metric is inflated by this overlap.\nWe therefore adopt leak-free binary F1 (gen-1 vs.\\ gen-2+)\\,=\\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.\nPer-generator binary F1 ranges from 0.633 (Mistral-7B) to 0.724 (Pythia-2.8B), with the primary difficulty being gen-1 vs.\\ gen-2+ discrimination (Appendix~\\ref{app:confusion}).\n\n\\paragraph{Cross-model generalization.}\nCross-model chains (randomly selected generator per step) yield binary F1\\,=\\,0.764 under 5-fold CV.\\footnote{Cross-model chains use the original five-generator subset (Pythia, OLMo, Qwen); Llama and Mistral were added later for single-generator evaluation. Sample-level CV is used because each chain contains multiple generators, making generator-level held-out splits inapplicable.}\nThe higher cross-model F1 (vs.\\ 0.694 single-generator LOGO) may reflect generator heterogeneity amplifying depth-correlated distributional shifts; generator identity information in mixed chains could partially confound the depth signal.\nLeave-one-family-out (LOFO) evaluation yields binary F1\\,=\\,0.686, consistent with cross-family transfer.\nA scale effect emerges: Pythia generators achieve the highest binary F1 (0.718--0.724), while larger models show degradation (Mistral-7B: 0.633), partly reflecting same-family affinity with the Pythia-410M reference model (cross-reference spread $\\leq$0.013; \\S\\ref{sec:results-differential}).\nPreliminary cross-domain evaluation suggests the signal persists with variation, though a domain$\\times$temperature interaction exists (Appendix~\\ref{app:domain}).\nAn end-to-end QLoRA classifier achieves 3-class F1\\,=\\,0.905 ($+$11.6\\,pp; Appendix~\\ref{app:qlora}), which indicates that richer representations capture additional depth signal beyond the 7-feature set.\n\n\\paragraph{Length confound control.}\nLength-matched subsampling yields binary F1\\,=\\,0.724 (vs.\\ 0.770 unmatched); a random-subsample control confirms the drop reflects deconfounding, not sample-size reduction (Appendix~\\ref{app:length}).\n\n\\paragraph{Seed-sharing control.}\nSeed-level demeaning (F1\\,=\\,0.701) and an independent-seed experiment with disjoint seed pools (F1\\,=\\,0.680; Appendix~\\ref{app:seed-control}) both confirm the classifier captures generative degradation, not seed-specific content.\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{llcccc}\n\\toprule\n\\textbf{Model} & \\textbf{Family} & \\textbf{Params} & \\textbf{Bin F1} & \\textbf{95\\% CI} & \\textbf{3-cl F1}$^{\\dagger}$ \\\\\n\\midrule\nPythia-2.8B     & Pythia  & 2.8B & \\textbf{0.724} & [.707, .742] & 0.798 \\\\\nPythia-1B       & Pythia  & 1.0B & 0.718 & [.700, .735] & \\textbf{0.806} \\\\\nQwen3-1.7B     & Qwen    & 1.7B & 0.709 & [.693, .726] & 0.772 \\\\\nLlama-3.2-3B   & Llama   & 3.2B & 0.697 & [.680, .713] & 0.775 \\\\\nOLMo-2-1B      & OLMo    & 1.5B & 0.695 & [.679, .711] & 0.781 \\\\\nQwen3-8B       & Qwen    & 8.2B & 0.692 & [.674, .708] & 0.714 \\\\\nQwen3-0.6B     & Qwen    & 0.6B & 0.691 & [.673, .709] & 0.780 \\\\\nMistral-7B     & Mistral & 7.0B & 0.633 & [.617, .648] & 0.682 \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textbf{Average (8-gen LOGO)}} & \\textbf{0.694} & [.688, .700] & \\textbf{0.762} \\\\\n\\multicolumn{3}{l}{\\textbf{LOFO (family-level)}} & 0.686 & --- & --- \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{8-generator LOGO macro-F1 for the 7-feature ensemble (bootstrap 95\\% CIs, $n$\\,=\\,1000). Binary F1 (gen-1 vs.\\ gen-2+) is the primary metric; it excludes gen-0 entirely and is unaffected by seed sharing. $^{\\dagger}$3-class F1 carries upward bias because gen-0 seeds are shared across generators (\\S\\ref{sec:generation}); independent-seed controls confirm the depth signal (F1\\,=\\,0.680; Appendix~\\ref{app:seed-control}).}\n\\label{tab:logo-results}\n\\end{table}\n\n\\subsection{Differential Depth Response}\n\\label{sec:results-differential}\n\nFeatures exhibit a continuous gradient of depth sensitivity, with a data-driven binary partition as the strongest structure: $k{=}2$ clustering in standardized $(|\\rho|, d)$ space yields silhouette\\,=\\,0.632 (Appendix~\\ref{app:ddr-validation}), separating \\emph{drifting} features (entropy mean, TTR, hapax ratio; $|\\rho| > 0.60$, $d{=}0.76$--$1.17$) from \\emph{non-drifting} ones.\nWe use the shorthand \\emph{differential depth response} (DDR) for this partition and further resolve a 3/1/3 characterization using domain-informed criteria: entropy std occupies a sole \\emph{intermediate} position (large level shift $d{=}0.55$, low monotonicity $|\\rho|{=}0.16$); the remaining three \\emph{near-stationary} features (entropy max, tail decay, entropy min) show negligible depth effects ($d < 0.10$; CV shift $<$3\\% vs.\\ $>$15\\% for drifting).\nThis partition is robust under heteroscedasticity-corrected metrics (below).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig1_differential_response.pdf}\n\\caption{Differential depth response: Spearman correlations between individual features and generation depth. Drifting features (hapax ratio, TTR, entropy mean) show $|\\rho| > 0.60$; entropy std ($|\\rho|{=}0.16$, $d{=}0.55$) is the sole intermediate feature; near-stationary features (entropy max, tail decay, entropy min) show $d < 0.10$ for gen-1 vs.\\ gen-2+ (entropy min's elevated pooled $|\\rho|$ reflects the gen-0/gen-1 boundary; \\S\\ref{sec:results-differential}).}\n\\label{fig:feature-drift}\n\\end{figure}\n\nPooled class-balanced Spearman correlations with depth confirm the split (Figure~\\ref{fig:feature-drift}):\ndrifting features show substantial monotonic trends (hapax ratio $\\rho = -0.64$, TTR $\\rho = -0.63$, entropy mean $\\rho = -0.60$),\nwhile shape features remain near-stationary (tail decay $|\\rho| = 0.04$; per-depth distributions in Appendix~\\ref{app:feature-distributions}).\nThe six-fold magnitude gap between drifting ($|\\rho| > 0.60$) and near-stationary features ($|\\rho| < 0.10$) defines the DDR partition, with entropy std ($|\\rho| = 0.16$, $d{=}0.55$) as the sole intermediate member; the 3/1/3 partition is stable across $d$ thresholds in $[0.56, 0.75]$: the drifting boundary reflects the natural gap between hapax ratio ($d{=}0.76$) and entropy std ($d{=}0.55$), and lowering it below 0.56 would reclassify entropy std as drifting despite its non-monotonic behavior ($|\\rho|{=}0.16$). Data-driven clustering confirms the primary drifting/non-drifting split as the strongest structure ($k{=}2$, silhouette\\,=\\,0.632); the 3/1/3 refinement incorporates domain-informed criteria (binary-task Cohen's $d$) for entropy min's boundary status (Appendix~\\ref{app:ddr-validation}).\n\n\\paragraph{Distributional shift quantification.}\nTwo-sample KS tests confirm the split: drifting-feature statistics (0.516--0.537) are ${\\sim}10\\times$ larger than shape-feature statistics (0.043--0.052; all $p \\approx 0$ after Bonferroni correction).\nCohen's $d$ \\cite{cohen1988statistical} (pooled, class-balanced) converges with $\\rho$: drifting features show large effects (entropy mean $d{=}1.17$, TTR $d{=}0.88$, hapax ratio $d{=}0.76$), while shape features are near zero (entropy max $d{=}0.08$, tail decay $d{=}0.08$).\nLevene tests reject strict equal-variance ($p < 10^{-10}$); Glass's $\\Delta$ (using gen-1 SD) amplifies drifting effects (entropy mean $\\Delta{=}1.41$, hapax $\\Delta{=}0.94$) while near-stationary features remain negligible ($\\Delta \\leq 0.10$), yielding a ${\\geq}9.5\\times$ gap. Cliff's $\\delta$ corroborates the partition (Appendix~\\ref{app:ddr-validation}).\nShape-feature CV shift ($<$3\\% vs.\\ $>$15\\% for drifting features) supports ``near-stationary'' as a practical characterization.\nFive features fall cleanly into the drifting or near-stationary groups under both $\\rho$ and $d$; the remaining two require qualification: entropy min's pooled $|\\rho|$ (0.40) reflects change concentrated at the gen-0/gen-1 boundary, but for gen-1 vs.\\ gen-2+ it is near-stationary ($d{=}0.03$), placing it in the near-stationary group; entropy std shows a substantial level shift ($d{=}0.55$) despite low monotonicity ($|\\rho|{=}0.16$), making it the sole intermediate feature.\nThe location/shape decomposition rests on the convergence of $\\rho$, Levene, CV shift, and $d$, not the omnibus KS statistic alone.\nPer-generator TOST equivalence testing confirms the partition is not a pooling artifact: entropy min passes equivalence ($|d| < 0.20$) for all eight generators, entropy max for six of eight, and tail decay for four of eight; all drifting features exceed the bound uniformly (Appendix~\\ref{app:tost}).\nTail decay is near-stationary at the aggregate level ($d{=}0.08$, CV shift $<$3\\%) with generator-dependent variation: the four non-passing generators show $d{=}0.15$--$0.22$, still far below the drifting threshold ($d > 0.75$).\nEven reclassifying tail decay as intermediate (yielding a 3/2/2 partition) preserves the core drifting/non-drifting split and does not change classification performance.\nHoldout generator validation (two 4/4 splits with swapped extreme-value generators) confirms partition stability: under simple joint thresholds the holdout produces a 3/2/2 partition (entropy min classified as intermediate due to elevated pooled $|\\rho|$), but five of seven features are unambiguously classified, and entropy min's boundary status ($d < 0.06$ across all splits) is consistently resolved by the binary-task criterion (Appendix~\\ref{app:tost}).\n\n\\paragraph{Feature complementarity.}\nThe full 7-feature set (F1\\,=\\,0.773) outperforms surface-only (0.688) and reference-only (0.713; McNemar $p \\approx 0$; Appendix~\\ref{app:ablation-table}).\nPermutation importance: hapax ratio (0.35), entropy mean (0.23), TTR (0.18).\nPCA confirms that the three drifting features share a single latent dimension: a single principal component explains 92.3\\% of their joint variance, with near-uniform loadings (0.56--0.59; Appendix~\\ref{sec:appendix-feature-correlation}).\nThe DDR partition thus distinguishes which features track this drifting dimension from those that remain depth-invariant, rather than claiming three independent depth signals.\nReplacing the three drifting features with their PC1 score costs only 1.1\\,pp binary F1 (0.840\\,$\\rightarrow$\\,0.829); the dominant shared dimension thus accounts for nearly all classification-relevant variance, with marginal residual signal.\nDDR's scientific contribution is identifying which distributional properties (NLL location vs.\\ shape) are depth-sensitive; individual features are necessary for this decomposition. PC scores achieve equivalent classification but obscure which specific properties drift, reducing the analysis to a black-box predictor.\nDirect ablation corroborates the effective dimensionality: retaining any single drifting feature alongside the four non-drifting features yields binary F1\\,=\\,0.692 (vs.\\ 0.701 for all seven), with the 0.9\\,pp gap falling within bootstrap CI overlap.\nTTR and hapax ratio are strongly correlated ($r = 0.97$); their permutation importance difference (0.35 vs.\\ 0.18) reflects feature masking in tree-based ensembles \\cite{strobl_conditional_2008}.\nAll three are retained for marginal LOFO gains (Appendix~\\ref{app:lofo}).\n\n\\paragraph{Cross-family reference models.}\nAlternative references (OLMo-2-1B, Qwen3-0.6B) achieve comparable LOGO F1 (spread 0.013; Table~\\ref{tab:cross-ref} in Appendix~\\ref{app:cross-ref}), with consistently negative entropy drift.\nPythia generators' highest F1 (0.718--0.724) may partly reflect same-family affinity with the Pythia-410M reference model, but the 0.013 cross-reference spread bounds this effect; depth features are robust to reference model choice, though this does not alone establish DDR as a fundamental property of recursive generation.\n\n\\paragraph{Temperature and prompt-type sensitivity.}\nThe depth signal is modulated by decoding parameters and prompt type (Appendices~\\ref{app:sampling-sensitivity},~\\ref{app:prompt-type}).\nAll four tested generators degrade at $t{=}0.9$ ($-9.3$ to $-26.0$\\,pp binary F1); low-temperature improvement is model-family-dependent ($+7$--$9$\\,pp for Pythia/OLMo at $t{=}0.5$, negligible for Qwen).\nContinuation chains show the strongest drift (binary F1\\,=\\,0.781), with cross-prompt-type transfer confirming shared signal (LOPTO F1\\,=\\,0.753).\n\n\n\\subsection{Comparison with Detection Baselines}\n\\label{sec:results-baselines}\n\nTo contextualize depth discrimination ability rather than claim competitive advantage over detection-optimized methods, we repurpose four detection scores as ordinal depth predictors using the same XGBoost framework and LOGO splits (Table~\\ref{tab:baselines}).\n\n\\begin{table}[t]\n\\centering\n\\footnotesize\n\\begin{tabular}{lcccc}\n\\toprule\n\\textbf{Method} & \\textbf{Feat.} & \\textbf{3-cl F1} & \\textbf{Bin F1} & \\textbf{ms/text} \\\\\n\\midrule\n4-det.\\ + surface     & 6 & \\textbf{0.795} & \\textbf{0.708} & 22.8 \\\\\n4-detector ens.\\      & 4 & 0.785 & 0.700 & 22.8 \\\\\n7-feature (ours)      & 7 & 0.774 & 0.705 & \\textbf{9.7} \\\\\nAvg-LogProb           & 1 & 0.707 & 0.673 & N/A \\\\\nFastDetectGPT         & 1 & 0.660 & 0.569 & N/A \\\\\nLD-Score              & 1 & 0.630 & 0.675 & N/A \\\\\nBinoculars            & 1 & 0.411 & 0.539 & N/A \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Depth classification (8-gen LOGO, pooled evaluation; slightly higher than per-generator macro average in Table~\\ref{tab:logo-results}). Identical XGBoost configuration. 7-feature: one 410M model (905\\,MB); 4-det ensembles: two models, 1.4B params (2{,}868\\,MB). Individual detection scores (N/A) share the reference-model forward pass; per-method timing is not separately profiled.}\n\\label{tab:baselines}\n\\end{table}\n\nThe 7-feature ensemble exceeds all individual baselines in 3-class F1 ($\\Delta$\\,=\\,6.7--36.3\\,pp).\nMulti-detector ensembles achieve marginally higher binary F1 (0.708 vs.\\ 0.705) at 2.4$\\times$ inference cost; that detection scores achieve comparable depth discrimination suggests depth information is implicitly encoded in distributional divergence measures, while our DDR decomposition makes this structure explicit.\n",
      "numLines": 130,
      "startLine": 1,
      "totalLines": 130
    }
  },
  "sourceToolAssistantUUID": "8cac35ad-302d-4204-a994-3c7735fdd896",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 46 · 2026-05-19T06:17:37.566Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LA13YLY2DKeb6SBzMjfjiG`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "93d879d7-10b9-44b7-836a-7f32aceccc24",
  "isSidechain": false,
  "requestId": "req_011CbBSTrDbwZzahyESiLTBV",
  "type": "assistant",
  "uuid": "e58f3c6e-74a6-4104-9938-6b5703471d80",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRnxsSQBR2khGm9XsTaGLu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3705,
      "cache_read_input_tokens": 31700,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3705,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 3705,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3705
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 47 · 2026-05-19T06:17:37.570Z_

<details><summary>↩ Tool result · `toolu_01LA13YLY2DKeb6SBzMjfjiG`</summary>

```text
1	\section{Discussion}
2	\label{sec:discussion}
3	
4	The DDR tri-partition (3 drifting / 1 intermediate / 3 near-stationary) is consistent with a location/shape decomposition: under fixed temperature $\tau$ and nucleus $p$, the softmax output distribution's shape (variance, tail behavior) is constrained by the decoding configuration, while iterative conditioning shifts the input distribution's location as text becomes increasingly predictable to the reference model.
5	One informal conjecture is that temperature acts as a shape control parameter: at fixed $\tau$, the softmax normalizes token probabilities to a distribution whose entropy spread is bounded, so recursive conditioning can shift the mean but not escape the shape constraint imposed by $\tau$.
6	This would explain why DDR degrades at high temperature (the shape constraint loosens) and why near-stationary features track shape.
7	This interpretation is post-hoc and empirical; formal analysis of softmax output distribution dynamics under recursive conditioning remains an open problem.
8	DDR is an empirical decomposition capturing this dichotomy, not a claimed universal law of recursive generation.
9	DDR as characterized here is a parameter-dependent phenomenon (modulated by temperature and prompt type), not an intrinsic property of recursive generation independent of decoding conditions.
10	Temperature and prompt-type ablations (\S\ref{sec:results-differential}) support this as a tendency rather than a guarantee: all four tested generators degrade at $t{=}0.9$ ($-9.3$ to $-26.0$\,pp), and the signal varies across prompt types.
11	
12	Instruction tuning fundamentally alters the depth signal across all three tested families (OLMo, Qwen, Llama; Appendix~\ref{app:instruct}).
13	Entropy-mean $\rho$ reverses sign consistently ($+0.48$ for OLMo and Qwen, $+0.23$ for Llama; all base models ${\approx}{-}0.6$), and 6 of 7 features reverse direction for OLMo and Qwen, 3 of 7 for Llama.
14	Retraining the classifier on instruction-tuned data partially recovers within-model binary F1 (OLMo: $0.321 \rightarrow 0.590$, $+$26.9\,pp; Qwen-1.7B: $0.500 \rightarrow 0.660$), but the recovered performance remains below base-model levels (0.69--0.72).
15	The DDR partition structure itself degrades under instruction tuning: $k{=}2$ clustering silhouette drops from 0.632 (base) to 0.338 (instruct), and cross-condition transfer is near chance in both directions (base$\rightarrow$instruct F1\,=\,0.490; instruct$\rightarrow$base F1\,=\,0.454).
16	Instruction tuning thus compresses the feature-space structure rather than simply reversing feature directions: RLHF disrupts the clean location/shape decomposition that underlies DDR in base models.
17	This restricts the structured DDR partition to base models, though within-model depth classification remains partially feasible with domain-specific retraining (Appendix~\ref{app:instruct}).
18	Cross-temperature transfer degrades substantially at $t{=}1.0$ (Appendix~\ref{app:cross-temp}).
19	DDR characterizes distributional structure under recursive generation; depth profiling identifies this structure rather than prescribing data-selection actions.
20	A preliminary pilot experiment ($n{=}3$ seeds; Appendix~\ref{app:downstream}) does not detect a depth-composition effect on training utility, but the sample size is insufficient to draw conclusions in either direction.
21	
22	The QLoRA end-to-end classifier (3-class F1\,=\,0.905; Appendix~\ref{app:qlora}) confirms that richer representations capture depth signal well beyond the 7-feature set; at binary F1\,=\,0.694, the handcrafted ensemble trades classification ceiling for interpretability and provides the DDR decomposition that end-to-end classifiers cannot.
23	Three classes represent the practical ceiling (5-class F1 ${\approx}$0.50; Appendix~\ref{app:finer-depth}), with the gen-1/gen-2+ boundary as the bottleneck.
24	Simulated human editing (token-level perturbation) suggests graceful degradation of the depth signal (Appendix~\ref{app:human-edit}), though the gap between simulated perturbation and real-world post-processing remains untested.
25	DDR is distinct from model collapse \cite{curse_of_recursion,strong_model_collapse}: inference-chain drift is fully reversible under fixed parameters and leaves distributional shape near-stationary ($d < 0.10$; variance ratios 0.98--1.12).
26	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e58f3c6e-74a6-4104-9938-6b5703471d80",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "af9b56fe-a702-44eb-8f6e-c0f9bdf5a9b2",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex",
      "content": "\\section{Discussion}\n\\label{sec:discussion}\n\nThe DDR tri-partition (3 drifting / 1 intermediate / 3 near-stationary) is consistent with a location/shape decomposition: under fixed temperature $\\tau$ and nucleus $p$, the softmax output distribution's shape (variance, tail behavior) is constrained by the decoding configuration, while iterative conditioning shifts the input distribution's location as text becomes increasingly predictable to the reference model.\nOne informal conjecture is that temperature acts as a shape control parameter: at fixed $\\tau$, the softmax normalizes token probabilities to a distribution whose entropy spread is bounded, so recursive conditioning can shift the mean but not escape the shape constraint imposed by $\\tau$.\nThis would explain why DDR degrades at high temperature (the shape constraint loosens) and why near-stationary features track shape.\nThis interpretation is post-hoc and empirical; formal analysis of softmax output distribution dynamics under recursive conditioning remains an open problem.\nDDR is an empirical decomposition capturing this dichotomy, not a claimed universal law of recursive generation.\nDDR as characterized here is a parameter-dependent phenomenon (modulated by temperature and prompt type), not an intrinsic property of recursive generation independent of decoding conditions.\nTemperature and prompt-type ablations (\\S\\ref{sec:results-differential}) support this as a tendency rather than a guarantee: all four tested generators degrade at $t{=}0.9$ ($-9.3$ to $-26.0$\\,pp), and the signal varies across prompt types.\n\nInstruction tuning fundamentally alters the depth signal across all three tested families (OLMo, Qwen, Llama; Appendix~\\ref{app:instruct}).\nEntropy-mean $\\rho$ reverses sign consistently ($+0.48$ for OLMo and Qwen, $+0.23$ for Llama; all base models ${\\approx}{-}0.6$), and 6 of 7 features reverse direction for OLMo and Qwen, 3 of 7 for Llama.\nRetraining the classifier on instruction-tuned data partially recovers within-model binary F1 (OLMo: $0.321 \\rightarrow 0.590$, $+$26.9\\,pp; Qwen-1.7B: $0.500 \\rightarrow 0.660$), but the recovered performance remains below base-model levels (0.69--0.72).\nThe DDR partition structure itself degrades under instruction tuning: $k{=}2$ clustering silhouette drops from 0.632 (base) to 0.338 (instruct), and cross-condition transfer is near chance in both directions (base$\\rightarrow$instruct F1\\,=\\,0.490; instruct$\\rightarrow$base F1\\,=\\,0.454).\nInstruction tuning thus compresses the feature-space structure rather than simply reversing feature directions: RLHF disrupts the clean location/shape decomposition that underlies DDR in base models.\nThis restricts the structured DDR partition to base models, though within-model depth classification remains partially feasible with domain-specific retraining (Appendix~\\ref{app:instruct}).\nCross-temperature transfer degrades substantially at $t{=}1.0$ (Appendix~\\ref{app:cross-temp}).\nDDR characterizes distributional structure under recursive generation; depth profiling identifies this structure rather than prescribing data-selection actions.\nA preliminary pilot experiment ($n{=}3$ seeds; Appendix~\\ref{app:downstream}) does not detect a depth-composition effect on training utility, but the sample size is insufficient to draw conclusions in either direction.\n\nThe QLoRA end-to-end classifier (3-class F1\\,=\\,0.905; Appendix~\\ref{app:qlora}) confirms that richer representations capture depth signal well beyond the 7-feature set; at binary F1\\,=\\,0.694, the handcrafted ensemble trades classification ceiling for interpretability and provides the DDR decomposition that end-to-end classifiers cannot.\nThree classes represent the practical ceiling (5-class F1 ${\\approx}$0.50; Appendix~\\ref{app:finer-depth}), with the gen-1/gen-2+ boundary as the bottleneck.\nSimulated human editing (token-level perturbation) suggests graceful degradation of the depth signal (Appendix~\\ref{app:human-edit}), though the gap between simulated perturbation and real-world post-processing remains untested.\nDDR is distinct from model collapse \\cite{curse_of_recursion,strong_model_collapse}: inference-chain drift is fully reversible under fixed parameters and leaves distributional shape near-stationary ($d < 0.10$; variance ratios 0.98--1.12).\n",
      "numLines": 26,
      "startLine": 1,
      "totalLines": 26
    }
  },
  "sourceToolAssistantUUID": "e58f3c6e-74a6-4104-9938-6b5703471d80",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 48 · 2026-05-19T06:17:38.041Z_

<details open><summary>🔧 Tool call — Read · `toolu_01N5h5F9DWXCWw79cJL2LRXC`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "af9b56fe-a702-44eb-8f6e-c0f9bdf5a9b2",
  "isSidechain": false,
  "requestId": "req_011CbBSTrDbwZzahyESiLTBV",
  "type": "assistant",
  "uuid": "8836354f-976f-4d06-acd3-302c0d4eb694",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRnxsSQBR2khGm9XsTaGLu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3705,
      "cache_read_input_tokens": 31700,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3705,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 3705,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3705
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 49 · 2026-05-19T06:17:38.045Z_

<details><summary>↩ Tool result · `toolu_01N5h5F9DWXCWw79cJL2LRXC`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	We introduced generation depth classification and identified a differential depth response (DDR) tri-partition across eight base-model generators from five families.
5	A 7-feature ensemble exploiting this tri-partition achieves leak-free binary F1\,=\,0.694 (LOGO) and 0.764 (cross-model chains).
6	Current applicability is restricted to base models; instruction tuning and larger scales remain open.
7	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8836354f-976f-4d06-acd3-302c0d4eb694",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "b80fccb7-350a-4efd-9d9e-a8d71d064875",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nWe introduced generation depth classification and identified a differential depth response (DDR) tri-partition across eight base-model generators from five families.\nA 7-feature ensemble exploiting this tri-partition achieves leak-free binary F1\\,=\\,0.694 (LOGO) and 0.764 (cross-model chains).\nCurrent applicability is restricted to base models; instruction tuning and larger scales remain open.\n",
      "numLines": 7,
      "startLine": 1,
      "totalLines": 7
    }
  },
  "sourceToolAssistantUUID": "8836354f-976f-4d06-acd3-302c0d4eb694",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 50 · 2026-05-19T06:17:38.516Z_

<details open><summary>🔧 Tool call — Read · `toolu_01BUNVPgHzu6NJwzSbAPc6t8`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b80fccb7-350a-4efd-9d9e-a8d71d064875",
  "isSidechain": false,
  "requestId": "req_011CbBSTrDbwZzahyESiLTBV",
  "type": "assistant",
  "uuid": "318ea9e4-95fe-4127-b3a8-b332aa712056",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRnxsSQBR2khGm9XsTaGLu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3705,
      "cache_read_input_tokens": 31700,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3705,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 3705,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3705
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 51 · 2026-05-19T06:17:38.520Z_

<details><summary>↩ Tool result · `toolu_01BUNVPgHzu6NJwzSbAPc6t8`</summary>

```text
1	\section*{Limitations}
2	\label{sec:limitations}
3	
4	All eight generators are base (pretrained) models.
5	This is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects and enable controlled study of recursive distributional drift.
6	However, web text is predominantly produced by instruction-tuned and RLHF-aligned models.
7	Preliminary instruct experiments confirm that depth signal degrades substantially under instruction tuning: OLMo-2-1B-Instruct drops to 3-class LOGO F1\,=\,0.338 (vs.\ 0.763 base; this is classification F1, distinct from the clustering silhouette of the same value reported in \S\ref{sec:discussion}) and Qwen3-0.6B with chat template to 0.667 (vs.\ 0.816 base); these comparisons use earlier LOGO subsets (5--6 generators) predating the full 8-generator expansion in Table~\ref{tab:logo-results}.
8	Length-matched analysis yields near-zero correlations ($|\rho| < 0.02$) and binary classification near chance (F1\,$\approx$\,0.5) for Qwen models, leaving interpretation ambiguous.
9	Extending depth profiling to instruct models requires addressing these confounds (length regulation, format constraints, safety-driven distribution shaping) that instruction tuning introduces.
10	
11	Our experiments include generators up to 8.2B parameters (Qwen3-8B).
12	Depth signal persists at this scale (Qwen3-8B 3-class F1\,=\,0.714), but cross-scale transfer incurs a moderate gap vs.\ $\leq$2.8B generators (F1\,=\,0.77--0.81).
13	Frontier models (70B+) and closed-source models remain untested; the consistent scale trend (Mistral-7B binary F1\,=\,0.633, lowest among all generators) suggests depth signal may weaken further at frontier scales, potentially approaching the detection floor.
14	
15	Differential depth response strength is prompt-type dependent: continuation chains show strongest drift (within-type binary F1\,=\,0.781) compared to elaboration (0.730) and rewriting (0.737), with within-prompt-type paraphrastic chains showing weaker signal (binary F1\,=\,0.671 vs.\ 0.749 for within-prompt-type continuation).
16	DDR is most reliably detected in continuation-style generation; near-paraphrastic settings approach the method's detection floor.
17	Cross-prompt-type transfer (LOPTO F1\,=\,0.753) confirms shared signal, yet additional prompt types (e.g., summarization, instruction following) and cross-generator $\times$ cross-prompt interactions remain untested.
18	
19	Our primary evaluation uses single-generator chains; cross-model chains (\S\ref{sec:results-classification}) confirm depth signal under generator heterogeneity (3-class F1\,=\,0.809, binary F1\,=\,0.764), though the eight generators represent a controlled laboratory setting rather than the full diversity of real-world contamination.
20	Simulated human editing (\S\ref{sec:discussion}) suggests graceful degradation, but the gap between simulated token replacement and real-world post-processing remains untested.
21	
22	The reference model is fixed to Pythia-410M throughout, although cross-family reference experiments (\S\ref{sec:results-differential}) confirm the phenomenon is not reference-specific (spread 0.013 across three references).
23	All seed texts in the main evaluation are English Wikipedia excerpts.
24	Cross-domain evaluation (Appendix~\ref{app:domain}) at both $t{=}1.0$ and $t{=}0.7$ shows that depth signal persists across News, Academic, and Code domains (binary F1 0.63--0.75 depending on domain and temperature), though a domain $\times$ temperature interaction exists: at $t{=}0.7$, Academic domain binary F1 drops to 0.628, suggesting that reference model calibration is critical for cross-domain deployment.
25	The reference model dependency (Pythia-410M, English-centric pretraining) limits non-English applicability and adds inference overhead relative to surface-feature-only approaches.
26	Generalization to other languages remains untested.
27	
28	Our default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A temperature ablation across four generators from three families (Appendix~\ref{app:sampling-sensitivity}) shows that the method operates reliably within $t \in [0.5, 0.7]$ but degrades at $t{=}0.9$ ($-9.3$ to $-26.0$\,pp across generators). Low-temperature improvement is model-dependent (Pythia/OLMo: $+7$--$9$\,pp; Qwen: $0$--$2$\,pp), indicating that depth profiling assumes standard decoding regimes and that the benefit of conservative temperature varies by model family.
29	Tokenizer differences across families may contribute to the observed temperature sensitivity pattern; within-family comparisons (two Qwen models showing consistent robustness) support a family-level effect, but controlling for tokenizer requires further study.
30	
31	Simpler features (character or word n-gram frequencies) were not explored; they may capture complementary surface-level patterns but would not contribute to the location/shape decomposition central to this analysis.
32	
33	We use 3-class granularity (gen-0\,/\,gen-1\,/\,gen-2+). A 5-class evaluation (Appendix~\ref{app:finer-depth}) yields LOGO F1\,$\approx$\,0.50, with depths 2--4 mutually indistinguishable, validating the 3-class design as the practical resolution limit.
34	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "318ea9e4-95fe-4127-b3a8-b332aa712056",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "52398fac-8b39-4e02-aa01-adb3e805ad1a",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex",
      "content": "\\section*{Limitations}\n\\label{sec:limitations}\n\nAll eight generators are base (pretrained) models.\nThis is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects and enable controlled study of recursive distributional drift.\nHowever, web text is predominantly produced by instruction-tuned and RLHF-aligned models.\nPreliminary instruct experiments confirm that depth signal degrades substantially under instruction tuning: OLMo-2-1B-Instruct drops to 3-class LOGO F1\\,=\\,0.338 (vs.\\ 0.763 base; this is classification F1, distinct from the clustering silhouette of the same value reported in \\S\\ref{sec:discussion}) and Qwen3-0.6B with chat template to 0.667 (vs.\\ 0.816 base); these comparisons use earlier LOGO subsets (5--6 generators) predating the full 8-generator expansion in Table~\\ref{tab:logo-results}.\nLength-matched analysis yields near-zero correlations ($|\\rho| < 0.02$) and binary classification near chance (F1\\,$\\approx$\\,0.5) for Qwen models, leaving interpretation ambiguous.\nExtending depth profiling to instruct models requires addressing these confounds (length regulation, format constraints, safety-driven distribution shaping) that instruction tuning introduces.\n\nOur experiments include generators up to 8.2B parameters (Qwen3-8B).\nDepth signal persists at this scale (Qwen3-8B 3-class F1\\,=\\,0.714), but cross-scale transfer incurs a moderate gap vs.\\ $\\leq$2.8B generators (F1\\,=\\,0.77--0.81).\nFrontier models (70B+) and closed-source models remain untested; the consistent scale trend (Mistral-7B binary F1\\,=\\,0.633, lowest among all generators) suggests depth signal may weaken further at frontier scales, potentially approaching the detection floor.\n\nDifferential depth response strength is prompt-type dependent: continuation chains show strongest drift (within-type binary F1\\,=\\,0.781) compared to elaboration (0.730) and rewriting (0.737), with within-prompt-type paraphrastic chains showing weaker signal (binary F1\\,=\\,0.671 vs.\\ 0.749 for within-prompt-type continuation).\nDDR is most reliably detected in continuation-style generation; near-paraphrastic settings approach the method's detection floor.\nCross-prompt-type transfer (LOPTO F1\\,=\\,0.753) confirms shared signal, yet additional prompt types (e.g., summarization, instruction following) and cross-generator $\\times$ cross-prompt interactions remain untested.\n\nOur primary evaluation uses single-generator chains; cross-model chains (\\S\\ref{sec:results-classification}) confirm depth signal under generator heterogeneity (3-class F1\\,=\\,0.809, binary F1\\,=\\,0.764), though the eight generators represent a controlled laboratory setting rather than the full diversity of real-world contamination.\nSimulated human editing (\\S\\ref{sec:discussion}) suggests graceful degradation, but the gap between simulated token replacement and real-world post-processing remains untested.\n\nThe reference model is fixed to Pythia-410M throughout, although cross-family reference experiments (\\S\\ref{sec:results-differential}) confirm the phenomenon is not reference-specific (spread 0.013 across three references).\nAll seed texts in the main evaluation are English Wikipedia excerpts.\nCross-domain evaluation (Appendix~\\ref{app:domain}) at both $t{=}1.0$ and $t{=}0.7$ shows that depth signal persists across News, Academic, and Code domains (binary F1 0.63--0.75 depending on domain and temperature), though a domain $\\times$ temperature interaction exists: at $t{=}0.7$, Academic domain binary F1 drops to 0.628, suggesting that reference model calibration is critical for cross-domain deployment.\nThe reference model dependency (Pythia-410M, English-centric pretraining) limits non-English applicability and adds inference overhead relative to surface-feature-only approaches.\nGeneralization to other languages remains untested.\n\nOur default analysis uses fixed decoding parameters (temperature 0.7, nucleus $p{=}0.9$). A temperature ablation across four generators from three families (Appendix~\\ref{app:sampling-sensitivity}) shows that the method operates reliably within $t \\in [0.5, 0.7]$ but degrades at $t{=}0.9$ ($-9.3$ to $-26.0$\\,pp across generators). Low-temperature improvement is model-dependent (Pythia/OLMo: $+7$--$9$\\,pp; Qwen: $0$--$2$\\,pp), indicating that depth profiling assumes standard decoding regimes and that the benefit of conservative temperature varies by model family.\nTokenizer differences across families may contribute to the observed temperature sensitivity pattern; within-family comparisons (two Qwen models showing consistent robustness) support a family-level effect, but controlling for tokenizer requires further study.\n\nSimpler features (character or word n-gram frequencies) were not explored; they may capture complementary surface-level patterns but would not contribute to the location/shape decomposition central to this analysis.\n\nWe use 3-class granularity (gen-0\\,/\\,gen-1\\,/\\,gen-2+). A 5-class evaluation (Appendix~\\ref{app:finer-depth}) yields LOGO F1\\,$\\approx$\\,0.50, with depths 2--4 mutually indistinguishable, validating the 3-class design as the practical resolution limit.\n",
      "numLines": 34,
      "startLine": 1,
      "totalLines": 34
    }
  },
  "sourceToolAssistantUUID": "318ea9e4-95fe-4127-b3a8-b332aa712056",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 52 · 2026-05-19T06:17:39.093Z_

<details open><summary>🔧 Tool call — Read · `toolu_01HnqqPw3dmxjzK9KEwzmLe2`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/ethics.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "52398fac-8b39-4e02-aa01-adb3e805ad1a",
  "isSidechain": false,
  "requestId": "req_011CbBSTrDbwZzahyESiLTBV",
  "type": "assistant",
  "uuid": "838a4ffe-5ff3-417e-9138-cd772e58c9c6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XRnxsSQBR2khGm9XsTaGLu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3705,
      "cache_read_input_tokens": 31700,
      "output_tokens": 891,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3705,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 891,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 3705,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3705
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "unavailable"
      }
    }
  }
}
```

</details>

---


### Runtime record

_source line 53_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 2  **你的审查侧重：新颖性 + 论文完整性 + 写作质量 + 格式合规**  ### 论文信息 - **标题**: Depth Profiling: Classifying Recursive Generation Depth in Base LLM Text Chains - **路径**: `projec…",
  "leafUuid": "8bbdd5c5-eca4-4a96-99ff-5594df69cbd5",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Runtime record

_source line 54_

```json
{
  "type": "ai-title",
  "aiTitle": "Review depth profiling LLM paper for EMNLP",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Tool result

_source line 55 · 2026-05-19T06:17:39.323Z_

<details><summary>↩ Tool result · `toolu_01HDt2zWwruNVH7wWq649C2G`</summary>

```text
# ARR Review Form Dimensions

Based on the guidelines provided, ARR reviewers use **three primary scoring dimensions**:

## 1. **Soundness Score**
This evaluates technical validity. Per the guidelines: "The _soundness_ scores must be justified by the text of the review." Low soundness ratings require explicit explanation of major faults; unexplained low scores indicate the review doesn't faithfully represent the recommendation.

## 2. **Excitement Score**
This captures subjective interest independent of technical quality. The guidelines note this is "orthogonal to the assessment of the soundness of the paper" and "reflect[s] our personal taste, and so do not necessarily come with explicit reasons."

## 3. **Overall Assessment Score**
This provides an explicit recommendation for conference acceptance. It's described as "a composite score reflecting your assessment of soundness, excitement, and also other factors like novelty and impact."

## Key Evaluation Standards

All papers recommended for publication must be "sufficiently sound and reproducible," though reviewers may recommend papers for main conferences even without personal excitement if they have significant potential impact (efficiency improvements, high-quality resources for underserved languages/domains).

**Note:** The document doesn't specify exact numerical scales or detailed level descriptions for these dimensions—those appear in the actual OpenReview form referenced separately.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c485135b-ce29-4bf9-a8b5-e1e58989473f",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "8b30e969-fdf7-40fc-b772-d786a9e70960",
  "toolUseResult": {
    "bytes": 100603,
    "code": 200,
    "codeText": "OK",
    "result": "# ARR Review Form Dimensions\n\nBased on the guidelines provided, ARR reviewers use **three primary scoring dimensions**:\n\n## 1. **Soundness Score**\nThis evaluates technical validity. Per the guidelines: \"The _soundness_ scores must be justified by the text of the review.\" Low soundness ratings require explicit explanation of major faults; unexplained low scores indicate the review doesn't faithfully represent the recommendation.\n\n## 2. **Excitement Score**\nThis captures subjective interest independent of technical quality. The guidelines note this is \"orthogonal to the assessment of the soundness of the paper\" and \"reflect[s] our personal taste, and so do not necessarily come with explicit reasons.\"\n\n## 3. **Overall Assessment Score**\nThis provides an explicit recommendation for conference acceptance. It's described as \"a composite score reflecting your assessment of soundness, excitement, and also other factors like novelty and impact.\"\n\n## Key Evaluation Standards\n\nAll papers recommended for publication must be \"sufficiently sound and reproducible,\" though reviewers may recommend papers for main conferences even without personal excitement if they have significant potential impact (efficiency improvements, high-quality resources for underserved languages/domains).\n\n**Note:** The document doesn't specify exact numerical scales or detailed level descriptions for these dimensions—those appear in the actual OpenReview form referenced separately.",
    "durationMs": 5910,
    "url": "https://aclrollingreview.org/reviewerguidelines"
  },
  "sourceToolAssistantUUID": "c485135b-ce29-4bf9-a8b5-e1e58989473f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Runtime record

_source line 56 · 2026-05-19T06:17:39.326Z_

```json
{
  "parentUuid": "8b30e969-fdf7-40fc-b772-d786a9e70960",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "05dba37a-7546-4bd4-a8e2-4ab572f1d8ae",
  "timestamp": "2026-05-19T06:17:39.326Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---


### Assistant

_source line 57 · 2026-05-19T06:17:44.933Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the reference verification results in detail, and also read the appendix sections to check completeness. Let me also check the PDF visuals.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "05dba37a-7546-4bd4-a8e2-4ab572f1d8ae",
  "isSidechain": false,
  "requestId": "req_011CbBSUqMHxxg2eutzmeLDY",
  "type": "assistant",
  "uuid": "0d3455da-bc9f-4323-84ae-4c1b7b79d4d1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AgX2GiE4EAhfet6wZiP3LX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 14892,
      "cache_creation_input_tokens": 5020,
      "cache_read_input_tokens": 31700,
      "output_tokens": 574,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5020,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 14892,
          "output_tokens": 574,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 5020,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5020
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "previous_message_not_found"
      }
    }
  }
}
```

</details>

---


### Assistant

_source line 58 · 2026-05-19T06:17:46.866Z_

已读取所有正文 section。现在并行读取引用验证详情、部分关键 appendix，以及论文 PDF 可视化检查。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0d3455da-bc9f-4323-84ae-4c1b7b79d4d1",
  "isSidechain": false,
  "requestId": "req_011CbBSUqMHxxg2eutzmeLDY",
  "type": "assistant",
  "uuid": "d8fae3f3-48ea-4d84-9034-307353405498",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AgX2GiE4EAhfet6wZiP3LX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 14892,
      "cache_creation_input_tokens": 5020,
      "cache_read_input_tokens": 31700,
      "output_tokens": 574,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5020,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 14892,
          "output_tokens": 574,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 5020,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5020
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "previous_message_not_found"
      }
    }
  }
}
```

</details>

---


### Tool call

_source line 59 · 2026-05-19T06:17:51.606Z_

<details open><summary>🔧 Tool call — Read · `toolu_01UM6eVxXdGQna5SXmfrY4ku`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint--claude-sessions-review-reviewer-2-3f564e41/34cea30f-783a-4e65-9506-a050519fc721/tool-results/toolu_01HhP5NwhXwiZFFWVxhaLNX8.txt",
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d8fae3f3-48ea-4d84-9034-307353405498",
  "isSidechain": false,
  "requestId": "req_011CbBSUqMHxxg2eutzmeLDY",
  "type": "assistant",
  "uuid": "1c589184-d4d7-42a2-8274-27bea1f9b6bc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AgX2GiE4EAhfet6wZiP3LX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 14892,
      "cache_creation_input_tokens": 5020,
      "cache_read_input_tokens": 31700,
      "output_tokens": 574,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5020,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 14892,
          "output_tokens": 574,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 5020,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5020
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "previous_message_not_found"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 60 · 2026-05-19T06:17:52.060Z_

<details><summary>↩ Tool result · `toolu_01UM6eVxXdGQna5SXmfrY4ku`</summary>

```text
1	{"result":"{\"success\": true, \"data\": {\"summary\": {\"total_bib_entries\": 71, \"total_citations\": 96, \"unique_cited_keys\": 71, \"orphan_bib\": 0, \"missing_bib\": 0, \"duplicate_keys\": 0, \"online_verified\": 57, \"online_not_found\": 9, \"online_mismatch\": 5}, \"cross_check\": {\"orphan_bib\": [], \"missing_bib\": [], \"orphan_count\": 0, \"missing_count\": 0}, \"bib_entries\": [{\"key\": \"mccarthy2010mtld\", \"type\": \"article\", \"title\": \"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\", \"authors\": \"McCarthy, Philip M. and Jarvis, Scott\", \"year\": \"2010\", \"venue\": \"Behavior Research Methods\"}, {\"key\": \"covington2010mattr\", \"type\": \"article\", \"title\": \"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\", \"authors\": \"Covington, Michael A. and McFall, Joe D.\", \"year\": \"2010\", \"venue\": \"Journal of Quantitative Linguistics\"}, {\"key\": \"oren2024proving\", \"type\": \"inproceedings\", \"title\": \"Proving Test Set Contamination in Black Box Language Models\", \"authors\": \"Oren, Yonatan and Meister, Nicole and Chatterji, Niladri and Laber, Faisal and S...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"golchin2024time\", \"type\": \"inproceedings\", \"title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"authors\": \"Golchin, Shahriar and Surdeanu, Mihai\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"longpre2024data\", \"type\": \"inproceedings\", \"title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"authors\": \"Longpre, Shayne and Mahari, Robert and Lee, Naana and Luccioni, Sasha and Jernit...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"cohen1988statistical\", \"type\": \"book\", \"title\": \"Statistical Power Analysis for the Behavioral Sciences\", \"authors\": \"Cohen, Jacob\", \"year\": \"1988\", \"venue\": \"\"}, {\"key\": \"tang2024science\", \"type\": \"article\", \"title\": \"The Science of Detecting LLM-Generated Text\", \"authors\": \"Tang, Ruixiang and Chuang, Yu-Neng and Hu, Xia\", \"year\": \"2024\", \"venue\": \"Communications of the ACM\"}, {\"key\": \"neal2017surveying\", \"type\": \"article\", \"title\": \"Surveying Stylometry Techniques and Applications\", \"authors\": \"Neal, Tempestt and Sundararajan, Kalaivani and Fatima, Aneez and Yan, Yiming and...\", \"year\": \"2017\", \"venue\": \"ACM Computing Surveys\"}, {\"key\": \"detectgpt\", \"type\": \"inproceedings\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"authors\": \"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"gltr\", \"type\": \"inproceedings\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"authors\": \"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\", \"year\": \"2019\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"dna_gpt\", \"type\": \"inproceedings\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"authors\": \"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"binoculars\", \"type\": \"inproceedings\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"authors\": \"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"fast_detectgpt\", \"type\": \"inproceedings\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"authors\": \"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"ld_score\", \"type\": \"article\", \"title\": \"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\", \"authors\": \"Narayanasamy, Priyadarshan and Agrawal, Swastik and Faber, Klint and Alam, Fardi...\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2605.01647\"}, {\"key\": \"intrinsic_dimension\", \"type\": \"inproceedings\", \"title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"authors\": \"Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavsk...\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"diveye\", \"type\": \"article\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"authors\": \"Basani, Advik Raj and Chen, Pin-Yu\", \"year\": \"2026\", \"venue\": \"Transactions on Machine Learning Research\"}, {\"key\": \"generator_barrier\", \"type\": \"article\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"authors\": \"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2604.13692\"}, {\"key\": \"feat_aug_transformer\", \"type\": \"article\", \"title\": \"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\", \"authors\": \"Mady, Mohamed and Reschke, Johannes and Schuller, Bj\\\\\\\"orn\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2605.03969\"}, {\"key\": \"reliable_detection\", \"type\": \"article\", \"title\": \"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\", \"authors\": \"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\", \"year\": \"2025\", \"venue\": \"Transactions on Machine Learning Research\"}, {\"key\": \"paraphrase_evades\", \"type\": \"inproceedings\", \"title\": \"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\", \"authors\": \"Krishna, Kalpesh and Song, Yixiao and Karpinska, Marzena and Wieting, John and I...\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"detection_possibilities\", \"type\": \"inproceedings\", \"title\": \"Position: On the Possibilities of AI-Generated Text Detection\", \"authors\": \"Chakraborty, Souradip and Bedi, Amrit Singh and Zhu, Sicheng and An, Bang and Ma...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"grover\", \"type\": \"inproceedings\", \"title\": \"Defending Against Neural Fake News\", \"authors\": \"Zellers, Rowan and Holtzman, Ari and Rashkin, Hannah and Bisk, Yonatan and Farha...\", \"year\": \"2019\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"release_strategies\", \"type\": \"article\", \"title\": \"Release Strategies and the Social Impacts of Language Models\", \"authors\": \"Solaiman, Irene and Brundage, Miles and Clark, Jack and Askell, Amanda and Herbe...\", \"year\": \"2019\", \"venue\": \"arXiv preprint arXiv:1908.09203\"}, {\"key\": \"beyond_binary\", \"type\": \"inproceedings\", \"title\": \"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\", \"authors\": \"Cheng, Zihao and Zhou, Li and Jiang, Feng and Wang, Benyou and Li, Haizhou\", \"year\": \"2025\", \"venue\": \"Proceedings of the ACM Web Conference\"}, {\"key\": \"semeval2024_task8\", \"type\": \"inproceedings\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"authors\": \"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Workshop on Semantic Evaluation\"}, {\"key\": \"abburi_multifaceted\", \"type\": \"article\", \"title\": \"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\", \"authors\": \"Abburi, Harika and Bhattacharya, Sanmitra and Bowen, Edward and Pudota, Nirmala\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2505.11550\"}, {\"key\": \"defactify_dataset\", \"type\": \"article\", \"title\": \"A Comprehensive Dataset for Human vs.\\\\ AI Generated Text Detection\", \"authors\": \"Roy, Rajarshi and Imanpour, Nasrin and Aziz, Ashhar and Bajpai, Shashwat and Sin...\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2510.22874\"}, {\"key\": \"self_consuming_mad\", \"type\": \"inproceedings\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"authors\": \"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"curse_of_recursion\", \"type\": \"article\", \"title\": \"AI models collapse when trained on recursively generated data\", \"authors\": \"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"strong_model_collapse\", \"type\": \"inproceedings\", \"title\": \"Strong Model Collapse\", \"authors\": \"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\", \"year\": \"2025\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"model_collapse_avoidable\", \"type\": \"inproceedings\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"authors\": \"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\", \"year\": \"2024\", \"venue\": \"Proceedings of the First Conference on Language Modeling (COLM)\"}, {\"key\": \"self_rewarding_lms\", \"type\": \"article\", \"title\": \"Self-Rewarding Language Models\", \"authors\": \"Yuan, Weizhe and Pang, Richard Yuanzhe and Cho, Kyunghyun and Sukhbaatar, Sainba...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2401.10020\"}, {\"key\": \"spin\", \"type\": \"inproceedings\", \"title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"authors\": \"Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan\", \"year\": \"2024\", \"venue\": \"Proceedings of the 41st International Conference on Machine Learning\"}, {\"key\": \"qlora\", \"type\": \"inproceedings\", \"title\": \"QLoRA: Efficient Finetuning of Quantized Language Models\", \"authors\": \"Dettmers, Tim and Pagnoni, Artidoro and Holtzman, Ari and Zettlemoyer, Luke\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"dsir\", \"type\": \"inproceedings\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"authors\": \"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\", \"year\": \"2023\", \"venue\": \"Advances in Neural Information Processing Systems\"}, {\"key\": \"qurating\", \"type\": \"inproceedings\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"authors\": \"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"ccnet\", \"type\": \"inproceedings\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"authors\": \"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\", \"year\": \"2020\", \"venue\": \"Proceedings of the Language Resources and Evaluation Conference\"}, {\"key\": \"watermark_llm\", \"type\": \"inproceedings\", \"title\": \"A Watermark for Large Language Models\", \"authors\": \"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"synthid_text\", \"type\": \"article\", \"title\": \"Scalable Watermarking for Identifying Large Language Model Outputs\", \"authors\": \"Dathathri, Sumanth and See, Abigail and Ghaisas, Sumedh and Huang, Po-Sen and Mc...\", \"year\": \"2024\", \"venue\": \"Nature\"}, {\"key\": \"aaronson_watermark\", \"type\": \"misc\", \"title\": \"Watermarking GPT Outputs\", \"authors\": \"Aaronson, Scott and Kirchner, Hendrik\", \"year\": \"2022\", \"venue\": \"\"}, {\"key\": \"chainwash\", \"type\": \"article\", \"title\": \"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\", \"authors\": \"Ameen, Mohd Ruhul and Islam, Akif and Mahmud, Nadim and Hamid, Md. Ekramul\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2605.05503\"}, {\"key\": \"curious_decline\", \"type\": \"inproceedings\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"authors\": \"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\'e\", \"year\": \"2024\", \"venue\": \"Findings of the Association for Computational Linguistics: NAACL\"}, {\"key\": \"writing_diversity\", \"type\": \"inproceedings\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"authors\": \"Padmakumar, Vishakh and He, He\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"nucleus_sampling\", \"type\": \"inproceedings\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"authors\": \"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\", \"year\": \"2020\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"stamatatos_survey\", \"type\": \"article\", \"title\": \"A Survey of Modern Authorship Attribution Methods\", \"authors\": \"Stamatatos, Efstathios\", \"year\": \"2009\", \"venue\": \"Journal of the American Society for Information Science and Technology\"}, {\"key\": \"koppel_authorship\", \"type\": \"article\", \"title\": \"Computational Methods in Authorship Attribution\", \"authors\": \"Koppel, Moshe and Schler, Jonathan and Argamon, Shlomo\", \"year\": \"2009\", \"venue\": \"Journal of the American Society for Information Science and Technology\"}, {\"key\": \"uchendu_attribution\", \"type\": \"inproceedings\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"authors\": \"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\", \"year\": \"2020\", \"venue\": \"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\"}, {\"key\": \"munir_looking_glass\", \"type\": \"inproceedings\", \"title\": \"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\", \"authors\": \"Munir, Shaoor and Batool, Brishna and Shafiq, Zubair and Srinivasan, Padmini and...\", \"year\": \"2021\", \"venue\": \"Proceedings of the Conference of the European Chapter of the Association for Com...\"}, {\"key\": \"broken_telephone\", \"type\": \"inproceedings\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"authors\": \"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\", \"year\": \"2025\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"attractor_cycles\", \"type\": \"inproceedings\", \"title\": \"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\", \"authors\": \"Wang, Yibo and Wu, Congying and Li, Yanan and Cai, Yi\", \"year\": \"2025\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"markovian_chains\", \"type\": \"article\", \"title\": \"Markovian Generation Chains in Large Language Models\", \"authors\": \"Geng, Mingmeng and Mohamed, Amr and Shang, Guokan and Vazirgiannis, Michalis and...\", \"year\": \"2026\", \"venue\": \"arXiv preprint arXiv:2603.11228\"}, {\"key\": \"min_k_percent\", \"type\": \"inproceedings\", \"title\": \"Detecting Pretraining Data from Large Language Models\", \"authors\": \"Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Da...\", \"year\": \"2024\", \"venue\": \"Proceedings of the International Conference on Learning Representations\"}, {\"key\": \"wu_survey_2025\", \"type\": \"article\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"authors\": \"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\", \"year\": \"2025\", \"venue\": \"Computational Linguistics\"}, {\"key\": \"jawahar_survey\", \"type\": \"inproceedings\", \"title\": \"Automatic Detection of Machine Generated Text: A Critical Survey\", \"authors\": \"Jawahar, Ganesh and Abdul-Mageed, Muhammad and Lakshmanan, Laks V.S.\", \"year\": \"2020\", \"venue\": \"Proceedings of the International Conference on Computational Linguistics\"}, {\"key\": \"pythia\", \"type\": \"inproceedings\", \"title\": \"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\", \"authors\": \"Biderman, Stella and Schoelkopf, Hailey and Anthony, Quentin Gregory and Bradley...\", \"year\": \"2023\", \"venue\": \"Proceedings of the International Conference on Machine Learning\"}, {\"key\": \"olmo\", \"type\": \"inproceedings\", \"title\": \"OLMo: Accelerating the Science of Language Models\", \"authors\": \"Groeneveld, Dirk and Beltagy, Iz and Walsh, Evan and Bhagia, Akshita and Kinney,...\", \"year\": \"2024\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"qwen3\", \"type\": \"article\", \"title\": \"Qwen3 Technical Report\", \"authors\": \"Qwen Team\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2505.09388\"}, {\"key\": \"ghostbuster\", \"type\": \"inproceedings\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"authors\": \"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Jurafsky, Dan\", \"year\": \"2024\", \"venue\": \"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\"}, {\"key\": \"two_birds\", \"type\": \"article\", \"title\": \"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\", \"authors\": \"Rao, Harika and Vashistha, Adaku Jane and Jain, Aaryan and Garg, Naman\", \"year\": \"2025\", \"venue\": \"arXiv preprint arXiv:2508.14190\"}, {\"key\": \"beyond_final_actor\", \"type\": \"inproceedings\", \"title\": \"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\", \"authors\": \"Li, Ziang and Gao, Guan-Yu and Yang, Songlin and Yu, Ning and Fritz, Mario and M...\", \"year\": \"2026\", \"venue\": \"Proceedings of the Association for Computational Linguistics\"}, {\"key\": \"gutierrez_ordinal_survey\", \"type\": \"article\", \"title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"authors\": \"Guti\\\\'errez, Pedro Antonio and P\\\\'erez-Ortiz, Mar\\\\'ia and S\\\\'anchez-Monedero, Ja...\", \"year\": \"2016\", \"venue\": \"IEEE Transactions on Knowledge and Data Engineering\"}, {\"key\": \"coral_ordinal\", \"type\": \"article\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"authors\": \"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\", \"year\": \"2020\", \"venue\": \"Pattern Recognition Letters\"}, {\"key\": \"frank_hall_ordinal\", \"type\": \"inproceedings\", \"title\": \"A Simple Approach to Ordinal Classification\", \"authors\": \"Frank, Eibe and Hall, Mark\", \"year\": \"2001\", \"venue\": \"Proceedings of the European Conference on Machine Learning\"}, {\"key\": \"pang_opinion_mining\", \"type\": \"inproceedings\", \"title\": \"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\", \"authors\": \"Pang, Bo and Lee, Lillian\", \"year\": \"2005\", \"venue\": \"Proceedings of the 43rd Annual Meeting of the Association for Computational Ling...\"}, {\"key\": \"taghipour_neural_essay\", \"type\": \"inproceedings\", \"title\": \"A Neural Approach to Automated Essay Scoring\", \"authors\": \"Taghipour, Kaveh and Ng, Hwee Tou\", \"year\": \"2016\", \"venue\": \"Proceedings of the 2016 Conference on Empirical Methods in Natural Language Proc...\"}, {\"key\": \"corn_ordinal\", \"type\": \"article\", \"title\": \"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\", \"authors\": \"Shi, Xintong and Cao, Wenzhi and Raschka, Sebastian\", \"year\": \"2023\", \"venue\": \"Pattern Analysis and Applications\"}, {\"key\": \"xgboost\", \"type\": \"inproceedings\", \"title\": \"XGBoost: A Scalable Tree Boosting System\", \"authors\": \"Chen, Tianqi and Guestrin, Carlos\", \"year\": \"2016\", \"venue\": \"Proceedings of the ACM SIGKDD International Conference on Knowledge Discovery an...\"}, {\"key\": \"lakens_equivalence\", \"type\": \"article\", \"title\": \"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\", \"authors\": \"Lakens, Dani\\\\\\\"el\", \"year\": \"2017\", \"venue\": \"Social Psychological and Personality Science\"}, {\"key\": \"llama3\", \"type\": \"article\", \"title\": \"The Llama 3 Herd of Models\", \"authors\": \"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\", \"year\": \"2024\", \"venue\": \"arXiv preprint arXiv:2407.21783\"}, {\"key\": \"mistral7b\", \"type\": \"article\", \"title\": \"Mistral 7B\", \"authors\": \"Jiang, Albert Q. and Sablayrolles, Alexandre and Mensch, Arthur and Bamford, Chr...\", \"year\": \"2023\", \"venue\": \"arXiv preprint arXiv:2310.06825\"}, {\"key\": \"strobl_conditional_2008\", \"type\": \"article\", \"title\": \"Conditional Variable Importance for Random Forests\", \"authors\": \"Strobl, Carolin and Boulesteix, Anne-Laure and Kneib, Thomas and Augustin, Thoma...\", \"year\": \"2008\", \"venue\": \"BMC Bioinformatics\"}], \"tex_citations\": [{\"key\": \"curse_of_recursion\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"self_consuming_mad\", \"file\": \"introduction.tex\", \"line\": 5, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"binoculars\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"ld_score\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"detectgpt\", \"file\": \"introduction.tex\", \"line\": 6, \"command\": \"cite\"}, {\"key\": \"curse_of_recursion\", \"file\": \"introduction.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"self_consuming_mad\", \"file\": \"introduction.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"gltr\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"grover\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"release_strategies\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"detectgpt\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"binoculars\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"dna_gpt\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"ghostbuster\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"feat_aug_transformer\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"abburi_multifaceted\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"reliable_detection\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"ld_score\", \"file\": \"related_work.tex\", \"line\": 7, \"command\": \"cite\"}, {\"key\": \"intrinsic_dimension\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"diveye\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"generator_barrier\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"cite\"}, {\"key\": \"tang2024science\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"citet\"}, {\"key\": \"wu_survey_2025\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"citet\"}, {\"key\": \"jawahar_survey\", \"file\": \"related_work.tex\", \"line\": 8, \"command\": \"citet\"}, {\"key\": \"beyond_binary\", \"file\": \"related_work.tex\", \"line\": 11, \"command\": \"citet\"}, {\"key\": \"two_birds\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"citet\"}, {\"key\": \"beyond_final_actor\", \"file\": \"related_work.tex\", \"line\": 12, \"command\": \"citet\"}, {\"key\": \"semeval2024_task8\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"defactify_dataset\", \"file\": \"related_work.tex\", \"line\": 13, \"command\": \"cite\"}, {\"key\": \"paraphrase_evades\", \"file\": \"related_work.tex\", \"line\": 15, \"command\": \"cite\"}, {\"key\": \"detection_possibilities\", \"file\": \"related_work.tex\", \"line\": 15, \"command\": \"cite\"}, {\"key\": \"gutierrez_ordinal_survey\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"coral_ordinal\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"corn_ordinal\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"frank_hall_ordinal\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"pang_opinion_mining\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"taghipour_neural_essay\", \"file\": \"related_work.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"uchendu_attribution\", \"file\": \"related_work.tex\", \"line\": 17, \"command\": \"cite\"}, {\"key\": \"munir_looking_glass\", \"file\": \"related_work.tex\", \"line\": 17, \"command\": \"cite\"}, {\"key\": \"self_consuming_mad\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"curse_of_recursion\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"model_collapse_avoidable\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"strong_model_collapse\", \"file\": \"related_work.tex\", \"line\": 23, \"command\": \"cite\"}, {\"key\": \"self_rewarding_lms\", \"file\": \"related_work.tex\", \"line\": 24, \"command\": \"cite\"}, {\"key\": \"spin\", \"file\": \"related_work.tex\", \"line\": 24, \"command\": \"cite\"}, {\"key\": \"curse_of_recursion\", \"file\": \"related_work.tex\", \"line\": 25, \"command\": \"cite\"}, {\"key\": \"strong_model_collapse\", \"file\": \"related_work.tex\", \"line\": 25, \"command\": \"cite\"}, {\"key\": \"broken_telephone\", \"file\": \"related_work.tex\", \"line\": 28, \"command\": \"citet\"}, {\"key\": \"markovian_chains\", \"file\": \"related_work.tex\", \"line\": 29, \"command\": \"citet\"}, {\"key\": \"attractor_cycles\", \"file\": \"related_work.tex\", \"line\": 30, \"command\": \"citet\"}, {\"key\": \"markovian_chains\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"broken_telephone\", \"file\": \"related_work.tex\", \"line\": 32, \"command\": \"cite\"}, {\"key\": \"curious_decline\", \"file\": \"related_work.tex\", \"line\": 37, \"command\": \"cite\"}, {\"key\": \"writing_diversity\", \"file\": \"related_work.tex\", \"line\": 37, \"command\": \"cite\"}, {\"key\": \"stamatatos_survey\", \"file\": \"related_work.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"koppel_authorship\", \"file\": \"related_work.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"neal2017surveying\", \"file\": \"related_work.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"mccarthy2010mtld\", \"file\": \"related_work.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"covington2010mattr\", \"file\": \"related_work.tex\", \"line\": 38, \"command\": \"cite\"}, {\"key\": \"uchendu_attribution\", \"file\": \"related_work.tex\", \"line\": 39, \"command\": \"cite\"}, {\"key\": \"nucleus_sampling\", \"file\": \"related_work.tex\", \"line\": 39, \"command\": \"cite\"}, {\"key\": \"dsir\", \"file\": \"related_work.tex\", \"line\": 44, \"command\": \"cite\"}, {\"key\": \"qurating\", \"file\": \"related_work.tex\", \"line\": 44, \"command\": \"cite\"}, {\"key\": \"ccnet\", \"file\": \"related_work.tex\", \"line\": 44, \"command\": \"cite\"}, {\"key\": \"oren2024proving\", \"file\": \"related_work.tex\", \"line\": 44, \"command\": \"cite\"}, {\"key\": \"golchin2024time\", \"file\": \"related_work.tex\", \"line\": 44, \"command\": \"cite\"}, {\"key\": \"longpre2024data\", \"file\": \"related_work.tex\", \"line\": 44, \"command\": \"cite\"}, {\"key\": \"watermark_llm\", \"file\": \"related_work.tex\", \"line\": 46, \"command\": \"cite\"}, {\"key\": \"synthid_text\", \"file\": \"related_work.tex\", \"line\": 46, \"command\": \"cite\"}, {\"key\": \"aaronson_watermark\", \"file\": \"related_work.tex\", \"line\": 46, \"command\": \"cite\"}, {\"key\": \"chainwash\", \"file\": \"related_work.tex\", \"line\": 46, \"command\": \"cite\"}, {\"key\": \"min_k_percent\", \"file\": \"related_work.tex\", \"line\": 47, \"command\": \"citet\"}, {\"key\": \"pythia\", \"file\": \"method.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"olmo\", \"file\": \"method.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"qwen3\", \"file\": \"method.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"llama3\", \"file\": \"method.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"mistral7b\", \"file\": \"method.tex\", \"line\": 16, \"command\": \"cite\"}, {\"key\": \"xgboost\", \"file\": \"method.tex\", \"line\": 75, \"command\": \"cite\"}, {\"key\": \"coral_ordinal\", \"file\": \"method.tex\", \"line\": 77, \"command\": \"cite\"}, {\"key\": \"corn_ordinal\", \"file\": \"method.tex\", \"line\": 77, \"command\": \"cite\"}, {\"key\": \"frank_hall_ordinal\", \"file\": \"method.tex\", \"line\": 77, \"command\": \"cite\"}, {\"key\": \"fast_detectgpt\", \"file\": \"method.tex\", \"line\": 86, \"command\": \"cite\"}, {\"key\": \"binoculars\", \"file\": \"method.tex\", \"line\": 86, \"command\": \"cite\"}, {\"key\": \"ld_score\", \"file\": \"method.tex\", \"line\": 86, \"command\": \"cite\"}, {\"key\": \"cohen1988statistical\", \"file\": \"results.tex\", \"line\": 72, \"command\": \"cite\"}, {\"key\": \"strobl_conditional_2008\", \"file\": \"results.tex\", \"line\": 90, \"command\": \"cite\"}, {\"key\": \"curse_of_recursion\", \"file\": \"discussion.tex\", \"line\": 25, \"command\": \"cite\"}, {\"key\": \"strong_model_collapse\", \"file\": \"discussion.tex\", \"line\": 25, \"command\": \"cite\"}, {\"key\": \"qlora\", \"file\": \"appendix_qlora.tex\", \"line\": 1, \"command\": \"cite\"}, {\"key\": \"coral_ordinal\", \"file\": \"appendix_classifier.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"frank_hall_ordinal\", \"file\": \"appendix_classifier.tex\", \"line\": 31, \"command\": \"cite\"}, {\"key\": \"lakens_equivalence\", \"file\": \"appendix_downstream.tex\", \"line\": 41, \"command\": \"cite\"}, {\"key\": \"lakens_equivalence\", \"file\": \"appendix_tost.tex\", \"line\": 4, \"command\": \"cite\"}, {\"key\": \"cohen1988statistical\", \"file\": \"appendix_tost.tex\", \"line\": 5, \"command\": \"cite\"}], \"online_verification\": [{\"key\": \"mccarthy2010mtld\", \"title\": \"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"MTLD, vocd-D, and HD-D: A validation study of sophisticated approaches to lexical diversity assessment\", \"matched_year\": \"2010\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"covington2010mattr\", \"title\": \"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\", \"status\": \"verified\", \"confidence\": 0.986, \"matched_title\": \"Cutting the Gordian Knot: The Moving-Average Type–Token Ratio (MATTR)\", \"matched_year\": \"2010\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"oren2024proving\", \"title\": \"Proving Test Set Contamination in Black Box Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Proving Test Set Contamination in Black Box Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"golchin2024time\", \"title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"longpre2024data\", \"title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"cohen1988statistical\", \"title\": \"Statistical Power Analysis for the Behavioral Sciences\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Statistical Power Analysis for the Behavioral Sciences\", \"matched_year\": \"1989\", \"mismatch_fields\": [\"first_author: bib=cohen vs api=muller\"], \"note\": \"\"}, {\"key\": \"tang2024science\", \"title\": \"The Science of Detecting LLM-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Science of Detecting LLM-Generated Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"neal2017surveying\", \"title\": \"Surveying Stylometry Techniques and Applications\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Surveying Stylometry Techniques and Applications\", \"matched_year\": \"2017\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"detectgpt\", \"title\": \"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\", \"status\": \"not_found\", \"confidence\": 0.382, \"matched_title\": \"Regulating ChatGPT and other Large Generative AI Models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.38 below threshold 0.82\"}, {\"key\": \"gltr\", \"title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"GLTR: Statistical Detection and Visualization of Generated Text\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dna_gpt\", \"title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"binoculars\", \"title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"fast_detectgpt\", \"title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"ld_score\", \"title\": \"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"intrinsic_dimension\", \"title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"diveye\", \"title\": \"Diversity Boosts AI-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Diversity Boosts AI-Generated Text Detection\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"generator_barrier\", \"title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"feat_aug_transformer\", \"title\": \"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"reliable_detection\", \"title\": \"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\", \"status\": \"not_found\", \"confidence\": 0.344, \"matched_title\": \"2015 ESC Guidelines for the management of acute coronary syndromes in patients presenting without persistent ST-segment elevation\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.34 below threshold 0.82\"}, {\"key\": \"paraphrase_evades\", \"title\": \"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Paraphrasing evades detectors of AI-generated text, but retrieval is an effective defense\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"detection_possibilities\", \"title\": \"Position: On the Possibilities of AI-Generated Text Detection\", \"status\": \"not_found\", \"confidence\": 0.253, \"matched_title\": \"Review of deep learning: concepts, CNN architectures, challenges, applications, future directions\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.25 below threshold 0.82\"}, {\"key\": \"grover\", \"title\": \"Defending Against Neural Fake News\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Defending Against Neural Fake News\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"release_strategies\", \"title\": \"Release Strategies and the Social Impacts of Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Release Strategies and the Social Impacts of Language Models\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"beyond_binary\", \"title\": \"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"semeval2024_task8\", \"title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"abburi_multifaceted\", \"title\": \"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"defactify_dataset\", \"title\": \"A Comprehensive Dataset for Human vs.\\\\ AI Generated Text Detection\", \"status\": \"not_found\", \"confidence\": 0.355, \"matched_title\": \"Performance of ChatGPT on USMLE: Potential for AI-assisted medical education using large language models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.36 below threshold 0.82\"}, {\"key\": \"self_consuming_mad\", \"title\": \"Self-Consuming Generative Models Go MAD\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Self-Consuming Generative Models go MAD\", \"matched_year\": \"2023\", \"mismatch_fields\": [\"first_author: bib=alemohammad vs api=casco-rodriguez\"], \"note\": \"\"}, {\"key\": \"curse_of_recursion\", \"title\": \"AI models collapse when trained on recursively generated data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"AI models collapse when trained on recursively generated data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"strong_model_collapse\", \"title\": \"Strong Model Collapse\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Strong Model Collapse\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"model_collapse_avoidable\", \"title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"self_rewarding_lms\", \"title\": \"Self-Rewarding Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Self-Rewarding Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"spin\", \"title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qlora\", \"title\": \"QLoRA: Efficient Finetuning of Quantized Language Models\", \"status\": \"verified\", \"confidence\": 0.871, \"matched_title\": \"QLoRA: Efficient Finetuning of Quantized LLMs\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"dsir\", \"title\": \"Data Selection for Language Models via Importance Resampling\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Data Selection for Language Models via Importance Resampling\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qurating\", \"title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"QuRating: Selecting High-Quality Data for Training Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"ccnet\", \"title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"watermark_llm\", \"title\": \"A Watermark for Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Watermark for Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"synthid_text\", \"title\": \"Scalable Watermarking for Identifying Large Language Model Outputs\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Scalable watermarking for identifying large language model outputs\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"aaronson_watermark\", \"title\": \"Watermarking GPT Outputs\", \"status\": \"not_found\", \"confidence\": 0.418, \"matched_title\": \"Undetectable Watermarks for Language Models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.42 below threshold 0.82\"}, {\"key\": \"chainwash\", \"title\": \"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"curious_decline\", \"title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"writing_diversity\", \"title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Does Writing with Language Models Reduce Content Diversity?\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"nucleus_sampling\", \"title\": \"The Curious Case of Neural Text Degeneration\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"The Curious Case of Neural Text Degeneration\", \"matched_year\": \"2019\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"stamatatos_survey\", \"title\": \"A Survey of Modern Authorship Attribution Methods\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A survey of modern authorship attribution methods\", \"matched_year\": \"2008\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"koppel_authorship\", \"title\": \"Computational Methods in Authorship Attribution\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Computational methods in authorship attribution\", \"matched_year\": \"2008\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"uchendu_attribution\", \"title\": \"Authorship Attribution for Neural Text Generation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Authorship Attribution for Neural Text Generation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"munir_looking_glass\", \"title\": \"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\", \"matched_year\": \"2021\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"broken_telephone\", \"title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"LLM as a Broken Telephone: Iterative Generation Distorts Information\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"attractor_cycles\", \"title\": \"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"markovian_chains\", \"title\": \"Markovian Generation Chains in Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Markovian Generation Chains in Large Language Models\", \"matched_year\": \"2026\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"min_k_percent\", \"title\": \"Detecting Pretraining Data from Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Detecting Pretraining Data from Large Language Models\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"wu_survey_2025\", \"title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\", \"matched_year\": \"2025\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"jawahar_survey\", \"title\": \"Automatic Detection of Machine Generated Text: A Critical Survey\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Automatic Detection of Machine Generated Text: A Critical Survey\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pythia\", \"title\": \"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\", \"status\": \"not_found\", \"confidence\": 0.497, \"matched_title\": \"The TRIPOD-LLM reporting guideline for studies using large language models\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.50 below threshold 0.82\"}, {\"key\": \"olmo\", \"title\": \"OLMo: Accelerating the Science of Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"OLMo: Accelerating the Science of Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"qwen3\", \"title\": \"Qwen3 Technical Report\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Qwen3 Technical Report\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=team vs api=yang\"], \"note\": \"\"}, {\"key\": \"ghostbuster\", \"title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\", \"matched_year\": \"2024\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"two_birds\", \"title\": \"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\", \"status\": \"not_found\", \"confidence\": 0.32, \"matched_title\": \"Large AI Models in Health Informatics: Applications, Challenges, and the Future\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.32 below threshold 0.82\"}, {\"key\": \"beyond_final_actor\", \"title\": \"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\", \"status\": \"not_found\", \"confidence\": 0.722, \"matched_title\": \"Beyond the Final Actor: Modeling the Dual Roles of Creator and Editor for Fine-Grained LLM-Generated Text Detection\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.72 below threshold 0.82\"}, {\"key\": \"gutierrez_ordinal_survey\", \"title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"Ordinal Regression Methods: Survey and Experimental Study\", \"matched_year\": \"2015\", \"mismatch_fields\": [\"first_author: bib=guti\\\\'errez vs api=gutiérrez\"], \"note\": \"\"}, {\"key\": \"coral_ordinal\", \"title\": \"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Rank consistent ordinal regression for neural networks with application to age estimation\", \"matched_year\": \"2020\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"frank_hall_ordinal\", \"title\": \"A Simple Approach to Ordinal Classification\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Simple Approach to Ordinal Classification\", \"matched_year\": \"2001\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"pang_opinion_mining\", \"title\": \"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Seeing stars: Exploiting class relationships for sentiment categorization with respect to rating scales\", \"matched_year\": \"2005\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"taghipour_neural_essay\", \"title\": \"A Neural Approach to Automated Essay Scoring\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"A Neural Approach to Automated Essay Scoring\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"corn_ordinal\", \"title\": \"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Deep neural networks for rank-consistent ordinal regression based on conditional probabilities\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"xgboost\", \"title\": \"XGBoost: A Scalable Tree Boosting System\", \"status\": \"not_found\", \"confidence\": 0.298, \"matched_title\": \"XGBoost\", \"matched_year\": \"\", \"mismatch_fields\": [], \"note\": \"best match similarity 0.30 below threshold 0.82\"}, {\"key\": \"lakens_equivalence\", \"title\": \"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\", \"status\": \"verified\", \"confidence\": 0.976, \"matched_title\": \"Equivalence Tests: A Practical Primer for t-Tests, Correlations, and Meta-Analyses\", \"matched_year\": \"2016\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"llama3\", \"title\": \"The Llama 3 Herd of Models\", \"status\": \"mismatch\", \"confidence\": 1.0, \"matched_title\": \"The Llama 3 herd of models\", \"matched_year\": \"2025\", \"mismatch_fields\": [\"first_author: bib=grattafiori vs api=aaron\"], \"note\": \"\"}, {\"key\": \"mistral7b\", \"title\": \"Mistral 7B\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Mistral 7B\", \"matched_year\": \"2023\", \"mismatch_fields\": [], \"note\": \"\"}, {\"key\": \"strobl_conditional_2008\", \"title\": \"Conditional Variable Importance for Random Forests\", \"status\": \"verified\", \"confidence\": 1.0, \"matched_title\": \"Conditional variable importance for random forests\", \"matched_year\": \"2008\", \"mismatch_fields\": [], \"note\": \"\"}]}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1c589184-d4d7-42a2-8274-27bea1f9b6bc",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "6857f36b-df70-4ffa-b833-8e673fe4b47f",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint--claude-sessions-review-reviewer-2-3f564e41/34cea30f-783a-4e65-9506-a050519fc721/tool-results/toolu_01HhP5NwhXwiZFFWVxhaLNX8.txt",
      "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"summary\\\": {\\\"total_bib_entries\\\": 71, \\\"total_citations\\\": 96, \\\"unique_cited_keys\\\": 71, \\\"orphan_bib\\\": 0, \\\"missing_bib\\\": 0, \\\"duplicate_keys\\\": 0, \\\"online_verified\\\": 57, \\\"online_not_found\\\": 9, \\\"online_mismatch\\\": 5}, \\\"cross_check\\\": {\\\"orphan_bib\\\": [], \\\"missing_bib\\\": [], \\\"orphan_count\\\": 0, \\\"missing_count\\\": 0}, \\\"bib_entries\\\": [{\\\"key\\\": \\\"mccarthy2010mtld\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\\\", \\\"authors\\\": \\\"McCarthy, Philip M. and Jarvis, Scott\\\", \\\"year\\\": \\\"2010\\\", \\\"venue\\\": \\\"Behavior Research Methods\\\"}, {\\\"key\\\": \\\"covington2010mattr\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\\\", \\\"authors\\\": \\\"Covington, Michael A. and McFall, Joe D.\\\", \\\"year\\\": \\\"2010\\\", \\\"venue\\\": \\\"Journal of Quantitative Linguistics\\\"}, {\\\"key\\\": \\\"oren2024proving\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Proving Test Set Contamination in Black Box Language Models\\\", \\\"authors\\\": \\\"Oren, Yonatan and Meister, Nicole and Chatterji, Niladri and Laber, Faisal and S...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"golchin2024time\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\\\", \\\"authors\\\": \\\"Golchin, Shahriar and Surdeanu, Mihai\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"longpre2024data\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\\\", \\\"authors\\\": \\\"Longpre, Shayne and Mahari, Robert and Lee, Naana and Luccioni, Sasha and Jernit...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"type\\\": \\\"book\\\", \\\"title\\\": \\\"Statistical Power Analysis for the Behavioral Sciences\\\", \\\"authors\\\": \\\"Cohen, Jacob\\\", \\\"year\\\": \\\"1988\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"tang2024science\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"The Science of Detecting LLM-Generated Text\\\", \\\"authors\\\": \\\"Tang, Ruixiang and Chuang, Yu-Neng and Hu, Xia\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Communications of the ACM\\\"}, {\\\"key\\\": \\\"neal2017surveying\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Surveying Stylometry Techniques and Applications\\\", \\\"authors\\\": \\\"Neal, Tempestt and Sundararajan, Kalaivani and Fatima, Aneez and Yan, Yiming and...\\\", \\\"year\\\": \\\"2017\\\", \\\"venue\\\": \\\"ACM Computing Surveys\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"authors\\\": \\\"Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"gltr\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"authors\\\": \\\"Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"dna_gpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"authors\\\": \\\"Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Ya...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"authors\\\": \\\"Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Ham...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"authors\\\": \\\"Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yu...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\\\", \\\"authors\\\": \\\"Narayanasamy, Priyadarshan and Agrawal, Swastik and Faber, Klint and Alam, Fardi...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2605.01647\\\"}, {\\\"key\\\": \\\"intrinsic_dimension\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"authors\\\": \\\"Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavsk...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"diveye\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"authors\\\": \\\"Basani, Advik Raj and Chen, Pin-Yu\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Transactions on Machine Learning Research\\\"}, {\\\"key\\\": \\\"generator_barrier\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"authors\\\": \\\"Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2604.13692\\\"}, {\\\"key\\\": \\\"feat_aug_transformer\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\\\", \\\"authors\\\": \\\"Mady, Mohamed and Reschke, Johannes and Schuller, Bj\\\\\\\\\\\\\\\"orn\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2605.03969\\\"}, {\\\"key\\\": \\\"reliable_detection\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\\\", \\\"authors\\\": \\\"Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, W...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Transactions on Machine Learning Research\\\"}, {\\\"key\\\": \\\"paraphrase_evades\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\\\", \\\"authors\\\": \\\"Krishna, Kalpesh and Song, Yixiao and Karpinska, Marzena and Wieting, John and I...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"detection_possibilities\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Position: On the Possibilities of AI-Generated Text Detection\\\", \\\"authors\\\": \\\"Chakraborty, Souradip and Bedi, Amrit Singh and Zhu, Sicheng and An, Bang and Ma...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"grover\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Defending Against Neural Fake News\\\", \\\"authors\\\": \\\"Zellers, Rowan and Holtzman, Ari and Rashkin, Hannah and Bisk, Yonatan and Farha...\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"release_strategies\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Release Strategies and the Social Impacts of Language Models\\\", \\\"authors\\\": \\\"Solaiman, Irene and Brundage, Miles and Clark, Jack and Askell, Amanda and Herbe...\\\", \\\"year\\\": \\\"2019\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:1908.09203\\\"}, {\\\"key\\\": \\\"beyond_binary\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\\\", \\\"authors\\\": \\\"Cheng, Zihao and Zhou, Li and Jiang, Feng and Wang, Benyou and Li, Haizhou\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the ACM Web Conference\\\"}, {\\\"key\\\": \\\"semeval2024_task8\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"authors\\\": \\\"Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Workshop on Semantic Evaluation\\\"}, {\\\"key\\\": \\\"abburi_multifaceted\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\\\", \\\"authors\\\": \\\"Abburi, Harika and Bhattacharya, Sanmitra and Bowen, Edward and Pudota, Nirmala\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2505.11550\\\"}, {\\\"key\\\": \\\"defactify_dataset\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Comprehensive Dataset for Human vs.\\\\\\\\ AI Generated Text Detection\\\", \\\"authors\\\": \\\"Roy, Rajarshi and Imanpour, Nasrin and Aziz, Ashhar and Bajpai, Shashwat and Sin...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2510.22874\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"authors\\\": \\\"Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahme...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"authors\\\": \\\"Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Nature\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"authors\\\": \\\"Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"model_collapse_avoidable\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"authors\\\": \\\"Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafae...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the First Conference on Language Modeling (COLM)\\\"}, {\\\"key\\\": \\\"self_rewarding_lms\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Self-Rewarding Language Models\\\", \\\"authors\\\": \\\"Yuan, Weizhe and Pang, Richard Yuanzhe and Cho, Kyunghyun and Sukhbaatar, Sainba...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2401.10020\\\"}, {\\\"key\\\": \\\"spin\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"authors\\\": \\\"Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the 41st International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"qlora\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"QLoRA: Efficient Finetuning of Quantized Language Models\\\", \\\"authors\\\": \\\"Dettmers, Tim and Pagnoni, Artidoro and Holtzman, Ari and Zettlemoyer, Luke\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"authors\\\": \\\"Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Advances in Neural Information Processing Systems\\\"}, {\\\"key\\\": \\\"qurating\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"authors\\\": \\\"Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"authors\\\": \\\"Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vis...\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the Language Resources and Evaluation Conference\\\"}, {\\\"key\\\": \\\"watermark_llm\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"authors\\\": \\\"Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Mier...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"synthid_text\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Scalable Watermarking for Identifying Large Language Model Outputs\\\", \\\"authors\\\": \\\"Dathathri, Sumanth and See, Abigail and Ghaisas, Sumedh and Huang, Po-Sen and Mc...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Nature\\\"}, {\\\"key\\\": \\\"aaronson_watermark\\\", \\\"type\\\": \\\"misc\\\", \\\"title\\\": \\\"Watermarking GPT Outputs\\\", \\\"authors\\\": \\\"Aaronson, Scott and Kirchner, Hendrik\\\", \\\"year\\\": \\\"2022\\\", \\\"venue\\\": \\\"\\\"}, {\\\"key\\\": \\\"chainwash\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\\\", \\\"authors\\\": \\\"Ameen, Mohd Ruhul and Islam, Akif and Mahmud, Nadim and Hamid, Md. Ekramul\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2605.05503\\\"}, {\\\"key\\\": \\\"curious_decline\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"authors\\\": \\\"Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\\\\\\\'e\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Findings of the Association for Computational Linguistics: NAACL\\\"}, {\\\"key\\\": \\\"writing_diversity\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"authors\\\": \\\"Padmakumar, Vishakh and He, He\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"nucleus_sampling\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"authors\\\": \\\"Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"stamatatos_survey\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Survey of Modern Authorship Attribution Methods\\\", \\\"authors\\\": \\\"Stamatatos, Efstathios\\\", \\\"year\\\": \\\"2009\\\", \\\"venue\\\": \\\"Journal of the American Society for Information Science and Technology\\\"}, {\\\"key\\\": \\\"koppel_authorship\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Computational Methods in Authorship Attribution\\\", \\\"authors\\\": \\\"Koppel, Moshe and Schler, Jonathan and Argamon, Shlomo\\\", \\\"year\\\": \\\"2009\\\", \\\"venue\\\": \\\"Journal of the American Society for Information Science and Technology\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"authors\\\": \\\"Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the Conference on Empirical Methods in Natural Language Processin...\\\"}, {\\\"key\\\": \\\"munir_looking_glass\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\\\", \\\"authors\\\": \\\"Munir, Shaoor and Batool, Brishna and Shafiq, Zubair and Srinivasan, Padmini and...\\\", \\\"year\\\": \\\"2021\\\", \\\"venue\\\": \\\"Proceedings of the Conference of the European Chapter of the Association for Com...\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"authors\\\": \\\"Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"attractor_cycles\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\\\", \\\"authors\\\": \\\"Wang, Yibo and Wu, Congying and Li, Yanan and Cai, Yi\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Markovian Generation Chains in Large Language Models\\\", \\\"authors\\\": \\\"Geng, Mingmeng and Mohamed, Amr and Shang, Guokan and Vazirgiannis, Michalis and...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2603.11228\\\"}, {\\\"key\\\": \\\"min_k_percent\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"authors\\\": \\\"Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Da...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Learning Representations\\\"}, {\\\"key\\\": \\\"wu_survey_2025\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"authors\\\": \\\"Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam a...\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"Computational Linguistics\\\"}, {\\\"key\\\": \\\"jawahar_survey\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Automatic Detection of Machine Generated Text: A Critical Survey\\\", \\\"authors\\\": \\\"Jawahar, Ganesh and Abdul-Mageed, Muhammad and Lakshmanan, Laks V.S.\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Computational Linguistics\\\"}, {\\\"key\\\": \\\"pythia\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\\\", \\\"authors\\\": \\\"Biderman, Stella and Schoelkopf, Hailey and Anthony, Quentin Gregory and Bradley...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Proceedings of the International Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"olmo\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"OLMo: Accelerating the Science of Language Models\\\", \\\"authors\\\": \\\"Groeneveld, Dirk and Beltagy, Iz and Walsh, Evan and Bhagia, Akshita and Kinney,...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"qwen3\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Qwen3 Technical Report\\\", \\\"authors\\\": \\\"Qwen Team\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2505.09388\\\"}, {\\\"key\\\": \\\"ghostbuster\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"authors\\\": \\\"Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Jurafsky, Dan\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"Proceedings of the Annual Meeting of the Association for Computational Linguisti...\\\"}, {\\\"key\\\": \\\"two_birds\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\\\", \\\"authors\\\": \\\"Rao, Harika and Vashistha, Adaku Jane and Jain, Aaryan and Garg, Naman\\\", \\\"year\\\": \\\"2025\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2508.14190\\\"}, {\\\"key\\\": \\\"beyond_final_actor\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\\\", \\\"authors\\\": \\\"Li, Ziang and Gao, Guan-Yu and Yang, Songlin and Yu, Ning and Fritz, Mario and M...\\\", \\\"year\\\": \\\"2026\\\", \\\"venue\\\": \\\"Proceedings of the Association for Computational Linguistics\\\"}, {\\\"key\\\": \\\"gutierrez_ordinal_survey\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"authors\\\": \\\"Guti\\\\\\\\'errez, Pedro Antonio and P\\\\\\\\'erez-Ortiz, Mar\\\\\\\\'ia and S\\\\\\\\'anchez-Monedero, Ja...\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"IEEE Transactions on Knowledge and Data Engineering\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"authors\\\": \\\"Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian\\\", \\\"year\\\": \\\"2020\\\", \\\"venue\\\": \\\"Pattern Recognition Letters\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"authors\\\": \\\"Frank, Eibe and Hall, Mark\\\", \\\"year\\\": \\\"2001\\\", \\\"venue\\\": \\\"Proceedings of the European Conference on Machine Learning\\\"}, {\\\"key\\\": \\\"pang_opinion_mining\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\\\", \\\"authors\\\": \\\"Pang, Bo and Lee, Lillian\\\", \\\"year\\\": \\\"2005\\\", \\\"venue\\\": \\\"Proceedings of the 43rd Annual Meeting of the Association for Computational Ling...\\\"}, {\\\"key\\\": \\\"taghipour_neural_essay\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"A Neural Approach to Automated Essay Scoring\\\", \\\"authors\\\": \\\"Taghipour, Kaveh and Ng, Hwee Tou\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"Proceedings of the 2016 Conference on Empirical Methods in Natural Language Proc...\\\"}, {\\\"key\\\": \\\"corn_ordinal\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\\\", \\\"authors\\\": \\\"Shi, Xintong and Cao, Wenzhi and Raschka, Sebastian\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"Pattern Analysis and Applications\\\"}, {\\\"key\\\": \\\"xgboost\\\", \\\"type\\\": \\\"inproceedings\\\", \\\"title\\\": \\\"XGBoost: A Scalable Tree Boosting System\\\", \\\"authors\\\": \\\"Chen, Tianqi and Guestrin, Carlos\\\", \\\"year\\\": \\\"2016\\\", \\\"venue\\\": \\\"Proceedings of the ACM SIGKDD International Conference on Knowledge Discovery an...\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\\\", \\\"authors\\\": \\\"Lakens, Dani\\\\\\\\\\\\\\\"el\\\", \\\"year\\\": \\\"2017\\\", \\\"venue\\\": \\\"Social Psychological and Personality Science\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"authors\\\": \\\"Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav ...\\\", \\\"year\\\": \\\"2024\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2407.21783\\\"}, {\\\"key\\\": \\\"mistral7b\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Mistral 7B\\\", \\\"authors\\\": \\\"Jiang, Albert Q. and Sablayrolles, Alexandre and Mensch, Arthur and Bamford, Chr...\\\", \\\"year\\\": \\\"2023\\\", \\\"venue\\\": \\\"arXiv preprint arXiv:2310.06825\\\"}, {\\\"key\\\": \\\"strobl_conditional_2008\\\", \\\"type\\\": \\\"article\\\", \\\"title\\\": \\\"Conditional Variable Importance for Random Forests\\\", \\\"authors\\\": \\\"Strobl, Carolin and Boulesteix, Anne-Laure and Kneib, Thomas and Augustin, Thoma...\\\", \\\"year\\\": \\\"2008\\\", \\\"venue\\\": \\\"BMC Bioinformatics\\\"}], \\\"tex_citations\\\": [{\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 6, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"file\\\": \\\"introduction.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gltr\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"grover\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"release_strategies\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dna_gpt\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ghostbuster\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"feat_aug_transformer\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"abburi_multifaceted\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"reliable_detection\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 7, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"intrinsic_dimension\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"diveye\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"generator_barrier\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"tang2024science\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"wu_survey_2025\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"jawahar_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 8, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"beyond_binary\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 11, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"two_birds\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"beyond_final_actor\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 12, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"semeval2024_task8\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"defactify_dataset\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 13, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"paraphrase_evades\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 15, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"detection_possibilities\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 15, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"gutierrez_ordinal_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"corn_ordinal\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"pang_opinion_mining\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"taghipour_neural_essay\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 17, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"munir_looking_glass\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 17, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"model_collapse_avoidable\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 23, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"self_rewarding_lms\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 24, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"spin\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 24, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 25, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 25, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 28, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 29, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"attractor_cycles\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 30, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 32, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 32, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curious_decline\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 37, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"writing_diversity\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 37, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"stamatatos_survey\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 38, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"koppel_authorship\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 38, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"neal2017surveying\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 38, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mccarthy2010mtld\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 38, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"covington2010mattr\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 38, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 39, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"nucleus_sampling\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 39, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 44, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qurating\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 44, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 44, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"oren2024proving\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 44, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"golchin2024time\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 44, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"longpre2024data\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 44, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"watermark_llm\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 46, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"synthid_text\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 46, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"aaronson_watermark\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 46, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"chainwash\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 46, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"min_k_percent\\\", \\\"file\\\": \\\"related_work.tex\\\", \\\"line\\\": 47, \\\"command\\\": \\\"citet\\\"}, {\\\"key\\\": \\\"pythia\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"olmo\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qwen3\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"mistral7b\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 16, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"xgboost\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 75, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 77, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"corn_ordinal\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 77, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 77, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 86, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 86, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"file\\\": \\\"method.tex\\\", \\\"line\\\": 86, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"file\\\": \\\"results.tex\\\", \\\"line\\\": 72, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strobl_conditional_2008\\\", \\\"file\\\": \\\"results.tex\\\", \\\"line\\\": 90, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 25, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"file\\\": \\\"discussion.tex\\\", \\\"line\\\": 25, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"qlora\\\", \\\"file\\\": \\\"appendix_qlora.tex\\\", \\\"line\\\": 1, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"file\\\": \\\"appendix_classifier.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"file\\\": \\\"appendix_classifier.tex\\\", \\\"line\\\": 31, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"file\\\": \\\"appendix_downstream.tex\\\", \\\"line\\\": 41, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"file\\\": \\\"appendix_tost.tex\\\", \\\"line\\\": 4, \\\"command\\\": \\\"cite\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"file\\\": \\\"appendix_tost.tex\\\", \\\"line\\\": 5, \\\"command\\\": \\\"cite\\\"}], \\\"online_verification\\\": [{\\\"key\\\": \\\"mccarthy2010mtld\\\", \\\"title\\\": \\\"MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"MTLD, vocd-D, and HD-D: A validation study of sophisticated approaches to lexical diversity assessment\\\", \\\"matched_year\\\": \\\"2010\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"covington2010mattr\\\", \\\"title\\\": \\\"Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.986, \\\"matched_title\\\": \\\"Cutting the Gordian Knot: The Moving-Average Type–Token Ratio (MATTR)\\\", \\\"matched_year\\\": \\\"2010\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"oren2024proving\\\", \\\"title\\\": \\\"Proving Test Set Contamination in Black Box Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Proving Test Set Contamination in Black Box Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"golchin2024time\\\", \\\"title\\\": \\\"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Time Travel in LLMs: Tracing Data Contamination in Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"longpre2024data\\\", \\\"title\\\": \\\"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"cohen1988statistical\\\", \\\"title\\\": \\\"Statistical Power Analysis for the Behavioral Sciences\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Statistical Power Analysis for the Behavioral Sciences\\\", \\\"matched_year\\\": \\\"1989\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=cohen vs api=muller\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"tang2024science\\\", \\\"title\\\": \\\"The Science of Detecting LLM-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Science of Detecting LLM-Generated Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"neal2017surveying\\\", \\\"title\\\": \\\"Surveying Stylometry Techniques and Applications\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Surveying Stylometry Techniques and Applications\\\", \\\"matched_year\\\": \\\"2017\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"detectgpt\\\", \\\"title\\\": \\\"DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.382, \\\"matched_title\\\": \\\"Regulating ChatGPT and other Large Generative AI Models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.38 below threshold 0.82\\\"}, {\\\"key\\\": \\\"gltr\\\", \\\"title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"GLTR: Statistical Detection and Visualization of Generated Text\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dna_gpt\\\", \\\"title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"binoculars\\\", \\\"title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"fast_detectgpt\\\", \\\"title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"ld_score\\\", \\\"title\\\": \\\"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"intrinsic_dimension\\\", \\\"title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"diveye\\\", \\\"title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Diversity Boosts AI-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"generator_barrier\\\", \\\"title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"feat_aug_transformer\\\", \\\"title\\\": \\\"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"reliable_detection\\\", \\\"title\\\": \\\"Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.344, \\\"matched_title\\\": \\\"2015 ESC Guidelines for the management of acute coronary syndromes in patients presenting without persistent ST-segment elevation\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.34 below threshold 0.82\\\"}, {\\\"key\\\": \\\"paraphrase_evades\\\", \\\"title\\\": \\\"Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Paraphrasing evades detectors of AI-generated text, but retrieval is an effective defense\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"detection_possibilities\\\", \\\"title\\\": \\\"Position: On the Possibilities of AI-Generated Text Detection\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.253, \\\"matched_title\\\": \\\"Review of deep learning: concepts, CNN architectures, challenges, applications, future directions\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.25 below threshold 0.82\\\"}, {\\\"key\\\": \\\"grover\\\", \\\"title\\\": \\\"Defending Against Neural Fake News\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Defending Against Neural Fake News\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"release_strategies\\\", \\\"title\\\": \\\"Release Strategies and the Social Impacts of Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Release Strategies and the Social Impacts of Language Models\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"beyond_binary\\\", \\\"title\\\": \\\"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"semeval2024_task8\\\", \\\"title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"abburi_multifaceted\\\", \\\"title\\\": \\\"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"defactify_dataset\\\", \\\"title\\\": \\\"A Comprehensive Dataset for Human vs.\\\\\\\\ AI Generated Text Detection\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.355, \\\"matched_title\\\": \\\"Performance of ChatGPT on USMLE: Potential for AI-assisted medical education using large language models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.36 below threshold 0.82\\\"}, {\\\"key\\\": \\\"self_consuming_mad\\\", \\\"title\\\": \\\"Self-Consuming Generative Models Go MAD\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Consuming Generative Models go MAD\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=alemohammad vs api=casco-rodriguez\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"curse_of_recursion\\\", \\\"title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"AI models collapse when trained on recursively generated data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"strong_model_collapse\\\", \\\"title\\\": \\\"Strong Model Collapse\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Strong Model Collapse\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"model_collapse_avoidable\\\", \\\"title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"self_rewarding_lms\\\", \\\"title\\\": \\\"Self-Rewarding Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Rewarding Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"spin\\\", \\\"title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qlora\\\", \\\"title\\\": \\\"QLoRA: Efficient Finetuning of Quantized Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.871, \\\"matched_title\\\": \\\"QLoRA: Efficient Finetuning of Quantized LLMs\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"dsir\\\", \\\"title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Data Selection for Language Models via Importance Resampling\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qurating\\\", \\\"title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"QuRating: Selecting High-Quality Data for Training Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"ccnet\\\", \\\"title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"watermark_llm\\\", \\\"title\\\": \\\"A Watermark for Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Watermark for Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"synthid_text\\\", \\\"title\\\": \\\"Scalable Watermarking for Identifying Large Language Model Outputs\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Scalable watermarking for identifying large language model outputs\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"aaronson_watermark\\\", \\\"title\\\": \\\"Watermarking GPT Outputs\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.418, \\\"matched_title\\\": \\\"Undetectable Watermarks for Language Models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.42 below threshold 0.82\\\"}, {\\\"key\\\": \\\"chainwash\\\", \\\"title\\\": \\\"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"curious_decline\\\", \\\"title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"writing_diversity\\\", \\\"title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Does Writing with Language Models Reduce Content Diversity?\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"nucleus_sampling\\\", \\\"title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Curious Case of Neural Text Degeneration\\\", \\\"matched_year\\\": \\\"2019\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"stamatatos_survey\\\", \\\"title\\\": \\\"A Survey of Modern Authorship Attribution Methods\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A survey of modern authorship attribution methods\\\", \\\"matched_year\\\": \\\"2008\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"koppel_authorship\\\", \\\"title\\\": \\\"Computational Methods in Authorship Attribution\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Computational methods in authorship attribution\\\", \\\"matched_year\\\": \\\"2008\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"uchendu_attribution\\\", \\\"title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Authorship Attribution for Neural Text Generation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"munir_looking_glass\\\", \\\"title\\\": \\\"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models\\\", \\\"matched_year\\\": \\\"2021\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"broken_telephone\\\", \\\"title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"LLM as a Broken Telephone: Iterative Generation Distorts Information\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"attractor_cycles\\\", \\\"title\\\": \\\"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"markovian_chains\\\", \\\"title\\\": \\\"Markovian Generation Chains in Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Markovian Generation Chains in Large Language Models\\\", \\\"matched_year\\\": \\\"2026\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"min_k_percent\\\", \\\"title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Detecting Pretraining Data from Large Language Models\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"wu_survey_2025\\\", \\\"title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"jawahar_survey\\\", \\\"title\\\": \\\"Automatic Detection of Machine Generated Text: A Critical Survey\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Automatic Detection of Machine Generated Text: A Critical Survey\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pythia\\\", \\\"title\\\": \\\"Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.497, \\\"matched_title\\\": \\\"The TRIPOD-LLM reporting guideline for studies using large language models\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.50 below threshold 0.82\\\"}, {\\\"key\\\": \\\"olmo\\\", \\\"title\\\": \\\"OLMo: Accelerating the Science of Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"OLMo: Accelerating the Science of Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"qwen3\\\", \\\"title\\\": \\\"Qwen3 Technical Report\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Qwen3 Technical Report\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=team vs api=yang\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"ghostbuster\\\", \\\"title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Ghostbuster: Detecting Text Ghostwritten by Large Language Models\\\", \\\"matched_year\\\": \\\"2024\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"two_birds\\\", \\\"title\\\": \\\"Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.32, \\\"matched_title\\\": \\\"Large AI Models in Health Informatics: Applications, Challenges, and the Future\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.32 below threshold 0.82\\\"}, {\\\"key\\\": \\\"beyond_final_actor\\\", \\\"title\\\": \\\"Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.722, \\\"matched_title\\\": \\\"Beyond the Final Actor: Modeling the Dual Roles of Creator and Editor for Fine-Grained LLM-Generated Text Detection\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.72 below threshold 0.82\\\"}, {\\\"key\\\": \\\"gutierrez_ordinal_survey\\\", \\\"title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Ordinal Regression Methods: Survey and Experimental Study\\\", \\\"matched_year\\\": \\\"2015\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=guti\\\\\\\\'errez vs api=gutiérrez\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"coral_ordinal\\\", \\\"title\\\": \\\"Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Rank consistent ordinal regression for neural networks with application to age estimation\\\", \\\"matched_year\\\": \\\"2020\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"frank_hall_ordinal\\\", \\\"title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Simple Approach to Ordinal Classification\\\", \\\"matched_year\\\": \\\"2001\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"pang_opinion_mining\\\", \\\"title\\\": \\\"Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Seeing stars: Exploiting class relationships for sentiment categorization with respect to rating scales\\\", \\\"matched_year\\\": \\\"2005\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"taghipour_neural_essay\\\", \\\"title\\\": \\\"A Neural Approach to Automated Essay Scoring\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"A Neural Approach to Automated Essay Scoring\\\", \\\"matched_year\\\": \\\"2016\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"corn_ordinal\\\", \\\"title\\\": \\\"Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Deep neural networks for rank-consistent ordinal regression based on conditional probabilities\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"xgboost\\\", \\\"title\\\": \\\"XGBoost: A Scalable Tree Boosting System\\\", \\\"status\\\": \\\"not_found\\\", \\\"confidence\\\": 0.298, \\\"matched_title\\\": \\\"XGBoost\\\", \\\"matched_year\\\": \\\"\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"best match similarity 0.30 below threshold 0.82\\\"}, {\\\"key\\\": \\\"lakens_equivalence\\\", \\\"title\\\": \\\"Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 0.976, \\\"matched_title\\\": \\\"Equivalence Tests: A Practical Primer for t-Tests, Correlations, and Meta-Analyses\\\", \\\"matched_year\\\": \\\"2016\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"llama3\\\", \\\"title\\\": \\\"The Llama 3 Herd of Models\\\", \\\"status\\\": \\\"mismatch\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"The Llama 3 herd of models\\\", \\\"matched_year\\\": \\\"2025\\\", \\\"mismatch_fields\\\": [\\\"first_author: bib=grattafiori vs api=aaron\\\"], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"mistral7b\\\", \\\"title\\\": \\\"Mistral 7B\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Mistral 7B\\\", \\\"matched_year\\\": \\\"2023\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}, {\\\"key\\\": \\\"strobl_conditional_2008\\\", \\\"title\\\": \\\"Conditional Variable Importance for Random Forests\\\", \\\"status\\\": \\\"verified\\\", \\\"confidence\\\": 1.0, \\\"matched_title\\\": \\\"Conditional variable importance for random forests\\\", \\\"matched_year\\\": \\\"2008\\\", \\\"mismatch_fields\\\": [], \\\"note\\\": \\\"\\\"}]}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
      "numLines": 1,
      "startLine": 1,
      "totalLines": 1
    }
  },
  "sourceToolAssistantUUID": "1c589184-d4d7-42a2-8274-27bea1f9b6bc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 61 · 2026-05-19T06:17:53.135Z_

<details open><summary>🔧 Tool call — Read · `toolu_01QUEckvksbaDsgwtwwQuEV4`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6857f36b-df70-4ffa-b833-8e673fe4b47f",
  "isSidechain": false,
  "requestId": "req_011CbBSUqMHxxg2eutzmeLDY",
  "type": "assistant",
  "uuid": "e039405a-7c68-40d5-9f07-2c13066c25c0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AgX2GiE4EAhfet6wZiP3LX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 14892,
      "cache_creation_input_tokens": 5020,
      "cache_read_input_tokens": 31700,
      "output_tokens": 574,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5020,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 14892,
          "output_tokens": 574,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 5020,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5020
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "previous_message_not_found"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 62 · 2026-05-19T06:17:53.140Z_

<details><summary>↩ Tool result · `toolu_01QUEckvksbaDsgwtwwQuEV4`</summary>

```text
1	% ===== Lexical Richness =====
2	
3	@article{mccarthy2010mtld,
4	  title = {{MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment}},
5	  author = {McCarthy, Philip M. and Jarvis, Scott},
6	  journal = {Behavior Research Methods},
7	  volume = {42},
8	  number = {2},
9	  pages = {381--392},
10	  year = {2010},
11	}
12	
13	@article{covington2010mattr,
14	  title = {{Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)}},
15	  author = {Covington, Michael A. and McFall, Joe D.},
16	  journal = {Journal of Quantitative Linguistics},
17	  volume = {17},
18	  number = {2},
19	  pages = {94--100},
20	  year = {2010},
21	}
22	
23	% ===== Data Provenance / Contamination =====
24	
25	@inproceedings{oren2024proving,
26	  title = {{Proving Test Set Contamination in Black Box Language Models}},
27	  author = {Oren, Yonatan and Meister, Nicole and Chatterji, Niladri and Laber, Faisal and Stern, Avi},
28	  booktitle = {Proceedings of the International Conference on Learning Representations},
29	  year = {2024},
30	}
31	
32	@inproceedings{golchin2024time,
33	  title = {{Time Travel in LLMs: Tracing Data Contamination in Large Language Models}},
34	  author = {Golchin, Shahriar and Surdeanu, Mihai},
35	  booktitle = {Proceedings of the International Conference on Learning Representations},
36	  year = {2024},
37	}
38	
39	@inproceedings{longpre2024data,
40	  title = {{Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?}},
41	  author = {Longpre, Shayne and Mahari, Robert and Lee, Naana and Luccioni, Sasha and Jernite, Yacine and others},
42	  booktitle = {Proceedings of the International Conference on Machine Learning},
43	  year = {2024},
44	}
45	
46	% ===== Statistics =====
47	
48	@book{cohen1988statistical,
49	  title = {{Statistical Power Analysis for the Behavioral Sciences}},
50	  author = {Cohen, Jacob},
51	  edition = {2nd},
52	  publisher = {Lawrence Erlbaum Associates},
53	  year = {1988},
54	}
55	
56	@article{tang2024science,
57	  title = {{The Science of Detecting LLM-Generated Text}},
58	  author = {Tang, Ruixiang and Chuang, Yu-Neng and Hu, Xia},
59	  journal = {Communications of the ACM},
60	  volume = {67},
61	  number = {4},
62	  pages = {50--59},
63	  year = {2024},
64	}
65	
66	@article{neal2017surveying,
67	  title = {{Surveying Stylometry Techniques and Applications}},
68	  author = {Neal, Tempestt and Sundararajan, Kalaivani and Fatima, Aneez and Yan, Yiming and Xiang, Yingfei and Woodard, Damon L.},
69	  journal = {ACM Computing Surveys},
70	  volume = {50},
71	  number = {6},
72	  pages = {1--36},
73	  year = {2017},
74	}
75	
76	% ===== Detection =====
77	
78	@inproceedings{detectgpt,
79	  title = {{DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature}},
80	  author = {Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher D. and Finn, Chelsea},
81	  booktitle = {Proceedings of the International Conference on Machine Learning},
82	  year = {2023},
83	}
84	
85	@inproceedings{gltr,
86	  title = {{GLTR: Statistical Detection and Visualization of Generated Text}},
87	  author = {Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.},
88	  booktitle = {Proceedings of the Annual Meeting of the Association for Computational Linguistics: System Demonstrations},
89	  year = {2019},
90	}
91	
92	@inproceedings{dna_gpt,
93	  title = {{DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text}},
94	  author = {Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Yang and Chen, Haifeng},
95	  booktitle = {Proceedings of the International Conference on Learning Representations},
96	  year = {2024},
97	}
98	
99	@inproceedings{binoculars,
100	  title = {{Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text}},
101	  author = {Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Hamid and Saha, Aniruddha and Goldblum, Micah and Geiping, Jonas and Goldstein, Tom},
102	  booktitle = {Proceedings of the International Conference on Machine Learning},
103	  year = {2024},
104	}
105	
106	@inproceedings{fast_detectgpt,
107	  title = {{Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature}},
108	  author = {Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yue},
109	  booktitle = {Proceedings of the International Conference on Learning Representations},
110	  year = {2024},
111	}
112	
113	@article{ld_score,
114	  title = {{Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection}},
115	  author = {Narayanasamy, Priyadarshan and Agrawal, Swastik and Faber, Klint and Alam, Fardina Fathmiul},
116	  journal = {arXiv preprint arXiv:2605.01647},
117	  year = {2026},
118	}
119	
120	@inproceedings{intrinsic_dimension,
121	  title = {{Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts}},
122	  author = {Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavskii, Daniil and Nikolenko, Sergey and Burnaev, Evgeny and Barannikov, Serguei and Piontkovskaya, Irina},
123	  booktitle = {Advances in Neural Information Processing Systems},
124	  year = {2023},
125	}
126	
127	@article{diveye,
128	  title = {{Diversity Boosts AI-Generated Text Detection}},
129	  author = {Basani, Advik Raj and Chen, Pin-Yu},
130	  journal = {Transactions on Machine Learning Research},
131	  year = {2026},
132	}
133	
134	@article{generator_barrier,
135	  title = {{Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection}},
136	  author = {Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli},
137	  journal = {arXiv preprint arXiv:2604.13692},
138	  year = {2026},
139	}
140	
141	@article{feat_aug_transformer,
142	  title = {{Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators}},
143	  author = {Mady, Mohamed and Reschke, Johannes and Schuller, Bj{\"o}rn},
144	  journal = {arXiv preprint arXiv:2605.03969},
145	  year = {2026},
146	}
147	
148	@article{reliable_detection,
149	  title = {{Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks}},
150	  author = {Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, Wenxiao and Feizi, Soheil},
151	  journal = {Transactions on Machine Learning Research},
152	  year = {2025},
153	  url = {https://openreview.net/forum?id=OOgsAZdFOt},
154	}
155	
156	@inproceedings{paraphrase_evades,
157	  title = {{Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense}},
158	  author = {Krishna, Kalpesh and Song, Yixiao and Karpinska, Marzena and Wieting, John and Iyyer, Mohit},
159	  booktitle = {Advances in Neural Information Processing Systems},
160	  year = {2023},
161	}
162	
163	@inproceedings{detection_possibilities,
164	  title = {{Position: On the Possibilities of AI-Generated Text Detection}},
165	  author = {Chakraborty, Souradip and Bedi, Amrit Singh and Zhu, Sicheng and An, Bang and Manocha, Dinesh and Huang, Furong},
166	  booktitle = {Proceedings of the International Conference on Machine Learning},
167	  year = {2024},
168	}
169	
170	@inproceedings{grover,
171	  title = {{Defending Against Neural Fake News}},
172	  author = {Zellers, Rowan and Holtzman, Ari and Rashkin, Hannah and Bisk, Yonatan and Farhadi, Ali and Roesner, Franziska and Choi, Yejin},
173	  booktitle = {Advances in Neural Information Processing Systems},
174	  year = {2019},
175	}
176	
177	@article{release_strategies,
178	  title = {{Release Strategies and the Social Impacts of Language Models}},
179	  author = {Solaiman, Irene and Brundage, Miles and Clark, Jack and Askell, Amanda and Herbert-Voss, Ariel and Wu, Jeff and Radford, Alec and Krueger, Gretchen and Kim, Jong Wook and Kreps, Sarah and McCain, Miles and Newhouse, Alex and Blazakis, Jason and McGuffie, Kris and Wang, Jasmine},
180	  journal = {arXiv preprint arXiv:1908.09203},
181	  year = {2019},
182	}
183	
184	@inproceedings{beyond_binary,
185	  title = {{Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement}},
186	  author = {Cheng, Zihao and Zhou, Li and Jiang, Feng and Wang, Benyou and Li, Haizhou},
187	  booktitle = {Proceedings of the ACM Web Conference},
188	  year = {2025},
189	}
190	
191	@inproceedings{semeval2024_task8,
192	  title = {{SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection}},
193	  author = {Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov, Artem and Tsvigun, Akim and Afzal, Osama Mohammed and Mahmoud, Tarek and Puccetti, Giovanni and Arnold, Thomas and Whitehouse, Chenxi and Aji, Alham Fikri and Habash, Nizar and Gurevych, Iryna and Nakov, Preslav},
194	  booktitle = {Proceedings of the International Workshop on Semantic Evaluation},
195	  year = {2024},
196	}
197	
198	@article{abburi_multifaceted,
199	  title = {{AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification}},
200	  author = {Abburi, Harika and Bhattacharya, Sanmitra and Bowen, Edward and Pudota, Nirmala},
201	  journal = {arXiv preprint arXiv:2505.11550},
202	  year = {2025},
203	}
204	
205	@article{defactify_dataset,
206	  title = {{A Comprehensive Dataset for Human vs.\ AI Generated Text Detection}},
207	  author = {Roy, Rajarshi and Imanpour, Nasrin and Aziz, Ashhar and Bajpai, Shashwat and Singh, Gurpreet and Biswas, Shwetangshu and Wanaskar, Kapil and Patwa, Parth and Ghosh, Subhankar and Dixit, Shreyas and Pal, Nilesh Ranjan and Rawte, Vipula and Garimella, Ritvik and Jena, Gaytri and Sheth, Amit and Sharma, Vasu and Reganti, Aishwarya Naresh and Jain, Vinija and Chadha, Aman and Das, Amitava},
208	  journal = {arXiv preprint arXiv:2510.22874},
209	  year = {2025},
210	}
211	
212	% ===== Model Collapse =====
213	
214	@inproceedings{self_consuming_mad,
215	  title = {{Self-Consuming Generative Models Go MAD}},
216	  author = {Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahmed Imtiaz and Babaei, Hossein and LeJeune, Daniel and Siahkoohi, Ali and Baraniuk, Richard G.},
217	  booktitle = {Proceedings of the International Conference on Learning Representations},
218	  year = {2024},
219	}
220	
221	@article{curse_of_recursion,
222	  title = {{AI models collapse when trained on recursively generated data}},
223	  author = {Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and Anderson, Ross and Gal, Yarin},
224	  journal = {Nature},
225	  volume = {631},
226	  pages = {755--759},
227	  year = {2024},
228	}
229	
230	@inproceedings{strong_model_collapse,
231	  title = {{Strong Model Collapse}},
232	  author = {Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia},
233	  booktitle = {Proceedings of the International Conference on Learning Representations},
234	  year = {2025},
235	}
236	
237	@inproceedings{model_collapse_avoidable,
238	  title = {{Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data}},
239	  author = {Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafael and Sleight, Henry and Hughes, John and Korbak, Tomasz and Agrawal, Rajashree and Pai, Dhruv and Gromov, Andrey and Roberts, Daniel A. and Yang, Diyi and Donoho, David L. and Koyejo, Sanmi},
240	  booktitle = {Proceedings of the First Conference on Language Modeling (COLM)},
241	  year = {2024},
242	}
243	
244	% ===== Self-Training / Self-Play =====
245	
246	@article{self_rewarding_lms,
247	  title = {{Self-Rewarding Language Models}},
248	  author = {Yuan, Weizhe and Pang, Richard Yuanzhe and Cho, Kyunghyun and Sukhbaatar, Sainbayar and Xu, Jing and Weston, Jason},
249	  journal = {arXiv preprint arXiv:2401.10020},
250	  year = {2024},
251	}
252	
253	@inproceedings{spin,
254	  title = {{Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models}},
255	  author = {Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan},
256	  booktitle = {Proceedings of the 41st International Conference on Machine Learning},
257	  year = {2024},
258	}
259	
260	% ===== Fine-tuning =====
261	
262	@inproceedings{qlora,
263	  title = {{QLoRA: Efficient Finetuning of Quantized Language Models}},
264	  author = {Dettmers, Tim and Pagnoni, Artidoro and Holtzman, Ari and Zettlemoyer, Luke},
265	  booktitle = {Advances in Neural Information Processing Systems},
266	  year = {2023},
267	}
268	
269	% ===== Data Quality =====
270	
271	% ===== (orphan entries removed: fineweb, dolma) =====
272	
273	@inproceedings{dsir,
274	  title = {{Data Selection for Language Models via Importance Resampling}},
275	  author = {Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy},
276	  booktitle = {Advances in Neural Information Processing Systems},
277	  year = {2023},
278	}
279	
280	@inproceedings{qurating,
281	  title = {{QuRating: Selecting High-Quality Data for Training Language Models}},
282	  author = {Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi},
283	  booktitle = {Proceedings of the International Conference on Machine Learning},
284	  year = {2024},
285	}
286	
287	@inproceedings{ccnet,
288	  title = {{CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data}},
289	  author = {Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vishrav and Guzm{\'a}n, Francisco and Joulin, Armand and Grave, Edouard},
290	  booktitle = {Proceedings of the Language Resources and Evaluation Conference},
291	  year = {2020},
292	}
293	
294	% ===== Watermarking =====
295	
296	@inproceedings{watermark_llm,
297	  title = {{A Watermark for Large Language Models}},
298	  author = {Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Miers, Ian and Goldstein, Tom},
299	  booktitle = {Proceedings of the International Conference on Machine Learning},
300	  year = {2023},
301	}
302	
303	@article{synthid_text,
304	  title = {{Scalable Watermarking for Identifying Large Language Model Outputs}},
305	  author = {Dathathri, Sumanth and See, Abigail and Ghaisas, Sumedh and Huang, Po-Sen and McAdam, Rob and Welbl, Johannes and Bachani, Vandana and Kaskasoli, Alex and Stanforth, Robert and Matejovicova, Tatiana and Hayes, Jamie and Vyas, Nidhi and Al Merey, Majd and Brown-Cohen, Jonah and Bunel, Rudy and Balle, Borja and Cemgil, Taylan and Ahmed, Zahra and Stacpoole, Kitty and Shumailov, Ilia and Baetu, Ciprian and Gowal, Sven and Hassabis, Demis and Kohli, Pushmeet},
306	  journal = {Nature},
307	  volume = {634},
308	  pages = {818--823},
309	  year = {2024},
310	}
311	
312	@misc{aaronson_watermark,
313	  title = {{Watermarking GPT Outputs}},
314	  author = {Aaronson, Scott and Kirchner, Hendrik},
315	  year = {2022},
316	  howpublished = {Technical Talk},
317	  url = {https://scottaaronson.blog/?p=6823},
318	}
319	
320	@article{chainwash,
321	  title = {{Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks}},
322	  author = {Ameen, Mohd Ruhul and Islam, Akif and Mahmud, Nadim and Hamid, Md. Ekramul},
323	  journal = {arXiv preprint arXiv:2605.05503},
324	  year = {2026},
325	}
326	
327	% ===== Vocabulary Diversity =====
328	
329	@inproceedings{curious_decline,
330	  title = {{The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text}},
331	  author = {Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\'{e}},
332	  booktitle = {Findings of the Association for Computational Linguistics: NAACL},
333	  year = {2024},
334	}
335	
336	@inproceedings{writing_diversity,
337	  title = {{Does Writing with Language Models Reduce Content Diversity?}},
338	  author = {Padmakumar, Vishakh and He, He},
339	  booktitle = {Proceedings of the International Conference on Learning Representations},
340	  year = {2024},
341	}
342	
343	@inproceedings{nucleus_sampling,
344	  title = {{The Curious Case of Neural Text Degeneration}},
345	  author = {Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin},
346	  booktitle = {Proceedings of the International Conference on Learning Representations},
347	  year = {2020},
348	}
349	
350	% ===== Stylometry =====
351	
352	@article{stamatatos_survey,
353	  title = {{A Survey of Modern Authorship Attribution Methods}},
354	  author = {Stamatatos, Efstathios},
355	  journal = {Journal of the American Society for Information Science and Technology},
356	  volume = {60},
357	  number = {3},
358	  pages = {538--556},
359	  year = {2009},
360	}
361	
362	@article{koppel_authorship,
363	  title = {{Computational Methods in Authorship Attribution}},
364	  author = {Koppel, Moshe and Schler, Jonathan and Argamon, Shlomo},
365	  journal = {Journal of the American Society for Information Science and Technology},
366	  volume = {60},
367	  number = {1},
368	  pages = {9--26},
369	  year = {2009},
370	}
371	
372	@inproceedings{uchendu_attribution,
373	  title = {{Authorship Attribution for Neural Text Generation}},
374	  author = {Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon},
375	  booktitle = {Proceedings of the Conference on Empirical Methods in Natural Language Processing},
376	  year = {2020},
377	}
378	
379	@inproceedings{munir_looking_glass,
380	  title = {{Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models}},
381	  author = {Munir, Shaoor and Batool, Brishna and Shafiq, Zubair and Srinivasan, Padmini and Zaffar, Fareed},
382	  booktitle = {Proceedings of the Conference of the European Chapter of the Association for Computational Linguistics},
383	  year = {2021},
384	}
385	
386	% ===== (orphan entries removed: briesch_self_consuming, jovanovic_watermark_stealing, mcgovern_fingerprints) =====
387	
388	% ===== Iterative Generation =====
389	
390	@inproceedings{broken_telephone,
391	  title = {{LLM as a Broken Telephone: Iterative Generation Distorts Information}},
392	  author = {Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan},
393	  booktitle = {Proceedings of the Annual Meeting of the Association for Computational Linguistics},
394	  year = {2025},
395	}
396	
397	@inproceedings{attractor_cycles,
398	  title = {{Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing}},
399	  author = {Wang, Yibo and Wu, Congying and Li, Yanan and Cai, Yi},
400	  booktitle = {Proceedings of the Annual Meeting of the Association for Computational Linguistics},
401	  year = {2025},
402	}
403	
404	@article{markovian_chains,
405	  title = {{Markovian Generation Chains in Large Language Models}},
406	  author = {Geng, Mingmeng and Mohamed, Amr and Shang, Guokan and Vazirgiannis, Michalis and Poibeau, Thierry},
407	  journal = {arXiv preprint arXiv:2603.11228},
408	  year = {2026},
409	}
410	
411	
412	% ===== Membership Inference =====
413	
414	@inproceedings{min_k_percent,
415	  title = {{Detecting Pretraining Data from Large Language Models}},
416	  author = {Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Daogao and Blevins, Terra and Chen, Danqi and Zettlemoyer, Luke},
417	  booktitle = {Proceedings of the International Conference on Learning Representations},
418	  year = {2024},
419	}
420	
421	% ===== Survey =====
422	
423	@article{wu_survey_2025,
424	  title = {{A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions}},
425	  author = {Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam and Wong, Derek Fai},
426	  journal = {Computational Linguistics},
427	  publisher = {MIT Press},
428	  year = {2025},
429	}
430	
431	@inproceedings{jawahar_survey,
432	  title = {{Automatic Detection of Machine Generated Text: A Critical Survey}},
433	  author = {Jawahar, Ganesh and Abdul-Mageed, Muhammad and Lakshmanan, Laks V.S.},
434	  booktitle = {Proceedings of the International Conference on Computational Linguistics},
435	  year = {2020},
436	}
437	
438	% ===== Models =====
439	
440	@inproceedings{pythia,
441	  title = {{Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling}},
442	  author = {Biderman, Stella and Schoelkopf, Hailey and Anthony, Quentin Gregory and Bradley, Herbie and O'Brien, Kyle and Hallahan, Eric and Khan, Mohammad Aflah and Purohit, Shivanshu and Prashanth, USVSN Sai and Raff, Edward and Skowron, Aviya and Sutawika, Lintang and {van der Wal}, Oskar},
443	  booktitle = {Proceedings of the International Conference on Machine Learning},
444	  year = {2023},
445	}
446	
447	@inproceedings{olmo,
448	  title = {{OLMo: Accelerating the Science of Language Models}},
449	  author = {Groeneveld, Dirk and Beltagy, Iz and Walsh, Evan and Bhagia, Akshita and Kinney, Rodney and Tafjord, Oyvind and Jha, Ananya Harsh and Ivison, Hamish and Magnusson, Ian and Wang, Yizhong and Arora, Shane and Atkinson, David and Authur, Russell and Chandu, Khyathi Raghavi and Cohan, Arman and Dumas, Jennifer and Elazar, Yanai and Gu, Yuling and Hessel, Jack and Khot, Tushar and Merrill, William and Morrison, Jacob and Muennighoff, Niklas and Naik, Aakanksha and Nam, Crystal and Peters, Matthew E. and Pyatkin, Valentina and Ravichander, Abhilasha and Schwenk, Dustin and Shah, Saurabh and Smith, Will and Strubell, Emma and Subramani, Nishant and Wortsman, Mitchell and Dasigi, Pradeep and Lambert, Nathan and Richardson, Kyle and Zettlemoyer, Luke and Dodge, Jesse and Lo, Kyle and Soldaini, Luca and Smith, Noah A. and Hajishirzi, Hannaneh},
450	  booktitle = {Proceedings of the Annual Meeting of the Association for Computational Linguistics},
451	  year = {2024},
452	}
453	
454	@article{qwen3,
455	  title = {{Qwen3 Technical Report}},
456	  author = {{Qwen Team}},
457	  journal = {arXiv preprint arXiv:2505.09388},
458	  year = {2025},
459	}
460	
461	@inproceedings{ghostbuster,
462	  title = {{Ghostbuster: Detecting Text Ghostwritten by Large Language Models}},
463	  author = {Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Jurafsky, Dan},
464	  booktitle = {Proceedings of the Annual Meeting of the Association for Computational Linguistics},
465	  year = {2024},
466	}
467	
468	@article{two_birds,
469	  title = {{Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution}},
470	  author = {Rao, Harika and Vashistha, Adaku Jane and Jain, Aaryan and Garg, Naman},
471	  journal = {arXiv preprint arXiv:2508.14190},
472	  year = {2025},
473	}
474	
475	@inproceedings{beyond_final_actor,
476	  title = {{Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection}},
477	  author = {Li, Ziang and Gao, Guan-Yu and Yang, Songlin and Yu, Ning and Fritz, Mario and Metze, Florian},
478	  booktitle = {Proceedings of the Association for Computational Linguistics},
479	  year = {2026},
480	}
481	
482	% ===== Machine Learning =====
483	
484	@article{gutierrez_ordinal_survey,
485	  title = {{Ordinal Regression Methods: Survey and Experimental Study}},
486	  author = {Guti{\'e}rrez, Pedro Antonio and P{\'e}rez-Ortiz, Mar{\'i}a and S{\'a}nchez-Monedero, Javier and Fern{\'a}ndez-Navarro, Francisco and Herv{\'a}s-Mart{\'i}nez, C{\'e}sar},
487	  journal = {IEEE Transactions on Knowledge and Data Engineering},
488	  volume = {28},
489	  number = {1},
490	  pages = {127--146},
491	  year = {2016},
492	}
493	
494	@article{coral_ordinal,
495	  title = {{Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation}},
496	  author = {Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian},
497	  journal = {Pattern Recognition Letters},
498	  volume = {140},
499	  pages = {325--331},
500	  year = {2020},
501	}
502	
503	@inproceedings{frank_hall_ordinal,
504	  title = {{A Simple Approach to Ordinal Classification}},
505	  author = {Frank, Eibe and Hall, Mark},
506	  booktitle = {Proceedings of the European Conference on Machine Learning},
507	  year = {2001},
508	}
509	
510	@inproceedings{pang_opinion_mining,
511	  title = {{Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales}},
512	  author = {Pang, Bo and Lee, Lillian},
513	  booktitle = {Proceedings of the 43rd Annual Meeting of the Association for Computational Linguistics},
514	  pages = {115--124},
515	  year = {2005},
516	}
517	
518	@inproceedings{taghipour_neural_essay,
519	  title = {{A Neural Approach to Automated Essay Scoring}},
520	  author = {Taghipour, Kaveh and Ng, Hwee Tou},
521	  booktitle = {Proceedings of the 2016 Conference on Empirical Methods in Natural Language Processing},
522	  pages = {1882--1891},
523	  year = {2016},
524	}
525	
526	@article{corn_ordinal,
527	  title = {{Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities}},
528	  author = {Shi, Xintong and Cao, Wenzhi and Raschka, Sebastian},
529	  journal = {Pattern Analysis and Applications},
530	  volume = {26},
531	  pages = {941--955},
532	  year = {2023},
533	}
534	
535	@inproceedings{xgboost,
536	  title = {{XGBoost: A Scalable Tree Boosting System}},
537	  author = {Chen, Tianqi and Guestrin, Carlos},
538	  booktitle = {Proceedings of the ACM SIGKDD International Conference on Knowledge Discovery and Data Mining},
539	  year = {2016},
540	}
541	
542	@article{lakens_equivalence,
543	  title = {{Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses}},
544	  author = {Lakens, Dani{\"e}l},
545	  journal = {Social Psychological and Personality Science},
546	  volume = {8},
547	  number = {4},
548	  pages = {355--362},
549	  year = {2017},
550	}
551	
552	% ===== Generator Model References =====
553	
554	@article{llama3,
555	  title = {{The Llama 3 Herd of Models}},
556	  author = {Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav and Kadian, Abhishek and Al-Dahle, Ahmad and Letman, Aiesha and Mathur, Akhil and Schelten, Alan and Yang, Amy and others},
557	  journal = {arXiv preprint arXiv:2407.21783},
558	  year = {2024},
559	}
560	
561	@article{mistral7b,
562	  title = {{Mistral 7B}},
563	  author = {Jiang, Albert Q. and Sablayrolles, Alexandre and Mensch, Arthur and Bamford, Chris and Chaplot, Devendra Singh and Casas, Diego de las and Bressand, Florian and Lengyel, Gianna and Lample, Guillaume and Saulnier, Lucile and others},
564	  journal = {arXiv preprint arXiv:2310.06825},
565	  year = {2023},
566	}
567	
568	@article{strobl_conditional_2008,
569	  title = {Conditional Variable Importance for Random Forests},
570	  author = {Strobl, Carolin and Boulesteix, Anne-Laure and Kneib, Thomas and Augustin, Thomas and Zeileis, Achim},
571	  journal = {BMC Bioinformatics},
572	  volume = {9},
573	  pages = {307},
574	  year = {2008},
575	}
576	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e039405a-7c68-40d5-9f07-2c13066c25c0",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "51fee309-6ecd-4862-929d-e25779782122",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/references.bib",
      "content": "% ===== Lexical Richness =====\n\n@article{mccarthy2010mtld,\n  title = {{MTLD, vocd-D, and HD-D: A Validation Study of Sophisticated Approaches to Lexical Diversity Assessment}},\n  author = {McCarthy, Philip M. and Jarvis, Scott},\n  journal = {Behavior Research Methods},\n  volume = {42},\n  number = {2},\n  pages = {381--392},\n  year = {2010},\n}\n\n@article{covington2010mattr,\n  title = {{Cutting the Gordian Knot: The Moving-Average Type-Token Ratio (MATTR)}},\n  author = {Covington, Michael A. and McFall, Joe D.},\n  journal = {Journal of Quantitative Linguistics},\n  volume = {17},\n  number = {2},\n  pages = {94--100},\n  year = {2010},\n}\n\n% ===== Data Provenance / Contamination =====\n\n@inproceedings{oren2024proving,\n  title = {{Proving Test Set Contamination in Black Box Language Models}},\n  author = {Oren, Yonatan and Meister, Nicole and Chatterji, Niladri and Laber, Faisal and Stern, Avi},\n  booktitle = {Proceedings of the International Conference on Learning Representations},\n  year = {2024},\n}\n\n@inproceedings{golchin2024time,\n  title = {{Time Travel in LLMs: Tracing Data Contamination in Large Language Models}},\n  author = {Golchin, Shahriar and Surdeanu, Mihai},\n  booktitle = {Proceedings of the International Conference on Learning Representations},\n  year = {2024},\n}\n\n@inproceedings{longpre2024data,\n  title = {{Data Authenticity, Consent, and Provenance for AI Are All Broken: What Will It Take to Fix Them?}},\n  author = {Longpre, Shayne and Mahari, Robert and Lee, Naana and Luccioni, Sasha and Jernite, Yacine and others},\n  booktitle = {Proceedings of the International Conference on Machine Learning},\n  year = {2024},\n}\n\n% ===== Statistics =====\n\n@book{cohen1988statistical,\n  title = {{Statistical Power Analysis for the Behavioral Sciences}},\n  author = {Cohen, Jacob},\n  edition = {2nd},\n  publisher = {Lawrence Erlbaum Associates},\n  year = {1988},\n}\n\n@article{tang2024science,\n  title = {{The Science of Detecting LLM-Generated Text}},\n  author = {Tang, Ruixiang and Chuang, Yu-Neng and Hu, Xia},\n  journal = {Communications of the ACM},\n  volume = {67},\n  number = {4},\n  pages = {50--59},\n  year = {2024},\n}\n\n@article{neal2017surveying,\n  title = {{Surveying Stylometry Techniques and Applications}},\n  author = {Neal, Tempestt and Sundararajan, Kalaivani and Fatima, Aneez and Yan, Yiming and Xiang, Yingfei and Woodard, Damon L.},\n  journal = {ACM Computing Surveys},\n  volume = {50},\n  number = {6},\n  pages = {1--36},\n  year = {2017},\n}\n\n% ===== Detection =====\n\n@inproceedings{detectgpt,\n  title = {{DetectGPT: Zero-Shot Machine-Generated Text Detection using Probability Curvature}},\n  author = {Mitchell, Eric and Lee, Yoonho and Khazatsky, Alexander and Manning, Christopher D. and Finn, Chelsea},\n  booktitle = {Proceedings of the International Conference on Machine Learning},\n  year = {2023},\n}\n\n@inproceedings{gltr,\n  title = {{GLTR: Statistical Detection and Visualization of Generated Text}},\n  author = {Gehrmann, Sebastian and Strobelt, Hendrik and Rush, Alexander M.},\n  booktitle = {Proceedings of the Annual Meeting of the Association for Computational Linguistics: System Demonstrations},\n  year = {2019},\n}\n\n@inproceedings{dna_gpt,\n  title = {{DNA-GPT: Divergent N-Gram Analysis for Training-Free Detection of GPT-Generated Text}},\n  author = {Yang, Xianjun and Cheng, Wei and Wu, Yue and Petzold, Linda and Wang, William Yang and Chen, Haifeng},\n  booktitle = {Proceedings of the International Conference on Learning Representations},\n  year = {2024},\n}\n\n@inproceedings{binoculars,\n  title = {{Spotting LLMs With Binoculars: Zero-Shot Detection of Machine-Generated Text}},\n  author = {Hans, Abhimanyu and Schwarzschild, Avi and Cherepanova, Valeriia and Kazemi, Hamid and Saha, Aniruddha and Goldblum, Micah and Geiping, Jonas and Goldstein, Tom},\n  booktitle = {Proceedings of the International Conference on Machine Learning},\n  year = {2024},\n}\n\n@inproceedings{fast_detectgpt,\n  title = {{Fast-DetectGPT: Efficient Zero-Shot Detection of Machine-Generated Text via Conditional Probability Curvature}},\n  author = {Bao, Guangsheng and Zhao, Yanbin and Teng, Zhiyang and Yang, Linyi and Zhang, Yue},\n  booktitle = {Proceedings of the International Conference on Learning Representations},\n  year = {2024},\n}\n\n@article{ld_score,\n  title = {{Beyond Perplexity: Character Distribution Signatures and the MDTA Benchmark for AI Text Detection}},\n  author = {Narayanasamy, Priyadarshan and Agrawal, Swastik and Faber, Klint and Alam, Fardina Fathmiul},\n  journal = {arXiv preprint arXiv:2605.01647},\n  year = {2026},\n}\n\n@inproceedings{intrinsic_dimension,\n  title = {{Intrinsic Dimension Estimation for Robust Detection of AI-Generated Texts}},\n  author = {Tulchinskii, Eduard and Kuznetsov, Kristian and Kushnareva, Laida and Cherniavskii, Daniil and Nikolenko, Sergey and Burnaev, Evgeny and Barannikov, Serguei and Piontkovskaya, Irina},\n  booktitle = {Advances in Neural Information Processing Systems},\n  year = {2023},\n}\n\n@article{diveye,\n  title = {{Diversity Boosts AI-Generated Text Detection}},\n  author = {Basani, Advik Raj and Chen, Pin-Yu},\n  journal = {Transactions on Machine Learning Research},\n  year = {2026},\n}\n\n@article{generator_barrier,\n  title = {{Breaking the Generator Barrier: Disentangled Representation for Generalizable AI-Text Detection}},\n  author = {Pu, Xiao and Cheng, Zepeng and Yuan, Lin and Wu, Yu and Bi, Xiuli},\n  journal = {arXiv preprint arXiv:2604.13692},\n  year = {2026},\n}\n\n@article{feat_aug_transformer,\n  title = {{Feature-Augmented Transformers for Robust AI-Text Detection Across Domains and Generators}},\n  author = {Mady, Mohamed and Reschke, Johannes and Schuller, Bj{\\\"o}rn},\n  journal = {arXiv preprint arXiv:2605.03969},\n  year = {2026},\n}\n\n@article{reliable_detection,\n  title = {{Can AI-Generated Text be Reliably Detected? Stress Testing AI Text Detectors Under Various Attacks}},\n  author = {Sadasivan, Vinu Sankar and Kumar, Aounon and Balasubramanian, Sriram and Wang, Wenxiao and Feizi, Soheil},\n  journal = {Transactions on Machine Learning Research},\n  year = {2025},\n  url = {https://openreview.net/forum?id=OOgsAZdFOt},\n}\n\n@inproceedings{paraphrase_evades,\n  title = {{Paraphrasing Evades Detectors of AI-Generated Text, but Retrieval is an Effective Defense}},\n  author = {Krishna, Kalpesh and Song, Yixiao and Karpinska, Marzena and Wieting, John and Iyyer, Mohit},\n  booktitle = {Advances in Neural Information Processing Systems},\n  year = {2023},\n}\n\n@inproceedings{detection_possibilities,\n  title = {{Position: On the Possibilities of AI-Generated Text Detection}},\n  author = {Chakraborty, Souradip and Bedi, Amrit Singh and Zhu, Sicheng and An, Bang and Manocha, Dinesh and Huang, Furong},\n  booktitle = {Proceedings of the International Conference on Machine Learning},\n  year = {2024},\n}\n\n@inproceedings{grover,\n  title = {{Defending Against Neural Fake News}},\n  author = {Zellers, Rowan and Holtzman, Ari and Rashkin, Hannah and Bisk, Yonatan and Farhadi, Ali and Roesner, Franziska and Choi, Yejin},\n  booktitle = {Advances in Neural Information Processing Systems},\n  year = {2019},\n}\n\n@article{release_strategies,\n  title = {{Release Strategies and the Social Impacts of Language Models}},\n  author = {Solaiman, Irene and Brundage, Miles and Clark, Jack and Askell, Amanda and Herbert-Voss, Ariel and Wu, Jeff and Radford, Alec and Krueger, Gretchen and Kim, Jong Wook and Kreps, Sarah and McCain, Miles and Newhouse, Alex and Blazakis, Jason and McGuffie, Kris and Wang, Jasmine},\n  journal = {arXiv preprint arXiv:1908.09203},\n  year = {2019},\n}\n\n@inproceedings{beyond_binary,\n  title = {{Beyond Binary: Towards Fine-Grained LLM-Generated Text Detection via Role Recognition and Involvement Measurement}},\n  author = {Cheng, Zihao and Zhou, Li and Jiang, Feng and Wang, Benyou and Li, Haizhou},\n  booktitle = {Proceedings of the ACM Web Conference},\n  year = {2025},\n}\n\n@inproceedings{semeval2024_task8,\n  title = {{SemEval-2024 Task 8: Multidomain, Multimodel and Multilingual Machine-Generated Text Detection}},\n  author = {Wang, Yuxia and Mansurov, Jonibek and Ivanov, Petar and Su, Jinyan and Shelmanov, Artem and Tsvigun, Akim and Afzal, Osama Mohammed and Mahmoud, Tarek and Puccetti, Giovanni and Arnold, Thomas and Whitehouse, Chenxi and Aji, Alham Fikri and Habash, Nizar and Gurevych, Iryna and Nakov, Preslav},\n  booktitle = {Proceedings of the International Workshop on Semantic Evaluation},\n  year = {2024},\n}\n\n@article{abburi_multifaceted,\n  title = {{AI-generated Text Detection: A Multifaceted Approach to Binary and Multiclass Classification}},\n  author = {Abburi, Harika and Bhattacharya, Sanmitra and Bowen, Edward and Pudota, Nirmala},\n  journal = {arXiv preprint arXiv:2505.11550},\n  year = {2025},\n}\n\n@article{defactify_dataset,\n  title = {{A Comprehensive Dataset for Human vs.\\ AI Generated Text Detection}},\n  author = {Roy, Rajarshi and Imanpour, Nasrin and Aziz, Ashhar and Bajpai, Shashwat and Singh, Gurpreet and Biswas, Shwetangshu and Wanaskar, Kapil and Patwa, Parth and Ghosh, Subhankar and Dixit, Shreyas and Pal, Nilesh Ranjan and Rawte, Vipula and Garimella, Ritvik and Jena, Gaytri and Sheth, Amit and Sharma, Vasu and Reganti, Aishwarya Naresh and Jain, Vinija and Chadha, Aman and Das, Amitava},\n  journal = {arXiv preprint arXiv:2510.22874},\n  year = {2025},\n}\n\n% ===== Model Collapse =====\n\n@inproceedings{self_consuming_mad,\n  title = {{Self-Consuming Generative Models Go MAD}},\n  author = {Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahmed Imtiaz and Babaei, Hossein and LeJeune, Daniel and Siahkoohi, Ali and Baraniuk, Richard G.},\n  booktitle = {Proceedings of the International Conference on Learning Representations},\n  year = {2024},\n}\n\n@article{curse_of_recursion,\n  title = {{AI models collapse when trained on recursively generated data}},\n  author = {Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and Anderson, Ross and Gal, Yarin},\n  journal = {Nature},\n  volume = {631},\n  pages = {755--759},\n  year = {2024},\n}\n\n@inproceedings{strong_model_collapse,\n  title = {{Strong Model Collapse}},\n  author = {Dohmatob, Elvis and Feng, Yunzhen and Subramonian, Arjun and Kempe, Julia},\n  booktitle = {Proceedings of the International Conference on Learning Representations},\n  year = {2025},\n}\n\n@inproceedings{model_collapse_avoidable,\n  title = {{Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data}},\n  author = {Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafael and Sleight, Henry and Hughes, John and Korbak, Tomasz and Agrawal, Rajashree and Pai, Dhruv and Gromov, Andrey and Roberts, Daniel A. and Yang, Diyi and Donoho, David L. and Koyejo, Sanmi},\n  booktitle = {Proceedings of the First Conference on Language Modeling (COLM)},\n  year = {2024},\n}\n\n% ===== Self-Training / Self-Play =====\n\n@article{self_rewarding_lms,\n  title = {{Self-Rewarding Language Models}},\n  author = {Yuan, Weizhe and Pang, Richard Yuanzhe and Cho, Kyunghyun and Sukhbaatar, Sainbayar and Xu, Jing and Weston, Jason},\n  journal = {arXiv preprint arXiv:2401.10020},\n  year = {2024},\n}\n\n@inproceedings{spin,\n  title = {{Self-Play Fine-Tuning Converts Weak Language Models to Strong Language Models}},\n  author = {Chen, Zixiang and Deng, Yihe and Yuan, Huizhuo and Ji, Kaixuan and Gu, Quanquan},\n  booktitle = {Proceedings of the 41st International Conference on Machine Learning},\n  year = {2024},\n}\n\n% ===== Fine-tuning =====\n\n@inproceedings{qlora,\n  title = {{QLoRA: Efficient Finetuning of Quantized Language Models}},\n  author = {Dettmers, Tim and Pagnoni, Artidoro and Holtzman, Ari and Zettlemoyer, Luke},\n  booktitle = {Advances in Neural Information Processing Systems},\n  year = {2023},\n}\n\n% ===== Data Quality =====\n\n% ===== (orphan entries removed: fineweb, dolma) =====\n\n@inproceedings{dsir,\n  title = {{Data Selection for Language Models via Importance Resampling}},\n  author = {Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy},\n  booktitle = {Advances in Neural Information Processing Systems},\n  year = {2023},\n}\n\n@inproceedings{qurating,\n  title = {{QuRating: Selecting High-Quality Data for Training Language Models}},\n  author = {Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi},\n  booktitle = {Proceedings of the International Conference on Machine Learning},\n  year = {2024},\n}\n\n@inproceedings{ccnet,\n  title = {{CCNet: Extracting High Quality Monolingual Datasets from Web Crawl Data}},\n  author = {Wenzek, Guillaume and Lachaux, Marie-Anne and Conneau, Alexis and Chaudhary, Vishrav and Guzm{\\'a}n, Francisco and Joulin, Armand and Grave, Edouard},\n  booktitle = {Proceedings of the Language Resources and Evaluation Conference},\n  year = {2020},\n}\n\n% ===== Watermarking =====\n\n@inproceedings{watermark_llm,\n  title = {{A Watermark for Large Language Models}},\n  author = {Kirchenbauer, John and Geiping, Jonas and Wen, Yuxin and Katz, Jonathan and Miers, Ian and Goldstein, Tom},\n  booktitle = {Proceedings of the International Conference on Machine Learning},\n  year = {2023},\n}\n\n@article{synthid_text,\n  title = {{Scalable Watermarking for Identifying Large Language Model Outputs}},\n  author = {Dathathri, Sumanth and See, Abigail and Ghaisas, Sumedh and Huang, Po-Sen and McAdam, Rob and Welbl, Johannes and Bachani, Vandana and Kaskasoli, Alex and Stanforth, Robert and Matejovicova, Tatiana and Hayes, Jamie and Vyas, Nidhi and Al Merey, Majd and Brown-Cohen, Jonah and Bunel, Rudy and Balle, Borja and Cemgil, Taylan and Ahmed, Zahra and Stacpoole, Kitty and Shumailov, Ilia and Baetu, Ciprian and Gowal, Sven and Hassabis, Demis and Kohli, Pushmeet},\n  journal = {Nature},\n  volume = {634},\n  pages = {818--823},\n  year = {2024},\n}\n\n@misc{aaronson_watermark,\n  title = {{Watermarking GPT Outputs}},\n  author = {Aaronson, Scott and Kirchner, Hendrik},\n  year = {2022},\n  howpublished = {Technical Talk},\n  url = {https://scottaaronson.blog/?p=6823},\n}\n\n@article{chainwash,\n  title = {{Chainwash: Multi-Step Rewriting Attacks on Diffusion Language Model Watermarks}},\n  author = {Ameen, Mohd Ruhul and Islam, Akif and Mahmud, Nadim and Hamid, Md. Ekramul},\n  journal = {arXiv preprint arXiv:2605.05503},\n  year = {2026},\n}\n\n% ===== Vocabulary Diversity =====\n\n@inproceedings{curious_decline,\n  title = {{The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text}},\n  author = {Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo\\'{e}},\n  booktitle = {Findings of the Association for Computational Linguistics: NAACL},\n  year = {2024},\n}\n\n@inproceedings{writing_diversity,\n  title = {{Does Writing with Language Models Reduce Content Diversity?}},\n  author = {Padmakumar, Vishakh and He, He},\n  booktitle = {Proceedings of the International Conference on Learning Representations},\n  year = {2024},\n}\n\n@inproceedings{nucleus_sampling,\n  title = {{The Curious Case of Neural Text Degeneration}},\n  author = {Holtzman, Ari and Buys, Jan and Du, Li and Forbes, Maxwell and Choi, Yejin},\n  booktitle = {Proceedings of the International Conference on Learning Representations},\n  year = {2020},\n}\n\n% ===== Stylometry =====\n\n@article{stamatatos_survey,\n  title = {{A Survey of Modern Authorship Attribution Methods}},\n  author = {Stamatatos, Efstathios},\n  journal = {Journal of the American Society for Information Science and Technology},\n  volume = {60},\n  number = {3},\n  pages = {538--556},\n  year = {2009},\n}\n\n@article{koppel_authorship,\n  title = {{Computational Methods in Authorship Attribution}},\n  author = {Koppel, Moshe and Schler, Jonathan and Argamon, Shlomo},\n  journal = {Journal of the American Society for Information Science and Technology},\n  volume = {60},\n  number = {1},\n  pages = {9--26},\n  year = {2009},\n}\n\n@inproceedings{uchendu_attribution,\n  title = {{Authorship Attribution for Neural Text Generation}},\n  author = {Uchendu, Adaku and Le, Thai and Shu, Kai and Lee, Dongwon},\n  booktitle = {Proceedings of the Conference on Empirical Methods in Natural Language Processing},\n  year = {2020},\n}\n\n@inproceedings{munir_looking_glass,\n  title = {{Through the Looking Glass: Learning to Attribute Synthetic Text Generated by Language Models}},\n  author = {Munir, Shaoor and Batool, Brishna and Shafiq, Zubair and Srinivasan, Padmini and Zaffar, Fareed},\n  booktitle = {Proceedings of the Conference of the European Chapter of the Association for Computational Linguistics},\n  year = {2021},\n}\n\n% ===== (orphan entries removed: briesch_self_consuming, jovanovic_watermark_stealing, mcgovern_fingerprints) =====\n\n% ===== Iterative Generation =====\n\n@inproceedings{broken_telephone,\n  title = {{LLM as a Broken Telephone: Iterative Generation Distorts Information}},\n  author = {Mohamed, Amr and Geng, Mingmeng and Vazirgiannis, Michalis and Shang, Guokan},\n  booktitle = {Proceedings of the Annual Meeting of the Association for Computational Linguistics},\n  year = {2025},\n}\n\n@inproceedings{attractor_cycles,\n  title = {{Unveiling Attractor Cycles in Large Language Models: A Dynamical Systems View of Successive Paraphrasing}},\n  author = {Wang, Yibo and Wu, Congying and Li, Yanan and Cai, Yi},\n  booktitle = {Proceedings of the Annual Meeting of the Association for Computational Linguistics},\n  year = {2025},\n}\n\n@article{markovian_chains,\n  title = {{Markovian Generation Chains in Large Language Models}},\n  author = {Geng, Mingmeng and Mohamed, Amr and Shang, Guokan and Vazirgiannis, Michalis and Poibeau, Thierry},\n  journal = {arXiv preprint arXiv:2603.11228},\n  year = {2026},\n}\n\n\n% ===== Membership Inference =====\n\n@inproceedings{min_k_percent,\n  title = {{Detecting Pretraining Data from Large Language Models}},\n  author = {Shi, Weijia and Ajith, Anirudh and Xia, Mengzhou and Huang, Yangsibo and Liu, Daogao and Blevins, Terra and Chen, Danqi and Zettlemoyer, Luke},\n  booktitle = {Proceedings of the International Conference on Learning Representations},\n  year = {2024},\n}\n\n% ===== Survey =====\n\n@article{wu_survey_2025,\n  title = {{A Survey on LLM-Generated Text Detection: Necessity, Methods, and Future Directions}},\n  author = {Wu, Junchao and Yang, Shu and Zhan, Runzhe and Yuan, Yulin and Chao, Lidia Sam and Wong, Derek Fai},\n  journal = {Computational Linguistics},\n  publisher = {MIT Press},\n  year = {2025},\n}\n\n@inproceedings{jawahar_survey,\n  title = {{Automatic Detection of Machine Generated Text: A Critical Survey}},\n  author = {Jawahar, Ganesh and Abdul-Mageed, Muhammad and Lakshmanan, Laks V.S.},\n  booktitle = {Proceedings of the International Conference on Computational Linguistics},\n  year = {2020},\n}\n\n% ===== Models =====\n\n@inproceedings{pythia,\n  title = {{Pythia: A Suite for Analyzing Large Language Models Across Training and Scaling}},\n  author = {Biderman, Stella and Schoelkopf, Hailey and Anthony, Quentin Gregory and Bradley, Herbie and O'Brien, Kyle and Hallahan, Eric and Khan, Mohammad Aflah and Purohit, Shivanshu and Prashanth, USVSN Sai and Raff, Edward and Skowron, Aviya and Sutawika, Lintang and {van der Wal}, Oskar},\n  booktitle = {Proceedings of the International Conference on Machine Learning},\n  year = {2023},\n}\n\n@inproceedings{olmo,\n  title = {{OLMo: Accelerating the Science of Language Models}},\n  author = {Groeneveld, Dirk and Beltagy, Iz and Walsh, Evan and Bhagia, Akshita and Kinney, Rodney and Tafjord, Oyvind and Jha, Ananya Harsh and Ivison, Hamish and Magnusson, Ian and Wang, Yizhong and Arora, Shane and Atkinson, David and Authur, Russell and Chandu, Khyathi Raghavi and Cohan, Arman and Dumas, Jennifer and Elazar, Yanai and Gu, Yuling and Hessel, Jack and Khot, Tushar and Merrill, William and Morrison, Jacob and Muennighoff, Niklas and Naik, Aakanksha and Nam, Crystal and Peters, Matthew E. and Pyatkin, Valentina and Ravichander, Abhilasha and Schwenk, Dustin and Shah, Saurabh and Smith, Will and Strubell, Emma and Subramani, Nishant and Wortsman, Mitchell and Dasigi, Pradeep and Lambert, Nathan and Richardson, Kyle and Zettlemoyer, Luke and Dodge, Jesse and Lo, Kyle and Soldaini, Luca and Smith, Noah A. and Hajishirzi, Hannaneh},\n  booktitle = {Proceedings of the Annual Meeting of the Association for Computational Linguistics},\n  year = {2024},\n}\n\n@article{qwen3,\n  title = {{Qwen3 Technical Report}},\n  author = {{Qwen Team}},\n  journal = {arXiv preprint arXiv:2505.09388},\n  year = {2025},\n}\n\n@inproceedings{ghostbuster,\n  title = {{Ghostbuster: Detecting Text Ghostwritten by Large Language Models}},\n  author = {Verma, Vivek and Fleisig, Eve and Tomlin, Nicholas and Jurafsky, Dan},\n  booktitle = {Proceedings of the Annual Meeting of the Association for Computational Linguistics},\n  year = {2024},\n}\n\n@article{two_birds,\n  title = {{Two Birds with One Stone: Multi-Task Machine-Generated Text Detection and LLM Source Attribution}},\n  author = {Rao, Harika and Vashistha, Adaku Jane and Jain, Aaryan and Garg, Naman},\n  journal = {arXiv preprint arXiv:2508.14190},\n  year = {2025},\n}\n\n@inproceedings{beyond_final_actor,\n  title = {{Beyond the Final Actor: Fine-Grained LLM-Generated Text Detection}},\n  author = {Li, Ziang and Gao, Guan-Yu and Yang, Songlin and Yu, Ning and Fritz, Mario and Metze, Florian},\n  booktitle = {Proceedings of the Association for Computational Linguistics},\n  year = {2026},\n}\n\n% ===== Machine Learning =====\n\n@article{gutierrez_ordinal_survey,\n  title = {{Ordinal Regression Methods: Survey and Experimental Study}},\n  author = {Guti{\\'e}rrez, Pedro Antonio and P{\\'e}rez-Ortiz, Mar{\\'i}a and S{\\'a}nchez-Monedero, Javier and Fern{\\'a}ndez-Navarro, Francisco and Herv{\\'a}s-Mart{\\'i}nez, C{\\'e}sar},\n  journal = {IEEE Transactions on Knowledge and Data Engineering},\n  volume = {28},\n  number = {1},\n  pages = {127--146},\n  year = {2016},\n}\n\n@article{coral_ordinal,\n  title = {{Rank Consistent Ordinal Regression for Neural Networks with Application to Age Estimation}},\n  author = {Cao, Wenzhi and Mirjalili, Vahid and Raschka, Sebastian},\n  journal = {Pattern Recognition Letters},\n  volume = {140},\n  pages = {325--331},\n  year = {2020},\n}\n\n@inproceedings{frank_hall_ordinal,\n  title = {{A Simple Approach to Ordinal Classification}},\n  author = {Frank, Eibe and Hall, Mark},\n  booktitle = {Proceedings of the European Conference on Machine Learning},\n  year = {2001},\n}\n\n@inproceedings{pang_opinion_mining,\n  title = {{Seeing Stars: Exploiting Class Relationships for Sentiment Categorization with Respect to Rating Scales}},\n  author = {Pang, Bo and Lee, Lillian},\n  booktitle = {Proceedings of the 43rd Annual Meeting of the Association for Computational Linguistics},\n  pages = {115--124},\n  year = {2005},\n}\n\n@inproceedings{taghipour_neural_essay,\n  title = {{A Neural Approach to Automated Essay Scoring}},\n  author = {Taghipour, Kaveh and Ng, Hwee Tou},\n  booktitle = {Proceedings of the 2016 Conference on Empirical Methods in Natural Language Processing},\n  pages = {1882--1891},\n  year = {2016},\n}\n\n@article{corn_ordinal,\n  title = {{Deep Neural Networks for Rank-Consistent Ordinal Regression Based On Conditional Probabilities}},\n  author = {Shi, Xintong and Cao, Wenzhi and Raschka, Sebastian},\n  journal = {Pattern Analysis and Applications},\n  volume = {26},\n  pages = {941--955},\n  year = {2023},\n}\n\n@inproceedings{xgboost,\n  title = {{XGBoost: A Scalable Tree Boosting System}},\n  author = {Chen, Tianqi and Guestrin, Carlos},\n  booktitle = {Proceedings of the ACM SIGKDD International Conference on Knowledge Discovery and Data Mining},\n  year = {2016},\n}\n\n@article{lakens_equivalence,\n  title = {{Equivalence Tests: A Practical Primer for $t$ Tests, Correlations, and Meta-Analyses}},\n  author = {Lakens, Dani{\\\"e}l},\n  journal = {Social Psychological and Personality Science},\n  volume = {8},\n  number = {4},\n  pages = {355--362},\n  year = {2017},\n}\n\n% ===== Generator Model References =====\n\n@article{llama3,\n  title = {{The Llama 3 Herd of Models}},\n  author = {Grattafiori, Aaron and Dubey, Abhimanyu and Jauhri, Abhinav and Pandey, Abhinav and Kadian, Abhishek and Al-Dahle, Ahmad and Letman, Aiesha and Mathur, Akhil and Schelten, Alan and Yang, Amy and others},\n  journal = {arXiv preprint arXiv:2407.21783},\n  year = {2024},\n}\n\n@article{mistral7b,\n  title = {{Mistral 7B}},\n  author = {Jiang, Albert Q. and Sablayrolles, Alexandre and Mensch, Arthur and Bamford, Chris and Chaplot, Devendra Singh and Casas, Diego de las and Bressand, Florian and Lengyel, Gianna and Lample, Guillaume and Saulnier, Lucile and others},\n  journal = {arXiv preprint arXiv:2310.06825},\n  year = {2023},\n}\n\n@article{strobl_conditional_2008,\n  title = {Conditional Variable Importance for Random Forests},\n  author = {Strobl, Carolin and Boulesteix, Anne-Laure and Kneib, Thomas and Augustin, Thomas and Zeileis, Achim},\n  journal = {BMC Bioinformatics},\n  volume = {9},\n  pages = {307},\n  year = {2008},\n}\n",
      "numLines": 576,
      "startLine": 1,
      "totalLines": 576
    }
  },
  "sourceToolAssistantUUID": "e039405a-7c68-40d5-9f07-2c13066c25c0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 63 · 2026-05-19T06:17:53.950Z_

<details open><summary>🔧 Tool call — Read · `toolu_012G4zTGNtrreNiPXmQ81UbQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_dataset_stats.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "51fee309-6ecd-4862-929d-e25779782122",
  "isSidechain": false,
  "requestId": "req_011CbBSUqMHxxg2eutzmeLDY",
  "type": "assistant",
  "uuid": "6a799139-9031-4eed-bc0b-6c17d3b0f869",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AgX2GiE4EAhfet6wZiP3LX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 14892,
      "cache_creation_input_tokens": 5020,
      "cache_read_input_tokens": 31700,
      "output_tokens": 574,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5020,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 14892,
          "output_tokens": 574,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 5020,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5020
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "previous_message_not_found"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 64 · 2026-05-19T06:17:53.954Z_

<details><summary>↩ Tool result · `toolu_012G4zTGNtrreNiPXmQ81UbQ`</summary>

```text
1	\section{Dataset Statistics}
2	\label{app:dataset-stats}
3	
4	Table~\ref{tab:dataset-stats} reports per-generator sample counts after filtering (removing generation failures, exact duplicates, and passages shorter than 50 whitespace tokens).
5	
6	\begin{table}[t]
7	\centering
8	\small
9	\begin{tabular}{llcc}
10	\toprule
11	\textbf{Generator} & \textbf{Family} & \textbf{Params} & \textbf{Samples} \\
12	\midrule
13	Pythia-1B       & Pythia  & 1.0B & 4{,}555 \\
14	Pythia-2.8B     & Pythia  & 2.8B & 4{,}609 \\
15	OLMo-2-1B      & OLMo    & 1.5B & 4{,}713 \\
16	Qwen3-0.6B     & Qwen    & 0.6B & 4{,}538 \\
17	Qwen3-1.7B     & Qwen    & 1.7B & 4{,}617 \\
18	Qwen3-8B       & Qwen    & 8.2B & 4{,}497 \\
19	Llama-3.2-3B   & Llama   & 3.2B & 4{,}680 \\
20	Mistral-7B-v0.3 & Mistral & 7.0B & 4{,}849 \\
21	\midrule
22	\multicolumn{3}{l}{\textbf{Total}} & \textbf{37{,}058} \\
23	\bottomrule
24	\end{tabular}
25	\caption[Per-generator sample counts]{Per-generator sample counts after filtering (8 generators, 5 families). Each generator starts from ${\sim}$1{,}000 shared Wikipedia seeds and produces chains of depth 4 (5 texts per chain). Attrition varies by generator due to differing generation failure rates.\protect\footnotemark}
26	\label{tab:dataset-stats}
27	\end{table}
28	\footnotetext{Table~\ref{tab:baselines} evaluates on a subset of 34{,}131 samples for which all detector scores (FastDetectGPT, Binoculars, LD-Score, Avg-LogProb) are available.}
29	
30	Figure~\ref{fig:violin} shows the full distribution of each feature across five generation depths (0--4), pooled across all eight generators ($N$\,=\,37{,}058).
31	The violin plots confirm the DDR pattern: drifting features (entropy mean, TTR, hapax ratio) show progressive narrowing and location shift, while shape features (entropy max, tail decay) maintain approximately constant distributions across depths.
32	
33	\begin{figure*}[ht]
34	\centering
35	\includegraphics[width=\textwidth]{fig_appendix_violin.pdf}
36	\caption{Feature distributions by generation depth (violin plots, $N$\,=\,37{,}058). Drifting features (entropy mean, TTR, hapax ratio: $|\rho| > 0.60$) show clear location shifts and narrowing with increasing depth. Shape features (entropy max, tail decay: $|\rho| < 0.10$) remain approximately stationary. Quartile lines indicate median and interquartile range.}
37	\label{fig:violin}
38	\end{figure*}
39	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6a799139-9031-4eed-bc0b-6c17d3b0f869",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "4d90f193-f2ac-4bb8-9466-3464f5e47cd7",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_dataset_stats.tex",
      "content": "\\section{Dataset Statistics}\n\\label{app:dataset-stats}\n\nTable~\\ref{tab:dataset-stats} reports per-generator sample counts after filtering (removing generation failures, exact duplicates, and passages shorter than 50 whitespace tokens).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Generator} & \\textbf{Family} & \\textbf{Params} & \\textbf{Samples} \\\\\n\\midrule\nPythia-1B       & Pythia  & 1.0B & 4{,}555 \\\\\nPythia-2.8B     & Pythia  & 2.8B & 4{,}609 \\\\\nOLMo-2-1B      & OLMo    & 1.5B & 4{,}713 \\\\\nQwen3-0.6B     & Qwen    & 0.6B & 4{,}538 \\\\\nQwen3-1.7B     & Qwen    & 1.7B & 4{,}617 \\\\\nQwen3-8B       & Qwen    & 8.2B & 4{,}497 \\\\\nLlama-3.2-3B   & Llama   & 3.2B & 4{,}680 \\\\\nMistral-7B-v0.3 & Mistral & 7.0B & 4{,}849 \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textbf{Total}} & \\textbf{37{,}058} \\\\\n\\bottomrule\n\\end{tabular}\n\\caption[Per-generator sample counts]{Per-generator sample counts after filtering (8 generators, 5 families). Each generator starts from ${\\sim}$1{,}000 shared Wikipedia seeds and produces chains of depth 4 (5 texts per chain). Attrition varies by generator due to differing generation failure rates.\\protect\\footnotemark}\n\\label{tab:dataset-stats}\n\\end{table}\n\\footnotetext{Table~\\ref{tab:baselines} evaluates on a subset of 34{,}131 samples for which all detector scores (FastDetectGPT, Binoculars, LD-Score, Avg-LogProb) are available.}\n\nFigure~\\ref{fig:violin} shows the full distribution of each feature across five generation depths (0--4), pooled across all eight generators ($N$\\,=\\,37{,}058).\nThe violin plots confirm the DDR pattern: drifting features (entropy mean, TTR, hapax ratio) show progressive narrowing and location shift, while shape features (entropy max, tail decay) maintain approximately constant distributions across depths.\n\n\\begin{figure*}[ht]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_appendix_violin.pdf}\n\\caption{Feature distributions by generation depth (violin plots, $N$\\,=\\,37{,}058). Drifting features (entropy mean, TTR, hapax ratio: $|\\rho| > 0.60$) show clear location shifts and narrowing with increasing depth. Shape features (entropy max, tail decay: $|\\rho| < 0.10$) remain approximately stationary. Quartile lines indicate median and interquartile range.}\n\\label{fig:violin}\n\\end{figure*}\n",
      "numLines": 39,
      "startLine": 1,
      "totalLines": 39
    }
  },
  "sourceToolAssistantUUID": "6a799139-9031-4eed-bc0b-6c17d3b0f869",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 65 · 2026-05-19T06:17:54.431Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Q7qMkga3QaZhQLLm3HpWo4`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_qlora.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4d90f193-f2ac-4bb8-9466-3464f5e47cd7",
  "isSidechain": false,
  "requestId": "req_011CbBSUqMHxxg2eutzmeLDY",
  "type": "assistant",
  "uuid": "93ac204c-0bfa-4094-831a-f999fe155b53",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AgX2GiE4EAhfet6wZiP3LX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 14892,
      "cache_creation_input_tokens": 5020,
      "cache_read_input_tokens": 31700,
      "output_tokens": 574,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5020,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 14892,
          "output_tokens": 574,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 5020,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5020
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "previous_message_not_found"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 66 · 2026-05-19T06:17:54.436Z_

<details><summary>↩ Tool result · `toolu_01Q7qMkga3QaZhQLLm3HpWo4`</summary>

```text
1	To assess whether depth signal extends beyond handcrafted features, we fine-tune a pretrained language model end-to-end as a depth classifier using QLoRA \cite{qlora}.
2	
3	\paragraph{Setup.}
4	We fine-tune Qwen3-0.6B-Base with LoRA rank 16, learning rate $2 \times 10^{-4}$, and 3 epochs, framing depth estimation as 5-class sequence classification (gen-0 through gen-4).\footnote{Evaluated on the original 6-generator subset; XGBoost 3-class F1\,=\,0.789. We expect 8-generator training to further improve given additional diversity; the comparison direction is preserved.}
5	For 3-class evaluation, we collapse predictions into gen-0\,/\,gen-1\,/\,gen-2+ post hoc.
6	All results use the same LOGO protocol as the main experiments.
7	
8	\begin{table}[h]
9	\centering
10	\small
11	\caption{QLoRA end-to-end depth classification vs.\ XGBoost on handcrafted features, under LOGO evaluation.}
12	\label{tab:qlora}
13	\resizebox{\linewidth}{!}{%
14	\begin{tabular}{lccc}
15	\toprule
16	\textbf{Method} & \textbf{5-class F1} & \textbf{3-class F1} & \textbf{Per-class F1 (5-class)} \\
17	\midrule
18	XGBoost (7 features) & 0.501 $\pm$ 0.038 & 0.789 & --- \\
19	QLoRA (Qwen3-0.6B)   & 0.583 $\pm$ 0.010 & 0.905 $\pm$ 0.003 & 0.999\,/\,0.796\,/\,0.413\,/\,0.259\,/\,0.447 \\
20	\bottomrule
21	\end{tabular}}
22	\end{table}
23	
24	\paragraph{Results.}
25	QLoRA achieves 3-class LOGO F1\,=\,0.905 ($\pm$0.003), a +11.6\,pp improvement over the XGBoost baseline (0.789).
26	On 5-class evaluation, QLoRA reaches F1\,=\,0.583 ($\pm$0.010) vs.\ 0.501 for XGBoost (+8.2\,pp), with the largest gains at gen-1 (0.796 vs.\ 0.634) and gen-2 (0.413 vs.\ 0.268).
27	The gen-2/gen-3 boundary remains the primary failure mode (gen-3 F1\,=\,0.259), consistent with the feature-level analysis in \S\ref{sec:discussion}.
28	
29	\paragraph{Hyperparameter robustness.}
30	A second run with LoRA rank 32 and seed 123 yields 5-class F1\,=\,0.587 ($\pm$0.005) and 3-class F1\,=\,0.905 ($\pm$0.004), which confirms stability across hyperparameter and seed variation ($\Delta < 1$\,pp on both metrics).
31	
32	\paragraph{Implications.}
33	The substantial 3-class improvement demonstrates that raw token embeddings contain depth signal beyond what summary statistics capture; the seven handcrafted features are a strong but lossy compression of the full distributional information.
34	End-to-end fine-tuning exploits token-level patterns (e.g., positional regularities, n-gram repetitions) that aggregate features cannot represent.
35	This confirms that the depth signal documented in our main analysis is real and exploitable beyond engineered features, while the handcrafted approach retains practical advantages: interpretability, computational efficiency (no GPU inference), and the ability to reveal the differential depth response pattern that motivates the task formulation.
36	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "93ac204c-0bfa-4094-831a-f999fe155b53",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "0bb1179a-8314-4a96-8e0e-75f7aae9b2e6",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_qlora.tex",
      "content": "To assess whether depth signal extends beyond handcrafted features, we fine-tune a pretrained language model end-to-end as a depth classifier using QLoRA \\cite{qlora}.\n\n\\paragraph{Setup.}\nWe fine-tune Qwen3-0.6B-Base with LoRA rank 16, learning rate $2 \\times 10^{-4}$, and 3 epochs, framing depth estimation as 5-class sequence classification (gen-0 through gen-4).\\footnote{Evaluated on the original 6-generator subset; XGBoost 3-class F1\\,=\\,0.789. We expect 8-generator training to further improve given additional diversity; the comparison direction is preserved.}\nFor 3-class evaluation, we collapse predictions into gen-0\\,/\\,gen-1\\,/\\,gen-2+ post hoc.\nAll results use the same LOGO protocol as the main experiments.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{QLoRA end-to-end depth classification vs.\\ XGBoost on handcrafted features, under LOGO evaluation.}\n\\label{tab:qlora}\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Method} & \\textbf{5-class F1} & \\textbf{3-class F1} & \\textbf{Per-class F1 (5-class)} \\\\\n\\midrule\nXGBoost (7 features) & 0.501 $\\pm$ 0.038 & 0.789 & --- \\\\\nQLoRA (Qwen3-0.6B)   & 0.583 $\\pm$ 0.010 & 0.905 $\\pm$ 0.003 & 0.999\\,/\\,0.796\\,/\\,0.413\\,/\\,0.259\\,/\\,0.447 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\n\\paragraph{Results.}\nQLoRA achieves 3-class LOGO F1\\,=\\,0.905 ($\\pm$0.003), a +11.6\\,pp improvement over the XGBoost baseline (0.789).\nOn 5-class evaluation, QLoRA reaches F1\\,=\\,0.583 ($\\pm$0.010) vs.\\ 0.501 for XGBoost (+8.2\\,pp), with the largest gains at gen-1 (0.796 vs.\\ 0.634) and gen-2 (0.413 vs.\\ 0.268).\nThe gen-2/gen-3 boundary remains the primary failure mode (gen-3 F1\\,=\\,0.259), consistent with the feature-level analysis in \\S\\ref{sec:discussion}.\n\n\\paragraph{Hyperparameter robustness.}\nA second run with LoRA rank 32 and seed 123 yields 5-class F1\\,=\\,0.587 ($\\pm$0.005) and 3-class F1\\,=\\,0.905 ($\\pm$0.004), which confirms stability across hyperparameter and seed variation ($\\Delta < 1$\\,pp on both metrics).\n\n\\paragraph{Implications.}\nThe substantial 3-class improvement demonstrates that raw token embeddings contain depth signal beyond what summary statistics capture; the seven handcrafted features are a strong but lossy compression of the full distributional information.\nEnd-to-end fine-tuning exploits token-level patterns (e.g., positional regularities, n-gram repetitions) that aggregate features cannot represent.\nThis confirms that the depth signal documented in our main analysis is real and exploitable beyond engineered features, while the handcrafted approach retains practical advantages: interpretability, computational efficiency (no GPU inference), and the ability to reveal the differential depth response pattern that motivates the task formulation.\n",
      "numLines": 36,
      "startLine": 1,
      "totalLines": 36
    }
  },
  "sourceToolAssistantUUID": "93ac204c-0bfa-4094-831a-f999fe155b53",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 67 · 2026-05-19T06:17:55.225Z_

<details open><summary>🔧 Tool call — Read · `toolu_016RhS8VkdRyfLCJBymeggXw`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_instruct.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0bb1179a-8314-4a96-8e0e-75f7aae9b2e6",
  "isSidechain": false,
  "requestId": "req_011CbBSUqMHxxg2eutzmeLDY",
  "type": "assistant",
  "uuid": "8b157d06-998e-45bc-89e0-3b181a4f8702",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AgX2GiE4EAhfet6wZiP3LX",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 14892,
      "cache_creation_input_tokens": 5020,
      "cache_read_input_tokens": 31700,
      "output_tokens": 574,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 5020,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 14892,
          "output_tokens": 574,
          "cache_read_input_tokens": 31700,
          "cache_creation_input_tokens": 5020,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 5020
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": {
      "cache_miss_reason": {
        "type": "previous_message_not_found"
      }
    }
  }
}
```

</details>

---


### Tool result

_source line 68 · 2026-05-19T06:17:55.239Z_

<details><summary>↩ Tool result · `toolu_016RhS8VkdRyfLCJBymeggXw`</summary>

```text
1	\subsection*{Instruction-Tuned Model Results}
2	
3	Table~\ref{tab:instruct} summarizes depth classification under instruction tuning for three model families.
4	All results use within-model 5-fold CV on single-generator chains; LOGO evaluation is available for two models but uses earlier generator subsets (5--6 generators), so cross-model numbers are not directly comparable across rows.
5	
6	\begin{table}[h]
7	\centering
8	\small
9	\caption{Depth classification: base vs.\ instruction-tuned models (within-model 5-fold CV). $\rho$: Spearman correlation of entropy mean with depth. Rev.: number of features (out of 7) whose $\rho$ reverses sign under instruction tuning.}
10	\label{tab:instruct}
11	\resizebox{\linewidth}{!}{%
12	\begin{tabular}{lcc cc cc c}
13	\toprule
14	& \multicolumn{2}{c}{\textbf{3-class F1}} & \multicolumn{2}{c}{\textbf{Binary F1}} & \multicolumn{2}{c}{$\boldsymbol{\rho}$\textbf{(ent.\ mean)}} & \\
15	\cmidrule(lr){2-3} \cmidrule(lr){4-5} \cmidrule(lr){6-7}
16	\textbf{Model} & Base & Instruct & Base & Instruct & Base & Instruct & \textbf{Rev.} \\
17	\midrule
18	OLMo-2-1B       & 0.754 & 0.575 & 0.845 & 0.813 & $-$0.64 & $+$0.48 & 6/7 \\
19	Qwen3-1.7B      & 0.769 & 0.732 & 0.861 & 0.875 & $-$0.60 & $+$0.48 & 6/7 \\
20	Llama-3.2-3B    & 0.742 & 0.544 & 0.849 & 0.838 & $-$0.63 & $+$0.23 & 3/7 \\
21	\bottomrule
22	\end{tabular}}
23	\end{table}
24	
25	Instruction tuning degrades 3-class F1 by 3.7--19.9\,pp across all three families, while binary F1 (gen-1 vs.\ gen-2+) changes remain small ($|\Delta| \leq 3.2$\,pp).
26	The asymmetry indicates that instruction tuning primarily disrupts the gen-0/gen-1 boundary (human vs.\ first-generation), consistent with RLHF shifting the output distribution away from human-like text.
27	Entropy-mean $\rho$ reverses sign for all three models ($-0.60$--$-0.64$ base $\rightarrow$ $+0.23$--$+0.48$ instruct), and 6 of 7 features reverse for OLMo and Qwen vs.\ 3 of 7 for Llama.
28	This pattern is consistent with instruction tuning shifting the generation attractor rather than eliminating iterative dynamics (\S\ref{sec:discussion}).
29	
30	\paragraph{Retraining on instruction-tuned data.}
31	To test whether the depth signal persists under instruction tuning with reversed polarity, we retrain the XGBoost classifier on instruction-tuned feature data (Table~\ref{tab:instruct-retrain}).
32	
33	\begin{table}[h]
34	\centering
35	\small
36	\caption{Classification recovery under instruction-tuned retraining (binary-only: gen-1 vs.\ gen-2+, gen-0 excluded from training and evaluation). Base$\rightarrow$Inst: base-trained classifier tested on instruct data. Note: Table~\ref{tab:instruct} reports higher instruct binary F1 (e.g., OLMo 0.813) because it uses 3-class training with binary evaluation, where gen-0 in training helps the classifier learn the feature space.}
37	\label{tab:instruct-retrain}
38	\begin{tabular}{lccc}
39	\toprule
40	\textbf{Model} & \textbf{Base$\rightarrow$Inst} & \textbf{Retrained} & \textbf{$\Delta$} \\
41	\midrule
42	OLMo-2-1B-Inst   & 0.321 & 0.590 & $+$0.269 \\
43	Qwen3-1.7B-Inst  & 0.500 & 0.660 & $+$0.160 \\
44	Qwen3-0.6B-Inst  & 0.532 & 0.600 & $+$0.068 \\
45	\bottomrule
46	\end{tabular}
47	\end{table}
48	
49	Retraining recovers substantial within-model performance ($+$6.8--26.9\,pp), but the retrained F1 (0.590--0.660) remains below base-model levels (0.69--0.72).
50	Three-generator instruct LOGO yields binary F1\,=\,0.487, indicating weak cross-generator transfer under instruction tuning.
51	
52	\paragraph{DDR structure under instruction tuning.}
53	$k{=}2$ clustering in $(|\rho|, d)$ space on pooled instruct features yields silhouette\,=\,0.338 (vs.\ 0.632 for base models), indicating that the clean drifting/non-drifting partition is substantially compressed.
54	The compression is model-dependent: OLMo-Instruct shows near-zero $|\rho|$ for TTR and hapax (0.006, 0.025), while Qwen instruct models retain moderate correlations ($|\rho|{=}0.48$--$0.53$).
55	Cross-condition transfer is near chance in both directions (base$\rightarrow$instruct binary F1\,=\,0.490; instruct$\rightarrow$base F1\,=\,0.454), with the asymmetry ($-$0.036) suggesting that instruct-trained features generalize even less to base distributions than the reverse.
56	These results indicate that instruction tuning compresses the feature-space structure underlying DDR rather than simply reversing feature directions.
57	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8b157d06-998e-45bc-89e0-3b181a4f8702",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "74c40dc9-9c6a-472b-9796-c386cde1fb39",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_instruct.tex",
      "content": "\\subsection*{Instruction-Tuned Model Results}\n\nTable~\\ref{tab:instruct} summarizes depth classification under instruction tuning for three model families.\nAll results use within-model 5-fold CV on single-generator chains; LOGO evaluation is available for two models but uses earlier generator subsets (5--6 generators), so cross-model numbers are not directly comparable across rows.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Depth classification: base vs.\\ instruction-tuned models (within-model 5-fold CV). $\\rho$: Spearman correlation of entropy mean with depth. Rev.: number of features (out of 7) whose $\\rho$ reverses sign under instruction tuning.}\n\\label{tab:instruct}\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{lcc cc cc c}\n\\toprule\n& \\multicolumn{2}{c}{\\textbf{3-class F1}} & \\multicolumn{2}{c}{\\textbf{Binary F1}} & \\multicolumn{2}{c}{$\\boldsymbol{\\rho}$\\textbf{(ent.\\ mean)}} & \\\\\n\\cmidrule(lr){2-3} \\cmidrule(lr){4-5} \\cmidrule(lr){6-7}\n\\textbf{Model} & Base & Instruct & Base & Instruct & Base & Instruct & \\textbf{Rev.} \\\\\n\\midrule\nOLMo-2-1B       & 0.754 & 0.575 & 0.845 & 0.813 & $-$0.64 & $+$0.48 & 6/7 \\\\\nQwen3-1.7B      & 0.769 & 0.732 & 0.861 & 0.875 & $-$0.60 & $+$0.48 & 6/7 \\\\\nLlama-3.2-3B    & 0.742 & 0.544 & 0.849 & 0.838 & $-$0.63 & $+$0.23 & 3/7 \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nInstruction tuning degrades 3-class F1 by 3.7--19.9\\,pp across all three families, while binary F1 (gen-1 vs.\\ gen-2+) changes remain small ($|\\Delta| \\leq 3.2$\\,pp).\nThe asymmetry indicates that instruction tuning primarily disrupts the gen-0/gen-1 boundary (human vs.\\ first-generation), consistent with RLHF shifting the output distribution away from human-like text.\nEntropy-mean $\\rho$ reverses sign for all three models ($-0.60$--$-0.64$ base $\\rightarrow$ $+0.23$--$+0.48$ instruct), and 6 of 7 features reverse for OLMo and Qwen vs.\\ 3 of 7 for Llama.\nThis pattern is consistent with instruction tuning shifting the generation attractor rather than eliminating iterative dynamics (\\S\\ref{sec:discussion}).\n\n\\paragraph{Retraining on instruction-tuned data.}\nTo test whether the depth signal persists under instruction tuning with reversed polarity, we retrain the XGBoost classifier on instruction-tuned feature data (Table~\\ref{tab:instruct-retrain}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Classification recovery under instruction-tuned retraining (binary-only: gen-1 vs.\\ gen-2+, gen-0 excluded from training and evaluation). Base$\\rightarrow$Inst: base-trained classifier tested on instruct data. Note: Table~\\ref{tab:instruct} reports higher instruct binary F1 (e.g., OLMo 0.813) because it uses 3-class training with binary evaluation, where gen-0 in training helps the classifier learn the feature space.}\n\\label{tab:instruct-retrain}\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Model} & \\textbf{Base$\\rightarrow$Inst} & \\textbf{Retrained} & \\textbf{$\\Delta$} \\\\\n\\midrule\nOLMo-2-1B-Inst   & 0.321 & 0.590 & $+$0.269 \\\\\nQwen3-1.7B-Inst  & 0.500 & 0.660 & $+$0.160 \\\\\nQwen3-0.6B-Inst  & 0.532 & 0.600 & $+$0.068 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nRetraining recovers substantial within-model performance ($+$6.8--26.9\\,pp), but the retrained F1 (0.590--0.660) remains below base-model levels (0.69--0.72).\nThree-generator instruct LOGO yields binary F1\\,=\\,0.487, indicating weak cross-generator transfer under instruction tuning.\n\n\\paragraph{DDR structure under instruction tuning.}\n$k{=}2$ clustering in $(|\\rho|, d)$ space on pooled instruct features yields silhouette\\,=\\,0.338 (vs.\\ 0.632 for base models), indicating that the clean drifting/non-drifting partition is substantially compressed.\nThe compression is model-dependent: OLMo-Instruct shows near-zero $|\\rho|$ for TTR and hapax (0.006, 0.025), while Qwen instruct models retain moderate correlations ($|\\rho|{=}0.48$--$0.53$).\nCross-condition transfer is near chance in both directions (base$\\rightarrow$instruct binary F1\\,=\\,0.490; instruct$\\rightarrow$base F1\\,=\\,0.454), with the asymmetry ($-$0.036) suggesting that instruct-trained features generalize even less to base distributions than the reverse.\nThese results indicate that instruction tuning compresses the feature-space structure underlying DDR rather than simply reversing feature directions.\n",
      "numLines": 57,
      "startLine": 1,
      "totalLines": 57
    }
  },
  "sourceToolAssistantUUID": "8b157d06-998e-45bc-89e0-3b181a4f8702",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Runtime record

_source line 69_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 2  **你的审查侧重：新颖性 + 论文完整性 + 写作质量 + 格式合规**  ### 论文信息 - **标题**: Depth Profiling: Classifying Recursive Generation Depth in Base LLM Text Chains - **路径**: `projec…",
  "leafUuid": "74c40dc9-9c6a-472b-9796-c386cde1fb39",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Runtime record

_source line 70_

```json
{
  "type": "ai-title",
  "aiTitle": "Review depth profiling LLM paper for EMNLP",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Assistant

_source line 71 · 2026-05-19T06:18:00.098Z_

<details><summary>Logged reasoning block</summary>

```text
Now let me also check the PDF pages to verify formatting (page count, figures, layout). Let me also read a few more appendix files and check for AI writing markers.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "74c40dc9-9c6a-472b-9796-c386cde1fb39",
  "isSidechain": false,
  "requestId": "req_011CbBSW1hfZGRXf4CzPfbSB",
  "type": "assistant",
  "uuid": "6f091ab3-5b34-4aa7-a65e-6b4cc4541d15",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VUGC9G1tjm1wed976VYfJ7",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 48384,
      "cache_read_input_tokens": 36720,
      "output_tokens": 336,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 48384,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 336,
          "cache_read_input_tokens": 36720,
          "cache_creation_input_tokens": 48384,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 48384
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


### Assistant

_source line 72 · 2026-05-19T06:18:01.128Z_

已读取核心内容。现在检查论文 PDF 视觉效果和页数。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6f091ab3-5b34-4aa7-a65e-6b4cc4541d15",
  "isSidechain": false,
  "requestId": "req_011CbBSW1hfZGRXf4CzPfbSB",
  "type": "assistant",
  "uuid": "eef95ba9-0222-4e26-a6fe-871e762bc93e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VUGC9G1tjm1wed976VYfJ7",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 48384,
      "cache_read_input_tokens": 36720,
      "output_tokens": 336,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 48384,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 336,
          "cache_read_input_tokens": 36720,
          "cache_creation_input_tokens": 48384,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 48384
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

_source line 73 · 2026-05-19T06:18:03.633Z_

<details open><summary>🔧 Tool call — Glob · `toolu_013sNDnEHenczqwXDDWZnu5T`</summary>

```json
{
  "pattern": "**/paper/main.pdf",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "eef95ba9-0222-4e26-a6fe-871e762bc93e",
  "isSidechain": false,
  "requestId": "req_011CbBSW1hfZGRXf4CzPfbSB",
  "type": "assistant",
  "uuid": "f2196537-f199-49cb-9864-32ceda91d7db",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VUGC9G1tjm1wed976VYfJ7",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 48384,
      "cache_read_input_tokens": 36720,
      "output_tokens": 336,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 48384,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 336,
          "cache_read_input_tokens": 36720,
          "cache_creation_input_tokens": 48384,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 48384
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

_source line 74 · 2026-05-19T06:18:04.597Z_

<details><summary>↩ Tool result · `toolu_015Jx8i5y2okrDnHmjL4J7D4`</summary>

```text
1	We evaluate whether depth signal generalizes beyond Wikipedia by constructing generation chains from three additional domains: News articles, Academic abstracts, and Code documentation.
2	For each domain, we sample 200 seed texts and generate chains of depth 3 using three generators (Pythia-1B, Qwen3-1.7B, Mistral-7B).
3	The same 7-feature ensemble and LOGO protocol are applied.
4	
5	\noindent\textbf{Important caveat:} Cross-domain generation used $t{=}1.0$, top-$p{=}1.0$, which falls outside the method's reliable operating range ($t \leq 0.7$; Appendix~\ref{app:sampling-sensitivity}). Domain and temperature effects are therefore confounded in the results below; the cross-domain signal may partly reflect temperature-induced distributional divergence rather than domain generalization alone.
6	
7	\begin{table}[h]
8	\centering
9	\small
10	\caption{Cross-domain depth classification under LOGO evaluation (binary: gen-1 vs.\ gen-2+). Three generators $\times$ 200 seeds per domain. Bootstrap 95\% CIs ($n$\,=\,1000).}
11	\label{tab:domain}
12	\begin{tabular}{lccc}
13	\toprule
14	\textbf{Domain} & \textbf{Binary F1} & \textbf{95\% CI} & \textbf{3-class F1} \\
15	\midrule
16	Code           & 0.754 & [0.737, 0.770] & 0.634 \\
17	News           & 0.746 & [0.726, 0.764] & 0.652 \\
18	Academic       & 0.739 & [0.720, 0.757] & 0.622 \\
19	\bottomrule
20	\end{tabular}
21	\end{table}
22	
23	All three non-Wikipedia domains achieve binary F1 $>$ 0.73 under leave-one-generator-out evaluation, which demonstrates that depth signal is not an artifact of Wikipedia text properties.
24	
25	\paragraph{Domain $\times$ temperature interaction.}
26	Cross-domain generation used $t{=}1.0$, top-$p{=}1.0$ (vs.\ the main experiment's $t{=}0.7$, top-$p{=}0.9$).
27	Supplementary evaluation at $t{=}0.7$ reveals a domain $\times$ temperature interaction: the main Wikipedia experiment favors lower temperature (depth signal degrades monotonically with rising temperature; Appendix~\ref{app:sampling-sensitivity}), while cross-domain evaluation favors higher temperature ($t{=}1.0$ yields +3 to +11\,pp over $t{=}0.7$; News 0.746 vs.\ 0.712, Academic 0.739 vs.\ 0.628, Code 0.754 vs.\ 0.687).
28	This asymmetry likely reflects reference-model calibration: Pythia-410M, trained predominantly on web text, detects subtle per-step drift in Wikipedia but requires larger distributional divergence (produced by higher temperature) to detect depth signal in out-of-distribution domains.
29	This finding suggests that reference model selection is a key factor for cross-domain deployment of depth profiling.
30	
31	\paragraph{3-class inversion as DDR evidence.}
32	In the cross-domain setting, 3-class F1 (0.62--0.65) falls below binary F1 (0.74--0.75), reversing the pattern observed in the main experiment (3-class 0.762 $>$ binary 0.694).
33	This inversion reflects degraded gen-0 vs.\ gen-1 separation: the Pythia-410M reference model is calibrated to Wikipedia text, so its baseline entropy estimates are less discriminative for out-of-domain human text and compresses the feature distance between gen-0 and gen-1.
34	The binary task (gen-1 vs.\ gen-2+) is unaffected because both classes are generated under identical domain and decoding conditions; recursive drift is a relative change that does not depend on absolute calibration.
35	This pattern provides additional evidence that DDR captures generation-process invariants rather than domain-specific text properties: depth signal remains robust even when the human-vs-machine boundary becomes less distinct.
36	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b27ad8c5-2d48-4cae-a3a0-a8fd411ada3f",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "6702e718-5fb3-42b5-a71a-264b4e2a7c54",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_domain.tex",
      "content": "We evaluate whether depth signal generalizes beyond Wikipedia by constructing generation chains from three additional domains: News articles, Academic abstracts, and Code documentation.\nFor each domain, we sample 200 seed texts and generate chains of depth 3 using three generators (Pythia-1B, Qwen3-1.7B, Mistral-7B).\nThe same 7-feature ensemble and LOGO protocol are applied.\n\n\\noindent\\textbf{Important caveat:} Cross-domain generation used $t{=}1.0$, top-$p{=}1.0$, which falls outside the method's reliable operating range ($t \\leq 0.7$; Appendix~\\ref{app:sampling-sensitivity}). Domain and temperature effects are therefore confounded in the results below; the cross-domain signal may partly reflect temperature-induced distributional divergence rather than domain generalization alone.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{Cross-domain depth classification under LOGO evaluation (binary: gen-1 vs.\\ gen-2+). Three generators $\\times$ 200 seeds per domain. Bootstrap 95\\% CIs ($n$\\,=\\,1000).}\n\\label{tab:domain}\n\\begin{tabular}{lccc}\n\\toprule\n\\textbf{Domain} & \\textbf{Binary F1} & \\textbf{95\\% CI} & \\textbf{3-class F1} \\\\\n\\midrule\nCode           & 0.754 & [0.737, 0.770] & 0.634 \\\\\nNews           & 0.746 & [0.726, 0.764] & 0.652 \\\\\nAcademic       & 0.739 & [0.720, 0.757] & 0.622 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nAll three non-Wikipedia domains achieve binary F1 $>$ 0.73 under leave-one-generator-out evaluation, which demonstrates that depth signal is not an artifact of Wikipedia text properties.\n\n\\paragraph{Domain $\\times$ temperature interaction.}\nCross-domain generation used $t{=}1.0$, top-$p{=}1.0$ (vs.\\ the main experiment's $t{=}0.7$, top-$p{=}0.9$).\nSupplementary evaluation at $t{=}0.7$ reveals a domain $\\times$ temperature interaction: the main Wikipedia experiment favors lower temperature (depth signal degrades monotonically with rising temperature; Appendix~\\ref{app:sampling-sensitivity}), while cross-domain evaluation favors higher temperature ($t{=}1.0$ yields +3 to +11\\,pp over $t{=}0.7$; News 0.746 vs.\\ 0.712, Academic 0.739 vs.\\ 0.628, Code 0.754 vs.\\ 0.687).\nThis asymmetry likely reflects reference-model calibration: Pythia-410M, trained predominantly on web text, detects subtle per-step drift in Wikipedia but requires larger distributional divergence (produced by higher temperature) to detect depth signal in out-of-distribution domains.\nThis finding suggests that reference model selection is a key factor for cross-domain deployment of depth profiling.\n\n\\paragraph{3-class inversion as DDR evidence.}\nIn the cross-domain setting, 3-class F1 (0.62--0.65) falls below binary F1 (0.74--0.75), reversing the pattern observed in the main experiment (3-class 0.762 $>$ binary 0.694).\nThis inversion reflects degraded gen-0 vs.\\ gen-1 separation: the Pythia-410M reference model is calibrated to Wikipedia text, so its baseline entropy estimates are less discriminative for out-of-domain human text and compresses the feature distance between gen-0 and gen-1.\nThe binary task (gen-1 vs.\\ gen-2+) is unaffected because both classes are generated under identical domain and decoding conditions; recursive drift is a relative change that does not depend on absolute calibration.\nThis pattern provides additional evidence that DDR captures generation-process invariants rather than domain-specific text properties: depth signal remains robust even when the human-vs-machine boundary becomes less distinct.\n",
      "numLines": 36,
      "startLine": 1,
      "totalLines": 36
    }
  },
  "sourceToolAssistantUUID": "b27ad8c5-2d48-4cae-a3a0-a8fd411ada3f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool result

_source line 75 · 2026-05-19T06:18:03.646Z_

<details><summary>↩ Tool result · `toolu_013sNDnEHenczqwXDDWZnu5T`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.pdf
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f2196537-f199-49cb-9864-32ceda91d7db",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "e70658c2-92a6-47a9-a9df-6c95606818fa",
  "toolUseResult": {
    "filenames": [
      "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.pdf"
    ],
    "durationMs": 8,
    "numFiles": 1,
    "truncated": false
  },
  "sourceToolAssistantUUID": "f2196537-f199-49cb-9864-32ceda91d7db",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 76 · 2026-05-19T06:18:04.165Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WsiCoQff1d4m2RfxQDf7DU`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_downstream.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e70658c2-92a6-47a9-a9df-6c95606818fa",
  "isSidechain": false,
  "requestId": "req_011CbBSW1hfZGRXf4CzPfbSB",
  "type": "assistant",
  "uuid": "bd544fef-9574-4b1f-87ff-82a6335c0fc6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VUGC9G1tjm1wed976VYfJ7",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 48384,
      "cache_read_input_tokens": 36720,
      "output_tokens": 336,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 48384,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 336,
          "cache_read_input_tokens": 36720,
          "cache_creation_input_tokens": 48384,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 48384
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

_source line 77 · 2026-05-19T06:18:04.174Z_

<details><summary>↩ Tool result · `toolu_01WsiCoQff1d4m2RfxQDf7DU`</summary>

```text
1	Can depth-aware data curation improve downstream language model quality?
2	We fine-tune OLMo-2-0425-1B on five data variants (3 seeds each) and evaluate perplexity on a held-out test set (Table~\ref{tab:downstream}).
3	
4	\begin{table}[h]
5	\centering
6	\small
7	\begin{tabular}{lrc}
8	\toprule
9	\textbf{Variant} & \textbf{$n$} & \textbf{Test PPL} \\
10	\midrule
11	All depths            & 12{,}299 & 2.335 $\pm$ 0.000 \\
12	Size-matched (random) & 3{,}951  & 2.367 $\pm$ 0.000 \\
13	Depth 0--1 only       & 3{,}951  & 2.387 $\pm$ 0.001 \\
14	Binary-filtered       & 3{,}951  & 2.389 $\pm$ 0.000 \\
15	Depth 0 only          & 797      & 2.681 $\pm$ 0.001 \\
16	\bottomrule
17	\end{tabular}
18	\caption{Downstream fine-tuning perplexity (OLMo-2-0425-1B, mean $\pm$ std across 3 seeds). At equal sample count, random subsampling (2.367) outperforms depth-aware curation (depth 0--1: 2.387, binary-filtered: 2.389).}
19	\label{tab:downstream}
20	\end{table}
21	
22	The results are unambiguous: data quantity dominates depth composition.
23	Training on all 12{,}299 samples yields the lowest perplexity (2.335).
24	At equal sample count ($n$\,=\,3{,}951), random subsampling (2.367) \emph{outperforms} both depth-stratified selection (depth 0--1: 2.387) and binary detection filtering (2.389).
25	Cross-seed variance is below 0.002 across all variants, which confirms the robustness of this null result.
26	
27	Restricting training to human-only text (depth 0, $n$\,=\,797) produces a sharp perplexity increase to 2.681, driven primarily by the 5$\times$ reduction in data volume rather than depth composition per se.
28	
29	\paragraph{Equivalence testing.}
30	We apply a two one-sided $t$-test (TOST) with a $\pm$2\% relative margin (equivalence bounds $\pm$0.047 on the ppl scale) to formally assess whether the depth-aware and random subsampling conditions produce practically indistinguishable perplexity.
31	At equal sample count ($n$\,=\,3{,}951): size-matched (random) ppl\,=\,2.367 vs.\ depth 0--1 ppl\,=\,2.387, $\Delta$\,=\,0.020.
32	TOST confirms equivalence ($p = 1.1 \times 10^{-4}$); the two curation strategies yield practically indistinguishable downstream quality within the $\pm$2\% margin.
33	Cross-seed standard deviation is below 0.001 for both variants.
34	
35	Comparing the full dataset ($n$\,=\,12{,}299, ppl\,=\,2.335) against the depth-filtered subset ($n$\,=\,3{,}951, ppl\,=\,2.387): TOST \emph{rejects} equivalence (minimum equivalence margin\,=\,0.053, exceeding the $\pm$2\% bound), which confirms that data quantity drives perplexity reduction beyond what depth-aware selection can recover.
36	
37	Knowing the generation depth of a document does not, by itself, make it more or less useful for training; at fixed sample count, depth-aware curation is statistically equivalent to uninformed random subsampling.
38	
39	\subsection*{Margin Sensitivity Analysis}
40	
41	To assess the robustness of the equivalence conclusion to margin choice, we repeat the TOST procedure across multiple equivalence margins \cite{lakens_equivalence}, following the recommendation to report sensitivity across plausible bounds rather than relying on a single threshold (Table~\ref{tab:tost-margins}).
42	
43	\begin{table}[h]
44	\centering
45	\small
46	\resizebox{\linewidth}{!}{%
47	\begin{tabular}{llcc}
48	\toprule
49	\textbf{Comparison} & \textbf{Margin} & \textbf{Equiv?} & \textbf{TOST $p$} \\
50	\midrule
51	Full (12{,}299) vs.\ Random (3{,}951) & $\pm$1\% & No & 1.0 \\
52	                                        & $\pm$2\% & Yes & $1 \times 10^{-6}$ \\
53	                                        & $\pm$3\% & Yes & $< 10^{-10}$ \\
54	                                        & $\pm$5\% & Yes & $< 10^{-10}$ \\
55	\midrule
56	Full (12{,}299) vs.\ Depth 0--1 (3{,}951) & $\pm$1\% & No & 1.0 \\
57	                                            & $\pm$2\% & No & 1.0 \\
58	                                            & $\pm$3\% & Yes & $< 10^{-10}$ \\
59	                                            & $\pm$5\% & Yes & $< 10^{-10}$ \\
60	\bottomrule
61	\end{tabular}}
62	\caption{TOST equivalence testing across multiple margins. ``Equiv?'' indicates whether equivalence is established at $\alpha = 0.05$.}
63	\label{tab:tost-margins}
64	\end{table}
65	
66	The full dataset vs.\ random subsample comparison passes equivalence at the $\pm$2\% margin ($p = 10^{-6}$), while the full vs.\ depth 0--1 comparison requires a $\pm$3\% margin.
67	In absolute terms, perplexity differences are small: $\Delta$\,=\,0.032 (full vs.\ random, 1.4\% of baseline) and $\Delta$\,=\,0.052 (full vs.\ depth 0--1, 2.2\% of baseline).
68	
69	Cohen's $d$ values are 86.0 (full vs.\ random) and 119.7 (full vs.\ depth 0--1).
70	These appear large but are unreliable: with only $n$\,=\,3 seeds per condition, the pooled standard deviation is extremely small ($<$0.001), artificially inflating $d$.
71	The inflated effect sizes reflect low seed-level variance (confirming reproducibility) rather than practically meaningful perplexity differences.
72	The TOST framework with pre-specified relative margins provides a more appropriate assessment than Cohen's $d$ in this low-seed regime.
73	However, with only $n{=}3$ seeds per condition, the TOST results have limited generalizability: the test is valid given observed variance but the conclusion generalizes over only three random seeds. We characterize this as a preliminary observation rather than a definitive null result.
74	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bd544fef-9574-4b1f-87ff-82a6335c0fc6",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "9f625f30-a3fb-4d75-a65a-dfedc73b73a1",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_downstream.tex",
      "content": "Can depth-aware data curation improve downstream language model quality?\nWe fine-tune OLMo-2-0425-1B on five data variants (3 seeds each) and evaluate perplexity on a held-out test set (Table~\\ref{tab:downstream}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{lrc}\n\\toprule\n\\textbf{Variant} & \\textbf{$n$} & \\textbf{Test PPL} \\\\\n\\midrule\nAll depths            & 12{,}299 & 2.335 $\\pm$ 0.000 \\\\\nSize-matched (random) & 3{,}951  & 2.367 $\\pm$ 0.000 \\\\\nDepth 0--1 only       & 3{,}951  & 2.387 $\\pm$ 0.001 \\\\\nBinary-filtered       & 3{,}951  & 2.389 $\\pm$ 0.000 \\\\\nDepth 0 only          & 797      & 2.681 $\\pm$ 0.001 \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Downstream fine-tuning perplexity (OLMo-2-0425-1B, mean $\\pm$ std across 3 seeds). At equal sample count, random subsampling (2.367) outperforms depth-aware curation (depth 0--1: 2.387, binary-filtered: 2.389).}\n\\label{tab:downstream}\n\\end{table}\n\nThe results are unambiguous: data quantity dominates depth composition.\nTraining on all 12{,}299 samples yields the lowest perplexity (2.335).\nAt equal sample count ($n$\\,=\\,3{,}951), random subsampling (2.367) \\emph{outperforms} both depth-stratified selection (depth 0--1: 2.387) and binary detection filtering (2.389).\nCross-seed variance is below 0.002 across all variants, which confirms the robustness of this null result.\n\nRestricting training to human-only text (depth 0, $n$\\,=\\,797) produces a sharp perplexity increase to 2.681, driven primarily by the 5$\\times$ reduction in data volume rather than depth composition per se.\n\n\\paragraph{Equivalence testing.}\nWe apply a two one-sided $t$-test (TOST) with a $\\pm$2\\% relative margin (equivalence bounds $\\pm$0.047 on the ppl scale) to formally assess whether the depth-aware and random subsampling conditions produce practically indistinguishable perplexity.\nAt equal sample count ($n$\\,=\\,3{,}951): size-matched (random) ppl\\,=\\,2.367 vs.\\ depth 0--1 ppl\\,=\\,2.387, $\\Delta$\\,=\\,0.020.\nTOST confirms equivalence ($p = 1.1 \\times 10^{-4}$); the two curation strategies yield practically indistinguishable downstream quality within the $\\pm$2\\% margin.\nCross-seed standard deviation is below 0.001 for both variants.\n\nComparing the full dataset ($n$\\,=\\,12{,}299, ppl\\,=\\,2.335) against the depth-filtered subset ($n$\\,=\\,3{,}951, ppl\\,=\\,2.387): TOST \\emph{rejects} equivalence (minimum equivalence margin\\,=\\,0.053, exceeding the $\\pm$2\\% bound), which confirms that data quantity drives perplexity reduction beyond what depth-aware selection can recover.\n\nKnowing the generation depth of a document does not, by itself, make it more or less useful for training; at fixed sample count, depth-aware curation is statistically equivalent to uninformed random subsampling.\n\n\\subsection*{Margin Sensitivity Analysis}\n\nTo assess the robustness of the equivalence conclusion to margin choice, we repeat the TOST procedure across multiple equivalence margins \\cite{lakens_equivalence}, following the recommendation to report sensitivity across plausible bounds rather than relying on a single threshold (Table~\\ref{tab:tost-margins}).\n\n\\begin{table}[h]\n\\centering\n\\small\n\\resizebox{\\linewidth}{!}{%\n\\begin{tabular}{llcc}\n\\toprule\n\\textbf{Comparison} & \\textbf{Margin} & \\textbf{Equiv?} & \\textbf{TOST $p$} \\\\\n\\midrule\nFull (12{,}299) vs.\\ Random (3{,}951) & $\\pm$1\\% & No & 1.0 \\\\\n                                        & $\\pm$2\\% & Yes & $1 \\times 10^{-6}$ \\\\\n                                        & $\\pm$3\\% & Yes & $< 10^{-10}$ \\\\\n                                        & $\\pm$5\\% & Yes & $< 10^{-10}$ \\\\\n\\midrule\nFull (12{,}299) vs.\\ Depth 0--1 (3{,}951) & $\\pm$1\\% & No & 1.0 \\\\\n                                            & $\\pm$2\\% & No & 1.0 \\\\\n                                            & $\\pm$3\\% & Yes & $< 10^{-10}$ \\\\\n                                            & $\\pm$5\\% & Yes & $< 10^{-10}$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\caption{TOST equivalence testing across multiple margins. ``Equiv?'' indicates whether equivalence is established at $\\alpha = 0.05$.}\n\\label{tab:tost-margins}\n\\end{table}\n\nThe full dataset vs.\\ random subsample comparison passes equivalence at the $\\pm$2\\% margin ($p = 10^{-6}$), while the full vs.\\ depth 0--1 comparison requires a $\\pm$3\\% margin.\nIn absolute terms, perplexity differences are small: $\\Delta$\\,=\\,0.032 (full vs.\\ random, 1.4\\% of baseline) and $\\Delta$\\,=\\,0.052 (full vs.\\ depth 0--1, 2.2\\% of baseline).\n\nCohen's $d$ values are 86.0 (full vs.\\ random) and 119.7 (full vs.\\ depth 0--1).\nThese appear large but are unreliable: with only $n$\\,=\\,3 seeds per condition, the pooled standard deviation is extremely small ($<$0.001), artificially inflating $d$.\nThe inflated effect sizes reflect low seed-level variance (confirming reproducibility) rather than practically meaningful perplexity differences.\nThe TOST framework with pre-specified relative margins provides a more appropriate assessment than Cohen's $d$ in this low-seed regime.\nHowever, with only $n{=}3$ seeds per condition, the TOST results have limited generalizability: the test is valid given observed variance but the conclusion generalizes over only three random seeds. We characterize this as a preliminary observation rather than a definitive null result.\n",
      "numLines": 74,
      "startLine": 1,
      "totalLines": 74
    }
  },
  "sourceToolAssistantUUID": "bd544fef-9574-4b1f-87ff-82a6335c0fc6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Tool call

_source line 78 · 2026-05-19T06:18:04.594Z_

<details open><summary>🔧 Tool call — Read · `toolu_015Jx8i5y2okrDnHmjL4J7D4`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_domain.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9f625f30-a3fb-4d75-a65a-dfedc73b73a1",
  "isSidechain": false,
  "requestId": "req_011CbBSW1hfZGRXf4CzPfbSB",
  "type": "assistant",
  "uuid": "b27ad8c5-2d48-4cae-a3a0-a8fd411ada3f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VUGC9G1tjm1wed976VYfJ7",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 48384,
      "cache_read_input_tokens": 36720,
      "output_tokens": 336,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 48384,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 336,
          "cache_read_input_tokens": 36720,
          "cache_creation_input_tokens": 48384,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 48384
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


### Runtime record

_source line 79 · 2026-05-19T06:18:04.658Z_

```json
{
  "parentUuid": "6702e718-5fb3-42b5-a71a-264b4e2a7c54",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "2cccc9b2-1c40-427f-895a-4e4924b5a2c1",
  "timestamp": "2026-05-19T06:18:04.658Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---


### Assistant

_source line 80 · 2026-05-19T06:18:08.337Z_

<details><summary>Logged reasoning block</summary>

```text
Let me check the PDF visual. I need to view the compiled PDF to check page count and formatting.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2cccc9b2-1c40-427f-895a-4e4924b5a2c1",
  "isSidechain": false,
  "requestId": "req_011CbBSWheVa4aSfsCZ3WTAb",
  "type": "assistant",
  "uuid": "299c046c-477c-45e0-a949-e03e52649c7a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Mu59bDz752vFFPGCqFTYHe",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3618,
      "cache_read_input_tokens": 85104,
      "output_tokens": 197,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3618,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 197,
          "cache_read_input_tokens": 85104,
          "cache_creation_input_tokens": 3618,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3618
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


### Assistant

_source line 81 · 2026-05-19T06:18:08.994Z_

现在查看论文 PDF 视觉（页数、格式）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "299c046c-477c-45e0-a949-e03e52649c7a",
  "isSidechain": false,
  "requestId": "req_011CbBSWheVa4aSfsCZ3WTAb",
  "type": "assistant",
  "uuid": "d0ee03ce-89d4-4744-84e3-c2af344f8412",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Mu59bDz752vFFPGCqFTYHe",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3618,
      "cache_read_input_tokens": 85104,
      "output_tokens": 197,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3618,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 197,
          "cache_read_input_tokens": 85104,
          "cache_creation_input_tokens": 3618,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3618
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

_source line 82 · 2026-05-19T06:18:09.807Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__pdf_to_images · `toolu_01U2Z72BCfe9hsKAzQrB79fg`</summary>

```json
{
  "pdf_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.pdf",
  "pages": "1-12",
  "dpi": 150
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d0ee03ce-89d4-4744-84e3-c2af344f8412",
  "isSidechain": false,
  "requestId": "req_011CbBSWheVa4aSfsCZ3WTAb",
  "type": "assistant",
  "uuid": "e50499b8-8243-4c27-93f2-864a2037a680",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Mu59bDz752vFFPGCqFTYHe",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3618,
      "cache_read_input_tokens": 85104,
      "output_tokens": 197,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3618,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 197,
          "cache_read_input_tokens": 85104,
          "cache_creation_input_tokens": 3618,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3618
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


### Runtime record

_source line 83_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 2  **你的审查侧重：新颖性 + 论文完整性 + 写作质量 + 格式合规**  ### 论文信息 - **标题**: Depth Profiling: Classifying Recursive Generation Depth in Base LLM Text Chains - **路径**: `projec…",
  "leafUuid": "e50499b8-8243-4c27-93f2-864a2037a680",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Runtime record

_source line 84_

```json
{
  "type": "ai-title",
  "aiTitle": "Review depth profiling LLM paper for EMNLP",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Tool result

_source line 85 · 2026-05-19T06:18:14.523Z_

<details><summary>↩ Tool result · `toolu_01U2Z72BCfe9hsKAzQrB79fg`</summary>

```text
Error: result (8,382,519 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint--claude-sessions-review-reviewer-2-3f564e41/34cea30f-783a-4e65-9506-a050519fc721/tool-results/mcp-agent-ml-research-pdf_to_images-1779171494508.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint--claude-sessions-review-reviewer-2-3f564e41/34cea30f-783a-4e65-9506-a050519fc721/tool-results/mcp-agent-ml-research-pdf_to_images-1779171494508.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint--claude-sessions-review-reviewer-2-3f564e41/34cea30f-783a-4e65-9506-a050519fc721/tool-results/mcp-agent-ml-research-pdf_to_images-1779171494508.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e50499b8-8243-4c27-93f2-864a2037a680",
  "isSidechain": false,
  "promptId": "2c23af36-9b75-4eca-8adb-e3cf5d79a4e4",
  "type": "user",
  "uuid": "98e93842-0783-4866-9ebc-69376f88e505",
  "toolUseResult": "Error: result (8,382,519 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint--claude-sessions-review-reviewer-2-3f564e41/34cea30f-783a-4e65-9506-a050519fc721/tool-results/mcp-agent-ml-research-pdf_to_images-1779171494508.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint--claude-sessions-review-reviewer-2-3f564e41/34cea30f-783a-4e65-9506-a050519fc721/tool-results/mcp-agent-ml-research-pdf_to_images-1779171494508.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint--claude-sessions-review-reviewer-2-3f564e41/34cea30f-783a-4e65-9506-a050519fc721/tool-results/mcp-agent-ml-research-pdf_to_images-1779171494508.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
  "mcpMeta": {
    "storage": "sanitized-trace-archive",
    "source_line": 85,
    "serialized_bytes": 8382556,
    "serialized_sha256": "205c39d5c17d6054c22ffe713f833338abb6da97b47a52b9d9438dd0eddfa22f",
    "note": "Complete sanitized source is retained in trace-files.tar.gz."
  },
  "sourceToolAssistantUUID": "e50499b8-8243-4c27-93f2-864a2037a680",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---


### Runtime record

_source line 86_

```json
{
  "type": "last-prompt",
  "lastPrompt": "[Round 1 审稿请求]: ## Round 1 审稿任务 — Reviewer 2  **你的审查侧重：新颖性 + 论文完整性 + 写作质量 + 格式合规**  ### 论文信息 - **标题**: Depth Profiling: Classifying Recursive Generation Depth in Base LLM Text Chains - **路径**: `projec…",
  "leafUuid": "98e93842-0783-4866-9ebc-69376f88e505",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Runtime record

_source line 87_

```json
{
  "type": "ai-title",
  "aiTitle": "Review depth profiling LLM paper for EMNLP",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721"
}
```

---


### Assistant

_source line 88 · 2026-05-19T06:18:17.112Z_

<details><summary>Logged reasoning block</summary>

```text
The PDF images are too large to include in my context. Let me try to view individual pages.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "98e93842-0783-4866-9ebc-69376f88e505",
  "isSidechain": false,
  "requestId": "req_011CbBSXSD5woTpcFzm7nEmy",
  "type": "assistant",
  "uuid": "006a8871-1908-45a3-a12f-e8ff4ea88d8f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PXv2uckrMYxkUsHqijDzxC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 749,
      "cache_read_input_tokens": 88722,
      "output_tokens": 430,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 749,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 430,
          "cache_read_input_tokens": 88722,
          "cache_creation_input_tokens": 749,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 749
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


### Assistant

_source line 89 · 2026-05-19T06:18:17.620Z_

PDF 太大了。让我逐页查看。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "006a8871-1908-45a3-a12f-e8ff4ea88d8f",
  "isSidechain": false,
  "requestId": "req_011CbBSXSD5woTpcFzm7nEmy",
  "type": "assistant",
  "uuid": "f2ecdd93-ff88-4ca0-80fe-fe713373ade2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PXv2uckrMYxkUsHqijDzxC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 749,
      "cache_read_input_tokens": 88722,
      "output_tokens": 430,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 749,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 430,
          "cache_read_input_tokens": 88722,
          "cache_creation_input_tokens": 749,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 749
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

_source line 90 · 2026-05-19T06:18:18.614Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__pdf_to_images · `toolu_01QVvutthcpt1FZuxosVGgdt`</summary>

```json
{
  "pdf_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.pdf",
  "pages": "1",
  "dpi": 150
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f2ecdd93-ff88-4ca0-80fe-fe713373ade2",
  "isSidechain": false,
  "requestId": "req_011CbBSXSD5woTpcFzm7nEmy",
  "type": "assistant",
  "uuid": "2e42ba73-5ae4-4ca3-ae27-d613f6202f93",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/.claude/sessions/review_reviewer_2_3f564e41",
  "sessionId": "34cea30f-783a-4e65-9506-a050519fc721",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PXv2uckrMYxkUsHqijDzxC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 749,
      "cache_read_input_tokens": 88722,
      "output_tokens": 430,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 749,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 430,
          "cache_read_input_tokens": 88722,
          "cache_creation_input_tokens": 749,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 749
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
