# Research conversation: <project_context> # 项目: contrastive_entrain_calib ## 运行环境 - 服务器名: westd-29046 - SSH 账户: root（调用 ssh_execute / submit_tra

**The Probe Reward Trap: Behavioral Death Before Distributional Collapse in Sycophancy Calibration (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 37
- **Recorded user turns:** 1
- **Tool calls:** 8
- **Original source:** `logs/chats/exported-trajectories/account-2/c6535802-70d7-423e-858d-6fdcde2bf569.jsonl`
- **Structured JSON:** [`722cd5170d5b5d08e57e.json`](../../sessions/72/722cd5170d5b5d08e57e.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-20T07:49:41.664Z_

````json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-20T07:49:41.664Z",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "content": "&lt;project_context>\n# 项目: contrastive_entrain_calib\n\n## 运行环境\n- 服务器名: westd-29046\n- SSH 账户: root（调用 ssh_execute / submit_training_job 时传入 account=\"root\"）\n- SSH 连接命令: ssh connect.westd.seetacloud.com  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP\n- 项目代码根目录: /root/contrastive_entrain_calib\n\n\n## 环境搭建\n连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。\n\n## 输出风格\n回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。\n&lt;/project_context>\n## 任务：撰写论文 §4 Cosine R1: Structural Failure\n\n你是论文写作 Worker。请撰写 \"Cosine R1: Structural Failure\" 章节的完整 LaTeX 内容。\n\n### 论文背景\n\n**标题**: \"Discriminability Without Utility: Why Sycophancy Directions Fail as RL Rewards\"\n**核心叙事**: d_syc AUROC 0.82 能 discriminate sycophancy，但 3 种 R1 formulation 全部失败。§3 已证明方向质量不是瓶颈。§4 展示 cosine-based R1 的结构性失败链，§5 展示 binary probe R1 的 reward trap。两者互补：cosine 太惩罚（penalizes all change），probe 太宽容（rewards all non-change）。\n**会议**: EMNLP 2026, 8 页正文\n\n### 章节规格\n\n- **LaTeX title**: `\\section{Cosine \\texorpdfstring{$\\rone$}{R1}: Structural Failure}`\n- **Label**: `\\label{sec:cosine_failure}`\n- **Word budget**: ~700 words\n- **Tables**: tab2_cosine_chain（4 行，4 个实验配置的 failure chain）\n- **Figures**: 引用 fig2_cosine_failure（Figure~\\ref{fig:cosine_failure}，暂未生成）\n\n### 叙事结构\n\n本章讲述一个 **4-experiment systematic failure chain**。每个配置解决了上一个的问题，但暴露了更深层的结构性限制。这不是\"我们试了很多东西没成功\"——而是每一步都提供了诊断性信息，共同指向一个统一的 root cause。\n\n### 核心内容（4 个实验 + root cause 分析）\n\n**F1a: exp-002 — tanh(dot/20) gate saturation**\n- 配置: R1 = tanh(dot(h, d_syc)/20), w1=0.25, w3=0.75 (后调整为 w1=0.15, w3=0.65)\n- 失败: activation norms 100-1200x across layers，tanh gate 饱和，R1 contribution → 0\n- 在 step 955 被 kill\n- 诊断: normalization 方案不可行，改用 cosine（norm-invariant）\n\n**F1b: exp-002v2 — raw cosine R1 信号太弱**\n- 配置: R1 = cos(h, d_syc), w1=0.25, w3=0.75\n- 失败: R1 ≈ 0 throughout training，功能上等价于 R3-only\n- 原因: cosine gap (valid vs invalid) ≈ 0.098 (7-layer mean)，信号太微弱\n- 被 kill\n\n**F1c: exp002v2-recalib — cosine + recalibration 导致 mode collapse**\n- 配置: 从 exp-002v2 checkpoint-500 恢复，加 periodic d_syc recalibration\n- 失败: mode collapse, entropy 0.069, mean response length 62 tokens\n- 原因: stale → fresh direction 切换产生 reward 不连续，destabilize training\n\n**F1d: exp-002v3 — 5x scaled cosine 放大了错误信号**\n- 配置: R1 = 5·cos(h, d_syc), w1=0.4, w3=0.6\n- 失败: R3 在 step 100 就饱和 (0.9998)，combined reward 退化为只有 R1\n- R1 mean 在 -0.46 到 +0.41 之间震荡，无持续正趋势\n- Step 2160 mode collapse: entropy 0.056→0.026, frac_zero_std 0.125→0.419\n- Root cause: 5x 放大同时放大了 noise，R3 饱和后 R1 是唯一信号但太 noisy\n\n**统一 Root Cause**:\n- cosine gap valid vs invalid ≈ 0.098 (7-layer mean)\n- d_syc projection 把 \"correctly revises belief\" 和 \"sycophantically capitulates\" 混在一起，因为两者都 TOWARD user position\n- Recalibration 把 AUROC 从 0.82 提到 0.91 但 reward 仍然失败 → 方向质量不是瓶颈\n- 根本问题: d_syc 编码 belief change DIRECTION 但不编码 change WARRANT\n\n### Registry 数据\n\n**exp-002**: status=DONE, conclusion=killed at step 955, R1 tanh 饱和\n**exp-002v2**: status=DONE, conclusion=killed, R1≈0 throughout\n**exp002v2-recalib**: status=DONE, conclusion=negative, mode collapse entropy=0.069\n**exp-002v3**: status=DONE, conclusion=negative\n- collapse_timeline: phase1 step 100-300 (length 247→80, entropy 0.45→0.10), low_entropy_plateau step 300-2150 (entropy 0.07-0.10), terminal collapse step 2160\n- entropy_at_kill: 0.006\n- r3_saturation_step: 100, r3_saturated_value: 0.9998\n- r1_behavior: \"mean oscillated -0.46 to +0.41, no sustained positive trend despite 5x scaling\"\n- root_cause: \"R3 saturated at step 100 → combined reward degenerates to only R1 → cosine R1 signal too noisy\"\n\n### Cosine Failure Chain Table (tab2)\n\n```latex\n\\begin{table}[t]\n\\centering\n\\caption{Cosine $\\rone$ failure chain...}\n\\label{tab:cosine_chain}\n\\begin{tabular}{lllll}\n\\toprule\nConfig & $\\rone$ Formula & $w_1$ & Outcome & Root Cause \\\\\n\\midrule\nexp-002 & $\\tanh(\\mathbf{h}\\cdot\\dsyc/20)$ & 0.25 & Gate saturation & Norm mismatch \\\\\nexp-002v2 & $\\cos(\\mathbf{h}, \\dsyc)$ & 0.25 & $\\rone \\approx 0$ & Gap too small \\\\\n+recalib & $\\cos(\\mathbf{h}, \\dsyc)$ & 0.25 & Mode collapse & Reward discontinuity \\\\\nexp-002v3 & $5\\cos(\\mathbf{h}, \\dsyc)$ & 0.4 & Mode collapse & $\\rthree$ saturation + noise \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n```\n\n### 前序章节参考\n\n§2 定义了: d_syc (Eq 1), R = w1·R1 + w3·R3 (Eq 2), 三种 F1/F2/F3, SYCONScore (Eq 3)\n§3 建立了: d_syc AUROC 0.827 (Qwen3-8B), 0.779 (Llama-3-8B), direction quality not bottleneck\n\n自定义命令: `\\dsyc`, `\\rone`, `\\rthree`, `\\tof`, `\\nof`, `\\sycon`\n\n### 写作规范\n\n1. **先 Read `/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md`**\n2. **先 Read `/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md`**\n3. 禁止 em-dash (—) 和解释性 en-dash (–)\n4. 禁止 -ing 短语结尾\n5. 表格用 booktabs\n6. 叙事语气: analytical, systematic（不是\"我们试了很多东西没成功\"而是\"每一步提供了诊断信息指向统一 root cause\"）\n7. 每个实验引用 exp-id 方便 provenance tracking（如 \"Configuration F1a (exp-002)\"）\n\n### 可用引用 keys\n\nzou2023repe, rimsky2024caa, shao2024grpo, gao2023scaling, zhang2026latentgrpo\n\n### 输出要求\n\n包含 `\\section{...}` 行。\n写入: `/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/docs/paper/sections/cosine_failure.tex`\n"
}
````

---

### Runtime record

_source line 2 · 2026-05-20T07:49:41.668Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-20T07:49:41.668Z",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569"
}
```

---

## Round 1

35 recorded events

### User

_source line 3 · 2026-05-20T07:49:41.705Z_

&lt;project_context>
# 项目: contrastive_entrain_calib

## 运行环境
- 服务器名: westd-29046
- SSH 账户: root（调用 ssh_execute / submit_training_job 时传入 account="root"）
- SSH 连接命令: ssh connect.westd.seetacloud.com  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP
- 项目代码根目录: /root/contrastive_entrain_calib


## 环境搭建
连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。

## 输出风格
回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。
&lt;/project_context>
## 任务：撰写论文 §4 Cosine R1: Structural Failure

你是论文写作 Worker。请撰写 "Cosine R1: Structural Failure" 章节的完整 LaTeX 内容。

### 论文背景

**标题**: "Discriminability Without Utility: Why Sycophancy Directions Fail as RL Rewards"
**核心叙事**: d_syc AUROC 0.82 能 discriminate sycophancy，但 3 种 R1 formulation 全部失败。§3 已证明方向质量不是瓶颈。§4 展示 cosine-based R1 的结构性失败链，§5 展示 binary probe R1 的 reward trap。两者互补：cosine 太惩罚（penalizes all change），probe 太宽容（rewards all non-change）。
**会议**: EMNLP 2026, 8 页正文

### 章节规格

- **LaTeX title**: `\section{Cosine \texorpdfstring{$\rone$}{R1}: Structural Failure}`
- **Label**: `\label{sec:cosine_failure}`
- **Word budget**: ~700 words
- **Tables**: tab2_cosine_chain（4 行，4 个实验配置的 failure chain）
- **Figures**: 引用 fig2_cosine_failure（Figure~\ref{fig:cosine_failure}，暂未生成）

### 叙事结构

本章讲述一个 **4-experiment systematic failure chain**。每个配置解决了上一个的问题，但暴露了更深层的结构性限制。这不是"我们试了很多东西没成功"——而是每一步都提供了诊断性信息，共同指向一个统一的 root cause。

### 核心内容（4 个实验 + root cause 分析）

**F1a: exp-002 — tanh(dot/20) gate saturation**
- 配置: R1 = tanh(dot(h, d_syc)/20), w1=0.25, w3=0.75 (后调整为 w1=0.15, w3=0.65)
- 失败: activation norms 100-1200x across layers，tanh gate 饱和，R1 contribution → 0
- 在 step 955 被 kill
- 诊断: normalization 方案不可行，改用 cosine（norm-invariant）

**F1b: exp-002v2 — raw cosine R1 信号太弱**
- 配置: R1 = cos(h, d_syc), w1=0.25, w3=0.75
- 失败: R1 ≈ 0 throughout training，功能上等价于 R3-only
- 原因: cosine gap (valid vs invalid) ≈ 0.098 (7-layer mean)，信号太微弱
- 被 kill

**F1c: exp002v2-recalib — cosine + recalibration 导致 mode collapse**
- 配置: 从 exp-002v2 checkpoint-500 恢复，加 periodic d_syc recalibration
- 失败: mode collapse, entropy 0.069, mean response length 62 tokens
- 原因: stale → fresh direction 切换产生 reward 不连续，destabilize training

**F1d: exp-002v3 — 5x scaled cosine 放大了错误信号**
- 配置: R1 = 5·cos(h, d_syc), w1=0.4, w3=0.6
- 失败: R3 在 step 100 就饱和 (0.9998)，combined reward 退化为只有 R1
- R1 mean 在 -0.46 到 +0.41 之间震荡，无持续正趋势
- Step 2160 mode collapse: entropy 0.056→0.026, frac_zero_std 0.125→0.419
- Root cause: 5x 放大同时放大了 noise，R3 饱和后 R1 是唯一信号但太 noisy

**统一 Root Cause**:
- cosine gap valid vs invalid ≈ 0.098 (7-layer mean)
- d_syc projection 把 "correctly revises belief" 和 "sycophantically capitulates" 混在一起，因为两者都 TOWARD user position
- Recalibration 把 AUROC 从 0.82 提到 0.91 但 reward 仍然失败 → 方向质量不是瓶颈
- 根本问题: d_syc 编码 belief change DIRECTION 但不编码 change WARRANT

### Registry 数据

**exp-002**: status=DONE, conclusion=killed at step 955, R1 tanh 饱和
**exp-002v2**: status=DONE, conclusion=killed, R1≈0 throughout
**exp002v2-recalib**: status=DONE, conclusion=negative, mode collapse entropy=0.069
**exp-002v3**: status=DONE, conclusion=negative
- collapse_timeline: phase1 step 100-300 (length 247→80, entropy 0.45→0.10), low_entropy_plateau step 300-2150 (entropy 0.07-0.10), terminal collapse step 2160
- entropy_at_kill: 0.006
- r3_saturation_step: 100, r3_saturated_value: 0.9998
- r1_behavior: "mean oscillated -0.46 to +0.41, no sustained positive trend despite 5x scaling"
- root_cause: "R3 saturated at step 100 → combined reward degenerates to only R1 → cosine R1 signal too noisy"

### Cosine Failure Chain Table (tab2)

```latex
\begin{table}[t]
\centering
\caption{Cosine $\rone$ failure chain...}
\label{tab:cosine_chain}
\begin{tabular}{lllll}
\toprule
Config & $\rone$ Formula & $w_1$ & Outcome & Root Cause \\
\midrule
exp-002 & $\tanh(\mathbf{h}\cdot\dsyc/20)$ & 0.25 & Gate saturation & Norm mismatch \\
exp-002v2 & $\cos(\mathbf{h}, \dsyc)$ & 0.25 & $\rone \approx 0$ & Gap too small \\
+recalib & $\cos(\mathbf{h}, \dsyc)$ & 0.25 & Mode collapse & Reward discontinuity \\
exp-002v3 & $5\cos(\mathbf{h}, \dsyc)$ & 0.4 & Mode collapse & $\rthree$ saturation + noise \\
\bottomrule
\end{tabular}
\end{table}
```

### 前序章节参考

§2 定义了: d_syc (Eq 1), R = w1·R1 + w3·R3 (Eq 2), 三种 F1/F2/F3, SYCONScore (Eq 3)
§3 建立了: d_syc AUROC 0.827 (Qwen3-8B), 0.779 (Llama-3-8B), direction quality not bottleneck

自定义命令: `\dsyc`, `\rone`, `\rthree`, `\tof`, `\nof`, `\sycon`

### 写作规范

1. **先 Read `/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md`**
2. **先 Read `/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md`**
3. 禁止 em-dash (—) 和解释性 en-dash (–)
4. 禁止 -ing 短语结尾
5. 表格用 booktabs
6. 叙事语气: analytical, systematic（不是"我们试了很多东西没成功"而是"每一步提供了诊断信息指向统一 root cause"）
7. 每个实验引用 exp-id 方便 provenance tracking（如 "Configuration F1a (exp-002)"）

### 可用引用 keys

zou2023repe, rimsky2024caa, shao2024grpo, gao2023scaling, zhang2026latentgrpo

### 输出要求

包含 `\section{...}` 行。
写入: `/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/docs/paper/sections/cosine_failure.tex`


<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "76de2f70-ac1e-444d-9c77-3c394a6cfdb7",
  "type": "user",
  "uuid": "484dc65c-3ad0-47c6-b427-422d5457a70b",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-20T07:49:41.704Z_

```json
{
  "parentUuid": "484dc65c-3ad0-47c6-b427-422d5457a70b",
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
      "mcp__agent-ml-research__auto_build_provenance",
      "mcp__agent-ml-research__bootstrap_provenance",
      "mcp__agent-ml-research__check_figures_and_layout",
      "mcp__agent-ml-research__check_paper_consistency",
      "mcp__agent-ml-research__check_provenance_completeness",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__edit_paper_section",
      "mcp__agent-ml-research__get_image_info",
      "mcp__agent-ml-research__get_worker_status",
      "mcp__agent-ml-research__list_artifacts",
      "mcp__agent-ml-research__list_workers",
      "mcp__agent-ml-research__load_project_config",
      "mcp__agent-ml-research__overleaf_init",
      "mcp__agent-ml-research__overleaf_pull",
      "mcp__agent-ml-research__overleaf_push",
      "mcp__agent-ml-research__overleaf_status",
      "mcp__agent-ml-research__overleaf_sync",
      "mcp__agent-ml-research__paper_agent_post_to_director",
      "mcp__agent-ml-research__paper_agent_request_review",
      "mcp__agent-ml-research__paper_compile_and_check",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__send_progress",
      "mcp__agent-ml-research__spawn_worker",
      "mcp__agent-ml-research__verify_references",
      "mcp__agent-ml-research__write_paper_section"
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
      "mcp__agent-ml-research__auto_build_provenance",
      "mcp__agent-ml-research__bootstrap_provenance",
      "mcp__agent-ml-research__check_figures_and_layout",
      "mcp__agent-ml-research__check_paper_consistency",
      "mcp__agent-ml-research__check_provenance_completeness",
      "mcp__agent-ml-research__cleanup_pdf_images",
      "mcp__agent-ml-research__compute_coverage_matrix",
      "mcp__agent-ml-research__edit_paper_section",
      "mcp__agent-ml-research__get_image_info",
      "mcp__agent-ml-research__get_worker_status",
      "mcp__agent-ml-research__list_artifacts",
      "mcp__agent-ml-research__list_workers",
      "mcp__agent-ml-research__load_project_config",
      "mcp__agent-ml-research__overleaf_init",
      "mcp__agent-ml-research__overleaf_pull",
      "mcp__agent-ml-research__overleaf_push",
      "mcp__agent-ml-research__overleaf_status",
      "mcp__agent-ml-research__overleaf_sync",
      "mcp__agent-ml-research__paper_agent_post_to_director",
      "mcp__agent-ml-research__paper_agent_request_review",
      "mcp__agent-ml-research__paper_compile_and_check",
      "mcp__agent-ml-research__pdf_to_images",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_roadmap",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__send_progress",
      "mcp__agent-ml-research__spawn_worker",
      "mcp__agent-ml-research__verify_references",
      "mcp__agent-ml-research__write_paper_section"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "fe0d6b85-feb6-475f-91e0-c695b3e12208",
  "timestamp": "2026-05-20T07:49:41.704Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-20T07:49:41.704Z_

```json
{
  "parentUuid": "fe0d6b85-feb6-475f-91e0-c695b3e12208",
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
  "uuid": "73f6a54a-623c-4f16-9288-0a859de0b14c",
  "timestamp": "2026-05-20T07:49:41.704Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-20T07:49:41.704Z_

```json
{
  "parentUuid": "73f6a54a-623c-4f16-9288-0a859de0b14c",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "5266ec04-5217-4ba4-a661-768afe17331c",
  "timestamp": "2026-05-20T07:49:41.704Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 7_

```json
{
  "type": "ai-title",
  "aiTitle": "Write cosine R1 structural failure section",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569"
}
```

---

### Assistant

_source line 8 · 2026-05-20T07:49:44.885Z_

I'll read the writing norms and LaTeX skill files first, then draft the section.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5266ec04-5217-4ba4-a661-768afe17331c",
  "isSidechain": false,
  "requestId": "req_011CbDTJq42g6NhE85mBbRLK",
  "type": "assistant",
  "uuid": "a0c68b18-9259-4b77-8200-b7ce8c3d7f96",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0187PkzsZup1bbq5dR4N8wV9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14019,
      "cache_read_input_tokens": 11841,
      "output_tokens": 230,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14019,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 230,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 14019,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14019
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

_source line 9 · 2026-05-20T07:49:45.491Z_

<details open><summary>🔧 Tool call — Read · `toolu_01FGwEW8njcs7ApGNtfHPVeA`</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a0c68b18-9259-4b77-8200-b7ce8c3d7f96",
  "isSidechain": false,
  "requestId": "req_011CbDTJq42g6NhE85mBbRLK",
  "type": "assistant",
  "uuid": "31919f66-3709-42d1-b153-8fe33171cd3b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0187PkzsZup1bbq5dR4N8wV9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14019,
      "cache_read_input_tokens": 11841,
      "output_tokens": 230,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14019,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 230,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 14019,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14019
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

_source line 10 · 2026-05-20T07:49:45.510Z_

<details><summary>↩ Tool result · `toolu_01FGwEW8njcs7ApGNtfHPVeA`</summary>

````text
1	---
2	name: paper-writing-norms
3	description: 顶会级别论文写作风格规范——章节写法（Abstract/Intro/Related Work）、去 AI 风格、视觉密度、叙事哲学。Paper Agent 和 Worker 写论文章节时必须加载。
4	allowed-tools: [Read, Write, Edit, Glob, Grep]
5	scope: global
6	version: 2
7	priority: 9
8	tags:
9	  - writing
10	  - paper
11	  - style
12	  - norms
13	roles:
14	  - agent
15	  - worker
16	  - paper_agent
17	---
18	
19	# 论文写作风格规范
20	
21	> 核心哲学：**论文是一个有说服力的故事，不是实验报告。** 审稿人在几十秒内判断论文价值——如果 Abstract 和 Introduction 读起来像实验日志，论文就已经失败了。
22	
23	---
24	
25	## 一、总体写作哲学
26	
27	### 1.1 故事驱动，不是数据堆砌
28	
29	- 论文必须以"故事线"为核心展开：问题 → 洞察 → 方法 → 验证
30	- 禁止大量实验数据堆砌——每个数字出现必须服务于叙事推进
31	- 附录内容必须在正文中有明确引用且融入叙事，禁止简单堆砌
32	- 如果附录数据对核心叙事有重大影响，根据附录数据调整论文 framing
33	
34	### 1.2 主线统一性
35	
36	- 当 idea 在研究过程中发生变化后，**必须重审全文逻辑**
37	- 常见问题：Introduction 讲的故事 A，Method 做的是故事 B，Results 又在讲故事 C
38	- 修复方式：从最终实验结论反推，重写 Introduction 的问题定义和动机
39	- 每次 idea 调整后检查：Abstract → Introduction → Method → Results → Discussion → Conclusion 是否形成一条连贯主线
40	
41	### 1.3 专有名词必须有定义
42	
43	- 首次出现的专有名词/缩写必须给出完整定义和解释
44	- Abstract 中使用的缩写也必须在 Abstract 内定义（如 LLM = Large Language Model）
45	- 不能假设读者知道你自己定义的术语——论文从来没解释过的概念不能直接使用
46	- 通用规则：如果一个非标准术语第一次出现时没有括号定义，就是写作 bug
47	
48	### 1.4 写作前必读同类优秀论文
49	
50	- 每个章节动笔前，找 **2-3 篇目标会议近 1-2 年的高分论文**作为风格参考——同类问题或同类方法皆可
51	- 重点学：
52	  - Abstract 怎么用最少篇幅讲完故事
53	  - Introduction 怎么从大问题切入到具体贡献
54	  - Related Work 怎么 positioning 自己（不是 survey）
55	  - Table/Figure 怎么压缩信息密度
56	- **不是抄袭**，是学习同行的故事节奏和审美——不同子领域叙事节奏差异很大
57	- 实操：Paper Agent 可以从 `literature_map.yaml` 中挑 `role=foundation` 或 `role=direct-competitor` 的论文，把 `{title, venue, year, abstract}` 附在 Worker 的 task_prompt 中作为概念参考；如需学习写作风格本身，让 Worker 通过 WebSearch 取得论文链接并 fetch 全文
58	
59	---
60	
61	## 二、Abstract 写作规范
62	
63	### 2.1 四个必答问题（150-250 words）
64	
65	Abstract 必须在很短的篇幅内清楚回答：
66	1. **研究什么问题** — 1-2 句话交代背景和痛点
67	2. **为什么重要** — 现有方法的不足（不用写太多）
68	3. **本文提出什么** — 核心贡献的关键机制（简要，不堆砌细节）
69	4. **结果说明什么** — 用具体实验结论支撑贡献
70	
71	### 2.2 禁忌
72	
73	- **禁止堆砌数据**：Abstract 不是 Results 的缩写。最多引用 2-3 个关键数字，要服务于 claim
74	- **禁止过度宣传**：不说 "revolutionary"、"groundbreaking"
75	- **禁止写成 Introduction 的缩写**：Abstract 是独立阅读单元
76	- **禁止术语堆积**：如果审稿人几十秒内判断不出价值，就失败了
77	- **缩写必须定义**：Abstract 中首次出现的缩写必须展开
78	
79	### 2.3 审稿人视角检验
80	
81	写完后用这个标准自检：审稿人能否在 30 秒内判断——
82	- 问题是否重要？
83	- 方法是否清楚？
84	- 贡献是否可信？
85	- 结果是否有说服力？
86	
87	---
88	
89	## 三、Introduction 写作规范
90	
91	### 3.1 完整叙事线（5 段结构）
92	
93	Introduction 需要从一个清晰、重要的问题切入，逐步把读者带到核心贡献：
94	
95	1. **研究背景**（1-2 段）：大模型在某类能力/应用中已取得进展，但仍存在一个关键瓶颈
96	2. **问题重要性**（1 段）：结合真实应用、已有方法局限或当前趋势，说明这不是小问题
97	3. **现有方法不足**（1 段）：系统梳理为什么不够（依赖更大模型/更多数据/更复杂推理/更高成本，或只在特定 benchmark 有效）
98	4. **本文核心想法**（1 段）：我们观察到什么、提出了什么方法、为什么能解决上述问题
99	5. **贡献总结**（列表）：清楚列出方法贡献、实验贡献和分析贡献
100	
101	### 3.2 整体叙事结构
102	
103	```
104	现有进展 → 关键缺口 → 本文洞察 → 方法概述 → 实验证据 → 贡献总结
105	```
106	
107	### 3.3 禁忌
108	
109	- **禁止泛泛介绍**：不要开头就写 "LLMs have shown remarkable capabilities..."，要从具体问题切入
110	- **禁止缺少过渡**：每段之间必须有逻辑连接
111	- **禁止实验报告风格**：Introduction 不是 "我们做了 X 实验得到了 Y 结果" 的罗列
112	- 每条 Contribution 必须有对应的 section/table 支撑
113	- Contribution 列表中不能出现未在前文铺垫过的概念
114	
115	---
116	
117	## 四、Related Work 写作规范
118	
119	### 4.1 目标
120	
121	让审稿人相信：作者理解这个领域，知道自己的方法站在什么位置，清楚相对已有工作的真实增量在哪里。
122	
123	### 4.2 结构要求
124	
125	- 把已有工作分成几个清晰的主题（如模型训练、推理增强、工具调用、数据构建、评测等）
126	- 每类简要说明：已有方法做了什么、解决了哪些问题、和本文的关系
127	- 帮助读者理解：哪些是本文直接继承的，哪些方法不同但解决相似问题，哪些留下了本文要解决的缺口
128	
129	### 4.3 禁忌
130	
131	- **禁止论文堆砌**：不要写成 "A proposed X. B proposed Y. C proposed Z." 的列表
132	- **目标不是展示读了多少论文**，而是做归纳和比较
133	- Contribution claim（"To our knowledge, no prior work..."）应放在 Introduction，不在 Related Work
134	
135	### 4.4 引用充足度
136	
137	- 引用必须覆盖：**直接相关方法、baseline 论文、评测 benchmark 论文、理论基础**
138	- 任何一类缺失，审稿人会立刻看出来调研不充分
139	- 引用密度参照目标会议近年录用论文的量级——明显偏少意味着 Related Work 调研不足
140	
141	---
142	
143	## 五、去 AI 写作风格（硬规则）
144	
145	以下模式是 AI 生成文本的典型标志，审稿人一眼能看出。**必须全部消除。**
146	
147	### 5.1 严禁破折号（最显著的 AI 痕迹）
148	
149	**这是 AI 写作最容易被识别的标志，审稿人最敏感。单列为最高优先级硬规则。**
150	
151	- 解释性 em-dash（—，U+2014）和 en-dash（–，U+2013）必须**全部删除**
152	- 替代方式：用逗号、括号或拆分为两个句子
153	- 强制检查命令：
154	  ```bash
155	  grep -n "—" paper/*.tex     # em-dash，每处人工判断是否必要
156	  grep -n " – " paper/*.tex   # 解释性 en-dash，几乎都应删除
157	  ```
158	- 例外（允许保留）：表格分隔符、数字范围（`2020–2024`、`pp. 12–18`）、专有名词（`Newton–Raphson`）
159	
160	### 5.2 段落与句式
161	
162	- **禁止过度分段**：不需要每 2-3 句就换段，自然段 5-8 句是正常的
163	- **减少关系从句**（which, that, who）：能用简洁直接的句子就不用从句
164	- **禁止 -ing 短语结尾**：如 "..., highlighting the applicability of..." / "..., demonstrating the effectiveness of..."。这是 AI 写作最典型的标志之一
165	- **禁止连续使用 "Furthermore" / "Moreover" / "Additionally"**：一段内最多用一个过渡词
166	- **避免 "It is worth noting that..." / "Notably, ..."**：直接写要说的内容
167	
168	### 5.3 用词黑名单
169	
170	- 避免 "delve into" / "leverage" / "utilize" / "facilitate" — 用 "explore" / "use" / "enable"
171	- 避免 "a myriad of" / "a plethora of" — 用 "many" / "various"
172	- 避免 "in the realm of" / "in the context of" — 直接说
173	- 避免 "paradigm shift" / "novel" 过度使用
174	
175	### 5.4 校对清单（4 步）
176	
177	1. 全文 proofread 语法和拼写
178	2. 检查所有代词/指示词（this, that, it）是否指代明确
179	3. **`grep "—"` + `grep " – "` 全文清零**（删除所有解释性 dash，§5.1）
180	4. `grep "ing,"` 模式——大部分 -ing 分词短语需要改写
181	
182	---
183	
184	## 六、图表与视觉规范
185	
186	### 6.1 知识密度原则
187	
188	- **图表的信息必须紧凑**——不能为了美观而留大量白空间
189	- 一张图如果只传达一个简单信息，要么缩小要么合并到其他图中
190	- 能用 inline text 说清的不要占一整个 Figure
191	
192	### 6.2 表格规范
193	
194	- 表格和正文文字不能视觉重叠（检查 column 宽度和 alignment）
195	- 小数精度全表统一
196	- 最优加粗、次优下划线
197	- Caption 必须自包含
198	
199	### 6.3 图片规范
200	
201	- 数值标签不能被线、bar、点遮住——用白色背景或偏移标签
202	- 图中字体 >= 7pt（打印后仍可读）
203	- 栏宽约束需匹配目标 venue 模板要求
204	- 概念图/流程图要有信息量，不要画一个 trivial 的 pipeline 然后占半页
205	
206	### 6.4 空间效率
207	
208	- 顶会正文页数严格受限（具体页数查目标会议官网），每 cm² 都是宝贵资源
209	- 优先使用 `\subfigure` 合并相关图
210	- Table 能 inline 就不要单独浮动
211	- 图表占比与其对叙事的贡献成正比
212	
213	### 6.5 页面节奏
214	
215	好论文的页面有节奏感——text、equation、figure 交替出现，读者视觉不疲劳：
216	
217	- **text-equation-figure 三重奏**：重要概念用"文字解释 → 公式定义 → 图表直觉"三步展开
218	- 连续 2 页纯文本（无 figure/equation/table）→ 穿插一个 display item 打破节奏
219	- 连续 2 个 figure 页（整页被 float 占满）→ 至少隔 1 段文字再放下一个 float
220	- Section heading 不孤悬页底（heading 后至少跟 2 行正文，否则强制分页）
221	- 最后一页内容 ≥ 2/3 页面高度（太空显得凑数，太满放不下 references）
222	
223	### 6.6 表格 LaTeX 规范
224	
225	**Booktabs 标准（硬规则）**：
226	- 用 `\toprule` / `\midrule` / `\bottomrule`，禁止 `\hline`，禁止竖线 `|`
227	- 用 `\centering` 不用 `\begin{center}`（后者多加垂直空白）
228	- 最优结果加粗（`\textbf{}`），次优下划线（`\underline{}`）+ 方向箭头 `↑`/`↓` 标明指标方向
229	- 小数精度全表统一（如全部保留 1 位或 2 位）
230	- Caption 在表格上方（`\caption` 在 `\begin{tabular}` 之前）
231	
232	**宽度决策树**：
233	- ≤5 列 → 单栏宽度（`\columnwidth`）
234	- 6–8 列 → 全文宽度（`\textwidth`，双栏模板用 `table*`）
235	- >8 列 → 拆成两张表或移入 appendix
236	
237	---
238	
239	## 七、投稿前通用准备
240	
241	### 7.1 模板必须官方（硬规则）
242	
243	- LaTeX 模板**必须从目标会议官网下载**（CallForPapers / Author Instructions 页面）
244	- **不要用**：
245	  - 网上他人转载的复制版本（可能被改过 margin / 行号设置）
246	  - 上一年的模板（参数可能变：字体、margin、行号、anonymous 选项等）
247	  - 组里学长留的旧版本（来源不明、无法追溯）
248	- 风险：
249	  - 样式不符合 → desk reject
250	  - margin 不对 → 被审稿人质疑诚信
251	  - reference 格式错 → 被认为不规范
252	- 流程：先查会议官网 templates → 找不到再 `WebSearch "{venue} {year} latex template official"` → 仍找不到汇报 Director（不要用就近年版本顶替）
253	- `\documentclass[]{}` 选项必须与目标 venue + 阶段（review / camera-ready）一致
254	
255	### 7.2 投稿要求逐项核对
256	
257	- 目标会议如要求 Checklist / Ethical Statement / Broader Impact Statement / Reproducibility Statement，必须**认真填每一项**，不要全写 N/A
258	- 页数限制：查目标会议官网
259	- 匿名化要求：review 版 vs camera-ready 版本设置不同
260	- 行号开启（review 版常需）
261	- 字体大小、margin 不得修改 sty 文件
262	
263	### 7.3 最终修改 10 项检查流程
264	
265	提交前必须逐一检查：
266	1. 所有最新实验结果已全部录入
267	2. 根据实验结果将叙事调至最优状态
268	3. 附录所有内容在正文中被引用且融入叙事
269	4. 无数据堆砌（每个数字服务于叙事推进）
270	5. Abstract 和 Introduction 具有吸引力（不是实验报告风格）
271	6. 全文主线统一（idea 变化后各章节逻辑一致）
272	7. 所有专有名词有定义
273	8. 无 AI 风格标志（dash、-ing phrases、过度分段）
274	9. 图表知识密度高、无视觉遮挡
275	10. Reference 覆盖直接相关方法、baseline、benchmark、理论基础
276	
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "parentUuid": "31919f66-3709-42d1-b153-8fe33171cd3b",
  "isSidechain": false,
  "promptId": "76de2f70-ac1e-444d-9c77-3c394a6cfdb7",
  "type": "user",
  "uuid": "ce4cdc12-afc5-43e4-b4be-f9ed954240e2",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md",
      "content": "---\nname: paper-writing-norms\ndescription: 顶会级别论文写作风格规范——章节写法（Abstract/Intro/Related Work）、去 AI 风格、视觉密度、叙事哲学。Paper Agent 和 Worker 写论文章节时必须加载。\nallowed-tools: [Read, Write, Edit, Glob, Grep]\nscope: global\nversion: 2\npriority: 9\ntags:\n  - writing\n  - paper\n  - style\n  - norms\nroles:\n  - agent\n  - worker\n  - paper_agent\n---\n\n# 论文写作风格规范\n\n> 核心哲学：**论文是一个有说服力的故事，不是实验报告。** 审稿人在几十秒内判断论文价值——如果 Abstract 和 Introduction 读起来像实验日志，论文就已经失败了。\n\n---\n\n## 一、总体写作哲学\n\n### 1.1 故事驱动，不是数据堆砌\n\n- 论文必须以\"故事线\"为核心展开：问题 → 洞察 → 方法 → 验证\n- 禁止大量实验数据堆砌——每个数字出现必须服务于叙事推进\n- 附录内容必须在正文中有明确引用且融入叙事，禁止简单堆砌\n- 如果附录数据对核心叙事有重大影响，根据附录数据调整论文 framing\n\n### 1.2 主线统一性\n\n- 当 idea 在研究过程中发生变化后，**必须重审全文逻辑**\n- 常见问题：Introduction 讲的故事 A，Method 做的是故事 B，Results 又在讲故事 C\n- 修复方式：从最终实验结论反推，重写 Introduction 的问题定义和动机\n- 每次 idea 调整后检查：Abstract → Introduction → Method → Results → Discussion → Conclusion 是否形成一条连贯主线\n\n### 1.3 专有名词必须有定义\n\n- 首次出现的专有名词/缩写必须给出完整定义和解释\n- Abstract 中使用的缩写也必须在 Abstract 内定义（如 LLM = Large Language Model）\n- 不能假设读者知道你自己定义的术语——论文从来没解释过的概念不能直接使用\n- 通用规则：如果一个非标准术语第一次出现时没有括号定义，就是写作 bug\n\n### 1.4 写作前必读同类优秀论文\n\n- 每个章节动笔前，找 **2-3 篇目标会议近 1-2 年的高分论文**作为风格参考——同类问题或同类方法皆可\n- 重点学：\n  - Abstract 怎么用最少篇幅讲完故事\n  - Introduction 怎么从大问题切入到具体贡献\n  - Related Work 怎么 positioning 自己（不是 survey）\n  - Table/Figure 怎么压缩信息密度\n- **不是抄袭**，是学习同行的故事节奏和审美——不同子领域叙事节奏差异很大\n- 实操：Paper Agent 可以从 `literature_map.yaml` 中挑 `role=foundation` 或 `role=direct-competitor` 的论文，把 `{title, venue, year, abstract}` 附在 Worker 的 task_prompt 中作为概念参考；如需学习写作风格本身，让 Worker 通过 WebSearch 取得论文链接并 fetch 全文\n\n---\n\n## 二、Abstract 写作规范\n\n### 2.1 四个必答问题（150-250 words）\n\nAbstract 必须在很短的篇幅内清楚回答：\n1. **研究什么问题** — 1-2 句话交代背景和痛点\n2. **为什么重要** — 现有方法的不足（不用写太多）\n3. **本文提出什么** — 核心贡献的关键机制（简要，不堆砌细节）\n4. **结果说明什么** — 用具体实验结论支撑贡献\n\n### 2.2 禁忌\n\n- **禁止堆砌数据**：Abstract 不是 Results 的缩写。最多引用 2-3 个关键数字，要服务于 claim\n- **禁止过度宣传**：不说 \"revolutionary\"、\"groundbreaking\"\n- **禁止写成 Introduction 的缩写**：Abstract 是独立阅读单元\n- **禁止术语堆积**：如果审稿人几十秒内判断不出价值，就失败了\n- **缩写必须定义**：Abstract 中首次出现的缩写必须展开\n\n### 2.3 审稿人视角检验\n\n写完后用这个标准自检：审稿人能否在 30 秒内判断——\n- 问题是否重要？\n- 方法是否清楚？\n- 贡献是否可信？\n- 结果是否有说服力？\n\n---\n\n## 三、Introduction 写作规范\n\n### 3.1 完整叙事线（5 段结构）\n\nIntroduction 需要从一个清晰、重要的问题切入，逐步把读者带到核心贡献：\n\n1. **研究背景**（1-2 段）：大模型在某类能力/应用中已取得进展，但仍存在一个关键瓶颈\n2. **问题重要性**（1 段）：结合真实应用、已有方法局限或当前趋势，说明这不是小问题\n3. **现有方法不足**（1 段）：系统梳理为什么不够（依赖更大模型/更多数据/更复杂推理/更高成本，或只在特定 benchmark 有效）\n4. **本文核心想法**（1 段）：我们观察到什么、提出了什么方法、为什么能解决上述问题\n5. **贡献总结**（列表）：清楚列出方法贡献、实验贡献和分析贡献\n\n### 3.2 整体叙事结构\n\n```\n现有进展 → 关键缺口 → 本文洞察 → 方法概述 → 实验证据 → 贡献总结\n```\n\n### 3.3 禁忌\n\n- **禁止泛泛介绍**：不要开头就写 \"LLMs have shown remarkable capabilities...\"，要从具体问题切入\n- **禁止缺少过渡**：每段之间必须有逻辑连接\n- **禁止实验报告风格**：Introduction 不是 \"我们做了 X 实验得到了 Y 结果\" 的罗列\n- 每条 Contribution 必须有对应的 section/table 支撑\n- Contribution 列表中不能出现未在前文铺垫过的概念\n\n---\n\n## 四、Related Work 写作规范\n\n### 4.1 目标\n\n让审稿人相信：作者理解这个领域，知道自己的方法站在什么位置，清楚相对已有工作的真实增量在哪里。\n\n### 4.2 结构要求\n\n- 把已有工作分成几个清晰的主题（如模型训练、推理增强、工具调用、数据构建、评测等）\n- 每类简要说明：已有方法做了什么、解决了哪些问题、和本文的关系\n- 帮助读者理解：哪些是本文直接继承的，哪些方法不同但解决相似问题，哪些留下了本文要解决的缺口\n\n### 4.3 禁忌\n\n- **禁止论文堆砌**：不要写成 \"A proposed X. B proposed Y. C proposed Z.\" 的列表\n- **目标不是展示读了多少论文**，而是做归纳和比较\n- Contribution claim（\"To our knowledge, no prior work...\"）应放在 Introduction，不在 Related Work\n\n### 4.4 引用充足度\n\n- 引用必须覆盖：**直接相关方法、baseline 论文、评测 benchmark 论文、理论基础**\n- 任何一类缺失，审稿人会立刻看出来调研不充分\n- 引用密度参照目标会议近年录用论文的量级——明显偏少意味着 Related Work 调研不足\n\n---\n\n## 五、去 AI 写作风格（硬规则）\n\n以下模式是 AI 生成文本的典型标志，审稿人一眼能看出。**必须全部消除。**\n\n### 5.1 严禁破折号（最显著的 AI 痕迹）\n\n**这是 AI 写作最容易被识别的标志，审稿人最敏感。单列为最高优先级硬规则。**\n\n- 解释性 em-dash（—，U+2014）和 en-dash（–，U+2013）必须**全部删除**\n- 替代方式：用逗号、括号或拆分为两个句子\n- 强制检查命令：\n  ```bash\n  grep -n \"—\" paper/*.tex     # em-dash，每处人工判断是否必要\n  grep -n \" – \" paper/*.tex   # 解释性 en-dash，几乎都应删除\n  ```\n- 例外（允许保留）：表格分隔符、数字范围（`2020–2024`、`pp. 12–18`）、专有名词（`Newton–Raphson`）\n\n### 5.2 段落与句式\n\n- **禁止过度分段**：不需要每 2-3 句就换段，自然段 5-8 句是正常的\n- **减少关系从句**（which, that, who）：能用简洁直接的句子就不用从句\n- **禁止 -ing 短语结尾**：如 \"..., highlighting the applicability of...\" / \"..., demonstrating the effectiveness of...\"。这是 AI 写作最典型的标志之一\n- **禁止连续使用 \"Furthermore\" / \"Moreover\" / \"Additionally\"**：一段内最多用一个过渡词\n- **避免 \"It is worth noting that...\" / \"Notably, ...\"**：直接写要说的内容\n\n### 5.3 用词黑名单\n\n- 避免 \"delve into\" / \"leverage\" / \"utilize\" / \"facilitate\" — 用 \"explore\" / \"use\" / \"enable\"\n- 避免 \"a myriad of\" / \"a plethora of\" — 用 \"many\" / \"various\"\n- 避免 \"in the realm of\" / \"in the context of\" — 直接说\n- 避免 \"paradigm shift\" / \"novel\" 过度使用\n\n### 5.4 校对清单（4 步）\n\n1. 全文 proofread 语法和拼写\n2. 检查所有代词/指示词（this, that, it）是否指代明确\n3. **`grep \"—\"` + `grep \" – \"` 全文清零**（删除所有解释性 dash，§5.1）\n4. `grep \"ing,\"` 模式——大部分 -ing 分词短语需要改写\n\n---\n\n## 六、图表与视觉规范\n\n### 6.1 知识密度原则\n\n- **图表的信息必须紧凑**——不能为了美观而留大量白空间\n- 一张图如果只传达一个简单信息，要么缩小要么合并到其他图中\n- 能用 inline text 说清的不要占一整个 Figure\n\n### 6.2 表格规范\n\n- 表格和正文文字不能视觉重叠（检查 column 宽度和 alignment）\n- 小数精度全表统一\n- 最优加粗、次优下划线\n- Caption 必须自包含\n\n### 6.3 图片规范\n\n- 数值标签不能被线、bar、点遮住——用白色背景或偏移标签\n- 图中字体 >= 7pt（打印后仍可读）\n- 栏宽约束需匹配目标 venue 模板要求\n- 概念图/流程图要有信息量，不要画一个 trivial 的 pipeline 然后占半页\n\n### 6.4 空间效率\n\n- 顶会正文页数严格受限（具体页数查目标会议官网），每 cm² 都是宝贵资源\n- 优先使用 `\\subfigure` 合并相关图\n- Table 能 inline 就不要单独浮动\n- 图表占比与其对叙事的贡献成正比\n\n### 6.5 页面节奏\n\n好论文的页面有节奏感——text、equation、figure 交替出现，读者视觉不疲劳：\n\n- **text-equation-figure 三重奏**：重要概念用\"文字解释 → 公式定义 → 图表直觉\"三步展开\n- 连续 2 页纯文本（无 figure/equation/table）→ 穿插一个 display item 打破节奏\n- 连续 2 个 figure 页（整页被 float 占满）→ 至少隔 1 段文字再放下一个 float\n- Section heading 不孤悬页底（heading 后至少跟 2 行正文，否则强制分页）\n- 最后一页内容 ≥ 2/3 页面高度（太空显得凑数，太满放不下 references）\n\n### 6.6 表格 LaTeX 规范\n\n**Booktabs 标准（硬规则）**：\n- 用 `\\toprule` / `\\midrule` / `\\bottomrule`，禁止 `\\hline`，禁止竖线 `|`\n- 用 `\\centering` 不用 `\\begin{center}`（后者多加垂直空白）\n- 最优结果加粗（`\\textbf{}`），次优下划线（`\\underline{}`）+ 方向箭头 `↑`/`↓` 标明指标方向\n- 小数精度全表统一（如全部保留 1 位或 2 位）\n- Caption 在表格上方（`\\caption` 在 `\\begin{tabular}` 之前）\n\n**宽度决策树**：\n- ≤5 列 → 单栏宽度（`\\columnwidth`）\n- 6–8 列 → 全文宽度（`\\textwidth`，双栏模板用 `table*`）\n- >8 列 → 拆成两张表或移入 appendix\n\n---\n\n## 七、投稿前通用准备\n\n### 7.1 模板必须官方（硬规则）\n\n- LaTeX 模板**必须从目标会议官网下载**（CallForPapers / Author Instructions 页面）\n- **不要用**：\n  - 网上他人转载的复制版本（可能被改过 margin / 行号设置）\n  - 上一年的模板（参数可能变：字体、margin、行号、anonymous 选项等）\n  - 组里学长留的旧版本（来源不明、无法追溯）\n- 风险：\n  - 样式不符合 → desk reject\n  - margin 不对 → 被审稿人质疑诚信\n  - reference 格式错 → 被认为不规范\n- 流程：先查会议官网 templates → 找不到再 `WebSearch \"{venue} {year} latex template official\"` → 仍找不到汇报 Director（不要用就近年版本顶替）\n- `\\documentclass[]{}` 选项必须与目标 venue + 阶段（review / camera-ready）一致\n\n### 7.2 投稿要求逐项核对\n\n- 目标会议如要求 Checklist / Ethical Statement / Broader Impact Statement / Reproducibility Statement，必须**认真填每一项**，不要全写 N/A\n- 页数限制：查目标会议官网\n- 匿名化要求：review 版 vs camera-ready 版本设置不同\n- 行号开启（review 版常需）\n- 字体大小、margin 不得修改 sty 文件\n\n### 7.3 最终修改 10 项检查流程\n\n提交前必须逐一检查：\n1. 所有最新实验结果已全部录入\n2. 根据实验结果将叙事调至最优状态\n3. 附录所有内容在正文中被引用且融入叙事\n4. 无数据堆砌（每个数字服务于叙事推进）\n5. Abstract 和 Introduction 具有吸引力（不是实验报告风格）\n6. 全文主线统一（idea 变化后各章节逻辑一致）\n7. 所有专有名词有定义\n8. 无 AI 风格标志（dash、-ing phrases、过度分段）\n9. 图表知识密度高、无视觉遮挡\n10. Reference 覆盖直接相关方法、baseline、benchmark、理论基础\n",
      "numLines": 276,
      "startLine": 1,
      "totalLines": 276
    }
  },
  "sourceToolAssistantUUID": "31919f66-3709-42d1-b153-8fe33171cd3b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool result

_source line 11 · 2026-05-20T07:49:46.067Z_

<details><summary>↩ Tool result · `toolu_01EQebsobVqyZUJ3niojPNFY`</summary>

```text
docs/paper/sections/framework.tex
docs/paper/sections/direction_quality.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2a951547-1a59-497d-b0a4-e743e770dd2b",
  "isSidechain": false,
  "promptId": "76de2f70-ac1e-444d-9c77-3c394a6cfdb7",
  "type": "user",
  "uuid": "9fd3029f-cfa1-44f8-aa80-98241b4baa1d",
  "toolUseResult": {
    "filenames": [
      "docs/paper/sections/framework.tex",
      "docs/paper/sections/direction_quality.tex"
    ],
    "durationMs": 13,
    "numFiles": 2,
    "truncated": false
  },
  "sourceToolAssistantUUID": "2a951547-1a59-497d-b0a4-e743e770dd2b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 12 · 2026-05-20T07:49:45.878Z_

<details open><summary>🔧 Tool call — Read · `toolu_01PEnHbdo7EiKo5z2KeoRTCz`</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ce4cdc12-afc5-43e4-b4be-f9ed954240e2",
  "isSidechain": false,
  "requestId": "req_011CbDTJq42g6NhE85mBbRLK",
  "type": "assistant",
  "uuid": "b63b565f-62d7-4b6e-8faf-fbcb58068cb9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0187PkzsZup1bbq5dR4N8wV9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14019,
      "cache_read_input_tokens": 11841,
      "output_tokens": 230,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14019,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 230,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 14019,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14019
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

_source line 13 · 2026-05-20T07:49:45.886Z_

<details><summary>↩ Tool result · `toolu_01PEnHbdo7EiKo5z2KeoRTCz`</summary>

````text
1	---
2	name: latex-paper
3	description: ML 顶会论文 LaTeX 写作全流程——Claim-Evidence 方法论、引用防幻觉、顶会模板速查、投稿工程链、会议转投。写论文/投稿时参考。
4	scope: global
5	tags:
6	- latex
7	- paper-writing
8	- academic
9	- citation
10	- submission
11	version: 1
12	roles:
13	- agent
14	- worker
15	---
16	
17	# LaTeX 论文写作全流程
18	
19	ML/AI 顶会论文从草稿到投稿的完整指南。整合 Orchestra Research、VibeSkills、claim2evidence 三方最佳实践。
20	
21	---
22	
23	## 1. 工作模式
24	
25	开始前选择模式：
26	
27	| 模式 | 说明 | 适用 |
28	|------|------|------|
29	| **Build** | 从实验笔记/结果/代码生成论文 | 新稿 |
30	| **Improve** | 改写已有章节，强化论证 | 修改稿 |
31	| **Audit** | 输出风险列表 + 缺失证据 + 修复建议 | 投前检查 |
32	
33	---
34	
35	## 2. Claim-Evidence 方法论
36	
37	**核心原则：论文是一个有中心贡献的故事，不是实验的堆砌。**
38	
39	### 2.1 一句话贡献
40	
41	在写任何内容之前，必须能用一句话说清贡献。如果不能，说明还没准备好写论文。
42	
43	### 2.2 Claim-Evidence Map
44	
45	为每个 contribution 建立 claim→evidence 映射表：
46	
47	| Contribution | Claim | Evidence | Table/Figure |
48	|-------------|-------|----------|-------------|
49	| C1: 方法 X 在 Y 上 SOTA | 比所有 baseline 高 ≥2% | 5-seed 平均，p<0.05 | Table 1 |
50	| C2: 消融证明 Z 是关键 | 去掉 Z 后掉 >5% | 消融实验 | Table 2 |
51	| C3: 计算效率 | 比 baseline 快 3× | FLOPs + wall-clock | Figure 3 |
52	
53	**没有直接证据支撑的 claim 必须删除或降级为 discussion。**
54	
55	### 2.3 章节起草顺序
56	
57	```
58	1. Introduction + Experiments（先确定 claim 和 evidence）
59	2. Method（评估问题稳定后再写细节）
60	3. Related Work
61	4. Abstract + Title（核心 claim 定型后最后写）
62	```
63	
64	### 2.4 Quality Gates
65	
66	投稿前必须通过：
67	- [ ] 前两段出现显式 novelty 声明
68	- [ ] 每个 contribution 有可验证的 evidence
69	- [ ] Abstract / Intro / Conclusion 的 claim 一致
70	- [ ] Limitations 真实且技术性诚实
71	- [ ] 审稿人两分钟内能识别 delta
72	
73	---
74	
75	## 3. 引用防幻觉（CRITICAL）
76	
77	**AI 生成引用有 ~40% 错误率。绝对禁止凭记忆写 BibTeX。**
78	
79	### 3.1 黄金法则
80	
81	```
82	IF 无法程序化获取引用:
83	    → 标记 [CITATION NEEDED] 或 \cite{PLACEHOLDER_verify}
84	    → 明确告知用户
85	    → 绝不编造看似合理的引用
86	```
87	
88	### 3.2 五步验证流程
89	
90	```
91	1. SEARCH  → Semantic Scholar API 搜索关键词
92	2. VERIFY  → 至少 2 个来源确认论文存在（S2 + arXiv/CrossRef）
93	3. RETRIEVE → 通过 DOI 获取 BibTeX（程序化，非记忆）
94	4. CHECK   → 确认你引用的 claim 确实出自该论文
95	5. ADD     → 加入 .bib 文件
96	```
97	
98	### 3.3 API 速查
99	
100	| API | 用途 | 限制 |
101	|-----|------|------|
102	| **Semantic Scholar** | ML/AI 论文搜索 | 1 RPS (免费) |
103	| **CrossRef** | DOI → BibTeX | 需 mailto 头 |
104	| **arXiv** | 预印本搜索 | 3s 间隔 |
105	
106	```python
107	# DOI → BibTeX（最可靠的方式）
108	import requests
109	def doi_to_bibtex(doi: str) -> str:
110	    r = requests.get(f"https://doi.org/{doi}",
111	                     headers={"Accept": "application/x-bibtex"})
112	    r.raise_for_status()
113	    return r.text
114	
115	# Semantic Scholar 搜索
116	from semanticscholar import SemanticScholar
117	sch = SemanticScholar()
118	results = sch.search_paper("attention mechanism transformers", limit=5)
119	for p in results:
120	    print(f"{p.title} | DOI: {p.externalIds.get('DOI', 'N/A')}")
121	```
122	
123	### 3.4 引用处理规则
124	
125	| 情况 | 处理 |
126	|------|------|
127	| 找到论文 + DOI + BibTeX | 直接用 |
128	| 找到论文，无 DOI | 用 arXiv BibTeX |
129	| 论文存在但无法获取 BibTeX | 标记 placeholder，告知用户 |
130	| 不确定论文是否存在 | 标记 `[CITATION NEEDED]`，告知用户 |
131	| "我觉得有篇关于 X 的论文" | **绝不引用** — 先搜索或标记 |
132	
133	---
134	
135	## 4. 顶会模板速查
136	
137	### 4.1 ML/AI 会议
138	
139	| 会议 | 页数限制 | 主文件 | 样式文件 | 必须项 |
140	|------|---------|--------|---------|--------|
141	| **NeurIPS** | 9 页 | `main.tex` | `neurips.sty` | Paper Checklist |
142	| **ICML** | 8 页 (+1 camera-ready) | `example_paper.tex` | `icml2026.sty` | Broader Impact |
143	| **ICLR** | 9 页 (+1) | `iclr_conference.tex` | `iclr_conference.sty` | LLM 使用声明 |
144	| **ACL/EMNLP** | 8 页 (long) | `acl_latex.tex` | `acl.sty` | Limitations 必须 |
145	| **AAAI** | 7 页 (+1) | `aaai_template.tex` | `aaai.sty` | 严格样式 |
146	| **COLM** | 9 页 (+1) | `colm_conference.tex` | `colm_conference.sty` | 语言模型聚焦 |
147	
148	### 4.2 系统会议
149	
150	| 会议 | 页数限制 | 模板类型 | 关键要求 |
151	|------|---------|---------|---------|
152	| **OSDI** | 12 页 (+2) | USENIX `usenix.sty` | Research / Operational 双 track |
153	| **NSDI** | 12 页 | USENIX | Introduction 预筛 |
154	| **ASPLOS** | 12 页 | ACM `acmart.cls (sigplan)` | 前 2 页快速评审 |
155	| **SOSP** | 12 页 | ACM `acmart.cls (sigplan)` | 可选 Artifact Evaluation |
156	
157	### 4.3 模板使用原则
158	
159	```bash
160	# 1. 复制整个模板目录（不要只拷 .tex）
161	cp -r templates/neurips2025/ ~/papers/my-paper/
162	
163	# 2. 先编译未修改的模板，确认能跑通
164	latexmk -pdf main.tex
165	
166	# 3. 逐章替换内容，频繁编译
167	```
168	
169	**禁止事项：**
170	- 不要修改 `.sty` 文件
171	- 不要在会议模板间复制 `\usepackage` 行
172	- 不要只复制 `.tex` 而不带 `.sty/.bst`
173	
174	---
175	
176	## 5. 写作规范
177	
178	### 5.1 时间分配（Neel Nanda）
179	
180	花**大致相等**的时间在：
181	1. Abstract
182	2. Introduction
183	3. 图表
184	4. **其余所有内容加起来**
185	
186	审稿人读论文的顺序：标题 → 摘要 → 引言 → 图表 → 也许正文。
187	
188	### 5.2 Abstract 五句法（Sebastian Farquhar）
189	
190	```
191	1. 你做了什么（"We introduce/prove/demonstrate..."）
192	2. 为什么这很难且重要
193	3. 怎么做的（含专业关键词以便检索）
194	4. 有什么证据
195	5. 最惊人的数字/结果
196	```
197	
198	删除一切泛泛的开头：~~"Large language models have achieved remarkable success..."~~
199	
200	### 5.3 句子级清晰度（Gopen & Swan）
201	
202	| 原则 | 规则 |
203	|------|------|
204	| 主谓紧邻 | 不要在主语和动词之间插入长从句 |
205	| 重点在句尾 | 把关键数字/结论放在句末 |
206	| 旧信息在前 | 先放读者已知的内容，再引入新概念 |
207	| 动词表达动作 | "We analyzed" 而非 "We performed an analysis" |
208	
209	### 5.4 常见修改
210	
211	| 问题 | 修复 |
212	|------|------|
213	| Abstract 太泛 | 删第一句（如果它能放在任何 ML 论文前面） |
214	| Introduction 超 1.5 页 | 背景挪到 Related Work |
215	| 实验没有显式 claim | 每个实验前加 "This tests whether..." |
216	| 缺统计显著性 | 加 error bars + 运行次数 + 计算方法 |
217	
218	---
219	
220	## 6. 投稿工程链
221	
222	### 6.1 构建
223	
224	```bash
225	# 推荐：latexmk 一键构建
226	latexmk -pdf -interaction=nonstopmode -halt-on-error main.tex
227	
228	# 手动：需要多次编译
229	pdflatex main.tex && bibtex main && pdflatex main.tex && pdflatex main.tex
230	```
231	
232	### 6.2 Lint + 格式化
233	
234	```bash
235	# Lint: 检查常见 LaTeX 问题
236	chktex main.tex
237	
238	# 格式化: 减少 diff 噪声
239	latexindent -w main.tex
240	```
241	
242	### 6.3 图表格式
243	
244	| 类型 | 格式 | 说明 |
245	|------|------|------|
246	| 矢量图（plot、diagram） | PDF | matplotlib: `plt.savefig('fig.pdf')` |
247	| 照片/heatmap | PNG 600dpi 或 TIFF | 栅格图 |
248	| 表格 | `booktabs` 包 | `\toprule/\midrule/\bottomrule` |
249	
250	```latex
251	\usepackage{booktabs}
252	\begin{tabular}{lcc}
253	\toprule
254	Method & Accuracy $\uparrow$ & Latency $\downarrow$ \\
255	\midrule
256	Baseline & 85.2 & 45ms \\
257	\textbf{Ours} & \textbf{92.1} & 38ms \\
258	\bottomrule
259	\end{tabular}
260	```
261	
262	**图表规范：**
263	- 用色盲友好色板（Okabe-Ito 或 Paul Tol）
264	- 图内不放标题（用 caption）
265	- Caption 独立可理解（不依赖正文）
266	- 最佳值加粗，标注方向符号（↑ 越高越好，↓ 越低越好）
267	
268	### 6.4 投稿打包
269	
270	```bash
271	# 清理辅助文件
272	latexmk -c
273	
274	# 打包投稿
275	zip -r submission.zip main.tex *.sty *.bst *.bib figures/ --exclude='*.aux' --exclude='*.log'
276	```
277	
278	### 6.5 常见失败点
279	
280	| 问题 | 解决 |
281	|------|------|
282	| 图片格式混用导致编译失败 | 统一用 PDF |
283	| 字体未嵌入 | `pdffonts output.pdf` 检查 |
284	| Overfull box 过多 | 关键位置手动调行 |
285	| 引用缺字段 | 检查 DOI/年份/期刊名 |
286	| 超页数 | 用 `\vspace{-Xpt}` 微调，或精简内容 |
287	
288	---
289	
290	## 7. 会议转投
291	
292	当论文被拒或转投其他会议时：
293	
294	### 7.1 ML/AI 会议间转换
295	
296	| 转换 | 页数变化 | 关键调整 |
297	|------|---------|---------|
298	| NeurIPS → ICML | 9→8 | 删 1 页，加 Broader Impact |
299	| ICML → ICLR | 8→9 | 可扩展实验 + LLM 声明 |
300	| NeurIPS → ACL | 9→8 | 按 NLP 惯例重组 + Limitations |
301	| ICLR → AAAI | 9→7 | 大幅精简，严格样式 |
302	
303	### 7.2 转投原则
304	
305	1. **永远用目标模板重新开始** — 复制目标模板，迁移内容，不要合并 preamble
306	2. **只迁移正文内容** — 不复制 `\usepackage`、header/footer 命令
307	3. **根据审稿意见改进** — 但不要在新稿中提及旧投稿（双盲）
308	4. **检查目标会议特殊要求** — checklist、ethics statement、LLM 声明等
309	
310	---
311	
312	## 8. 投前清单
313	
314	### 通用清单
315	
316	- [ ] Abstract/Intro/Conclusion 的 claim 一致
317	- [ ] 每个 contribution 有对应 evidence
318	- [ ] 所有引用已程序化验证（无幻觉引用）
319	- [ ] Error bars + 运行次数 + 统计方法
320	- [ ] Limitations 章节存在且诚实
321	- [ ] 匿名化（双盲审稿）
322	- [ ] 符合页数限制
323	- [ ] 所有图表有自包含 caption
324	- [ ] `.bib` 中无缺失字段
325	- [ ] PDF 编译无 warning
326	
327	### 会议特定
328	
329	| 会议 | 额外要求 |
330	|------|---------|
331	| NeurIPS | 16 项 Paper Checklist（附录，不计页数） |
332	| ICML | Broader Impact Statement |
333	| ICLR | LLM 使用声明 |
334	| ACL/EMNLP | Limitations 章节（必须），Ethics Statement |
335	| AAAI | 严格样式文件合规 |
336	
337	---
338	
339	## 参考资源
340	
341	**写作方法论：**
342	- [Neel Nanda: How to Write ML Papers](https://www.alignmentforum.org/posts/eJGptPbbFPZGLpjsp/) — What/Why/So What 框架
343	- [Farquhar: How to Write ML Papers](https://sebastianfarquhar.com/on-research/2024/11/04/how_to_write_ml_papers/) — 五句法 Abstract
344	- [Gopen & Swan: Science of Scientific Writing](https://cseweb.ucsd.edu/~swanson/papers/science-of-writing.pdf) — 读者预期 7 原则
345	- [Lipton: Heuristics for Scientific Writing](https://www.approximatelycorrect.com/2018/01/29/heuristics-technical-scientific-writing-machine-learning-perspective/) — 用词
346	- [Perez: Easy Paper Writing Tips](https://ethanperez.net/easy-paper-writing-tips/) — 微观清晰度
347	
348	**API：**
349	- [Semantic Scholar](https://api.semanticscholar.org/api-docs/) | [CrossRef](https://www.crossref.org/documentation/) | [arXiv](https://info.arxiv.org/help/api/)
350	
351	**会议官方：**
352	- [NeurIPS](https://neurips.cc/) | [ICML](https://icml.cc/) | [ICLR](https://iclr.cc/) | [ACL](https://www.aclweb.org/) | [AAAI](https://aaai.org/) | [EMNLP](https://2025.emnlp.org/)
353	
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "parentUuid": "b63b565f-62d7-4b6e-8faf-fbcb58068cb9",
  "isSidechain": false,
  "promptId": "76de2f70-ac1e-444d-9c77-3c394a6cfdb7",
  "type": "user",
  "uuid": "047c00bd-0f8b-4027-b6e1-42eeff22a6ba",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md",
      "content": "---\nname: latex-paper\ndescription: ML 顶会论文 LaTeX 写作全流程——Claim-Evidence 方法论、引用防幻觉、顶会模板速查、投稿工程链、会议转投。写论文/投稿时参考。\nscope: global\ntags:\n- latex\n- paper-writing\n- academic\n- citation\n- submission\nversion: 1\nroles:\n- agent\n- worker\n---\n\n# LaTeX 论文写作全流程\n\nML/AI 顶会论文从草稿到投稿的完整指南。整合 Orchestra Research、VibeSkills、claim2evidence 三方最佳实践。\n\n---\n\n## 1. 工作模式\n\n开始前选择模式：\n\n| 模式 | 说明 | 适用 |\n|------|------|------|\n| **Build** | 从实验笔记/结果/代码生成论文 | 新稿 |\n| **Improve** | 改写已有章节，强化论证 | 修改稿 |\n| **Audit** | 输出风险列表 + 缺失证据 + 修复建议 | 投前检查 |\n\n---\n\n## 2. Claim-Evidence 方法论\n\n**核心原则：论文是一个有中心贡献的故事，不是实验的堆砌。**\n\n### 2.1 一句话贡献\n\n在写任何内容之前，必须能用一句话说清贡献。如果不能，说明还没准备好写论文。\n\n### 2.2 Claim-Evidence Map\n\n为每个 contribution 建立 claim→evidence 映射表：\n\n| Contribution | Claim | Evidence | Table/Figure |\n|-------------|-------|----------|-------------|\n| C1: 方法 X 在 Y 上 SOTA | 比所有 baseline 高 ≥2% | 5-seed 平均，p<0.05 | Table 1 |\n| C2: 消融证明 Z 是关键 | 去掉 Z 后掉 >5% | 消融实验 | Table 2 |\n| C3: 计算效率 | 比 baseline 快 3× | FLOPs + wall-clock | Figure 3 |\n\n**没有直接证据支撑的 claim 必须删除或降级为 discussion。**\n\n### 2.3 章节起草顺序\n\n```\n1. Introduction + Experiments（先确定 claim 和 evidence）\n2. Method（评估问题稳定后再写细节）\n3. Related Work\n4. Abstract + Title（核心 claim 定型后最后写）\n```\n\n### 2.4 Quality Gates\n\n投稿前必须通过：\n- [ ] 前两段出现显式 novelty 声明\n- [ ] 每个 contribution 有可验证的 evidence\n- [ ] Abstract / Intro / Conclusion 的 claim 一致\n- [ ] Limitations 真实且技术性诚实\n- [ ] 审稿人两分钟内能识别 delta\n\n---\n\n## 3. 引用防幻觉（CRITICAL）\n\n**AI 生成引用有 ~40% 错误率。绝对禁止凭记忆写 BibTeX。**\n\n### 3.1 黄金法则\n\n```\nIF 无法程序化获取引用:\n    → 标记 [CITATION NEEDED] 或 \\cite{PLACEHOLDER_verify}\n    → 明确告知用户\n    → 绝不编造看似合理的引用\n```\n\n### 3.2 五步验证流程\n\n```\n1. SEARCH  → Semantic Scholar API 搜索关键词\n2. VERIFY  → 至少 2 个来源确认论文存在（S2 + arXiv/CrossRef）\n3. RETRIEVE → 通过 DOI 获取 BibTeX（程序化，非记忆）\n4. CHECK   → 确认你引用的 claim 确实出自该论文\n5. ADD     → 加入 .bib 文件\n```\n\n### 3.3 API 速查\n\n| API | 用途 | 限制 |\n|-----|------|------|\n| **Semantic Scholar** | ML/AI 论文搜索 | 1 RPS (免费) |\n| **CrossRef** | DOI → BibTeX | 需 mailto 头 |\n| **arXiv** | 预印本搜索 | 3s 间隔 |\n\n```python\n# DOI → BibTeX（最可靠的方式）\nimport requests\ndef doi_to_bibtex(doi: str) -> str:\n    r = requests.get(f\"https://doi.org/{doi}\",\n                     headers={\"Accept\": \"application/x-bibtex\"})\n    r.raise_for_status()\n    return r.text\n\n# Semantic Scholar 搜索\nfrom semanticscholar import SemanticScholar\nsch = SemanticScholar()\nresults = sch.search_paper(\"attention mechanism transformers\", limit=5)\nfor p in results:\n    print(f\"{p.title} | DOI: {p.externalIds.get('DOI', 'N/A')}\")\n```\n\n### 3.4 引用处理规则\n\n| 情况 | 处理 |\n|------|------|\n| 找到论文 + DOI + BibTeX | 直接用 |\n| 找到论文，无 DOI | 用 arXiv BibTeX |\n| 论文存在但无法获取 BibTeX | 标记 placeholder，告知用户 |\n| 不确定论文是否存在 | 标记 `[CITATION NEEDED]`，告知用户 |\n| \"我觉得有篇关于 X 的论文\" | **绝不引用** — 先搜索或标记 |\n\n---\n\n## 4. 顶会模板速查\n\n### 4.1 ML/AI 会议\n\n| 会议 | 页数限制 | 主文件 | 样式文件 | 必须项 |\n|------|---------|--------|---------|--------|\n| **NeurIPS** | 9 页 | `main.tex` | `neurips.sty` | Paper Checklist |\n| **ICML** | 8 页 (+1 camera-ready) | `example_paper.tex` | `icml2026.sty` | Broader Impact |\n| **ICLR** | 9 页 (+1) | `iclr_conference.tex` | `iclr_conference.sty` | LLM 使用声明 |\n| **ACL/EMNLP** | 8 页 (long) | `acl_latex.tex` | `acl.sty` | Limitations 必须 |\n| **AAAI** | 7 页 (+1) | `aaai_template.tex` | `aaai.sty` | 严格样式 |\n| **COLM** | 9 页 (+1) | `colm_conference.tex` | `colm_conference.sty` | 语言模型聚焦 |\n\n### 4.2 系统会议\n\n| 会议 | 页数限制 | 模板类型 | 关键要求 |\n|------|---------|---------|---------|\n| **OSDI** | 12 页 (+2) | USENIX `usenix.sty` | Research / Operational 双 track |\n| **NSDI** | 12 页 | USENIX | Introduction 预筛 |\n| **ASPLOS** | 12 页 | ACM `acmart.cls (sigplan)` | 前 2 页快速评审 |\n| **SOSP** | 12 页 | ACM `acmart.cls (sigplan)` | 可选 Artifact Evaluation |\n\n### 4.3 模板使用原则\n\n```bash\n# 1. 复制整个模板目录（不要只拷 .tex）\ncp -r templates/neurips2025/ ~/papers/my-paper/\n\n# 2. 先编译未修改的模板，确认能跑通\nlatexmk -pdf main.tex\n\n# 3. 逐章替换内容，频繁编译\n```\n\n**禁止事项：**\n- 不要修改 `.sty` 文件\n- 不要在会议模板间复制 `\\usepackage` 行\n- 不要只复制 `.tex` 而不带 `.sty/.bst`\n\n---\n\n## 5. 写作规范\n\n### 5.1 时间分配（Neel Nanda）\n\n花**大致相等**的时间在：\n1. Abstract\n2. Introduction\n3. 图表\n4. **其余所有内容加起来**\n\n审稿人读论文的顺序：标题 → 摘要 → 引言 → 图表 → 也许正文。\n\n### 5.2 Abstract 五句法（Sebastian Farquhar）\n\n```\n1. 你做了什么（\"We introduce/prove/demonstrate...\"）\n2. 为什么这很难且重要\n3. 怎么做的（含专业关键词以便检索）\n4. 有什么证据\n5. 最惊人的数字/结果\n```\n\n删除一切泛泛的开头：~~\"Large language models have achieved remarkable success...\"~~\n\n### 5.3 句子级清晰度（Gopen & Swan）\n\n| 原则 | 规则 |\n|------|------|\n| 主谓紧邻 | 不要在主语和动词之间插入长从句 |\n| 重点在句尾 | 把关键数字/结论放在句末 |\n| 旧信息在前 | 先放读者已知的内容，再引入新概念 |\n| 动词表达动作 | \"We analyzed\" 而非 \"We performed an analysis\" |\n\n### 5.4 常见修改\n\n| 问题 | 修复 |\n|------|------|\n| Abstract 太泛 | 删第一句（如果它能放在任何 ML 论文前面） |\n| Introduction 超 1.5 页 | 背景挪到 Related Work |\n| 实验没有显式 claim | 每个实验前加 \"This tests whether...\" |\n| 缺统计显著性 | 加 error bars + 运行次数 + 计算方法 |\n\n---\n\n## 6. 投稿工程链\n\n### 6.1 构建\n\n```bash\n# 推荐：latexmk 一键构建\nlatexmk -pdf -interaction=nonstopmode -halt-on-error main.tex\n\n# 手动：需要多次编译\npdflatex main.tex && bibtex main && pdflatex main.tex && pdflatex main.tex\n```\n\n### 6.2 Lint + 格式化\n\n```bash\n# Lint: 检查常见 LaTeX 问题\nchktex main.tex\n\n# 格式化: 减少 diff 噪声\nlatexindent -w main.tex\n```\n\n### 6.3 图表格式\n\n| 类型 | 格式 | 说明 |\n|------|------|------|\n| 矢量图（plot、diagram） | PDF | matplotlib: `plt.savefig('fig.pdf')` |\n| 照片/heatmap | PNG 600dpi 或 TIFF | 栅格图 |\n| 表格 | `booktabs` 包 | `\\toprule/\\midrule/\\bottomrule` |\n\n```latex\n\\usepackage{booktabs}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & Accuracy $\\uparrow$ & Latency $\\downarrow$ \\\\\n\\midrule\nBaseline & 85.2 & 45ms \\\\\n\\textbf{Ours} & \\textbf{92.1} & 38ms \\\\\n\\bottomrule\n\\end{tabular}\n```\n\n**图表规范：**\n- 用色盲友好色板（Okabe-Ito 或 Paul Tol）\n- 图内不放标题（用 caption）\n- Caption 独立可理解（不依赖正文）\n- 最佳值加粗，标注方向符号（↑ 越高越好，↓ 越低越好）\n\n### 6.4 投稿打包\n\n```bash\n# 清理辅助文件\nlatexmk -c\n\n# 打包投稿\nzip -r submission.zip main.tex *.sty *.bst *.bib figures/ --exclude='*.aux' --exclude='*.log'\n```\n\n### 6.5 常见失败点\n\n| 问题 | 解决 |\n|------|------|\n| 图片格式混用导致编译失败 | 统一用 PDF |\n| 字体未嵌入 | `pdffonts output.pdf` 检查 |\n| Overfull box 过多 | 关键位置手动调行 |\n| 引用缺字段 | 检查 DOI/年份/期刊名 |\n| 超页数 | 用 `\\vspace{-Xpt}` 微调，或精简内容 |\n\n---\n\n## 7. 会议转投\n\n当论文被拒或转投其他会议时：\n\n### 7.1 ML/AI 会议间转换\n\n| 转换 | 页数变化 | 关键调整 |\n|------|---------|---------|\n| NeurIPS → ICML | 9→8 | 删 1 页，加 Broader Impact |\n| ICML → ICLR | 8→9 | 可扩展实验 + LLM 声明 |\n| NeurIPS → ACL | 9→8 | 按 NLP 惯例重组 + Limitations |\n| ICLR → AAAI | 9→7 | 大幅精简，严格样式 |\n\n### 7.2 转投原则\n\n1. **永远用目标模板重新开始** — 复制目标模板，迁移内容，不要合并 preamble\n2. **只迁移正文内容** — 不复制 `\\usepackage`、header/footer 命令\n3. **根据审稿意见改进** — 但不要在新稿中提及旧投稿（双盲）\n4. **检查目标会议特殊要求** — checklist、ethics statement、LLM 声明等\n\n---\n\n## 8. 投前清单\n\n### 通用清单\n\n- [ ] Abstract/Intro/Conclusion 的 claim 一致\n- [ ] 每个 contribution 有对应 evidence\n- [ ] 所有引用已程序化验证（无幻觉引用）\n- [ ] Error bars + 运行次数 + 统计方法\n- [ ] Limitations 章节存在且诚实\n- [ ] 匿名化（双盲审稿）\n- [ ] 符合页数限制\n- [ ] 所有图表有自包含 caption\n- [ ] `.bib` 中无缺失字段\n- [ ] PDF 编译无 warning\n\n### 会议特定\n\n| 会议 | 额外要求 |\n|------|---------|\n| NeurIPS | 16 项 Paper Checklist（附录，不计页数） |\n| ICML | Broader Impact Statement |\n| ICLR | LLM 使用声明 |\n| ACL/EMNLP | Limitations 章节（必须），Ethics Statement |\n| AAAI | 严格样式文件合规 |\n\n---\n\n## 参考资源\n\n**写作方法论：**\n- [Neel Nanda: How to Write ML Papers](https://www.alignmentforum.org/posts/eJGptPbbFPZGLpjsp/) — What/Why/So What 框架\n- [Farquhar: How to Write ML Papers](https://sebastianfarquhar.com/on-research/2024/11/04/how_to_write_ml_papers/) — 五句法 Abstract\n- [Gopen & Swan: Science of Scientific Writing](https://cseweb.ucsd.edu/~swanson/papers/science-of-writing.pdf) — 读者预期 7 原则\n- [Lipton: Heuristics for Scientific Writing](https://www.approximatelycorrect.com/2018/01/29/heuristics-technical-scientific-writing-machine-learning-perspective/) — 用词\n- [Perez: Easy Paper Writing Tips](https://ethanperez.net/easy-paper-writing-tips/) — 微观清晰度\n\n**API：**\n- [Semantic Scholar](https://api.semanticscholar.org/api-docs/) | [CrossRef](https://www.crossref.org/documentation/) | [arXiv](https://info.arxiv.org/help/api/)\n\n**会议官方：**\n- [NeurIPS](https://neurips.cc/) | [ICML](https://icml.cc/) | [ICLR](https://iclr.cc/) | [ACL](https://www.aclweb.org/) | [AAAI](https://aaai.org/) | [EMNLP](https://2025.emnlp.org/)\n",
      "numLines": 353,
      "startLine": 1,
      "totalLines": 353
    }
  },
  "sourceToolAssistantUUID": "b63b565f-62d7-4b6e-8faf-fbcb58068cb9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Tool call

_source line 14 · 2026-05-20T07:49:46.050Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01EQebsobVqyZUJ3niojPNFY`</summary>

```json
{
  "pattern": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/docs/paper/sections/*.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "047c00bd-0f8b-4027-b6e1-42eeff22a6ba",
  "isSidechain": false,
  "requestId": "req_011CbDTJq42g6NhE85mBbRLK",
  "type": "assistant",
  "uuid": "2a951547-1a59-497d-b0a4-e743e770dd2b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0187PkzsZup1bbq5dR4N8wV9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14019,
      "cache_read_input_tokens": 11841,
      "output_tokens": 230,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 14019,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 230,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 14019,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 14019
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

_source line 15_

```json
{
  "type": "last-prompt",
  "leafUuid": "9fd3029f-cfa1-44f8-aa80-98241b4baa1d",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569"
}
```

---

### Runtime record

_source line 16_

```json
{
  "type": "ai-title",
  "aiTitle": "Write cosine R1 structural failure section",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569"
}
```

---

### Assistant

_source line 17 · 2026-05-20T07:49:48.966Z_

<details><summary>Logged reasoning block</summary>

```text
Let me read the existing sections to understand the style and conventions used so far.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9fd3029f-cfa1-44f8-aa80-98241b4baa1d",
  "isSidechain": false,
  "requestId": "req_011CbDTK9pe58pWb2wpwwHQr",
  "type": "assistant",
  "uuid": "15af5736-887f-4c3b-84c2-7905132c070c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TcXWsPX4ULW43gVuaVqt8T",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11248,
      "cache_read_input_tokens": 25860,
      "output_tokens": 219,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11248,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 219,
          "cache_read_input_tokens": 25860,
          "cache_creation_input_tokens": 11248,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11248
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

_source line 18 · 2026-05-20T07:49:49.419Z_

Let me read the existing sections to match style and conventions.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "15af5736-887f-4c3b-84c2-7905132c070c",
  "isSidechain": false,
  "requestId": "req_011CbDTK9pe58pWb2wpwwHQr",
  "type": "assistant",
  "uuid": "af40983e-3879-4452-af91-f21bb9e8b9ae",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TcXWsPX4ULW43gVuaVqt8T",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11248,
      "cache_read_input_tokens": 25860,
      "output_tokens": 219,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11248,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 219,
          "cache_read_input_tokens": 25860,
          "cache_creation_input_tokens": 11248,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11248
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

_source line 19 · 2026-05-20T07:49:50.817Z_

<details open><summary>🔧 Tool call — Read · `toolu_01UXuJ9Bkbekh44LznQyHTHn`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/docs/paper/sections/framework.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "af40983e-3879-4452-af91-f21bb9e8b9ae",
  "isSidechain": false,
  "requestId": "req_011CbDTK9pe58pWb2wpwwHQr",
  "type": "assistant",
  "uuid": "95547e05-8102-47b7-9788-e4bd4bb47df6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TcXWsPX4ULW43gVuaVqt8T",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11248,
      "cache_read_input_tokens": 25860,
      "output_tokens": 219,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11248,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 219,
          "cache_read_input_tokens": 25860,
          "cache_creation_input_tokens": 11248,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11248
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

_source line 20 · 2026-05-20T07:49:51.437Z_

<details><summary>↩ Tool result · `toolu_01REVbLC4CfS8Mcso56dPhnR`</summary>

```text
1	\section{Direction Discriminability}
2	\label{sec:direction_quality}
3	
4	Before evaluating $\dsyc$ as a reward signal (\S\ref{sec:cosine_failure}--\S\ref{sec:probe_trap}), we first establish that it captures a genuine sycophancy-related signal in the residual stream.
5	If the direction failed to discriminate sycophantic from non-sycophantic activations, downstream reward failures would be trivially explained by poor direction quality rather than by a fundamental gap between discriminability and reward utility.
6	We evaluate discriminability along five axes: cross-validated classification accuracy, evidence-strength stratification, cross-model transfer, training stability, and probe ablation.
7	Figure~\ref{fig:direction_quality} summarizes the per-layer AUROC profiles for both models.
8	
9	\paragraph{Qwen3-8B layer-wise discriminability.}
10	We evaluate $\dsyc$ via 5-fold cross-validated AUROC on 181 style-controlled contrastive pairs (\S\ref{ssec:extraction}).
11	The direction achieves AUROC $0.827 \pm 0.028$ at its best layer (L19).
12	Discriminability emerges gradually across depth: layers L0--L8 perform near chance, statistical significance ($p < 0.01$) first appears at L16, and performance peaks at L19.
13	This gradual emergence, with the peak in the upper third of the network, suggests that sycophancy-relevant information is encoded as a late-stage representation rather than an input-level confound.
14	The direction also captures evidential granularity.
15	AUROC rises monotonically from 0.675 on weak-evidence pairs to 0.883 on medium and 0.929 on strong pairs.
16	This gradient indicates that $\dsyc$ encodes the degree of evidential warrant, not merely a binary sycophancy label.
17	
18	\paragraph{Cross-model generalization.}
19	To rule out that these results are specific to Qwen3-8B's representation geometry, we repeat the full extraction and evaluation pipeline on Llama-3-8B-Instruct.
20	Table~\ref{tab:cross_model} compares the two models.
21	Llama-3-8B achieves CV AUROC $0.779 \pm 0.019$ at L16, with a parallel evidence-strength gradient (weak 0.711, medium 0.864, strong 0.911).
22	The best-layer depth differs (L16 vs.\ L19), consistent with the architectural differences between the two families, but the qualitative pattern is identical: gradual emergence, best-layer selection in the upper third, and monotonic strength scaling.
23	Discriminability is robust across knowledge domains, with per-domain AUROCs on Llama-3-8B ranging from 0.751 (geography) to 0.844 (commonsense).
24	When surface confounds (response length, hedging patterns) are explicitly controlled, Llama-3-8B's AUROC rises to 0.923, which confirms that the direction captures semantic content rather than stylistic artifacts.
25	The consistent results across architecturally distinct model families indicate that contrastive sycophancy directions reflect a shared representational phenomenon rather than a model-specific idiosyncrasy.
26	
27	\begin{table}[t]
28	\centering
29	\caption{Cross-model $\dsyc$ discriminability. CV AUROC is 5-fold cross-validated; evidence-strength AUROCs are evaluated on the full dataset at each model's best layer.}
30	\label{tab:cross_model}
31	\begin{tabular}{lccccc}
32	\toprule
33	Model & Best Layer & CV AUROC & Weak & Medium & Strong \\
34	\midrule
35	Qwen3-8B & L19 & $0.827{\pm}0.028$ & 0.675 & 0.883 & 0.929 \\
36	Llama-3-8B & L16 & $0.779{\pm}0.019$ & 0.711 & 0.864 & 0.911 \\
37	\bottomrule
38	\end{tabular}
39	\end{table}
40	
41	\paragraph{Training stability and probe ablation.}
42	Two additional analyses confirm the robustness of $\dsyc$ under training dynamics.
43	First, we track direction drift during LoRA fine-tuning: at step 500, the cosine similarity between the original and re-extracted $\dsyc$ is approximately 0.96, and per-layer AUROC remains above 0.77.
44	The direction drifts slowly relative to the 500-step recalibration interval (\S\ref{ssec:recalib}), so the reward signal does not become stale between updates.
45	Second, we compare $\dsyc$ against a random baseline: a logistic probe trained on the learned direction achieves AUROC 0.835, versus 0.727 for a probe trained on a random direction of equal dimensionality ($\Delta{=}{+}0.108$).
46	The learned direction carries substantially more sycophancy-relevant information than an arbitrary axis in the same activation space.
47	
48	\paragraph{Implications for reward design.}
49	These results establish that $\dsyc$ reliably separates sycophantic from non-sycophantic representations across models, evidence-strength levels, and training checkpoints.
50	Direction quality is not the bottleneck.
51	The reward failures documented in \S\ref{sec:cosine_failure}--\S\ref{sec:probe_trap} therefore cannot be attributed to a noisy or degenerate direction; they point to a deeper incompatibility between discriminability and reward utility.
52	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ea1feb90-fef0-4897-b6f3-060246dd16fb",
  "isSidechain": false,
  "promptId": "76de2f70-ac1e-444d-9c77-3c394a6cfdb7",
  "type": "user",
  "uuid": "b285c393-743d-493d-a940-851b55fb15b6",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/docs/paper/sections/direction_quality.tex",
      "content": "\\section{Direction Discriminability}\n\\label{sec:direction_quality}\n\nBefore evaluating $\\dsyc$ as a reward signal (\\S\\ref{sec:cosine_failure}--\\S\\ref{sec:probe_trap}), we first establish that it captures a genuine sycophancy-related signal in the residual stream.\nIf the direction failed to discriminate sycophantic from non-sycophantic activations, downstream reward failures would be trivially explained by poor direction quality rather than by a fundamental gap between discriminability and reward utility.\nWe evaluate discriminability along five axes: cross-validated classification accuracy, evidence-strength stratification, cross-model transfer, training stability, and probe ablation.\nFigure~\\ref{fig:direction_quality} summarizes the per-layer AUROC profiles for both models.\n\n\\paragraph{Qwen3-8B layer-wise discriminability.}\nWe evaluate $\\dsyc$ via 5-fold cross-validated AUROC on 181 style-controlled contrastive pairs (\\S\\ref{ssec:extraction}).\nThe direction achieves AUROC $0.827 \\pm 0.028$ at its best layer (L19).\nDiscriminability emerges gradually across depth: layers L0--L8 perform near chance, statistical significance ($p < 0.01$) first appears at L16, and performance peaks at L19.\nThis gradual emergence, with the peak in the upper third of the network, suggests that sycophancy-relevant information is encoded as a late-stage representation rather than an input-level confound.\nThe direction also captures evidential granularity.\nAUROC rises monotonically from 0.675 on weak-evidence pairs to 0.883 on medium and 0.929 on strong pairs.\nThis gradient indicates that $\\dsyc$ encodes the degree of evidential warrant, not merely a binary sycophancy label.\n\n\\paragraph{Cross-model generalization.}\nTo rule out that these results are specific to Qwen3-8B's representation geometry, we repeat the full extraction and evaluation pipeline on Llama-3-8B-Instruct.\nTable~\\ref{tab:cross_model} compares the two models.\nLlama-3-8B achieves CV AUROC $0.779 \\pm 0.019$ at L16, with a parallel evidence-strength gradient (weak 0.711, medium 0.864, strong 0.911).\nThe best-layer depth differs (L16 vs.\\ L19), consistent with the architectural differences between the two families, but the qualitative pattern is identical: gradual emergence, best-layer selection in the upper third, and monotonic strength scaling.\nDiscriminability is robust across knowledge domains, with per-domain AUROCs on Llama-3-8B ranging from 0.751 (geography) to 0.844 (commonsense).\nWhen surface confounds (response length, hedging patterns) are explicitly controlled, Llama-3-8B's AUROC rises to 0.923, which confirms that the direction captures semantic content rather than stylistic artifacts.\nThe consistent results across architecturally distinct model families indicate that contrastive sycophancy directions reflect a shared representational phenomenon rather than a model-specific idiosyncrasy.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cross-model $\\dsyc$ discriminability. CV AUROC is 5-fold cross-validated; evidence-strength AUROCs are evaluated on the full dataset at each model's best layer.}\n\\label{tab:cross_model}\n\\begin{tabular}{lccccc}\n\\toprule\nModel & Best Layer & CV AUROC & Weak & Medium & Strong \\\\\n\\midrule\nQwen3-8B & L19 & $0.827{\\pm}0.028$ & 0.675 & 0.883 & 0.929 \\\\\nLlama-3-8B & L16 & $0.779{\\pm}0.019$ & 0.711 & 0.864 & 0.911 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Training stability and probe ablation.}\nTwo additional analyses confirm the robustness of $\\dsyc$ under training dynamics.\nFirst, we track direction drift during LoRA fine-tuning: at step 500, the cosine similarity between the original and re-extracted $\\dsyc$ is approximately 0.96, and per-layer AUROC remains above 0.77.\nThe direction drifts slowly relative to the 500-step recalibration interval (\\S\\ref{ssec:recalib}), so the reward signal does not become stale between updates.\nSecond, we compare $\\dsyc$ against a random baseline: a logistic probe trained on the learned direction achieves AUROC 0.835, versus 0.727 for a probe trained on a random direction of equal dimensionality ($\\Delta{=}{+}0.108$).\nThe learned direction carries substantially more sycophancy-relevant information than an arbitrary axis in the same activation space.\n\n\\paragraph{Implications for reward design.}\nThese results establish that $\\dsyc$ reliably separates sycophantic from non-sycophantic representations across models, evidence-strength levels, and training checkpoints.\nDirection quality is not the bottleneck.\nThe reward failures documented in \\S\\ref{sec:cosine_failure}--\\S\\ref{sec:probe_trap} therefore cannot be attributed to a noisy or degenerate direction; they point to a deeper incompatibility between discriminability and reward utility.\n",
      "numLines": 52,
      "startLine": 1,
      "totalLines": 52
    }
  },
  "sourceToolAssistantUUID": "ea1feb90-fef0-4897-b6f3-060246dd16fb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 21 · 2026-05-20T07:49:50.822Z_

<details><summary>↩ Tool result · `toolu_01UXuJ9Bkbekh44LznQyHTHn`</summary>

```text
1	\section{Experimental Framework}
2	\label{sec:framework}
3	
4	This section establishes the notation, experimental components, and evaluation protocol used throughout the paper.
5	We first describe how the contrastive sycophancy direction $\dsyc$ is extracted (\S\ref{ssec:extraction}), then define three reward formulations that incorporate $\dsyc$ into GRPO training (\S\ref{ssec:reward}), explain the online recalibration procedure (\S\ref{ssec:recalib}), and finally specify the evaluation metrics (\S\ref{ssec:eval}).
6	
7	\subsection{Direction Extraction}
8	\label{ssec:extraction}
9	
10	We extract a linear sycophancy direction $\dsyc$ from the residual stream of a target model using contrastive activation pairs.
11	Each pair consists of two model responses to the same user challenge: a \emph{valid correction}, in which the model appropriately revises its earlier answer upon receiving well-supported counter-evidence, and a \emph{sycophantic capitulation}, in which the model abandons a correct answer under social pressure without adequate evidential warrant.
12	
13	To isolate the cognitive signal from surface-level linguistic variation, we apply style control: both responses in each pair are generated with matched hedging patterns, politeness markers, and response length, so that $\dsyc$ reflects the distinction between warranted and unwarranted belief change rather than stylistic differences.
14	Concretely, we construct 362 style-controlled contrastive activations from 181 paired examples stratified across three evidence-strength levels (weak, medium, strong).
15	
16	Given a target layer $\ell$, let $\mathbf{h}^{+}_i$ denote the residual-stream activation for the $i$-th valid correction and $\mathbf{h}^{-}_i$ for the corresponding sycophantic capitulation.
17	The sycophancy direction is the mean difference:
18	\begin{equation}
19	\label{eq:dsyc}
20	\dsyc = \frac{1}{N}\sum_{i=1}^{N}\left(\mathbf{h}^{+}_i - \mathbf{h}^{-}_i\right)
21	\end{equation}
22	where $N{=}181$ is the number of contrastive pairs.
23	We select the target layer by 5-fold cross-validated AUROC over a linear classifier trained on the projection $\mathbf{h} \cdot \dsyc$; on Qwen3-8B this yields layer 19 with AUROC $0.827 \pm 0.028$ (exp-001).
24	Section~\ref{sec:direction_quality} presents detailed discriminability analyses, including cross-model validation on Llama-3-8B.
25	
26	\subsection{GRPO Reward Formulation}
27	\label{ssec:reward}
28	
29	Group Relative Policy Optimization \citep[GRPO;][]{shao2024grpo} uses a reward signal to rank sampled completions and update the policy toward higher-reward outputs.
30	We define a combined reward:
31	\begin{equation}
32	\label{eq:reward}
33	R = w_1 \cdot \rone + w_3 \cdot \rthree
34	\end{equation}
35	where $\rone$ is a direction-based component derived from $\dsyc$ and $\rthree$ is a behavioral component.
36	
37	\paragraph{Direction-based reward ($\rone$).}
38	We investigate three formulations that translate $\dsyc$ into a scalar training signal.
39	Let $\mathbf{h}$ denote the model's residual-stream activation at a designated token position during a training rollout.
40	
41	\begin{itemize}
42	\item[\textbf{F1}] \textbf{Cosine.} $\rone = \cos(\mathbf{h},\, \dsyc)$, the cosine similarity between the activation and the sycophancy direction.
43	\item[\textbf{F2}] \textbf{Scaled cosine.} $\rone = \alpha \cdot \cos(\mathbf{h},\, \dsyc)$, where $\alpha$ amplifies the gradient signal to compete with $\rthree$ in magnitude.
44	\item[\textbf{F3}] \textbf{Binary probe.} $\rone = \mathbb{I}[P(\text{syc} \mid \mathbf{h}) < 0.5]$, a binary indicator derived from a logistic probe trained on the same contrastive data. The probe is frozen during GRPO training and gradients are stopped at its input.
45	\end{itemize}
46	
47	\paragraph{Behavioral reward ($\rthree$).}
48	$\rthree$ is computed by a DeBERTa-based natural language inference (NLI) classifier that scores whether the model's response is consistent with the ground-truth answer.
49	This component provides a task-level behavioral signal independent of internal representations.
50	The weight configuration ($w_1$, $w_3$) varies across experiments and is specified in the corresponding sections (\S\ref{sec:cosine_failure}, \S\ref{sec:probe_trap}).
51	
52	\subsection{Online Recalibration}
53	\label{ssec:recalib}
54	
55	LoRA fine-tuning progressively shifts the model's internal representations, which could cause $\dsyc$ to become misaligned with the current activation geometry.
56	To address this, we re-extract $\dsyc$ every 500 training steps by re-running the contrastive pairs through the updated model and recomputing Equation~\ref{eq:dsyc}.
57	Empirically, the cosine similarity between consecutive directions remains high (${\approx}\,0.96$ at step 500), indicating that the direction drifts slowly relative to the recalibration frequency.
58	This procedure ensures that $\rone$ tracks the evolving representation space throughout training rather than scoring against a stale direction.
59	
60	\subsection{Evaluation Protocol}
61	\label{ssec:eval}
62	
63	We evaluate sycophancy mitigation along two complementary axes: the model's willingness to accept valid corrections and its resistance to invalid pressure.
64	
65	\paragraph{Metrics.}
66	We define two primary rates.
67	The \emph{True-positive Flip rate} ($\tof$) measures the fraction of valid corrections that the model accepts, i.e., cases where the model appropriately revises an incorrect initial answer when presented with well-supported counter-evidence.
68	The \emph{No-Flip rate} ($\nof$) measures the fraction of invalid challenges that the model resists, i.e., cases where the model maintains a correct initial answer despite unsupported social pressure.
69	Both rates range from 0 to 1 with higher values indicating better performance.
70	
71	A model that accepts all challenges (including invalid ones) achieves high $\tof$ but low $\nof$; a model that rejects all challenges achieves the opposite.
72	We capture this trade-off with $\sycon$, the harmonic mean of the two rates:
73	\begin{equation}
74	\label{eq:sycon}
75	\sycon = \frac{2 \cdot \tof \cdot \nof}{\tof + \nof}
76	\end{equation}
77	
78	$\sycon$ is analogous to the $F_1$ score: it penalizes models that sacrifice one axis for the other, and a high $\sycon$ requires balanced performance on both.
79	Classification of each response (flip vs.\ no-flip) is determined by an NLI-based procedure following the protocol of \citet{consistency2025bctact}.
80	
81	\paragraph{Test set and model configuration.}
82	Evaluation uses the same 362 style-controlled contrastive instances (181 pairs, weak/medium/strong stratification) described in \S\ref{ssec:extraction}, with a held-out split not used during direction extraction.
83	All training experiments use Qwen3-8B with LoRA (rank$=$64, $\alpha{=}128$) and DeepSpeed ZeRO-2 for memory-efficient optimization.
84	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "95547e05-8102-47b7-9788-e4bd4bb47df6",
  "isSidechain": false,
  "promptId": "76de2f70-ac1e-444d-9c77-3c394a6cfdb7",
  "type": "user",
  "uuid": "4937dc76-5ef3-4dec-b642-17aa29a757d0",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/docs/paper/sections/framework.tex",
      "content": "\\section{Experimental Framework}\n\\label{sec:framework}\n\nThis section establishes the notation, experimental components, and evaluation protocol used throughout the paper.\nWe first describe how the contrastive sycophancy direction $\\dsyc$ is extracted (\\S\\ref{ssec:extraction}), then define three reward formulations that incorporate $\\dsyc$ into GRPO training (\\S\\ref{ssec:reward}), explain the online recalibration procedure (\\S\\ref{ssec:recalib}), and finally specify the evaluation metrics (\\S\\ref{ssec:eval}).\n\n\\subsection{Direction Extraction}\n\\label{ssec:extraction}\n\nWe extract a linear sycophancy direction $\\dsyc$ from the residual stream of a target model using contrastive activation pairs.\nEach pair consists of two model responses to the same user challenge: a \\emph{valid correction}, in which the model appropriately revises its earlier answer upon receiving well-supported counter-evidence, and a \\emph{sycophantic capitulation}, in which the model abandons a correct answer under social pressure without adequate evidential warrant.\n\nTo isolate the cognitive signal from surface-level linguistic variation, we apply style control: both responses in each pair are generated with matched hedging patterns, politeness markers, and response length, so that $\\dsyc$ reflects the distinction between warranted and unwarranted belief change rather than stylistic differences.\nConcretely, we construct 362 style-controlled contrastive activations from 181 paired examples stratified across three evidence-strength levels (weak, medium, strong).\n\nGiven a target layer $\\ell$, let $\\mathbf{h}^{+}_i$ denote the residual-stream activation for the $i$-th valid correction and $\\mathbf{h}^{-}_i$ for the corresponding sycophantic capitulation.\nThe sycophancy direction is the mean difference:\n\\begin{equation}\n\\label{eq:dsyc}\n\\dsyc = \\frac{1}{N}\\sum_{i=1}^{N}\\left(\\mathbf{h}^{+}_i - \\mathbf{h}^{-}_i\\right)\n\\end{equation}\nwhere $N{=}181$ is the number of contrastive pairs.\nWe select the target layer by 5-fold cross-validated AUROC over a linear classifier trained on the projection $\\mathbf{h} \\cdot \\dsyc$; on Qwen3-8B this yields layer 19 with AUROC $0.827 \\pm 0.028$ (exp-001).\nSection~\\ref{sec:direction_quality} presents detailed discriminability analyses, including cross-model validation on Llama-3-8B.\n\n\\subsection{GRPO Reward Formulation}\n\\label{ssec:reward}\n\nGroup Relative Policy Optimization \\citep[GRPO;][]{shao2024grpo} uses a reward signal to rank sampled completions and update the policy toward higher-reward outputs.\nWe define a combined reward:\n\\begin{equation}\n\\label{eq:reward}\nR = w_1 \\cdot \\rone + w_3 \\cdot \\rthree\n\\end{equation}\nwhere $\\rone$ is a direction-based component derived from $\\dsyc$ and $\\rthree$ is a behavioral component.\n\n\\paragraph{Direction-based reward ($\\rone$).}\nWe investigate three formulations that translate $\\dsyc$ into a scalar training signal.\nLet $\\mathbf{h}$ denote the model's residual-stream activation at a designated token position during a training rollout.\n\n\\begin{itemize}\n\\item[\\textbf{F1}] \\textbf{Cosine.} $\\rone = \\cos(\\mathbf{h},\\, \\dsyc)$, the cosine similarity between the activation and the sycophancy direction.\n\\item[\\textbf{F2}] \\textbf{Scaled cosine.} $\\rone = \\alpha \\cdot \\cos(\\mathbf{h},\\, \\dsyc)$, where $\\alpha$ amplifies the gradient signal to compete with $\\rthree$ in magnitude.\n\\item[\\textbf{F3}] \\textbf{Binary probe.} $\\rone = \\mathbb{I}[P(\\text{syc} \\mid \\mathbf{h}) < 0.5]$, a binary indicator derived from a logistic probe trained on the same contrastive data. The probe is frozen during GRPO training and gradients are stopped at its input.\n\\end{itemize}\n\n\\paragraph{Behavioral reward ($\\rthree$).}\n$\\rthree$ is computed by a DeBERTa-based natural language inference (NLI) classifier that scores whether the model's response is consistent with the ground-truth answer.\nThis component provides a task-level behavioral signal independent of internal representations.\nThe weight configuration ($w_1$, $w_3$) varies across experiments and is specified in the corresponding sections (\\S\\ref{sec:cosine_failure}, \\S\\ref{sec:probe_trap}).\n\n\\subsection{Online Recalibration}\n\\label{ssec:recalib}\n\nLoRA fine-tuning progressively shifts the model's internal representations, which could cause $\\dsyc$ to become misaligned with the current activation geometry.\nTo address this, we re-extract $\\dsyc$ every 500 training steps by re-running the contrastive pairs through the updated model and recomputing Equation~\\ref{eq:dsyc}.\nEmpirically, the cosine similarity between consecutive directions remains high (${\\approx}\\,0.96$ at step 500), indicating that the direction drifts slowly relative to the recalibration frequency.\nThis procedure ensures that $\\rone$ tracks the evolving representation space throughout training rather than scoring against a stale direction.\n\n\\subsection{Evaluation Protocol}\n\\label{ssec:eval}\n\nWe evaluate sycophancy mitigation along two complementary axes: the model's willingness to accept valid corrections and its resistance to invalid pressure.\n\n\\paragraph{Metrics.}\nWe define two primary rates.\nThe \\emph{True-positive Flip rate} ($\\tof$) measures the fraction of valid corrections that the model accepts, i.e., cases where the model appropriately revises an incorrect initial answer when presented with well-supported counter-evidence.\nThe \\emph{No-Flip rate} ($\\nof$) measures the fraction of invalid challenges that the model resists, i.e., cases where the model maintains a correct initial answer despite unsupported social pressure.\nBoth rates range from 0 to 1 with higher values indicating better performance.\n\nA model that accepts all challenges (including invalid ones) achieves high $\\tof$ but low $\\nof$; a model that rejects all challenges achieves the opposite.\nWe capture this trade-off with $\\sycon$, the harmonic mean of the two rates:\n\\begin{equation}\n\\label{eq:sycon}\n\\sycon = \\frac{2 \\cdot \\tof \\cdot \\nof}{\\tof + \\nof}\n\\end{equation}\n\n$\\sycon$ is analogous to the $F_1$ score: it penalizes models that sacrifice one axis for the other, and a high $\\sycon$ requires balanced performance on both.\nClassification of each response (flip vs.\\ no-flip) is determined by an NLI-based procedure following the protocol of \\citet{consistency2025bctact}.\n\n\\paragraph{Test set and model configuration.}\nEvaluation uses the same 362 style-controlled contrastive instances (181 pairs, weak/medium/strong stratification) described in \\S\\ref{ssec:extraction}, with a held-out split not used during direction extraction.\nAll training experiments use Qwen3-8B with LoRA (rank$=$64, $\\alpha{=}128$) and DeepSpeed ZeRO-2 for memory-efficient optimization.\n",
      "numLines": 84,
      "startLine": 1,
      "totalLines": 84
    }
  },
  "sourceToolAssistantUUID": "95547e05-8102-47b7-9788-e4bd4bb47df6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 22 · 2026-05-20T07:49:51.432Z_

<details open><summary>🔧 Tool call — Read · `toolu_01REVbLC4CfS8Mcso56dPhnR`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/docs/paper/sections/direction_quality.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4937dc76-5ef3-4dec-b642-17aa29a757d0",
  "isSidechain": false,
  "requestId": "req_011CbDTK9pe58pWb2wpwwHQr",
  "type": "assistant",
  "uuid": "ea1feb90-fef0-4897-b6f3-060246dd16fb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TcXWsPX4ULW43gVuaVqt8T",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11248,
      "cache_read_input_tokens": 25860,
      "output_tokens": 219,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 11248,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 219,
          "cache_read_input_tokens": 25860,
          "cache_creation_input_tokens": 11248,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 11248
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

_source line 23 · 2026-05-20T07:49:59.746Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clear picture of the style, conventions, and what's been established in §2 and §3. Let me write the §4 section.

Key conventions from existing sections:
- `\dsyc`, `\rone`, `\rthree`, `\tof`, `\nof`, `\sycon` custom commands
- Reference style: `\S\ref{...}`, `\citet{...}`, `\citep{...}`
- Paragraph headings with `\paragraph{}`
- No em-dashes, no -ing endings
- Analytical tone


- Booktabs tables for formatting
- Each section opens with an orientation sentence

Now I'll draft the section.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b285c393-743d-493d-a940-851b55fb15b6",
  "isSidechain": false,
  "requestId": "req_011CbDTKZ4dLt97wD4w5Z75J",
  "type": "assistant",
  "uuid": "9e54c1cc-6160-40b6-9b16-9d7c99da5ed3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AqSNX6bBDY8Xxa3ZwqA423",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3820,
      "cache_read_input_tokens": 37108,
      "output_tokens": 2414,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3820,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2414,
          "cache_read_input_tokens": 37108,
          "cache_creation_input_tokens": 3820,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3820
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

_source line 24 · 2026-05-20T07:49:59.752Z_

Now I have the full context. Let me write the section.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9e54c1cc-6160-40b6-9b16-9d7c99da5ed3",
  "isSidechain": false,
  "requestId": "req_011CbDTKZ4dLt97wD4w5Z75J",
  "type": "assistant",
  "uuid": "f1754c4d-f5e2-4643-9b75-71c7289b6319",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AqSNX6bBDY8Xxa3ZwqA423",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3820,
      "cache_read_input_tokens": 37108,
      "output_tokens": 2414,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3820,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2414,
          "cache_read_input_tokens": 37108,
          "cache_creation_input_tokens": 3820,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3820
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

_source line 25 · 2026-05-20T07:50:43.265Z_

<details open><summary>🔧 Tool call — Write · `toolu_01FitnxaTSUCNhRc48CbqxvW`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/docs/paper/sections/cosine_failure.tex",
  "content": "\\section{Cosine \\texorpdfstring{$\\rone$}{R1}: Structural Failure}\n\\label{sec:cosine_failure}\n\nSection~\\ref{sec:direction_quality} established that $\\dsyc$ achieves AUROC 0.827 on Qwen3-8B and generalizes across models.\nWe now test whether this discriminability translates into a viable GRPO reward signal.\nThis section reports four configurations (F1a--F1d) that form a systematic diagnostic chain: each configuration resolves the failure mode of its predecessor but exposes a deeper structural limitation.\nTable~\\ref{tab:cosine_chain} summarizes the chain; Figure~\\ref{fig:cosine_failure} visualizes the training dynamics.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cosine $\\rone$ failure chain. Each configuration addresses the preceding failure but reveals a more fundamental limitation. All experiments use Qwen3-8B with LoRA (rank$=$64) and GRPO with $R = w_1 \\cdot \\rone + w_3 \\cdot \\rthree$.}\n\\label{tab:cosine_chain}\n\\begin{tabular}{lllll}\n\\toprule\nConfig & $\\rone$ Formula & $w_1$ & Outcome & Root Cause \\\\\n\\midrule\nF1a & $\\tanh(\\mathbf{h}\\cdot\\dsyc/20)$ & 0.25 & Gate saturation & Norm mismatch \\\\\nF1b & $\\cos(\\mathbf{h},\\, \\dsyc)$ & 0.25 & $\\rone \\approx 0$ & Gap too small \\\\\nF1c & +recalibration & 0.25 & Mode collapse & Reward discontinuity \\\\\nF1d & $5\\cos(\\mathbf{h},\\, \\dsyc)$ & 0.40 & Mode collapse & $\\rthree$ saturation + noise \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{F1a: Tanh gate saturation (exp-002).}\nThe initial configuration defines $\\rone = \\tanh(\\mathbf{h} \\cdot \\dsyc / 20)$ with $w_1{=}0.25$, $w_3{=}0.75$.\nThe dot product formulation preserves directional sensitivity but is not scale-invariant: activation norms in the residual stream range from $100{\\times}$ to $1{,}200{\\times}$ the direction norm across layers.\nThis norm mismatch drives the pre-activation into the saturated tails of tanh, where the gradient vanishes.\nBy step 955, $\\rone$ contributes effectively zero gradient to the combined reward, and training was terminated.\nSubsequent weight adjustments ($w_1{=}0.15$, $w_3{=}0.65$) did not resolve the saturation because the pre-activation magnitude, not the weight, controls the gate.\nThe diagnostic conclusion is clear: any formulation that passes raw dot products through a bounded nonlinearity will saturate in high-norm activation spaces.\nCosine similarity, which normalizes by both norms, is the natural alternative.\n\n\\paragraph{F1b: Raw cosine signal too weak (exp-002v2).}\nReplacing the dot product with cosine similarity ($\\rone = \\cos(\\mathbf{h},\\, \\dsyc)$) eliminates the norm dependence.\nHowever, the cosine gap between valid corrections and sycophantic capitulations is only 0.098 when averaged across the seven highest-AUROC layers.\nWith $w_1{=}0.25$, this yields an effective $\\rone$ contribution of approximately $0.025$ per token, a signal that is negligible relative to $\\rthree$ variance.\nThroughout training, $\\rone \\approx 0$, and the combined reward $R$ is functionally equivalent to $w_3 \\cdot \\rthree$ alone.\nTraining was terminated after confirming that the sycophancy component exerts no measurable influence on policy updates.\nThe failure isolates a quantitative limitation: the cosine projection of $\\dsyc$ onto individual activations produces a gap too narrow to generate meaningful reward contrast between sycophantic and non-sycophantic completions.\n\n\\paragraph{F1c: Recalibration induces mode collapse (exp002v2-recalib).}\nOne hypothesis for the weak signal in F1b is that $\\dsyc$ drifts during LoRA training, eroding the already-small gap.\nTo test this, we resume from the exp-002v2 checkpoint at step 500 and enable the online recalibration procedure described in \\S\\ref{ssec:recalib}, re-extracting $\\dsyc$ every 500 steps.\nRecalibration increases the offline AUROC from 0.82 to 0.91, confirming that the refreshed direction better separates the updated activations.\nTraining collapses nonetheless.\nWithin 300 steps of the first recalibration event, the policy degenerates into a low-entropy mode: generation entropy drops to 0.069, and mean response length contracts to 62 tokens.\nThe mechanism is a reward discontinuity at the recalibration boundary.\nWhen $\\dsyc$ is replaced by a fresh direction, the cosine projection of every cached rollout shifts abruptly.\nCompletions that were mildly rewarded under the stale direction may become penalized under the fresh one, and vice versa.\nThis discontinuity destabilizes the GRPO advantage estimates and drives the policy toward a narrow region of activation space that remains low-risk under both the old and new directions.\nThe result is a degenerate policy that produces short, hedged responses regardless of the input.\nImproving direction quality via recalibration, paradoxically, makes the reward landscape less stable.\n\n\\paragraph{F1d: Scaling amplifies noise (exp-002v3).}\nConfiguration F1d addresses the magnitude problem directly: $\\rone = 5 \\cdot \\cos(\\mathbf{h},\\, \\dsyc)$ with $w_1{=}0.4$, $w_3{=}0.6$.\nThe $5{\\times}$ scaling lifts the $\\rone$ contribution above the $\\rthree$ noise floor, but it simultaneously amplifies the noise in the cosine projection.\nTraining proceeds in three phases.\nIn the first phase (steps 100--300), $\\rthree$ saturates at 0.9998 as the policy rapidly learns to produce NLI-consistent answers; mean response length drops from 247 to 80 tokens and entropy falls from 0.45 to 0.10.\nIn the second phase (steps 300--2150), the combined reward degenerates to $R \\approx w_1 \\cdot \\rone + \\text{const}$ because the saturated $\\rthree$ provides no gradient.\n$\\rone$ is now the sole learning signal, but its mean oscillates between $-0.46$ and $+0.41$ with no sustained positive trend, because the cosine projection conflates warranted belief revision with unwarranted capitulation (both shift activations toward the user's position along $\\dsyc$).\nIn the third phase (step 2160), the policy collapses terminally: entropy drops from 0.056 to 0.026, and the fraction of completions with zero reward standard deviation rises from 0.125 to 0.419, indicating that the policy has converged to a near-deterministic mode.\n\n\\paragraph{Unified diagnosis.}\nThe four configurations converge on a single structural limitation.\nThe cosine gap between valid and sycophantic activations (0.098 across layers) is too narrow to serve as a reward signal, and this narrowness is not a calibration artifact.\nRecalibration raises offline AUROC to 0.91 yet rewards still fail (F1c), confirming that direction quality is not the bottleneck.\nThe root cause is semantic: $\\dsyc$ encodes the \\emph{direction} of belief change (toward or away from the user's position) but does not encode whether that change is \\emph{warranted}.\nA model that appropriately revises an incorrect answer in response to strong evidence and a model that capitulates under social pressure both shift their activations toward the user's position along $\\dsyc$.\nThe cosine projection assigns similar scores to both behaviors.\nScaling the projection (F1d) amplifies this conflation rather than resolving it.\nAny reward formulation that uses $\\dsyc$ as a continuous scalar will inherit this ambiguity.\nSection~\\ref{sec:probe_trap} examines whether discretizing the signal via a binary probe can escape this limitation.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f1754c4d-f5e2-4643-9b75-71c7289b6319",
  "isSidechain": false,
  "requestId": "req_011CbDTKZ4dLt97wD4w5Z75J",
  "type": "assistant",
  "uuid": "fe392ba9-5e9b-4a9f-b0f8-ce25547d1297",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AqSNX6bBDY8Xxa3ZwqA423",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3820,
      "cache_read_input_tokens": 37108,
      "output_tokens": 2414,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 3820,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2414,
          "cache_read_input_tokens": 37108,
          "cache_creation_input_tokens": 3820,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 3820
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

_source line 26 · 2026-05-20T07:50:43.291Z_

<details><summary>↩ Tool result · `toolu_01FitnxaTSUCNhRc48CbqxvW`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/docs/paper/sections/cosine_failure.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fe392ba9-5e9b-4a9f-b0f8-ce25547d1297",
  "isSidechain": false,
  "promptId": "76de2f70-ac1e-444d-9c77-3c394a6cfdb7",
  "type": "user",
  "uuid": "5b4f9b42-81d1-454c-8675-c45b81845165",
  "toolUseResult": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/docs/paper/sections/cosine_failure.tex",
    "content": "\\section{Cosine \\texorpdfstring{$\\rone$}{R1}: Structural Failure}\n\\label{sec:cosine_failure}\n\nSection~\\ref{sec:direction_quality} established that $\\dsyc$ achieves AUROC 0.827 on Qwen3-8B and generalizes across models.\nWe now test whether this discriminability translates into a viable GRPO reward signal.\nThis section reports four configurations (F1a--F1d) that form a systematic diagnostic chain: each configuration resolves the failure mode of its predecessor but exposes a deeper structural limitation.\nTable~\\ref{tab:cosine_chain} summarizes the chain; Figure~\\ref{fig:cosine_failure} visualizes the training dynamics.\n\n\\begin{table}[t]\n\\centering\n\\caption{Cosine $\\rone$ failure chain. Each configuration addresses the preceding failure but reveals a more fundamental limitation. All experiments use Qwen3-8B with LoRA (rank$=$64) and GRPO with $R = w_1 \\cdot \\rone + w_3 \\cdot \\rthree$.}\n\\label{tab:cosine_chain}\n\\begin{tabular}{lllll}\n\\toprule\nConfig & $\\rone$ Formula & $w_1$ & Outcome & Root Cause \\\\\n\\midrule\nF1a & $\\tanh(\\mathbf{h}\\cdot\\dsyc/20)$ & 0.25 & Gate saturation & Norm mismatch \\\\\nF1b & $\\cos(\\mathbf{h},\\, \\dsyc)$ & 0.25 & $\\rone \\approx 0$ & Gap too small \\\\\nF1c & +recalibration & 0.25 & Mode collapse & Reward discontinuity \\\\\nF1d & $5\\cos(\\mathbf{h},\\, \\dsyc)$ & 0.40 & Mode collapse & $\\rthree$ saturation + noise \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{F1a: Tanh gate saturation (exp-002).}\nThe initial configuration defines $\\rone = \\tanh(\\mathbf{h} \\cdot \\dsyc / 20)$ with $w_1{=}0.25$, $w_3{=}0.75$.\nThe dot product formulation preserves directional sensitivity but is not scale-invariant: activation norms in the residual stream range from $100{\\times}$ to $1{,}200{\\times}$ the direction norm across layers.\nThis norm mismatch drives the pre-activation into the saturated tails of tanh, where the gradient vanishes.\nBy step 955, $\\rone$ contributes effectively zero gradient to the combined reward, and training was terminated.\nSubsequent weight adjustments ($w_1{=}0.15$, $w_3{=}0.65$) did not resolve the saturation because the pre-activation magnitude, not the weight, controls the gate.\nThe diagnostic conclusion is clear: any formulation that passes raw dot products through a bounded nonlinearity will saturate in high-norm activation spaces.\nCosine similarity, which normalizes by both norms, is the natural alternative.\n\n\\paragraph{F1b: Raw cosine signal too weak (exp-002v2).}\nReplacing the dot product with cosine similarity ($\\rone = \\cos(\\mathbf{h},\\, \\dsyc)$) eliminates the norm dependence.\nHowever, the cosine gap between valid corrections and sycophantic capitulations is only 0.098 when averaged across the seven highest-AUROC layers.\nWith $w_1{=}0.25$, this yields an effective $\\rone$ contribution of approximately $0.025$ per token, a signal that is negligible relative to $\\rthree$ variance.\nThroughout training, $\\rone \\approx 0$, and the combined reward $R$ is functionally equivalent to $w_3 \\cdot \\rthree$ alone.\nTraining was terminated after confirming that the sycophancy component exerts no measurable influence on policy updates.\nThe failure isolates a quantitative limitation: the cosine projection of $\\dsyc$ onto individual activations produces a gap too narrow to generate meaningful reward contrast between sycophantic and non-sycophantic completions.\n\n\\paragraph{F1c: Recalibration induces mode collapse (exp002v2-recalib).}\nOne hypothesis for the weak signal in F1b is that $\\dsyc$ drifts during LoRA training, eroding the already-small gap.\nTo test this, we resume from the exp-002v2 checkpoint at step 500 and enable the online recalibration procedure described in \\S\\ref{ssec:recalib}, re-extracting $\\dsyc$ every 500 steps.\nRecalibration increases the offline AUROC from 0.82 to 0.91, confirming that the refreshed direction better separates the updated activations.\nTraining collapses nonetheless.\nWithin 300 steps of the first recalibration event, the policy degenerates into a low-entropy mode: generation entropy drops to 0.069, and mean response length contracts to 62 tokens.\nThe mechanism is a reward discontinuity at the recalibration boundary.\nWhen $\\dsyc$ is replaced by a fresh direction, the cosine projection of every cached rollout shifts abruptly.\nCompletions that were mildly rewarded under the stale direction may become penalized under the fresh one, and vice versa.\nThis discontinuity destabilizes the GRPO advantage estimates and drives the policy toward a narrow region of activation space that remains low-risk under both the old and new directions.\nThe result is a degenerate policy that produces short, hedged responses regardless of the input.\nImproving direction quality via recalibration, paradoxically, makes the reward landscape less stable.\n\n\\paragraph{F1d: Scaling amplifies noise (exp-002v3).}\nConfiguration F1d addresses the magnitude problem directly: $\\rone = 5 \\cdot \\cos(\\mathbf{h},\\, \\dsyc)$ with $w_1{=}0.4$, $w_3{=}0.6$.\nThe $5{\\times}$ scaling lifts the $\\rone$ contribution above the $\\rthree$ noise floor, but it simultaneously amplifies the noise in the cosine projection.\nTraining proceeds in three phases.\nIn the first phase (steps 100--300), $\\rthree$ saturates at 0.9998 as the policy rapidly learns to produce NLI-consistent answers; mean response length drops from 247 to 80 tokens and entropy falls from 0.45 to 0.10.\nIn the second phase (steps 300--2150), the combined reward degenerates to $R \\approx w_1 \\cdot \\rone + \\text{const}$ because the saturated $\\rthree$ provides no gradient.\n$\\rone$ is now the sole learning signal, but its mean oscillates between $-0.46$ and $+0.41$ with no sustained positive trend, because the cosine projection conflates warranted belief revision with unwarranted capitulation (both shift activations toward the user's position along $\\dsyc$).\nIn the third phase (step 2160), the policy collapses terminally: entropy drops from 0.056 to 0.026, and the fraction of completions with zero reward standard deviation rises from 0.125 to 0.419, indicating that the policy has converged to a near-deterministic mode.\n\n\\paragraph{Unified diagnosis.}\nThe four configurations converge on a single structural limitation.\nThe cosine gap between valid and sycophantic activations (0.098 across layers) is too narrow to serve as a reward signal, and this narrowness is not a calibration artifact.\nRecalibration raises offline AUROC to 0.91 yet rewards still fail (F1c), confirming that direction quality is not the bottleneck.\nThe root cause is semantic: $\\dsyc$ encodes the \\emph{direction} of belief change (toward or away from the user's position) but does not encode whether that change is \\emph{warranted}.\nA model that appropriately revises an incorrect answer in response to strong evidence and a model that capitulates under social pressure both shift their activations toward the user's position along $\\dsyc$.\nThe cosine projection assigns similar scores to both behaviors.\nScaling the projection (F1d) amplifies this conflation rather than resolving it.\nAny reward formulation that uses $\\dsyc$ as a continuous scalar will inherit this ambiguity.\nSection~\\ref{sec:probe_trap} examines whether discretizing the signal via a binary probe can escape this limitation.\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  },
  "sourceToolAssistantUUID": "fe392ba9-5e9b-4a9f-b0f8-ce25547d1297",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 27_

```json
{
  "type": "last-prompt",
  "leafUuid": "5b4f9b42-81d1-454c-8675-c45b81845165",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569"
}
```

---

### Runtime record

_source line 28_

```json
{
  "type": "ai-title",
  "aiTitle": "Write cosine R1 structural failure section",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569"
}
```

---

### Assistant

_source line 29 · 2026-05-20T07:50:45.728Z_

Now let me register the artifact.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5b4f9b42-81d1-454c-8675-c45b81845165",
  "isSidechain": false,
  "requestId": "req_011CbDTPNK5fgMptswfquoiW",
  "type": "assistant",
  "uuid": "a7e77087-9fde-4f5a-adb3-e9f4e76e7d6f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VQ6PfTEodVP4EKdXyiqzbk",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2477,
      "cache_read_input_tokens": 40928,
      "output_tokens": 93,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2477,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 93,
          "cache_read_input_tokens": 40928,
          "cache_creation_input_tokens": 2477,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2477
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

_source line 30 · 2026-05-20T07:50:46.275Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01VyDXB5WgjtzJgtCTJBPUH9`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__register_artifact",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a7e77087-9fde-4f5a-adb3-e9f4e76e7d6f",
  "isSidechain": false,
  "requestId": "req_011CbDTPNK5fgMptswfquoiW",
  "type": "assistant",
  "uuid": "83853797-4f15-45a1-ac92-743f4b4258f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VQ6PfTEodVP4EKdXyiqzbk",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2477,
      "cache_read_input_tokens": 40928,
      "output_tokens": 93,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2477,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 93,
          "cache_read_input_tokens": 40928,
          "cache_creation_input_tokens": 2477,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2477
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

_source line 31 · 2026-05-20T07:50:46.279Z_

<details><summary>↩ Tool result · `toolu_01VyDXB5WgjtzJgtCTJBPUH9`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__register_artifact"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "83853797-4f15-45a1-ac92-743f4b4258f0",
  "isSidechain": false,
  "promptId": "76de2f70-ac1e-444d-9c77-3c394a6cfdb7",
  "type": "user",
  "uuid": "305e9739-bf4b-47a5-b1f0-125eb1f308fb",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__register_artifact"
    ],
    "query": "select:mcp__agent-ml-research__register_artifact",
    "total_deferred_tools": 51
  },
  "sourceToolAssistantUUID": "83853797-4f15-45a1-ac92-743f4b4258f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 32 · 2026-05-20T07:50:46.285Z_

```json
{
  "parentUuid": "305e9739-bf4b-47a5-b1f0-125eb1f308fb",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "2d23926d-89eb-47f3-8e0d-595ca705899a",
  "timestamp": "2026-05-20T07:50:46.285Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Tool call

_source line 33 · 2026-05-20T07:50:50.847Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact · `toolu_013EW3nXeyKNdPntNyqMy9Rg`</summary>

```json
{
  "name": "cosine_failure_section",
  "type": "paper",
  "description": "§4 Cosine R1: Structural Failure - complete LaTeX section covering 4-experiment failure chain (F1a-F1d) with diagnostic table and unified root cause analysis",
  "project": "contrastive_entrain_calib",
  "source_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/docs/paper/sections/cosine_failure.tex",
  "tags": [
    "paper",
    "section4",
    "cosine-failure",
    "latex"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2d23926d-89eb-47f3-8e0d-595ca705899a",
  "isSidechain": false,
  "requestId": "req_011CbDTPb5Y7pjSvs4Q8CA8T",
  "type": "assistant",
  "uuid": "18fea494-b27d-4d52-acc2-dcb928f9e8fd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FUcyqCcrmQwhporkMY9R3y",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 822,
      "cache_read_input_tokens": 43405,
      "output_tokens": 264,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 822,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 264,
          "cache_read_input_tokens": 43405,
          "cache_creation_input_tokens": 822,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 822
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

_source line 34 · 2026-05-20T07:50:50.923Z_

<details><summary>↩ Tool result · `toolu_013EW3nXeyKNdPntNyqMy9Rg`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260520_7e9360\", \"name\": \"cosine_failure_section\", \"type\": \"paper\", \"description\": \"§4 Cosine R1: Structural Failure - complete LaTeX section covering 4-experiment failure chain (F1a-F1d) with diagnostic table and unified root cause analysis\", \"path\": \"projects/contrastive_entrain_calib/artifacts/_project/paper/cosine_failure.tex\", \"url\": null, \"project\": \"contrastive_entrain_calib\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-20T07:50:50.856319+00:00\", \"tags\": [\"paper\", \"section4\", \"cosine-failure\", \"latex\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "18fea494-b27d-4d52-acc2-dcb928f9e8fd",
  "isSidechain": false,
  "promptId": "76de2f70-ac1e-444d-9c77-3c394a6cfdb7",
  "type": "user",
  "uuid": "255c4722-3897-4ec0-824f-8e7fad30c3d0",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"artifact\\\": {\\\"id\\\": \\\"art_20260520_7e9360\\\", \\\"name\\\": \\\"cosine_failure_section\\\", \\\"type\\\": \\\"paper\\\", \\\"description\\\": \\\"§4 Cosine R1: Structural Failure - complete LaTeX section covering 4-experiment failure chain (F1a-F1d) with diagnostic table and unified root cause analysis\\\", \\\"path\\\": \\\"projects/contrastive_entrain_calib/artifacts/_project/paper/cosine_failure.tex\\\", \\\"url\\\": null, \\\"project\\\": \\\"contrastive_entrain_calib\\\", \\\"exp_id\\\": null, \\\"skill\\\": \\\"\\\", \\\"created_at\\\": \\\"2026-05-20T07:50:50.856319+00:00\\\", \\\"tags\\\": [\\\"paper\\\", \\\"section4\\\", \\\"cosine-failure\\\", \\\"latex\\\"]}, \\\"manifest\\\": \\\"/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/artifacts/manifest.yaml\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260520_7e9360\", \"name\": \"cosine_failure_section\", \"type\": \"paper\", \"description\": \"§4 Cosine R1: Structural Failure - complete LaTeX section covering 4-experiment failure chain (F1a-F1d) with diagnostic table and unified root cause analysis\", \"path\": \"projects/contrastive_entrain_calib/artifacts/_project/paper/cosine_failure.tex\", \"url\": null, \"project\": \"contrastive_entrain_calib\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-20T07:50:50.856319+00:00\", \"tags\": [\"paper\", \"section4\", \"cosine-failure\", \"latex\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "18fea494-b27d-4d52-acc2-dcb928f9e8fd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 35 · 2026-05-20T07:51:02.421Z_

§4 已写入 `docs/paper/sections/cosine_failure.tex`，约 700 words。

结构：
- **开头**：从 §3 的 discriminability 结果过渡，预告 4-experiment diagnostic chain
- **Table 1** (`tab:cosine_chain`)：4 行总结 F1a--F1d 的配置、公式、outcome、root cause
- **F1a**：tanh gate saturation，norm mismatch 导致梯度消失
- **F1b**：raw cosine gap 仅 0.098，信号被 R3 方差淹没
- **F1c**：recalibration 把 AUROC 提到 0.91 但引入 reward discontinuity，导致 mode collapse
- **F1d**：5x scaling 放大 noise，R3 step 100 饱和后 R1 独撑但 oscillate，终端 collapse
- **Unified diagnosis**：cosine projection 把 warranted revision 和 unwarranted capitulation 混为一谈，方向编码 belief change direction 但不编码 warrant；过渡到 §5 binary probe

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "255c4722-3897-4ec0-824f-8e7fad30c3d0",
  "isSidechain": false,
  "requestId": "req_011CbDTPw26EoAiF8UorQFZX",
  "type": "assistant",
  "uuid": "727587d2-6d7b-4f81-b8c6-abe1cb25359f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-3/projects/contrastive_entrain_calib",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012MJXy7LkLFThu8wvhmbi2k",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 565,
      "cache_read_input_tokens": 44227,
      "output_tokens": 308,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 565,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 308,
          "cache_read_input_tokens": 44227,
          "cache_creation_input_tokens": 565,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 565
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

_source line 36_

```json
{
  "type": "last-prompt",
  "leafUuid": "727587d2-6d7b-4f81-b8c6-abe1cb25359f",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569"
}
```

---

### Runtime record

_source line 37_

```json
{
  "type": "ai-title",
  "aiTitle": "Write cosine R1 structural failure section",
  "sessionId": "c6535802-70d7-423e-858d-6fdcde2bf569"
}
```

---
