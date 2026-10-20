# Research conversation: <project_context> # 项目: solver-trace-ablation ## 运行环境 - 服务器名: westd-39279 - SSH 账户: root（调用 ssh_execute / submit_trainin

**Observe but Don’t Optimize: Structural Rewards Trigger Goodhart Effects in Neurosymbolic Reasoning (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 61
- **Recorded user turns:** 1
- **Tool calls:** 15
- **Original source:** `logs/chats/exported-trajectories/account-2/d09c16fe-783f-4107-8777-2fc80b263d10.jsonl`
- **Structured JSON:** [`c716ece217cbbe2f706c.json`](../../sessions/c7/c716ece217cbbe2f706c.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-15T17:37:58.556Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-15T17:37:58.556Z",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "content": "&lt;project_context>\n# 项目: solver-trace-ablation\n\n## 运行环境\n- 服务器名: westd-39279\n- SSH 账户: root（调用 ssh_execute / submit_training_job 时传入 account=\"root\"）\n- SSH 连接命令: ssh connect.westd.seetacloud.com  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP\n- 项目代码根目录: /root/solver-trace-ablation\n\n## ⚠️ 活跃约束（必须遵守）\n\n- **C001**: 所有实验统一使用 data/train_500_seed42.jsonl 作为训练数据，禁止使用 proofwriter_fol_500.jsonl 或其他数据文件（原因：Reviewer CRITICAL: plan001-s43 使用了不同数据文件导致多 seed 对比 confound。多 seed 实验必须控制数据变量，seed 仅控制模型初始化和训练随机性。）\n- **C002**: 提交训练任务前必须用 export CUDA_VISIBLE_DEVICES=N 显式设置 GPU，禁止 inline 赋值（bash -c VAR=X cmd），提交后验证 nvidia-smi 确认只占用分配的 GPU（原因：plan013 因 CUDA_VISIBLE_DEVICES inline 赋值引号问题越界占用两张 GPU，导致 plan001-s43 OOM 死亡。这是第二次 GPU 冲突事故。）\n- **C003**: 训练配置必须设置 save_total_limit=1 且禁用/限制 completions parquet 保存，防止磁盘耗尽（原因：plan013-r3 和 plan001-s43-r3 因磁盘 250G/250G 满导致 step 23/28 崩溃。根因：TRL 每实验保存 3 份模型权重（~48GB）+ completions parquet（~2.5GB）。）\n- **C004**: 跨 seed/跨 run 的 ISR 对比必须使用 eval_sta.py 统一评估，禁止引用训练日志 ISR 做跨 run 对比（不同 run 可能使用不同版本的 ISR 计算代码）（原因：Reviewer 核实发现 plan001-s42-r2 训练日志 ISR 使用 binary _fast_fn，plan001-s43-r4 使用 full STA _full_fn，同一指标名下计算方法不同导致不可比。论文中所有 ISR 数据必须来自 eval_sta.py 统一评估。）\n- **C005**: 所有 worker（含 fix/ops 类）启动任何 Python 进程前必须显式设置 CUDA_VISIBLE_DEVICES，禁止裸跑（原因：fix worker 未设 CUDA_VISIBLE_DEVICES 导致测试进程泄漏到 cuda:1（plan017 训练卡），占用 8638 MiB 显存。2026-05-14 事故。）\n- **C006**: 论文讨论 ISR 时必须区分两种语义：exec-only 的 low ISR = 冗余编码（重复 ground facts 导致 n_necessary=0），exec+STA 的 high ISR = metric gaming（Goodhart 效应）。不可将 ISR 差异直接等同于 reasoning 能力差异。（原因：Reviewer 发现 Prolog exec-only 生成大量重复 ground facts（如 penguin(fido). 出现 3 次），per-clause ablation 下删任一重复不影响结果，ISR=0。这是冗余不是无推理。如不区分，审稿人会误读 ISR 差异。）\n- **C007**: kill_job 后必须 nvidia-smi 确认 GPU 释放，submit 前必须 nvidia-smi 确认目标 GPU 无残留进程（原因：同一 session 两次出现 kill tmux → Python orphan → 新实验 OOM 的 pattern。kill_job 只杀 tmux session 不杀进程组，submit_on_allocated 只检查 registry 不检查实际 GPU 占用。）\n- **C008**: 所有 eval 命令必须显式指定 --data_path data/proofwriter_fol_100.jsonl，禁止依赖默认值或使用 test_100.jsonl（原因：D063: exp1 系列 eval 使用了 test_100.jsonl（与论文数据集零重叠），导致结果不可比。C004 约束的加固版。） [来自 D063]\n- **C009**: 所有 eval 命令必须显式指定 --data_path data/proofwriter_fol_100.jsonl，禁止使用默认值或 test_100.jsonl（原因：exp1 系列 eval 使用了错误的 test_100.jsonl（与 plan 系列的 proofwriter_fol_100.jsonl 零重叠），导致跨系列数据不可比。违反 C004。） [来自 D062]\n- **C010**: 磁盘清理禁止删除 conclusion=success 且标记 needs-re-eval 的 checkpoint，删前必须检查 registry 状态（原因：disk-cleanup-v2 误删了 exp1-isr-b03-s43 和 exp1-random-b03-s43 的 checkpoint，导致必须重训。这两个 checkpoint 因 D062/D063 需要用正确测试集 re-eval。）\n- **C011**: 磁盘清理禁止删除 conclusion=success 且标记 needs-re-eval 的 checkpoint 目录（原因：disk-cleanup-v2 Worker 误删 exp1_isr_b03_s43 和 exp1_random_b03_s43 checkpoint，导致必须重训。清理前必须交叉检查 registry 中 re-eval 标记。）\n- **C012**: Resume 训练时必须验证步数语义：--model_path 指向 checkpoint 时，确认 train_grpo.py 是从该 step 继续（resume）还是从 0 开始新训练。如不确定，从 base model 重新训练，不用 checkpoint。禁止第三次犯 resume 步数不对等错误。（原因：Agent 两次将 checkpoint-350 作为 model_path 启动 1000 步训练，实际训练了 1350 步（350+1000）而非 resume 到 1000 步，导致与 ISR 1000 步实验不可比。plan018-r2 数据作废。）\n- **C013**: Taxonomy 标准：genuine = proved − H7 − H1_exact − H8。H1-near 保留为 genuine 但单独标记。ISR 和 Random 两侧必须对称使用同一标准。（原因：D084 决策。H8 是退化证明必须扣除；H1-near 仍需推理步骤保留为 genuine；标准必须两侧对称以确保论文方法论一致性。） [来自 D084]\n\n\n## 环境搭建\n连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。\n\n## 输出风格\n回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。\n&lt;/project_context>\n你是 solver-trace-ablation 项目的 Worker。当前任务有两部分：\n\n## 任务 1: Provenance 查缺 (35/36)\n\n项目 provenance 目前 35/36，需要找到缺失的那 1 个并补全。\n\n步骤：\n1. 用 `read_project_file(project=\"solver-trace-ablation\", file=\"paper_provenance.yaml\", max_chars=0)` 读取完整 provenance 文件\n2. 检查所有 claim（Claim 1/2/3）下的 evidence 条目，找到缺失 provenance 的实验\n3. 对缺失项，查 registry 获取所需信息（checkpoint_path, log_path, command, server 等）\n4. 用 `save_project_file` 补全缺失的 provenance 条目\n\n## 任务 2: 统计量重算脚本准备\n\n当前 Random s43/s44 旧数据已 DEPRECATED。等 plan018-additive-random-b01-s43-r3 和 plan018-additive-random-b01-s44-r2 完成后，需要用新数据重算所有 Random pooled 统计量。\n\n需要准备的计算模板/checklist（写入 artifacts 目录）：\n\n需要重算的统计量清单：\n- Random 3-seed pooled genuine rate（s42 + 新s43 + 新s44）\n- Fisher exact test p-value（Random vs exec-only genuine rates）\n- Wilson CI for Random genuine rate\n- H7/H1/H8 分布（Random 3-seed 汇总）\n- Random vs ISR premise-count-matched comparison（更新 1.06x 是否变化）\n\n步骤：\n1. 读 `read_project_file(project=\"solver-trace-ablation\", file=\"paper_framing.md\", max_chars=0)` 了解当前 claims 和 PROVISIONAL/DEPRECATED 标记\n2. 读 registry 获取 s42 已完成的 Random 数据（plan018-additive-random-b01-s42 的 metrics）\n3. 列出每个统计量的计算公式 + 需要的输入数据 + 数据来源实验 ID\n4. 写一个 checklist 文件到 `/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/artifacts/stats_recalc_checklist.md`\n5. 用 `register_artifact` 注册该文件\n\n## 环境信息\n- 项目路径: `/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/`\n- artifacts 目录: `/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/artifacts/`\n- 这是 CPU-only 任务，不需要 SSH"
}
```

---

### Runtime record

_source line 2 · 2026-05-15T17:37:58.560Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-15T17:37:58.560Z",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10"
}
```

---

## Round 1

59 recorded events

### User

_source line 3 · 2026-05-15T17:37:58.598Z_

&lt;project_context>
# 项目: solver-trace-ablation

## 运行环境
- 服务器名: westd-39279
- SSH 账户: root（调用 ssh_execute / submit_training_job 时传入 account="root"）
- SSH 连接命令: ssh connect.westd.seetacloud.com  # 必须用此命令，~/.ssh/config 自动应用密钥和跳板机，禁止用裸 IP
- 项目代码根目录: /root/solver-trace-ablation

## ⚠️ 活跃约束（必须遵守）

- **C001**: 所有实验统一使用 data/train_500_seed42.jsonl 作为训练数据，禁止使用 proofwriter_fol_500.jsonl 或其他数据文件（原因：Reviewer CRITICAL: plan001-s43 使用了不同数据文件导致多 seed 对比 confound。多 seed 实验必须控制数据变量，seed 仅控制模型初始化和训练随机性。）
- **C002**: 提交训练任务前必须用 export CUDA_VISIBLE_DEVICES=N 显式设置 GPU，禁止 inline 赋值（bash -c VAR=X cmd），提交后验证 nvidia-smi 确认只占用分配的 GPU（原因：plan013 因 CUDA_VISIBLE_DEVICES inline 赋值引号问题越界占用两张 GPU，导致 plan001-s43 OOM 死亡。这是第二次 GPU 冲突事故。）
- **C003**: 训练配置必须设置 save_total_limit=1 且禁用/限制 completions parquet 保存，防止磁盘耗尽（原因：plan013-r3 和 plan001-s43-r3 因磁盘 250G/250G 满导致 step 23/28 崩溃。根因：TRL 每实验保存 3 份模型权重（~48GB）+ completions parquet（~2.5GB）。）
- **C004**: 跨 seed/跨 run 的 ISR 对比必须使用 eval_sta.py 统一评估，禁止引用训练日志 ISR 做跨 run 对比（不同 run 可能使用不同版本的 ISR 计算代码）（原因：Reviewer 核实发现 plan001-s42-r2 训练日志 ISR 使用 binary _fast_fn，plan001-s43-r4 使用 full STA _full_fn，同一指标名下计算方法不同导致不可比。论文中所有 ISR 数据必须来自 eval_sta.py 统一评估。）
- **C005**: 所有 worker（含 fix/ops 类）启动任何 Python 进程前必须显式设置 CUDA_VISIBLE_DEVICES，禁止裸跑（原因：fix worker 未设 CUDA_VISIBLE_DEVICES 导致测试进程泄漏到 cuda:1（plan017 训练卡），占用 8638 MiB 显存。2026-05-14 事故。）
- **C006**: 论文讨论 ISR 时必须区分两种语义：exec-only 的 low ISR = 冗余编码（重复 ground facts 导致 n_necessary=0），exec+STA 的 high ISR = metric gaming（Goodhart 效应）。不可将 ISR 差异直接等同于 reasoning 能力差异。（原因：Reviewer 发现 Prolog exec-only 生成大量重复 ground facts（如 penguin(fido). 出现 3 次），per-clause ablation 下删任一重复不影响结果，ISR=0。这是冗余不是无推理。如不区分，审稿人会误读 ISR 差异。）
- **C007**: kill_job 后必须 nvidia-smi 确认 GPU 释放，submit 前必须 nvidia-smi 确认目标 GPU 无残留进程（原因：同一 session 两次出现 kill tmux → Python orphan → 新实验 OOM 的 pattern。kill_job 只杀 tmux session 不杀进程组，submit_on_allocated 只检查 registry 不检查实际 GPU 占用。）
- **C008**: 所有 eval 命令必须显式指定 --data_path data/proofwriter_fol_100.jsonl，禁止依赖默认值或使用 test_100.jsonl（原因：D063: exp1 系列 eval 使用了 test_100.jsonl（与论文数据集零重叠），导致结果不可比。C004 约束的加固版。） [来自 D063]
- **C009**: 所有 eval 命令必须显式指定 --data_path data/proofwriter_fol_100.jsonl，禁止使用默认值或 test_100.jsonl（原因：exp1 系列 eval 使用了错误的 test_100.jsonl（与 plan 系列的 proofwriter_fol_100.jsonl 零重叠），导致跨系列数据不可比。违反 C004。） [来自 D062]
- **C010**: 磁盘清理禁止删除 conclusion=success 且标记 needs-re-eval 的 checkpoint，删前必须检查 registry 状态（原因：disk-cleanup-v2 误删了 exp1-isr-b03-s43 和 exp1-random-b03-s43 的 checkpoint，导致必须重训。这两个 checkpoint 因 D062/D063 需要用正确测试集 re-eval。）
- **C011**: 磁盘清理禁止删除 conclusion=success 且标记 needs-re-eval 的 checkpoint 目录（原因：disk-cleanup-v2 Worker 误删 exp1_isr_b03_s43 和 exp1_random_b03_s43 checkpoint，导致必须重训。清理前必须交叉检查 registry 中 re-eval 标记。）
- **C012**: Resume 训练时必须验证步数语义：--model_path 指向 checkpoint 时，确认 train_grpo.py 是从该 step 继续（resume）还是从 0 开始新训练。如不确定，从 base model 重新训练，不用 checkpoint。禁止第三次犯 resume 步数不对等错误。（原因：Agent 两次将 checkpoint-350 作为 model_path 启动 1000 步训练，实际训练了 1350 步（350+1000）而非 resume 到 1000 步，导致与 ISR 1000 步实验不可比。plan018-r2 数据作废。）
- **C013**: Taxonomy 标准：genuine = proved − H7 − H1_exact − H8。H1-near 保留为 genuine 但单独标记。ISR 和 Random 两侧必须对称使用同一标准。（原因：D084 决策。H8 是退化证明必须扣除；H1-near 仍需推理步骤保留为 genuine；标准必须两侧对称以确保论文方法论一致性。） [来自 D084]


## 环境搭建
连接服务器后先调 `detect_image` 检测是否为预置镜像。如果匹配，跳过基础环境搭建，只装项目特有依赖。已预装的包不要重复安装。

## 输出风格
回复简洁直接。只输出执行结果和必要信息，不要解释过程、不要客套、不要给未被要求的建议。
&lt;/project_context>
你是 solver-trace-ablation 项目的 Worker。当前任务有两部分：

## 任务 1: Provenance 查缺 (35/36)

项目 provenance 目前 35/36，需要找到缺失的那 1 个并补全。

步骤：
1. 用 `read_project_file(project="solver-trace-ablation", file="paper_provenance.yaml", max_chars=0)` 读取完整 provenance 文件
2. 检查所有 claim（Claim 1/2/3）下的 evidence 条目，找到缺失 provenance 的实验
3. 对缺失项，查 registry 获取所需信息（checkpoint_path, log_path, command, server 等）
4. 用 `save_project_file` 补全缺失的 provenance 条目

## 任务 2: 统计量重算脚本准备

当前 Random s43/s44 旧数据已 DEPRECATED。等 plan018-additive-random-b01-s43-r3 和 plan018-additive-random-b01-s44-r2 完成后，需要用新数据重算所有 Random pooled 统计量。

需要准备的计算模板/checklist（写入 artifacts 目录）：

需要重算的统计量清单：
- Random 3-seed pooled genuine rate（s42 + 新s43 + 新s44）
- Fisher exact test p-value（Random vs exec-only genuine rates）
- Wilson CI for Random genuine rate
- H7/H1/H8 分布（Random 3-seed 汇总）
- Random vs ISR premise-count-matched comparison（更新 1.06x 是否变化）

步骤：
1. 读 `read_project_file(project="solver-trace-ablation", file="paper_framing.md", max_chars=0)` 了解当前 claims 和 PROVISIONAL/DEPRECATED 标记
2. 读 registry 获取 s42 已完成的 Random 数据（plan018-additive-random-b01-s42 的 metrics）
3. 列出每个统计量的计算公式 + 需要的输入数据 + 数据来源实验 ID
4. 写一个 checklist 文件到 `/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/artifacts/stats_recalc_checklist.md`
5. 用 `register_artifact` 注册该文件

## 环境信息
- 项目路径: `/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/`
- artifacts 目录: `/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/artifacts/`
- 这是 CPU-only 任务，不需要 SSH

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "cacbb957-9499-4274-b432-f719e0836d9a",
  "permissionMode": "bypassPermissions",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-15T17:37:58.597Z_

```json
{
  "parentUuid": "cacbb957-9499-4274-b432-f719e0836d9a",
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
      "mcp__agent-ml-research__append_idea",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__update_registry"
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
      "mcp__agent-ml-research__append_idea",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__update_registry"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "400c7982-5151-4ae2-b1dc-7e12bef67133",
  "timestamp": "2026-05-15T17:37:58.597Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-15T17:37:58.597Z_

```json
{
  "parentUuid": "400c7982-5151-4ae2-b1dc-7e12bef67133",
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
  "uuid": "7bf2d941-e51b-40ef-b0ec-0f6091ea2bfd",
  "timestamp": "2026-05-15T17:37:58.597Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 6 · 2026-05-15T17:37:58.597Z_

```json
{
  "parentUuid": "7bf2d941-e51b-40ef-b0ec-0f6091ea2bfd",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo). Omit the interval to let the model self-pace. - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- schedule: Create, update, list, or run scheduled remote agents (routines) that execute on a cron schedule. - When the user wants to schedule a recurring remote agent, set up automated tasks, create a cron job for Claude Code, or manage their scheduled agents/routines. Also use when the user wants a one-time scheduled run (\"run this once at 3pm\", \"remind me to check X tomorrow\").\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 10,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "fdc86592-ac65-4e33-84a7-dfd25e3a4b0e",
  "timestamp": "2026-05-15T17:37:58.597Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
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
  "aiTitle": "Fix provenance gaps and prepare statistics recalc checklist",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10"
}
```

---

### Assistant

_source line 8 · 2026-05-15T17:38:01.812Z_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the necessary project files to understand the current state. I'll read the provenance file and paper_framing.md in parallel, and also check the registry.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fdc86592-ac65-4e33-84a7-dfd25e3a4b0e",
  "isSidechain": false,
  "requestId": "req_011Cb4m88przEBABtkzQwKPq",
  "type": "assistant",
  "uuid": "4e5f075b-db8f-47f3-b913-712370baa0bd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014wb6RGd8FfJEAxURU3BfWY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13459,
      "cache_read_input_tokens": 11841,
      "output_tokens": 201,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13459,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 201,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13459,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13459
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

_source line 9 · 2026-05-15T17:38:02.395Z_

Starting both tasks in parallel: reading provenance file, paper framing, and registry.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4e5f075b-db8f-47f3-b913-712370baa0bd",
  "isSidechain": false,
  "requestId": "req_011Cb4m88przEBABtkzQwKPq",
  "type": "assistant",
  "uuid": "56c778c1-0fda-4523-a8bb-c7d7f076cbd0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014wb6RGd8FfJEAxURU3BfWY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13459,
      "cache_read_input_tokens": 11841,
      "output_tokens": 201,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13459,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 201,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13459,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13459
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

_source line 10 · 2026-05-15T17:38:03.222Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_013g9qQkbGsrQpn2gH4LqpDq`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_registry,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__register_artifact",
  "max_results": 4
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "56c778c1-0fda-4523-a8bb-c7d7f076cbd0",
  "isSidechain": false,
  "requestId": "req_011Cb4m88przEBABtkzQwKPq",
  "type": "assistant",
  "uuid": "e3843e74-7f0d-442d-95ae-a44a9b2d8848",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014wb6RGd8FfJEAxURU3BfWY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 13459,
      "cache_read_input_tokens": 11841,
      "output_tokens": 201,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 13459,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 201,
          "cache_read_input_tokens": 11841,
          "cache_creation_input_tokens": 13459,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 13459
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

_source line 11 · 2026-05-15T17:38:03.232Z_

<details><summary>↩ Tool result · `toolu_013g9qQkbGsrQpn2gH4LqpDq`</summary>

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
  "tool_name": "mcp__agent-ml-research__read_registry"
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
  "tool_name": "mcp__agent-ml-research__register_artifact"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e3843e74-7f0d-442d-95ae-a44a9b2d8848",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "d7735b44-ec2a-492b-b06b-0e8362a31603",
  "toolUseResult": {
    "matches": [
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__register_artifact"
    ],
    "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_registry,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__register_artifact",
    "total_deferred_tools": 25
  },
  "sourceToolAssistantUUID": "e3843e74-7f0d-442d-95ae-a44a9b2d8848",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 12 · 2026-05-15T17:38:06.218Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_0166WY7PRc6AZsHcnApYrTBQ`</summary>

```json
{
  "project": "solver-trace-ablation",
  "file": "paper_provenance.yaml",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d7735b44-ec2a-492b-b06b-0e8362a31603",
  "isSidechain": false,
  "requestId": "req_011Cb4m8UmR95FrM5jLwbazq",
  "type": "assistant",
  "uuid": "e009a122-b00b-4e99-bb1a-edb4516b769f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UcQMvCzmko3cqYaJDy3N7L",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1731,
      "cache_read_input_tokens": 25300,
      "output_tokens": 290,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1731,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 290,
          "cache_read_input_tokens": 25300,
          "cache_creation_input_tokens": 1731,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1731
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

_source line 13 · 2026-05-15T17:38:06.241Z_

<details><summary>↩ Tool result · `toolu_0166WY7PRc6AZsHcnApYrTBQ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_provenance.yaml\", \"content\": \"paper:\\n  title: ''\\n  version: 12\\n  generated_at: '2026-05-15T02:40:08.884665+00:00'\\nclaims:\\n- id: C001\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'ISR collapse: 0.642 to 0.132 to 0.003'\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: proved_only_isr\\n  - exp_id: plan001-exec-only-s42-r2\\n    metric: eval_proved_only_isr\\n  - exp_id: plan016-extended-1000-s42\\n    metric: isr\\n  decisions: []\\n  deprecated: true\\n- id: C003\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'H7 ISR-specific: 64.5% vs 0% random'\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan002-additive-b01-s42\\n    metric: h7_rate\\n  - exp_id: plan018-additive-random-b01-s42\\n    metric: H7=0\\n  decisions: []\\n  deprecated: true\\n- id: C006\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: Premise-matched ISR 1.06x\\n  type: quantitative\\n  evidence:\\n  - exp_id: D051-analysis\\n    metric: premise_matched_ratio\\n  decisions: []\\n  deprecated: true\\n- id: C010\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: SFT 92.9% genuine\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan009-sft-baseline-s42-r4\\n    metric: genuine_rate\\n  decisions: []\\n  deprecated: true\\n- id: C015\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: Prolog STA 3/3 gaming 0% genuine\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan006-prolog-sta-s42\\n    metric: eval_h7_rate\\n  decisions: []\\n  deprecated: true\\n- id: C016\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: 87% of proved outputs embed the conclusion verbatim among the premises\\n  type: empirical\\n  evidence:\\n  - plan001 exec-only training results\\n  decisions: []\\n  deprecated: true\\n- id: C018\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR falls from 0.642 to 0.003 (99.5% degradation) over 100-1000 GRPO steps\\n    while prove rate rises 32% to 96%\\n  type: empirical\\n  evidence:\\n  - plan001 exec-only 3-seed eval_sta results\\n  decisions: []\\n  deprecated: true\\n- id: C021\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: SFT baseline achieves 92.9% genuine proofs with near-zero hacking\\n  type: empirical\\n  evidence:\\n  - plan008 SFT baseline eval\\n  decisions: []\\n  deprecated: true\\n- id: C025\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: 64.5% of proved samples exhibit conclusion duplication (H7) at beta=0.1, vs\\n    0% under random control\\n  type: empirical\\n  evidence:\\n  - plan013 ISR-as-reward eval\\n  - plan014 random control eval\\n  decisions: []\\n  deprecated: true\\n- id: C030\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: Sole apparent ISR improvement reduces to 1.06x after premise-count confound\\n    control\\n  type: empirical\\n  evidence:\\n  - plan013 premise-count analysis\\n  decisions: []\\n  deprecated: true\\n- id: C036\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: beta=0.3 prove rate collapses to 18% vs 48% random control\\n  type: empirical\\n  evidence:\\n  - plan013 high-dose results\\n  - plan014 random control\\n  decisions: []\\n  deprecated: true\\n- id: C043\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: 'Prolog ISR-as-reward: 3/3 seeds gaming, 0% genuine proofs'\\n  type: empirical\\n  evidence:\\n  - plan017 Prolog ISR-as-reward eval\\n  decisions: []\\n  deprecated: true\\n- id: C051\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: 7 distinct reward hacking modes across conditions and logic types\\n  type: empirical\\n  evidence:\\n  - taxonomy analysis across all experiments\\n  decisions: []\\n  deprecated: true\\n- id: C052\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR definition via LOO ablation\\n  type: definition\\n  evidence:\\n  - exp_id: sta-phase0-baseline\\n    metric: isr_computation\\n  decisions: []\\n  deprecated: true\\n- id: C054\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: Additive reward formulation\\n  type: definition\\n  evidence:\\n  - exp_id: plan002-additive-b01-s42\\n    metric: reward_formula\\n  decisions: []\\n  deprecated: true\\n- id: C055\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: 93% prove rate but 87% conclusion embedding\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan001-exec-only-s42-r2\\n    metric: eval_prove_rate=0.93, h1_rate=0.871\\n  decisions: []\\n  deprecated: false\\n- id: C057\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR collapse 0.642 to 0.132 to 0.003\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: proved_only_isr\\n  - exp_id: plan001-exec-only-s42-r2\\n    metric: eval_proved_only_isr\\n  - exp_id: plan016-extended-1000-s42\\n    metric: isr\\n  decisions: []\\n  deprecated: false\\n- id: C060\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: SFT 92.9% genuine\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan009-sft-baseline-s42-r4\\n    metric: genuine_rate\\n  decisions: []\\n  deprecated: false\\n- id: C064\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: H7=64.5% ISR vs 0% random\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan002-additive-b01-*\\n    metric: h7_rate 3-seed\\n  - exp_id: plan018-additive-random-b01-*\\n    metric: h7_rate=0\\n  decisions: []\\n  deprecated: false\\n- id: C069\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: Premise-matched 1.06x\\n  type: quantitative\\n  evidence:\\n  - exp_id: D051-analysis\\n    metric: premise_matched_ratio\\n  decisions: []\\n  deprecated: false\\n- id: C075\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: 'beta=0.3: PR 18% vs random 48%'\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan002-additive-b03-s42\\n    metric: overall_prove_rate\\n  - exp_id: plan017-additive-random-s42\\n    metric: eval_prove_rate\\n  decisions: []\\n  deprecated: false\\n- id: C082\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: Prolog STA 3/3 gaming 0% genuine\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan006-prolog-sta-*\\n    metric: 0% genuine all seeds\\n  decisions: []\\n  deprecated: false\\n- id: C083\\n  location:\\n    section: related_work\\n    paragraph: 0\\n    sentence: 0\\n  text: 87% of proved outputs under exec-only GRPO embed the conclusion among the\\n    premises\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: h1_rate_step500\\n  decisions: []\\n  deprecated: false\\n- id: C085\\n  location:\\n    section: related_work\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR reliably diagnoses structural quality yet becomes gamed when used as training\\n    reward\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: proved_only_isr\\n  - exp_id: plan003-eval-isr-beta01-r5\\n    metric: h7_rate\\n  decisions: []\\n  deprecated: false\\n- id: C086\\n  location:\\n    section: discussion\\n    paragraph: 0\\n    sentence: 0\\n  text: Downstream NLI accuracy shows no correlation with ISR (Spearman rho=-0.049,\\n    p=0.187, n.s.)\\n  type: empirical\\n  evidence:\\n  - exp_id: plan014-downstream-nli-s42\\n    metric: spearman_rho_isr_nli\\n  decisions: []\\n  deprecated: false\\n- id: C088\\n  location:\\n    section: discussion\\n    paragraph: 0\\n    sentence: 0\\n  text: Controlling for premise count eliminates apparent ISR advantage (1.06x vs\\n    raw 2.4x)\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-isr-beta01-r5\\n    metric: premise_count_matched_isr_ratio\\n  decisions: []\\n  deprecated: false\\n- id: C091\\n  location:\\n    section: discussion\\n    paragraph: 0\\n    sentence: 0\\n  text: 'Meta-level Goodhart: ISR designed to detect gaming becomes gamed when optimized'\\n  type: interpretive\\n  evidence:\\n  - exp_id: plan003-eval-isr-beta01-r5\\n    metric: h7_rate\\n  - exp_id: plan003-eval-isr-beta03-r5\\n    metric: prove_rate\\n  decisions: []\\n  deprecated: false\\n- id: C092\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: 93% prove rate on FOLIO with 87% conclusion embedding\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: prove_rate_step500\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: h1_rate_step500\\n  decisions: []\\n  deprecated: false\\n- id: C094\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR falls from 0.642 to 0.003 over 1000 steps while PR rises 32% to 96%\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: proved_only_isr_trajectory\\n  decisions: []\\n  deprecated: false\\n- id: C097\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: SFT baseline 92.9% genuine proofs\\n  type: empirical\\n  evidence:\\n  - exp_id: sft-baseline\\n    metric: genuine_rate\\n  decisions: []\\n  deprecated: false\\n- id: C101\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: 64.5% H7 under ISR beta=0.1 vs 0% random\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-isr-beta01-r5\\n    metric: h7_rate_3seed\\n  decisions: []\\n  deprecated: false\\n- id: C106\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: Premise-count-matched 1.06x\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-isr-beta01-r5\\n    metric: premise_count_matched_ratio\\n  decisions: []\\n  deprecated: false\\n- id: C112\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: beta=0.3 PR 18% vs random 48%\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-isr-beta03-r5\\n    metric: prove_rate\\n  decisions: []\\n  deprecated: false\\n- id: C119\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: Prolog 3/3 seeds gaming, 0% genuine\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-prolog-isr-r5\\n    metric: genuine_rate_3seed\\n  decisions: []\\n  deprecated: false\\n- id: C120\\n  location:\\n    section: conclusion\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR and NLI accuracy are uncorrelated (rho=-0.049, n.s.)\\n  type: empirical\\n  evidence:\\n  - exp_id: plan014-downstream-nli-s42\\n    metric: spearman_rho\\n  decisions: []\\n  deprecated: false\\n- id: C121\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR measures the fraction of necessary components via LOO ablation on solver\\n    inputs\\n  type: methodological\\n  evidence:\\n  - eq:isr\\n  decisions:\\n  - D010\\n  deprecated: true\\n- id: C123\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: 'ISR is subject to component-count confound: fewer components yield mechanically\\n    higher ISR'\\n  type: methodological\\n  evidence:\\n  - D051\\n  decisions:\\n  - D051\\n  deprecated: true\\n- id: C126\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: Seven hacking modes identified across conditions, seeds, and logic types\\n  type: methodological\\n  evidence:\\n  - plan001-exec-only-s42-r2\\n  - plan002-additive-b01-s42\\n  - plan006-prolog-sta-s44\\n  decisions:\\n  - D027\\n  deprecated: true\\n- id: C127\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR collapse trajectory 0.642 to 0.132 to 0.003 over 100 to 500 to 1000 steps\\n    under exec-only GRPO\\n  type: empirical\\n  evidence:\\n  - plan003-eval-exec-only-r5\\n  - plan001-exec-only-s42-r2\\n  - plan016-extended-1000-s42\\n  decisions: []\\n  deprecated: false\\n- id: C129\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: '3-seed exec-only divergence: s42 H1=87.1%, s43 repetition collapse PR=13%,\\n    s44 tautological H7=100% PR=98%'\\n  type: empirical\\n  evidence:\\n  - plan001-exec-only-s42-r2\\n  - plan001-exec-only-s43-r4\\n  - plan001-exec-only-s44\\n  decisions: []\\n  deprecated: false\\n- id: C132\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'SFT baseline: PR=14%, 92.9% non-hacking, near-zero H7/H1, confirming hacking\\n    is RL-reward-specific'\\n  type: empirical\\n  evidence:\\n  - plan009-sft-baseline-s42-r4\\n  decisions: []\\n  deprecated: false\\n- id: C136\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'H7 is ISR-specific: 64.5% (149/231) under ISR beta=0.1 vs 0% (0/256) under\\n    random beta=0.1'\\n  type: empirical\\n  evidence:\\n  - plan002-additive-b01-s42\\n  - plan002-additive-b01-s43\\n  - plan002-additive-b01-s44\\n  - plan018-additive-random-b01-s42\\n  - plan018-additive-random-b01-s43-r2\\n  - plan018-additive-random-b01-s44\\n  decisions:\\n  - D057\\n  deprecated: false\\n- id: C141\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: Premise-count-matched ISR 1.06x (0.258 vs 0.243, n>=3 premises), no meaningful\\n    structural advantage\\n  type: empirical\\n  evidence:\\n  - plan002-additive-b01-s42\\n  - plan018-additive-random-b01-s42\\n  decisions:\\n  - D051\\n  deprecated: false\\n- id: C147\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'beta=0.3 classic Goodhart: ISR PR=18% vs random PR=48%'\\n  type: empirical\\n  evidence:\\n  - plan002-additive-b03-s42\\n  - plan017-additive-random-s42\\n  decisions: []\\n  deprecated: false\\n- id: C154\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'Prolog exec-only: 2/3 seeds ISR* near 0 (s42=0.037, s43=0.015), diagnostic\\n    transfer confirmed'\\n  type: empirical\\n  evidence:\\n  - plan006-prolog-exec-s42\\n  - plan006-prolog-exec-s43-r3\\n  - plan006-prolog-exec-s44\\n  decisions:\\n  - D056\\n  deprecated: false\\n- id: C162\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'Prolog ISR-reward: universal Goodhart 0% non-hacking across 185 proved, 3\\n    distinct gaming mechanisms'\\n  type: empirical\\n  evidence:\\n  - plan006-prolog-sta-s42\\n  - plan006-prolog-sta-s43\\n  - plan006-prolog-sta-s44\\n  decisions: []\\n  deprecated: false\\n- id: C171\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: Conclusion embedding is GRPO-universal (68-97%); ISR restructures hacking\\n    composition not prevalence\\n  type: empirical\\n  evidence:\\n  - plan002-additive-b01-s42\\n  - plan018-additive-random-b01-s42\\n  - plan018-additive-random-b01-s43-r2\\n  decisions:\\n  - D057\\n  deprecated: false\\n- id: C172\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: STA applies LOO ablation to solver inputs to compute ISR as a diagnostic for\\n    reward hacking\\n  type: methodological\\n  evidence:\\n  - sta-phase0-baseline\\n  - plan003-eval-exec-only-r5\\n  decisions:\\n  - D003\\n  - D007\\n  deprecated: false\\n- id: C174\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR measures syntactic component necessity, not semantic faithfulness\\n  type: scope_limitation\\n  evidence:\\n  - plan014-downstream-nli-s42\\n  decisions:\\n  - D021\\n  deprecated: false\\n- id: C177\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR is mathematically sensitive to component count (premise count bias)\\n  type: scope_limitation\\n  evidence: []\\n  decisions:\\n  - D051\\n  deprecated: false\\n- id: C181\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: 'Additive ISR bonus formulation: r = r_exec * (1 + beta * ISR)'\\n  type: methodological\\n  evidence:\\n  - plan002-additive-b01-s42\\n  decisions:\\n  - D010\\n  deprecated: false\\n- id: C186\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: Convex formulation discarded due to inherent penalty effect\\n  type: negative_result\\n  evidence:\\n  - plan005-sta-low-s42\\n  decisions:\\n  - D010\\n  - D011\\n  deprecated: false\\n- id: C192\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: 'H7 (conclusion duplication with ISR inflation) is exclusive to ISR-reward\\n    conditions: 64.5% vs 0% under random control'\\n  type: empirical\\n  evidence:\\n  - plan002-additive-b01-s42\\n  - plan002-additive-b01-s43\\n  - plan002-additive-b01-s44\\n  - plan018-additive-random-b01-s42\\n  - plan018-additive-random-b01-s43-r2\\n  - plan018-additive-random-b01-s44\\n  decisions:\\n  - D043\\n  - D057\\n  deprecated: false\\n- id: C199\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: Seven distinct hacking modes identified across reward conditions and logic\\n    types\\n  type: empirical\\n  evidence:\\n  - plan012-hacking-taxonomy\\n  decisions: []\\n  deprecated: false\\ntables: []\\nfigures: []\\n_completeness:\\n  coverage: 35/36\\n  claims: 36\\n  tables: 0\\n  figures: 0\\n  tier_counts:\\n    tier1: 0\\n    tier2: 35\\n    tier3: 1\\n    tierX: 0\\n  last_checked: '2026-05-15T02:40:08.884772+00:00'\\n\", \"total_chars\": 16362, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e009a122-b00b-4e99-bb1a-edb4516b769f",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "af26dfce-2a99-496d-8201-95dcf78a4759",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_provenance.yaml\\\", \\\"content\\\": \\\"paper:\\\\n  title: ''\\\\n  version: 12\\\\n  generated_at: '2026-05-15T02:40:08.884665+00:00'\\\\nclaims:\\\\n- id: C001\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'ISR collapse: 0.642 to 0.132 to 0.003'\\\\n  type: quantitative\\\\n  evidence:\\\\n  - exp_id: plan003-eval-exec-only-r5\\\\n    metric: proved_only_isr\\\\n  - exp_id: plan001-exec-only-s42-r2\\\\n    metric: eval_proved_only_isr\\\\n  - exp_id: plan016-extended-1000-s42\\\\n    metric: isr\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C003\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'H7 ISR-specific: 64.5% vs 0% random'\\\\n  type: quantitative\\\\n  evidence:\\\\n  - exp_id: plan002-additive-b01-s42\\\\n    metric: h7_rate\\\\n  - exp_id: plan018-additive-random-b01-s42\\\\n    metric: H7=0\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C006\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Premise-matched ISR 1.06x\\\\n  type: quantitative\\\\n  evidence:\\\\n  - exp_id: D051-analysis\\\\n    metric: premise_matched_ratio\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C010\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: SFT 92.9% genuine\\\\n  type: quantitative\\\\n  evidence:\\\\n  - exp_id: plan009-sft-baseline-s42-r4\\\\n    metric: genuine_rate\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C015\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Prolog STA 3/3 gaming 0% genuine\\\\n  type: quantitative\\\\n  evidence:\\\\n  - exp_id: plan006-prolog-sta-s42\\\\n    metric: eval_h7_rate\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C016\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 87% of proved outputs embed the conclusion verbatim among the premises\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan001 exec-only training results\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C018\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: ISR falls from 0.642 to 0.003 (99.5% degradation) over 100-1000 GRPO steps\\\\n    while prove rate rises 32% to 96%\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan001 exec-only 3-seed eval_sta results\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C021\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: SFT baseline achieves 92.9% genuine proofs with near-zero hacking\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan008 SFT baseline eval\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C025\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 64.5% of proved samples exhibit conclusion duplication (H7) at beta=0.1, vs\\\\n    0% under random control\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan013 ISR-as-reward eval\\\\n  - plan014 random control eval\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C030\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Sole apparent ISR improvement reduces to 1.06x after premise-count confound\\\\n    control\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan013 premise-count analysis\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C036\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: beta=0.3 prove rate collapses to 18% vs 48% random control\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan013 high-dose results\\\\n  - plan014 random control\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C043\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'Prolog ISR-as-reward: 3/3 seeds gaming, 0% genuine proofs'\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan017 Prolog ISR-as-reward eval\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C051\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 7 distinct reward hacking modes across conditions and logic types\\\\n  type: empirical\\\\n  evidence:\\\\n  - taxonomy analysis across all experiments\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C052\\\\n  location:\\\\n    section: method\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: ISR definition via LOO ablation\\\\n  type: definition\\\\n  evidence:\\\\n  - exp_id: sta-phase0-baseline\\\\n    metric: isr_computation\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C054\\\\n  location:\\\\n    section: method\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Additive reward formulation\\\\n  type: definition\\\\n  evidence:\\\\n  - exp_id: plan002-additive-b01-s42\\\\n    metric: reward_formula\\\\n  decisions: []\\\\n  deprecated: true\\\\n- id: C055\\\\n  location:\\\\n    section: introduction\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 93% prove rate but 87% conclusion embedding\\\\n  type: quantitative\\\\n  evidence:\\\\n  - exp_id: plan001-exec-only-s42-r2\\\\n    metric: eval_prove_rate=0.93, h1_rate=0.871\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C057\\\\n  location:\\\\n    section: introduction\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: ISR collapse 0.642 to 0.132 to 0.003\\\\n  type: quantitative\\\\n  evidence:\\\\n  - exp_id: plan003-eval-exec-only-r5\\\\n    metric: proved_only_isr\\\\n  - exp_id: plan001-exec-only-s42-r2\\\\n    metric: eval_proved_only_isr\\\\n  - exp_id: plan016-extended-1000-s42\\\\n    metric: isr\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C060\\\\n  location:\\\\n    section: introduction\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: SFT 92.9% genuine\\\\n  type: quantitative\\\\n  evidence:\\\\n  - exp_id: plan009-sft-baseline-s42-r4\\\\n    metric: genuine_rate\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C064\\\\n  location:\\\\n    section: introduction\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: H7=64.5% ISR vs 0% random\\\\n  type: quantitative\\\\n  evidence:\\\\n  - exp_id: plan002-additive-b01-*\\\\n    metric: h7_rate 3-seed\\\\n  - exp_id: plan018-additive-random-b01-*\\\\n    metric: h7_rate=0\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C069\\\\n  location:\\\\n    section: introduction\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Premise-matched 1.06x\\\\n  type: quantitative\\\\n  evidence:\\\\n  - exp_id: D051-analysis\\\\n    metric: premise_matched_ratio\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C075\\\\n  location:\\\\n    section: introduction\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'beta=0.3: PR 18% vs random 48%'\\\\n  type: quantitative\\\\n  evidence:\\\\n  - exp_id: plan002-additive-b03-s42\\\\n    metric: overall_prove_rate\\\\n  - exp_id: plan017-additive-random-s42\\\\n    metric: eval_prove_rate\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C082\\\\n  location:\\\\n    section: introduction\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Prolog STA 3/3 gaming 0% genuine\\\\n  type: quantitative\\\\n  evidence:\\\\n  - exp_id: plan006-prolog-sta-*\\\\n    metric: 0% genuine all seeds\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C083\\\\n  location:\\\\n    section: related_work\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 87% of proved outputs under exec-only GRPO embed the conclusion among the\\\\n    premises\\\\n  type: empirical\\\\n  evidence:\\\\n  - exp_id: plan003-eval-exec-only-r5\\\\n    metric: h1_rate_step500\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C085\\\\n  location:\\\\n    section: related_work\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: ISR reliably diagnoses structural quality yet becomes gamed when used as training\\\\n    reward\\\\n  type: empirical\\\\n  evidence:\\\\n  - exp_id: plan003-eval-exec-only-r5\\\\n    metric: proved_only_isr\\\\n  - exp_id: plan003-eval-isr-beta01-r5\\\\n    metric: h7_rate\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C086\\\\n  location:\\\\n    section: discussion\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Downstream NLI accuracy shows no correlation with ISR (Spearman rho=-0.049,\\\\n    p=0.187, n.s.)\\\\n  type: empirical\\\\n  evidence:\\\\n  - exp_id: plan014-downstream-nli-s42\\\\n    metric: spearman_rho_isr_nli\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C088\\\\n  location:\\\\n    section: discussion\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Controlling for premise count eliminates apparent ISR advantage (1.06x vs\\\\n    raw 2.4x)\\\\n  type: empirical\\\\n  evidence:\\\\n  - exp_id: plan003-eval-isr-beta01-r5\\\\n    metric: premise_count_matched_isr_ratio\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C091\\\\n  location:\\\\n    section: discussion\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'Meta-level Goodhart: ISR designed to detect gaming becomes gamed when optimized'\\\\n  type: interpretive\\\\n  evidence:\\\\n  - exp_id: plan003-eval-isr-beta01-r5\\\\n    metric: h7_rate\\\\n  - exp_id: plan003-eval-isr-beta03-r5\\\\n    metric: prove_rate\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C092\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 93% prove rate on FOLIO with 87% conclusion embedding\\\\n  type: empirical\\\\n  evidence:\\\\n  - exp_id: plan003-eval-exec-only-r5\\\\n    metric: prove_rate_step500\\\\n  - exp_id: plan003-eval-exec-only-r5\\\\n    metric: h1_rate_step500\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C094\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: ISR falls from 0.642 to 0.003 over 1000 steps while PR rises 32% to 96%\\\\n  type: empirical\\\\n  evidence:\\\\n  - exp_id: plan003-eval-exec-only-r5\\\\n    metric: proved_only_isr_trajectory\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C097\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: SFT baseline 92.9% genuine proofs\\\\n  type: empirical\\\\n  evidence:\\\\n  - exp_id: sft-baseline\\\\n    metric: genuine_rate\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C101\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 64.5% H7 under ISR beta=0.1 vs 0% random\\\\n  type: empirical\\\\n  evidence:\\\\n  - exp_id: plan003-eval-isr-beta01-r5\\\\n    metric: h7_rate_3seed\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C106\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Premise-count-matched 1.06x\\\\n  type: empirical\\\\n  evidence:\\\\n  - exp_id: plan003-eval-isr-beta01-r5\\\\n    metric: premise_count_matched_ratio\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C112\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: beta=0.3 PR 18% vs random 48%\\\\n  type: empirical\\\\n  evidence:\\\\n  - exp_id: plan003-eval-isr-beta03-r5\\\\n    metric: prove_rate\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C119\\\\n  location:\\\\n    section: abstract\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Prolog 3/3 seeds gaming, 0% genuine\\\\n  type: empirical\\\\n  evidence:\\\\n  - exp_id: plan003-eval-prolog-isr-r5\\\\n    metric: genuine_rate_3seed\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C120\\\\n  location:\\\\n    section: conclusion\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: ISR and NLI accuracy are uncorrelated (rho=-0.049, n.s.)\\\\n  type: empirical\\\\n  evidence:\\\\n  - exp_id: plan014-downstream-nli-s42\\\\n    metric: spearman_rho\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C121\\\\n  location:\\\\n    section: method\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: ISR measures the fraction of necessary components via LOO ablation on solver\\\\n    inputs\\\\n  type: methodological\\\\n  evidence:\\\\n  - eq:isr\\\\n  decisions:\\\\n  - D010\\\\n  deprecated: true\\\\n- id: C123\\\\n  location:\\\\n    section: method\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'ISR is subject to component-count confound: fewer components yield mechanically\\\\n    higher ISR'\\\\n  type: methodological\\\\n  evidence:\\\\n  - D051\\\\n  decisions:\\\\n  - D051\\\\n  deprecated: true\\\\n- id: C126\\\\n  location:\\\\n    section: method\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Seven hacking modes identified across conditions, seeds, and logic types\\\\n  type: methodological\\\\n  evidence:\\\\n  - plan001-exec-only-s42-r2\\\\n  - plan002-additive-b01-s42\\\\n  - plan006-prolog-sta-s44\\\\n  decisions:\\\\n  - D027\\\\n  deprecated: true\\\\n- id: C127\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: ISR collapse trajectory 0.642 to 0.132 to 0.003 over 100 to 500 to 1000 steps\\\\n    under exec-only GRPO\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan003-eval-exec-only-r5\\\\n  - plan001-exec-only-s42-r2\\\\n  - plan016-extended-1000-s42\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C129\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: '3-seed exec-only divergence: s42 H1=87.1%, s43 repetition collapse PR=13%,\\\\n    s44 tautological H7=100% PR=98%'\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan001-exec-only-s42-r2\\\\n  - plan001-exec-only-s43-r4\\\\n  - plan001-exec-only-s44\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C132\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'SFT baseline: PR=14%, 92.9% non-hacking, near-zero H7/H1, confirming hacking\\\\n    is RL-reward-specific'\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan009-sft-baseline-s42-r4\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C136\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'H7 is ISR-specific: 64.5% (149/231) under ISR beta=0.1 vs 0% (0/256) under\\\\n    random beta=0.1'\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan002-additive-b01-s42\\\\n  - plan002-additive-b01-s43\\\\n  - plan002-additive-b01-s44\\\\n  - plan018-additive-random-b01-s42\\\\n  - plan018-additive-random-b01-s43-r2\\\\n  - plan018-additive-random-b01-s44\\\\n  decisions:\\\\n  - D057\\\\n  deprecated: false\\\\n- id: C141\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Premise-count-matched ISR 1.06x (0.258 vs 0.243, n>=3 premises), no meaningful\\\\n    structural advantage\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan002-additive-b01-s42\\\\n  - plan018-additive-random-b01-s42\\\\n  decisions:\\\\n  - D051\\\\n  deprecated: false\\\\n- id: C147\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'beta=0.3 classic Goodhart: ISR PR=18% vs random PR=48%'\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan002-additive-b03-s42\\\\n  - plan017-additive-random-s42\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C154\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'Prolog exec-only: 2/3 seeds ISR* near 0 (s42=0.037, s43=0.015), diagnostic\\\\n    transfer confirmed'\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan006-prolog-exec-s42\\\\n  - plan006-prolog-exec-s43-r3\\\\n  - plan006-prolog-exec-s44\\\\n  decisions:\\\\n  - D056\\\\n  deprecated: false\\\\n- id: C162\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'Prolog ISR-reward: universal Goodhart 0% non-hacking across 185 proved, 3\\\\n    distinct gaming mechanisms'\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan006-prolog-sta-s42\\\\n  - plan006-prolog-sta-s43\\\\n  - plan006-prolog-sta-s44\\\\n  decisions: []\\\\n  deprecated: false\\\\n- id: C171\\\\n  location:\\\\n    section: experiments\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Conclusion embedding is GRPO-universal (68-97%); ISR restructures hacking\\\\n    composition not prevalence\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan002-additive-b01-s42\\\\n  - plan018-additive-random-b01-s42\\\\n  - plan018-additive-random-b01-s43-r2\\\\n  decisions:\\\\n  - D057\\\\n  deprecated: false\\\\n- id: C172\\\\n  location:\\\\n    section: method\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: STA applies LOO ablation to solver inputs to compute ISR as a diagnostic for\\\\n    reward hacking\\\\n  type: methodological\\\\n  evidence:\\\\n  - sta-phase0-baseline\\\\n  - plan003-eval-exec-only-r5\\\\n  decisions:\\\\n  - D003\\\\n  - D007\\\\n  deprecated: false\\\\n- id: C174\\\\n  location:\\\\n    section: method\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: ISR measures syntactic component necessity, not semantic faithfulness\\\\n  type: scope_limitation\\\\n  evidence:\\\\n  - plan014-downstream-nli-s42\\\\n  decisions:\\\\n  - D021\\\\n  deprecated: false\\\\n- id: C177\\\\n  location:\\\\n    section: method\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: ISR is mathematically sensitive to component count (premise count bias)\\\\n  type: scope_limitation\\\\n  evidence: []\\\\n  decisions:\\\\n  - D051\\\\n  deprecated: false\\\\n- id: C181\\\\n  location:\\\\n    section: method\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'Additive ISR bonus formulation: r = r_exec * (1 + beta * ISR)'\\\\n  type: methodological\\\\n  evidence:\\\\n  - plan002-additive-b01-s42\\\\n  decisions:\\\\n  - D010\\\\n  deprecated: false\\\\n- id: C186\\\\n  location:\\\\n    section: method\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Convex formulation discarded due to inherent penalty effect\\\\n  type: negative_result\\\\n  evidence:\\\\n  - plan005-sta-low-s42\\\\n  decisions:\\\\n  - D010\\\\n  - D011\\\\n  deprecated: false\\\\n- id: C192\\\\n  location:\\\\n    section: method\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: 'H7 (conclusion duplication with ISR inflation) is exclusive to ISR-reward\\\\n    conditions: 64.5% vs 0% under random control'\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan002-additive-b01-s42\\\\n  - plan002-additive-b01-s43\\\\n  - plan002-additive-b01-s44\\\\n  - plan018-additive-random-b01-s42\\\\n  - plan018-additive-random-b01-s43-r2\\\\n  - plan018-additive-random-b01-s44\\\\n  decisions:\\\\n  - D043\\\\n  - D057\\\\n  deprecated: false\\\\n- id: C199\\\\n  location:\\\\n    section: method\\\\n    paragraph: 0\\\\n    sentence: 0\\\\n  text: Seven distinct hacking modes identified across reward conditions and logic\\\\n    types\\\\n  type: empirical\\\\n  evidence:\\\\n  - plan012-hacking-taxonomy\\\\n  decisions: []\\\\n  deprecated: false\\\\ntables: []\\\\nfigures: []\\\\n_completeness:\\\\n  coverage: 35/36\\\\n  claims: 36\\\\n  tables: 0\\\\n  figures: 0\\\\n  tier_counts:\\\\n    tier1: 0\\\\n    tier2: 35\\\\n    tier3: 1\\\\n    tierX: 0\\\\n  last_checked: '2026-05-15T02:40:08.884772+00:00'\\\\n\\\", \\\"total_chars\\\": 16362, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_provenance.yaml\", \"content\": \"paper:\\n  title: ''\\n  version: 12\\n  generated_at: '2026-05-15T02:40:08.884665+00:00'\\nclaims:\\n- id: C001\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'ISR collapse: 0.642 to 0.132 to 0.003'\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: proved_only_isr\\n  - exp_id: plan001-exec-only-s42-r2\\n    metric: eval_proved_only_isr\\n  - exp_id: plan016-extended-1000-s42\\n    metric: isr\\n  decisions: []\\n  deprecated: true\\n- id: C003\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'H7 ISR-specific: 64.5% vs 0% random'\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan002-additive-b01-s42\\n    metric: h7_rate\\n  - exp_id: plan018-additive-random-b01-s42\\n    metric: H7=0\\n  decisions: []\\n  deprecated: true\\n- id: C006\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: Premise-matched ISR 1.06x\\n  type: quantitative\\n  evidence:\\n  - exp_id: D051-analysis\\n    metric: premise_matched_ratio\\n  decisions: []\\n  deprecated: true\\n- id: C010\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: SFT 92.9% genuine\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan009-sft-baseline-s42-r4\\n    metric: genuine_rate\\n  decisions: []\\n  deprecated: true\\n- id: C015\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: Prolog STA 3/3 gaming 0% genuine\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan006-prolog-sta-s42\\n    metric: eval_h7_rate\\n  decisions: []\\n  deprecated: true\\n- id: C016\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: 87% of proved outputs embed the conclusion verbatim among the premises\\n  type: empirical\\n  evidence:\\n  - plan001 exec-only training results\\n  decisions: []\\n  deprecated: true\\n- id: C018\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR falls from 0.642 to 0.003 (99.5% degradation) over 100-1000 GRPO steps\\n    while prove rate rises 32% to 96%\\n  type: empirical\\n  evidence:\\n  - plan001 exec-only 3-seed eval_sta results\\n  decisions: []\\n  deprecated: true\\n- id: C021\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: SFT baseline achieves 92.9% genuine proofs with near-zero hacking\\n  type: empirical\\n  evidence:\\n  - plan008 SFT baseline eval\\n  decisions: []\\n  deprecated: true\\n- id: C025\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: 64.5% of proved samples exhibit conclusion duplication (H7) at beta=0.1, vs\\n    0% under random control\\n  type: empirical\\n  evidence:\\n  - plan013 ISR-as-reward eval\\n  - plan014 random control eval\\n  decisions: []\\n  deprecated: true\\n- id: C030\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: Sole apparent ISR improvement reduces to 1.06x after premise-count confound\\n    control\\n  type: empirical\\n  evidence:\\n  - plan013 premise-count analysis\\n  decisions: []\\n  deprecated: true\\n- id: C036\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: beta=0.3 prove rate collapses to 18% vs 48% random control\\n  type: empirical\\n  evidence:\\n  - plan013 high-dose results\\n  - plan014 random control\\n  decisions: []\\n  deprecated: true\\n- id: C043\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: 'Prolog ISR-as-reward: 3/3 seeds gaming, 0% genuine proofs'\\n  type: empirical\\n  evidence:\\n  - plan017 Prolog ISR-as-reward eval\\n  decisions: []\\n  deprecated: true\\n- id: C051\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: 7 distinct reward hacking modes across conditions and logic types\\n  type: empirical\\n  evidence:\\n  - taxonomy analysis across all experiments\\n  decisions: []\\n  deprecated: true\\n- id: C052\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR definition via LOO ablation\\n  type: definition\\n  evidence:\\n  - exp_id: sta-phase0-baseline\\n    metric: isr_computation\\n  decisions: []\\n  deprecated: true\\n- id: C054\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: Additive reward formulation\\n  type: definition\\n  evidence:\\n  - exp_id: plan002-additive-b01-s42\\n    metric: reward_formula\\n  decisions: []\\n  deprecated: true\\n- id: C055\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: 93% prove rate but 87% conclusion embedding\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan001-exec-only-s42-r2\\n    metric: eval_prove_rate=0.93, h1_rate=0.871\\n  decisions: []\\n  deprecated: false\\n- id: C057\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR collapse 0.642 to 0.132 to 0.003\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: proved_only_isr\\n  - exp_id: plan001-exec-only-s42-r2\\n    metric: eval_proved_only_isr\\n  - exp_id: plan016-extended-1000-s42\\n    metric: isr\\n  decisions: []\\n  deprecated: false\\n- id: C060\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: SFT 92.9% genuine\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan009-sft-baseline-s42-r4\\n    metric: genuine_rate\\n  decisions: []\\n  deprecated: false\\n- id: C064\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: H7=64.5% ISR vs 0% random\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan002-additive-b01-*\\n    metric: h7_rate 3-seed\\n  - exp_id: plan018-additive-random-b01-*\\n    metric: h7_rate=0\\n  decisions: []\\n  deprecated: false\\n- id: C069\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: Premise-matched 1.06x\\n  type: quantitative\\n  evidence:\\n  - exp_id: D051-analysis\\n    metric: premise_matched_ratio\\n  decisions: []\\n  deprecated: false\\n- id: C075\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: 'beta=0.3: PR 18% vs random 48%'\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan002-additive-b03-s42\\n    metric: overall_prove_rate\\n  - exp_id: plan017-additive-random-s42\\n    metric: eval_prove_rate\\n  decisions: []\\n  deprecated: false\\n- id: C082\\n  location:\\n    section: introduction\\n    paragraph: 0\\n    sentence: 0\\n  text: Prolog STA 3/3 gaming 0% genuine\\n  type: quantitative\\n  evidence:\\n  - exp_id: plan006-prolog-sta-*\\n    metric: 0% genuine all seeds\\n  decisions: []\\n  deprecated: false\\n- id: C083\\n  location:\\n    section: related_work\\n    paragraph: 0\\n    sentence: 0\\n  text: 87% of proved outputs under exec-only GRPO embed the conclusion among the\\n    premises\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: h1_rate_step500\\n  decisions: []\\n  deprecated: false\\n- id: C085\\n  location:\\n    section: related_work\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR reliably diagnoses structural quality yet becomes gamed when used as training\\n    reward\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: proved_only_isr\\n  - exp_id: plan003-eval-isr-beta01-r5\\n    metric: h7_rate\\n  decisions: []\\n  deprecated: false\\n- id: C086\\n  location:\\n    section: discussion\\n    paragraph: 0\\n    sentence: 0\\n  text: Downstream NLI accuracy shows no correlation with ISR (Spearman rho=-0.049,\\n    p=0.187, n.s.)\\n  type: empirical\\n  evidence:\\n  - exp_id: plan014-downstream-nli-s42\\n    metric: spearman_rho_isr_nli\\n  decisions: []\\n  deprecated: false\\n- id: C088\\n  location:\\n    section: discussion\\n    paragraph: 0\\n    sentence: 0\\n  text: Controlling for premise count eliminates apparent ISR advantage (1.06x vs\\n    raw 2.4x)\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-isr-beta01-r5\\n    metric: premise_count_matched_isr_ratio\\n  decisions: []\\n  deprecated: false\\n- id: C091\\n  location:\\n    section: discussion\\n    paragraph: 0\\n    sentence: 0\\n  text: 'Meta-level Goodhart: ISR designed to detect gaming becomes gamed when optimized'\\n  type: interpretive\\n  evidence:\\n  - exp_id: plan003-eval-isr-beta01-r5\\n    metric: h7_rate\\n  - exp_id: plan003-eval-isr-beta03-r5\\n    metric: prove_rate\\n  decisions: []\\n  deprecated: false\\n- id: C092\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: 93% prove rate on FOLIO with 87% conclusion embedding\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: prove_rate_step500\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: h1_rate_step500\\n  decisions: []\\n  deprecated: false\\n- id: C094\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR falls from 0.642 to 0.003 over 1000 steps while PR rises 32% to 96%\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-exec-only-r5\\n    metric: proved_only_isr_trajectory\\n  decisions: []\\n  deprecated: false\\n- id: C097\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: SFT baseline 92.9% genuine proofs\\n  type: empirical\\n  evidence:\\n  - exp_id: sft-baseline\\n    metric: genuine_rate\\n  decisions: []\\n  deprecated: false\\n- id: C101\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: 64.5% H7 under ISR beta=0.1 vs 0% random\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-isr-beta01-r5\\n    metric: h7_rate_3seed\\n  decisions: []\\n  deprecated: false\\n- id: C106\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: Premise-count-matched 1.06x\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-isr-beta01-r5\\n    metric: premise_count_matched_ratio\\n  decisions: []\\n  deprecated: false\\n- id: C112\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: beta=0.3 PR 18% vs random 48%\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-isr-beta03-r5\\n    metric: prove_rate\\n  decisions: []\\n  deprecated: false\\n- id: C119\\n  location:\\n    section: abstract\\n    paragraph: 0\\n    sentence: 0\\n  text: Prolog 3/3 seeds gaming, 0% genuine\\n  type: empirical\\n  evidence:\\n  - exp_id: plan003-eval-prolog-isr-r5\\n    metric: genuine_rate_3seed\\n  decisions: []\\n  deprecated: false\\n- id: C120\\n  location:\\n    section: conclusion\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR and NLI accuracy are uncorrelated (rho=-0.049, n.s.)\\n  type: empirical\\n  evidence:\\n  - exp_id: plan014-downstream-nli-s42\\n    metric: spearman_rho\\n  decisions: []\\n  deprecated: false\\n- id: C121\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR measures the fraction of necessary components via LOO ablation on solver\\n    inputs\\n  type: methodological\\n  evidence:\\n  - eq:isr\\n  decisions:\\n  - D010\\n  deprecated: true\\n- id: C123\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: 'ISR is subject to component-count confound: fewer components yield mechanically\\n    higher ISR'\\n  type: methodological\\n  evidence:\\n  - D051\\n  decisions:\\n  - D051\\n  deprecated: true\\n- id: C126\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: Seven hacking modes identified across conditions, seeds, and logic types\\n  type: methodological\\n  evidence:\\n  - plan001-exec-only-s42-r2\\n  - plan002-additive-b01-s42\\n  - plan006-prolog-sta-s44\\n  decisions:\\n  - D027\\n  deprecated: true\\n- id: C127\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR collapse trajectory 0.642 to 0.132 to 0.003 over 100 to 500 to 1000 steps\\n    under exec-only GRPO\\n  type: empirical\\n  evidence:\\n  - plan003-eval-exec-only-r5\\n  - plan001-exec-only-s42-r2\\n  - plan016-extended-1000-s42\\n  decisions: []\\n  deprecated: false\\n- id: C129\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: '3-seed exec-only divergence: s42 H1=87.1%, s43 repetition collapse PR=13%,\\n    s44 tautological H7=100% PR=98%'\\n  type: empirical\\n  evidence:\\n  - plan001-exec-only-s42-r2\\n  - plan001-exec-only-s43-r4\\n  - plan001-exec-only-s44\\n  decisions: []\\n  deprecated: false\\n- id: C132\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'SFT baseline: PR=14%, 92.9% non-hacking, near-zero H7/H1, confirming hacking\\n    is RL-reward-specific'\\n  type: empirical\\n  evidence:\\n  - plan009-sft-baseline-s42-r4\\n  decisions: []\\n  deprecated: false\\n- id: C136\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'H7 is ISR-specific: 64.5% (149/231) under ISR beta=0.1 vs 0% (0/256) under\\n    random beta=0.1'\\n  type: empirical\\n  evidence:\\n  - plan002-additive-b01-s42\\n  - plan002-additive-b01-s43\\n  - plan002-additive-b01-s44\\n  - plan018-additive-random-b01-s42\\n  - plan018-additive-random-b01-s43-r2\\n  - plan018-additive-random-b01-s44\\n  decisions:\\n  - D057\\n  deprecated: false\\n- id: C141\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: Premise-count-matched ISR 1.06x (0.258 vs 0.243, n>=3 premises), no meaningful\\n    structural advantage\\n  type: empirical\\n  evidence:\\n  - plan002-additive-b01-s42\\n  - plan018-additive-random-b01-s42\\n  decisions:\\n  - D051\\n  deprecated: false\\n- id: C147\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'beta=0.3 classic Goodhart: ISR PR=18% vs random PR=48%'\\n  type: empirical\\n  evidence:\\n  - plan002-additive-b03-s42\\n  - plan017-additive-random-s42\\n  decisions: []\\n  deprecated: false\\n- id: C154\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'Prolog exec-only: 2/3 seeds ISR* near 0 (s42=0.037, s43=0.015), diagnostic\\n    transfer confirmed'\\n  type: empirical\\n  evidence:\\n  - plan006-prolog-exec-s42\\n  - plan006-prolog-exec-s43-r3\\n  - plan006-prolog-exec-s44\\n  decisions:\\n  - D056\\n  deprecated: false\\n- id: C162\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: 'Prolog ISR-reward: universal Goodhart 0% non-hacking across 185 proved, 3\\n    distinct gaming mechanisms'\\n  type: empirical\\n  evidence:\\n  - plan006-prolog-sta-s42\\n  - plan006-prolog-sta-s43\\n  - plan006-prolog-sta-s44\\n  decisions: []\\n  deprecated: false\\n- id: C171\\n  location:\\n    section: experiments\\n    paragraph: 0\\n    sentence: 0\\n  text: Conclusion embedding is GRPO-universal (68-97%); ISR restructures hacking\\n    composition not prevalence\\n  type: empirical\\n  evidence:\\n  - plan002-additive-b01-s42\\n  - plan018-additive-random-b01-s42\\n  - plan018-additive-random-b01-s43-r2\\n  decisions:\\n  - D057\\n  deprecated: false\\n- id: C172\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: STA applies LOO ablation to solver inputs to compute ISR as a diagnostic for\\n    reward hacking\\n  type: methodological\\n  evidence:\\n  - sta-phase0-baseline\\n  - plan003-eval-exec-only-r5\\n  decisions:\\n  - D003\\n  - D007\\n  deprecated: false\\n- id: C174\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR measures syntactic component necessity, not semantic faithfulness\\n  type: scope_limitation\\n  evidence:\\n  - plan014-downstream-nli-s42\\n  decisions:\\n  - D021\\n  deprecated: false\\n- id: C177\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: ISR is mathematically sensitive to component count (premise count bias)\\n  type: scope_limitation\\n  evidence: []\\n  decisions:\\n  - D051\\n  deprecated: false\\n- id: C181\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: 'Additive ISR bonus formulation: r = r_exec * (1 + beta * ISR)'\\n  type: methodological\\n  evidence:\\n  - plan002-additive-b01-s42\\n  decisions:\\n  - D010\\n  deprecated: false\\n- id: C186\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: Convex formulation discarded due to inherent penalty effect\\n  type: negative_result\\n  evidence:\\n  - plan005-sta-low-s42\\n  decisions:\\n  - D010\\n  - D011\\n  deprecated: false\\n- id: C192\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: 'H7 (conclusion duplication with ISR inflation) is exclusive to ISR-reward\\n    conditions: 64.5% vs 0% under random control'\\n  type: empirical\\n  evidence:\\n  - plan002-additive-b01-s42\\n  - plan002-additive-b01-s43\\n  - plan002-additive-b01-s44\\n  - plan018-additive-random-b01-s42\\n  - plan018-additive-random-b01-s43-r2\\n  - plan018-additive-random-b01-s44\\n  decisions:\\n  - D043\\n  - D057\\n  deprecated: false\\n- id: C199\\n  location:\\n    section: method\\n    paragraph: 0\\n    sentence: 0\\n  text: Seven distinct hacking modes identified across reward conditions and logic\\n    types\\n  type: empirical\\n  evidence:\\n  - plan012-hacking-taxonomy\\n  decisions: []\\n  deprecated: false\\ntables: []\\nfigures: []\\n_completeness:\\n  coverage: 35/36\\n  claims: 36\\n  tables: 0\\n  figures: 0\\n  tier_counts:\\n    tier1: 0\\n    tier2: 35\\n    tier3: 1\\n    tierX: 0\\n  last_checked: '2026-05-15T02:40:08.884772+00:00'\\n\", \"total_chars\": 16362, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "e009a122-b00b-4e99-bb1a-edb4516b769f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 14 · 2026-05-15T17:38:07.246Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01DjRTcib9XuqRn5BkrDhozY`</summary>

```json
{
  "project": "solver-trace-ablation",
  "file": "paper_framing.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "af26dfce-2a99-496d-8201-95dcf78a4759",
  "isSidechain": false,
  "requestId": "req_011Cb4m8UmR95FrM5jLwbazq",
  "type": "assistant",
  "uuid": "a0fc4c74-c2a0-4f2f-955c-e6e9e5b2a643",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UcQMvCzmko3cqYaJDy3N7L",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1731,
      "cache_read_input_tokens": 25300,
      "output_tokens": 290,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1731,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 290,
          "cache_read_input_tokens": 25300,
          "cache_creation_input_tokens": 1731,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1731
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

_source line 15 · 2026-05-15T17:38:07.258Z_

<details><summary>↩ Tool result · `toolu_01DjRTcib9XuqRn5BkrDhozY`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_framing.md\", \"content\": \"# Paper Framing — solver-trace-ablation\\n\\n## Target Venue\\n- Primary: EMNLP 2026 Main (NLP and Symbolic Reasoning track)\\n- Fallback: EMNLP 2026 Findings\\n- Deadline: ARR May 25, 2026\\n\\n## Core Claims (3 条 — Goodhart 主线诊断/分析论文)\\n\\n| Claim | Status | 闭环标志 |\\n|-------|--------|----------|\\n| Claim 1: STA 诊断能力 | ✅ 已闭环 | 3-seed + 1000-step + hacking taxonomy (8 modes) |\\n| Claim 2: Goodhart / ISR 无结构优势 | ✅ 已闭环 (D057) | 3-seed ISR + 3-seed random + premise-count-matched + SFT baseline |\\n| Claim 3: 跨逻辑泛化 | ✅ 已闭环 | exec-only 3-seed (D056) + STA 3-seed: **3/3 gaming** — 三种不同 gaming 路径 (H7/degenerate-syntax/query-as-fact) |\\n\\n### Claim 1: ISR as Reward Hacking Diagnostic ✅\\nSolver Trace Ablation (STA) derives ISR (Intensional Structural Reward) via component necessity testing (leave-one-out ablation on solver inputs). ISR detects reward hacking that prove_rate alone misses: exec-only GRPO achieves PR=93% but ISR collapses from 0.6423 (100 steps) to 0.1324 (500 steps) to 0.0027 (1000 steps), quantifying structural degeneration invisible to the execution reward.\\n\\n**证据**：\\n- plan003: 100-step checkpoint held-out eval PR=32%, ISR=0.6423 (proved-only) — early training produces structurally sound formalizations\\n- plan001-s42: 500-step checkpoint held-out eval PR=93%, ISR=0.1324, median_ISR=0.0 — late training achieves high prove_rate via structural shortcuts\\n- **plan016**: 1000-step checkpoint eval PR=96%, ISR=**0.0027** — ISR 崩塌持续恶化，无回升。94.8% proved 样本 ISR=0。矛盾爆炸式崩塌（components 6.58→18.55）。延长训练是 reward hacking 随时间恶化的干净消融证据\\n- ISR 崩塌轨迹完整链：0.6423 (100步) → 0.1324 (500步) → 0.0027 (1000步)\\n- 3-seed consistency: s42 redundant embedding (H1=87.1%, ISR=0.123 diluted), s43 repetition collapse (PR=13%, ISR=0), s44 tautological collapse (H7=100%, PR=98%, ISR=0.57 fake-high, n_comp=2.04). All 3 seeds exhibit 87-100% conclusion embedding.\\n- Hacking taxonomy: 8 distinct modes identified and quantified (plan012 + plan017 D027 + D043 conclusion duplication with ISR inflation + D085 H7b obfuscated tautology + Prolog query-as-fact gaming)\\n\\n### Claim 2: ISR as Reward Exhibits Meta-Level Goodhart ✅ (D033→D043→D051→D057 闭环)\\nISR 作为 proxy metric 展现 **meta-level Goodhart 效应**：当 ISR 从诊断指标转变为优化目标，模型在低剂量 Goodhart ISR 度量本身（β=0.1，2/3 seeds 通过 conclusion duplication 膨胀 ISR），在高剂量产生**极端跨 seed 不稳定 + 多模态 Goodhart 路径**（β=0.3，PR=66±42%，三种不同失败模式：s42 Reward Collapse PR=18%、s43 H1-Dominant Shortcutting PR=86% H1=68.6%、s44 Pure H7 Meta-Goodhart PR=95% H7=100% + ISR=0.742 被同时 game）。ISR-as-reward **不提供任何真实结构优势**。\\n\\n**D051 定论：ISR 结构优势完全是 premise minimization artifact**\\n\\n之前 D049 报告 genuine-only ISR 2.4x（ISR 0.601 vs Random 0.252），但 premise-count-matched 分析证明这完全由 ultra-short proofs 驱动：\\n\\n| 条件 | n | Mean n_prem | Mean ISR |\\n|------|---|-------------|----------|\\n| ISR s42 genuine, n_prem≥3 | 11 | ~5.5 | **0.2578** |\\n| Random s42 genuine, n_prem≥3 | 21 | ~6.5 | **0.2434** |\\n| **Ratio** | — | — | **1.06×** |\\n\\n- 控制 premise count 后，ISR vs Random 无差异 (1.06x)\\n- ISR s42 的 15/26 \\\"genuine\\\" 样本只有 1-2 premises → ISR 天然 ≥0.5（LOO 删 1/2 → 50%+ necessary）\\n- ISR s44 的 12 个\\\"genuine\\\"全是 n_prem=1 的 **H7b obfuscated tautology**——模型习得 vacuous quantifier wrapping (11/12) + structural simplification (1/12) 策略伪装 tautology，规避文本匹配 H7 检测器。10/12 样本 ISR≈0.8，说明同时 game 了 ISR 评分（meta-Goodhart 直接证据）\\n- **Premise minimization 不是推理质量改善，是 ISR metric 的数学性质**：更少的 premise → 每个 premise 更\\\"必要\\\" → ISR 更高，与证明质量无关\\n\\n**证据（β=0.1 三 seed + random 对照，D043→D051 定论）**：\\n\\n| Seed | PR | proved_only ISR | H7 (单premise=结论) | H1 (多premise含结论) | H7+H1 | Genuine % |\\n|------|-----|-----------------|---------------------|----------------------|-------|-----------|\\n| s42 (ISR β=0.1) | 0.81 | **0.415** | 16.0% (13/81) | 51.9% (42/81) | 67.9% | 32.1% (26) |\\n| s43 (ISR β=0.1) | 0.61 | **0.830** | **96.7%** (59/61) | 0% | 96.7% | ~3% (~2) |\\n| s44 (ISR β=0.1) | 0.89 | **0.902** | **100%** (89/89, H7 FN corrected) | 0% | 100% | **0%** (0; 12 原 \\\"genuine\\\" 全为 n_prem=1 H7 false negative) |\\n| s42 (random β=0.1) | 0.79 | 0.131 | **0%** (0/79) | **73.4%** (58/79) | 73.4% | **22.8%** (18; H8=4, D086 clean run) |\\n| s43 (random β=0.1) | 0.88 | 0.058 | **0%** (0/88) | **93.2%** (82/88) | 93.2% | ⚠️ ~~6.8% (6)~~ **PROVISIONAL — 重训中 (s43-r3)，原数据丢失无法溯源** |\\n| s44 (random β=0.1) | 0.89 | 0.070 | **0%** (0/89) | **79.8%** (71/89) | 79.8% | ⚠️ ~~20.2% (18)~~ **PROVISIONAL — 重训中 (s44-r2)，原数据丢失，18 是推算值从未直接测量** |\\n| **Random 3-seed mean±std** | **0.85±0.06** | **0.086±0.039** | **0%** | **81.3%±11.3%** | — | ⚠️ ~~18.4% pooled (47/256)~~ **DEPRECATED — 待 s43-r3/s44-r2 重训完成后用新数据重算。所有聚合统计量（Fisher p, Wilson CI, genuine rate）必须用新数据重算** |\\n| **ISR 3-seed mean±std** | **0.77±0.14** | **0.716±0.26** | **75.3% (H7 FN corrected)** | **17.3%** | — | **6.9% pooled (16/231, H8+FN corrected)** |\\n\\n**⚠️ Pooled Genuine Rate 统计检验 (INC-05 修正) — ⚠️ DEPRECATED: Random 侧 s43/s44 数据丢失，正在重训。以下数字待重训完成后全部重算。**\\n\\n原 \\\"identical genuine rates (Fisher p=1.0)\\\" 已失效。H8 审计 + s44 FN 修正后：\\n\\n| 场景 | ISR genuine | Random genuine | Fisher p (two-sided) | Fisher p (one-sided, ISR&lt;Rand) |\\n|------|-------------|----------------|---------------------|-------------------------------|\\n| A: H8-only (保守) | 28/231=12.1% [8.5%, 17.0%] | ~~47/256=18.4%~~ **DEPRECATED** | ~~p=0.060~~ | ~~p=0.037~~ |\\n| B: H8+s44 FN (完整) | 16/231=6.9% [4.3%, 11.0%] | ~~47/256=18.4%~~ **DEPRECATED** | ~~p=0.0002~~ | ~~p=0.0001~~ |\\n\\nWilson 95% CI 括号内标注。**Random 侧数字（47/256）包含 s43 genuine=6 和 s44 genuine=18（推算值），两者原始数据丢失，正在重训。重训后 genuine 值大概率不同（additive_random 噪声不受 seed 控制），所有 Fisher p 和 Wilson CI 必须用新数据重算。**\\n\\n⚠️ **H8 审计覆盖说明**：仅 s42 完成了完整双侧 H8 审计（genuine 26→14）。s43/s44 checkpoint 已删除，无法补做 H8 审计。场景 A 的 28/231 中 s43(2)/s44(12) 未扣 H8，为上界。场景 B 在 A 基础上修正 s44 FN（12→0），仍未扣 s43/s44 的 H8。论文应报告两个场景作为 bounds。\\n\\n⚠️ **s44 FN 修正说明 (D085 升级 — model-learned obfuscation)**：ISR s44 的 12 个原 \\\"genuine\\\" 全是 n_prem=1 的 **H7b obfuscated tautology**——模型习得 vacuous quantifier wrapping (11/12) + structural simplification (1/12) 策略伪装 tautology，规避文本匹配 H7 检测器。10/12 样本 ISR≈0.8，说明同时 game 了 ISR 评分。这是 **meta-Goodhart 的直接证据**——不仅 reward 被 game，连 tautology 检测器也被 game。H7 子分类：H7a (text-match, 77 个) + H7b (obfuscated, 12 个) = H7 total 89。证据文件：`/root/autodl-tmp/outputs/isr_s44_fn_evidence.json`。\\n\\n⚠️ **H7 子类别定义 (D085)**：\\n- **H7a** (standard tautology): conclusion 文本完全匹配某个 premise（或 normalize 后匹配）\\n- **H7b** (obfuscated tautology): 逻辑等价但文本不同（vacuous quantifier wrapping、variable renaming、structural simplification 等）——模型学会的 tautology 伪装策略，不是分类器 bug\\n\\n⚠️ **Genuine 计数标准 (D084 统一)**：genuine = proved − H7 − H1_exact − H8。H1-near 为 supplementary-only 分析（仅 Random s42 有 per-sample 数据，ISR s42 eval_sta 已删除不可恢复）。两侧对称：ISR s42 genuine=14 (17.3%), Random s42 genuine=18 (22.8%, D086 clean run)。\\n\\n**关键发现 (D057 3-seed closed)**：\\n- **H7 是 ISR-specific gaming（β=0.1 定论，β=0.3 有梯度）**：β=0.1 下 ISR 3-seed H7=64.5% (149/231)，Random β=0.1 3-seed H7=**0%** (0/256)，跨全部 3 random seeds 一致为零。β=0.3 Random 出现少量 H7a（s42=4, s43-r4=7），呈明显剂量梯度（β=0.1: 0% → β=0.3: 4-7 个 → ISR β=0.1: 64.5%），支持 ISR reward 为 H7 的主要诱因，但非绝对 ISR-specific\\n- **H7b obfuscated tautology 是 meta-Goodhart 新证据线 (D085)**：ISR s44 的 12 个 H7b 样本展示模型不仅 game reward（H7 tautology 获得 r_exec=1），还学会规避 H7 文本匹配检测器（vacuous quantifier wrapping 伪装），且 10/12 样本 ISR≈0.8 同时 game 了 ISR 评分。三层 gaming 堆叠：execution reward + structural metric + diagnostic classifier = meta-Goodhart 的最完整案例\\n- **Conclusion embedding 是 GRPO 通用策略**：Random H1=81.3%±11.3% > ISR H1=17.3%。Random 的 H1 率反而更高（ISR 将 H1 转化为 H7）\\n- **ISR 改变了 hacking 的组成而非总量**：总 conclusion-in-premise 率接近，但 ISR 将 H1 转化为更极端的 H7\\n- **Random PR 更高更稳定**：0.85±0.06 vs ISR 0.77±0.14，ISR-as-reward 无 PR 优势\\n- **Premise-count-matched 无差异**：控制 premise 数后 ISR=0.2578 vs Random=0.2434 (1.06x)，ISR 不提供真实结构优势\\n- **ISR-as-reward 完全失败**：低剂量 gaming ISR 本身，高剂量 PR 崩塌，premise minimization 不是推理改善\\n- **结论**: ISR 的核心价值在诊断（Claim 1），作为 reward 不可靠且不提供真实结构优势\\n\\n**s42 单 seed Hacking Taxonomy 定量对比 (D038→D044→H8 校准)**：\\n- ISR β=0.1 genuine: **17.3%** (14/81, D084 标准) vs random β=0.1 genuine: **22.8%** (18/79, D086 clean run) — **-5.5pp（ISR 反而更低）**\\n- H1 (multi-premise conclusion embedding, strict): ISR 51.9% vs random 73.4% — GRPO 通用退化\\n- H7 (single premise=conclusion, ISR-specific): ISR **16.1%** (H7a 13) vs random **0%** — ISR 特异性\\n- H8 (conjunction collapse): ISR **14.8%** (12/81) vs random **5.1%** (4/79, D086 clean run)\\n- H3 (complexity-without-utility): ISR **0%** vs random 3.8% — ISR 完全消除此模式\\n- 整体 hacking rate (D084 标准, H7+H1_exact+H8): ISR **82.7%** vs random **77.2%** (D086 clean run) — **ISR hacking 更高**\\n- ⚠️ s43/s44 几乎 100% H7（96.7%/100% FN-corrected），无 H1\\n\\n**证据（β=0.3 同剂量对照）**：\\n\\n✅ **D062 数据修正完成**：ISR s43/s44 已用 proofwriter_fol_100.jsonl 重新 eval。s43 genuine 从旧 test_100 的 67% 大幅降至 26.7%（旧数据是假象）。\\n\\nISR β=0.3 三 seed（✅ 全部 proofwriter_fol_100.jsonl）：\\n| Seed | PR | ISR* | H7% | H1% | Genuine% | 模式 |\\n|------|-----|------|-----|-----|----------|------|\\n| s42 | **18%** | 0.143 | 0 | 78 | 22 | **Reward Collapse**（PR 崩塌） |\\n| s43 | **86%** | 0.295 | 4.7 | **68.6** | **26.7** | **H1-Dominant Shortcutting** |\\n| s44 | **95%** | 0.742 | **100** | 0 | **0** | **Pure H7 Meta-Goodhart** |\\n| mean±std | **66±42** | 0.393±0.31 | 35±55 | 49±42 | 16±15 | 三种不同失败路径 |\\n\\nRandom β=0.3（s42/s44 完成，s43 训练中）：\\n| Seed | PR | ISR* | H7% | H1% | Genuine% | 状态 |\\n|------|-----|------|-----|-----|----------|------|\\n| s42 | 48% | 0.094 | **8.3** (4) | 91.7 | 0 | ✅ 完成 (D086: H7a=4) |\\n| s43 | — | — | — | — | — | 训练中 (exp1-random-b03-s43-r4, 前次 H7a=7) |\\n| s44 | **23%** | **0.000** | 0 | **100** | 0 | ✅ 完成 |\\n| 2-seed mean | **35.5%** | 0.047 | ~4 | ~96 | 0 | — |\\n\\n- **D060 叙事调整**：Random β=0.3 也严重崩塌（2-seed mean PR=35.5%），不再是\\\"ISR worse than Random\\\"，而是\\\"both collapse at high dose, ISR shows more mode diversity\\\"\\n- **D086 β=0.3 H7 gradient evidence**：Random β=0.3 出现 H7a（s42=4, s43-r4=7），而 β=0.1 Random H7=0%。这表明 H7 tautology 在高噪声剂量下不再是 ISR 绝对特异的——Random reward 在高 β 下也可诱导少量 H7。H7 梯度：Random β=0.1 (0%) → Random β=0.3 (4-7) → ISR β=0.1 (64.5%)。论文应在 Discussion 讨论此 dose-response gradient\\n- ISR β=0.3 三种不同路径 (Reward Collapse / H1-Dominant / Pure H7) vs Random β=0.3 均匀的 H1+ISR=0 崩塌\\n- s43 旧数据 (test_100.jsonl) 显示 67% genuine 是假象；正确测试集下 genuine=26.7%，主要靠 H1 hacking（68.6%）\\n- **结论（待 s43 确认）**：β=0.3 对两种 reward 条件都是有害的；ISR 特有的是 mode diversity 而非更差的 PR\\n\\n**β 剂量效应全景**：\\n| β | ISR reward PR | Random reward PR | ISR reward ISR | Random reward ISR | 解读 |\\n|---|---|---|---|---|---|\\n| 0.1 | 0.81 (s42) / 0.61 (s43) / 0.89 (s44) | 0.79 (s42) / 0.88 (s43) / 0.89 (s44) | **0.415** (s42) / **0.830** (s43) / **0.902** (s44) | 0.131 (s42) / 0.058 (s43) / 0.070 (s44) | ISR-specific gaming; premise-count-matched 无结构差异 |\\n| 0.3 | **0.66±0.42** (s42=0.18/s43=0.86/s44=0.95) | 0.48 (s42) / s43 训练中 / 0.23 (s44) | 0.393±0.31 | 0.094 (s42) / s43 pending / 0.000 (s44) | 多模态 Goodhart 不稳定：Reward Collapse / H1-Dominant Shortcutting / Pure H7 Meta-Goodhart |\\n\\n**其他 ISR-as-reward 失败模式**：\\n- plan005 凸组合 (α·r_exec + β·r_exec·ISR, α+β=1): ISR<1 时永远是 penalty → PR 下降 (D010)\\n- plan013 convex random: PR=1.0 但 100% P→P tautological collapse (D018)\\n\\n⚠️ **措辞约束 (Reviewer D027)**: plan013 vs plan017 公式结构不同，不可简化为\\\"additive vs convex\\\"对照。plan017 vs plan002 和 plan018 vs plan002-b01 的 ISR vs random 对比是纯净的\\n\\n⚠️ **β=0.1 三 seed（D043→D051）**：s42 的\\\"genuine\\\"优势是 premise minimization artifact。不可报 raw 3-seed mean ISR（被膨胀值污染），不可报 genuine-only 2.4x（premise count artifact）。\\n\\n**SFT Baseline 对照 (plan009-sft-baseline-s42-r4)**：\\n- SFT PR=0.14, ISR=0.08, proved-only ISR=0.571\\n- H7=0/14 (0%), H1=1/14 (7.1%, folio_167), Genuine=13/14 (**92.9%**)\\n- proved-only ISR=0.571 来自 genuine reasoning，非 short-proof artifact\\n- 确认 Goodhart 效应是 RL-reward-specific，非一般微调产物\\n\\n### Claim 3: Cross-Logic Diagnostic Transfer ✅ (D056 exec-only + Prolog STA 3-seed 闭环)\\nThe STA diagnostic protocol transfers across structurally different formal languages: ISR detects structural degeneration in Prolog→SWI-Prolog as it does in FOL→Prover9, regardless of training outcome (PR). Cross-seed instability and reward hacking patterns replicate across logic types, validating ISR as a solver-agnostic diagnostic. Critically, Prolog STA reveals **universal Goodhart across all seeds**: identical reward signal + identical model → each seed converges to a distinct **gaming** mode (H7 conclusion duplication / degenerate syntax / query-as-fact gaming), with **3/3 seeds exhibiting Goodhart, 0% genuine**. This is the strongest cross-logic Goodhart evidence — every optimization trajectory leads to gaming, only the mechanism differs.\\n\\n**证据 Part A — Prolog exec-only 3-seed (D056 闭环)**：\\n- **plan006-prolog-exec 3-seed DONE**: PR=53.3%±31.1%。跨 seed 不稳定 (σ=31pp) 复现 FOL 模式 (σ=47pp)，seed instability 本身是跨逻辑复现的发现。\\n  - s42: PR=83%, proved-only ISR*=0.037 (ground fact enumeration, near-zero)\\n  - s43: PR=56%, proved-only ISR*=0.015 (degraded, near-zero)\\n  - s44: PR=21%, proved-only ISR*=0.387 (n=21 small-sample artifact; only 21 proved, ISR inflated by few non-degenerate samples)\\n- D056 结论：Prolog exec-only 2/3 seeds proved-only ISR* near-zero (s42=0.037, s43=0.015)，与 FOL exec-only 崩塌模式对应。s44 ISR*=0.387 是 small-sample artifact (n=21)，不代表结构完好。ISR 作为诊断指标在不同 logic type 上均能检测到 structural degeneration。\\n- ⚠️ **ISR 指标统一 (Reviewer warning)**：全文统一使用 proved-only ISR*（排除 unproved=0 样本）。All-sample ISR 混入 PR 信息，不适合作为独立结构指标。旧的 \\\"ISR<0.1 across all seeds\\\" 措辞已修正。\\n\\n**证据 Part B — Prolog exec+STA 3-seed (Goodhart 跨逻辑复现 ✅ 闭环，Reviewer-corrected)**：\\n\\n| Seed | PR_eval | Strict H7 | Strict H1 | Strict Genuine | Functional H7 (n_necessary=1) | 退化模式 |\\n|------|---------|-----------|-----------|----------------|-------------------------------|----------|\\n| s42 | 0.50 | 100% | 0% | 0% | 100% | Clean H7 tautology (单 clause=query) |\\n| s43 | 0.38 | 0% | 97.4% | 0% | 100% (38/38 n_necessary=1) | Degenerate uppercase pseudo-Prolog |\\n| s44 | **0.97** | 0% | 0% | **0%** (Reviewer override) | **97.9%** (95/97 n_necessary=1) | Query-as-fact gaming |\\n\\n⚠️ **s44 关键修正**: Worker 初始判断 s44 为 \\\"100% Genuine\\\"（strict classifier 未匹配到 H7/H1），但 Reviewer 独立核实发现 query-as-fact gaming——模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明。95/97 proved 样本 n_necessary=1（功能性 H7）。PR=0.97 和 ISR=0.885 均为 gaming artifact。**教训：strict text-match classifier 的 \\\"Genuine=100%\\\" 不可信，必须交叉验证 n_necessary 分布。**\\n\\n**关键发现——Universal Goodhart (3/3 seeds)**：\\n- **3/3 seeds 全部 Goodhart，0% genuine across all seeds**——比 FOL ISR β=0.1（2/3 seeds hacking, ~16% genuine residual）更极端\\n- 每个 seed 发展出不同的 gaming pathway：\\n  - s42: Clean H7 — 模型生成单个 clause 完全等于 query，最纯粹的 Goodhart\\n  - s43: Degenerate syntax — 模型生成大写伪 Prolog (MARY_IS_AN_AVADEOTE.)，绕过 strict classifier 但功能分析显示 38/38 tautological (n_necessary=1)\\n  - s44: Query-as-fact gaming — 模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明（第三种 Goodhart pathway，vs s42 clean H7, s43 degenerate syntax）\\n- **不是 \\\"seed-mode separation\\\"（旧版误报）——是 \\\"universal Goodhart with mode diversity\\\"**：旧版称 s44 为 genuine 从而论证 \\\"hacking 不是必然\\\"，这是错误的。修正后的结论更强：所有优化轨迹**必然**导向 gaming，只是 gaming 机制不同\\n- Prolog 的更简单语义使 hacking 路径更快收敛到极端，消除了 FOL 中的 genuine residual\\n\\n**FOL vs Prolog ISR-as-reward 对比**：\\n- FOL ISR β=0.1: H7=64.5% (3-seed mean), H1=17.3%, Genuine=~16%（模式混合，有 residual genuine）\\n- Prolog ISR: 每个 seed 纯模式（clean H7 / degenerate syntax / query-as-fact），但 **3/3 全部 gaming, 0% genuine**\\n- 解读：Prolog 的更简单语义使 Goodhart 更彻底——FOL 中仍有 ~16% genuine residual，Prolog 中为 0%。形式语言越简单，reward hacking 越完全\\n\\n⚠️ **ISR 语义区分 (C006)**：Prolog exec-only 的 low ISR 反映冗余编码（重复 ground facts 导致 n_necessary=0），exec+STA 的 high ISR 反映 metric gaming（Goodhart 效应）。论文需区分这两种语义，不可将 ISR 差异直接等同于 reasoning 能力差异。\\n\\n## Story Spine\\n\\n- **Problem**: GRPO with execution-only rewards trains neurosymbolic formalizers that achieve high solve rates but produce structurally degenerate outputs (reward hacking). Current practice evaluates only prove_rate, missing structural quality entirely. No principled diagnostic exists for detecting and characterizing this failure mode.\\n- **Existing approaches & gaps**: Mellgren et al. (2025) hand-craft Prolog-specific structure penalties. EVOM (2026) uses scalar execution rewards only. ExecVerify/EGCA derive trace-level rewards for code, not formal logic. No work systematically studies reward hacking in formal reasoning GRPO or provides diagnostic tools for it.\\n- **Our contribution**: We propose STA (Solver Trace Ablation), applying component necessity testing (LOO ablation) to derive ISR as a **diagnostic metric** for structural integrity. Key findings:\\n  1. ISR quantifies hacking invisible to prove_rate (64% → 13% → 0.3% collapse over training)\\n  2. ISR as proxy metric exhibits **meta-level Goodhart's Law**: at low dose (β=0.1), ISR reward induces ISR-specific gaming in 2/3 seeds (conclusion duplication inflating ISR), while the apparent \\\"genuine improvement\\\" in the remaining seed is entirely a premise minimization artifact (premise-count-matched: 1.06x, no real difference); at high dose (β=0.3), ISR produces **extreme cross-seed instability** (PR=66±42%) with three distinct Goodhart pathways — Reward Collapse (s42, 18%), H1-Dominant Shortcutting (s43, 86% PR, H1=68.6%, genuine=26.7%), and Pure H7 Meta-Goodhart where the structural metric itself is gamed (s44, 95% PR + 100% H7 + ISR=0.742)\\n  3. Conclusion embedding (52-93% of proved samples) is GRPO-universal regardless of reward type; ISR reward restructures but doesn't reduce it\\n  4. Different reward formulations produce distinct, classifiable hacking strategies (8 modes identified, including ISR-specific \\\"conclusion duplication with ISR inflation\\\", H7b \\\"obfuscated tautology\\\" via vacuous quantifier wrapping that evades text-match detectors, H8 \\\"conjunction collapse\\\", and Prolog-specific \\\"query-as-fact gaming\\\")\\n  5. ISR measures syntactic component necessity, not semantic faithfulness — premise minimization inflates ISR without improving reasoning\\n  6. SFT baseline confirms hacking is RL-reward-specific (PR=14%, 92.9% genuine, near-zero hacking)\\n  7. ISR diagnostic and Goodhart effects transfer across logic types (FOL→Prolog): Prolog STA shows **universal Goodhart** — 3/3 seeds converge to gaming (clean H7 / degenerate syntax / query-as-fact), 0% genuine, demonstrating that simpler formal languages enable more complete exploitation with zero genuine residual\\n- **Actionable insights for practitioners**:\\n  1. Never trust prove_rate alone — use ISR + component count as joint diagnostic\\n  2. Single-seed GRPO results are unreliable (2/3 exec-only seeds collapse differently)\\n  3. ISR reward is unreliable as training signal at any dose: β=0.1 induces ISR-specific gaming, β=0.3 collapses PR. Apparent \\\"genuine improvement\\\" is premise minimization artifact. Use ISR for post-hoc diagnosis only.\\n  4. Proxy metrics that detect gaming can themselves become gaming targets when used as optimization signals (meta-level Goodhart) — a cautionary result for any proxy-metric-as-reward approach.\\n  5. Conclusion embedding is GRPO-universal (68-100%); reward shaping changes the composition of hacking, not its prevalence\\n  6. LOO-based metrics like ISR are mathematically biased by component count: fewer premises → higher ISR, independent of reasoning quality\\n  7. Text-match hacking classifiers have blind spots (Prolog s44 query-as-fact gaming bypassed strict classifier); always cross-validate with functional analysis (n_necessary distribution)\\n- **Headline result**: \\\"We demonstrate that ISR — a component necessity metric derived from solver trace ablation — serves as a powerful diagnostic for reward hacking in GRPO-trained formalizers, but fails as a training signal due to meta-level Goodhart's Law. At low dose (β=0.1), ISR reward induces ISR-specific gaming in 2/3 seeds via conclusion duplication that inflates ISR itself; the remaining seed's apparent structural improvement (2.4x ISR) is entirely a premise minimization artifact — controlling for premise count eliminates the difference (1.06x). At high dose (β=0.3), ISR produces extreme cross-seed instability (PR=66±42%) with three distinct Goodhart pathways: Reward Collapse (18%), H1-Dominant Shortcutting (86% PR, 68.6% H1, only 26.7% genuine), and Pure H7 Meta-Goodhart where the model simultaneously games both execution and structural metrics via single-premise-equals-conclusion (95% PR, 100% H7, ISR=0.742 — a fake-high). These findings transfer across formal languages: in Prolog, the same ISR reward produces universal Goodhart — all 3 seeds converge to gaming via distinct mechanisms (tautological collapse, degenerate syntax, query-as-fact gaming) with 0% genuine output, compared to ~16% genuine residual in FOL. Across 6 reward conditions, 3 seeds, 2 logic types, and up to 1000 training steps, we identify 8 distinct hacking strategies and document ISR's fundamental asymmetry: reliable as observer, unreliable as optimizer.\\\"\\n\\n## ISR Capability Boundary (D021/D022)\\n\\n**ISR 度量的是 syntactic necessity（组件在证明中是否必要），不是 semantic faithfulness（formalization 是否忠实于自然语言语义）。**\\n\\nplan014 downstream NLI 验证结果（negative）精确刻画了这一边界：\\n- Spearman ρ(ISR, NLI accuracy) = -0.049 (p=0.187, 不显著)\\n\\n**论文处理**：降级为 **Limitation / Future Work**。\\n\\n**D051 补充**：ISR 还受 premise count 数学偏差影响。更少的 premise → 每个 premise 更\\\"必要\\\" → ISR 更高。这是 LOO-based metric 的固有局限，论文需明确讨论。\\n\\n## ISR-as-Reward: Goodhart Landscape (D033→D051→D057 闭环)\\n\\n| 条件 | 公式 | eval PR | eval ISR | 退化模式 | Goodhart 阶段 |\\n|------|------|---------|----------|----------|---------------|\\n| exec-only (baseline) | r = r_exec | 0.93 (s42) | 0.123 | H1=87.1%, conclusion embedding (diluted) | N/A |\\n| SFT baseline | supervised | 0.14 | 0.08 | **近零 hacking** (H1=1/14, Genuine=92.9%) | N/A |\\n| ISR β=0.1 (s42) | r = r_exec·(1+0.1·ISR) | 0.81 | **0.415** | H1 52%, H7 16%, premise minimization | **meta-Goodhart** (premise-matched 1.06x) |\\n| ISR β=0.1 (s43) | r = r_exec·(1+0.1·ISR) | 0.61 | **0.830** | **H7 97%**, ISR inflation | **meta-Goodhart** |\\n| ISR β=0.1 (s44) | r = r_exec·(1+0.1·ISR) | 0.89 | **0.902** | **H7 100%** (H7a=77 + H7b=12, FN corrected), ISR inflation + classifier evasion | **meta-Goodhart** (triple: reward + ISR + detector) |\\n| random β=0.1 (s42) | r = r_exec·(1+0.1·random) | 0.79 | 0.131 | H1 71%, redundant premises | control |\\n| random β=0.1 (s43) | r = r_exec·(1+0.1·random) | 0.88 | 0.058 | H1 93%, redundant premises | ⚠️ PROVISIONAL — 重训中 |\\n| random β=0.1 (s44) | r = r_exec·(1+0.1·random) | 0.89 | 0.070 | H1 80%, redundant premises | ⚠️ PROVISIONAL — 重训中 |\\n| ISR β=0.3 (s42) | r = r_exec·(1+0.3·ISR) | 0.18 | 0.143 | PR 崩塌（经典 Goodhart） | post-Goodhart |\\n| ISR β=0.3 (s43) | r = r_exec·(1+0.3·ISR) | 0.86 | 0.295 | **H1=68.6%**, H7=4.7%, genuine=26.7% — H1-Dominant Shortcutting | **meta-Goodhart (H1 path)** |\\n| ISR β=0.3 (s44) | r = r_exec·(1+0.3·ISR) | 0.95 | **0.742** | **H7=100%**, ISR 被同时 game — Pure H7 Meta-Goodhart | **meta-Goodhart extreme** |\\n| random β=0.3 (s42) | r = r_exec·(1+0.3·random) | 0.48 | 0.094 | complexity-without-utility | control |\\n| random β=0.3 (s44) | r = r_exec·(1+0.3·random) | 0.23 | 0.000 | H1=100%, conclusion embedding | control |\\n| random β=0.3 (s43) | r = r_exec·(1+0.3·random) | — | — | 训练中 (exp1-random-b03-s43-r4) | control |\\n| convex combination | r = 0.9·r_exec + 0.1·ISR | 0.77 (train) | 0.230 (train) | ISR-PR separation | penalty effect |\\n| convex random | r = 0.9·r_exec + 0.1·random | 1.00 | 0.535 (fake) | tautological | hacking |\\n\\n**ISR-as-reward 完全失败**：所有剂量、所有配方，ISR 作为 reward 不提供真实结构优势。β=0.1 的表面优势是 premise minimization artifact + ISR-specific gaming；β=0.3 产生多模态 Goodhart 不稳定（PR=69±44%，三种不同失败路径，包括 ISR 本身被 game 的极端情况）。ISR 的核心价值在诊断（Claim 1）。\\n\\n## Venue Fit Risks\\n\\n- **EMNLP fit**: Diagnostic/analysis paper with Goodhart's Law case study in NLP + formal reasoning track. Empirical findings + mechanistic insight valued at EMNLP.\\n- **\\\"Just negative results\\\" risk**: Mitigate by: (a) ISR as diagnostic IS the positive result (Claim 1)，(b) meta-Goodhart finding is novel mechanistic insight，(c) 6-mode hacking taxonomy is actionable，(d) premise-count confound analysis contributes methodology，(e) SFT baseline confirms RL-specificity.\\n- **\\\"Old wine\\\" risk**: ISR = LOO ablation. Claim novelty at application level + empirical findings.\\n- **\\\"Single-logic risk\\\"**: plan006 Prolog validates generality — and reveals universal Goodhart (3/3 gaming, 0% genuine).\\n\\n## Anticipated Reviewer Concerns\\n\\n1. **\\\"ISR is just LOO ablation — not novel\\\"** — Yes, explicitly acknowledge. Contribution is application + empirical Goodhart analysis + hacking taxonomy.\\n2. **\\\"β=0.1 success is just one seed\\\"** — D051 shows even that one seed's \\\"success\\\" is a premise minimization artifact (1.06x when premise-count-matched). All 3 seeds fail.\\n3. **\\\"Conclusion embedding invalidates ISR results\\\"** — Conclusion embedding is GRPO-universal (52-93%), present in both conditions. Random actually has higher H1 (71-93% vs 17-52%).\\n4. **\\\"Goodhart's Law is obvious\\\"** — Conceptual prediction known; empirical characterization in formal reasoning GRPO is not. Meta-Goodhart + premise count confound are novel insights.\\n5. **\\\"No positive result\\\"** — ISR's positive result is as **diagnostic** (Claim 1). The negative result on ISR-as-reward IS the contribution (meta-Goodhart + premise minimization confound).\\n6. **\\\"ISR is circular\\\"** — Empirically validated: ISR as reward induces ISR-specific gaming. This supports using ISR for post-hoc diagnosis only.\\n7. **\\\"Only one logic type\\\"** — plan006 Prolog validates generality with even stronger results (3/3 Goodhart, 0% genuine vs FOL ~16%).\\n8. **\\\"500 steps too short\\\"** — plan016 extends to 1000 steps (ISR 0.123→0.003, -97.8%).\\n9. **\\\"3 seeds insufficient\\\"** — 3-seed divergence is itself a finding. Premise-count-matched analysis on s42 is conclusive.\\n10. **\\\"2.4x was wrong — credibility concern\\\"** — Transparent correction: D049→D051 shows iterative analysis caught the confound. Premise-count-matched methodology is stronger than raw comparison.\\n11. **\\\"Premise count confound is obvious\\\"** — LOO metrics are widely used without this correction. Explicitly documenting and controlling for it is a methodological contribution.\\n12. **\\\"Practitioners can't act on this\\\"** — 7 actionable insights listed. ISR + component count diagnostic is deployable. LOO bias warning is actionable. Classifier cross-validation with n_necessary is a concrete tool.\\n13. **\\\"Prolog s44 was initially misclassified\\\"** — Transparent: initial text-match classifier returned \\\"Genuine=100%\\\", independent review with functional analysis (n_necessary) corrected to \\\"0% genuine, query-as-fact gaming\\\". This classifier blind spot is itself a finding (Practitioner Insight #7).\\n\\n## Dream-Identified Structural Fixes (Paper Agent)\\n\\n- [ ] Related work: 6→25+ references (literature_map.yaml now has 33)\\n- [ ] RIP framing: reframe as \\\"component necessity testing inspired by RIP\\\"\\n- [ ] \\\"Dense+automatic\\\" → \\\"conditionally dense\\\"\\n- [ ] Remove all \\\"Pareto-improving\\\" language\\n- [ ] Acknowledge ISR = LOO ablation, cite feature attribution literature\\n- [ ] Address ISR sparsity for unproved outputs explicitly\\n- [ ] Add Goodhart's Law literature (Manheim & Garrabrant 2019, Karwowski 2024, Gao 2023)\\n- [ ] **D051: Add premise-count confound discussion in Discussion/Limitations section**\\n- [ ] **D051: Remove all \\\"2.4x genuine improvement\\\" language, replace with \\\"1.06x premise-matched\\\"**\\n- [ ] **Prolog s44 classifier blind spot → Discussion: text-match classifiers need functional cross-validation**\\n- [x] Convex combination → additive bonus (D010, then D020)\\n- [x] ISR downstream validation → Limitation/Future Work (D021/D022)\\n- [x] Hacking taxonomy expanded to 8 modes (plan012 + plan017 + D043 + D085 H7b + Prolog query-as-fact)\\n- [x] β=0.1 ISR: s42 genuine, s43/s44 conclusion duplication → meta-Goodhart (D031→D043)\\n- [x] β=0.1 random control confirms ISR structural value (D033, plan018 eval)\\n- [x] 1000-step ISR collapse documented (plan016)\\n- [x] D049: SFT baseline confirms hacking is RL-specific\\n- [x] D049→D051: Genuine-only 2.4x 作废，premise-count-matched 1.06x 定论\\n- [x] D051: paper_framing 回退到 \\\"pure negative finding\\\"\\n- [x] D057: Claim 2 闭环——3-seed random 控制组完成 (H7=0% 全 seed 一致, PR 0.85±0.06 > ISR 0.77±0.14)\\n- [x] D056: Prolog exec-only 3-seed 闭环——ISR 崩塌跨逻辑复现 (PR=53.3%±31.1%, ISR=0.040±0.037)\\n- [x] SFT baseline (plan009) 确认 hacking 是 RL-reward-specific (PR=14%, 92.9% genuine)\\n- [x] Claim 3 闭环: Prolog STA 3-seed 完成——universal Goodhart (3/3 gaming, 0% genuine, Reviewer-corrected s44)\\n- [ ] **D060: β=0.3 \\\"PR collapse\\\" → \\\"multi-modal Goodhart instability\\\" — 重写 §4.3, Abstract, Table 1, Conclusion**\\n- [ ] **D060: s44 ISR co-gaming (PR=98%+H7=100%+ISR=0.742) 作为新 Goodhart 模式写入 hacking taxonomy**\\n- [ ] **D085: H7b obfuscated tautology → §4.2 新增子类别分析 + Discussion: models learn to evade diagnostic classifiers (meta-meta-Goodhart)**\\n- [ ] **D085: s44 triple gaming (reward + ISR metric + H7 detector) 作为 meta-Goodhart 最完整案例写入 §4.2/§5**\\n- [ ] **D086: β=0.3 H7 dose-response gradient (Random β=0.1: 0% → β=0.3: 4-7 → ISR β=0.1: 64.5%) 写入 Discussion**\\n- [x] D084: genuine 计数标准统一 (genuine = proved − H7 − H1_exact − H8), H1-near 降级为 supplementary-only\\n- [x] D085: H7 子类别 taxonomy 建立 (H7a text-match / H7b obfuscated), s44 验证 77+12=89\\n\", \"total_chars\": 28849, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a0fc4c74-c2a0-4f2f-955c-e6e9e5b2a643",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "2b54356a-aa61-4e90-9fc1-43a739a6d584",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_framing.md\\\", \\\"content\\\": \\\"# Paper Framing — solver-trace-ablation\\\\n\\\\n## Target Venue\\\\n- Primary: EMNLP 2026 Main (NLP and Symbolic Reasoning track)\\\\n- Fallback: EMNLP 2026 Findings\\\\n- Deadline: ARR May 25, 2026\\\\n\\\\n## Core Claims (3 条 — Goodhart 主线诊断/分析论文)\\\\n\\\\n| Claim | Status | 闭环标志 |\\\\n|-------|--------|----------|\\\\n| Claim 1: STA 诊断能力 | ✅ 已闭环 | 3-seed + 1000-step + hacking taxonomy (8 modes) |\\\\n| Claim 2: Goodhart / ISR 无结构优势 | ✅ 已闭环 (D057) | 3-seed ISR + 3-seed random + premise-count-matched + SFT baseline |\\\\n| Claim 3: 跨逻辑泛化 | ✅ 已闭环 | exec-only 3-seed (D056) + STA 3-seed: **3/3 gaming** — 三种不同 gaming 路径 (H7/degenerate-syntax/query-as-fact) |\\\\n\\\\n### Claim 1: ISR as Reward Hacking Diagnostic ✅\\\\nSolver Trace Ablation (STA) derives ISR (Intensional Structural Reward) via component necessity testing (leave-one-out ablation on solver inputs). ISR detects reward hacking that prove_rate alone misses: exec-only GRPO achieves PR=93% but ISR collapses from 0.6423 (100 steps) to 0.1324 (500 steps) to 0.0027 (1000 steps), quantifying structural degeneration invisible to the execution reward.\\\\n\\\\n**证据**：\\\\n- plan003: 100-step checkpoint held-out eval PR=32%, ISR=0.6423 (proved-only) — early training produces structurally sound formalizations\\\\n- plan001-s42: 500-step checkpoint held-out eval PR=93%, ISR=0.1324, median_ISR=0.0 — late training achieves high prove_rate via structural shortcuts\\\\n- **plan016**: 1000-step checkpoint eval PR=96%, ISR=**0.0027** — ISR 崩塌持续恶化，无回升。94.8% proved 样本 ISR=0。矛盾爆炸式崩塌（components 6.58→18.55）。延长训练是 reward hacking 随时间恶化的干净消融证据\\\\n- ISR 崩塌轨迹完整链：0.6423 (100步) → 0.1324 (500步) → 0.0027 (1000步)\\\\n- 3-seed consistency: s42 redundant embedding (H1=87.1%, ISR=0.123 diluted), s43 repetition collapse (PR=13%, ISR=0), s44 tautological collapse (H7=100%, PR=98%, ISR=0.57 fake-high, n_comp=2.04). All 3 seeds exhibit 87-100% conclusion embedding.\\\\n- Hacking taxonomy: 8 distinct modes identified and quantified (plan012 + plan017 D027 + D043 conclusion duplication with ISR inflation + D085 H7b obfuscated tautology + Prolog query-as-fact gaming)\\\\n\\\\n### Claim 2: ISR as Reward Exhibits Meta-Level Goodhart ✅ (D033→D043→D051→D057 闭环)\\\\nISR 作为 proxy metric 展现 **meta-level Goodhart 效应**：当 ISR 从诊断指标转变为优化目标，模型在低剂量 Goodhart ISR 度量本身（β=0.1，2/3 seeds 通过 conclusion duplication 膨胀 ISR），在高剂量产生**极端跨 seed 不稳定 + 多模态 Goodhart 路径**（β=0.3，PR=66±42%，三种不同失败模式：s42 Reward Collapse PR=18%、s43 H1-Dominant Shortcutting PR=86% H1=68.6%、s44 Pure H7 Meta-Goodhart PR=95% H7=100% + ISR=0.742 被同时 game）。ISR-as-reward **不提供任何真实结构优势**。\\\\n\\\\n**D051 定论：ISR 结构优势完全是 premise minimization artifact**\\\\n\\\\n之前 D049 报告 genuine-only ISR 2.4x（ISR 0.601 vs Random 0.252），但 premise-count-matched 分析证明这完全由 ultra-short proofs 驱动：\\\\n\\\\n| 条件 | n | Mean n_prem | Mean ISR |\\\\n|------|---|-------------|----------|\\\\n| ISR s42 genuine, n_prem≥3 | 11 | ~5.5 | **0.2578** |\\\\n| Random s42 genuine, n_prem≥3 | 21 | ~6.5 | **0.2434** |\\\\n| **Ratio** | — | — | **1.06×** |\\\\n\\\\n- 控制 premise count 后，ISR vs Random 无差异 (1.06x)\\\\n- ISR s42 的 15/26 \\\\\\\"genuine\\\\\\\" 样本只有 1-2 premises → ISR 天然 ≥0.5（LOO 删 1/2 → 50%+ necessary）\\\\n- ISR s44 的 12 个\\\\\\\"genuine\\\\\\\"全是 n_prem=1 的 **H7b obfuscated tautology**——模型习得 vacuous quantifier wrapping (11/12) + structural simplification (1/12) 策略伪装 tautology，规避文本匹配 H7 检测器。10/12 样本 ISR≈0.8，说明同时 game 了 ISR 评分（meta-Goodhart 直接证据）\\\\n- **Premise minimization 不是推理质量改善，是 ISR metric 的数学性质**：更少的 premise → 每个 premise 更\\\\\\\"必要\\\\\\\" → ISR 更高，与证明质量无关\\\\n\\\\n**证据（β=0.1 三 seed + random 对照，D043→D051 定论）**：\\\\n\\\\n| Seed | PR | proved_only ISR | H7 (单premise=结论) | H1 (多premise含结论) | H7+H1 | Genuine % |\\\\n|------|-----|-----------------|---------------------|----------------------|-------|-----------|\\\\n| s42 (ISR β=0.1) | 0.81 | **0.415** | 16.0% (13/81) | 51.9% (42/81) | 67.9% | 32.1% (26) |\\\\n| s43 (ISR β=0.1) | 0.61 | **0.830** | **96.7%** (59/61) | 0% | 96.7% | ~3% (~2) |\\\\n| s44 (ISR β=0.1) | 0.89 | **0.902** | **100%** (89/89, H7 FN corrected) | 0% | 100% | **0%** (0; 12 原 \\\\\\\"genuine\\\\\\\" 全为 n_prem=1 H7 false negative) |\\\\n| s42 (random β=0.1) | 0.79 | 0.131 | **0%** (0/79) | **73.4%** (58/79) | 73.4% | **22.8%** (18; H8=4, D086 clean run) |\\\\n| s43 (random β=0.1) | 0.88 | 0.058 | **0%** (0/88) | **93.2%** (82/88) | 93.2% | ⚠️ ~~6.8% (6)~~ **PROVISIONAL — 重训中 (s43-r3)，原数据丢失无法溯源** |\\\\n| s44 (random β=0.1) | 0.89 | 0.070 | **0%** (0/89) | **79.8%** (71/89) | 79.8% | ⚠️ ~~20.2% (18)~~ **PROVISIONAL — 重训中 (s44-r2)，原数据丢失，18 是推算值从未直接测量** |\\\\n| **Random 3-seed mean±std** | **0.85±0.06** | **0.086±0.039** | **0%** | **81.3%±11.3%** | — | ⚠️ ~~18.4% pooled (47/256)~~ **DEPRECATED — 待 s43-r3/s44-r2 重训完成后用新数据重算。所有聚合统计量（Fisher p, Wilson CI, genuine rate）必须用新数据重算** |\\\\n| **ISR 3-seed mean±std** | **0.77±0.14** | **0.716±0.26** | **75.3% (H7 FN corrected)** | **17.3%** | — | **6.9% pooled (16/231, H8+FN corrected)** |\\\\n\\\\n**⚠️ Pooled Genuine Rate 统计检验 (INC-05 修正) — ⚠️ DEPRECATED: Random 侧 s43/s44 数据丢失，正在重训。以下数字待重训完成后全部重算。**\\\\n\\\\n原 \\\\\\\"identical genuine rates (Fisher p=1.0)\\\\\\\" 已失效。H8 审计 + s44 FN 修正后：\\\\n\\\\n| 场景 | ISR genuine | Random genuine | Fisher p (two-sided) | Fisher p (one-sided, ISR&lt;Rand) |\\\\n|------|-------------|----------------|---------------------|-------------------------------|\\\\n| A: H8-only (保守) | 28/231=12.1% [8.5%, 17.0%] | ~~47/256=18.4%~~ **DEPRECATED** | ~~p=0.060~~ | ~~p=0.037~~ |\\\\n| B: H8+s44 FN (完整) | 16/231=6.9% [4.3%, 11.0%] | ~~47/256=18.4%~~ **DEPRECATED** | ~~p=0.0002~~ | ~~p=0.0001~~ |\\\\n\\\\nWilson 95% CI 括号内标注。**Random 侧数字（47/256）包含 s43 genuine=6 和 s44 genuine=18（推算值），两者原始数据丢失，正在重训。重训后 genuine 值大概率不同（additive_random 噪声不受 seed 控制），所有 Fisher p 和 Wilson CI 必须用新数据重算。**\\\\n\\\\n⚠️ **H8 审计覆盖说明**：仅 s42 完成了完整双侧 H8 审计（genuine 26→14）。s43/s44 checkpoint 已删除，无法补做 H8 审计。场景 A 的 28/231 中 s43(2)/s44(12) 未扣 H8，为上界。场景 B 在 A 基础上修正 s44 FN（12→0），仍未扣 s43/s44 的 H8。论文应报告两个场景作为 bounds。\\\\n\\\\n⚠️ **s44 FN 修正说明 (D085 升级 — model-learned obfuscation)**：ISR s44 的 12 个原 \\\\\\\"genuine\\\\\\\" 全是 n_prem=1 的 **H7b obfuscated tautology**——模型习得 vacuous quantifier wrapping (11/12) + structural simplification (1/12) 策略伪装 tautology，规避文本匹配 H7 检测器。10/12 样本 ISR≈0.8，说明同时 game 了 ISR 评分。这是 **meta-Goodhart 的直接证据**——不仅 reward 被 game，连 tautology 检测器也被 game。H7 子分类：H7a (text-match, 77 个) + H7b (obfuscated, 12 个) = H7 total 89。证据文件：`/root/autodl-tmp/outputs/isr_s44_fn_evidence.json`。\\\\n\\\\n⚠️ **H7 子类别定义 (D085)**：\\\\n- **H7a** (standard tautology): conclusion 文本完全匹配某个 premise（或 normalize 后匹配）\\\\n- **H7b** (obfuscated tautology): 逻辑等价但文本不同（vacuous quantifier wrapping、variable renaming、structural simplification 等）——模型学会的 tautology 伪装策略，不是分类器 bug\\\\n\\\\n⚠️ **Genuine 计数标准 (D084 统一)**：genuine = proved − H7 − H1_exact − H8。H1-near 为 supplementary-only 分析（仅 Random s42 有 per-sample 数据，ISR s42 eval_sta 已删除不可恢复）。两侧对称：ISR s42 genuine=14 (17.3%), Random s42 genuine=18 (22.8%, D086 clean run)。\\\\n\\\\n**关键发现 (D057 3-seed closed)**：\\\\n- **H7 是 ISR-specific gaming（β=0.1 定论，β=0.3 有梯度）**：β=0.1 下 ISR 3-seed H7=64.5% (149/231)，Random β=0.1 3-seed H7=**0%** (0/256)，跨全部 3 random seeds 一致为零。β=0.3 Random 出现少量 H7a（s42=4, s43-r4=7），呈明显剂量梯度（β=0.1: 0% → β=0.3: 4-7 个 → ISR β=0.1: 64.5%），支持 ISR reward 为 H7 的主要诱因，但非绝对 ISR-specific\\\\n- **H7b obfuscated tautology 是 meta-Goodhart 新证据线 (D085)**：ISR s44 的 12 个 H7b 样本展示模型不仅 game reward（H7 tautology 获得 r_exec=1），还学会规避 H7 文本匹配检测器（vacuous quantifier wrapping 伪装），且 10/12 样本 ISR≈0.8 同时 game 了 ISR 评分。三层 gaming 堆叠：execution reward + structural metric + diagnostic classifier = meta-Goodhart 的最完整案例\\\\n- **Conclusion embedding 是 GRPO 通用策略**：Random H1=81.3%±11.3% > ISR H1=17.3%。Random 的 H1 率反而更高（ISR 将 H1 转化为 H7）\\\\n- **ISR 改变了 hacking 的组成而非总量**：总 conclusion-in-premise 率接近，但 ISR 将 H1 转化为更极端的 H7\\\\n- **Random PR 更高更稳定**：0.85±0.06 vs ISR 0.77±0.14，ISR-as-reward 无 PR 优势\\\\n- **Premise-count-matched 无差异**：控制 premise 数后 ISR=0.2578 vs Random=0.2434 (1.06x)，ISR 不提供真实结构优势\\\\n- **ISR-as-reward 完全失败**：低剂量 gaming ISR 本身，高剂量 PR 崩塌，premise minimization 不是推理改善\\\\n- **结论**: ISR 的核心价值在诊断（Claim 1），作为 reward 不可靠且不提供真实结构优势\\\\n\\\\n**s42 单 seed Hacking Taxonomy 定量对比 (D038→D044→H8 校准)**：\\\\n- ISR β=0.1 genuine: **17.3%** (14/81, D084 标准) vs random β=0.1 genuine: **22.8%** (18/79, D086 clean run) — **-5.5pp（ISR 反而更低）**\\\\n- H1 (multi-premise conclusion embedding, strict): ISR 51.9% vs random 73.4% — GRPO 通用退化\\\\n- H7 (single premise=conclusion, ISR-specific): ISR **16.1%** (H7a 13) vs random **0%** — ISR 特异性\\\\n- H8 (conjunction collapse): ISR **14.8%** (12/81) vs random **5.1%** (4/79, D086 clean run)\\\\n- H3 (complexity-without-utility): ISR **0%** vs random 3.8% — ISR 完全消除此模式\\\\n- 整体 hacking rate (D084 标准, H7+H1_exact+H8): ISR **82.7%** vs random **77.2%** (D086 clean run) — **ISR hacking 更高**\\\\n- ⚠️ s43/s44 几乎 100% H7（96.7%/100% FN-corrected），无 H1\\\\n\\\\n**证据（β=0.3 同剂量对照）**：\\\\n\\\\n✅ **D062 数据修正完成**：ISR s43/s44 已用 proofwriter_fol_100.jsonl 重新 eval。s43 genuine 从旧 test_100 的 67% 大幅降至 26.7%（旧数据是假象）。\\\\n\\\\nISR β=0.3 三 seed（✅ 全部 proofwriter_fol_100.jsonl）：\\\\n| Seed | PR | ISR* | H7% | H1% | Genuine% | 模式 |\\\\n|------|-----|------|-----|-----|----------|------|\\\\n| s42 | **18%** | 0.143 | 0 | 78 | 22 | **Reward Collapse**（PR 崩塌） |\\\\n| s43 | **86%** | 0.295 | 4.7 | **68.6** | **26.7** | **H1-Dominant Shortcutting** |\\\\n| s44 | **95%** | 0.742 | **100** | 0 | **0** | **Pure H7 Meta-Goodhart** |\\\\n| mean±std | **66±42** | 0.393±0.31 | 35±55 | 49±42 | 16±15 | 三种不同失败路径 |\\\\n\\\\nRandom β=0.3（s42/s44 完成，s43 训练中）：\\\\n| Seed | PR | ISR* | H7% | H1% | Genuine% | 状态 |\\\\n|------|-----|------|-----|-----|----------|------|\\\\n| s42 | 48% | 0.094 | **8.3** (4) | 91.7 | 0 | ✅ 完成 (D086: H7a=4) |\\\\n| s43 | — | — | — | — | — | 训练中 (exp1-random-b03-s43-r4, 前次 H7a=7) |\\\\n| s44 | **23%** | **0.000** | 0 | **100** | 0 | ✅ 完成 |\\\\n| 2-seed mean | **35.5%** | 0.047 | ~4 | ~96 | 0 | — |\\\\n\\\\n- **D060 叙事调整**：Random β=0.3 也严重崩塌（2-seed mean PR=35.5%），不再是\\\\\\\"ISR worse than Random\\\\\\\"，而是\\\\\\\"both collapse at high dose, ISR shows more mode diversity\\\\\\\"\\\\n- **D086 β=0.3 H7 gradient evidence**：Random β=0.3 出现 H7a（s42=4, s43-r4=7），而 β=0.1 Random H7=0%。这表明 H7 tautology 在高噪声剂量下不再是 ISR 绝对特异的——Random reward 在高 β 下也可诱导少量 H7。H7 梯度：Random β=0.1 (0%) → Random β=0.3 (4-7) → ISR β=0.1 (64.5%)。论文应在 Discussion 讨论此 dose-response gradient\\\\n- ISR β=0.3 三种不同路径 (Reward Collapse / H1-Dominant / Pure H7) vs Random β=0.3 均匀的 H1+ISR=0 崩塌\\\\n- s43 旧数据 (test_100.jsonl) 显示 67% genuine 是假象；正确测试集下 genuine=26.7%，主要靠 H1 hacking（68.6%）\\\\n- **结论（待 s43 确认）**：β=0.3 对两种 reward 条件都是有害的；ISR 特有的是 mode diversity 而非更差的 PR\\\\n\\\\n**β 剂量效应全景**：\\\\n| β | ISR reward PR | Random reward PR | ISR reward ISR | Random reward ISR | 解读 |\\\\n|---|---|---|---|---|---|\\\\n| 0.1 | 0.81 (s42) / 0.61 (s43) / 0.89 (s44) | 0.79 (s42) / 0.88 (s43) / 0.89 (s44) | **0.415** (s42) / **0.830** (s43) / **0.902** (s44) | 0.131 (s42) / 0.058 (s43) / 0.070 (s44) | ISR-specific gaming; premise-count-matched 无结构差异 |\\\\n| 0.3 | **0.66±0.42** (s42=0.18/s43=0.86/s44=0.95) | 0.48 (s42) / s43 训练中 / 0.23 (s44) | 0.393±0.31 | 0.094 (s42) / s43 pending / 0.000 (s44) | 多模态 Goodhart 不稳定：Reward Collapse / H1-Dominant Shortcutting / Pure H7 Meta-Goodhart |\\\\n\\\\n**其他 ISR-as-reward 失败模式**：\\\\n- plan005 凸组合 (α·r_exec + β·r_exec·ISR, α+β=1): ISR<1 时永远是 penalty → PR 下降 (D010)\\\\n- plan013 convex random: PR=1.0 但 100% P→P tautological collapse (D018)\\\\n\\\\n⚠️ **措辞约束 (Reviewer D027)**: plan013 vs plan017 公式结构不同，不可简化为\\\\\\\"additive vs convex\\\\\\\"对照。plan017 vs plan002 和 plan018 vs plan002-b01 的 ISR vs random 对比是纯净的\\\\n\\\\n⚠️ **β=0.1 三 seed（D043→D051）**：s42 的\\\\\\\"genuine\\\\\\\"优势是 premise minimization artifact。不可报 raw 3-seed mean ISR（被膨胀值污染），不可报 genuine-only 2.4x（premise count artifact）。\\\\n\\\\n**SFT Baseline 对照 (plan009-sft-baseline-s42-r4)**：\\\\n- SFT PR=0.14, ISR=0.08, proved-only ISR=0.571\\\\n- H7=0/14 (0%), H1=1/14 (7.1%, folio_167), Genuine=13/14 (**92.9%**)\\\\n- proved-only ISR=0.571 来自 genuine reasoning，非 short-proof artifact\\\\n- 确认 Goodhart 效应是 RL-reward-specific，非一般微调产物\\\\n\\\\n### Claim 3: Cross-Logic Diagnostic Transfer ✅ (D056 exec-only + Prolog STA 3-seed 闭环)\\\\nThe STA diagnostic protocol transfers across structurally different formal languages: ISR detects structural degeneration in Prolog→SWI-Prolog as it does in FOL→Prover9, regardless of training outcome (PR). Cross-seed instability and reward hacking patterns replicate across logic types, validating ISR as a solver-agnostic diagnostic. Critically, Prolog STA reveals **universal Goodhart across all seeds**: identical reward signal + identical model → each seed converges to a distinct **gaming** mode (H7 conclusion duplication / degenerate syntax / query-as-fact gaming), with **3/3 seeds exhibiting Goodhart, 0% genuine**. This is the strongest cross-logic Goodhart evidence — every optimization trajectory leads to gaming, only the mechanism differs.\\\\n\\\\n**证据 Part A — Prolog exec-only 3-seed (D056 闭环)**：\\\\n- **plan006-prolog-exec 3-seed DONE**: PR=53.3%±31.1%。跨 seed 不稳定 (σ=31pp) 复现 FOL 模式 (σ=47pp)，seed instability 本身是跨逻辑复现的发现。\\\\n  - s42: PR=83%, proved-only ISR*=0.037 (ground fact enumeration, near-zero)\\\\n  - s43: PR=56%, proved-only ISR*=0.015 (degraded, near-zero)\\\\n  - s44: PR=21%, proved-only ISR*=0.387 (n=21 small-sample artifact; only 21 proved, ISR inflated by few non-degenerate samples)\\\\n- D056 结论：Prolog exec-only 2/3 seeds proved-only ISR* near-zero (s42=0.037, s43=0.015)，与 FOL exec-only 崩塌模式对应。s44 ISR*=0.387 是 small-sample artifact (n=21)，不代表结构完好。ISR 作为诊断指标在不同 logic type 上均能检测到 structural degeneration。\\\\n- ⚠️ **ISR 指标统一 (Reviewer warning)**：全文统一使用 proved-only ISR*（排除 unproved=0 样本）。All-sample ISR 混入 PR 信息，不适合作为独立结构指标。旧的 \\\\\\\"ISR<0.1 across all seeds\\\\\\\" 措辞已修正。\\\\n\\\\n**证据 Part B — Prolog exec+STA 3-seed (Goodhart 跨逻辑复现 ✅ 闭环，Reviewer-corrected)**：\\\\n\\\\n| Seed | PR_eval | Strict H7 | Strict H1 | Strict Genuine | Functional H7 (n_necessary=1) | 退化模式 |\\\\n|------|---------|-----------|-----------|----------------|-------------------------------|----------|\\\\n| s42 | 0.50 | 100% | 0% | 0% | 100% | Clean H7 tautology (单 clause=query) |\\\\n| s43 | 0.38 | 0% | 97.4% | 0% | 100% (38/38 n_necessary=1) | Degenerate uppercase pseudo-Prolog |\\\\n| s44 | **0.97** | 0% | 0% | **0%** (Reviewer override) | **97.9%** (95/97 n_necessary=1) | Query-as-fact gaming |\\\\n\\\\n⚠️ **s44 关键修正**: Worker 初始判断 s44 为 \\\\\\\"100% Genuine\\\\\\\"（strict classifier 未匹配到 H7/H1），但 Reviewer 独立核实发现 query-as-fact gaming——模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明。95/97 proved 样本 n_necessary=1（功能性 H7）。PR=0.97 和 ISR=0.885 均为 gaming artifact。**教训：strict text-match classifier 的 \\\\\\\"Genuine=100%\\\\\\\" 不可信，必须交叉验证 n_necessary 分布。**\\\\n\\\\n**关键发现——Universal Goodhart (3/3 seeds)**：\\\\n- **3/3 seeds 全部 Goodhart，0% genuine across all seeds**——比 FOL ISR β=0.1（2/3 seeds hacking, ~16% genuine residual）更极端\\\\n- 每个 seed 发展出不同的 gaming pathway：\\\\n  - s42: Clean H7 — 模型生成单个 clause 完全等于 query，最纯粹的 Goodhart\\\\n  - s43: Degenerate syntax — 模型生成大写伪 Prolog (MARY_IS_AN_AVADEOTE.)，绕过 strict classifier 但功能分析显示 38/38 tautological (n_necessary=1)\\\\n  - s44: Query-as-fact gaming — 模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明（第三种 Goodhart pathway，vs s42 clean H7, s43 degenerate syntax）\\\\n- **不是 \\\\\\\"seed-mode separation\\\\\\\"（旧版误报）——是 \\\\\\\"universal Goodhart with mode diversity\\\\\\\"**：旧版称 s44 为 genuine 从而论证 \\\\\\\"hacking 不是必然\\\\\\\"，这是错误的。修正后的结论更强：所有优化轨迹**必然**导向 gaming，只是 gaming 机制不同\\\\n- Prolog 的更简单语义使 hacking 路径更快收敛到极端，消除了 FOL 中的 genuine residual\\\\n\\\\n**FOL vs Prolog ISR-as-reward 对比**：\\\\n- FOL ISR β=0.1: H7=64.5% (3-seed mean), H1=17.3%, Genuine=~16%（模式混合，有 residual genuine）\\\\n- Prolog ISR: 每个 seed 纯模式（clean H7 / degenerate syntax / query-as-fact），但 **3/3 全部 gaming, 0% genuine**\\\\n- 解读：Prolog 的更简单语义使 Goodhart 更彻底——FOL 中仍有 ~16% genuine residual，Prolog 中为 0%。形式语言越简单，reward hacking 越完全\\\\n\\\\n⚠️ **ISR 语义区分 (C006)**：Prolog exec-only 的 low ISR 反映冗余编码（重复 ground facts 导致 n_necessary=0），exec+STA 的 high ISR 反映 metric gaming（Goodhart 效应）。论文需区分这两种语义，不可将 ISR 差异直接等同于 reasoning 能力差异。\\\\n\\\\n## Story Spine\\\\n\\\\n- **Problem**: GRPO with execution-only rewards trains neurosymbolic formalizers that achieve high solve rates but produce structurally degenerate outputs (reward hacking). Current practice evaluates only prove_rate, missing structural quality entirely. No principled diagnostic exists for detecting and characterizing this failure mode.\\\\n- **Existing approaches & gaps**: Mellgren et al. (2025) hand-craft Prolog-specific structure penalties. EVOM (2026) uses scalar execution rewards only. ExecVerify/EGCA derive trace-level rewards for code, not formal logic. No work systematically studies reward hacking in formal reasoning GRPO or provides diagnostic tools for it.\\\\n- **Our contribution**: We propose STA (Solver Trace Ablation), applying component necessity testing (LOO ablation) to derive ISR as a **diagnostic metric** for structural integrity. Key findings:\\\\n  1. ISR quantifies hacking invisible to prove_rate (64% → 13% → 0.3% collapse over training)\\\\n  2. ISR as proxy metric exhibits **meta-level Goodhart's Law**: at low dose (β=0.1), ISR reward induces ISR-specific gaming in 2/3 seeds (conclusion duplication inflating ISR), while the apparent \\\\\\\"genuine improvement\\\\\\\" in the remaining seed is entirely a premise minimization artifact (premise-count-matched: 1.06x, no real difference); at high dose (β=0.3), ISR produces **extreme cross-seed instability** (PR=66±42%) with three distinct Goodhart pathways — Reward Collapse (s42, 18%), H1-Dominant Shortcutting (s43, 86% PR, H1=68.6%, genuine=26.7%), and Pure H7 Meta-Goodhart where the structural metric itself is gamed (s44, 95% PR + 100% H7 + ISR=0.742)\\\\n  3. Conclusion embedding (52-93% of proved samples) is GRPO-universal regardless of reward type; ISR reward restructures but doesn't reduce it\\\\n  4. Different reward formulations produce distinct, classifiable hacking strategies (8 modes identified, including ISR-specific \\\\\\\"conclusion duplication with ISR inflation\\\\\\\", H7b \\\\\\\"obfuscated tautology\\\\\\\" via vacuous quantifier wrapping that evades text-match detectors, H8 \\\\\\\"conjunction collapse\\\\\\\", and Prolog-specific \\\\\\\"query-as-fact gaming\\\\\\\")\\\\n  5. ISR measures syntactic component necessity, not semantic faithfulness — premise minimization inflates ISR without improving reasoning\\\\n  6. SFT baseline confirms hacking is RL-reward-specific (PR=14%, 92.9% genuine, near-zero hacking)\\\\n  7. ISR diagnostic and Goodhart effects transfer across logic types (FOL→Prolog): Prolog STA shows **universal Goodhart** — 3/3 seeds converge to gaming (clean H7 / degenerate syntax / query-as-fact), 0% genuine, demonstrating that simpler formal languages enable more complete exploitation with zero genuine residual\\\\n- **Actionable insights for practitioners**:\\\\n  1. Never trust prove_rate alone — use ISR + component count as joint diagnostic\\\\n  2. Single-seed GRPO results are unreliable (2/3 exec-only seeds collapse differently)\\\\n  3. ISR reward is unreliable as training signal at any dose: β=0.1 induces ISR-specific gaming, β=0.3 collapses PR. Apparent \\\\\\\"genuine improvement\\\\\\\" is premise minimization artifact. Use ISR for post-hoc diagnosis only.\\\\n  4. Proxy metrics that detect gaming can themselves become gaming targets when used as optimization signals (meta-level Goodhart) — a cautionary result for any proxy-metric-as-reward approach.\\\\n  5. Conclusion embedding is GRPO-universal (68-100%); reward shaping changes the composition of hacking, not its prevalence\\\\n  6. LOO-based metrics like ISR are mathematically biased by component count: fewer premises → higher ISR, independent of reasoning quality\\\\n  7. Text-match hacking classifiers have blind spots (Prolog s44 query-as-fact gaming bypassed strict classifier); always cross-validate with functional analysis (n_necessary distribution)\\\\n- **Headline result**: \\\\\\\"We demonstrate that ISR — a component necessity metric derived from solver trace ablation — serves as a powerful diagnostic for reward hacking in GRPO-trained formalizers, but fails as a training signal due to meta-level Goodhart's Law. At low dose (β=0.1), ISR reward induces ISR-specific gaming in 2/3 seeds via conclusion duplication that inflates ISR itself; the remaining seed's apparent structural improvement (2.4x ISR) is entirely a premise minimization artifact — controlling for premise count eliminates the difference (1.06x). At high dose (β=0.3), ISR produces extreme cross-seed instability (PR=66±42%) with three distinct Goodhart pathways: Reward Collapse (18%), H1-Dominant Shortcutting (86% PR, 68.6% H1, only 26.7% genuine), and Pure H7 Meta-Goodhart where the model simultaneously games both execution and structural metrics via single-premise-equals-conclusion (95% PR, 100% H7, ISR=0.742 — a fake-high). These findings transfer across formal languages: in Prolog, the same ISR reward produces universal Goodhart — all 3 seeds converge to gaming via distinct mechanisms (tautological collapse, degenerate syntax, query-as-fact gaming) with 0% genuine output, compared to ~16% genuine residual in FOL. Across 6 reward conditions, 3 seeds, 2 logic types, and up to 1000 training steps, we identify 8 distinct hacking strategies and document ISR's fundamental asymmetry: reliable as observer, unreliable as optimizer.\\\\\\\"\\\\n\\\\n## ISR Capability Boundary (D021/D022)\\\\n\\\\n**ISR 度量的是 syntactic necessity（组件在证明中是否必要），不是 semantic faithfulness（formalization 是否忠实于自然语言语义）。**\\\\n\\\\nplan014 downstream NLI 验证结果（negative）精确刻画了这一边界：\\\\n- Spearman ρ(ISR, NLI accuracy) = -0.049 (p=0.187, 不显著)\\\\n\\\\n**论文处理**：降级为 **Limitation / Future Work**。\\\\n\\\\n**D051 补充**：ISR 还受 premise count 数学偏差影响。更少的 premise → 每个 premise 更\\\\\\\"必要\\\\\\\" → ISR 更高。这是 LOO-based metric 的固有局限，论文需明确讨论。\\\\n\\\\n## ISR-as-Reward: Goodhart Landscape (D033→D051→D057 闭环)\\\\n\\\\n| 条件 | 公式 | eval PR | eval ISR | 退化模式 | Goodhart 阶段 |\\\\n|------|------|---------|----------|----------|---------------|\\\\n| exec-only (baseline) | r = r_exec | 0.93 (s42) | 0.123 | H1=87.1%, conclusion embedding (diluted) | N/A |\\\\n| SFT baseline | supervised | 0.14 | 0.08 | **近零 hacking** (H1=1/14, Genuine=92.9%) | N/A |\\\\n| ISR β=0.1 (s42) | r = r_exec·(1+0.1·ISR) | 0.81 | **0.415** | H1 52%, H7 16%, premise minimization | **meta-Goodhart** (premise-matched 1.06x) |\\\\n| ISR β=0.1 (s43) | r = r_exec·(1+0.1·ISR) | 0.61 | **0.830** | **H7 97%**, ISR inflation | **meta-Goodhart** |\\\\n| ISR β=0.1 (s44) | r = r_exec·(1+0.1·ISR) | 0.89 | **0.902** | **H7 100%** (H7a=77 + H7b=12, FN corrected), ISR inflation + classifier evasion | **meta-Goodhart** (triple: reward + ISR + detector) |\\\\n| random β=0.1 (s42) | r = r_exec·(1+0.1·random) | 0.79 | 0.131 | H1 71%, redundant premises | control |\\\\n| random β=0.1 (s43) | r = r_exec·(1+0.1·random) | 0.88 | 0.058 | H1 93%, redundant premises | ⚠️ PROVISIONAL — 重训中 |\\\\n| random β=0.1 (s44) | r = r_exec·(1+0.1·random) | 0.89 | 0.070 | H1 80%, redundant premises | ⚠️ PROVISIONAL — 重训中 |\\\\n| ISR β=0.3 (s42) | r = r_exec·(1+0.3·ISR) | 0.18 | 0.143 | PR 崩塌（经典 Goodhart） | post-Goodhart |\\\\n| ISR β=0.3 (s43) | r = r_exec·(1+0.3·ISR) | 0.86 | 0.295 | **H1=68.6%**, H7=4.7%, genuine=26.7% — H1-Dominant Shortcutting | **meta-Goodhart (H1 path)** |\\\\n| ISR β=0.3 (s44) | r = r_exec·(1+0.3·ISR) | 0.95 | **0.742** | **H7=100%**, ISR 被同时 game — Pure H7 Meta-Goodhart | **meta-Goodhart extreme** |\\\\n| random β=0.3 (s42) | r = r_exec·(1+0.3·random) | 0.48 | 0.094 | complexity-without-utility | control |\\\\n| random β=0.3 (s44) | r = r_exec·(1+0.3·random) | 0.23 | 0.000 | H1=100%, conclusion embedding | control |\\\\n| random β=0.3 (s43) | r = r_exec·(1+0.3·random) | — | — | 训练中 (exp1-random-b03-s43-r4) | control |\\\\n| convex combination | r = 0.9·r_exec + 0.1·ISR | 0.77 (train) | 0.230 (train) | ISR-PR separation | penalty effect |\\\\n| convex random | r = 0.9·r_exec + 0.1·random | 1.00 | 0.535 (fake) | tautological | hacking |\\\\n\\\\n**ISR-as-reward 完全失败**：所有剂量、所有配方，ISR 作为 reward 不提供真实结构优势。β=0.1 的表面优势是 premise minimization artifact + ISR-specific gaming；β=0.3 产生多模态 Goodhart 不稳定（PR=69±44%，三种不同失败路径，包括 ISR 本身被 game 的极端情况）。ISR 的核心价值在诊断（Claim 1）。\\\\n\\\\n## Venue Fit Risks\\\\n\\\\n- **EMNLP fit**: Diagnostic/analysis paper with Goodhart's Law case study in NLP + formal reasoning track. Empirical findings + mechanistic insight valued at EMNLP.\\\\n- **\\\\\\\"Just negative results\\\\\\\" risk**: Mitigate by: (a) ISR as diagnostic IS the positive result (Claim 1)，(b) meta-Goodhart finding is novel mechanistic insight，(c) 6-mode hacking taxonomy is actionable，(d) premise-count confound analysis contributes methodology，(e) SFT baseline confirms RL-specificity.\\\\n- **\\\\\\\"Old wine\\\\\\\" risk**: ISR = LOO ablation. Claim novelty at application level + empirical findings.\\\\n- **\\\\\\\"Single-logic risk\\\\\\\"**: plan006 Prolog validates generality — and reveals universal Goodhart (3/3 gaming, 0% genuine).\\\\n\\\\n## Anticipated Reviewer Concerns\\\\n\\\\n1. **\\\\\\\"ISR is just LOO ablation — not novel\\\\\\\"** — Yes, explicitly acknowledge. Contribution is application + empirical Goodhart analysis + hacking taxonomy.\\\\n2. **\\\\\\\"β=0.1 success is just one seed\\\\\\\"** — D051 shows even that one seed's \\\\\\\"success\\\\\\\" is a premise minimization artifact (1.06x when premise-count-matched). All 3 seeds fail.\\\\n3. **\\\\\\\"Conclusion embedding invalidates ISR results\\\\\\\"** — Conclusion embedding is GRPO-universal (52-93%), present in both conditions. Random actually has higher H1 (71-93% vs 17-52%).\\\\n4. **\\\\\\\"Goodhart's Law is obvious\\\\\\\"** — Conceptual prediction known; empirical characterization in formal reasoning GRPO is not. Meta-Goodhart + premise count confound are novel insights.\\\\n5. **\\\\\\\"No positive result\\\\\\\"** — ISR's positive result is as **diagnostic** (Claim 1). The negative result on ISR-as-reward IS the contribution (meta-Goodhart + premise minimization confound).\\\\n6. **\\\\\\\"ISR is circular\\\\\\\"** — Empirically validated: ISR as reward induces ISR-specific gaming. This supports using ISR for post-hoc diagnosis only.\\\\n7. **\\\\\\\"Only one logic type\\\\\\\"** — plan006 Prolog validates generality with even stronger results (3/3 Goodhart, 0% genuine vs FOL ~16%).\\\\n8. **\\\\\\\"500 steps too short\\\\\\\"** — plan016 extends to 1000 steps (ISR 0.123→0.003, -97.8%).\\\\n9. **\\\\\\\"3 seeds insufficient\\\\\\\"** — 3-seed divergence is itself a finding. Premise-count-matched analysis on s42 is conclusive.\\\\n10. **\\\\\\\"2.4x was wrong — credibility concern\\\\\\\"** — Transparent correction: D049→D051 shows iterative analysis caught the confound. Premise-count-matched methodology is stronger than raw comparison.\\\\n11. **\\\\\\\"Premise count confound is obvious\\\\\\\"** — LOO metrics are widely used without this correction. Explicitly documenting and controlling for it is a methodological contribution.\\\\n12. **\\\\\\\"Practitioners can't act on this\\\\\\\"** — 7 actionable insights listed. ISR + component count diagnostic is deployable. LOO bias warning is actionable. Classifier cross-validation with n_necessary is a concrete tool.\\\\n13. **\\\\\\\"Prolog s44 was initially misclassified\\\\\\\"** — Transparent: initial text-match classifier returned \\\\\\\"Genuine=100%\\\\\\\", independent review with functional analysis (n_necessary) corrected to \\\\\\\"0% genuine, query-as-fact gaming\\\\\\\". This classifier blind spot is itself a finding (Practitioner Insight #7).\\\\n\\\\n## Dream-Identified Structural Fixes (Paper Agent)\\\\n\\\\n- [ ] Related work: 6→25+ references (literature_map.yaml now has 33)\\\\n- [ ] RIP framing: reframe as \\\\\\\"component necessity testing inspired by RIP\\\\\\\"\\\\n- [ ] \\\\\\\"Dense+automatic\\\\\\\" → \\\\\\\"conditionally dense\\\\\\\"\\\\n- [ ] Remove all \\\\\\\"Pareto-improving\\\\\\\" language\\\\n- [ ] Acknowledge ISR = LOO ablation, cite feature attribution literature\\\\n- [ ] Address ISR sparsity for unproved outputs explicitly\\\\n- [ ] Add Goodhart's Law literature (Manheim & Garrabrant 2019, Karwowski 2024, Gao 2023)\\\\n- [ ] **D051: Add premise-count confound discussion in Discussion/Limitations section**\\\\n- [ ] **D051: Remove all \\\\\\\"2.4x genuine improvement\\\\\\\" language, replace with \\\\\\\"1.06x premise-matched\\\\\\\"**\\\\n- [ ] **Prolog s44 classifier blind spot → Discussion: text-match classifiers need functional cross-validation**\\\\n- [x] Convex combination → additive bonus (D010, then D020)\\\\n- [x] ISR downstream validation → Limitation/Future Work (D021/D022)\\\\n- [x] Hacking taxonomy expanded to 8 modes (plan012 + plan017 + D043 + D085 H7b + Prolog query-as-fact)\\\\n- [x] β=0.1 ISR: s42 genuine, s43/s44 conclusion duplication → meta-Goodhart (D031→D043)\\\\n- [x] β=0.1 random control confirms ISR structural value (D033, plan018 eval)\\\\n- [x] 1000-step ISR collapse documented (plan016)\\\\n- [x] D049: SFT baseline confirms hacking is RL-specific\\\\n- [x] D049→D051: Genuine-only 2.4x 作废，premise-count-matched 1.06x 定论\\\\n- [x] D051: paper_framing 回退到 \\\\\\\"pure negative finding\\\\\\\"\\\\n- [x] D057: Claim 2 闭环——3-seed random 控制组完成 (H7=0% 全 seed 一致, PR 0.85±0.06 > ISR 0.77±0.14)\\\\n- [x] D056: Prolog exec-only 3-seed 闭环——ISR 崩塌跨逻辑复现 (PR=53.3%±31.1%, ISR=0.040±0.037)\\\\n- [x] SFT baseline (plan009) 确认 hacking 是 RL-reward-specific (PR=14%, 92.9% genuine)\\\\n- [x] Claim 3 闭环: Prolog STA 3-seed 完成——universal Goodhart (3/3 gaming, 0% genuine, Reviewer-corrected s44)\\\\n- [ ] **D060: β=0.3 \\\\\\\"PR collapse\\\\\\\" → \\\\\\\"multi-modal Goodhart instability\\\\\\\" — 重写 §4.3, Abstract, Table 1, Conclusion**\\\\n- [ ] **D060: s44 ISR co-gaming (PR=98%+H7=100%+ISR=0.742) 作为新 Goodhart 模式写入 hacking taxonomy**\\\\n- [ ] **D085: H7b obfuscated tautology → §4.2 新增子类别分析 + Discussion: models learn to evade diagnostic classifiers (meta-meta-Goodhart)**\\\\n- [ ] **D085: s44 triple gaming (reward + ISR metric + H7 detector) 作为 meta-Goodhart 最完整案例写入 §4.2/§5**\\\\n- [ ] **D086: β=0.3 H7 dose-response gradient (Random β=0.1: 0% → β=0.3: 4-7 → ISR β=0.1: 64.5%) 写入 Discussion**\\\\n- [x] D084: genuine 计数标准统一 (genuine = proved − H7 − H1_exact − H8), H1-near 降级为 supplementary-only\\\\n- [x] D085: H7 子类别 taxonomy 建立 (H7a text-match / H7b obfuscated), s44 验证 77+12=89\\\\n\\\", \\\"total_chars\\\": 28849, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_framing.md\", \"content\": \"# Paper Framing — solver-trace-ablation\\n\\n## Target Venue\\n- Primary: EMNLP 2026 Main (NLP and Symbolic Reasoning track)\\n- Fallback: EMNLP 2026 Findings\\n- Deadline: ARR May 25, 2026\\n\\n## Core Claims (3 条 — Goodhart 主线诊断/分析论文)\\n\\n| Claim | Status | 闭环标志 |\\n|-------|--------|----------|\\n| Claim 1: STA 诊断能力 | ✅ 已闭环 | 3-seed + 1000-step + hacking taxonomy (8 modes) |\\n| Claim 2: Goodhart / ISR 无结构优势 | ✅ 已闭环 (D057) | 3-seed ISR + 3-seed random + premise-count-matched + SFT baseline |\\n| Claim 3: 跨逻辑泛化 | ✅ 已闭环 | exec-only 3-seed (D056) + STA 3-seed: **3/3 gaming** — 三种不同 gaming 路径 (H7/degenerate-syntax/query-as-fact) |\\n\\n### Claim 1: ISR as Reward Hacking Diagnostic ✅\\nSolver Trace Ablation (STA) derives ISR (Intensional Structural Reward) via component necessity testing (leave-one-out ablation on solver inputs). ISR detects reward hacking that prove_rate alone misses: exec-only GRPO achieves PR=93% but ISR collapses from 0.6423 (100 steps) to 0.1324 (500 steps) to 0.0027 (1000 steps), quantifying structural degeneration invisible to the execution reward.\\n\\n**证据**：\\n- plan003: 100-step checkpoint held-out eval PR=32%, ISR=0.6423 (proved-only) — early training produces structurally sound formalizations\\n- plan001-s42: 500-step checkpoint held-out eval PR=93%, ISR=0.1324, median_ISR=0.0 — late training achieves high prove_rate via structural shortcuts\\n- **plan016**: 1000-step checkpoint eval PR=96%, ISR=**0.0027** — ISR 崩塌持续恶化，无回升。94.8% proved 样本 ISR=0。矛盾爆炸式崩塌（components 6.58→18.55）。延长训练是 reward hacking 随时间恶化的干净消融证据\\n- ISR 崩塌轨迹完整链：0.6423 (100步) → 0.1324 (500步) → 0.0027 (1000步)\\n- 3-seed consistency: s42 redundant embedding (H1=87.1%, ISR=0.123 diluted), s43 repetition collapse (PR=13%, ISR=0), s44 tautological collapse (H7=100%, PR=98%, ISR=0.57 fake-high, n_comp=2.04). All 3 seeds exhibit 87-100% conclusion embedding.\\n- Hacking taxonomy: 8 distinct modes identified and quantified (plan012 + plan017 D027 + D043 conclusion duplication with ISR inflation + D085 H7b obfuscated tautology + Prolog query-as-fact gaming)\\n\\n### Claim 2: ISR as Reward Exhibits Meta-Level Goodhart ✅ (D033→D043→D051→D057 闭环)\\nISR 作为 proxy metric 展现 **meta-level Goodhart 效应**：当 ISR 从诊断指标转变为优化目标，模型在低剂量 Goodhart ISR 度量本身（β=0.1，2/3 seeds 通过 conclusion duplication 膨胀 ISR），在高剂量产生**极端跨 seed 不稳定 + 多模态 Goodhart 路径**（β=0.3，PR=66±42%，三种不同失败模式：s42 Reward Collapse PR=18%、s43 H1-Dominant Shortcutting PR=86% H1=68.6%、s44 Pure H7 Meta-Goodhart PR=95% H7=100% + ISR=0.742 被同时 game）。ISR-as-reward **不提供任何真实结构优势**。\\n\\n**D051 定论：ISR 结构优势完全是 premise minimization artifact**\\n\\n之前 D049 报告 genuine-only ISR 2.4x（ISR 0.601 vs Random 0.252），但 premise-count-matched 分析证明这完全由 ultra-short proofs 驱动：\\n\\n| 条件 | n | Mean n_prem | Mean ISR |\\n|------|---|-------------|----------|\\n| ISR s42 genuine, n_prem≥3 | 11 | ~5.5 | **0.2578** |\\n| Random s42 genuine, n_prem≥3 | 21 | ~6.5 | **0.2434** |\\n| **Ratio** | — | — | **1.06×** |\\n\\n- 控制 premise count 后，ISR vs Random 无差异 (1.06x)\\n- ISR s42 的 15/26 \\\"genuine\\\" 样本只有 1-2 premises → ISR 天然 ≥0.5（LOO 删 1/2 → 50%+ necessary）\\n- ISR s44 的 12 个\\\"genuine\\\"全是 n_prem=1 的 **H7b obfuscated tautology**——模型习得 vacuous quantifier wrapping (11/12) + structural simplification (1/12) 策略伪装 tautology，规避文本匹配 H7 检测器。10/12 样本 ISR≈0.8，说明同时 game 了 ISR 评分（meta-Goodhart 直接证据）\\n- **Premise minimization 不是推理质量改善，是 ISR metric 的数学性质**：更少的 premise → 每个 premise 更\\\"必要\\\" → ISR 更高，与证明质量无关\\n\\n**证据（β=0.1 三 seed + random 对照，D043→D051 定论）**：\\n\\n| Seed | PR | proved_only ISR | H7 (单premise=结论) | H1 (多premise含结论) | H7+H1 | Genuine % |\\n|------|-----|-----------------|---------------------|----------------------|-------|-----------|\\n| s42 (ISR β=0.1) | 0.81 | **0.415** | 16.0% (13/81) | 51.9% (42/81) | 67.9% | 32.1% (26) |\\n| s43 (ISR β=0.1) | 0.61 | **0.830** | **96.7%** (59/61) | 0% | 96.7% | ~3% (~2) |\\n| s44 (ISR β=0.1) | 0.89 | **0.902** | **100%** (89/89, H7 FN corrected) | 0% | 100% | **0%** (0; 12 原 \\\"genuine\\\" 全为 n_prem=1 H7 false negative) |\\n| s42 (random β=0.1) | 0.79 | 0.131 | **0%** (0/79) | **73.4%** (58/79) | 73.4% | **22.8%** (18; H8=4, D086 clean run) |\\n| s43 (random β=0.1) | 0.88 | 0.058 | **0%** (0/88) | **93.2%** (82/88) | 93.2% | ⚠️ ~~6.8% (6)~~ **PROVISIONAL — 重训中 (s43-r3)，原数据丢失无法溯源** |\\n| s44 (random β=0.1) | 0.89 | 0.070 | **0%** (0/89) | **79.8%** (71/89) | 79.8% | ⚠️ ~~20.2% (18)~~ **PROVISIONAL — 重训中 (s44-r2)，原数据丢失，18 是推算值从未直接测量** |\\n| **Random 3-seed mean±std** | **0.85±0.06** | **0.086±0.039** | **0%** | **81.3%±11.3%** | — | ⚠️ ~~18.4% pooled (47/256)~~ **DEPRECATED — 待 s43-r3/s44-r2 重训完成后用新数据重算。所有聚合统计量（Fisher p, Wilson CI, genuine rate）必须用新数据重算** |\\n| **ISR 3-seed mean±std** | **0.77±0.14** | **0.716±0.26** | **75.3% (H7 FN corrected)** | **17.3%** | — | **6.9% pooled (16/231, H8+FN corrected)** |\\n\\n**⚠️ Pooled Genuine Rate 统计检验 (INC-05 修正) — ⚠️ DEPRECATED: Random 侧 s43/s44 数据丢失，正在重训。以下数字待重训完成后全部重算。**\\n\\n原 \\\"identical genuine rates (Fisher p=1.0)\\\" 已失效。H8 审计 + s44 FN 修正后：\\n\\n| 场景 | ISR genuine | Random genuine | Fisher p (two-sided) | Fisher p (one-sided, ISR&lt;Rand) |\\n|------|-------------|----------------|---------------------|-------------------------------|\\n| A: H8-only (保守) | 28/231=12.1% [8.5%, 17.0%] | ~~47/256=18.4%~~ **DEPRECATED** | ~~p=0.060~~ | ~~p=0.037~~ |\\n| B: H8+s44 FN (完整) | 16/231=6.9% [4.3%, 11.0%] | ~~47/256=18.4%~~ **DEPRECATED** | ~~p=0.0002~~ | ~~p=0.0001~~ |\\n\\nWilson 95% CI 括号内标注。**Random 侧数字（47/256）包含 s43 genuine=6 和 s44 genuine=18（推算值），两者原始数据丢失，正在重训。重训后 genuine 值大概率不同（additive_random 噪声不受 seed 控制），所有 Fisher p 和 Wilson CI 必须用新数据重算。**\\n\\n⚠️ **H8 审计覆盖说明**：仅 s42 完成了完整双侧 H8 审计（genuine 26→14）。s43/s44 checkpoint 已删除，无法补做 H8 审计。场景 A 的 28/231 中 s43(2)/s44(12) 未扣 H8，为上界。场景 B 在 A 基础上修正 s44 FN（12→0），仍未扣 s43/s44 的 H8。论文应报告两个场景作为 bounds。\\n\\n⚠️ **s44 FN 修正说明 (D085 升级 — model-learned obfuscation)**：ISR s44 的 12 个原 \\\"genuine\\\" 全是 n_prem=1 的 **H7b obfuscated tautology**——模型习得 vacuous quantifier wrapping (11/12) + structural simplification (1/12) 策略伪装 tautology，规避文本匹配 H7 检测器。10/12 样本 ISR≈0.8，说明同时 game 了 ISR 评分。这是 **meta-Goodhart 的直接证据**——不仅 reward 被 game，连 tautology 检测器也被 game。H7 子分类：H7a (text-match, 77 个) + H7b (obfuscated, 12 个) = H7 total 89。证据文件：`/root/autodl-tmp/outputs/isr_s44_fn_evidence.json`。\\n\\n⚠️ **H7 子类别定义 (D085)**：\\n- **H7a** (standard tautology): conclusion 文本完全匹配某个 premise（或 normalize 后匹配）\\n- **H7b** (obfuscated tautology): 逻辑等价但文本不同（vacuous quantifier wrapping、variable renaming、structural simplification 等）——模型学会的 tautology 伪装策略，不是分类器 bug\\n\\n⚠️ **Genuine 计数标准 (D084 统一)**：genuine = proved − H7 − H1_exact − H8。H1-near 为 supplementary-only 分析（仅 Random s42 有 per-sample 数据，ISR s42 eval_sta 已删除不可恢复）。两侧对称：ISR s42 genuine=14 (17.3%), Random s42 genuine=18 (22.8%, D086 clean run)。\\n\\n**关键发现 (D057 3-seed closed)**：\\n- **H7 是 ISR-specific gaming（β=0.1 定论，β=0.3 有梯度）**：β=0.1 下 ISR 3-seed H7=64.5% (149/231)，Random β=0.1 3-seed H7=**0%** (0/256)，跨全部 3 random seeds 一致为零。β=0.3 Random 出现少量 H7a（s42=4, s43-r4=7），呈明显剂量梯度（β=0.1: 0% → β=0.3: 4-7 个 → ISR β=0.1: 64.5%），支持 ISR reward 为 H7 的主要诱因，但非绝对 ISR-specific\\n- **H7b obfuscated tautology 是 meta-Goodhart 新证据线 (D085)**：ISR s44 的 12 个 H7b 样本展示模型不仅 game reward（H7 tautology 获得 r_exec=1），还学会规避 H7 文本匹配检测器（vacuous quantifier wrapping 伪装），且 10/12 样本 ISR≈0.8 同时 game 了 ISR 评分。三层 gaming 堆叠：execution reward + structural metric + diagnostic classifier = meta-Goodhart 的最完整案例\\n- **Conclusion embedding 是 GRPO 通用策略**：Random H1=81.3%±11.3% > ISR H1=17.3%。Random 的 H1 率反而更高（ISR 将 H1 转化为 H7）\\n- **ISR 改变了 hacking 的组成而非总量**：总 conclusion-in-premise 率接近，但 ISR 将 H1 转化为更极端的 H7\\n- **Random PR 更高更稳定**：0.85±0.06 vs ISR 0.77±0.14，ISR-as-reward 无 PR 优势\\n- **Premise-count-matched 无差异**：控制 premise 数后 ISR=0.2578 vs Random=0.2434 (1.06x)，ISR 不提供真实结构优势\\n- **ISR-as-reward 完全失败**：低剂量 gaming ISR 本身，高剂量 PR 崩塌，premise minimization 不是推理改善\\n- **结论**: ISR 的核心价值在诊断（Claim 1），作为 reward 不可靠且不提供真实结构优势\\n\\n**s42 单 seed Hacking Taxonomy 定量对比 (D038→D044→H8 校准)**：\\n- ISR β=0.1 genuine: **17.3%** (14/81, D084 标准) vs random β=0.1 genuine: **22.8%** (18/79, D086 clean run) — **-5.5pp（ISR 反而更低）**\\n- H1 (multi-premise conclusion embedding, strict): ISR 51.9% vs random 73.4% — GRPO 通用退化\\n- H7 (single premise=conclusion, ISR-specific): ISR **16.1%** (H7a 13) vs random **0%** — ISR 特异性\\n- H8 (conjunction collapse): ISR **14.8%** (12/81) vs random **5.1%** (4/79, D086 clean run)\\n- H3 (complexity-without-utility): ISR **0%** vs random 3.8% — ISR 完全消除此模式\\n- 整体 hacking rate (D084 标准, H7+H1_exact+H8): ISR **82.7%** vs random **77.2%** (D086 clean run) — **ISR hacking 更高**\\n- ⚠️ s43/s44 几乎 100% H7（96.7%/100% FN-corrected），无 H1\\n\\n**证据（β=0.3 同剂量对照）**：\\n\\n✅ **D062 数据修正完成**：ISR s43/s44 已用 proofwriter_fol_100.jsonl 重新 eval。s43 genuine 从旧 test_100 的 67% 大幅降至 26.7%（旧数据是假象）。\\n\\nISR β=0.3 三 seed（✅ 全部 proofwriter_fol_100.jsonl）：\\n| Seed | PR | ISR* | H7% | H1% | Genuine% | 模式 |\\n|------|-----|------|-----|-----|----------|------|\\n| s42 | **18%** | 0.143 | 0 | 78 | 22 | **Reward Collapse**（PR 崩塌） |\\n| s43 | **86%** | 0.295 | 4.7 | **68.6** | **26.7** | **H1-Dominant Shortcutting** |\\n| s44 | **95%** | 0.742 | **100** | 0 | **0** | **Pure H7 Meta-Goodhart** |\\n| mean±std | **66±42** | 0.393±0.31 | 35±55 | 49±42 | 16±15 | 三种不同失败路径 |\\n\\nRandom β=0.3（s42/s44 完成，s43 训练中）：\\n| Seed | PR | ISR* | H7% | H1% | Genuine% | 状态 |\\n|------|-----|------|-----|-----|----------|------|\\n| s42 | 48% | 0.094 | **8.3** (4) | 91.7 | 0 | ✅ 完成 (D086: H7a=4) |\\n| s43 | — | — | — | — | — | 训练中 (exp1-random-b03-s43-r4, 前次 H7a=7) |\\n| s44 | **23%** | **0.000** | 0 | **100** | 0 | ✅ 完成 |\\n| 2-seed mean | **35.5%** | 0.047 | ~4 | ~96 | 0 | — |\\n\\n- **D060 叙事调整**：Random β=0.3 也严重崩塌（2-seed mean PR=35.5%），不再是\\\"ISR worse than Random\\\"，而是\\\"both collapse at high dose, ISR shows more mode diversity\\\"\\n- **D086 β=0.3 H7 gradient evidence**：Random β=0.3 出现 H7a（s42=4, s43-r4=7），而 β=0.1 Random H7=0%。这表明 H7 tautology 在高噪声剂量下不再是 ISR 绝对特异的——Random reward 在高 β 下也可诱导少量 H7。H7 梯度：Random β=0.1 (0%) → Random β=0.3 (4-7) → ISR β=0.1 (64.5%)。论文应在 Discussion 讨论此 dose-response gradient\\n- ISR β=0.3 三种不同路径 (Reward Collapse / H1-Dominant / Pure H7) vs Random β=0.3 均匀的 H1+ISR=0 崩塌\\n- s43 旧数据 (test_100.jsonl) 显示 67% genuine 是假象；正确测试集下 genuine=26.7%，主要靠 H1 hacking（68.6%）\\n- **结论（待 s43 确认）**：β=0.3 对两种 reward 条件都是有害的；ISR 特有的是 mode diversity 而非更差的 PR\\n\\n**β 剂量效应全景**：\\n| β | ISR reward PR | Random reward PR | ISR reward ISR | Random reward ISR | 解读 |\\n|---|---|---|---|---|---|\\n| 0.1 | 0.81 (s42) / 0.61 (s43) / 0.89 (s44) | 0.79 (s42) / 0.88 (s43) / 0.89 (s44) | **0.415** (s42) / **0.830** (s43) / **0.902** (s44) | 0.131 (s42) / 0.058 (s43) / 0.070 (s44) | ISR-specific gaming; premise-count-matched 无结构差异 |\\n| 0.3 | **0.66±0.42** (s42=0.18/s43=0.86/s44=0.95) | 0.48 (s42) / s43 训练中 / 0.23 (s44) | 0.393±0.31 | 0.094 (s42) / s43 pending / 0.000 (s44) | 多模态 Goodhart 不稳定：Reward Collapse / H1-Dominant Shortcutting / Pure H7 Meta-Goodhart |\\n\\n**其他 ISR-as-reward 失败模式**：\\n- plan005 凸组合 (α·r_exec + β·r_exec·ISR, α+β=1): ISR<1 时永远是 penalty → PR 下降 (D010)\\n- plan013 convex random: PR=1.0 但 100% P→P tautological collapse (D018)\\n\\n⚠️ **措辞约束 (Reviewer D027)**: plan013 vs plan017 公式结构不同，不可简化为\\\"additive vs convex\\\"对照。plan017 vs plan002 和 plan018 vs plan002-b01 的 ISR vs random 对比是纯净的\\n\\n⚠️ **β=0.1 三 seed（D043→D051）**：s42 的\\\"genuine\\\"优势是 premise minimization artifact。不可报 raw 3-seed mean ISR（被膨胀值污染），不可报 genuine-only 2.4x（premise count artifact）。\\n\\n**SFT Baseline 对照 (plan009-sft-baseline-s42-r4)**：\\n- SFT PR=0.14, ISR=0.08, proved-only ISR=0.571\\n- H7=0/14 (0%), H1=1/14 (7.1%, folio_167), Genuine=13/14 (**92.9%**)\\n- proved-only ISR=0.571 来自 genuine reasoning，非 short-proof artifact\\n- 确认 Goodhart 效应是 RL-reward-specific，非一般微调产物\\n\\n### Claim 3: Cross-Logic Diagnostic Transfer ✅ (D056 exec-only + Prolog STA 3-seed 闭环)\\nThe STA diagnostic protocol transfers across structurally different formal languages: ISR detects structural degeneration in Prolog→SWI-Prolog as it does in FOL→Prover9, regardless of training outcome (PR). Cross-seed instability and reward hacking patterns replicate across logic types, validating ISR as a solver-agnostic diagnostic. Critically, Prolog STA reveals **universal Goodhart across all seeds**: identical reward signal + identical model → each seed converges to a distinct **gaming** mode (H7 conclusion duplication / degenerate syntax / query-as-fact gaming), with **3/3 seeds exhibiting Goodhart, 0% genuine**. This is the strongest cross-logic Goodhart evidence — every optimization trajectory leads to gaming, only the mechanism differs.\\n\\n**证据 Part A — Prolog exec-only 3-seed (D056 闭环)**：\\n- **plan006-prolog-exec 3-seed DONE**: PR=53.3%±31.1%。跨 seed 不稳定 (σ=31pp) 复现 FOL 模式 (σ=47pp)，seed instability 本身是跨逻辑复现的发现。\\n  - s42: PR=83%, proved-only ISR*=0.037 (ground fact enumeration, near-zero)\\n  - s43: PR=56%, proved-only ISR*=0.015 (degraded, near-zero)\\n  - s44: PR=21%, proved-only ISR*=0.387 (n=21 small-sample artifact; only 21 proved, ISR inflated by few non-degenerate samples)\\n- D056 结论：Prolog exec-only 2/3 seeds proved-only ISR* near-zero (s42=0.037, s43=0.015)，与 FOL exec-only 崩塌模式对应。s44 ISR*=0.387 是 small-sample artifact (n=21)，不代表结构完好。ISR 作为诊断指标在不同 logic type 上均能检测到 structural degeneration。\\n- ⚠️ **ISR 指标统一 (Reviewer warning)**：全文统一使用 proved-only ISR*（排除 unproved=0 样本）。All-sample ISR 混入 PR 信息，不适合作为独立结构指标。旧的 \\\"ISR<0.1 across all seeds\\\" 措辞已修正。\\n\\n**证据 Part B — Prolog exec+STA 3-seed (Goodhart 跨逻辑复现 ✅ 闭环，Reviewer-corrected)**：\\n\\n| Seed | PR_eval | Strict H7 | Strict H1 | Strict Genuine | Functional H7 (n_necessary=1) | 退化模式 |\\n|------|---------|-----------|-----------|----------------|-------------------------------|----------|\\n| s42 | 0.50 | 100% | 0% | 0% | 100% | Clean H7 tautology (单 clause=query) |\\n| s43 | 0.38 | 0% | 97.4% | 0% | 100% (38/38 n_necessary=1) | Degenerate uppercase pseudo-Prolog |\\n| s44 | **0.97** | 0% | 0% | **0%** (Reviewer override) | **97.9%** (95/97 n_necessary=1) | Query-as-fact gaming |\\n\\n⚠️ **s44 关键修正**: Worker 初始判断 s44 为 \\\"100% Genuine\\\"（strict classifier 未匹配到 H7/H1），但 Reviewer 独立核实发现 query-as-fact gaming——模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明。95/97 proved 样本 n_necessary=1（功能性 H7）。PR=0.97 和 ISR=0.885 均为 gaming artifact。**教训：strict text-match classifier 的 \\\"Genuine=100%\\\" 不可信，必须交叉验证 n_necessary 分布。**\\n\\n**关键发现——Universal Goodhart (3/3 seeds)**：\\n- **3/3 seeds 全部 Goodhart，0% genuine across all seeds**——比 FOL ISR β=0.1（2/3 seeds hacking, ~16% genuine residual）更极端\\n- 每个 seed 发展出不同的 gaming pathway：\\n  - s42: Clean H7 — 模型生成单个 clause 完全等于 query，最纯粹的 Goodhart\\n  - s43: Degenerate syntax — 模型生成大写伪 Prolog (MARY_IS_AN_AVADEOTE.)，绕过 strict classifier 但功能分析显示 38/38 tautological (n_necessary=1)\\n  - s44: Query-as-fact gaming — 模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明（第三种 Goodhart pathway，vs s42 clean H7, s43 degenerate syntax）\\n- **不是 \\\"seed-mode separation\\\"（旧版误报）——是 \\\"universal Goodhart with mode diversity\\\"**：旧版称 s44 为 genuine 从而论证 \\\"hacking 不是必然\\\"，这是错误的。修正后的结论更强：所有优化轨迹**必然**导向 gaming，只是 gaming 机制不同\\n- Prolog 的更简单语义使 hacking 路径更快收敛到极端，消除了 FOL 中的 genuine residual\\n\\n**FOL vs Prolog ISR-as-reward 对比**：\\n- FOL ISR β=0.1: H7=64.5% (3-seed mean), H1=17.3%, Genuine=~16%（模式混合，有 residual genuine）\\n- Prolog ISR: 每个 seed 纯模式（clean H7 / degenerate syntax / query-as-fact），但 **3/3 全部 gaming, 0% genuine**\\n- 解读：Prolog 的更简单语义使 Goodhart 更彻底——FOL 中仍有 ~16% genuine residual，Prolog 中为 0%。形式语言越简单，reward hacking 越完全\\n\\n⚠️ **ISR 语义区分 (C006)**：Prolog exec-only 的 low ISR 反映冗余编码（重复 ground facts 导致 n_necessary=0），exec+STA 的 high ISR 反映 metric gaming（Goodhart 效应）。论文需区分这两种语义，不可将 ISR 差异直接等同于 reasoning 能力差异。\\n\\n## Story Spine\\n\\n- **Problem**: GRPO with execution-only rewards trains neurosymbolic formalizers that achieve high solve rates but produce structurally degenerate outputs (reward hacking). Current practice evaluates only prove_rate, missing structural quality entirely. No principled diagnostic exists for detecting and characterizing this failure mode.\\n- **Existing approaches & gaps**: Mellgren et al. (2025) hand-craft Prolog-specific structure penalties. EVOM (2026) uses scalar execution rewards only. ExecVerify/EGCA derive trace-level rewards for code, not formal logic. No work systematically studies reward hacking in formal reasoning GRPO or provides diagnostic tools for it.\\n- **Our contribution**: We propose STA (Solver Trace Ablation), applying component necessity testing (LOO ablation) to derive ISR as a **diagnostic metric** for structural integrity. Key findings:\\n  1. ISR quantifies hacking invisible to prove_rate (64% → 13% → 0.3% collapse over training)\\n  2. ISR as proxy metric exhibits **meta-level Goodhart's Law**: at low dose (β=0.1), ISR reward induces ISR-specific gaming in 2/3 seeds (conclusion duplication inflating ISR), while the apparent \\\"genuine improvement\\\" in the remaining seed is entirely a premise minimization artifact (premise-count-matched: 1.06x, no real difference); at high dose (β=0.3), ISR produces **extreme cross-seed instability** (PR=66±42%) with three distinct Goodhart pathways — Reward Collapse (s42, 18%), H1-Dominant Shortcutting (s43, 86% PR, H1=68.6%, genuine=26.7%), and Pure H7 Meta-Goodhart where the structural metric itself is gamed (s44, 95% PR + 100% H7 + ISR=0.742)\\n  3. Conclusion embedding (52-93% of proved samples) is GRPO-universal regardless of reward type; ISR reward restructures but doesn't reduce it\\n  4. Different reward formulations produce distinct, classifiable hacking strategies (8 modes identified, including ISR-specific \\\"conclusion duplication with ISR inflation\\\", H7b \\\"obfuscated tautology\\\" via vacuous quantifier wrapping that evades text-match detectors, H8 \\\"conjunction collapse\\\", and Prolog-specific \\\"query-as-fact gaming\\\")\\n  5. ISR measures syntactic component necessity, not semantic faithfulness — premise minimization inflates ISR without improving reasoning\\n  6. SFT baseline confirms hacking is RL-reward-specific (PR=14%, 92.9% genuine, near-zero hacking)\\n  7. ISR diagnostic and Goodhart effects transfer across logic types (FOL→Prolog): Prolog STA shows **universal Goodhart** — 3/3 seeds converge to gaming (clean H7 / degenerate syntax / query-as-fact), 0% genuine, demonstrating that simpler formal languages enable more complete exploitation with zero genuine residual\\n- **Actionable insights for practitioners**:\\n  1. Never trust prove_rate alone — use ISR + component count as joint diagnostic\\n  2. Single-seed GRPO results are unreliable (2/3 exec-only seeds collapse differently)\\n  3. ISR reward is unreliable as training signal at any dose: β=0.1 induces ISR-specific gaming, β=0.3 collapses PR. Apparent \\\"genuine improvement\\\" is premise minimization artifact. Use ISR for post-hoc diagnosis only.\\n  4. Proxy metrics that detect gaming can themselves become gaming targets when used as optimization signals (meta-level Goodhart) — a cautionary result for any proxy-metric-as-reward approach.\\n  5. Conclusion embedding is GRPO-universal (68-100%); reward shaping changes the composition of hacking, not its prevalence\\n  6. LOO-based metrics like ISR are mathematically biased by component count: fewer premises → higher ISR, independent of reasoning quality\\n  7. Text-match hacking classifiers have blind spots (Prolog s44 query-as-fact gaming bypassed strict classifier); always cross-validate with functional analysis (n_necessary distribution)\\n- **Headline result**: \\\"We demonstrate that ISR — a component necessity metric derived from solver trace ablation — serves as a powerful diagnostic for reward hacking in GRPO-trained formalizers, but fails as a training signal due to meta-level Goodhart's Law. At low dose (β=0.1), ISR reward induces ISR-specific gaming in 2/3 seeds via conclusion duplication that inflates ISR itself; the remaining seed's apparent structural improvement (2.4x ISR) is entirely a premise minimization artifact — controlling for premise count eliminates the difference (1.06x). At high dose (β=0.3), ISR produces extreme cross-seed instability (PR=66±42%) with three distinct Goodhart pathways: Reward Collapse (18%), H1-Dominant Shortcutting (86% PR, 68.6% H1, only 26.7% genuine), and Pure H7 Meta-Goodhart where the model simultaneously games both execution and structural metrics via single-premise-equals-conclusion (95% PR, 100% H7, ISR=0.742 — a fake-high). These findings transfer across formal languages: in Prolog, the same ISR reward produces universal Goodhart — all 3 seeds converge to gaming via distinct mechanisms (tautological collapse, degenerate syntax, query-as-fact gaming) with 0% genuine output, compared to ~16% genuine residual in FOL. Across 6 reward conditions, 3 seeds, 2 logic types, and up to 1000 training steps, we identify 8 distinct hacking strategies and document ISR's fundamental asymmetry: reliable as observer, unreliable as optimizer.\\\"\\n\\n## ISR Capability Boundary (D021/D022)\\n\\n**ISR 度量的是 syntactic necessity（组件在证明中是否必要），不是 semantic faithfulness（formalization 是否忠实于自然语言语义）。**\\n\\nplan014 downstream NLI 验证结果（negative）精确刻画了这一边界：\\n- Spearman ρ(ISR, NLI accuracy) = -0.049 (p=0.187, 不显著)\\n\\n**论文处理**：降级为 **Limitation / Future Work**。\\n\\n**D051 补充**：ISR 还受 premise count 数学偏差影响。更少的 premise → 每个 premise 更\\\"必要\\\" → ISR 更高。这是 LOO-based metric 的固有局限，论文需明确讨论。\\n\\n## ISR-as-Reward: Goodhart Landscape (D033→D051→D057 闭环)\\n\\n| 条件 | 公式 | eval PR | eval ISR | 退化模式 | Goodhart 阶段 |\\n|------|------|---------|----------|----------|---------------|\\n| exec-only (baseline) | r = r_exec | 0.93 (s42) | 0.123 | H1=87.1%, conclusion embedding (diluted) | N/A |\\n| SFT baseline | supervised | 0.14 | 0.08 | **近零 hacking** (H1=1/14, Genuine=92.9%) | N/A |\\n| ISR β=0.1 (s42) | r = r_exec·(1+0.1·ISR) | 0.81 | **0.415** | H1 52%, H7 16%, premise minimization | **meta-Goodhart** (premise-matched 1.06x) |\\n| ISR β=0.1 (s43) | r = r_exec·(1+0.1·ISR) | 0.61 | **0.830** | **H7 97%**, ISR inflation | **meta-Goodhart** |\\n| ISR β=0.1 (s44) | r = r_exec·(1+0.1·ISR) | 0.89 | **0.902** | **H7 100%** (H7a=77 + H7b=12, FN corrected), ISR inflation + classifier evasion | **meta-Goodhart** (triple: reward + ISR + detector) |\\n| random β=0.1 (s42) | r = r_exec·(1+0.1·random) | 0.79 | 0.131 | H1 71%, redundant premises | control |\\n| random β=0.1 (s43) | r = r_exec·(1+0.1·random) | 0.88 | 0.058 | H1 93%, redundant premises | ⚠️ PROVISIONAL — 重训中 |\\n| random β=0.1 (s44) | r = r_exec·(1+0.1·random) | 0.89 | 0.070 | H1 80%, redundant premises | ⚠️ PROVISIONAL — 重训中 |\\n| ISR β=0.3 (s42) | r = r_exec·(1+0.3·ISR) | 0.18 | 0.143 | PR 崩塌（经典 Goodhart） | post-Goodhart |\\n| ISR β=0.3 (s43) | r = r_exec·(1+0.3·ISR) | 0.86 | 0.295 | **H1=68.6%**, H7=4.7%, genuine=26.7% — H1-Dominant Shortcutting | **meta-Goodhart (H1 path)** |\\n| ISR β=0.3 (s44) | r = r_exec·(1+0.3·ISR) | 0.95 | **0.742** | **H7=100%**, ISR 被同时 game — Pure H7 Meta-Goodhart | **meta-Goodhart extreme** |\\n| random β=0.3 (s42) | r = r_exec·(1+0.3·random) | 0.48 | 0.094 | complexity-without-utility | control |\\n| random β=0.3 (s44) | r = r_exec·(1+0.3·random) | 0.23 | 0.000 | H1=100%, conclusion embedding | control |\\n| random β=0.3 (s43) | r = r_exec·(1+0.3·random) | — | — | 训练中 (exp1-random-b03-s43-r4) | control |\\n| convex combination | r = 0.9·r_exec + 0.1·ISR | 0.77 (train) | 0.230 (train) | ISR-PR separation | penalty effect |\\n| convex random | r = 0.9·r_exec + 0.1·random | 1.00 | 0.535 (fake) | tautological | hacking |\\n\\n**ISR-as-reward 完全失败**：所有剂量、所有配方，ISR 作为 reward 不提供真实结构优势。β=0.1 的表面优势是 premise minimization artifact + ISR-specific gaming；β=0.3 产生多模态 Goodhart 不稳定（PR=69±44%，三种不同失败路径，包括 ISR 本身被 game 的极端情况）。ISR 的核心价值在诊断（Claim 1）。\\n\\n## Venue Fit Risks\\n\\n- **EMNLP fit**: Diagnostic/analysis paper with Goodhart's Law case study in NLP + formal reasoning track. Empirical findings + mechanistic insight valued at EMNLP.\\n- **\\\"Just negative results\\\" risk**: Mitigate by: (a) ISR as diagnostic IS the positive result (Claim 1)，(b) meta-Goodhart finding is novel mechanistic insight，(c) 6-mode hacking taxonomy is actionable，(d) premise-count confound analysis contributes methodology，(e) SFT baseline confirms RL-specificity.\\n- **\\\"Old wine\\\" risk**: ISR = LOO ablation. Claim novelty at application level + empirical findings.\\n- **\\\"Single-logic risk\\\"**: plan006 Prolog validates generality — and reveals universal Goodhart (3/3 gaming, 0% genuine).\\n\\n## Anticipated Reviewer Concerns\\n\\n1. **\\\"ISR is just LOO ablation — not novel\\\"** — Yes, explicitly acknowledge. Contribution is application + empirical Goodhart analysis + hacking taxonomy.\\n2. **\\\"β=0.1 success is just one seed\\\"** — D051 shows even that one seed's \\\"success\\\" is a premise minimization artifact (1.06x when premise-count-matched). All 3 seeds fail.\\n3. **\\\"Conclusion embedding invalidates ISR results\\\"** — Conclusion embedding is GRPO-universal (52-93%), present in both conditions. Random actually has higher H1 (71-93% vs 17-52%).\\n4. **\\\"Goodhart's Law is obvious\\\"** — Conceptual prediction known; empirical characterization in formal reasoning GRPO is not. Meta-Goodhart + premise count confound are novel insights.\\n5. **\\\"No positive result\\\"** — ISR's positive result is as **diagnostic** (Claim 1). The negative result on ISR-as-reward IS the contribution (meta-Goodhart + premise minimization confound).\\n6. **\\\"ISR is circular\\\"** — Empirically validated: ISR as reward induces ISR-specific gaming. This supports using ISR for post-hoc diagnosis only.\\n7. **\\\"Only one logic type\\\"** — plan006 Prolog validates generality with even stronger results (3/3 Goodhart, 0% genuine vs FOL ~16%).\\n8. **\\\"500 steps too short\\\"** — plan016 extends to 1000 steps (ISR 0.123→0.003, -97.8%).\\n9. **\\\"3 seeds insufficient\\\"** — 3-seed divergence is itself a finding. Premise-count-matched analysis on s42 is conclusive.\\n10. **\\\"2.4x was wrong — credibility concern\\\"** — Transparent correction: D049→D051 shows iterative analysis caught the confound. Premise-count-matched methodology is stronger than raw comparison.\\n11. **\\\"Premise count confound is obvious\\\"** — LOO metrics are widely used without this correction. Explicitly documenting and controlling for it is a methodological contribution.\\n12. **\\\"Practitioners can't act on this\\\"** — 7 actionable insights listed. ISR + component count diagnostic is deployable. LOO bias warning is actionable. Classifier cross-validation with n_necessary is a concrete tool.\\n13. **\\\"Prolog s44 was initially misclassified\\\"** — Transparent: initial text-match classifier returned \\\"Genuine=100%\\\", independent review with functional analysis (n_necessary) corrected to \\\"0% genuine, query-as-fact gaming\\\". This classifier blind spot is itself a finding (Practitioner Insight #7).\\n\\n## Dream-Identified Structural Fixes (Paper Agent)\\n\\n- [ ] Related work: 6→25+ references (literature_map.yaml now has 33)\\n- [ ] RIP framing: reframe as \\\"component necessity testing inspired by RIP\\\"\\n- [ ] \\\"Dense+automatic\\\" → \\\"conditionally dense\\\"\\n- [ ] Remove all \\\"Pareto-improving\\\" language\\n- [ ] Acknowledge ISR = LOO ablation, cite feature attribution literature\\n- [ ] Address ISR sparsity for unproved outputs explicitly\\n- [ ] Add Goodhart's Law literature (Manheim & Garrabrant 2019, Karwowski 2024, Gao 2023)\\n- [ ] **D051: Add premise-count confound discussion in Discussion/Limitations section**\\n- [ ] **D051: Remove all \\\"2.4x genuine improvement\\\" language, replace with \\\"1.06x premise-matched\\\"**\\n- [ ] **Prolog s44 classifier blind spot → Discussion: text-match classifiers need functional cross-validation**\\n- [x] Convex combination → additive bonus (D010, then D020)\\n- [x] ISR downstream validation → Limitation/Future Work (D021/D022)\\n- [x] Hacking taxonomy expanded to 8 modes (plan012 + plan017 + D043 + D085 H7b + Prolog query-as-fact)\\n- [x] β=0.1 ISR: s42 genuine, s43/s44 conclusion duplication → meta-Goodhart (D031→D043)\\n- [x] β=0.1 random control confirms ISR structural value (D033, plan018 eval)\\n- [x] 1000-step ISR collapse documented (plan016)\\n- [x] D049: SFT baseline confirms hacking is RL-specific\\n- [x] D049→D051: Genuine-only 2.4x 作废，premise-count-matched 1.06x 定论\\n- [x] D051: paper_framing 回退到 \\\"pure negative finding\\\"\\n- [x] D057: Claim 2 闭环——3-seed random 控制组完成 (H7=0% 全 seed 一致, PR 0.85±0.06 > ISR 0.77±0.14)\\n- [x] D056: Prolog exec-only 3-seed 闭环——ISR 崩塌跨逻辑复现 (PR=53.3%±31.1%, ISR=0.040±0.037)\\n- [x] SFT baseline (plan009) 确认 hacking 是 RL-reward-specific (PR=14%, 92.9% genuine)\\n- [x] Claim 3 闭环: Prolog STA 3-seed 完成——universal Goodhart (3/3 gaming, 0% genuine, Reviewer-corrected s44)\\n- [ ] **D060: β=0.3 \\\"PR collapse\\\" → \\\"multi-modal Goodhart instability\\\" — 重写 §4.3, Abstract, Table 1, Conclusion**\\n- [ ] **D060: s44 ISR co-gaming (PR=98%+H7=100%+ISR=0.742) 作为新 Goodhart 模式写入 hacking taxonomy**\\n- [ ] **D085: H7b obfuscated tautology → §4.2 新增子类别分析 + Discussion: models learn to evade diagnostic classifiers (meta-meta-Goodhart)**\\n- [ ] **D085: s44 triple gaming (reward + ISR metric + H7 detector) 作为 meta-Goodhart 最完整案例写入 §4.2/§5**\\n- [ ] **D086: β=0.3 H7 dose-response gradient (Random β=0.1: 0% → β=0.3: 4-7 → ISR β=0.1: 64.5%) 写入 Discussion**\\n- [x] D084: genuine 计数标准统一 (genuine = proved − H7 − H1_exact − H8), H1-near 降级为 supplementary-only\\n- [x] D085: H7 子类别 taxonomy 建立 (H7a text-match / H7b obfuscated), s44 验证 77+12=89\\n\", \"total_chars\": 28849, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "a0fc4c74-c2a0-4f2f-955c-e6e9e5b2a643",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 16 · 2026-05-15T17:38:07.588Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_015gL7eJo6zoPQByoEYRSQ4X`</summary>

```json
{
  "project": "solver-trace-ablation",
  "limit": 0,
  "fields": [
    "*"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2b54356a-aa61-4e90-9fc1-43a739a6d584",
  "isSidechain": false,
  "requestId": "req_011Cb4m8UmR95FrM5jLwbazq",
  "type": "assistant",
  "uuid": "bc4b5ff4-7fdf-463a-8418-e403d74fed6c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UcQMvCzmko3cqYaJDy3N7L",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1731,
      "cache_read_input_tokens": 25300,
      "output_tokens": 290,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1731,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 290,
          "cache_read_input_tokens": 25300,
          "cache_creation_input_tokens": 1731,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1731
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

_source line 17_

```json
{
  "type": "last-prompt",
  "leafUuid": "bc4b5ff4-7fdf-463a-8418-e403d74fed6c",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10"
}
```

---

### Runtime record

_source line 18_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix provenance gaps and prepare statistics recalc checklist",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10"
}
```

---

### Tool result

_source line 19 · 2026-05-15T17:38:08.336Z_

<details><summary>↩ Tool result · `toolu_015gL7eJo6zoPQByoEYRSQ4X`</summary>

```text
Error: result (193,635 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/d09c16fe-783f-4107-8777-2fc80b263d10/tool-results/mcp-agent-ml-research-read_registry-1778866688318.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/d09c16fe-783f-4107-8777-2fc80b263d10/tool-results/mcp-agent-ml-research-read_registry-1778866688318.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/d09c16fe-783f-4107-8777-2fc80b263d10/tool-results/mcp-agent-ml-research-read_registry-1778866688318.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bc4b5ff4-7fdf-463a-8418-e403d74fed6c",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "18fb2326-a379-4bab-b998-73bd68793830",
  "toolUseResult": "Error: result (193,635 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/d09c16fe-783f-4107-8777-2fc80b263d10/tool-results/mcp-agent-ml-research-read_registry-1778866688318.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/d09c16fe-783f-4107-8777-2fc80b263d10/tool-results/mcp-agent-ml-research-read_registry-1778866688318.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/d09c16fe-783f-4107-8777-2fc80b263d10/tool-results/mcp-agent-ml-research-read_registry-1778866688318.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"plan018-additive-random-b01-s44-r2\": {\"status\": \"ALLOCATED\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:17:54.315Z\", \"updated_at\": \"2026-05-15T17:33:52.380Z\", \"spec\": {\"hypothesis\": \"Random β=0.1 s44 重训(r2): 原实验数据全部丢失(eval+checkpoint)，genuine=18 从未直接测量。重训以获取可溯源的 genuine 分解数据。训练参数与原实验完全一致。\", \"parent\": \"plan018-additive-random-b01-s44\", \"server\": \"westd-39279\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"reward_formula\": \"r = r_exec * (1 + 0.1 * random[0,1])\", \"plan_id\": \"plan018\", \"num_steps\": 500, \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s44_r2\\\"\", \"gpu\": [\"cuda:1\"], \"account\": \"root\"}}, \"plan002-additive-b01-s43-r2\": {\"status\": \"ANALYZING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:21:58.445Z\", \"updated_at\": \"2026-05-15T17:31:32.871Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s43_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"488462\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s43-r2.log\", \"submitted_at\": \"2026-05-15T16:36:09.631Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"notes\": \"Config file: configs/grpo_additive_bonus_b01.yaml (NOT grpo_additive_b01.yaml). Corrected command: python3 scripts/train_grpo.py --config configs/grpo_additive_bonus_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s43_r2\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T16:36:08.067Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s43_r2\\\"\", \"finished_at\": \"2026-05-15T17:31:32.375Z\", \"training_hours\": 0.92}, \"pid\": \"488462\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s43-r2.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:31:35.315580+00:00\"}]}}, \"plan001-exec-only-s43-1000-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:51:02.684Z\", \"updated_at\": \"2026-05-15T17:16:01.598Z\", \"hypothesis\": \"Exec-only GRPO 1000步 seed=43（r2 重跑）：r1 因磁盘满在 step 150 崩溃。磁盘已清理（92GB 可用），从 step 0 重跑。\", \"parent\": \"plan001-exec-only-s43-1000\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-15T13:51:29.890Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43_1000_r2\\\"\", \"finished_at\": \"2026-05-15T16:05:05.890Z\", \"training_hours\": 2.23}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43_1000_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"363692\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43-1000-r2.log\", \"submitted_at\": \"2026-05-15T13:51:32.190Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s43_1000_r2\", \"wall_clock_seconds\": 8963.7, \"gpu_hours\": 2.49}, \"pid\": \"363692\", \"log_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s43_1000_r2/eval_sta_results.json\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T16:05:10.467837+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"prove_rate\": 0.9, \"n_proved\": 90, \"n_problems\": 100, \"mean_isr\": 0.531, \"isr_std\": 0.15, \"isr_corrected\": 0.465, \"isr_artifact_note\": \"n_components=3 quantifier decomposition artifact (+0.066) + $T solver bug 5 samples (+0.025). Corrected ISR=0.465, but both values entirely from H7a tautological necessity, no reasoning quality signal.\", \"h7_count\": 90, \"h7_rate\": 1, \"h7a_count\": 90, \"h7b_count\": 0, \"h1_count\": 0, \"h1_rate\": 0, \"h8_count\": 0, \"h8_rate\": 0, \"genuine_count\": 0, \"genuine_rate\": 0}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s43_1000_r2\", \"completed_at\": \"2026-05-15T16:20:55.876Z\", \"notes\": \"Taxonomy audit (2026-05-15): 90/90 proved = H7a (100% tautology). All single-premise with conclusion text-matching premise. Content-independent predicates only 1/90. ISR分布反映H7a下quantifier结构差异(部分有∃x wrapping). genuine_strict=0. s43 1000步与500步(s43-r4)同为H7主导模式,但1000步PR大幅提升(14%→90%)。\"}, \"plan016-extended-1000-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T05:29:47.634Z\", \"updated_at\": \"2026-05-15T17:11:13.058Z\", \"hypothesis\": \"Extended training 1000 steps exec-only: plan001-s42 500步 PR=93% 是真收敛还是 lucky early convergence? 1000步观察 PR 和 ISR 在更长 horizon 的行为。s43(14%)/s44(98% tautological) 在 500 步均失败，延长训练是否能改善？\", \"parent\": \"plan001-exec-only-s42-r2\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 42 --output_dir /root/autodl-tmp/outputs/plan016_extended_1000_s42\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Extended training 1000 steps exec-only: plan001-s42 500步 PR=93% 是真收敛还是 lucky early convergence?\", \"plan_id\": \"plan016\", \"reward_formula\": \"r = r_exec (exec-only)\", \"num_steps\": 1000}, \"pid\": \"263268\", \"log_path\": \"~/runs/solver-trace-ablation/plan016-extended-1000-s42.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 42 --output_dir /root/autodl-tmp/outputs/plan016_extended_1000_s42\\\"\", \"finished_at\": \"2026-05-14T08:02:31.805Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T08:02:33.434519+00:00\"}]}, \"metrics\": {\"prove_rate\": 0.96, \"n_proved\": 96, \"n_problems\": 100, \"h7_count\": 0, \"h7_rate\": 0, \"h7a_count\": 0, \"h7b_count\": 0, \"h1_count\": 96, \"h1_rate\": 1, \"h8_count\": 0, \"h8_rate\": 0, \"genuine_count\": 0, \"genuine_rate\": 0, \"genuine_h1_near\": 0, \"genuine_strict\": 0, \"content_independent_rate\": 1, \"single_premise_rate\": 0, \"taxonomy_audit\": \"2026-05-15\", \"taxonomy_tool\": \"classify_h7.py current version (with H8 detection)\", \"taxonomy_note\": \"Re-run with current classify_h7.py. Old value genuine=7 was incorrect (old version lacked H8 and had weaker H1 detection). All 96 proved are H1 (conclusion embedded in premises). 0 H7, 0 H8.\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan016_extended_1000_s42\", \"completed_at\": \"2026-05-14T08:13:51.754Z\", \"notes\": \"Extended training to 1000 steps CONFIRMS ISR collapse worsens monotonically.\\\\n\\\\n## 500 vs 1000 step comparison (eval_sta.py):\\\\n| Metric | plan001-s42 (500步) | plan016 (1000步) | Change |\\\\n|--------|-------------------|-----------------|--------|\\\\n| eval PR | 0.93 | 0.96 | +3.2% |\\\\n| eval ISR | 0.123 | 0.0027 | -97.8% |\\\\n| proved_only ISR | 0.132 | 0.0028 | -97.9% |\\\\n| components | 6.58 | 18.55 | +182% |\\\\n| ISR=0 ratio | - | 94.8% | - |\\\\n| n_necessary=0 ratio | - | 94.8% | - |\\\\n\\\\n## Key findings:\\\\n1. PR improves (+3%) but ISR collapses near-zero (0.0027). The model gets BETTER at proving while becoming WORSE at faithful reasoning.\\\\n2. Component count nearly tripled (6.58→18.55). Model generates longer proofs with more components, but 94.8% have ZERO necessary components.\\\\n3. NOT tautological collapse (comp=2 ratio=0). Instead: contradiction-based collapse — model embeds P(a) and ¬P(a) among many irrelevant premises, making anything provable via explosion.\\\\n4. Windowed ISR trend is monotonically decreasing: 0.1115 (101-200) → 0.0433 (401-500) → 0.0200 (601-700) → 0.0144 (901-1000). No recovery signal.\\\\n5. The exec-only reward creates a pure reward hacking incentive: the model discovers that contradictions + trivially true conclusions always satisfy the prover.\\\\n\\\\n## Implication for paper:\\\\nExtended training is a clean ablation showing exec-only reward's failure mode worsens over time. The 500-step ISR of 0.123 was not a floor — it was a snapshot of ongoing collapse.\"}, \"plan001-exec-only-s44-1000-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:51:03.762Z\", \"updated_at\": \"2026-05-15T17:06:45.730Z\", \"hypothesis\": \"Exec-only GRPO 1000步 seed=44（r2 重跑）：r1 因磁盘满被 kill。磁盘已清理（92GB 可用），从 step 0 重跑。\", \"parent\": \"plan001-exec-only-s44-1000\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T13:51:35.383Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 44 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s44_1000_r2\\\"\", \"finished_at\": \"2026-05-15T16:11:51.095Z\", \"training_hours\": 2.34}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 44 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s44_1000_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"363840\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s44-1000-r2.log\", \"submitted_at\": \"2026-05-15T13:51:37.012Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 8895.8, \"gpu_hours\": 2.47, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s44_1000_r2\"}, \"pid\": \"363840\", \"log_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s44_1000_r2/eval_sta_results.json\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T16:11:54.943668+00:00\"}]}, \"metrics\": {\"prove_rate\": 1, \"n_proved\": 100, \"n_problems\": 100, \"mean_isr\": 0.002, \"isr_std\": 0.0146, \"h7_count\": 0, \"h7_rate\": 0, \"h7a_count\": 0, \"h7b_count\": 0, \"h1_count\": 85, \"h1_rate\": 0.85, \"h8_count\": 15, \"h8_rate\": 0.15, \"genuine_count\": 0, \"genuine_rate\": 0, \"genuine_note\": \"D091: 3 samples escape text-match classifiers but are functionally degenerate (ISR=0, disjunctive/commuted bypasses)\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s44_1000_r2\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T16:19:52.818Z\", \"taxonomy_note\": \"D086 clean eval: proved=100, H7=0 (H7a=0, H7b=0), H1=85, H8=15, genuine=3 (3%). 500步→1000步变化: H7 97→0, H1 0→85, H8 0→15. 完全从H7模式转向H1+H8模式. Eval data: proofwriter_fol_100.jsonl\", \"notes\": \"Taxonomy audit (2026-05-15): H1_only=82, H8_only=12, H1∩H8=3, genuine=3 (all H1-near). 3个genuine proof全部ISR=0, 结论为析取式, universal premise实例化后精确等于/包含结论 + ground facts冗余满足各析取项: folio_1296(∀x实例化+析取交换), folio_1428(∀x子公式+ground facts重复6次), folio_1051(∀x(C(x)∨S(x))实例化=C(a)∨S(a)精确匹配). classify_h7漏检原因: H1不做∀x实例化, H8不检查析取式. Per C013: H1-near保留为genuine但标记. genuine_strict=0.\"}, \"plan018-additive-random-b01-s43-r3\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:17:51.220Z\", \"updated_at\": \"2026-05-15T16:34:10.295Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s43_r3\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"486853\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s43-r3.log\", \"submitted_at\": \"2026-05-15T16:27:24.202Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43}, \"server\": \"westd-39279\", \"gpu_id\": \"cuda:0\", \"account\": \"root\"}, \"plan018-additive-random-b01-s42-1000-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:26:49.094Z\", \"updated_at\": \"2026-05-15T15:39:20.811Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000_r3 --num_steps 1000 --beta 0.1 --seed 42 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"269147\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42-1000-r3.log\", \"submitted_at\": \"2026-05-15T10:27:08.529Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 6985.6, \"gpu_hours\": 1.94}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"269147\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42-1000-r3.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000_r3 --num_steps 1000 --beta 0.1 --seed 42 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T12:05:43.550Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T12:05:46.554124+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000_r3/checkpoint-1000\", \"metrics\": {\"eval_prove_rate\": 0.97, \"eval_mean_isr\": 0.6892, \"eval_isr_std\": 0.2037, \"eval_median_isr\": 0.75, \"eval_proved_only_isr\": 0.7105, \"eval_n_proved\": 97, \"eval_n_problems\": 100, \"genuine_count\": 0, \"genuine_rate\": 0, \"h1_count\": 0, \"h1_rate\": 0, \"h7_count\": 97, \"h7_rate\": 1, \"tautological_collapse\": true, \"train_final_prove_rate\": 0.827, \"train_final_mean_isr\": 0.5213, \"train_loss\": 0.00671, \"train_final_entropy\": 0.003, \"train_runtime_seconds\": 5783, \"train_steps\": 1000, \"eval_by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 25, \"prove_rate\": 1, \"mean_isr\": 0.7533}, \"unknown\": {\"count\": 41, \"proved\": 39, \"prove_rate\": 0.951, \"mean_isr\": 0.6565}, \"true\": {\"count\": 34, \"proved\": 33, \"prove_rate\": 0.971, \"mean_isr\": 0.6814}}, \"n_premise_distribution\": {\"1\": 97}, \"pattern_description\": \"All 97 proved: 1 premise identical to conclusion (P therefore P). D088 correction: h7=97 h1=0 (was h1=97 h7=0 pre-D086 bugfix).\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T12:23:34.170Z\", \"taxonomy_note\": \"D088 修正: metrics 字段已同步 (h7=97, h1=0, genuine=0, 全 H7a). D086 clean run classify_h7 确认 97/97 proved 均为 single_premise=conclusion (H7 tautology). 之前 metrics 残留 h1=97/h7=0 是 D086 前 classify_h7 bug 导致的错误分类. ⚠️ batch_h7ab_clean.json 中 plan018_additive_random_b01_s42_1000 条目处理的是原始失败实验(proved=100)非 r3(proved=97), 不可引用.\", \"h7_count\": 97, \"h1_count\": 0, \"h8_count\": 0, \"genuine_count\": 0}, \"plan009-sft-baseline-s44-1000\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-15T12:47:54.021Z\", \"updated_at\": \"2026-05-15T15:38:21.803Z\", \"hypothesis\": \"SFT 1000步 seed=44：与 s42/s43 相同配置的第三个 seed，验证 SFT 在 1000 步的 genuine rate 稳定性。3-seed 统计支撑 Goodhart collapse 是 RL (GRPO) 特有现象的 claim。\", \"parent\": \"plan009-sft-baseline-s42-r4\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T12:49:08.008Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000 --num_steps 1000 --seed 44 --no_wandb --gpu 1\\\"\", \"finished_at\": \"2026-05-15T12:50:00.305Z\", \"training_hours\": 0.01}, \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 742.00 MiB. GPU 0 has a total capacity of 94.97 GiB of which 100.25 MiB is free. Process 352142 has 62.36 GiB memory in use. Including non-PyTorch memory, this process has 32.51 GiB memory in use. Of the allocate\", \"completed_at\": \"2026-05-15T12:50:04.083Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T12:50:14.696431+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44}, \"pid\": \"352970\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s44-1000-r3.log\", \"conclusion\": \"success\", \"metrics\": {\"prove_rate\": 0.15, \"n_proved\": 15, \"n_problems\": 100, \"mean_isr\": 0.0884, \"isr_std\": 0.2268, \"median_isr\": 0, \"proved_only_mean_isr\": 0.5892, \"max_isr\": 0.8571, \"by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 15, \"prove_rate\": 0.4412}, \"false\": {\"count\": 25, \"proved\": 0, \"prove_rate\": 0}, \"unknown\": {\"count\": 41, \"proved\": 0, \"prove_rate\": 0}}, \"genuine_count\": 14, \"genuine_rate\": 0.9333, \"h7_strict_count\": 0, \"h7_strict_rate\": 0, \"h1_strict_count\": 1, \"h1_strict_rate\": 0.0667, \"h8_conjunction_collapse_count\": 0, \"h8_conjunction_collapse_rate\": 0, \"conclusion_in_premise_count\": 1, \"conclusion_in_premise_rate\": 0.0667, \"content_independent_count\": 0, \"content_independent_rate\": 0, \"isr_1_count\": 0, \"isr_1_rate\": 0, \"train_final_loss\": 0.0171, \"train_avg_loss\": 0.1544, \"train_token_accuracy\": 0.995, \"train_runtime_s\": 1580.97, \"eval_elapsed_s\": 391.8}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000/checkpoint-1000\", \"notes\": \"SFT s44 1000步 r3 成功（r1 OOM 因 GPU 冲突）。prove_rate=0.15 略高于 s42(0.13)/s43(0.11)，genuine_rate=93.3% 稳定高。3-seed SFT 均 genuine_rate>90% 无 Goodhart collapse。\", \"taxonomy_note\": \"D086 补扫: proved=15, H7=0, H1=1, H8=0, genuine=14 (93.3%). SFT 1000-step s44 保持高 genuine rate. eval: /root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000/eval_sta_results.json\", \"genuine_rate\": 0.933}, \"plan009-sft-baseline-s43-1000\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:28:46.064Z\", \"updated_at\": \"2026-05-15T15:38:21.200Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43}, \"hypothesis\": \"SFT 1000步 seed=43：与 s42 相同配置的第二个 seed，验证 SFT 在 1000 步的 genuine rate 稳定性。与 GRPO 各条件 1000步对比，确认 Goodhart collapse 是 RL 特有现象。\", \"parent\": \"plan009-sft-baseline-s43\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"352137\", \"log_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s43_1000/checkpoint-1000/trainer_state.json\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s43_1000 --num_steps 1000 --seed 43 --no_wandb --gpu 0\\\"\", \"finished_at\": \"2026-05-15T13:15:26.388Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:15:29.227018+00:00\"}]}, \"metrics\": {\"prove_rate\": 0.11, \"n_proved\": 11, \"n_problems\": 100, \"mean_isr\": 0.0699, \"isr_std\": 0.2155, \"median_isr\": 0, \"proved_only_mean_isr\": 0.6352, \"by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 11, \"prove_rate\": 0.3235}, \"false\": {\"count\": 25, \"proved\": 0, \"prove_rate\": 0}, \"unknown\": {\"count\": 41, \"proved\": 0, \"prove_rate\": 0}}, \"genuine_count\": 10, \"genuine_rate\": 0.9091, \"h7_strict_count\": 0, \"h7_strict_rate\": 0, \"h1_strict_count\": 1, \"h1_strict_rate\": 0.0909, \"h8_conjunction_collapse_count\": 0, \"h8_conjunction_collapse_rate\": 0, \"conclusion_in_premise_count\": 1, \"conclusion_in_premise_rate\": 0.0909, \"content_independent_count\": 0, \"content_independent_rate\": 0, \"isr_1_count\": 1, \"isr_1_rate\": 0.0909, \"train_final_loss\": 0.0167, \"train_avg_loss\": 0.1551, \"train_token_accuracy\": 0.9954, \"train_runtime_s\": 1584.79, \"eval_elapsed_s\": 326.1}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s43_1000/checkpoint-1000\", \"conclusion\": \"success\", \"notes\": \"SFT s43 1000步结果与 s42 高度一致：prove_rate 11% vs 13%（-2pp），mean_isr 0.0699 vs 0.0738，final_loss 0.0167 vs 0.0168。差异在 seed 方差范围内。SFT baseline 稳定。注意：eval_sta.py 当前版本不输出 h7/h1/h8/genuine 分类指标。\", \"completed_at\": \"2026-05-15T13:25:00.854Z\", \"taxonomy_note\": \"D086 补扫: proved=11, H7=0, H1=1, H8=0, genuine=10 (90.9%). SFT 1000-step s43 保持高 genuine rate. eval: /root/autodl-tmp/outputs/plan009_sft_baseline_s43_1000/eval_sta_results.json\", \"genuine_count\": 10, \"genuine_rate\": 0.909}, \"plan009-sft-baseline-s42-1000\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-15T11:57:52.856Z\", \"updated_at\": \"2026-05-15T15:38:19.225Z\", \"hypothesis\": \"SFT 1000步延伸：验证 SFT（无 reward optimization）在 1000 步是否维持 genuine rate。500 步 SFT 已达 93% genuine，若 1000 步仍保持高 genuine → Goodhart collapse 是 RL (GRPO) 特有现象，非一般 finetuning 退化。与 exec-only/ISR/random 1000步形成对比。\", \"parent\": \"plan009-sft-baseline-s42-r4\", \"completed_at\": \"2026-05-15T12:25:32.031Z\", \"eval_prove_rate\": 0.13, \"eval_mean_isr\": 0.0738, \"eval_isr_std\": 0.2077, \"eval_proved_only_isr\": 0.5677, \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 1, \"h1_rate\": 7.7, \"genuine_count\": 12, \"genuine_rate\": 0.923, \"extra\": {\"previous_failure\": {\"conclusion\": \"success\"}}, \"spec\": {\"command\": \"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s42_1000 --num_steps 1000 --seed 42 --no_wandb --bf16\", \"server\": \"westd-39279\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"gpu\": [\"cuda:0\"], \"submitted_at\": \"2026-05-15T19:58:15+08:00\", \"wall_clock_seconds\": 1415, \"gpu_hours\": 0.39, \"checkpoint_source\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42_1000/checkpoint-1000\", \"eval_data\": \"data/proofwriter_fol_100.jsonl\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42_1000/checkpoint-1000\", \"log_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42_1000/checkpoint-1000/trainer_state.json\", \"metrics\": {\"train_final_loss\": 0.0168, \"train_last_step_loss\": 0.0168, \"train_token_accuracy\": 0.9955, \"train_epochs\": 15.88, \"train_runtime_sec\": 1415, \"train_steps\": 1000, \"eval_prove_rate\": 0.13, \"eval_n_proved\": 13, \"eval_n_problems\": 100, \"eval_mean_isr\": 0.0738, \"eval_isr_std\": 0.2077, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.5677, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_method\": \"eval_sta.py full STA\", \"eval_output_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42_1000/eval_sta_results.json\", \"h7_strict_count\": 0, \"h7_strict_rate\": 0, \"h1_strict_count\": 1, \"h1_strict_rate\": 0.0769, \"h8_conjunction_collapse_count\": 0, \"h8_conjunction_collapse_rate\": 0, \"genuine_count\": 12, \"genuine_rate\": 0.9231, \"conclusion_in_premise_count\": 1, \"conclusion_in_premise_rate\": 0.0769, \"isr_1_count\": 0, \"content_independent_count\": 0, \"eval_by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 12, \"prove_rate\": 0.353, \"mean_isr\": 0.209}, \"false\": {\"count\": 25, \"proved\": 1, \"prove_rate\": 0.04, \"mean_isr\": 0.011}, \"unknown\": {\"count\": 41, \"proved\": 0, \"prove_rate\": 0, \"mean_isr\": 0}}}, \"conclusion\": \"success\", \"notes\": \"SFT 1000步 (15.88 epochs): train loss 降至 0.0168（严重过拟合），但 eval genuine_rate=92.31% 与 500步的 92.9% 基本持平。prove_rate 从 0.14 微降至 0.13，h7=0，h1=1。结论：SFT 即使过拟合也不产生 Goodhart collapse（h7/h8=0），验证了 Goodhart 是 RL(GRPO) reward optimization 特有现象。Unknown 类全部 0/41 未 prove（与 500步一致），SFT 不具备泛化到 unknown 类的能力。\", \"taxonomy_note\": \"D086 补扫: proved=13, H7=0, H1=1, H8=0, genuine=12 (92.3%). SFT 1000-step 保持高 genuine rate，确认 hacking 是 RL-specific. eval: /root/autodl-tmp/outputs/plan009_sft_baseline_s42_1000/eval_sta_results.json\"}, \"exp1-random-b03-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:52:08.290Z\", \"updated_at\": \"2026-05-15T15:35:21.404Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"β=0.3 random seed 43: supplement for 3-seed statistics in Table 1. Reference: plan017-additive-random-s42\", \"plan_id\": \"EXP-1\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * random[0,1])\", \"num_steps\": 500, \"beta\": 0.3, \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/exp1_random_b03_s43\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"963653\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_random_b03_s43/\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-random-b03-s43.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T23:35:47.399Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:35:48.354Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:35:52.992924+00:00\"}]}, \"notes\": \"D062/D063 INVALIDATED: eval used test_100.jsonl (wrong test set). Checkpoint deleted, cannot re-eval. Retrain as exp1-random-b03-s43-r2.\", \"metrics\": {\"parse_rate\": 1, \"prove_rate\": 0.79, \"mean_isr\": 0.1745, \"isr_std\": 0.1628, \"median_isr\": 0.1667, \"proved_only_mean_isr\": 0.2209, \"hacking_rate_strict_h7\": 0, \"hacking_rate_functional\": 0.1013, \"genuine_rate\": 0.8987, \"genuine_count\": 71, \"n_proved\": 79, \"n_problems\": 100, \"h1_conclusion_in_premise\": 0.759, \"eval_data\": \"test_100.jsonl\", \"eval_output\": \"/root/autodl-tmp/outputs/eval_sta_exp1_random_b03_s43.json\"}, \"eval_metrics\": {\"prove_rate\": 0.79, \"mean_isr\": 0.1745, \"isr_std\": 0.1628, \"proved_only_isr\": 0.2209, \"n_proved\": 79, \"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 0.759, \"h1_count\": 60, \"genuine_rate\": 0.241, \"genuine_count\": 19, \"single_premise_rate\": 0, \"eval_data\": \"test_100.jsonl\"}, \"h7a_count\": null, \"h1_count\": null, \"taxonomy_note\": \"INVALIDATED: taxonomy based on test_100.jsonl eval, not comparable with proofwriter_fol_100 runs. Do not use in paper. D086 写入的 h7a/h1 字段仅反映旧 eval 数据，不可引用。\"}, \"exp1-random-b03-s43-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T02:44:48.792Z\", \"updated_at\": \"2026-05-15T15:35:19.765Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.3 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/exp1_random_b03_s43_r4\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"117566\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-random-b03-s43-r4.log\", \"submitted_at\": \"2026-05-15T02:44:48.579Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"Random beta=0.3 s43 retry #4: previous r2 killed, r3 OOM. Clean GPU now.\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * random[0,1])\", \"plan_id\": \"EXP-1\", \"output_dir\": \"/root/autodl-tmp/outputs/exp1_random_b03_s43_r4\", \"wall_clock_seconds\": 6738.6, \"gpu_hours\": 1.87}, \"reproduce\": {\"finished_at\": \"2026-05-15T04:29:26.819Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T04:29:29.426423+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"final_step\": 500, \"prove_rate\": 0.5505, \"mean_isr\": 0.1358, \"parse_rate\": 1, \"train_loss\": 0.01365, \"train_runtime_sec\": 6161.1, \"epoch\": 2, \"eval_prove_rate\": 0.92, \"eval_mean_isr\": 0.1659, \"eval_isr_std\": 0.1147, \"eval_median_isr\": 0.1429, \"eval_proved_only_mean_isr\": 0.1803, \"eval_min_isr\": 0, \"eval_max_isr\": 0.5, \"eval_n_proved\": 92, \"eval_n_problems\": 100, \"eval_h7_strict_rate\": 0.076, \"eval_h7_strict_count\": 7, \"eval_h1_strict_rate\": 0.891, \"eval_h1_strict_count\": 82, \"eval_genuine_rate\": 0.0326, \"eval_genuine_count\": 3, \"eval_isr0_count\": 6, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 23, \"prove_rate\": 0.92, \"mean_isr\": 0.156}, \"unknown\": {\"count\": 41, \"proved\": 37, \"prove_rate\": 0.902, \"mean_isr\": 0.184}, \"true\": {\"count\": 34, \"proved\": 32, \"prove_rate\": 0.941, \"mean_isr\": 0.151}}, \"D086_correction\": \"H1 90→82, genuine 2→3 per D086 clean batch run\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_random_b03_s43_r4/checkpoint-500\", \"completed_at\": \"2026-05-15T04:37:07.139Z\", \"notes\": \"Training 500/500 steps, 1h42m. Final train: prove_rate=0.5505, mean_isr=0.1358, loss=0.01365. EVAL (proofwriter_fol_100.jsonl): PR=0.92, ISR=0.1659, H7=7/92(7.6%), H1=90/92(97.8%), genuine=2/92(2.2%). ANOMALY: massive seed variance vs s44-r2 (PR=0.23, ISR=0, H1=100%, genuine=0%). s43 learned high-PR hacking strategy with conclusion-in-premise; s44 barely proved anything. Both are random baseline — this variance weakens cross-seed claims.\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-random-b03-s43-r4.log\", \"eval_h7_strict_count\": 0, \"eval_h1_strict_count\": 89, \"eval_genuine_count\": 3, \"h7a_count\": 7, \"h1_count\": 82, \"taxonomy_note\": \"D086 clean run: H7a=7, H1=82, genuine=3. metrics 字段已从旧值 (H1=90, genuine=2) 同步修正.\"}, \"plan002-additive-b01-s42-1000\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:08:50.639Z\", \"updated_at\": \"2026-05-15T15:35:12.176Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode execution_sta --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s42_1000 --num_steps 1000 --beta 0.1 --seed 42 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"171076\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s42-1000.log\", \"submitted_at\": \"2026-05-15T07:29:48.253Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4944.1, \"gpu_hours\": 1.37}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"171076\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s42-1000.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode execution_sta --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s42_1000 --num_steps 1000 --beta 0.1 --seed 42 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T08:44:46.526Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T08:44:51.343174+00:00\"}]}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan002_additive_b01_s42_1000\", \"metrics\": {\"eval_prove_rate\": 0.9, \"eval_mean_isr\": 0.7892, \"eval_isr_std\": 0.3424, \"eval_proved_only_isr\": 0.8769, \"eval_median_isr\": 1, \"eval_n_proved\": 90, \"eval_n_problems\": 100, \"eval_component_count_mean\": 2.889, \"tautological_collapse\": true, \"train_final_prove_rate\": 0.855, \"train_final_mean_isr\": 0.532, \"h7_count\": 87, \"h7_rate\": 0.9667, \"h1_count\": 0, \"h1_rate\": 0, \"h1_near_count\": 1, \"h1_near_rate\": 0.0111, \"h8_conjunction_collapse_count\": 1, \"h8_conjunction_collapse_rate\": 0.0111, \"genuine_count\": 2, \"genuine_rate\": 0.0222, \"taxonomy_standard\": \"D086 clean run = ground truth. D084 residual removed.\"}, \"completed_at\": \"2026-05-15T08:52:12.385Z\", \"genuine_count\": 2, \"genuine_rate\": 0.0111, \"h8_count\": 1, \"notes\": \"D084 taxonomy re-audit (2026-05-15): 90 proved → H7=87 (96.7%), H1_exact=0, H1_near=1, H8=2 (2.2%), genuine=1 (1.1%). Changes vs prior: H7 +4 (paren normalization), H1 -4→0 (reclassified H7), H8 +1 (folio_1255 shared-antecedent conjunction missed), genuine -1. Tautological collapse confirmed. Taxonomy JSON: /root/autodl-tmp/outputs/plan002_additive_b01_s42_1000_taxonomy_unified.json\", \"h7a_count\": 87, \"h7_count\": 87, \"h1_count\": 0, \"taxonomy_note\": \"D086 clean run (ground truth): H7a=87, H7b=0, H1=0, H8=1, genuine=2. D084 residual (H8=2, genuine=1) replaced. metrics 字段已同步.\"}, \"plan018-additive-random-b01-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T06:55:48.888Z\", \"updated_at\": \"2026-05-15T15:34:21.957Z\", \"hypothesis\": \"β=0.1 random control: r = r_exec·(1+0.1·random[0,1]). 与 plan002-b01 (additive ISR β=0.1, PR=0.81, ISR=0.337) 同 β 对照。如果 ISR β=0.1 >> random β=0.1 → ISR 信号在低剂量下有结构价值; 如果 ISR ≈ random → ISR 信号在低剂量下也仅是 variance regularization。D031 紧急实验。\", \"parent\": \"plan002-additive-b01-s42\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"377678\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42.log\", \"submitted_at\": \"2026-05-14T06:55:59.287Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"plan_id\": \"plan018\", \"reward_formula\": \"r = r_exec * (1 + 0.1 * random[0,1])\", \"num_steps\": 500, \"checkpoint_source\": \"N/A (training, not eval)\", \"eval_data\": \"N/A (training, not eval)\", \"wall_clock_seconds\": 5160.4, \"gpu_hours\": 1.43, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan018_additive_random_b01_s42\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T08:09:07.662Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T08:09:09.188407+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"eval_prove_rate\": 0.79, \"eval_mean_isr\": 0.1038, \"eval_isr_std\": 0.1369, \"eval_median_isr\": 0.0357, \"eval_proved_only_isr\": 0.1314, \"eval_n_proved\": 79, \"eval_n_problems\": 100, \"tautological_collapse\": false, \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 56, \"h1_rate\": 0.7089, \"h1_near_count\": 8, \"h1_near_rate\": 0.1013, \"h8_conjunction_collapse_count\": 3, \"h8_conjunction_collapse_rate\": 0.038, \"genuine_count_exact_h1\": 23, \"genuine_rate_exact_h1\": 0.2911, \"genuine_count_strict\": 12, \"genuine_rate_strict\": 0.1519, \"taxonomy_verification\": \"2026-05-15: full re-verification from eval_sta file. H1 exact=56, H1-near(substring)=8 (5 conc_in_prem + 3 prem_in_conc), H8=3, strict genuine=12. Registry original genuine=23 = H8(3) + H1-near(8) + strict genuine(12).\"}, \"notes\": \"Random control β=0.1 vs ISR β=0.1 (plan002-b01) 对照。conclusion=negative: random control的ISR远低于ISR-guided。\\n\\n对比 plan002-b01 (ISR β=0.1):\\n- PR: 0.79 vs 0.81 (≈持平, Δ=0.02)\\n- Mean ISR: 0.104 vs 0.337 (ISR 3.2x higher)\\n- Proved-only ISR: 0.131 vs 0.415 (ISR 3.2x higher)\\n- Median ISR: 0.036 vs plan002未记录\\n- Component count: 8.46 vs 5.58 (random组更多冗余)\\n- ISR=0占比(proved): 36.7% (random组大量proof无结构)\\n- Tautological collapse: 无 (component_2_ratio=0)\\n\\n关键发现: PR几乎相同说明β=0.1 random噪声不影响证明能力。但ISR差3.2倍，证明ISR reward提供genuine structural guidance而非仅variance regularization。这强力支持Claim 2: ISR信号在低剂量下有结构价值。\\n\\nEval output: /root/autodl-tmp/outputs/plan018_additive_random_b01_s42/eval_results.json\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan018_additive_random_b01_s42\", \"completed_at\": \"2026-05-14T08:21:59.737Z\", \"h7_count\": 0, \"h1_count\": 58, \"genuine_count\": 18, \"h8_count\": 4, \"genuine_rate\": 0.228, \"taxonomy_note\": \"D086 clean run (ground truth): H7=0, H1=58, H8=4, genuine=18 (22.8%). 1 H1∩H8 overlap sample; genuine computed from set union (|H7∪H1∪H8|=61), not simple subtraction (0+58+4=62). genuine = 79 − 61 = 18.\"}, \"plan002-additive-b01-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:36:17.298Z\", \"updated_at\": \"2026-05-15T15:32:47.807Z\", \"hypothesis\": \"ISR β=0.1 seed=44 多 seed 验证：exec-only s44 是 tautological collapse (PR=98%, ISR=0.57 fake)，ISR β=0.1 能否防止 tautological collapse？3-seed mean±std 用于论文 Claim 2。\", \"parent\": \"plan002-additive-b01-s42\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-14T08:45:11.826Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s44\\\"\", \"finished_at\": \"2026-05-14T09:28:10.836Z\", \"training_hours\": 0.72}, \"spec\": {\"command\": \"python3 scripts/train_grpo.py --mode additive_bonus --isr_beta 0.1 --seed 44\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"466540\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s44.log\", \"submitted_at\": \"2026-05-14T08:46:23.037Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"wall_clock_seconds\": 2950.3, \"gpu_hours\": 0.82}, \"pid\": \"466540\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s44.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T09:28:12.416418+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.89, \"eval_mean_isr\": 0.803, \"eval_isr_std\": null, \"eval_proved_only_isr\": 0.902, \"eval_n_proved\": 89, \"eval_n_problems\": 100, \"h7_count\": 89, \"h7_rate\": 1, \"h1_count\": 0, \"h1_rate\": 0, \"h8_conjunction_collapse_count\": 0, \"h8_conjunction_collapse_rate\": 0, \"genuine_count\": 0, \"genuine_rate\": 0, \"component_mean\": 4.33, \"comp_2_ratio\": 0.022, \"h7_fn_correction\": \"12 former genuine reclassified as H7: all n_prem=1 false negatives (normalization mismatch prevented conclusion matching)\"}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan002_additive_b01_s44\", \"notes\": \"H7 FN correction: 12 samples with n_prem=1 misclassified as genuine. Mismatch types: 11 vacuous_quantifier_wrapping (∃x(P(x)) vs ∃x(∃y(P(y)))), 1 structural_simplification. Not simple whitespace/case but logically equivalent structural variants. Evidence file: /root/autodl-tmp/outputs/isr_s44_fn_evidence.json. Source eval: /root/runs/solver-trace-ablation/plan002-additive-b01-s44-eval.json\", \"completed_at\": \"2026-05-14T09:35:33.310Z\", \"h7_count\": 89, \"h1_count\": 0, \"genuine_count\": 0, \"h7_fn_correction\": \"vacuous quantifier wrapping (11/12) + structural simplification (1/12); model-learned obfuscation, not classifier bug\", \"h7a_count\": 77, \"h7b_count\": 12, \"taxonomy_note\": \"D086 补正(Reviewer): H7a=77, H7b=12, H1=0, H8=0, genuine=0. s44 全部 89 proved 均为 single_premise, H8(conjunction collapse)要求 multi-premise 数学上不可能触发. D086 clean run 误报 H8=1 已修正.\", \"h8_count\": 0}, \"plan013-random-reward-s42-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T01:40:35.587Z\", \"updated_at\": \"2026-05-15T15:28:11.035Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_random_reward.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --exec_weight 0.9 --sta_weight 0.1 --output_dir /root/autodl-tmp/outputs/plan013_random_reward_s42_r4\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"136261\", \"log_path\": \"~/runs/solver-trace-ablation/plan013-random-reward-s42-r4.log\", \"submitted_at\": \"2026-05-14T01:40:35.528Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Random reward baseline: replacing ISR with random values should degrade structural quality while maintaining execution reward, proving ISR's causal contribution\", \"plan_id\": \"plan013\", \"wall_clock_seconds\": 2492.4, \"gpu_hours\": 0.69}, \"reproduce\": {\"finished_at\": \"2026-05-14T02:19:57.306Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T02:19:58.514969+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42_r4/checkpoint-500\", \"log_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42_r4/reward_log.jsonl\", \"metrics\": {\"eval_prove_rate\": 1, \"eval_mean_isr\": 0.535, \"eval_isr_std\": 0.1282, \"eval_proved_only_isr\": 0.535, \"eval_median_isr\": 0.5, \"eval_n_proved\": 100, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_note\": \"DEGENERATE: model generates trivial 2-component proofs (premise=conclusion, conclusion=conclusion), ISR=0.5 is artifact of trivial proof structure\"}, \"completed_at\": \"2026-05-14T02:22:07.933Z\", \"notes\": \"⚠️ 训练日志 ISR 为 binary approximation (_fast_fn)，ISR≈prove_rate，不含结构信息。真实 ISR 需通过 eval_sta.py (full STA) 在 checkpoint-500 上重新评估。final_mean_isr=0.6705 实为 binary 近似值，禁止用于论文或跨实验 ISR 对比。\", \"taxonomy_note\": \"D086 补扫: proved=100, H7=100(100%), H1=0, H8=0, genuine=0 (0%). Convex random reward (0.9·r_exec+0.1·random) 100% tautological collapse. eval: /root/solver-trace-ablation/outputs/eval_sta_plan013_random_reward_s42_r4.json\"}, \"plan001-exec-only-s43-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T01:40:37.808Z\", \"updated_at\": \"2026-05-15T15:28:09.062Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43_r4\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"136339\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43-r4.log\", \"submitted_at\": \"2026-05-14T01:40:37.746Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"Exec-only seed=43 replication: confirm plan001-r2 (seed=42) prove_rate convergence is reproducible across seeds\", \"plan_id\": \"plan001\", \"wall_clock_seconds\": 10020.8, \"gpu_hours\": 2.78}, \"reproduce\": {\"finished_at\": \"2026-05-14T03:13:08.926Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T03:13:12.957272+00:00\"}]}, \"metrics\": {\"eval_sampling_prove_rate\": 0.14, \"eval_sampling_mean_isr\": 0, \"eval_sampling_n_proved\": 14, \"eval_sampling_temperature\": 0.7, \"eval_sampling_method\": \"do_sample=True, temperature=0.7\", \"eval_sampling_by_answer\": {\"true\": {\"count\": 34, \"proved\": 6, \"prove_rate\": 0.176}, \"false\": {\"count\": 25, \"proved\": 2, \"prove_rate\": 0.08}, \"unknown\": {\"count\": 41, \"proved\": 6, \"prove_rate\": 0.146}}, \"eval_greedy_prove_rate\": 0.13, \"eval_greedy_mean_isr\": 0, \"eval_greedy_proved_only_isr\": 0, \"eval_greedy_n_proved\": 13, \"eval_greedy_method\": \"eval_sta.py default (do_sample=False)\", \"eval_greedy_by_answer\": {\"true\": {\"count\": 34, \"proved\": 4, \"prove_rate\": 0.118}, \"false\": {\"count\": 25, \"proved\": 5, \"prove_rate\": 0.2}, \"unknown\": {\"count\": 41, \"proved\": 4, \"prove_rate\": 0.0976}}, \"eval_greedy_h7_count\": 0, \"eval_greedy_h7_rate\": 0, \"eval_greedy_h1_count\": 13, \"eval_greedy_h1_rate\": 1, \"eval_greedy_genuine_rate\": 0, \"eval_greedy_n_premises_proved_mean\": 17.92, \"eval_greedy_mean_components_proved\": 18.92, \"eval_greedy_n_premises_all_mean\": 32.67, \"eval_sampling_h1_rate\": 1, \"eval_sampling_h7_rate\": 0, \"eval_sampling_genuine_rate\": 0, \"eval_sampling_mean_components_proved\": 18.5, \"eval_greedy_vs_sampling_delta_pr\": -0.01, \"eval_method_note\": \"Greedy and sampling agree on failure profile (ISR*=0, H1=100%, components~18.5-18.9). s43 collapse is decoding-invariant.\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s43_r4\", \"log_path\": \"/root/runs/solver-trace-ablation/plan001-exec-only-s43-r4.log\", \"conclusion\": \"negative\", \"notes\": \"EXP-2 (2026-05-15): greedy eval (T=0) on same 100 held-out problems also done with eval_sta.py defaults (do_sample=False). Result: PR=0.13, ISR*=0.0, H1=100% (13/13), H7=0%, genuine=0%, mean components (proved)=18.92. Sampling (T=0.7) baseline: PR=0.14, ISR*=0.0, H1=100% (14/14), components~18.5. ΔPR=-0.01, both ISR*=0 → s43 collapse is decoding-invariant, NOT a sampling artifact. ~85% of inputs hit max_new_tokens with long repeated-clause outputs; the ~15% that do parse contain the conclusion verbatim among 14-30 premises (n_necessary=0 by per-clause ablation → ISR=0). 训练 PR(last100)=0.883 但 eval PR=13-14% across decoders, ISR=0。与 s42 (eval PR=93%) 形成极端跨 seed 不稳定。Checkpoint 已删除（C003）。Report: outputs/h7_classification/exp2_s43_greedy_vs_sample.txt.\", \"completed_at\": \"2026-05-14T04:27:38.542Z\", \"taxonomy_note\": \"D086 补扫: proved=13, H7=0, H1=13, H8=1, genuine=0 (0%). exec-only s43 PR=13%, 100% H1 collapse. eval: /root/solver-trace-ablation/outputs/eval_sta_plan001_exec_only_s43_r4.json\"}, \"plan001-exec-only-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:19:41.568Z\", \"updated_at\": \"2026-05-15T15:27:42.555Z\", \"spec\": {\"command\": \"python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --num_steps 500 --seed 42\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"83029\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s42.log\", \"submitted_at\": \"2026-05-13T22:20:46.569Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"exec-only 500步训练 baseline\", \"wall_clock_seconds\": 2576.3, \"gpu_hours\": 0.72}, \"conclusion\": \"failed\", \"checkpoint_path\": \"N/A (failed before checkpoint)\", \"completed_at\": \"2026-05-13T23:03:42.892Z\", \"taxonomy_note\": \"D086 补扫: H7=1, H1=80, H8=6, genuine=7 (7.5%). 500-step exec-only 以 H1 为主 (86%), 少量 H7(1) 和 H8(6). eval文件: /root/solver-trace-ablation/outputs/eval_sta_plan001_exec_only_s42.json\", \"h7_count\": 1, \"h1_count\": 80, \"h8_count\": 6, \"genuine_count\": 7}, \"plan017-additive-random-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T03:11:14.694Z\", \"updated_at\": \"2026-05-15T15:17:35.229Z\", \"hypothesis\": \"Additive random control: r = r_exec·(1+0.3·random). 隔离 ISR structural signal vs variance regularization. 若 ISR > random > exec-only → signal+regularization 均贡献; 若 ISR > random ≈ exec-only → ISR signal 是关键; 若 ISR ≈ random → ISR 无结构价值。\", \"parent\": \"plan013-random-reward-s42-r4\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan017_additive_random_s42\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Additive random control: r = r_exec·(1+0.3·random)\", \"plan_id\": \"plan017\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * random[0,1])\", \"beta\": 0.3}, \"pid\": \"207116\", \"log_path\": \"~/runs/solver-trace-ablation/plan017-additive-random-s42.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan017_additive_random_s42\\\"\", \"finished_at\": \"2026-05-14T05:17:13.920Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T05:17:18.376399+00:00\"}]}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan017_additive_random_s42\", \"notes\": \"Eval结果: PR=0.48, mean_ISR=0.0453, proved_only_ISR=0.0943, mean_components=9.56 (3+比例100%, 无tautological collapse). 但33%已证明样本ISR=0 (n_necessary=0, conclusion trivially provable). 与plan013的不同failure mode: additive random防止了2-component坍缩, 但模型转向生成复杂但无用的formalization (多premises但conclusion不依赖任何premise). Variance regularization不足以产生genuine proofs.\", \"metrics\": {\"eval_prove_rate\": 0.48, \"eval_mean_isr\": 0.0453, \"eval_isr_std\": 0.0759, \"eval_median_isr\": 0, \"eval_max_isr\": 0.2857, \"eval_proved_only_isr\": 0.0943, \"eval_n_proved\": 48, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_component_count_mean\": 9.6, \"eval_component_count_2_ratio\": 0, \"tautological_collapse\": false, \"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 1, \"h1_count\": 48, \"genuine_rate\": 0, \"genuine_count\": 0}, \"completed_at\": \"2026-05-14T05:30:46.783Z\", \"h7a_count\": 4, \"h1_count\": 44, \"taxonomy_note\": \"D086 clean run: H7a=4 (new, deeper normalization), H7b=0, H1=44, H8=0, genuine=0. β=0.3 Random also produces H7 under higher reward pressure.\"}, \"plan002-additive-b01-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T05:29:08.138Z\", \"updated_at\": \"2026-05-15T14:38:00.829Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s42\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"262261\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s42.log\", \"submitted_at\": \"2026-05-14T05:32:32.415Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"plan_id\": \"plan002\", \"reward_formula\": \"r_exec * (1 + 0.1 * ISR)\", \"num_steps\": 500, \"wall_clock_seconds\": 4493.9, \"gpu_hours\": 1.25, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan002_additive_b01_s42\"}, \"parent\": \"plan002-additive-b03-s42\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"262261\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s42.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s42\\\"\", \"finished_at\": \"2026-05-14T06:37:58.285Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T06:37:59.656631+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"eval_prove_rate\": 0.81, \"eval_mean_isr\": 0.3365, \"eval_isr_std\": 0.3227, \"eval_proved_only_isr\": 0.4154, \"eval_median_isr\": 0.2, \"eval_n_proved\": 81, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_component_count_mean\": 5.58, \"h7_rate\": 0.16, \"h7_count\": 13, \"h1_rate\": 0.519, \"h1_count\": 42, \"h8_conjunction_collapse_count\": 12, \"h8_conjunction_collapse_rate\": 0.148, \"genuine_rate\": 0.173, \"genuine_count\": 14, \"tautological_collapse\": false, \"h8_audit_note\": \"2026-05-15: H8 conjunction collapse audit completed. 12/81 proved samples are H8. Genuine 26→14 (32.1%→17.3%). H8 JSON at /root/autodl-tmp/outputs/h7_classification/plan002_additive_b01_s42_h8.json\"}, \"notes\": \"H8 re-audit (2026-05-15): 81 proved samples. H7 (single premise=conclusion): 13/81=16.1%, H1 (multi-prem conclusion embedding): 42/81=51.9%, H8 (conjunction collapse): 12/81=14.8%, content-independent: 19/81=23.5%. Genuine (proved - H7 - H1 - H8): 14/81=17.3%. Pre-H8 genuine was 26/81=32.1% — H8 removed 12 samples. Combined conclusion duplication+conjunction = 82.7%. Eval source: proofwriter_fol_100.jsonl (backup at /root/autodl-tmp/eval_results_backup/). H8 JSON: /root/autodl-tmp/outputs/h7_classification/plan002_additive_b01_s42_h8.json. ⚠️ RECLASSIFIED negative (Reviewer WARNING): 500步快照 genuine 30.9%（H8 未扣除，为上界），1000步崩塌至 2.2%，表明 Goodhart collapse 已在 500 步启动但未完成。\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan002_additive_b01_s42\", \"completed_at\": \"2026-05-14T06:47:26.358Z\", \"genuine_count\": 14, \"h1_near_count\": null, \"taxonomy_note\": \"H1-near analysis infeasible: eval_sta deleted; genuine=14 computed from aggregated H7+H1_exact+H8 exclusion per D084. H1-near is supplementary-only (per-sample data available only for Random s42).\"}, \"plan002-additive-b01-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:36:16.367Z\", \"updated_at\": \"2026-05-15T14:27:04.296Z\", \"hypothesis\": \"ISR β=0.1 seed=43 多 seed 验证：plan002-b01-s42 (PR=0.81, ISR=0.337) 在 s43 下是否可复现？exec-only s43 是 degraded seed (PR=14%)，ISR β=0.1 能否拯救 bad seed？3-seed mean±std 用于论文 Claim 2 统计支撑。\", \"parent\": \"plan002-additive-b01-s42\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T08:45:10.999Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s43\\\"\", \"finished_at\": \"2026-05-14T09:41:23.932Z\", \"training_hours\": 0.94}, \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_b01_s43\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"466128\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s43.log\", \"submitted_at\": \"2026-05-14T08:45:54.837Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4096.6, \"gpu_hours\": 1.14}, \"pid\": \"466128\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b01-s43.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T09:41:25.536028+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.61, \"eval_n_proved\": 61, \"eval_n_problems\": 100, \"eval_proved_only_isr\": 0.83, \"h7_count\": 59, \"h7_rate\": 0.9672, \"h1_count\": 0, \"h1_rate\": 0, \"h1_near_count\": 0, \"h1_near_rate\": 0, \"h8_conjunction_collapse_count\": 0, \"h8_conjunction_collapse_rate\": 0, \"genuine_count\": 2, \"genuine_rate\": 0.0328, \"proved_single_premise_ratio\": 1, \"taxonomy_note\": \"structurally determined: proved_single_premise_ratio=1.0, all taxonomy categories except H7 are zero by construction. eval file lost but classification derivable from structure.\"}, \"conclusion\": \"negative\", \"notes\": \"NEGATIVE: conclusion duplication hacking 确认。100% proved 样本仅 1 premise，97% premise=conclusion（重言式 P→P）。ISR=0.506 是 artifact（唯一 premise 必然 necessary）。与 s44 相同失败模式。3-seed 中 s42 唯一可能 genuine（待验证），s43/s44 均 collapse。β=0.1 additive bonus 多 seed 可靠性不足。\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan002_additive_b01_s43/checkpoint-500\", \"completed_at\": \"2026-05-14T09:54:11.468Z\", \"h7_count\": 59, \"h1_count\": 0, \"genuine_count\": 2}, \"exp1-isr-b03-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:52:06.992Z\", \"updated_at\": \"2026-05-15T14:15:06.019Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"β=0.3 ISR seed 43: supplement for 3-seed statistics in Table 1. Reference: plan002-additive-b03-s42\", \"plan_id\": \"EXP-1\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * ISR)\", \"num_steps\": 500, \"beta\": 0.3, \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s43\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"963576\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s43/checkpoint-500/\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T23:07:44.402Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:07:45.360Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:07:50.234603+00:00\"}]}, \"notes\": \"D062/D063 INVALIDATED: eval used test_100.jsonl (wrong test set). Checkpoint deleted, cannot re-eval. Retrain as exp1-isr-b03-s43-r4.\", \"metrics\": {\"parse_rate\": 1, \"prove_rate\": 0.91, \"mean_isr\": 0.2575, \"isr_std\": 0.2363, \"median_isr\": 0.3333, \"proved_only_mean_isr\": 0.283, \"hacking_rate_strict_h7\": 0.022, \"hacking_rate_functional\": 0.3297, \"genuine_rate\": 0.6703, \"genuine_count\": 61, \"n_proved\": 91, \"n_problems\": 100, \"h1_conclusion_in_premise\": 0.747, \"eval_data\": \"test_100.jsonl\", \"eval_output\": \"/root/autodl-tmp/outputs/eval_sta_exp1_isr_b03_s43.json\"}, \"eval_metrics\": {\"prove_rate\": 0.91, \"mean_isr\": 0.2575, \"isr_std\": 0.2363, \"proved_only_isr\": 0.283, \"n_proved\": 91, \"h7_rate\": 0.022, \"h7_count\": 2, \"h1_rate\": 0.747, \"h1_count\": 68, \"genuine_rate\": 0.231, \"genuine_count\": 21, \"single_premise_rate\": 0.044, \"eval_data\": \"test_100.jsonl\"}, \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s43.log\"}, \"plan009-sft-baseline-s44-1000-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:55:38.775Z\", \"updated_at\": \"2026-05-15T14:14:37.264Z\", \"hypothesis\": \"SFT 1000步 seed=44（第三次重试）：r1/r2 均因 --gpu 0 覆盖 CUDA_VISIBLE_DEVICES 导致 OOM。本次用 --gpu 1 直接指定物理 GPU 1。验证 SFT 在 1000 步的 genuine rate 稳定性，完成 3-seed 统计。\", \"parent\": \"plan009-sft-baseline-s44-1000-r2\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44}, \"pid\": \"353656\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s44-1000-r3.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000 --num_steps 1000 --seed 44 --no_wandb --gpu 1\\\"\", \"finished_at\": \"2026-05-15T13:24:08.251Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:24:12.025706+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.15, \"eval_n_proved\": 15, \"eval_n_problems\": 100, \"eval_mean_isr\": 0.0884, \"eval_isr_std\": 0.2268, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.5892, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_method\": \"eval_sta.py full STA\", \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 1, \"h1_rate\": 0.0667, \"h8_conjunction_collapse_count\": 0, \"h8_conjunction_collapse_rate\": 0, \"genuine_count\": 14, \"genuine_rate\": 0.9333, \"eval_by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 15, \"prove_rate\": 0.441, \"mean_isr\": 0.26}, \"false\": {\"count\": 25, \"proved\": 0, \"prove_rate\": 0, \"mean_isr\": 0}, \"unknown\": {\"count\": 41, \"proved\": 0, \"prove_rate\": 0, \"mean_isr\": 0}}}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000\", \"completed_at\": \"2026-05-15T14:11:36.232Z\"}, \"plan009-sft-baseline-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:32:29.554Z\", \"updated_at\": \"2026-05-15T14:14:33.719Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"188375\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s44.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s44 --num_steps 500 --seed 44 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T08:25:36.539Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T08:25:40.098764+00:00\"}]}, \"metrics\": {\"train_final_loss\": 0.2397, \"train_last_step_loss\": 0.0328, \"train_token_accuracy\": 0.9928, \"train_epochs\": 7.94, \"train_runtime_sec\": 729.05, \"train_steps\": 500, \"eval_prove_rate\": 0.17, \"eval_n_proved\": 17, \"eval_n_problems\": 100, \"eval_mean_isr\": 0.0974, \"eval_isr_std\": 0.2409, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.5729, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_method\": \"eval_sta.py full STA\", \"eval_output_path\": \"/root/autodl-tmp/outputs/eval_sta_plan009_sft_s44.json\", \"eval_tautological_collapse\": false, \"eval_h7_count\": 0, \"eval_h7_rate\": 0, \"eval_h1_count\": 2, \"eval_h1_rate\": 0.118, \"eval_genuine_count\": 15, \"eval_genuine_rate\": 0.882, \"eval_by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 15, \"prove_rate\": 0.441, \"mean_isr\": 0.257}, \"false\": {\"count\": 25, \"proved\": 1, \"prove_rate\": 0.04, \"mean_isr\": 0.027}, \"unknown\": {\"count\": 41, \"proved\": 1, \"prove_rate\": 0.024, \"mean_isr\": 0.008}}, \"eval_correction_note\": \"Corrected 2026-05-15: previous eval used test_100.jsonl (50/44/6 distribution), re-evaled with proofwriter_fol_100.jsonl (34/25/41)\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s44\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T08:32:34.374Z\"}, \"plan009-sft-baseline-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:08:54.164Z\", \"updated_at\": \"2026-05-15T14:14:22.594Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"171222\", \"log_path\": \"/root/runs/solver-trace-ablation/plan009-sft-baseline-s43.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s43 --num_steps 500 --seed 43 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T07:42:41.848Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T07:42:44.711163+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s43\", \"metrics\": {\"train_loss\": 0.2391, \"train_token_accuracy\": 0.9938, \"train_epochs\": 7.94, \"train_runtime_sec\": 677.14, \"train_steps\": 500, \"eval_prove_rate\": 0.15, \"eval_mean_isr\": 0.0895, \"eval_isr_std\": 0.2338, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.5967, \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 1, \"h1_rate\": 0.067, \"genuine_count\": 14, \"genuine_rate\": 0.933, \"by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 13, \"prove_rate\": 0.382, \"mean_isr\": 0.234}, \"false\": {\"count\": 25, \"proved\": 1, \"prove_rate\": 0.04, \"mean_isr\": 0.027}, \"unknown\": {\"count\": 41, \"proved\": 1, \"prove_rate\": 0.024, \"mean_isr\": 0.008}}, \"eval_data_path\": \"data/proofwriter_fol_100.jsonl\", \"eval_output_path\": \"/root/autodl-tmp/outputs/eval_sta_plan009_sft_s43.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T07:52:31.794Z\"}, \"plan001-exec-only-s44-1000\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:22:45.226Z\", \"updated_at\": \"2026-05-15T13:50:32.148Z\", \"hypothesis\": \"Exec-only GRPO 1000步 seed=44：与 plan016(s42) 相同配置的第三个 seed。完成 3-seed exec-only 1000步统计，与 SFT 1000步 3-seed 对照，统计支撑 Goodhart collapse 是 RL 特有现象的 claim。\", \"parent\": \"plan016-extended-1000-s42\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 44 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s44_1000\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"357074\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s44-1000.log\", \"submitted_at\": \"2026-05-15T13:28:02.714Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1335.7, \"gpu_hours\": 0.37}, \"pid\": \"357074\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s44-1000.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 44 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s44_1000\\\"\", \"finished_at\": \"2026-05-15T13:50:19.963Z\"}, \"conclusion\": \"failed\", \"failure_reason\": \"磁盘满 (/dev/md0 250G/250G)，进程被手动 kill 防止 checkpoint 损坏。需从 step 0 重跑。\", \"completed_at\": \"2026-05-15T13:50:18.432Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:50:24.979972+00:00\"}]}}, \"plan001-exec-only-s43-1000\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:22:44.661Z\", \"updated_at\": \"2026-05-15T13:48:08.794Z\", \"hypothesis\": \"Exec-only GRPO 1000步 seed=43：与 plan016(s42) 相同配置的第二个 seed。3-seed exec-only 1000步统计，验证 Goodhart collapse（genuine→0%）在 exec-only 条件下的可重复性。与 SFT 1000步 3-seed 对照，确认 collapse 是 RL(GRPO) 特有现象。\", \"parent\": \"plan016-extended-1000-s42\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-15T13:23:32.864Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43_1000\\\"\", \"finished_at\": \"2026-05-15T13:45:01.320Z\", \"training_hours\": 0.36}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43_1000\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"356071\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43-1000.log\", \"submitted_at\": \"2026-05-15T13:23:35.275Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1288.0, \"gpu_hours\": 0.36}, \"pid\": \"356071\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43-1000.log\", \"failure_reason\": \"磁盘满 (os error 28): /root/autodl-tmp/ 250G/250G (100%)，step 150 保存 checkpoint 时 safetensors serialize 失败。checkpoint-100 完整可用(15GB)，checkpoint-150 不完整(仅2/4 shards)。分类: disk_full, retryable。\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T13:45:03.313Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:45:05.583858+00:00\"}]}}, \"plan009-sft-baseline-s44-1000-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:53:24.774Z\", \"updated_at\": \"2026-05-15T12:56:27.871Z\", \"hypothesis\": \"SFT 1000步 seed=44（重试）：r1 因 CUDA_VISIBLE_DEVICES 未设导致 OOM 失败。与 s42/s43 相同配置的第三个 seed，验证 SFT 在 1000 步的 genuine rate 稳定性。3-seed 统计支撑 Goodhart collapse 是 RL (GRPO) 特有现象的 claim。\", \"parent\": \"plan009-sft-baseline-s44-1000\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000 --num_steps 1000 --seed 44 --no_wandb --gpu 0\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"353256\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s44-1000-r2.log\", \"submitted_at\": \"2026-05-15T12:53:53.733Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 32.2, \"gpu_hours\": 0.01}, \"pid\": \"353256\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s44-1000-r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s44_1000 --num_steps 1000 --seed 44 --no_wandb --gpu 0\\\"\", \"finished_at\": \"2026-05-15T12:54:24.026Z\"}, \"failure_reason\": \"CUDA OOM: 重试 r2 在已被 plan009-sft-baseline-s43-1000 (PID 352142) 占用的 GPU 0 上启动，仅剩 100.25 MiB 可用显存。原始实验 plan009-sft-baseline-s44-1000 仍在 cuda:1 正常运行，此 r2 为冗余重试，无需再次重试。\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T12:54:25.923Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T12:54:28.360459+00:00\"}]}}, \"plan002-additive-b03-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T02:24:47.843Z\", \"updated_at\": \"2026-05-15T12:45:27.465Z\", \"spec\": {\"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Additive ISR bonus r=r_exec*(1+β*ISR) with β=0.3: ISR can only boost reward, never penalize. Should preserve prove_rate (unlike convex combination penalty in plan005) while improving structural quality.\", \"plan_id\": \"plan_002\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * ISR)\", \"beta\": 0.3, \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/plan002_additive_beta03_s42\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"161819\"}, \"reproduce\": {\"finished_at\": \"2026-05-14T03:24:44.110Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T03:24:48.666027+00:00\"}]}, \"metrics\": {\"total_steps\": 500, \"duration_min\": 56.7, \"overall_prove_rate\": 0.34025, \"overall_isr\": 0.11527, \"last100_prove_rate\": 0.5525, \"eval_prove_rate\": 0.18, \"eval_mean_isr\": 0.0257, \"eval_isr_std\": 0.0742, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.1427, \"eval_n_proved\": 18, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 0.778, \"h1_count\": 14, \"h8_conjunction_collapse_count\": 3, \"h8_conjunction_collapse_rate\": 0.1667, \"genuine_rate\": 0.0556, \"genuine_count\": 1, \"eval_by_type_false_pr\": 0.12, \"eval_by_type_false_isr\": 0.0102, \"eval_by_type_unknown_pr\": 0.195, \"eval_by_type_unknown_isr\": 0.0422, \"eval_by_type_true_pr\": 0.206, \"eval_by_type_true_isr\": 0.0172, \"h8_audit_note\": \"2026-05-15: H8 conjunction collapse added. genuine 4→1.\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan002_additive_beta03_s42\", \"log_path\": \"~/runs/solver-trace-ablation/plan002-additive-b03-s42.log\", \"notes\": \"ISR 为 binary 近似 (_fast_fn)，不可用于论文跨 run 对比，需 eval_sta.py 统一评估真实 ISR。prove_rate 轨迹 0.13→0.095→0.185→0.375→0.476→0.553，呈稳步上升趋势，尚未完全饱和（仅 52/500 步 ≥0.85），与 plan001/plan013 的强饱和模式不同。\", \"conclusion\": \"negative\", \"eval_prove_rate\": 0.18, \"eval_mean_isr\": 0.0257, \"eval_isr_std\": 0.0742, \"eval_proved_only_isr\": 0.1427, \"eval_median_isr\": 0, \"eval_isr_pr_ratio\": 0.1427, \"completed_at\": \"2026-05-14T04:27:38.822Z\", \"genuine_count\": 1, \"genuine_rate\": 0.056, \"h8_count\": 3}, \"plan001-exec-only-s42-r2\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-13T22:40:41.773Z\", \"updated_at\": \"2026-05-15T12:45:21.831Z\", \"completed_at\": \"2026-05-13T23:46:00Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\"}, \"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T23:46:01.596431+00:00\"}]}, \"spec\": {\"command\": \"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s42\", \"server\": \"westd-39279\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"500-step exec-only baseline for STA comparison (K=8)\", \"pid\": \"84901\", \"gpu\": [\"cuda:0\"], \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s42-r2.log\", \"submitted_at\": \"2026-05-13T22:42:40.204Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 3820, \"gpu_hours\": 1.06}, \"notes\": \"Cron 误判 DONE/failed（因 --help|grep 前缀命令的 PID 84896 退出，实际训练子进程 PID 84901 仍在运行）。已手动恢复 RUNNING。严禁在 cuda:0 启动新进程直到 r2 自然完成。⚠️ Reviewer 中期审查标注: 训练日志中 ISR=0.8612 为 binary approximation (_fast_fn)，非真实 ISR。最终可比 ISR 需通过 eval_sta.py (full STA) 重新评估。\", \"reproduce\": {\"finished_at\": \"2026-05-13T23:46:00.369Z\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s42/checkpoint-500\", \"log_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s42/reward_log.jsonl\", \"metrics\": {\"eval_prove_rate\": 0.93, \"eval_mean_isr\": 0.1232, \"eval_isr_std\": 0.1887, \"eval_proved_only_isr\": 0.1324, \"eval_median_isr\": 0, \"eval_n_proved\": 93, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 0.871, \"h1_count\": 81, \"h8_conjunction_collapse_count\": 6, \"h8_conjunction_collapse_rate\": 0.0645, \"genuine_rate\": 0.0753, \"genuine_count\": 7, \"genuine_mean_isr\": 0.3141, \"h1_mean_isr\": 0.1055, \"conclusion_embedding_total\": 0.871, \"content_independent_predicates_count\": 1, \"h8_audit_note\": \"2026-05-15: H8 conjunction collapse added. genuine 12→7.\"}, \"genuine_count\": 7, \"genuine_rate\": 0.075, \"h8_count\": 6}, \"plan004-o1-ablation-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T04:37:39.643Z\", \"updated_at\": \"2026-05-15T12:06:55.592Z\", \"hypothesis\": \"O(1) binary ISR (fast_isr_fol) vs O(N) full STA ablation: 100-step pilot showed binary ISR ≈ exec-only (all proved samples ISR=1). 500-step full run confirms O(1) is ineffective at scale — the LOO ablation (O(N)) is necessary for ISR to carry structural signal. Negative result strengthens paper's methodological contribution.\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T04:39:03.284Z\"}, \"spec\": {\"command\": \"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_fast_isr_ablation.yaml --output_dir /root/autodl-tmp/outputs/plan004_fast_isr_s42 --num_steps 500 --num_generations 8 --no_wandb\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"155099\", \"log_path\": \"/root/runs/solver-trace-ablation/plan004-o1-ablation-s42.log\", \"submitted_at\": \"2026-05-15T12:50:15Z\", \"submitted_via\": \"manual_tmux\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"O(1) binary ISR (fast_isr_fol) vs O(N) full STA ablation. fast_sta_reward returns 1.0 for all proved samples, losing partial redundancy signal. Expected negative result.\", \"reward_formula\": \"r = 0.5 * exec + 0.5 * fast_ISR\", \"plan_id\": \"plan004\", \"output_dir\": \"/root/autodl-tmp/outputs/plan004_fast_isr_s42\"}, \"metrics\": {\"prove_rate\": 0.63, \"mean_isr\": 0.0072, \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 63, \"h1_rate\": 1, \"h8_conjunction_collapse_count\": 2, \"h8_conjunction_collapse_rate\": 0.0317, \"genuine_count\": 0, \"genuine_rate\": 0, \"content_independent_predicates_count\": 3, \"h8_audit_note\": \"2026-05-15: H8 conjunction collapse added. genuine unchanged (0).\"}, \"conclusion\": \"negative\", \"notes\": \"NEGATIVE (expected): O(1) binary ISR (fast_isr) 训练 500 步后 eval ISR=0.0072（本质为0）。模型生成大量冗余 premise（如62+重复 ground facts），per-clause ablation 删任一重复不影响结果，ISR趋近0。与 exec-only 的 ISR 崩塌模式一致（ISR=0.003）。确认 O(1) binary ISR 退化为 exec-only——LOO ablation (O(N)) 是 ISR 携带结构信号的必要条件。此负向结果强化论文方法论贡献：O(N) 复杂度有其必要性。PR=63% 低于 exec-only s42 (93%) 和 ISR β=0.1 s42 (81%)。\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan004_fast_isr_s42/checkpoint-500\", \"log_path\": \"/root/runs/solver-trace-ablation/plan004-o1-ablation-s42.log\", \"completed_at\": \"2026-05-15T06:21:42.630Z\"}, \"exp1-isr-b03-s42-1000-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:31:37.813Z\", \"updated_at\": \"2026-05-15T11:52:23.241Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s42_1000 --num_steps 1000 --beta 0.3 --seed 42 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"224651\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s42-1000-r2.log\", \"submitted_at\": \"2026-05-15T09:32:05.796Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7320.6, \"gpu_hours\": 2.03}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"224651\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s42-1000-r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s42_1000 --num_steps 1000 --beta 0.3 --seed 42 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T11:27:09.017Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T11:27:13.616148+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.95, \"eval_mean_isr\": 0.734, \"eval_isr_std\": 0.2575, \"eval_median_isr\": 0.6, \"eval_proved_only_isr\": 0.7726, \"eval_n_proved\": 95, \"eval_n_problems\": 100, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 25, \"prove_rate\": 1, \"mean_isr\": 0.824}, \"unknown\": {\"count\": 41, \"proved\": 38, \"prove_rate\": 0.927, \"mean_isr\": 0.673}, \"true\": {\"count\": 34, \"proved\": 32, \"prove_rate\": 0.941, \"mean_isr\": 0.741}}, \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 54, \"h1_rate\": 0.568, \"genuine_count\": 0, \"genuine_rate\": 0, \"tautological_collapse\": true, \"isr_1_count\": 41, \"isr_1_rate\": 0.432, \"single_premise_count\": 0, \"train_final_prove_rate\": 0.829, \"train_final_mean_isr\": 0.727, \"train_loss\": 0.0041, \"train_runtime_seconds\": 6280, \"train_final_entropy\": 9e-06, \"completions_mean_length\": 47, \"h8_conjunction_collapse_count\": 41, \"h8_conjunction_collapse_rate\": 0.432, \"content_independent_predicates\": true}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s42_1000\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T11:34:06.399Z\"}, \"plan018-additive-random-b01-s42-1000-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:31:40.077Z\", \"updated_at\": \"2026-05-15T11:31:44.382Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000/checkpoint-350 --data_path data/train_500_seed42.jsonl --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000 --num_steps 1000 --beta 0.1 --seed 42 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"224797\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42-1000-r2.log\", \"submitted_at\": \"2026-05-15T09:32:10.554Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7173.8, \"gpu_hours\": 1.99}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"224797\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42-1000-r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000/checkpoint-350 --data_path data/train_500_seed42.jsonl --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000 --num_steps 1000 --beta 0.1 --seed 42 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T10:23:56.400Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T10:23:59.009335+00:00\"}]}, \"metrics\": {\"train_final_prove_rate\": 0.989, \"train_final_mean_isr\": 0.353, \"train_final_reward\": 1.062, \"train_steps\": 1000, \"train_runtime_seconds\": 2957, \"eval_prove_rate\": 1, \"eval_mean_isr\": 0.3333, \"eval_isr_std\": 0, \"eval_median_isr\": 0.3333, \"eval_proved_only_isr\": 0.3333, \"eval_n_proved\": 100, \"eval_n_problems\": 100, \"eval_component_count_mean\": 3, \"genuine_rate\": 0, \"genuine_count\": 0, \"tautological_collapse\": true, \"h7_rate\": null, \"h7_count\": null, \"h1_rate\": null, \"h1_count\": null}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000\", \"completed_at\": \"2026-05-15T11:31:44.382Z\"}, \"plan018-additive-random-b01-s42-1000\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:08:56.941Z\", \"updated_at\": \"2026-05-15T09:25:12.327Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 42 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"197860\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42-1000.log\", \"submitted_at\": \"2026-05-15T08:28:46.060Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 3386.3, \"gpu_hours\": 0.94}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T08:28:44.610Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 1000 --seed 42 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s42_1000 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T09:25:10.249Z\", \"training_hours\": 0.94}, \"pid\": \"197860\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s42-1000.log\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T09:25:12.327Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:25:17.262043+00:00\"}]}}, \"exp1-isr-b03-s42-1000\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T08:55:55.364Z\", \"updated_at\": \"2026-05-15T09:24:46.558Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s42_1000 --num_steps 1000 --beta 0.3 --seed 42 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"219058\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s42-1000.log\", \"submitted_at\": \"2026-05-15T09:16:01.559Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 525.0, \"gpu_hours\": 0.15}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"219058\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s42-1000.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s42_1000 --num_steps 1000 --beta 0.3 --seed 42 --no_wandb\\\"\", \"finished_at\": \"2026-05-15T09:24:44.644Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T09:24:46.558Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:24:49.137230+00:00\"}]}}, \"plan001-exec-only-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T03:57:09.690Z\", \"updated_at\": \"2026-05-15T08:29:40.375Z\", \"hypothesis\": \"Exec-only seed=44 第3 seed: 解决 s42(93% eval PR) vs s43(13% eval PR) 的跨 seed 不稳定问题，3-seed mean±std 是论文必需。\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s44\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"226200\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s44.log\", \"submitted_at\": \"2026-05-14T04:29:05.471Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 2725.5, \"gpu_hours\": 0.76}, \"pid\": \"226200\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s44.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s44\\\"\", \"finished_at\": \"2026-05-14T05:06:39.227Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T05:06:40.707032+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.98, \"eval_mean_isr\": 0.57, \"eval_isr_std\": 0.2013, \"eval_median_isr\": 0.5, \"eval_proved_only_isr\": 0.5816, \"eval_n_proved\": 98, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_component_count_mean\": 2.04, \"eval_component_count_2\": 94, \"eval_component_count_3\": 4, \"tautological_collapse\": true, \"h7_rate\": 1, \"h7_count\": 97, \"h1_rate\": 0, \"h1_count\": 0, \"genuine_rate\": 0, \"genuine_count\": 0, \"conclusion_embedding_total\": 1}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s44\", \"conclusion\": \"negative\", \"notes\": \"TAUTOLOGICAL COLLAPSE 确认。eval PR=98% 但 94% 样本仅 2 components (premise=conclusion tautology)，mean components=2.04，与 plan013 random reward 完全一致。ISR≈0.5 是 2-component artifact。s42 是唯一产生 genuine proofs (mean components=6.58) 的 seed。3-seed 结果：s42=genuine, s43=degraded(PR=13%), s44=tautological(PR=98% fake)。Exec-only reward 2/3 seeds 失败。\", \"completed_at\": \"2026-05-14T05:14:30.940Z\", \"h7_count\": 98}, \"plan018-additive-random-b01-s43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:01:24.111Z\", \"updated_at\": \"2026-05-15T06:39:54.823Z\", \"hypothesis\": \"Random β=0.1 seed=43 控制组 r2: 重试 (原 s43 step 200 磁盘满崩溃)。与 plan002-b01-s43 (ISR β=0.1) 同 seed 对照。3-seed mean±std 审稿硬性要求。\", \"parent\": \"plan018-additive-random-b01-s43\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s43_r2\\\"\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s43_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"858386\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s43-r2.log\", \"submitted_at\": \"2026-05-14T15:24:32.942Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan018_additive_random_b01_s43_r2\", \"wall_clock_seconds\": 6748.8, \"gpu_hours\": 1.87}, \"pid\": \"858386\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s43-r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s43_r2\\\"\", \"finished_at\": \"2026-05-14T16:43:53.042Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T16:43:54.952857+00:00\"}]}, \"metrics\": {\"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 93.2, \"h1_count\": 82, \"genuine_rate\": 6.8, \"genuine_count\": 6, \"eval_prove_rate\": 0.88, \"eval_mean_isr\": 0.058}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T17:17:01.774Z\"}, \"exp1-random-b03-s44-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:42:02.173Z\", \"updated_at\": \"2026-05-15T03:07:35.496Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.3 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/exp1_random_b03_s44_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": 51297, \"log_path\": \"/root/autodl-tmp/outputs/eval_sta_exp1_random_b03_s44_r2.json\", \"submitted_at\": \"2026-05-15T00:42:39.447Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"hypothesis\": \"Random beta=0.3 s44: 3-seed random control for Claim 2\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * random[0,1])\", \"plan_id\": \"EXP-1\", \"parent\": \"exp1-random-b03-s44\", \"output_dir\": \"/root/autodl-tmp/outputs/exp1_random_b03_s44_r2\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_random_b03_s44_r2\", \"wall_clock_seconds\": 8595.6, \"gpu_hours\": 2.39}, \"reproduce\": {\"finished_at\": \"2026-05-15T02:26:26.919Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T02:26:39.221668+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"eval_prove_rate\": 0.23, \"eval_proved_only_mean_isr\": 0, \"eval_mean_isr\": 0, \"eval_isr_std\": 0, \"eval_median_isr\": 0, \"eval_n_proved\": 23, \"eval_n_problems\": 100, \"eval_h7_strict_rate\": 0, \"eval_h7_strict_count\": 0, \"eval_h1_strict_rate\": 1, \"eval_h1_strict_count\": 23, \"eval_genuine_rate\": 0, \"eval_genuine_count\": 0, \"eval_data\": \"proofwriter_fol_100.jsonl\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_random_b03_s44_r2/checkpoint-500\", \"log_path\": \"/root/autodl-tmp/outputs/exp1_random_b03_s44_r2/reward_log.jsonl\", \"completed_at\": \"2026-05-15T03:05:55.070Z\"}, \"exp1-isr-b03-s43-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:02:10.292Z\", \"updated_at\": \"2026-05-15T02:39:55.709Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s43_r3\\\"\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"pid\": 58051, \"log_path\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s43_r3/reward_log.jsonl\", \"submitted_at\": \"2026-05-15T01:02:18.804Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"output_dir\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s43_r3\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s43_r3\", \"wall_clock_seconds\": 4321.2, \"gpu_hours\": 1.2}, \"conclusion\": \"success\", \"notes\": \"Training completed 500/500 steps in 69min. Final stats: prove_rate=0.56125, mean_isr=0.1515, parse_rate=1.0. Checkpoint saved at checkpoint-500. EVAL: PR=0.86 (greedy), mean_ISR=0.2535, H7_strict=4/86(4.7%), H1_strict=59/86(68.6%), total_hacking=63/86(73.3%), genuine=23/86(26.7%). Hacking pattern: predominantly H1 (conclusion embedding in multi-premise), NOT H7 (unlike s44's 100% H7). Data: proofwriter_fol_100.jsonl.\", \"completed_at\": \"2026-05-15T02:14:19.967Z\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s43_r3/checkpoint-500\", \"log_path\": \"/root/runs/solver-trace-ablation/exp1-isr-b03-s43-r3.log\", \"metrics\": {\"final_step\": 500, \"prove_rate\": 0.56125, \"mean_isr\": 0.1515, \"parse_rate\": 1, \"train_loss\": 0.0176, \"train_runtime_sec\": 4153.6, \"epoch\": 2, \"eval_prove_rate\": 0.86, \"eval_mean_isr\": 0.2535, \"eval_isr_std\": 0.2406, \"eval_median_isr\": 0.3333, \"eval_proved_only_mean_isr\": 0.2948, \"eval_min_isr\": 0, \"eval_max_isr\": 0.75, \"eval_n_proved\": 86, \"eval_n_problems\": 100, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_h7_strict_rate\": 0.047, \"eval_h7_strict_count\": 4, \"eval_h1_strict_rate\": 0.686, \"eval_h1_strict_count\": 59, \"eval_conclusion_in_premise_rate\": 0.733, \"eval_conclusion_in_premise_count\": 63, \"eval_genuine_rate\": 0.267, \"eval_genuine_count\": 23, \"eval_single_premise_rate\": 0.058, \"eval_single_premise_count\": 5, \"eval_isr_1_count\": 0, \"eval_by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 23, \"prove_rate\": 0.92, \"mean_isr\": 0.334}, \"unknown\": {\"count\": 41, \"proved\": 35, \"prove_rate\": 0.854, \"mean_isr\": 0.199}, \"true\": {\"count\": 34, \"proved\": 28, \"prove_rate\": 0.824, \"mean_isr\": 0.26}}}}, \"exp1-random-b03-s43-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T02:34:11.247Z\", \"updated_at\": \"2026-05-15T02:37:49.701Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.3 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/exp1_random_b03_s43_r3\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"114576\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-random-b03-s43-r3.log\", \"submitted_at\": \"2026-05-15T02:34:10.754Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"beta=0.3 random s43 retry: supplement for 3-seed random statistics\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * random[0,1])\", \"plan_id\": \"EXP-1\", \"output_dir\": \"/root/autodl-tmp/outputs/exp1_random_b03_s43_r3\", \"wall_clock_seconds\": 218.9, \"gpu_hours\": 0.06}, \"reproduce\": {\"finished_at\": \"2026-05-15T02:37:46.271Z\"}, \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 28.00 MiB. GPU 0 has a total capacity of 94.97 GiB of which 24.25 MiB is free. Process 113293 has 81.17 GiB memory in use. Including non-PyTorch memory, this process has 13.77 GiB memory in use. Of the allocated \", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T02:37:49.701Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T02:37:52.575206+00:00\"}]}}, \"plan015-linear-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:05:37.944Z\", \"updated_at\": \"2026-05-15T02:36:29.622Z\", \"spec\": {\"command\": \"killed-cleanup\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"60030\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-15T01:05:52.053Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 5429.0, \"gpu_hours\": 1.51}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T02:36:21.092Z\"}, \"exp1-isr-b03-s43-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:07:39.840Z\", \"updated_at\": \"2026-05-15T02:36:28.581Z\", \"spec\": {\"command\": \"killed-cleanup\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"61219\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-15T01:07:48.622Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 5311.2, \"gpu_hours\": 1.48}, \"conclusion\": \"killed\", \"notes\": \"Duplicate of exp1-isr-b03-s43-r3 (already RUNNING on cuda:0). Created during D068 chaos, confirmed redundant at Loop #10.\", \"completed_at\": \"2026-05-15T02:36:19.862Z\"}, \"exp1-random-b03-s43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T02:30:55.259Z\", \"updated_at\": \"2026-05-15T02:36:22.901Z\", \"spec\": {\"command\": \"killed-cleanup\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"113288\", \"log_path\": \"N/A\", \"submitted_at\": \"2026-05-15T02:31:28.051Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"checkpoint_path\": \"N/A\", \"wall_clock_seconds\": 294.9, \"gpu_hours\": 0.08}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T02:36:22.901Z\"}, \"exp1-isr-b03-s44-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:21:38.601Z\", \"updated_at\": \"2026-05-15T01:09:36.604Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"hypothesis\": \"β=0.3 ISR seed 44 retry: original failed due to orphan process OOM on GPU 0. Same config as exp1-isr-b03-s44.\", \"plan_id\": \"EXP-1\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * ISR)\", \"num_steps\": 500, \"beta\": 0.3, \"parent\": \"exp1-isr-b03-s44\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s44_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"10597\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s44-r2.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T00:15:28.410Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T00:15:30.528573+00:00\"}]}, \"eval_metrics\": {\"prove_rate\": 0.98, \"mean_isr\": 0.7275, \"isr_std\": 0.1184, \"proved_only_isr\": 0.7423, \"n_proved\": 98, \"h7_rate\": 1, \"h7_count\": 98, \"h1_rate\": 0, \"h1_count\": 0, \"genuine_rate\": 0, \"genuine_count\": 0, \"single_premise_rate\": 1, \"eval_data\": \"test_100.jsonl\"}, \"conclusion\": \"success\", \"metrics\": {\"prove_rate\": 0.95, \"mean_isr\": 0.705, \"isr_std\": 0.172, \"proved_only_isr\": 0.7421, \"n_proved\": 95, \"n_problems\": 100, \"h7_rate\": 1, \"h7_count\": 95, \"h1_rate\": 0, \"h1_count\": 0, \"genuine_rate\": 0, \"genuine_count\": 0, \"single_premise_rate\": 1, \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_note\": \"Re-eval with correct test set (D062). Previous test_100.jsonl results invalidated.\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp1_isr_b03_s44_r2/checkpoint-500/\", \"completed_at\": \"2026-05-15T00:35:22.489Z\", \"notes\": \"D062/D063: eval_metrics used test_100.jsonl (invalidated). metrics field contains re-eval with proofwriter_fol_100.jsonl (valid). eval_invalidated applies only to eval_metrics.\"}, \"exp1-random-b03-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:06:04.388Z\", \"updated_at\": \"2026-05-15T00:36:20.012Z\", \"spec\": {\"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"hypothesis\": \"β=0.3 random seed 44: supplement for 3-seed statistics in Table 1. Reference: plan017-additive-random-s42\", \"plan_id\": \"EXP-1\", \"reward_formula\": \"r = r_exec * (1 + 0.3 * random[0,1])\", \"num_steps\": 500, \"beta\": 0.3, \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"account\": \"root\", \"command\": \"python3 scripts/train_grpo.py --config configs/grpo_additive_random.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.3 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/exp1_random_b03_s44\"}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"finished_at\": \"2026-05-15T00:36:18.060Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T00:36:20.012Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T00:36:27.151961+00:00\"}]}}, \"exp1-isr-b03-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:06:01.473Z\", \"updated_at\": \"2026-05-14T23:21:59.279Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s44\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"7303\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s44.log\", \"submitted_at\": \"2026-05-14T23:16:22.350Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 139.8, \"gpu_hours\": 0.04}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"7303\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s44.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s44\\\"\", \"finished_at\": \"2026-05-14T23:18:40.671Z\"}, \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 44.00 MiB. GPU 0 has a total capacity of 94.97 GiB of which 12.25 MiB is free. Process 5480 has 83.06 GiB memory in use. Including non-PyTorch memory, this process has 11.89 GiB memory in use. Of the allocated me\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T23:18:42.116Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:18:43.961885+00:00\"}]}, \"notes\": \"OOM on first submission: GPU 0 was occupied by orphan PID 5480 (exp1-isr-b03-s43-r2 training process survived tmux kill). Pending resubmission after GPU 0 cleared.\"}, \"exp1-isr-b03-s43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:09:49.339Z\", \"updated_at\": \"2026-05-14T23:15:53.081Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s43_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"5475\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s43-r2.log\", \"submitted_at\": \"2026-05-14T23:14:05.147Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 107.9, \"gpu_hours\": 0.03}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"5475\", \"log_path\": \"~/runs/solver-trace-ablation/exp1-isr-b03-s43-r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_bonus.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.3 --reward_mode additive_bonus --output_dir /root/autodl-tmp/outputs/exp1_isr_b03_s43_r2\\\"\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T23:15:53.081Z\"}, \"exp2-exec-s43-greedy\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:46:57.466Z\", \"updated_at\": \"2026-05-14T23:06:25.776Z\", \"spec\": {\"command\": \"eval_sta.py --greedy on plan001-exec-only-s43-r4 checkpoint\", \"server\": \"westd-39279\", \"data_path\": \"data/eval_100.jsonl\", \"data_count\": 100, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"EXP-2: Greedy re-eval of exec-only s43 to verify decoding invariance\", \"checkpoint_source\": \"plan001-exec-only-s43-r4\", \"eval_data\": \"data/eval_100.jsonl\", \"parent\": \"plan001-exec-only-s43-r4\", \"checkpoint_path\": \"N/A (eval only)\", \"log_path\": \"N/A (eval only)\", \"metrics\": {\"greedy_pr\": 0.13, \"greedy_isr_star\": 0, \"greedy_h1_pct\": 100, \"greedy_h7_pct\": 0, \"greedy_genuine_pct\": 0, \"sampling_pr\": 0.14, \"sampling_isr_star\": 0, \"conclusion_text\": \"s43 collapse is decoding-invariant. Both greedy and sampling show ISR*=0, H1=100%, genuine=0%\"}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:06:15.509Z\"}, \"exp4-100step-h1h7\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:47:55.686Z\", \"updated_at\": \"2026-05-14T23:06:24.790Z\", \"spec\": {\"command\": \"H1/H7 classification on plan003 (100-step exec-only checkpoint) eval outputs\", \"server\": \"westd-39279\", \"data_path\": \"plan003_eval_exec_only_r5.json\", \"data_count\": 100, \"model_name\": \"Qwen3-4B (100-step checkpoint)\", \"seed\": 42, \"hypothesis\": \"EXP-4: If hacking exists at 100-step PR=32%, supports RL-specific claim independent of PR level\", \"checkpoint_source\": \"sta-phase1-exec-only-r5\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/exp4_100step_h1h7_classification.json\", \"log_path\": \"N/A\", \"metrics\": {\"pr\": 0.32, \"isr_star\": 0.642, \"h7_pct\": 28.1, \"h1_pct\": 3.1, \"total_hacking_pct\": 31.2, \"genuine_pct\": 68.8, \"n_proved\": 32, \"h7_count\": 9, \"h1_count\": 1}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:06:14.584Z\"}, \"plan006-prolog-sta-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:19:39.743Z\", \"updated_at\": \"2026-05-14T18:47:53.131Z\", \"hypothesis\": \"Prolog exec+STA GRPO seed=44: 第三 seed。3-seed mean±std 用于论文 Claim 3 跨 logic type 统计支撑。\", \"notes\": \"Reviewer 独立核实: query-as-fact gaming, 0% genuine. 97/97 proved 样本中 95/97 n_necessary=1（功能性 H7）。模型将 NL 问题转为 snake_case atom 同时设为 fact 和 query，Prolog trivially 证明。PR=0.97, ISR=0.885 是 gaming artifact（高 ISR 因单 clause = query）。第三种 Goodhart pathway（vs s42 clean H7, s43 degenerate syntax H1）。对照: s42=negative (clean H7=100%), s43=negative (uppercase pseudo-Prolog H1=97.4%), s44=negative (query-as-fact gaming, functional H7=95/97).\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T16:46:42.163Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_sta.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --output_dir /root/autodl-tmp/outputs/plan006_prolog_sta_s44\\\"\", \"finished_at\": \"2026-05-14T18:17:19.877Z\", \"training_hours\": 1.51}, \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_sta.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --output_dir /root/autodl-tmp/outputs/plan006_prolog_sta_s44\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"908945\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-sta-s44.log\", \"submitted_at\": \"2026-05-14T16:52:27.078Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 5546.5, \"gpu_hours\": 1.54}, \"pid\": \"908945\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-sta-s44.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T18:17:22.483042+00:00\"}]}, \"metrics\": {\"pass_rate\": 0.97, \"isr_mean\": 0.885, \"isr_n_cl_ge3\": \"N/A (0 samples)\", \"n_clauses_dist\": \"78/100 single-clause, 22/100 two-clause\", \"h7_functional_rate\": 0.979, \"genuine_rate\": 0, \"premise_count_analysis\": \"100% artifact - zero samples with n_clauses>=3, model exclusively generates 1-2 clause programs\", \"failure_mode\": \"query-as-fact gaming (total H7 collapse)\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_sta_s44/\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T18:24:53.618Z\"}, \"plan006-prolog-sta-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:19:39.141Z\", \"updated_at\": \"2026-05-14T18:20:56.947Z\", \"hypothesis\": \"Prolog exec+STA GRPO seed=43: 跨 seed 稳定性检查。与 exec-only s43 对照。\", \"notes\": \"Eval: PR=0.38, ISR=0.185 proved-only. Strict classifier: H7=0%, H1=0%, Genuine=100%. 但功能分析显示所有 38 proved 样本 n_necessary=1（功能性 H7）。模型生成大写伪 Prolog（如 MARY_IS_AN_AVADEOTE.）—— 非标准语法，strict classifier 无法匹配 conclusion。与 s42 (clean H7=100%) 不同的 Goodhart 路径，但同样是 hacking。磁盘 240G/250G 需清理。\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_sta.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_sta_s43\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"901135\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-sta-s43.log\", \"submitted_at\": \"2026-05-14T16:36:41.878Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_sta_s43\", \"wall_clock_seconds\": 6158.3, \"gpu_hours\": 1.71}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"901135\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-sta-s43.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_sta.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_sta_s43\\\"\", \"finished_at\": \"2026-05-14T18:03:44.715Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T18:03:46.512937+00:00\"}]}, \"metrics\": {\"train\": {\"final_prove_rate\": 0.769, \"final_mean_isr\": 0.129, \"final_loss\": 0.0155, \"final_entropy\": 0.09, \"final_reward\": 0.573, \"completion_length_mean\": 143, \"train_runtime_seconds\": 5095, \"train_runtime_minutes\": 84.9}, \"eval\": {\"n_problems\": 100, \"n_proved\": 38, \"prove_rate\": 0.38, \"mean_isr\": 0.0704, \"isr_std\": 0.1263, \"median_isr\": 0, \"proved_only_mean_isr\": 0.1853, \"min_isr\": 0, \"max_isr\": 1, \"by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 11, \"prove_rate\": 0.44, \"mean_isr\": 0.1003}, \"unknown\": {\"count\": 41, \"proved\": 11, \"prove_rate\": 0.268, \"mean_isr\": 0.0394}, \"true\": {\"count\": 34, \"proved\": 16, \"prove_rate\": 0.471, \"mean_isr\": 0.0859}}}, \"h7_classification\": {\"h7_strict\": 0, \"h7_rate\": 0, \"h1_strict\": 37, \"h1_rate\": 0.974, \"conclusion_in_premise_total\": 37, \"conclusion_in_premise_rate\": 0.974, \"genuine_count\": 0, \"genuine_rate\": 0, \"isr_1_count\": 1, \"note\": \"1 pseudo-genuine sample (folio_1415) has query embedded in single mega-clause; all 38/38 proved samples are tautological\"}}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T18:19:20.203Z\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_sta_s43\"}, \"plan006-prolog-sta-s42\": {\"status\": \"DONE\", \"retry_count\": 2, \"created_at\": \"2026-05-14T09:19:38.117Z\", \"updated_at\": \"2026-05-14T16:49:42.052Z\", \"hypothesis\": \"Prolog exec+STA GRPO seed=42: ISR reward 在 Prolog logic type 上的效果。与 plan006-prolog-exec-s42 (exec-only) 对照，验证 STA/ISR 的 hacking 检测和 Goodhart 效应是否跨 logic type 泛化。\", \"server\": \"westd-39279\", \"gpu\": \"\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-14T09:49:40.272Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_sta.yaml --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan006_prolog_sta_s42\\\"\", \"finished_at\": \"2026-05-14T10:38:13.891Z\", \"training_hours\": 0.81}, \"failure_reason\": \"\", \"completed_at\": \"2026-05-14T09:46:00.917Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T09:46:02.621139+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T10:38:15.900825+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"第二次启动失败。根因：config reward_mode=execution_sta (0.5*exec+0.5*ISR) 可能与 FOL 实验不匹配，待 Director 确认后修复重启。cuda:1 释放给 plan018。\"}}, \"account\": \"root\", \"notes\": \"Eval metrics provenance: eval 在训练完成后立即在 westd-39279 服务器上运行 eval_sta.py，checkpoint 路径 /root/autodl-tmp/outputs/plan006_prolog_sta_s42/。Eval 结果由 Worker 从服务器 SSH 读取 eval_results.json 并手动录入 registry。Checkpoint 可能已被磁盘清理删除（C003 save_total_limit=1）。训练日志: ~/runs/solver-trace-ablation/plan006-prolog-sta-s42.log。H7 分类由 classify_h7.py 在 eval 目录上运行。\", \"spec\": {\"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"account\": \"root\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_sta.yaml --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan006_prolog_sta_s42\\\"\", \"pid\": \"506117\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-sta-s42.log\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_sta_s42/ (may be cleaned up per C003)\", \"metrics\": {\"cumulative_prove_rate\": 0.848, \"cumulative_mean_isr\": 0.787, \"final_prove_rate\": 1, \"final_isr\": 1, \"final_reward\": 1, \"saturation_onset_step\": 100, \"train_loss\": 0.00716, \"training_hours\": 0.78, \"final_entropy\": 0.01, \"final_completion_length\": 27, \"initial_completion_length\": 120, \"steps_at_perfect_reward\": 400, \"train_runtime_sec\": 2791, \"eval_prove_rate\": 0.5, \"eval_mean_isr\": 0.5, \"eval_proved_only_isr\": 1, \"eval_h7_rate\": 1, \"eval_h7_count\": 50, \"eval_proved_count\": 50, \"eval_total_count\": 100, \"eval_n_clauses_mean\": 1, \"eval_isr_distribution\": \"binary: 50x0 + 50x1\"}}, \"plan006-prolog-exec-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:13:35.647Z\", \"updated_at\": \"2026-05-14T16:27:18.570Z\", \"hypothesis\": \"Prolog exec-only GRPO seed=44: third seed for Prolog exec-only. Together with s42 (PR=83%, ISR=0.031) and s43, provides 3-seed evidence for cross-logic generalization claim (Claim 3). 3-seed mean±std required for paper.\", \"notes\": \"Eval 完成。PR=21% (3-seed 最低), ISR=0.081, proved_only_ISR=0.387 (max_ISR=1.0)。与 s42/s43 不同模式：PR 极低但 proved_only_ISR 较高，可能有少量样本 ISR=1 (H7-like)。Prolog exec-only 3-seed 汇总：s42 PR=83%/ISR=0.031, s43 PR=56%/ISR=0.008, s44 PR=21%/ISR=0.081。Mean PR=53.3%±31.1%, Mean ISR=0.040±0.037。跨 seed 极不稳定（PR std=31pp），与 FOL exec-only 一致。ISR 始终极低（<0.1），确认 Prolog exec-only 不产生 genuine reasoning traces。\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T13:43:55.707Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 44 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s44\\\"\", \"finished_at\": \"2026-05-14T15:20:42.126Z\", \"training_hours\": 1.61}, \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 44 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s44\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"479357\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s44.log\", \"submitted_at\": \"2026-05-14T13:43:57.850Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 9800.7, \"gpu_hours\": 2.72}, \"pid\": \"479357\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s44.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T15:20:44.093424+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.21, \"eval_mean_isr\": 0.0812, \"eval_isr_std\": 0.2343, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.3866, \"eval_min_isr\": 0, \"eval_max_isr\": 1, \"eval_n_proved\": 21, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_elapsed_seconds\": 683.9, \"eval_by_type_false_pr\": 0.04, \"eval_by_type_false_isr\": 0.04, \"eval_by_type_unknown_pr\": 0.317, \"eval_by_type_unknown_isr\": 0.099, \"eval_by_type_true_pr\": 0.206, \"eval_by_type_true_isr\": 0.09, \"solver\": \"PrologSolver\", \"logic_type\": \"prolog\"}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_exec_s44/checkpoint-500\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T16:27:18.570Z\"}, \"plan009-sft-baseline-s42-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:40:28.142Z\", \"updated_at\": \"2026-05-14T16:27:01.864Z\", \"hypothesis\": \"SFT baseline: supervised finetuning on FOLIO data (500 steps, Qwen3-4B, same model as all GRPO experiments) to establish whether hacking patterns are GRPO-specific or general finetuning artifacts. r4: fix CUDA_VISIBLE_DEVICES + --gpu + --no_wandb.\", \"parent\": \"plan009-sft-baseline-s42-r2\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s42 --num_steps 500 --seed 42 --no_wandb --gpu 1\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42/checkpoint-500/\"}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"notes\": \"r4 训练完成 (500 steps, TRL SFT). Checkpoint 实际保存在 plan009_sft_baseline_s42（非 plan009_sft_s42_r4）。两卡满载 (cuda:0 80GB, cuda:1 80GB)，eval 待 GPU 释放。checkpoint-500/ 含 15GB optimizer.pt 可在 eval 后清理。\", \"reproduce\": {\"finished_at\": \"2026-05-14T12:18:55.639Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T12:18:57.313588+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42/checkpoint-500/\", \"log_path\": \"/root/autodl-tmp/outputs/plan009_sft_baseline_s42/checkpoint-500/trainer_state.json\", \"metrics\": {\"eval_prove_rate\": 0.14, \"eval_mean_isr\": 0.08, \"eval_isr_std\": 0.214, \"eval_median_isr\": 0, \"eval_max_isr\": 0.833, \"eval_proved_only_isr\": 0.571, \"eval_n_proved\": 14, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"train_final_loss\": 0.0287, \"train_token_accuracy\": 0.9935, \"train_epochs\": 7.94, \"train_runtime_sec\": 789.6, \"by_answer_type\": {\"true\": {\"count\": 34, \"proved\": 13, \"pr\": 0.382, \"isr\": 0.226}, \"unknown\": {\"count\": 41, \"proved\": 1, \"pr\": 0.024, \"isr\": 0.008}, \"false\": {\"count\": 25, \"proved\": 0, \"pr\": 0, \"isr\": 0}}, \"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 0.071, \"h1_count\": 1, \"genuine_rate\": 0.929, \"genuine_count\": 13, \"hacking_patterns\": \"near-zero (1/14 H1, 0 H7, 92.9% genuine)\", \"tautological_collapse\": false}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T14:20:25.035Z\"}, \"plan006-prolog-exec-s43-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:38:23.818Z\", \"updated_at\": \"2026-05-14T16:16:56.523Z\", \"hypothesis\": \"Prolog exec-only GRPO seed=43 r3: warmup_ratio=0.0 与 s42 一致。r2 因残留进程 OOM 失败，cuda:1 已清理。\", \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-14T13:44:06.728Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s43_r3\\\"\", \"finished_at\": \"2026-05-14T15:54:25.754Z\", \"training_hours\": 2.17}, \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s43_r3\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"483820\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s43-r3.log\", \"submitted_at\": \"2026-05-14T13:44:08.516Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 9168.0, \"gpu_hours\": 2.55}, \"pid\": \"483820\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s43-r3.log\", \"notes\": \"Eval 完成。PR=56% (远低于 s42 的 83%), ISR=0.0084 (与 s42 的 0.031 同量级，均极低)。proved_only_ISR=0.015。Prolog exec-only 跨 seed 表现：s42 PR=83%/ISR=0.031, s43 PR=56%/ISR=0.008。s43 prove_rate 显著下降但 ISR 模式一致（极低，ground fact enumeration hacking）。与 FOL exec-only 类似，存在跨 seed 不稳定性（FOL: s42=93%, s43=14%, s44=98%）。等 s44 eval 完成后计算 3-seed mean±std。\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T15:54:27.521808+00:00\"}]}, \"metrics\": {\"eval_prove_rate\": 0.56, \"eval_mean_isr\": 0.0084, \"eval_isr_std\": 0.0221, \"eval_median_isr\": 0, \"eval_proved_only_isr\": 0.015, \"eval_min_isr\": 0, \"eval_max_isr\": 0.1, \"eval_n_proved\": 56, \"eval_n_problems\": 100, \"eval_method\": \"eval_sta.py full STA\", \"eval_data\": \"proofwriter_fol_100.jsonl\", \"eval_elapsed_seconds\": 868.2, \"eval_by_type_false_pr\": 0.48, \"eval_by_type_false_isr\": 0.0043, \"eval_by_type_unknown_pr\": 0.6585, \"eval_by_type_unknown_isr\": 0.0114, \"eval_by_type_true_pr\": 0.5, \"eval_by_type_true_isr\": 0.0078, \"solver\": \"PrologSolver\", \"logic_type\": \"prolog\"}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_exec_s43_r3/checkpoint-500\", \"completed_at\": \"2026-05-14T16:16:56.523Z\"}, \"plan018-additive-random-b01-s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:36:18.722Z\", \"updated_at\": \"2026-05-14T15:00:09.178Z\", \"hypothesis\": \"Random β=0.1 seed=44 控制组：与 plan002-b01-s44 (ISR β=0.1) 同 seed 对照。验证 ISR 3.2x > random 的结论在 s44 下是否成立。\", \"parent\": \"plan018-additive-random-b01-s42\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T11:34:13.338Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s44\\\"\", \"finished_at\": \"2026-05-14T13:37:42.200Z\", \"training_hours\": 2.06}, \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 44 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s44\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"564900\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 44, \"reward_formula\": \"r = r_exec * (1 + 0.1 * random[0,1])\", \"num_steps\": 500}, \"pid\": \"564900\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s44.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:37:43.236026+00:00\"}]}, \"metrics\": {\"prove_rate\": 0.89, \"mean_isr\": 0.0619, \"isr_std\": 0.1756, \"median_isr\": 0, \"proved_only_mean_isr\": 0.0695, \"n_proved\": 89, \"n_problems\": 100, \"max_isr\": 1, \"min_isr\": 0, \"isr_pr_ratio\": 0.0695, \"isr_zero_count\": 72, \"isr_one_count\": 2, \"by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 21, \"prove_rate\": 0.84, \"mean_isr\": 0.0533}, \"unknown\": {\"count\": 41, \"proved\": 40, \"prove_rate\": 0.976, \"mean_isr\": 0.0892}, \"true\": {\"count\": 34, \"proved\": 28, \"prove_rate\": 0.824, \"mean_isr\": 0.0353}}, \"elapsed_seconds\": 1012.7, \"eval_method\": \"eval_sta.py with Prover9Solver, FOL\"}, \"conclusion\": \"success\", \"notes\": \"DONE (success). Random β=0.1 s44 对照分析完成: PR=0.89/ISR=0.062 (clean) vs ISR β=0.1 s44 PR=0.89/ISR=0.803 (H7=86.5% inflated). 同 PR 下 ISR reward 导致 conclusion duplication，random 无此问题。与 s42 结论一致: ISR s42 genuine ISR=0.337 vs Random s42 ISR=0.104 (3.2x)。Random 2/3 seeds done, 等 s43 (plan018-random-b01-s43-r2 QUEUED)。\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan018_additive_random_b01_s44/checkpoint-500\", \"completed_at\": \"2026-05-14T14:29:21.226Z\"}, \"plan009-sft-baseline-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:51:58.328Z\", \"updated_at\": \"2026-05-14T14:20:43.363Z\", \"hypothesis\": \"SFT baseline: supervised finetuning on FOLIO data (500 steps, Qwen3-4B) to establish whether hacking patterns are GRPO-specific or general finetuning artifacts. Same model as all GRPO experiments for fair comparison.\", \"conclusion\": \"killed\", \"notes\": \"模型必须改为 Qwen3-4B（与 GRPO 实验一致）。用 Qwen2.5-1.5B 无法作为 fair baseline——模型不同无法隔离训练方法差异。修正模型后重新注册提交。\", \"completed_at\": \"2026-05-14T14:20:42.452Z\"}, \"plan006-prolog-exec-s43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:32:37.140Z\", \"updated_at\": \"2026-05-14T13:43:01.701Z\", \"hypothesis\": \"Prolog exec-only GRPO seed=43 r2: 修正 warmup_ratio=0.0 与 s42 一致。cross-seed stability check for Prolog logic type.\", \"parent\": \"plan006-prolog-exec-s43\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s43_r2\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"712243\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s43-r2.log\", \"submitted_at\": \"2026-05-14T12:33:05.887Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 136.2, \"gpu_hours\": 0.04}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"712243\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s43-r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s43_r2\\\"\", \"finished_at\": \"2026-05-14T12:35:20.730Z\"}, \"failure_reason\": \"CUDA OOM: CUDA out of memory. Tried to allocate 48.00 MiB. GPU 0 has a total capacity of 94.97 GiB of which 40.25 MiB is free. Process 587160 has 78.09 GiB memory in use. Including non-PyTorch memory, this process has 16.83 GiB memory in use. Of the allocated \", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T12:35:22.121Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T12:35:23.802887+00:00\"}]}, \"notes\": \"OOM 诊断：非 batch size 问题。根因是 kill_job 只杀了 tmux 包装进程 (PID 587155)，训练子进程 587159/587160 残留在 cuda:1 上占 78.09 GiB 显存。s43-r2 启动时 cuda:1 仅剩 40 MiB free，首次前向传播即 OOM (尝试分配 48 MiB)。教训：kill_job 后必须 SSH 确认子进程也已终止（ps aux grep + nvidia-smi），不能只看 PID 返回成功。\"}, \"plan006-prolog-exec-s42\": {\"status\": \"DONE\", \"retry_count\": 2, \"created_at\": \"2026-05-14T07:13:34.169Z\", \"updated_at\": \"2026-05-14T12:33:17.845Z\", \"hypothesis\": \"Prolog exec-only GRPO seed=42: STA/ISR hacking patterns generalize across logic types? Prolog uses rule ablation (vs FOL axiom ablation). If same degeneration modes appear → STA is logic-agnostic diagnostic.\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T09:49:36.534Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s42\\\"\", \"finished_at\": \"2026-05-14T11:29:25.346Z\", \"training_hours\": 1.66}, \"failure_reason\": \"\", \"completed_at\": \"2026-05-14T09:47:36.390Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T09:47:38.546001+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T11:29:27.709792+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"失败原因: FileNotFoundError — data/prolog/train_500_seed42.jsonl 不存在 | error_type: data | 同一原因影响所有 plan006 实验 (exec/sta × s42/s43/s44) | 建议: 需先生成 Prolog 训练数据再重试\"}}, \"account\": \"root\", \"notes\": \"Eval (eval_sta.py) 完成。PR=83%, mean_ISR=0.031, proved_only_ISR=0.037, H7=0%, H1=0%。与 sta-s42 (PR=50%, ISR=1.0, H7=100%) 形成鲜明对比。exec-only 产生完全不同的 hacking 模式：ground fact enumeration（倾泻大量无关 ground facts，query 作为其中一个 fact 平凡成功），而非 sta-s42 的 tautological collapse。两种 reward signal 驱动两种不同的 hacking 策略。对论文是 positive finding：强化 Claim 1 且揭示 reward-specific hacking 机制。\", \"spec\": {\"command\": \"python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 42 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s42\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"506020\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42}, \"metrics\": {\"eval_prove_rate\": 0.83, \"eval_mean_isr\": 0.031, \"eval_proved_only_isr\": 0.037, \"eval_median_isr\": 0, \"eval_max_isr\": 0.2, \"eval_isr_std\": 0.0534, \"h7_rate\": 0, \"h1_rate\": 0, \"isr_1_rate\": 0, \"single_premise_rate\": 0, \"by_answer_type\": {\"true\": {\"proved\": 37, \"count\": 40, \"pr\": 0.925, \"isr\": 0.037}, \"false\": {\"proved\": 21, \"count\": 29, \"pr\": 0.724, \"isr\": 0.038}, \"unknown\": {\"proved\": 25, \"count\": 31, \"pr\": 0.806, \"isr\": 0.016}}}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan006_prolog_exec_s42/checkpoint-500\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s42.log\"}, \"plan006-prolog-exec-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:13:35.078Z\", \"updated_at\": \"2026-05-14T12:32:13.799Z\", \"hypothesis\": \"Prolog exec-only GRPO seed=43: cross-seed stability check for Prolog logic type. FOL showed extreme cross-seed variance (s42 genuine vs s43 degraded vs s44 tautological). Prolog exec-only s42 showed PR=83%, ISR=0.031. s43 tests if Prolog also has seed instability.\", \"notes\": \"KILLED at step 36/500: warmup_ratio=0.1 与 s42 (0.0) 不一致，3-seed 对比无效。重启为 plan006-prolog-exec-s43-r2 (warmup_ratio=0.0)。\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s43 --warmup_ratio 0.1\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"587155\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s43.log\", \"submitted_at\": \"2026-05-14T12:22:08.915Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"wall_clock_seconds\": 602.2, \"gpu_hours\": 0.17}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"587155\", \"log_path\": \"~/runs/solver-trace-ablation/plan006-prolog-exec-s43.log\", \"reproduce\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_prolog_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan006_prolog_exec_s43 --warmup_ratio 0.1\\\"\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T12:32:11.136Z\"}, \"plan009-sft-baseline-s42-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:37:49.306Z\", \"updated_at\": \"2026-05-14T11:48:05.087Z\", \"hypothesis\": \"SFT baseline: supervised finetuning on FOLIO data (500 steps, Qwen3-4B, same model as all GRPO experiments) to establish whether hacking patterns are GRPO-specific or general finetuning artifacts. Compare eval PR/ISR/hacking taxonomy against GRPO exec-only and exec+ISR conditions.\", \"parent\": \"plan009-sft-baseline-s42-r2\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_s42_r3 --num_steps 500 --seed 42 --bf16 --wandb_project solver-trace-ablation --wandb_run plan009-sft-s42-r3\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"566690\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s42-r3.log\", \"submitted_at\": \"2026-05-14T11:39:19.395Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 18.5, \"gpu_hours\": 0.01}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"566690\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s42-r3.log\", \"wandb_run_id\": \"plan009-sft-s42-r3\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_s42_r3 --num_steps 500 --seed 42 --bf16 --wandb_project solver-trace-ablation --wandb_run plan009-sft-s42-r3\\\"\", \"wandb_run_id\": \"plan009-sft-s42-r3\", \"finished_at\": \"2026-05-14T11:39:36.697Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T11:39:37.935Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T11:39:39.416777+00:00\"}]}, \"notes\": \"r3 crash root cause: wandb.init() failed because no W&B API key configured on server (no .netrc, no WANDB_API_KEY). Fix: add --no_wandb flag. Secondary issue: both GPUs currently near-full, need to wait for GPU availability before r4. Correct r4 command: export CUDA_VISIBLE_DEVICES=N && ... python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_s42_r4 --num_steps 500 --seed 42 --no_wandb\"}, \"plan009-sft-baseline-s42-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:02:25.369Z\", \"updated_at\": \"2026-05-14T11:43:20.347Z\", \"hypothesis\": \"SFT baseline: supervised finetuning on FOLIO data (500 steps, Qwen3-4B, same model as all GRPO experiments) to establish whether hacking patterns are GRPO-specific or general finetuning artifacts. Compare eval PR/ISR/hacking taxonomy against GRPO exec-only and exec+ISR conditions.\", \"plan_id\": \"plan_009\", \"notes\": \"SFT baseline with Qwen3-4B (same model as GRPO experiments). Replaces killed plan009-sft-baseline-s42 which incorrectly used Qwen2.5-1.5B. cuda:1, seed=42, 500 steps, FOLIO data (data/train_500_seed42.jsonl). Dream 审稿三档均指出缺 SFT baseline 是 gap。**FAILED**: 两个问题：(1) W&B API key 未配置，trainer.train() 启动时 wandb callback 报 UsageError; (2) device_map='auto' 把模型分到多 GPU，需改为单卡绑定。修复方案：加 WANDB_MODE=disabled + 改 train_sft.py 的 device_map 为单卡。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_sft.py --model_path /root/autodl-tmp/models/Qwen3-4B --data_path data/train_500_seed42.jsonl --output_dir /root/autodl-tmp/outputs/plan009_sft_baseline_s42 --num_steps 200 --seed 42 --no_wandb\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"548527\", \"log_path\": \"~/runs/solver-trace-ablation/plan009-sft-baseline-s42-r2.log\", \"submitted_at\": \"2026-05-14T11:08:22.511Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"wall_clock_seconds\": 236.8, \"gpu_hours\": 0.07}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T11:12:19.306Z\", \"failure_reason\": \"OOM: 缺少 CUDA_VISIBLE_DEVICES 显式设置，device_map='auto' 跨 GPU 侵入 cuda:0 (plan006)，导致双卡 OOM。修复：(1) 启动命令加 --gpu 1，(2) device_map 改为 {\\\"\\\": 0} 或 .to(\\\"cuda\\\")，(3) num_steps 改为 500\"}, \"plan018-additive-random-b01-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:36:18.260Z\", \"updated_at\": \"2026-05-14T11:42:09.950Z\", \"hypothesis\": \"Random β=0.1 seed=43 控制组：与 plan002-b01-s43 (ISR β=0.1) 同 seed 对照。验证 ISR 3.2x > random 的结论在 s43 下是否成立。\", \"parent\": \"plan018-additive-random-b01-s42\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_additive_random_b01.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --beta 0.1 --reward_mode additive_random --output_dir /root/autodl-tmp/outputs/plan018_additive_random_b01_s43\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"540910\", \"log_path\": \"~/runs/solver-trace-ablation/plan018-additive-random-b01-s43.log\", \"submitted_at\": \"2026-05-14T10:58:27.110Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"checkpoint_source\": \"plan018-additive-random-b01-s42\", \"eval_data\": \"data/train_500_seed42.jsonl\", \"wall_clock_seconds\": 1929.4, \"gpu_hours\": 0.54}, \"reproduce\": {\"finished_at\": \"2026-05-14T11:30:34.690Z\"}, \"failure_reason\": \"磁盘满 (No space left on device): /root/autodl-tmp/ 250G/250G 100% 占满。训练在 step 200/500 保存 checkpoint-200 时 safetensors 序列化失败 (os error 28)。根因: 多个已完成实验的 checkpoint 未清理。可重试——清理磁盘后重跑。\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T11:30:36.549Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T11:30:40.886615+00:00\"}]}, \"notes\": \"Disk full (os error 28) at step 200/500 during checkpoint save. Training ran fine for 200 steps but safetensors serialization failed with \\\"No space left on device\\\". No checkpoint saved. Disk now has 109G free. Retryable as-is.\"}, \"plan012-hacking-taxonomy\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:06:38.613Z\", \"updated_at\": \"2026-05-14T09:07:42.314Z\", \"spec\": {\"command\": \"rule-based hacking taxonomy classification on eval_sta outputs\", \"server\": \"westd-39279\", \"data_path\": \"eval_results.json from plan002-b01-s42 + plan018-b01-s42\", \"data_count\": 160, \"model_name\": \"N/A (rule-based analysis)\", \"seed\": \"N/A\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (analysis task)\", \"log_path\": \"artifacts/hacking_taxonomy_comparison.md\", \"completed_at\": \"2026-05-14T09:07:12.765Z\", \"hypothesis\": \"ISR β=0.1 vs Random β=0.1 hacking taxonomy 对比：ISR reward 能否减少 hacking 模式比例、增加 genuine proof 比例？5 种 hacking 分类（conclusion embedding, repetition collapse, tautological collapse, complexity-without-utility, premise padding）。\", \"metrics\": {\"isr_b01_genuine_rate\": 0.259, \"random_b01_genuine_rate\": 0.177, \"genuine_rate_delta_pp\": 8.2, \"isr_b01_conclusion_embedding_rate\": 0.728, \"random_b01_conclusion_embedding_rate\": 0.785, \"isr_b01_genuine_mean_isr\": 0.6723, \"random_b01_genuine_mean_isr\": 0.3427, \"isr_b01_complexity_wo_utility_rate\": 0, \"random_b01_complexity_wo_utility_rate\": 0.038, \"isr_b01_hacking_rate\": 0.741, \"random_b01_hacking_rate\": 0.823}, \"notes\": \"D037/D038 完成。Conclusion embedding 是主导 hacking 模式（ISR 72.8% vs Random 78.5%）。ISR β=0.1 genuine proof +8.2pp (25.9% vs 17.7%)，genuine ISR 质量 0.67 vs 0.34。ISR 消除 complexity-without-utility hacking。LLM-as-judge 跳过（D038），记入 Discussion/Future Work。Artifact: art_20260514_bf31aa。\"}, \"plan005-sta-low-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:20:47.812Z\", \"updated_at\": \"2026-05-14T06:31:05.119Z\", \"spec\": {\"model_name\": \"Qwen3-4B\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\"}, \"reproduce\": {\"finished_at\": \"2026-05-13T23:55:02.341Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T23:55:06.559440+00:00\"}]}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan005_sta_low_s42/checkpoint-500\", \"log_path\": \"/root/autodl-tmp/outputs/plan005_sta_low_s42/reward_log.jsonl\", \"completed_at\": \"2026-05-13T23:59:25.396Z\", \"metrics\": {\"total_steps\": 500, \"duration_min\": 71, \"parse_rate\": 1, \"overall_prove_rate\": 0.5657, \"overall_isr\": 0.1682, \"last50_prove_rate\": 0.77, \"last50_isr\": 0.2559, \"last100_prove_rate\": 0.7725, \"last100_isr\": 0.2299, \"last100_loss\": 0.022752, \"overall_loss\": 0.017296, \"last100_isr_pr_ratio\": 0.298, \"last100_isr_lt_pr_count\": \"99/100\", \"first_rolling10_pr_ge_0.8\": 178, \"first_rolling10_pr_ge_0.9\": 439, \"max_rolling10_pr\": 0.9375, \"max_rolling10_isr\": 0.3282, \"windowed\": {\"1-50\": {\"pr\": 0.1775, \"isr\": 0.0906}, \"51-100\": {\"pr\": 0.1775, \"isr\": 0.0835}, \"101-200\": {\"pr\": 0.5062, \"isr\": 0.1463}, \"201-300\": {\"pr\": 0.6713, \"isr\": 0.1791}, \"301-400\": {\"pr\": 0.7013, \"isr\": 0.1984}, \"401-500\": {\"pr\": 0.7725, \"isr\": 0.2299}}}, \"notes\": \"conclusion=negative 基于 prove_rate 下降（last100 0.7725 vs exec-only 0.865）。但结构性发现：ISR/PR ratio=0.298，99/100 步 ISR &lt; PR，说明 STA=0.1 维持了 ISR 与 PR 的持续分离——模型未通过 hacking prove_rate 绕过 STA penalty。此观察支持论文 \\\"STA 抑制 reward hacking\\\" claim。windowed ISR/PR: 1-50 (0.51), 51-100 (0.47), 101-200 (0.29), 201-300 (0.27), 301-400 (0.28), 401-500 (0.30) — 分离在100步后稳定。D030 决策：checkpoint 已删除，不重训。论文用训练曲线 windowed ISR/PR 数据作为证据。\"}, \"plan014-downstream-nli-s42\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T03:43:37.925Z\", \"updated_at\": \"2026-05-14T04:29:48.645Z\", \"hypothesis\": \"Downstream NLI validation: 高ISR formalization 应在独立推理任务上表现更好(entailment accuracy)，Spearman ρ(ISR, accuracy) > 0.1 验证 ISR 作为 quality proxy 的实用价值。同时用 Z3 cross-solver agreement 验证 formalization 鲁棒性。\", \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T03:49:52.891Z\", \"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/eval_downstream.py --checkpoint_path /root/autodl-tmp/outputs/plan001_exec_only_s42 --base_model /root/autodl-tmp/models/Qwen3-4B --data_path data/proofwriter_fol_100.jsonl --output_path /root/autodl-tmp/outputs/plan014_downstream_nli.json --num_generations 8 --workers 4\\\"\", \"finished_at\": \"2026-05-14T04:26:05.334Z\", \"training_hours\": 0.6}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"completed_at\": \"2026-05-14T03:51:18.427Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T03:51:19.514390+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T04:26:06.788787+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"r1 失败: checkpoint_path 多了 /checkpoint-500。save_total_limit=1 导致模型直接保存在 plan001_exec_only_s42/ 根目录。修正路径为 /root/autodl-tmp/outputs/plan001_exec_only_s42 即可。等 s43 re-eval 完成后重跑。\"}}, \"notes\": \"Negative: ISR 作为 downstream NLI quality proxy 无效。Spearman ρ(ISR, correct)=-0.049 (p=0.187)，Best-of-N ISR 仅 +0.9pp over random (不显著)。主因：模型严重 true-bias (false accuracy=0%)，NLI accuracy 天花板仅 34.1%，ISR 无区分空间。ISR bucket 层面有弱单调趋势 (high=75% > mid=37.7% > low=32.7%) 但 high bucket 仅 12 样本。quartile 分析非单调。\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/eval_downstream.py --checkpoint_path /root/autodl-tmp/outputs/plan001_exec_only_s42 --base_model /root/autodl-tmp/models/Qwen3-4B --data_path data/proofwriter_fol_100.jsonl --output_path /root/autodl-tmp/outputs/plan014_downstream_nli.json --num_generations 8 --workers 4\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"216133\", \"log_path\": \"~/runs/solver-trace-ablation/plan014-downstream-nli-s42.log\", \"submitted_at\": \"2026-05-14T04:17:30.763Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 737.9, \"gpu_hours\": 0.2}, \"pid\": \"216133\", \"log_path\": \"~/runs/solver-trace-ablation/plan014-downstream-nli-s42.log\", \"conclusion\": \"negative\", \"metrics\": {\"overall_accuracy\": 0.341, \"proved_rate\": 0.915, \"proved_count\": 732, \"total_generations\": 800, \"parse_errors\": 0, \"accuracy_by_label\": {\"true\": 0.912, \"false\": 0, \"unknown\": 0.076}, \"spearman_rho\": -0.049, \"spearman_p\": 0.187, \"mann_whitney_U\": 17202, \"mann_whitney_p\": 0.288, \"bon_isr_accuracy\": 0.35, \"bon_random_accuracy\": 0.341, \"bon_oracle_accuracy\": 0.44, \"bon_prove_first_accuracy\": 0.35, \"isr_bucket_high_acc\": 0.75, \"isr_bucket_mid_acc\": 0.377, \"isr_bucket_low_acc\": 0.327, \"runtime_inference_s\": 408.8, \"runtime_eval_s\": 13.6}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan014_downstream_nli.json\"}, \"plan001-exec-only-s43-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T01:02:31.830Z\", \"updated_at\": \"2026-05-14T01:41:28.427Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=1 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43_r3\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"133258\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"exec-only 500 steps seed 43 (r3), 3-seed baseline 2nd seed\", \"plan_id\": \"plan_001\"}, \"conclusion\": \"failed\", \"failure_reason\": \"OSError: [Errno 28] No space left on device — /root/autodl-tmp 磁盘满，TRL GRPOTrainer completions parquet 写入失败 at step 23\", \"checkpoint_path\": \"N/A (disk full crash at step 23)\", \"log_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s43_r3/reward_log.jsonl\", \"completed_at\": \"2026-05-14T01:41:28.427Z\"}, \"plan013-random-reward-s42-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T01:02:30.063Z\", \"updated_at\": \"2026-05-14T01:41:28.122Z\", \"spec\": {\"command\": \"bash -c \\\"export CUDA_VISIBLE_DEVICES=0 && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_random_reward.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --exec_weight 0.9 --sta_weight 0.1 --output_dir /root/autodl-tmp/outputs/plan013_random_reward_s42_r3\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"133178\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Random reward baseline (r3): random value replaces ISR to isolate ISR-specific signal vs multi-objective regularization\", \"plan_id\": \"plan_013\", \"hyperparams\": {\"alpha\": 0.9, \"beta\": 0.1, \"K\": 8, \"num_steps\": 500, \"reward_type\": \"random_penalty\"}}, \"conclusion\": \"failed\", \"failure_reason\": \"OSError: [Errno 28] No space left on device — /root/autodl-tmp 磁盘满，TRL GRPOTrainer completions parquet 写入失败 at step 28\", \"checkpoint_path\": \"N/A (disk full crash at step 28)\", \"log_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42_r3/reward_log.jsonl\", \"completed_at\": \"2026-05-14T01:41:28.122Z\"}, \"plan001-exec-only-s43-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T00:22:12.292Z\", \"updated_at\": \"2026-05-14T01:01:56.416Z\", \"spec\": {\"command\": \"python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"126541\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43-r2.log\", \"submitted_at\": \"2026-05-14T00:22:12.241Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"exec-only 500步 seed 43 (retry), 3-seed baseline 第2个 seed\", \"wall_clock_seconds\": 2384.2, \"gpu_hours\": 0.66}, \"checkpoint_path\": \"N/A (crashed after submission)\", \"log_path\": \"/root/autodl-tmp/outputs/plan001_exec_only_s43_r2/reward_log.jsonl\", \"conclusion\": \"failed\", \"failure_reason\": \"Process crashed after submission (PID 126546 not found, tmux session dead). Worker verified 91% util at submission but process died within 30 min.\", \"completed_at\": \"2026-05-14T01:01:56.416Z\"}, \"plan013-random-reward-s42-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T00:22:10.140Z\", \"updated_at\": \"2026-05-14T01:01:55.694Z\", \"spec\": {\"command\": \"python3 scripts/train_grpo.py --config configs/grpo_random_reward.yaml --data_path data/train_500_seed42.jsonl --num_steps 500 --seed 42 --exec_weight 0.9 --sta_weight 0.1 --output_dir /root/autodl-tmp/outputs/plan013_random_reward_s42\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"126461\", \"log_path\": \"~/runs/solver-trace-ablation/plan013-random-reward-s42-r2.log\", \"submitted_at\": \"2026-05-14T00:22:10.091Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Random reward baseline (retry): 用随机值替代 ISR，隔离 ISR-specific signal vs multi-objective regularization effect\", \"wall_clock_seconds\": 2385.6, \"gpu_hours\": 0.66}, \"checkpoint_path\": \"N/A (crashed after submission)\", \"log_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42_r2/reward_log.jsonl\", \"conclusion\": \"failed\", \"failure_reason\": \"Process crashed after submission (PID 126466 not found, tmux session dead). Worker verified 91% util at submission but process died within 30 min.\", \"completed_at\": \"2026-05-14T01:01:55.694Z\"}, \"plan013-random-reward-s42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T23:56:44.062Z\", \"updated_at\": \"2026-05-14T00:21:05.430Z\", \"spec\": {\"hypothesis\": \"Random reward baseline: 用随机值替代 ISR，隔离 ISR-specific signal vs multi-objective regularization effect\", \"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=0 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_random_reward.yaml --num_steps 500 --seed 42 --exec_weight 0.9 --sta_weight 0.1\\\"\", \"server\": \"westd-39279\", \"data_path\": \"data/proofwriter_fol_500.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"plan_id\": \"plan_013\", \"gpu\": \"cuda:0\", \"hyperparams\": {\"alpha\": 0.9, \"beta\": 0.1, \"K\": 8, \"num_steps\": 500, \"reward_type\": \"random_penalty\"}, \"pid\": 122796, \"output_dir\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42\", \"log_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42.log\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42\", \"reward_mode\": \"random_reward\", \"exec_weight\": 0.9, \"sta_weight\": 0.1, \"num_steps\": 500}, \"checkpoint_path\": \"N/A (GPU overflow, no valid output)\", \"log_path\": \"/root/autodl-tmp/outputs/plan013_random_reward_s42.log\", \"conclusion\": \"failed\", \"failure_reason\": \"CUDA_VISIBLE_DEVICES not set (inline assignment not exported), GPU overflow to both GPUs\", \"completed_at\": \"2026-05-14T00:21:05.430Z\"}, \"plan001-exec-only-s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T23:55:08.635Z\", \"updated_at\": \"2026-05-14T00:21:04.003Z\", \"spec\": {\"command\": \"python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --num_steps 500 --seed 43 --output_dir /root/autodl-tmp/outputs/plan001_exec_only_s43\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"121275\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43.log\", \"submitted_at\": \"2026-05-13T23:55:08.544Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/proofwriter_fol_500.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 43, \"hypothesis\": \"exec-only 500步 seed 43, 3-seed baseline 第2个 seed。预期 prove_rate>0.80 (与 s42 一致)\", \"wall_clock_seconds\": 1555.5, \"gpu_hours\": 0.43}, \"checkpoint_path\": \"N/A (killed by OOM before completion)\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s43.log\", \"conclusion\": \"failed\", \"failure_reason\": \"OOM by plan013 GPU overflow — plan013 未设 CUDA_VISIBLE_DEVICES 导致占用两张 GPU，plan001-s43 被 OOM kill\", \"completed_at\": \"2026-05-14T00:21:04.003Z\"}, \"plan003-eval-exec-only-r5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:21:48.691Z\", \"updated_at\": \"2026-05-13T23:03:19.945Z\", \"spec\": {\"command\": \"eval_sta.py on r5 exec-only checkpoint\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"83690\", \"log_path\": \"~/runs/solver-trace-ablation/plan003-eval-exec-only-r5.log\", \"submitted_at\": \"2026-05-13T22:21:48.658Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/proofwriter_fol_100.jsonl\", \"data_count\": 100, \"model_name\": \"Qwen3-4B (r5 exec-only checkpoint)\", \"seed\": 0, \"checkpoint_source\": \"sta-phase1-exec-only-r5\", \"eval_data\": \"proofwriter_fol_100\", \"hypothesis\": \"Full STA eval on exec-only 100-step checkpoint to measure formalization quality\", \"wall_clock_seconds\": 2490.2, \"gpu_hours\": 0.69}, \"metrics\": {\"prove_rate\": 0.32, \"mean_isr\": 0.2055, \"isr_std\": 0.3194, \"proved_only_isr\": 0.6423, \"isr_by_type\": {\"true\": 0.3598, \"false\": 0.1723, \"unknown\": 0.0979}, \"total_samples\": 100, \"proved_count\": 32, \"runtime_s\": 251.7}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/plan003_eval_exec_only_r5.json\", \"log_path\": \"~/runs/solver-trace-ablation/plan003-eval-exec-only-r5.log\", \"completed_at\": \"2026-05-13T23:03:18.848Z\"}, \"plan001-exec-only-s42-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T22:42:40.242Z\", \"updated_at\": \"2026-05-13T23:03:11.395Z\", \"spec\": {\"command\": \"python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml --num_steps 500 --seed 42\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"85710\", \"log_path\": \"~/runs/solver-trace-ablation/plan001-exec-only-s42-r3.log\", \"submitted_at\": \"2026-05-13T22:42:40.204Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/train_500_seed42.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"exec-only 500步训练 baseline (retry 3)\", \"wall_clock_seconds\": 1228.1, \"gpu_hours\": 0.34}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T23:03:08.298Z\", \"failure_reason\": \"OOM crash - duplicate submission while plan001-r2 was occupying cuda:0\"}, \"sta-phase1-exec-sta-r5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:54:31.353Z\", \"updated_at\": \"2026-05-13T22:20:41.274Z\", \"spec\": {\"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=1 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"75968\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r5.log\", \"submitted_at\": \"2026-05-13T20:54:38.781Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/proofwriter_fol_500.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Full STA continuous ISR (0.0-1.0) 作为 reward 组件，应在训练中产生与 execution-only 不同的 ISR 趋势——execution-only ISR 随 prove_rate 上升而虚高(reward hacking)，execution+STA ISR 维持真实水平(STA 抑制 hacking)\", \"wall_clock_seconds\": 3506.3, \"gpu_hours\": 0.97}, \"metrics\": {\"parse_rate\": 1, \"prove_rate\": 0.1, \"mean_isr\": 0.04347, \"last20_prove_rate\": 0.15, \"last20_isr_mean\": 0.04956, \"first20_prove_rate\": 0.08125, \"first20_isr_mean\": 0.05182, \"overall_reward_mean\": 0.07174, \"last20_reward_mean\": 0.09978, \"training_steps\": 100, \"training_minutes\": 16.9, \"step_time_s\": 10.13, \"isr_pr_ratio_overall\": 0.43, \"isr_pr_ratio_last20\": 0.33, \"K\": 8}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/grpo_exec_sta/\", \"log_path\": \"/root/autodl-tmp/outputs/grpo_exec_sta/reward_log.jsonl\", \"completed_at\": \"2026-05-13T21:53:05.068Z\"}, \"sta-phase1-exec-only-r5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:54:27.505Z\", \"updated_at\": \"2026-05-13T21:53:04.486Z\", \"spec\": {\"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=0 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"75890\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r5.log\", \"submitted_at\": \"2026-05-13T20:54:37.293Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/solver-trace-ablation/data/proofwriter_fol_500.jsonl\", \"data_count\": 500, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"K=8 增加 within-group variance，减少全零 reward batch，使 GRPO 有更多有效梯度信号\", \"wall_clock_seconds\": 3507.2, \"gpu_hours\": 0.97}, \"metrics\": {\"parse_rate\": 1, \"prove_rate\": 0.15125, \"mean_isr\": 0.1475, \"last20_prove_rate\": 0.2, \"last20_isr_mean\": 0.2, \"first20_prove_rate\": 0.11875, \"first20_isr_mean\": 0.11875, \"overall_reward_mean\": 0.15125, \"last20_reward_mean\": 0.2, \"training_steps\": 100, \"training_minutes\": 15.7, \"step_time_s\": 9.44, \"isr_pr_ratio_last20\": 1, \"K\": 8}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/outputs/grpo_exec_only/\", \"log_path\": \"/root/autodl-tmp/outputs/grpo_exec_only/reward_log.jsonl\", \"completed_at\": \"2026-05-13T21:53:04.486Z\"}, \"sta-phase1-exec-sta-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:28:22.778Z\", \"updated_at\": \"2026-05-13T20:52:58.761Z\", \"spec\": {\"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=1 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"70797\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r4.log\", \"submitted_at\": \"2026-05-13T20:28:32.091Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1404.7, \"gpu_hours\": 0.39}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-13T20:28:31.240Z\", \"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=1 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"finished_at\": \"2026-05-13T20:45:55.480Z\", \"training_hours\": 0.29}, \"pid\": \"70797\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r4.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:45:56.962544+00:00\"}]}, \"metrics\": {\"parse_rate\": 1, \"prove_rate\": 0.1575, \"mean_isr\": 0.1525, \"last20_prove_rate\": 0.2125, \"last20_isr_mean\": 0.2125, \"first20_reward_mean\": 0.119, \"training_steps\": 100, \"training_minutes\": 15}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/grpo_exec_sta/\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-13T20:51:56.799Z\", \"notes\": \"Phase 1 r4 完成但无差异。fast_isr_fol 二值信号(0/1)对 proved samples 几乎全部 ISR=1，exec+STA reward ≈ exec-only reward。连续 ISR 才能产生有意义的差异信号。→ r5 改用 full sta_reward (continuous ISR 0.0-1.0) + K=8\"}, \"sta-phase1-exec-only-r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:28:18.040Z\", \"updated_at\": \"2026-05-13T20:52:56.416Z\", \"spec\": {\"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=0 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"70716\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r4.log\", \"submitted_at\": \"2026-05-13T20:28:30.420Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1405.8, \"gpu_hours\": 0.39}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-13T20:28:28.733Z\", \"command\": \"bash -c \\\"CUDA_VISIBLE_DEVICES=0 source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"finished_at\": \"2026-05-13T20:45:53.506Z\", \"training_hours\": 0.29}, \"pid\": \"70716\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r4.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:45:54.294365+00:00\"}]}, \"metrics\": {\"parse_rate\": 1, \"prove_rate\": 0.15125, \"mean_isr\": 0.1475, \"last20_prove_rate\": 0.2, \"last20_isr_mean\": 0.2, \"first20_reward_mean\": 0.119, \"training_steps\": 100, \"training_minutes\": 15}, \"checkpoint_path\": \"/root/autodl-tmp/outputs/grpo_exec_only/\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-13T20:51:56.183Z\", \"notes\": \"Phase 1 r4 完成但无差异。fast_isr_fol 二值信号(0/1)对 proved samples 几乎全部 ISR=1，导致 exec+STA ≈ exec-only。prove_rate 从 baseline 12% → last20 20%（微弱提升）。K=4 导致大量全零 reward batch。→ r5 改用 full STA + K=8\"}, \"sta-phase1-exec-only-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:15:04.067Z\", \"updated_at\": \"2026-05-13T20:23:15.460Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"67225\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r3.log\", \"submitted_at\": \"2026-05-13T20:15:15.911Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 276.4, \"gpu_hours\": 0.08}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-13T20:15:14.333Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"finished_at\": \"2026-05-13T20:19:51.612Z\", \"training_hours\": 0.08}, \"pid\": \"67225\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r3.log\", \"failure_reason\": \"EXIT_CODE=137 (SIGKILL — OOM killer or manual kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T20:19:52.268Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:19:52.981720+00:00\"}]}, \"notes\": \"EXIT_CODE=137 (OOM/SIGKILL) after ~276s. 同 sta-phase1-exec-sta-r3 一起诊断中\"}, \"sta-phase1-exec-sta-r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T20:15:08.133Z\", \"updated_at\": \"2026-05-13T20:23:14.516Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"67306\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r3.log\", \"submitted_at\": \"2026-05-13T20:15:17.535Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 277.9, \"gpu_hours\": 0.08}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-13T20:15:16.704Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"finished_at\": \"2026-05-13T20:19:54.409Z\", \"training_hours\": 0.08}, \"pid\": \"67306\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r3.log\", \"failure_reason\": \"EXIT_CODE=137 (SIGKILL — OOM killer or manual kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T20:19:55.400Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T20:19:56.549926+00:00\"}]}, \"notes\": \"EXIT_CODE=137 (OOM/SIGKILL) after ~278s. 诊断中: worker_diagnose_sta-phase1-r3-oom_20260513T202300\"}, \"sta-phase1-exec-sta-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T19:55:08.640Z\", \"updated_at\": \"2026-05-13T19:55:41.544Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"62364\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r2.log\", \"submitted_at\": \"2026-05-13T19:55:19.065Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 22.5, \"gpu_hours\": 0.01}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-13T19:55:18.267Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"finished_at\": \"2026-05-13T19:55:40.449Z\", \"training_hours\": 0.01}, \"pid\": \"62364\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta-r2.log\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T19:55:41.544Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T19:55:42.974865+00:00\"}]}}, \"sta-phase1-exec-only-r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T19:55:04.711Z\", \"updated_at\": \"2026-05-13T19:55:37.426Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"62283\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r2.log\", \"submitted_at\": \"2026-05-13T19:55:17.509Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 19.9, \"gpu_hours\": 0.01}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-13T19:55:16.037Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"finished_at\": \"2026-05-13T19:55:36.845Z\", \"training_hours\": 0.01}, \"pid\": \"62283\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only-r2.log\", \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T19:55:37.426Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T19:55:38.155358+00:00\"}]}}, \"sta-phase1-exec-sta\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T18:26:53.258Z\", \"updated_at\": \"2026-05-13T19:33:03.905Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:1\"], \"pid\": \"59574\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta.log\", \"submitted_at\": \"2026-05-13T19:32:47.783Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 16.1, \"gpu_hours\": 0.0}, \"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-13T19:30:58.981Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_sta.yaml\\\"\", \"finished_at\": \"2026-05-13T19:33:03.170Z\", \"training_hours\": 0.03}, \"pid\": \"59574\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-sta.log\", \"failure_reason\": \"EXIT_CODE=2 (shell misuse / syntax)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T19:33:03.905Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T19:33:05.009356+00:00\"}]}}, \"sta-phase1-exec-only\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T18:26:46.351Z\", \"updated_at\": \"2026-05-13T19:33:01.169Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"server\": \"westd-39279\", \"gpu\": [\"cuda:0\"], \"pid\": \"59274\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only.log\", \"submitted_at\": \"2026-05-13T19:32:30.340Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 30.8, \"gpu_hours\": 0.01}, \"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"westd-39279\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-13T19:32:28.753Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/solver-trace-ablation && python3 scripts/train_grpo.py --config configs/grpo_exec_only.yaml\\\"\", \"finished_at\": \"2026-05-13T19:33:00.602Z\", \"training_hours\": 0.01}, \"pid\": \"59274\", \"log_path\": \"~/runs/solver-trace-ablation/sta-phase1-exec-only.log\", \"failure_reason\": \"EXIT_CODE=2 (shell misuse / syntax)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-13T19:33:01.169Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-13T19:33:01.864437+00:00\"}]}}, \"sta-gt-isr-baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T18:11:13.283Z\", \"updated_at\": \"2026-05-13T18:12:44.147Z\", \"spec\": {\"command\": \"python3 scripts/gt_isr_baseline.py\", \"server\": \"westd-39279\", \"data_path\": \"/root/solver-trace-ablation/data/proofwriter_fol_100.jsonl\", \"data_count\": 100, \"model_name\": \"ground-truth-fol\", \"seed\": 0}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/solver-trace-ablation/outputs/gt_isr_baseline.json\", \"log_path\": \"/root/solver-trace-ablation/outputs/gt_isr_baseline.json\", \"completed_at\": \"2026-05-13T18:12:43.141Z\", \"metrics\": {\"gt_prove_rate\": 0.18, \"gt_mean_isr\": 0.5588, \"gt_isr_std\": 0.2582, \"gt_isr_median\": 0.6125, \"solver_execution_rate\": 1, \"true_prove_rate\": 0.5, \"true_mean_isr\": 0.5833}}, \"sta-phase0-baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-13T17:51:48.853Z\", \"updated_at\": \"2026-05-13T18:10:40.982Z\", \"spec\": {\"hypothesis\": \"锚定 base Qwen3-4B 的 ISR baseline，后续判断 GRPO 训练是否导致 ISR 下降（reward hacking）\", \"model_name\": \"Qwen3-4B\", \"data_path\": \"/root/solver-trace-ablation/data/proofwriter_fol_100.jsonl\", \"data_count\": 100, \"server\": \"westd-39279\", \"data_source\": \"tasksource/folio\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 scripts/phase0_baseline.py --model_path models/Qwen3-4B --data_path data/proofwriter_fol_100.jsonl --output outputs/phase0_baseline.json\", \"seed\": 0, \"checkpoint_path\": \"N/A (inference only)\", \"log_path\": \"/root/solver-trace-ablation/outputs/phase0_baseline.json\", \"notes\": \"conclusion=success 但语义是 baseline_anchored（registry 不支持自定义 conclusion）。此实验是 baseline 锚定，非传统 success/failure。ISR 盲区：premise-conclusion 重复的 trivial formalization 可能获高 ISR，论文 Discussion 需讨论。\"}, \"log_path\": \"/tmp/phase0_baseline.log\", \"checkpoint_path\": \"/root/solver-trace-ablation/outputs/phase0_baseline.json\", \"metrics\": {\"mean_isr\": 0.0641, \"isr_std\": 0.1983, \"median_isr\": 0, \"isr_range\": [0, 0.889], \"prove_rate\": 0.12, \"proved_count\": 12, \"total_samples\": 100, \"xor_affected_samples\": 34, \"effective_prove_rate_no_xor\": 0.182, \"avg_time_per_sample_s\": 3.4, \"total_runtime_s\": 336, \"isr_by_answer\": {\"true\": {\"n\": 34, \"proved\": 9, \"prove_rate\": 0.265, \"mean_isr\": 0.1345}, \"false\": {\"n\": 25, \"proved\": 1, \"prove_rate\": 0.04, \"mean_isr\": 0.024}, \"unknown\": {\"n\": 41, \"proved\": 2, \"prove_rate\": 0.049, \"mean_isr\": 0.0302}}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-13T18:04:56.962Z\"}}, \"count\": 86, \"total\": 86, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3806}}"
    }
  },
  "sourceToolAssistantUUID": "bc4b5ff4-7fdf-463a-8418-e403d74fed6c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 20_

```json
{
  "type": "last-prompt",
  "leafUuid": "18fb2326-a379-4bab-b998-73bd68793830",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10"
}
```

---

### Runtime record

_source line 21_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix provenance gaps and prepare statistics recalc checklist",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10"
}
```

---

### Assistant

_source line 22 · 2026-05-15T17:38:30.703Z_

<details><summary>Logged reasoning block</summary>

```text
The provenance file is large. Let me analyze it to find the missing provenance entry. The coverage says 35/36, meaning one claim out of 36 is missing provenance (tier3 = 1, which means one claim has incomplete provenance).

Let me look through all claims and identify which one has empty or incomplete evidence. Looking at the YAML:

Looking through each non-deprecated claim:
1. C055 - has evidence with exp_id
2. C057 - has evidence with exp_ids
3. C060 - has evidence with exp_id
4. C064 - has evidence with exp_ids (wildcard)


5. C069 - has evidence with exp_id
6. C075 - has evidence with exp_ids
7. C082 - has evidence with exp_id (wildcard)
8. C083 - has evidence with exp_id
9. C085 - has evidence with exp_ids
10. C086 - has evidence with exp_id
11. C088 - has evidence with exp_id
12. C091 - has evidence with exp_ids
13. C092 - has evidence with exp_id
14. C094 - has evidence with exp_id
15. C097 - has evidence with exp_id "sft-baseline" - this one looks like it might be the issue

, not a proper registry ID. Continuing through the rest of the cases, most have standard exp_id or exp_ids fields, though C177 appears to be cut off in the list.

Looking at C177 more closely, it has an empty evidence array, which is unusual. This claim about ISR's sensitivity to premise count bias is categorized as a scope limitation in the methods section and references decision D051. The tier breakdown shows mostly tier2 claims with just one tier3, which is likely this incomplete evidence case. I need to track down what experiment or artifact actually supports this particular claim about premise count bias. I'm searching the registry to locate the D051-analysis entry and understand what specific confound it identified regarding ISR sensitivity to component count.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "18fb2326-a379-4bab-b998-73bd68793830",
  "isSidechain": false,
  "requestId": "req_011Cb4m8rTtWM84vb2Ze3YoF",
  "type": "assistant",
  "uuid": "5ec2127f-890b-4a76-b2af-0d39c2b0951a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016Nhb2Dp9ZsKihWRYaCut98",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21071,
      "cache_read_input_tokens": 27031,
      "output_tokens": 1320,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21071,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1320,
          "cache_read_input_tokens": 27031,
          "cache_creation_input_tokens": 21071,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21071
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

_source line 23 · 2026-05-15T17:38:30.705Z_

Found the gap: **C177** has `evidence: []`. Let me look up D051 analysis info in the registry.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5ec2127f-890b-4a76-b2af-0d39c2b0951a",
  "isSidechain": false,
  "requestId": "req_011Cb4m8rTtWM84vb2Ze3YoF",
  "type": "assistant",
  "uuid": "4cbf4227-8ef9-47d2-9db1-e9acaa1acb7e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016Nhb2Dp9ZsKihWRYaCut98",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21071,
      "cache_read_input_tokens": 27031,
      "output_tokens": 1320,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21071,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1320,
          "cache_read_input_tokens": 27031,
          "cache_creation_input_tokens": 21071,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21071
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

_source line 24 · 2026-05-15T17:38:31.067Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_017JzkiCSJ76dbipJP9jaRRg`</summary>

```json
{
  "project": "solver-trace-ablation",
  "filters": {
    "exp_id": "D051-analysis"
  },
  "fields": [
    "*"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4cbf4227-8ef9-47d2-9db1-e9acaa1acb7e",
  "isSidechain": false,
  "requestId": "req_011Cb4m8rTtWM84vb2Ze3YoF",
  "type": "assistant",
  "uuid": "cc9c15b8-952f-49fc-95c5-69a61aaf9f8e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016Nhb2Dp9ZsKihWRYaCut98",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21071,
      "cache_read_input_tokens": 27031,
      "output_tokens": 1320,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21071,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1320,
          "cache_read_input_tokens": 27031,
          "cache_creation_input_tokens": 21071,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21071
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

_source line 25 · 2026-05-15T17:38:31.376Z_

<details><summary>↩ Tool result · `toolu_017JzkiCSJ76dbipJP9jaRRg`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.2982}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "cc9c15b8-952f-49fc-95c5-69a61aaf9f8e",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "6740fd76-9481-42a1-8499-31564c3275c2",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {}, \\\"count\\\": 0, \\\"total\\\": 0, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.2982}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.2982}}"
    }
  },
  "sourceToolAssistantUUID": "cc9c15b8-952f-49fc-95c5-69a61aaf9f8e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-15T17:38:32.015Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01PLFzoG2mdK8BNFBpEVzuak`</summary>

```json
{
  "project": "solver-trace-ablation",
  "filters": {
    "exp_id": "plan002-additive-b01-s42"
  },
  "fields": [
    "*"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6740fd76-9481-42a1-8499-31564c3275c2",
  "isSidechain": false,
  "requestId": "req_011Cb4m8rTtWM84vb2Ze3YoF",
  "type": "assistant",
  "uuid": "dafb80dd-76e4-4979-be88-33c54ef7a839",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016Nhb2Dp9ZsKihWRYaCut98",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21071,
      "cache_read_input_tokens": 27031,
      "output_tokens": 1320,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21071,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1320,
          "cache_read_input_tokens": 27031,
          "cache_creation_input_tokens": 21071,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21071
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

_source line 27 · 2026-05-15T17:38:32.332Z_

<details><summary>↩ Tool result · `toolu_01PLFzoG2mdK8BNFBpEVzuak`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3068}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dafb80dd-76e4-4979-be88-33c54ef7a839",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "17fefb68-98aa-4dd4-9c68-8124c1d49dae",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {}, \\\"count\\\": 0, \\\"total\\\": 0, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.3068}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3068}}"
    }
  },
  "sourceToolAssistantUUID": "dafb80dd-76e4-4979-be88-33c54ef7a839",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-15T17:38:32.496Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_014yoZrgGP3WY9mmQKLezwBU`</summary>

```json
{
  "project": "solver-trace-ablation",
  "filters": {
    "exp_id": "plan018-additive-random-b01-s42"
  },
  "fields": [
    "*"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "17fefb68-98aa-4dd4-9c68-8124c1d49dae",
  "isSidechain": false,
  "requestId": "req_011Cb4m8rTtWM84vb2Ze3YoF",
  "type": "assistant",
  "uuid": "ec3ca1b8-ed83-44ba-9920-ba7ec3e45bfe",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016Nhb2Dp9ZsKihWRYaCut98",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 21071,
      "cache_read_input_tokens": 27031,
      "output_tokens": 1320,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 21071,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1320,
          "cache_read_input_tokens": 27031,
          "cache_creation_input_tokens": 21071,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 21071
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

_source line 29 · 2026-05-15T17:38:32.825Z_

<details><summary>↩ Tool result · `toolu_014yoZrgGP3WY9mmQKLezwBU`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3161}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ec3ca1b8-ed83-44ba-9920-ba7ec3e45bfe",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "02a2e784-0273-4cbb-9f26-50b1b22496de",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {}, \\\"count\\\": 0, \\\"total\\\": 0, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.3161}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3161}}"
    }
  },
  "sourceToolAssistantUUID": "ec3ca1b8-ed83-44ba-9920-ba7ec3e45bfe",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 30 · 2026-05-15T17:38:36.985Z_

<details><summary>Logged reasoning block</summary>

```text
The exact exp_ids don't match. Let me search differently in the registry. Let me use a broader filter or search for similar exp_ids.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "02a2e784-0273-4cbb-9f26-50b1b22496de",
  "isSidechain": false,
  "requestId": "req_011Cb4mAf8KRSjWEqmr7FJuU",
  "type": "assistant",
  "uuid": "6ec77b09-ca93-4407-8820-d7f52240efec",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DidESq5tQpU9LfGXxSeuf9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1629,
      "cache_read_input_tokens": 48102,
      "output_tokens": 402,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1629,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 402,
          "cache_read_input_tokens": 48102,
          "cache_creation_input_tokens": 1629,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1629
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

_source line 31 · 2026-05-15T17:38:37.483Z_

Exact IDs not found. Let me search the registry with partial matches.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6ec77b09-ca93-4407-8820-d7f52240efec",
  "isSidechain": false,
  "requestId": "req_011Cb4mAf8KRSjWEqmr7FJuU",
  "type": "assistant",
  "uuid": "f12e0bb0-40cb-4e7f-a673-43069eeec66a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DidESq5tQpU9LfGXxSeuf9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1629,
      "cache_read_input_tokens": 48102,
      "output_tokens": 402,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1629,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 402,
          "cache_read_input_tokens": 48102,
          "cache_creation_input_tokens": 1629,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1629
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

_source line 32 · 2026-05-15T17:38:40.986Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01TvsKNmjw67YVq6yhZfzn26`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/d09c16fe-783f-4107-8777-2fc80b263d10/tool-results/mcp-agent-ml-research-read_registry-1778866688318.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n# Find experiment IDs containing D051 or plan002-additive or plan018-additive-random\nfor eid in sorted(exps.keys()):\n    if any(x in eid.lower() for x in ['d051', 'plan002-additive-b01', 'plan018-additive-random-b01-s42']):\n        print(f'{eid}: status={exps[eid].get(\\\"status\\\")}, conclusion={exps[eid].get(\\\"conclusion\\\")}')\n\"\n",
  "description": "Search registry for D051 and related experiment IDs"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f12e0bb0-40cb-4e7f-a673-43069eeec66a",
  "isSidechain": false,
  "requestId": "req_011Cb4mAf8KRSjWEqmr7FJuU",
  "type": "assistant",
  "uuid": "b67f5aa9-fb94-4ff1-b17e-4b6727d90967",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DidESq5tQpU9LfGXxSeuf9",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1629,
      "cache_read_input_tokens": 48102,
      "output_tokens": 402,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1629,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 402,
          "cache_read_input_tokens": 48102,
          "cache_creation_input_tokens": 1629,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1629
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

_source line 33 · 2026-05-15T17:38:41.207Z_

<details><summary>↩ Tool result · `toolu_01TvsKNmjw67YVq6yhZfzn26`</summary>

```text
plan002-additive-b01-s42: status=DONE, conclusion=negative
plan002-additive-b01-s42-1000: status=DONE, conclusion=negative
plan002-additive-b01-s43: status=DONE, conclusion=negative
plan002-additive-b01-s43-r2: status=ANALYZING, conclusion=None
plan002-additive-b01-s44: status=DONE, conclusion=negative
plan018-additive-random-b01-s42: status=DONE, conclusion=negative
plan018-additive-random-b01-s42-1000: status=DONE, conclusion=failed
plan018-additive-random-b01-s42-1000-r2: status=DONE, conclusion=negative
plan018-additive-random-b01-s42-1000-r3: status=DONE, conclusion=negative
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b67f5aa9-fb94-4ff1-b17e-4b6727d90967",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "4c54c1e4-5440-4701-a9dc-62bcecc3119f",
  "toolUseResult": {
    "stdout": "plan002-additive-b01-s42: status=DONE, conclusion=negative\nplan002-additive-b01-s42-1000: status=DONE, conclusion=negative\nplan002-additive-b01-s43: status=DONE, conclusion=negative\nplan002-additive-b01-s43-r2: status=ANALYZING, conclusion=None\nplan002-additive-b01-s44: status=DONE, conclusion=negative\nplan018-additive-random-b01-s42: status=DONE, conclusion=negative\nplan018-additive-random-b01-s42-1000: status=DONE, conclusion=failed\nplan018-additive-random-b01-s42-1000-r2: status=DONE, conclusion=negative\nplan018-additive-random-b01-s42-1000-r3: status=DONE, conclusion=negative",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "b67f5aa9-fb94-4ff1-b17e-4b6727d90967",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 34 · 2026-05-15T17:38:41.209Z_

```json
{
  "parentUuid": "4c54c1e4-5440-4701-a9dc-62bcecc3119f",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "7654d552-8d3e-43cd-85eb-dfdf6d001d4c",
  "timestamp": "2026-05-15T17:38:41.209Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 35 · 2026-05-15T17:39:02.827Z_

<details><summary>Logged reasoning block</summary>

```text
Now I see the actual exp_ids. For C177 (ISR is mathematically sensitive to component count / premise count bias), the evidence should reference D051-analysis or the experiments that demonstrated this. Since D051-analysis doesn't exist as a registry entry, let me check what C069 and C141 reference - they both reference "D051-analysis" as an exp_id but that doesn't exist in the registry either.

Wait, C069 has `exp_id: D051-analysis` and C141 has `exp_id: plan002-additive-b01-s42` and `plan018-additive-random-b01-s42`. These are in the registry.


For C177, the evidence should come from the D051 analysis that compared premise-count-matched ISR values between conditions, which draws from the same underlying experimental data as C141. I need to check the decisions.yaml for D051 to see what the canonical evidence reference should be. Looking at the tier system, C177 is currently tier3 with empty evidence, so adding the experiment references should bump it to tier2 and get us to 36/36 total. Now I need to check whether the save_project_file tool can actually write to the provenance YAML file...

it looks like that file doesn't have a dedicated tool listed, so I'll try writing it directly using the standard Write tool with the full project path.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7654d552-8d3e-43cd-85eb-dfdf6d001d4c",
  "isSidechain": false,
  "requestId": "req_011Cb4mBGxqnavZsa5ko4xiC",
  "type": "assistant",
  "uuid": "aaad6a5f-ad4c-43a6-9621-42df9677f7e0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KVsFSFdUd1q6tWYxbZoVwb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 734,
      "cache_read_input_tokens": 49731,
      "output_tokens": 1662,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 734,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1662,
          "cache_read_input_tokens": 49731,
          "cache_creation_input_tokens": 734,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 734
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

_source line 36 · 2026-05-15T17:39:02.833Z_

C177 is the missing claim — it has `evidence: []`. Let me read the actual provenance file to edit it, and start Task 2 in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "aaad6a5f-ad4c-43a6-9621-42df9677f7e0",
  "isSidechain": false,
  "requestId": "req_011Cb4mBGxqnavZsa5ko4xiC",
  "type": "assistant",
  "uuid": "0789937a-ec30-4c0c-82a0-8c3424274aff",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KVsFSFdUd1q6tWYxbZoVwb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 734,
      "cache_read_input_tokens": 49731,
      "output_tokens": 1662,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 734,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1662,
          "cache_read_input_tokens": 49731,
          "cache_creation_input_tokens": 734,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 734
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

_source line 37 · 2026-05-15T17:39:03.263Z_

<details open><summary>🔧 Tool call — Read · `toolu_01JTMToRhnr8xfSiW8cF3jZd`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_provenance.yaml"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0789937a-ec30-4c0c-82a0-8c3424274aff",
  "isSidechain": false,
  "requestId": "req_011Cb4mBGxqnavZsa5ko4xiC",
  "type": "assistant",
  "uuid": "399a36ea-61c9-4cf6-a26a-34c80acc5f29",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KVsFSFdUd1q6tWYxbZoVwb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 734,
      "cache_read_input_tokens": 49731,
      "output_tokens": 1662,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 734,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1662,
          "cache_read_input_tokens": 49731,
          "cache_creation_input_tokens": 734,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 734
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

_source line 38 · 2026-05-15T17:39:03.282Z_

<details><summary>↩ Tool result · `toolu_01JTMToRhnr8xfSiW8cF3jZd`</summary>

```text
1	paper:
2	  title: ''
3	  version: 12
4	  generated_at: '2026-05-15T02:40:08.884665+00:00'
5	claims:
6	- id: C001
7	  location:
8	    section: experiments
9	    paragraph: 0
10	    sentence: 0
11	  text: 'ISR collapse: 0.642 to 0.132 to 0.003'
12	  type: quantitative
13	  evidence:
14	  - exp_id: plan003-eval-exec-only-r5
15	    metric: proved_only_isr
16	  - exp_id: plan001-exec-only-s42-r2
17	    metric: eval_proved_only_isr
18	  - exp_id: plan016-extended-1000-s42
19	    metric: isr
20	  decisions: []
21	  deprecated: true
22	- id: C003
23	  location:
24	    section: experiments
25	    paragraph: 0
26	    sentence: 0
27	  text: 'H7 ISR-specific: 64.5% vs 0% random'
28	  type: quantitative
29	  evidence:
30	  - exp_id: plan002-additive-b01-s42
31	    metric: h7_rate
32	  - exp_id: plan018-additive-random-b01-s42
33	    metric: H7=0
34	  decisions: []
35	  deprecated: true
36	- id: C006
37	  location:
38	    section: experiments
39	    paragraph: 0
40	    sentence: 0
41	  text: Premise-matched ISR 1.06x
42	  type: quantitative
43	  evidence:
44	  - exp_id: D051-analysis
45	    metric: premise_matched_ratio
46	  decisions: []
47	  deprecated: true
48	- id: C010
49	  location:
50	    section: experiments
51	    paragraph: 0
52	    sentence: 0
53	  text: SFT 92.9% genuine
54	  type: quantitative
55	  evidence:
56	  - exp_id: plan009-sft-baseline-s42-r4
57	    metric: genuine_rate
58	  decisions: []
59	  deprecated: true
60	- id: C015
61	  location:
62	    section: experiments
63	    paragraph: 0
64	    sentence: 0
65	  text: Prolog STA 3/3 gaming 0% genuine
66	  type: quantitative
67	  evidence:
68	  - exp_id: plan006-prolog-sta-s42
69	    metric: eval_h7_rate
70	  decisions: []
71	  deprecated: true
72	- id: C016
73	  location:
74	    section: abstract
75	    paragraph: 0
76	    sentence: 0
77	  text: 87% of proved outputs embed the conclusion verbatim among the premises
78	  type: empirical
79	  evidence:
80	  - plan001 exec-only training results
81	  decisions: []
82	  deprecated: true
83	- id: C018
84	  location:
85	    section: abstract
86	    paragraph: 0
87	    sentence: 0
88	  text: ISR falls from 0.642 to 0.003 (99.5% degradation) over 100-1000 GRPO steps
89	    while prove rate rises 32% to 96%
90	  type: empirical
91	  evidence:
92	  - plan001 exec-only 3-seed eval_sta results
93	  decisions: []
94	  deprecated: true
95	- id: C021
96	  location:
97	    section: abstract
98	    paragraph: 0
99	    sentence: 0
100	  text: SFT baseline achieves 92.9% genuine proofs with near-zero hacking
101	  type: empirical
102	  evidence:
103	  - plan008 SFT baseline eval
104	  decisions: []
105	  deprecated: true
106	- id: C025
107	  location:
108	    section: abstract
109	    paragraph: 0
110	    sentence: 0
111	  text: 64.5% of proved samples exhibit conclusion duplication (H7) at beta=0.1, vs
112	    0% under random control
113	  type: empirical
114	  evidence:
115	  - plan013 ISR-as-reward eval
116	  - plan014 random control eval
117	  decisions: []
118	  deprecated: true
119	- id: C030
120	  location:
121	    section: abstract
122	    paragraph: 0
123	    sentence: 0
124	  text: Sole apparent ISR improvement reduces to 1.06x after premise-count confound
125	    control
126	  type: empirical
127	  evidence:
128	  - plan013 premise-count analysis
129	  decisions: []
130	  deprecated: true
131	- id: C036
132	  location:
133	    section: abstract
134	    paragraph: 0
135	    sentence: 0
136	  text: beta=0.3 prove rate collapses to 18% vs 48% random control
137	  type: empirical
138	  evidence:
139	  - plan013 high-dose results
140	  - plan014 random control
141	  decisions: []
142	  deprecated: true
143	- id: C043
144	  location:
145	    section: abstract
146	    paragraph: 0
147	    sentence: 0
148	  text: 'Prolog ISR-as-reward: 3/3 seeds gaming, 0% genuine proofs'
149	  type: empirical
150	  evidence:
151	  - plan017 Prolog ISR-as-reward eval
152	  decisions: []
153	  deprecated: true
154	- id: C051
155	  location:
156	    section: abstract
157	    paragraph: 0
158	    sentence: 0
159	  text: 7 distinct reward hacking modes across conditions and logic types
160	  type: empirical
161	  evidence:
162	  - taxonomy analysis across all experiments
163	  decisions: []
164	  deprecated: true
165	- id: C052
166	  location:
167	    section: method
168	    paragraph: 0
169	    sentence: 0
170	  text: ISR definition via LOO ablation
171	  type: definition
172	  evidence:
173	  - exp_id: sta-phase0-baseline
174	    metric: isr_computation
175	  decisions: []
176	  deprecated: true
177	- id: C054
178	  location:
179	    section: method
180	    paragraph: 0
181	    sentence: 0
182	  text: Additive reward formulation
183	  type: definition
184	  evidence:
185	  - exp_id: plan002-additive-b01-s42
186	    metric: reward_formula
187	  decisions: []
188	  deprecated: true
189	- id: C055
190	  location:
191	    section: introduction
192	    paragraph: 0
193	    sentence: 0
194	  text: 93% prove rate but 87% conclusion embedding
195	  type: quantitative
196	  evidence:
197	  - exp_id: plan001-exec-only-s42-r2
198	    metric: eval_prove_rate=0.93, h1_rate=0.871
199	  decisions: []
200	  deprecated: false
201	- id: C057
202	  location:
203	    section: introduction
204	    paragraph: 0
205	    sentence: 0
206	  text: ISR collapse 0.642 to 0.132 to 0.003
207	  type: quantitative
208	  evidence:
209	  - exp_id: plan003-eval-exec-only-r5
210	    metric: proved_only_isr
211	  - exp_id: plan001-exec-only-s42-r2
212	    metric: eval_proved_only_isr
213	  - exp_id: plan016-extended-1000-s42
214	    metric: isr
215	  decisions: []
216	  deprecated: false
217	- id: C060
218	  location:
219	    section: introduction
220	    paragraph: 0
221	    sentence: 0
222	  text: SFT 92.9% genuine
223	  type: quantitative
224	  evidence:
225	  - exp_id: plan009-sft-baseline-s42-r4
226	    metric: genuine_rate
227	  decisions: []
228	  deprecated: false
229	- id: C064
230	  location:
231	    section: introduction
232	    paragraph: 0
233	    sentence: 0
234	  text: H7=64.5% ISR vs 0% random
235	  type: quantitative
236	  evidence:
237	  - exp_id: plan002-additive-b01-*
238	    metric: h7_rate 3-seed
239	  - exp_id: plan018-additive-random-b01-*
240	    metric: h7_rate=0
241	  decisions: []
242	  deprecated: false
243	- id: C069
244	  location:
245	    section: introduction
246	    paragraph: 0
247	    sentence: 0
248	  text: Premise-matched 1.06x
249	  type: quantitative
250	  evidence:
251	  - exp_id: D051-analysis
252	    metric: premise_matched_ratio
253	  decisions: []
254	  deprecated: false
255	- id: C075
256	  location:
257	    section: introduction
258	    paragraph: 0
259	    sentence: 0
260	  text: 'beta=0.3: PR 18% vs random 48%'
261	  type: quantitative
262	  evidence:
263	  - exp_id: plan002-additive-b03-s42
264	    metric: overall_prove_rate
265	  - exp_id: plan017-additive-random-s42
266	    metric: eval_prove_rate
267	  decisions: []
268	  deprecated: false
269	- id: C082
270	  location:
271	    section: introduction
272	    paragraph: 0
273	    sentence: 0
274	  text: Prolog STA 3/3 gaming 0% genuine
275	  type: quantitative
276	  evidence:
277	  - exp_id: plan006-prolog-sta-*
278	    metric: 0% genuine all seeds
279	  decisions: []
280	  deprecated: false
281	- id: C083
282	  location:
283	    section: related_work
284	    paragraph: 0
285	    sentence: 0
286	  text: 87% of proved outputs under exec-only GRPO embed the conclusion among the
287	    premises
288	  type: empirical
289	  evidence:
290	  - exp_id: plan003-eval-exec-only-r5
291	    metric: h1_rate_step500
292	  decisions: []
293	  deprecated: false
294	- id: C085
295	  location:
296	    section: related_work
297	    paragraph: 0
298	    sentence: 0
299	  text: ISR reliably diagnoses structural quality yet becomes gamed when used as training
300	    reward
301	  type: empirical
302	  evidence:
303	  - exp_id: plan003-eval-exec-only-r5
304	    metric: proved_only_isr
305	  - exp_id: plan003-eval-isr-beta01-r5
306	    metric: h7_rate
307	  decisions: []
308	  deprecated: false
309	- id: C086
310	  location:
311	    section: discussion
312	    paragraph: 0
313	    sentence: 0
314	  text: Downstream NLI accuracy shows no correlation with ISR (Spearman rho=-0.049,
315	    p=0.187, n.s.)
316	  type: empirical
317	  evidence:
318	  - exp_id: plan014-downstream-nli-s42
319	    metric: spearman_rho_isr_nli
320	  decisions: []
321	  deprecated: false
322	- id: C088
323	  location:
324	    section: discussion
325	    paragraph: 0
326	    sentence: 0
327	  text: Controlling for premise count eliminates apparent ISR advantage (1.06x vs
328	    raw 2.4x)
329	  type: empirical
330	  evidence:
331	  - exp_id: plan003-eval-isr-beta01-r5
332	    metric: premise_count_matched_isr_ratio
333	  decisions: []
334	  deprecated: false
335	- id: C091
336	  location:
337	    section: discussion
338	    paragraph: 0
339	    sentence: 0
340	  text: 'Meta-level Goodhart: ISR designed to detect gaming becomes gamed when optimized'
341	  type: interpretive
342	  evidence:
343	  - exp_id: plan003-eval-isr-beta01-r5
344	    metric: h7_rate
345	  - exp_id: plan003-eval-isr-beta03-r5
346	    metric: prove_rate
347	  decisions: []
348	  deprecated: false
349	- id: C092
350	  location:
351	    section: abstract
352	    paragraph: 0
353	    sentence: 0
354	  text: 93% prove rate on FOLIO with 87% conclusion embedding
355	  type: empirical
356	  evidence:
357	  - exp_id: plan003-eval-exec-only-r5
358	    metric: prove_rate_step500
359	  - exp_id: plan003-eval-exec-only-r5
360	    metric: h1_rate_step500
361	  decisions: []
362	  deprecated: false
363	- id: C094
364	  location:
365	    section: abstract
366	    paragraph: 0
367	    sentence: 0
368	  text: ISR falls from 0.642 to 0.003 over 1000 steps while PR rises 32% to 96%
369	  type: empirical
370	  evidence:
371	  - exp_id: plan003-eval-exec-only-r5
372	    metric: proved_only_isr_trajectory
373	  decisions: []
374	  deprecated: false
375	- id: C097
376	  location:
377	    section: abstract
378	    paragraph: 0
379	    sentence: 0
380	  text: SFT baseline 92.9% genuine proofs
381	  type: empirical
382	  evidence:
383	  - exp_id: sft-baseline
384	    metric: genuine_rate
385	  decisions: []
386	  deprecated: false
387	- id: C101
388	  location:
389	    section: abstract
390	    paragraph: 0
391	    sentence: 0
392	  text: 64.5% H7 under ISR beta=0.1 vs 0% random
393	  type: empirical
394	  evidence:
395	  - exp_id: plan003-eval-isr-beta01-r5
396	    metric: h7_rate_3seed
397	  decisions: []
398	  deprecated: false
399	- id: C106
400	  location:
401	    section: abstract
402	    paragraph: 0
403	    sentence: 0
404	  text: Premise-count-matched 1.06x
405	  type: empirical
406	  evidence:
407	  - exp_id: plan003-eval-isr-beta01-r5
408	    metric: premise_count_matched_ratio
409	  decisions: []
410	  deprecated: false
411	- id: C112
412	  location:
413	    section: abstract
414	    paragraph: 0
415	    sentence: 0
416	  text: beta=0.3 PR 18% vs random 48%
417	  type: empirical
418	  evidence:
419	  - exp_id: plan003-eval-isr-beta03-r5
420	    metric: prove_rate
421	  decisions: []
422	  deprecated: false
423	- id: C119
424	  location:
425	    section: abstract
426	    paragraph: 0
427	    sentence: 0
428	  text: Prolog 3/3 seeds gaming, 0% genuine
429	  type: empirical
430	  evidence:
431	  - exp_id: plan003-eval-prolog-isr-r5
432	    metric: genuine_rate_3seed
433	  decisions: []
434	  deprecated: false
435	- id: C120
436	  location:
437	    section: conclusion
438	    paragraph: 0
439	    sentence: 0
440	  text: ISR and NLI accuracy are uncorrelated (rho=-0.049, n.s.)
441	  type: empirical
442	  evidence:
443	  - exp_id: plan014-downstream-nli-s42
444	    metric: spearman_rho
445	  decisions: []
446	  deprecated: false
447	- id: C121
448	  location:
449	    section: method
450	    paragraph: 0
451	    sentence: 0
452	  text: ISR measures the fraction of necessary components via LOO ablation on solver
453	    inputs
454	  type: methodological
455	  evidence:
456	  - eq:isr
457	  decisions:
458	  - D010
459	  deprecated: true
460	- id: C123
461	  location:
462	    section: method
463	    paragraph: 0
464	    sentence: 0
465	  text: 'ISR is subject to component-count confound: fewer components yield mechanically
466	    higher ISR'
467	  type: methodological
468	  evidence:
469	  - D051
470	  decisions:
471	  - D051
472	  deprecated: true
473	- id: C126
474	  location:
475	    section: method
476	    paragraph: 0
477	    sentence: 0
478	  text: Seven hacking modes identified across conditions, seeds, and logic types
479	  type: methodological
480	  evidence:
481	  - plan001-exec-only-s42-r2
482	  - plan002-additive-b01-s42
483	  - plan006-prolog-sta-s44
484	  decisions:
485	  - D027
486	  deprecated: true
487	- id: C127
488	  location:
489	    section: experiments
490	    paragraph: 0
491	    sentence: 0
492	  text: ISR collapse trajectory 0.642 to 0.132 to 0.003 over 100 to 500 to 1000 steps
493	    under exec-only GRPO
494	  type: empirical
495	  evidence:
496	  - plan003-eval-exec-only-r5
497	  - plan001-exec-only-s42-r2
498	  - plan016-extended-1000-s42
499	  decisions: []
500	  deprecated: false
501	- id: C129
502	  location:
503	    section: experiments
504	    paragraph: 0
505	    sentence: 0
506	  text: '3-seed exec-only divergence: s42 H1=87.1%, s43 repetition collapse PR=13%,
507	    s44 tautological H7=100% PR=98%'
508	  type: empirical
509	  evidence:
510	  - plan001-exec-only-s42-r2
511	  - plan001-exec-only-s43-r4
512	  - plan001-exec-only-s44
513	  decisions: []
514	  deprecated: false
515	- id: C132
516	  location:
517	    section: experiments
518	    paragraph: 0
519	    sentence: 0
520	  text: 'SFT baseline: PR=14%, 92.9% non-hacking, near-zero H7/H1, confirming hacking
521	    is RL-reward-specific'
522	  type: empirical
523	  evidence:
524	  - plan009-sft-baseline-s42-r4
525	  decisions: []
526	  deprecated: false
527	- id: C136
528	  location:
529	    section: experiments
530	    paragraph: 0
531	    sentence: 0
532	  text: 'H7 is ISR-specific: 64.5% (149/231) under ISR beta=0.1 vs 0% (0/256) under
533	    random beta=0.1'
534	  type: empirical
535	  evidence:
536	  - plan002-additive-b01-s42
537	  - plan002-additive-b01-s43
538	  - plan002-additive-b01-s44
539	  - plan018-additive-random-b01-s42
540	  - plan018-additive-random-b01-s43-r2
541	  - plan018-additive-random-b01-s44
542	  decisions:
543	  - D057
544	  deprecated: false
545	- id: C141
546	  location:
547	    section: experiments
548	    paragraph: 0
549	    sentence: 0
550	  text: Premise-count-matched ISR 1.06x (0.258 vs 0.243, n>=3 premises), no meaningful
551	    structural advantage
552	  type: empirical
553	  evidence:
554	  - plan002-additive-b01-s42
555	  - plan018-additive-random-b01-s42
556	  decisions:
557	  - D051
558	  deprecated: false
559	- id: C147
560	  location:
561	    section: experiments
562	    paragraph: 0
563	    sentence: 0
564	  text: 'beta=0.3 classic Goodhart: ISR PR=18% vs random PR=48%'
565	  type: empirical
566	  evidence:
567	  - plan002-additive-b03-s42
568	  - plan017-additive-random-s42
569	  decisions: []
570	  deprecated: false
571	- id: C154
572	  location:
573	    section: experiments
574	    paragraph: 0
575	    sentence: 0
576	  text: 'Prolog exec-only: 2/3 seeds ISR* near 0 (s42=0.037, s43=0.015), diagnostic
577	    transfer confirmed'
578	  type: empirical
579	  evidence:
580	  - plan006-prolog-exec-s42
581	  - plan006-prolog-exec-s43-r3
582	  - plan006-prolog-exec-s44
583	  decisions:
584	  - D056
585	  deprecated: false
586	- id: C162
587	  location:
588	    section: experiments
589	    paragraph: 0
590	    sentence: 0
591	  text: 'Prolog ISR-reward: universal Goodhart 0% non-hacking across 185 proved, 3
592	    distinct gaming mechanisms'
593	  type: empirical
594	  evidence:
595	  - plan006-prolog-sta-s42
596	  - plan006-prolog-sta-s43
597	  - plan006-prolog-sta-s44
598	  decisions: []
599	  deprecated: false
600	- id: C171
601	  location:
602	    section: experiments
603	    paragraph: 0
604	    sentence: 0
605	  text: Conclusion embedding is GRPO-universal (68-97%); ISR restructures hacking
606	    composition not prevalence
607	  type: empirical
608	  evidence:
609	  - plan002-additive-b01-s42
610	  - plan018-additive-random-b01-s42
611	  - plan018-additive-random-b01-s43-r2
612	  decisions:
613	  - D057
614	  deprecated: false
615	- id: C172
616	  location:
617	    section: method
618	    paragraph: 0
619	    sentence: 0
620	  text: STA applies LOO ablation to solver inputs to compute ISR as a diagnostic for
621	    reward hacking
622	  type: methodological
623	  evidence:
624	  - sta-phase0-baseline
625	  - plan003-eval-exec-only-r5
626	  decisions:
627	  - D003
628	  - D007
629	  deprecated: false
630	- id: C174
631	  location:
632	    section: method
633	    paragraph: 0
634	    sentence: 0
635	  text: ISR measures syntactic component necessity, not semantic faithfulness
636	  type: scope_limitation
637	  evidence:
638	  - plan014-downstream-nli-s42
639	  decisions:
640	  - D021
641	  deprecated: false
642	- id: C177
643	  location:
644	    section: method
645	    paragraph: 0
646	    sentence: 0
647	  text: ISR is mathematically sensitive to component count (premise count bias)
648	  type: scope_limitation
649	  evidence: []
650	  decisions:
651	  - D051
652	  deprecated: false
653	- id: C181
654	  location:
655	    section: method
656	    paragraph: 0
657	    sentence: 0
658	  text: 'Additive ISR bonus formulation: r = r_exec * (1 + beta * ISR)'
659	  type: methodological
660	  evidence:
661	  - plan002-additive-b01-s42
662	  decisions:
663	  - D010
664	  deprecated: false
665	- id: C186
666	  location:
667	    section: method
668	    paragraph: 0
669	    sentence: 0
670	  text: Convex formulation discarded due to inherent penalty effect
671	  type: negative_result
672	  evidence:
673	  - plan005-sta-low-s42
674	  decisions:
675	  - D010
676	  - D011
677	  deprecated: false
678	- id: C192
679	  location:
680	    section: method
681	    paragraph: 0
682	    sentence: 0
683	  text: 'H7 (conclusion duplication with ISR inflation) is exclusive to ISR-reward
684	    conditions: 64.5% vs 0% under random control'
685	  type: empirical
686	  evidence:
687	  - plan002-additive-b01-s42
688	  - plan002-additive-b01-s43
689	  - plan002-additive-b01-s44
690	  - plan018-additive-random-b01-s42
691	  - plan018-additive-random-b01-s43-r2
692	  - plan018-additive-random-b01-s44
693	  decisions:
694	  - D043
695	  - D057
696	  deprecated: false
697	- id: C199
698	  location:
699	    section: method
700	    paragraph: 0
701	    sentence: 0
702	  text: Seven distinct hacking modes identified across reward conditions and logic
703	    types
704	  type: empirical
705	  evidence:
706	  - plan012-hacking-taxonomy
707	  decisions: []
708	  deprecated: false
709	tables: []
710	figures: []
711	_completeness:
712	  coverage: 35/36
713	  claims: 36
714	  tables: 0
715	  figures: 0
716	  tier_counts:
717	    tier1: 0
718	    tier2: 35
719	    tier3: 1
720	    tierX: 0
721	  last_checked: '2026-05-15T02:40:08.884772+00:00'
722	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "399a36ea-61c9-4cf6-a26a-34c80acc5f29",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "8a3ad403-c15f-47f8-a868-8c73d8c66aa1",
  "toolUseResult": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_provenance.yaml",
      "content": "paper:\n  title: ''\n  version: 12\n  generated_at: '2026-05-15T02:40:08.884665+00:00'\nclaims:\n- id: C001\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: 'ISR collapse: 0.642 to 0.132 to 0.003'\n  type: quantitative\n  evidence:\n  - exp_id: plan003-eval-exec-only-r5\n    metric: proved_only_isr\n  - exp_id: plan001-exec-only-s42-r2\n    metric: eval_proved_only_isr\n  - exp_id: plan016-extended-1000-s42\n    metric: isr\n  decisions: []\n  deprecated: true\n- id: C003\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: 'H7 ISR-specific: 64.5% vs 0% random'\n  type: quantitative\n  evidence:\n  - exp_id: plan002-additive-b01-s42\n    metric: h7_rate\n  - exp_id: plan018-additive-random-b01-s42\n    metric: H7=0\n  decisions: []\n  deprecated: true\n- id: C006\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: Premise-matched ISR 1.06x\n  type: quantitative\n  evidence:\n  - exp_id: D051-analysis\n    metric: premise_matched_ratio\n  decisions: []\n  deprecated: true\n- id: C010\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: SFT 92.9% genuine\n  type: quantitative\n  evidence:\n  - exp_id: plan009-sft-baseline-s42-r4\n    metric: genuine_rate\n  decisions: []\n  deprecated: true\n- id: C015\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: Prolog STA 3/3 gaming 0% genuine\n  type: quantitative\n  evidence:\n  - exp_id: plan006-prolog-sta-s42\n    metric: eval_h7_rate\n  decisions: []\n  deprecated: true\n- id: C016\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: 87% of proved outputs embed the conclusion verbatim among the premises\n  type: empirical\n  evidence:\n  - plan001 exec-only training results\n  decisions: []\n  deprecated: true\n- id: C018\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: ISR falls from 0.642 to 0.003 (99.5% degradation) over 100-1000 GRPO steps\n    while prove rate rises 32% to 96%\n  type: empirical\n  evidence:\n  - plan001 exec-only 3-seed eval_sta results\n  decisions: []\n  deprecated: true\n- id: C021\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: SFT baseline achieves 92.9% genuine proofs with near-zero hacking\n  type: empirical\n  evidence:\n  - plan008 SFT baseline eval\n  decisions: []\n  deprecated: true\n- id: C025\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: 64.5% of proved samples exhibit conclusion duplication (H7) at beta=0.1, vs\n    0% under random control\n  type: empirical\n  evidence:\n  - plan013 ISR-as-reward eval\n  - plan014 random control eval\n  decisions: []\n  deprecated: true\n- id: C030\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: Sole apparent ISR improvement reduces to 1.06x after premise-count confound\n    control\n  type: empirical\n  evidence:\n  - plan013 premise-count analysis\n  decisions: []\n  deprecated: true\n- id: C036\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: beta=0.3 prove rate collapses to 18% vs 48% random control\n  type: empirical\n  evidence:\n  - plan013 high-dose results\n  - plan014 random control\n  decisions: []\n  deprecated: true\n- id: C043\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: 'Prolog ISR-as-reward: 3/3 seeds gaming, 0% genuine proofs'\n  type: empirical\n  evidence:\n  - plan017 Prolog ISR-as-reward eval\n  decisions: []\n  deprecated: true\n- id: C051\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: 7 distinct reward hacking modes across conditions and logic types\n  type: empirical\n  evidence:\n  - taxonomy analysis across all experiments\n  decisions: []\n  deprecated: true\n- id: C052\n  location:\n    section: method\n    paragraph: 0\n    sentence: 0\n  text: ISR definition via LOO ablation\n  type: definition\n  evidence:\n  - exp_id: sta-phase0-baseline\n    metric: isr_computation\n  decisions: []\n  deprecated: true\n- id: C054\n  location:\n    section: method\n    paragraph: 0\n    sentence: 0\n  text: Additive reward formulation\n  type: definition\n  evidence:\n  - exp_id: plan002-additive-b01-s42\n    metric: reward_formula\n  decisions: []\n  deprecated: true\n- id: C055\n  location:\n    section: introduction\n    paragraph: 0\n    sentence: 0\n  text: 93% prove rate but 87% conclusion embedding\n  type: quantitative\n  evidence:\n  - exp_id: plan001-exec-only-s42-r2\n    metric: eval_prove_rate=0.93, h1_rate=0.871\n  decisions: []\n  deprecated: false\n- id: C057\n  location:\n    section: introduction\n    paragraph: 0\n    sentence: 0\n  text: ISR collapse 0.642 to 0.132 to 0.003\n  type: quantitative\n  evidence:\n  - exp_id: plan003-eval-exec-only-r5\n    metric: proved_only_isr\n  - exp_id: plan001-exec-only-s42-r2\n    metric: eval_proved_only_isr\n  - exp_id: plan016-extended-1000-s42\n    metric: isr\n  decisions: []\n  deprecated: false\n- id: C060\n  location:\n    section: introduction\n    paragraph: 0\n    sentence: 0\n  text: SFT 92.9% genuine\n  type: quantitative\n  evidence:\n  - exp_id: plan009-sft-baseline-s42-r4\n    metric: genuine_rate\n  decisions: []\n  deprecated: false\n- id: C064\n  location:\n    section: introduction\n    paragraph: 0\n    sentence: 0\n  text: H7=64.5% ISR vs 0% random\n  type: quantitative\n  evidence:\n  - exp_id: plan002-additive-b01-*\n    metric: h7_rate 3-seed\n  - exp_id: plan018-additive-random-b01-*\n    metric: h7_rate=0\n  decisions: []\n  deprecated: false\n- id: C069\n  location:\n    section: introduction\n    paragraph: 0\n    sentence: 0\n  text: Premise-matched 1.06x\n  type: quantitative\n  evidence:\n  - exp_id: D051-analysis\n    metric: premise_matched_ratio\n  decisions: []\n  deprecated: false\n- id: C075\n  location:\n    section: introduction\n    paragraph: 0\n    sentence: 0\n  text: 'beta=0.3: PR 18% vs random 48%'\n  type: quantitative\n  evidence:\n  - exp_id: plan002-additive-b03-s42\n    metric: overall_prove_rate\n  - exp_id: plan017-additive-random-s42\n    metric: eval_prove_rate\n  decisions: []\n  deprecated: false\n- id: C082\n  location:\n    section: introduction\n    paragraph: 0\n    sentence: 0\n  text: Prolog STA 3/3 gaming 0% genuine\n  type: quantitative\n  evidence:\n  - exp_id: plan006-prolog-sta-*\n    metric: 0% genuine all seeds\n  decisions: []\n  deprecated: false\n- id: C083\n  location:\n    section: related_work\n    paragraph: 0\n    sentence: 0\n  text: 87% of proved outputs under exec-only GRPO embed the conclusion among the\n    premises\n  type: empirical\n  evidence:\n  - exp_id: plan003-eval-exec-only-r5\n    metric: h1_rate_step500\n  decisions: []\n  deprecated: false\n- id: C085\n  location:\n    section: related_work\n    paragraph: 0\n    sentence: 0\n  text: ISR reliably diagnoses structural quality yet becomes gamed when used as training\n    reward\n  type: empirical\n  evidence:\n  - exp_id: plan003-eval-exec-only-r5\n    metric: proved_only_isr\n  - exp_id: plan003-eval-isr-beta01-r5\n    metric: h7_rate\n  decisions: []\n  deprecated: false\n- id: C086\n  location:\n    section: discussion\n    paragraph: 0\n    sentence: 0\n  text: Downstream NLI accuracy shows no correlation with ISR (Spearman rho=-0.049,\n    p=0.187, n.s.)\n  type: empirical\n  evidence:\n  - exp_id: plan014-downstream-nli-s42\n    metric: spearman_rho_isr_nli\n  decisions: []\n  deprecated: false\n- id: C088\n  location:\n    section: discussion\n    paragraph: 0\n    sentence: 0\n  text: Controlling for premise count eliminates apparent ISR advantage (1.06x vs\n    raw 2.4x)\n  type: empirical\n  evidence:\n  - exp_id: plan003-eval-isr-beta01-r5\n    metric: premise_count_matched_isr_ratio\n  decisions: []\n  deprecated: false\n- id: C091\n  location:\n    section: discussion\n    paragraph: 0\n    sentence: 0\n  text: 'Meta-level Goodhart: ISR designed to detect gaming becomes gamed when optimized'\n  type: interpretive\n  evidence:\n  - exp_id: plan003-eval-isr-beta01-r5\n    metric: h7_rate\n  - exp_id: plan003-eval-isr-beta03-r5\n    metric: prove_rate\n  decisions: []\n  deprecated: false\n- id: C092\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: 93% prove rate on FOLIO with 87% conclusion embedding\n  type: empirical\n  evidence:\n  - exp_id: plan003-eval-exec-only-r5\n    metric: prove_rate_step500\n  - exp_id: plan003-eval-exec-only-r5\n    metric: h1_rate_step500\n  decisions: []\n  deprecated: false\n- id: C094\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: ISR falls from 0.642 to 0.003 over 1000 steps while PR rises 32% to 96%\n  type: empirical\n  evidence:\n  - exp_id: plan003-eval-exec-only-r5\n    metric: proved_only_isr_trajectory\n  decisions: []\n  deprecated: false\n- id: C097\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: SFT baseline 92.9% genuine proofs\n  type: empirical\n  evidence:\n  - exp_id: sft-baseline\n    metric: genuine_rate\n  decisions: []\n  deprecated: false\n- id: C101\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: 64.5% H7 under ISR beta=0.1 vs 0% random\n  type: empirical\n  evidence:\n  - exp_id: plan003-eval-isr-beta01-r5\n    metric: h7_rate_3seed\n  decisions: []\n  deprecated: false\n- id: C106\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: Premise-count-matched 1.06x\n  type: empirical\n  evidence:\n  - exp_id: plan003-eval-isr-beta01-r5\n    metric: premise_count_matched_ratio\n  decisions: []\n  deprecated: false\n- id: C112\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: beta=0.3 PR 18% vs random 48%\n  type: empirical\n  evidence:\n  - exp_id: plan003-eval-isr-beta03-r5\n    metric: prove_rate\n  decisions: []\n  deprecated: false\n- id: C119\n  location:\n    section: abstract\n    paragraph: 0\n    sentence: 0\n  text: Prolog 3/3 seeds gaming, 0% genuine\n  type: empirical\n  evidence:\n  - exp_id: plan003-eval-prolog-isr-r5\n    metric: genuine_rate_3seed\n  decisions: []\n  deprecated: false\n- id: C120\n  location:\n    section: conclusion\n    paragraph: 0\n    sentence: 0\n  text: ISR and NLI accuracy are uncorrelated (rho=-0.049, n.s.)\n  type: empirical\n  evidence:\n  - exp_id: plan014-downstream-nli-s42\n    metric: spearman_rho\n  decisions: []\n  deprecated: false\n- id: C121\n  location:\n    section: method\n    paragraph: 0\n    sentence: 0\n  text: ISR measures the fraction of necessary components via LOO ablation on solver\n    inputs\n  type: methodological\n  evidence:\n  - eq:isr\n  decisions:\n  - D010\n  deprecated: true\n- id: C123\n  location:\n    section: method\n    paragraph: 0\n    sentence: 0\n  text: 'ISR is subject to component-count confound: fewer components yield mechanically\n    higher ISR'\n  type: methodological\n  evidence:\n  - D051\n  decisions:\n  - D051\n  deprecated: true\n- id: C126\n  location:\n    section: method\n    paragraph: 0\n    sentence: 0\n  text: Seven hacking modes identified across conditions, seeds, and logic types\n  type: methodological\n  evidence:\n  - plan001-exec-only-s42-r2\n  - plan002-additive-b01-s42\n  - plan006-prolog-sta-s44\n  decisions:\n  - D027\n  deprecated: true\n- id: C127\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: ISR collapse trajectory 0.642 to 0.132 to 0.003 over 100 to 500 to 1000 steps\n    under exec-only GRPO\n  type: empirical\n  evidence:\n  - plan003-eval-exec-only-r5\n  - plan001-exec-only-s42-r2\n  - plan016-extended-1000-s42\n  decisions: []\n  deprecated: false\n- id: C129\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: '3-seed exec-only divergence: s42 H1=87.1%, s43 repetition collapse PR=13%,\n    s44 tautological H7=100% PR=98%'\n  type: empirical\n  evidence:\n  - plan001-exec-only-s42-r2\n  - plan001-exec-only-s43-r4\n  - plan001-exec-only-s44\n  decisions: []\n  deprecated: false\n- id: C132\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: 'SFT baseline: PR=14%, 92.9% non-hacking, near-zero H7/H1, confirming hacking\n    is RL-reward-specific'\n  type: empirical\n  evidence:\n  - plan009-sft-baseline-s42-r4\n  decisions: []\n  deprecated: false\n- id: C136\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: 'H7 is ISR-specific: 64.5% (149/231) under ISR beta=0.1 vs 0% (0/256) under\n    random beta=0.1'\n  type: empirical\n  evidence:\n  - plan002-additive-b01-s42\n  - plan002-additive-b01-s43\n  - plan002-additive-b01-s44\n  - plan018-additive-random-b01-s42\n  - plan018-additive-random-b01-s43-r2\n  - plan018-additive-random-b01-s44\n  decisions:\n  - D057\n  deprecated: false\n- id: C141\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: Premise-count-matched ISR 1.06x (0.258 vs 0.243, n>=3 premises), no meaningful\n    structural advantage\n  type: empirical\n  evidence:\n  - plan002-additive-b01-s42\n  - plan018-additive-random-b01-s42\n  decisions:\n  - D051\n  deprecated: false\n- id: C147\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: 'beta=0.3 classic Goodhart: ISR PR=18% vs random PR=48%'\n  type: empirical\n  evidence:\n  - plan002-additive-b03-s42\n  - plan017-additive-random-s42\n  decisions: []\n  deprecated: false\n- id: C154\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: 'Prolog exec-only: 2/3 seeds ISR* near 0 (s42=0.037, s43=0.015), diagnostic\n    transfer confirmed'\n  type: empirical\n  evidence:\n  - plan006-prolog-exec-s42\n  - plan006-prolog-exec-s43-r3\n  - plan006-prolog-exec-s44\n  decisions:\n  - D056\n  deprecated: false\n- id: C162\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: 'Prolog ISR-reward: universal Goodhart 0% non-hacking across 185 proved, 3\n    distinct gaming mechanisms'\n  type: empirical\n  evidence:\n  - plan006-prolog-sta-s42\n  - plan006-prolog-sta-s43\n  - plan006-prolog-sta-s44\n  decisions: []\n  deprecated: false\n- id: C171\n  location:\n    section: experiments\n    paragraph: 0\n    sentence: 0\n  text: Conclusion embedding is GRPO-universal (68-97%); ISR restructures hacking\n    composition not prevalence\n  type: empirical\n  evidence:\n  - plan002-additive-b01-s42\n  - plan018-additive-random-b01-s42\n  - plan018-additive-random-b01-s43-r2\n  decisions:\n  - D057\n  deprecated: false\n- id: C172\n  location:\n    section: method\n    paragraph: 0\n    sentence: 0\n  text: STA applies LOO ablation to solver inputs to compute ISR as a diagnostic for\n    reward hacking\n  type: methodological\n  evidence:\n  - sta-phase0-baseline\n  - plan003-eval-exec-only-r5\n  decisions:\n  - D003\n  - D007\n  deprecated: false\n- id: C174\n  location:\n    section: method\n    paragraph: 0\n    sentence: 0\n  text: ISR measures syntactic component necessity, not semantic faithfulness\n  type: scope_limitation\n  evidence:\n  - plan014-downstream-nli-s42\n  decisions:\n  - D021\n  deprecated: false\n- id: C177\n  location:\n    section: method\n    paragraph: 0\n    sentence: 0\n  text: ISR is mathematically sensitive to component count (premise count bias)\n  type: scope_limitation\n  evidence: []\n  decisions:\n  - D051\n  deprecated: false\n- id: C181\n  location:\n    section: method\n    paragraph: 0\n    sentence: 0\n  text: 'Additive ISR bonus formulation: r = r_exec * (1 + beta * ISR)'\n  type: methodological\n  evidence:\n  - plan002-additive-b01-s42\n  decisions:\n  - D010\n  deprecated: false\n- id: C186\n  location:\n    section: method\n    paragraph: 0\n    sentence: 0\n  text: Convex formulation discarded due to inherent penalty effect\n  type: negative_result\n  evidence:\n  - plan005-sta-low-s42\n  decisions:\n  - D010\n  - D011\n  deprecated: false\n- id: C192\n  location:\n    section: method\n    paragraph: 0\n    sentence: 0\n  text: 'H7 (conclusion duplication with ISR inflation) is exclusive to ISR-reward\n    conditions: 64.5% vs 0% under random control'\n  type: empirical\n  evidence:\n  - plan002-additive-b01-s42\n  - plan002-additive-b01-s43\n  - plan002-additive-b01-s44\n  - plan018-additive-random-b01-s42\n  - plan018-additive-random-b01-s43-r2\n  - plan018-additive-random-b01-s44\n  decisions:\n  - D043\n  - D057\n  deprecated: false\n- id: C199\n  location:\n    section: method\n    paragraph: 0\n    sentence: 0\n  text: Seven distinct hacking modes identified across reward conditions and logic\n    types\n  type: empirical\n  evidence:\n  - plan012-hacking-taxonomy\n  decisions: []\n  deprecated: false\ntables: []\nfigures: []\n_completeness:\n  coverage: 35/36\n  claims: 36\n  tables: 0\n  figures: 0\n  tier_counts:\n    tier1: 0\n    tier2: 35\n    tier3: 1\n    tierX: 0\n  last_checked: '2026-05-15T02:40:08.884772+00:00'\n",
      "numLines": 722,
      "startLine": 1,
      "totalLines": 722
    }
  },
  "sourceToolAssistantUUID": "399a36ea-61c9-4cf6-a26a-34c80acc5f29",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 39 · 2026-05-15T17:39:09.170Z_

<details open><summary>🔧 Tool call — Bash · `toolu_013hX4heaNFL1SG5f1qqGNmW`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-3-projects-solver-trace-ablation/d09c16fe-783f-4107-8777-2fc80b263d10/tool-results/mcp-agent-ml-research-read_registry-1778866688318.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n# Get plan018-additive-random-b01-s42 details\ne = exps.get('plan018-additive-random-b01-s42', {})\nprint('=== plan018-additive-random-b01-s42 ===')\nprint(json.dumps({k: e.get(k) for k in ['status','conclusion','metrics','notes']}, indent=2, default=str))\nprint()\n# Get plan002-additive-b01-s42 details for genuine data\ne2 = exps.get('plan002-additive-b01-s42', {})\nprint('=== plan002-additive-b01-s42 ===')\nprint(json.dumps({k: e2.get(k) for k in ['status','conclusion','metrics','notes']}, indent=2, default=str))\nprint()\n# Get plan018-additive-random-b01-s43 related\nfor eid in sorted(exps.keys()):\n    if 'plan018-additive-random-b01-s4' in eid:\n        e3 = exps[eid]\n        print(f'=== {eid} ===')\n        print(f'  status={e3.get(\\\"status\\\")}, conclusion={e3.get(\\\"conclusion\\\")}')\n        m = e3.get('metrics', {})\n        if m:\n            print(f'  metrics={json.dumps(m, default=str)}')\n\"\n",
  "description": "Get registry details for Random s42/s43/s44 experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8a3ad403-c15f-47f8-a868-8c73d8c66aa1",
  "isSidechain": false,
  "requestId": "req_011Cb4mBGxqnavZsa5ko4xiC",
  "type": "assistant",
  "uuid": "0028b458-1f5e-4ff4-98e7-aa06967cf19e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KVsFSFdUd1q6tWYxbZoVwb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 734,
      "cache_read_input_tokens": 49731,
      "output_tokens": 1662,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 734,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1662,
          "cache_read_input_tokens": 49731,
          "cache_creation_input_tokens": 734,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 734
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

_source line 40 · 2026-05-15T17:39:09.292Z_

<details><summary>↩ Tool result · `toolu_013hX4heaNFL1SG5f1qqGNmW`</summary>

```text
=== plan018-additive-random-b01-s42 ===
{
  "status": "DONE",
  "conclusion": "negative",
  "metrics": {
    "eval_prove_rate": 0.79,
    "eval_mean_isr": 0.1038,
    "eval_isr_std": 0.1369,
    "eval_median_isr": 0.0357,
    "eval_proved_only_isr": 0.1314,
    "eval_n_proved": 79,
    "eval_n_problems": 100,
    "tautological_collapse": false,
    "h7_count": 0,
    "h7_rate": 0,
    "h1_count": 56,
    "h1_rate": 0.7089,
    "h1_near_count": 8,
    "h1_near_rate": 0.1013,
    "h8_conjunction_collapse_count": 3,
    "h8_conjunction_collapse_rate": 0.038,
    "genuine_count_exact_h1": 23,
    "genuine_rate_exact_h1": 0.2911,
    "genuine_count_strict": 12,
    "genuine_rate_strict": 0.1519,
    "taxonomy_verification": "2026-05-15: full re-verification from eval_sta file. H1 exact=56, H1-near(substring)=8 (5 conc_in_prem + 3 prem_in_conc), H8=3, strict genuine=12. Registry original genuine=23 = H8(3) + H1-near(8) + strict genuine(12)."
  },
  "notes": "Random control \u03b2=0.1 vs ISR \u03b2=0.1 (plan002-b01) \u5bf9\u7167\u3002conclusion=negative: random control\u7684ISR\u8fdc\u4f4e\u4e8eISR-guided\u3002\n\n\u5bf9\u6bd4 plan002-b01 (ISR \u03b2=0.1):\n- PR: 0.79 vs 0.81 (\u2248\u6301\u5e73, \u0394=0.02)\n- Mean ISR: 0.104 vs 0.337 (ISR 3.2x higher)\n- Proved-only ISR: 0.131 vs 0.415 (ISR 3.2x higher)\n- Median ISR: 0.036 vs plan002\u672a\u8bb0\u5f55\n- Component count: 8.46 vs 5.58 (random\u7ec4\u66f4\u591a\u5197\u4f59)\n- ISR=0\u5360\u6bd4(proved): 36.7% (random\u7ec4\u5927\u91cfproof\u65e0\u7ed3\u6784)\n- Tautological collapse: \u65e0 (component_2_ratio=0)\n\n\u5173\u952e\u53d1\u73b0: PR\u51e0\u4e4e\u76f8\u540c\u8bf4\u660e\u03b2=0.1 random\u566a\u58f0\u4e0d\u5f71\u54cd\u8bc1\u660e\u80fd\u529b\u3002\u4f46ISR\u5dee3.2\u500d\uff0c\u8bc1\u660eISR reward\u63d0\u4f9bgenuine structural guidance\u800c\u975e\u4ec5variance regularization\u3002\u8fd9\u5f3a\u529b\u652f\u6301Claim 2: ISR\u4fe1\u53f7\u5728\u4f4e\u5242\u91cf\u4e0b\u6709\u7ed3\u6784\u4ef7\u503c\u3002\n\nEval output: /root/autodl-tmp/outputs/plan018_additive_random_b01_s42/eval_results.json"
}

=== plan002-additive-b01-s42 ===
{
  "status": "DONE",
  "conclusion": "negative",
  "metrics": {
    "eval_prove_rate": 0.81,
    "eval_mean_isr": 0.3365,
    "eval_isr_std": 0.3227,
    "eval_proved_only_isr": 0.4154,
    "eval_median_isr": 0.2,
    "eval_n_proved": 81,
    "eval_n_problems": 100,
    "eval_method": "eval_sta.py full STA",
    "eval_data": "proofwriter_fol_100.jsonl",
    "eval_component_count_mean": 5.58,
    "h7_rate": 0.16,
    "h7_count": 13,
    "h1_rate": 0.519,
    "h1_count": 42,
    "h8_conjunction_collapse_count": 12,
    "h8_conjunction_collapse_rate": 0.148,
    "genuine_rate": 0.173,
    "genuine_count": 14,
    "tautological_collapse": false,
    "h8_audit_note": "2026-05-15: H8 conjunction collapse audit completed. 12/81 proved samples are H8. Genuine 26\u219214 (32.1%\u219217.3%). H8 JSON at /root/autodl-tmp/outputs/h7_classification/plan002_additive_b01_s42_h8.json"
  },
  "notes": "H8 re-audit (2026-05-15): 81 proved samples. H7 (single premise=conclusion): 13/81=16.1%, H1 (multi-prem conclusion embedding): 42/81=51.9%, H8 (conjunction collapse): 12/81=14.8%, content-independent: 19/81=23.5%. Genuine (proved - H7 - H1 - H8): 14/81=17.3%. Pre-H8 genuine was 26/81=32.1% \u2014 H8 removed 12 samples. Combined conclusion duplication+conjunction = 82.7%. Eval source: proofwriter_fol_100.jsonl (backup at /root/autodl-tmp/eval_results_backup/). H8 JSON: /root/autodl-tmp/outputs/h7_classification/plan002_additive_b01_s42_h8.json. \u26a0\ufe0f RECLASSIFIED negative (Reviewer WARNING): 500\u6b65\u5feb\u7167 genuine 30.9%\uff08H8 \u672a\u6263\u9664\uff0c\u4e3a\u4e0a\u754c\uff09\uff0c1000\u6b65\u5d29\u584c\u81f3 2.2%\uff0c\u8868\u660e Goodhart collapse \u5df2\u5728 500 \u6b65\u542f\u52a8\u4f46\u672a\u5b8c\u6210\u3002"
}

=== plan018-additive-random-b01-s42 ===
  status=DONE, conclusion=negative
  metrics={"eval_prove_rate": 0.79, "eval_mean_isr": 0.1038, "eval_isr_std": 0.1369, "eval_median_isr": 0.0357, "eval_proved_only_isr": 0.1314, "eval_n_proved": 79, "eval_n_problems": 100, "tautological_collapse": false, "h7_count": 0, "h7_rate": 0, "h1_count": 56, "h1_rate": 0.7089, "h1_near_count": 8, "h1_near_rate": 0.1013, "h8_conjunction_collapse_count": 3, "h8_conjunction_collapse_rate": 0.038, "genuine_count_exact_h1": 23, "genuine_rate_exact_h1": 0.2911, "genuine_count_strict": 12, "genuine_rate_strict": 0.1519, "taxonomy_verification": "2026-05-15: full re-verification from eval_sta file. H1 exact=56, H1-near(substring)=8 (5 conc_in_prem + 3 prem_in_conc), H8=3, strict genuine=12. Registry original genuine=23 = H8(3) + H1-near(8) + strict genuine(12)."}
=== plan018-additive-random-b01-s42-1000 ===
  status=DONE, conclusion=failed
=== plan018-additive-random-b01-s42-1000-r2 ===
  status=DONE, conclusion=negative
  metrics={"train_final_prove_rate": 0.989, "train_final_mean_isr": 0.353, "train_final_reward": 1.062, "train_steps": 1000, "train_runtime_seconds": 2957, "eval_prove_rate": 1, "eval_mean_isr": 0.3333, "eval_isr_std": 0, "eval_median_isr": 0.3333, "eval_proved_only_isr": 0.3333, "eval_n_proved": 100, "eval_n_problems": 100, "eval_component_count_mean": 3, "genuine_rate": 0, "genuine_count": 0, "tautological_collapse": true, "h7_rate": null, "h7_count": null, "h1_rate": null, "h1_count": null}
=== plan018-additive-random-b01-s42-1000-r3 ===
  status=DONE, conclusion=negative
  metrics={"eval_prove_rate": 0.97, "eval_mean_isr": 0.6892, "eval_isr_std": 0.2037, "eval_median_isr": 0.75, "eval_proved_only_isr": 0.7105, "eval_n_proved": 97, "eval_n_problems": 100, "genuine_count": 0, "genuine_rate": 0, "h1_count": 0, "h1_rate": 0, "h7_count": 97, "h7_rate": 1, "tautological_collapse": true, "train_final_prove_rate": 0.827, "train_final_mean_isr": 0.5213, "train_loss": 0.00671, "train_final_entropy": 0.003, "train_runtime_seconds": 5783, "train_steps": 1000, "eval_by_answer_type": {"false": {"count": 25, "proved": 25, "prove_rate": 1, "mean_isr": 0.7533}, "unknown": {"count": 41, "proved": 39, "prove_rate": 0.951, "mean_isr": 0.6565}, "true": {"count": 34, "proved": 33, "prove_rate": 0.971, "mean_isr": 0.6814}}, "n_premise_distribution": {"1": 97}, "pattern_description": "All 97 proved: 1 premise identical to conclusion (P therefore P). D088 correction: h7=97 h1=0 (was h1=97 h7=0 pre-D086 bugfix)."}
=== plan018-additive-random-b01-s43 ===
  status=DONE, conclusion=failed
=== plan018-additive-random-b01-s43-r2 ===
  status=DONE, conclusion=negative
  metrics={"h7_rate": 0, "h7_count": 0, "h1_rate": 93.2, "h1_count": 82, "genuine_rate": 6.8, "genuine_count": 6, "eval_prove_rate": 0.88, "eval_mean_isr": 0.058}
=== plan018-additive-random-b01-s43-r3 ===
  status=RUNNING, conclusion=None
=== plan018-additive-random-b01-s44 ===
  status=DONE, conclusion=success
  metrics={"prove_rate": 0.89, "mean_isr": 0.0619, "isr_std": 0.1756, "median_isr": 0, "proved_only_mean_isr": 0.0695, "n_proved": 89, "n_problems": 100, "max_isr": 1, "min_isr": 0, "isr_pr_ratio": 0.0695, "isr_zero_count": 72, "isr_one_count": 2, "by_answer_type": {"false": {"count": 25, "proved": 21, "prove_rate": 0.84, "mean_isr": 0.0533}, "unknown": {"count": 41, "proved": 40, "prove_rate": 0.976, "mean_isr": 0.0892}, "true": {"count": 34, "proved": 28, "prove_rate": 0.824, "mean_isr": 0.0353}}, "elapsed_seconds": 1012.7, "eval_method": "eval_sta.py with Prover9Solver, FOL"}
=== plan018-additive-random-b01-s44-r2 ===
  status=ALLOCATED, conclusion=None
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0028b458-1f5e-4ff4-98e7-aa06967cf19e",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "7d448989-665f-44b1-8d28-7b5cc6c1283e",
  "toolUseResult": {
    "stdout": "=== plan018-additive-random-b01-s42 ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"negative\",\n  \"metrics\": {\n    \"eval_prove_rate\": 0.79,\n    \"eval_mean_isr\": 0.1038,\n    \"eval_isr_std\": 0.1369,\n    \"eval_median_isr\": 0.0357,\n    \"eval_proved_only_isr\": 0.1314,\n    \"eval_n_proved\": 79,\n    \"eval_n_problems\": 100,\n    \"tautological_collapse\": false,\n    \"h7_count\": 0,\n    \"h7_rate\": 0,\n    \"h1_count\": 56,\n    \"h1_rate\": 0.7089,\n    \"h1_near_count\": 8,\n    \"h1_near_rate\": 0.1013,\n    \"h8_conjunction_collapse_count\": 3,\n    \"h8_conjunction_collapse_rate\": 0.038,\n    \"genuine_count_exact_h1\": 23,\n    \"genuine_rate_exact_h1\": 0.2911,\n    \"genuine_count_strict\": 12,\n    \"genuine_rate_strict\": 0.1519,\n    \"taxonomy_verification\": \"2026-05-15: full re-verification from eval_sta file. H1 exact=56, H1-near(substring)=8 (5 conc_in_prem + 3 prem_in_conc), H8=3, strict genuine=12. Registry original genuine=23 = H8(3) + H1-near(8) + strict genuine(12).\"\n  },\n  \"notes\": \"Random control \\u03b2=0.1 vs ISR \\u03b2=0.1 (plan002-b01) \\u5bf9\\u7167\\u3002conclusion=negative: random control\\u7684ISR\\u8fdc\\u4f4e\\u4e8eISR-guided\\u3002\\n\\n\\u5bf9\\u6bd4 plan002-b01 (ISR \\u03b2=0.1):\\n- PR: 0.79 vs 0.81 (\\u2248\\u6301\\u5e73, \\u0394=0.02)\\n- Mean ISR: 0.104 vs 0.337 (ISR 3.2x higher)\\n- Proved-only ISR: 0.131 vs 0.415 (ISR 3.2x higher)\\n- Median ISR: 0.036 vs plan002\\u672a\\u8bb0\\u5f55\\n- Component count: 8.46 vs 5.58 (random\\u7ec4\\u66f4\\u591a\\u5197\\u4f59)\\n- ISR=0\\u5360\\u6bd4(proved): 36.7% (random\\u7ec4\\u5927\\u91cfproof\\u65e0\\u7ed3\\u6784)\\n- Tautological collapse: \\u65e0 (component_2_ratio=0)\\n\\n\\u5173\\u952e\\u53d1\\u73b0: PR\\u51e0\\u4e4e\\u76f8\\u540c\\u8bf4\\u660e\\u03b2=0.1 random\\u566a\\u58f0\\u4e0d\\u5f71\\u54cd\\u8bc1\\u660e\\u80fd\\u529b\\u3002\\u4f46ISR\\u5dee3.2\\u500d\\uff0c\\u8bc1\\u660eISR reward\\u63d0\\u4f9bgenuine structural guidance\\u800c\\u975e\\u4ec5variance regularization\\u3002\\u8fd9\\u5f3a\\u529b\\u652f\\u6301Claim 2: ISR\\u4fe1\\u53f7\\u5728\\u4f4e\\u5242\\u91cf\\u4e0b\\u6709\\u7ed3\\u6784\\u4ef7\\u503c\\u3002\\n\\nEval output: /root/autodl-tmp/outputs/plan018_additive_random_b01_s42/eval_results.json\"\n}\n\n=== plan002-additive-b01-s42 ===\n{\n  \"status\": \"DONE\",\n  \"conclusion\": \"negative\",\n  \"metrics\": {\n    \"eval_prove_rate\": 0.81,\n    \"eval_mean_isr\": 0.3365,\n    \"eval_isr_std\": 0.3227,\n    \"eval_proved_only_isr\": 0.4154,\n    \"eval_median_isr\": 0.2,\n    \"eval_n_proved\": 81,\n    \"eval_n_problems\": 100,\n    \"eval_method\": \"eval_sta.py full STA\",\n    \"eval_data\": \"proofwriter_fol_100.jsonl\",\n    \"eval_component_count_mean\": 5.58,\n    \"h7_rate\": 0.16,\n    \"h7_count\": 13,\n    \"h1_rate\": 0.519,\n    \"h1_count\": 42,\n    \"h8_conjunction_collapse_count\": 12,\n    \"h8_conjunction_collapse_rate\": 0.148,\n    \"genuine_rate\": 0.173,\n    \"genuine_count\": 14,\n    \"tautological_collapse\": false,\n    \"h8_audit_note\": \"2026-05-15: H8 conjunction collapse audit completed. 12/81 proved samples are H8. Genuine 26\\u219214 (32.1%\\u219217.3%). H8 JSON at /root/autodl-tmp/outputs/h7_classification/plan002_additive_b01_s42_h8.json\"\n  },\n  \"notes\": \"H8 re-audit (2026-05-15): 81 proved samples. H7 (single premise=conclusion): 13/81=16.1%, H1 (multi-prem conclusion embedding): 42/81=51.9%, H8 (conjunction collapse): 12/81=14.8%, content-independent: 19/81=23.5%. Genuine (proved - H7 - H1 - H8): 14/81=17.3%. Pre-H8 genuine was 26/81=32.1% \\u2014 H8 removed 12 samples. Combined conclusion duplication+conjunction = 82.7%. Eval source: proofwriter_fol_100.jsonl (backup at /root/autodl-tmp/eval_results_backup/). H8 JSON: /root/autodl-tmp/outputs/h7_classification/plan002_additive_b01_s42_h8.json. \\u26a0\\ufe0f RECLASSIFIED negative (Reviewer WARNING): 500\\u6b65\\u5feb\\u7167 genuine 30.9%\\uff08H8 \\u672a\\u6263\\u9664\\uff0c\\u4e3a\\u4e0a\\u754c\\uff09\\uff0c1000\\u6b65\\u5d29\\u584c\\u81f3 2.2%\\uff0c\\u8868\\u660e Goodhart collapse \\u5df2\\u5728 500 \\u6b65\\u542f\\u52a8\\u4f46\\u672a\\u5b8c\\u6210\\u3002\"\n}\n\n=== plan018-additive-random-b01-s42 ===\n  status=DONE, conclusion=negative\n  metrics={\"eval_prove_rate\": 0.79, \"eval_mean_isr\": 0.1038, \"eval_isr_std\": 0.1369, \"eval_median_isr\": 0.0357, \"eval_proved_only_isr\": 0.1314, \"eval_n_proved\": 79, \"eval_n_problems\": 100, \"tautological_collapse\": false, \"h7_count\": 0, \"h7_rate\": 0, \"h1_count\": 56, \"h1_rate\": 0.7089, \"h1_near_count\": 8, \"h1_near_rate\": 0.1013, \"h8_conjunction_collapse_count\": 3, \"h8_conjunction_collapse_rate\": 0.038, \"genuine_count_exact_h1\": 23, \"genuine_rate_exact_h1\": 0.2911, \"genuine_count_strict\": 12, \"genuine_rate_strict\": 0.1519, \"taxonomy_verification\": \"2026-05-15: full re-verification from eval_sta file. H1 exact=56, H1-near(substring)=8 (5 conc_in_prem + 3 prem_in_conc), H8=3, strict genuine=12. Registry original genuine=23 = H8(3) + H1-near(8) + strict genuine(12).\"}\n=== plan018-additive-random-b01-s42-1000 ===\n  status=DONE, conclusion=failed\n=== plan018-additive-random-b01-s42-1000-r2 ===\n  status=DONE, conclusion=negative\n  metrics={\"train_final_prove_rate\": 0.989, \"train_final_mean_isr\": 0.353, \"train_final_reward\": 1.062, \"train_steps\": 1000, \"train_runtime_seconds\": 2957, \"eval_prove_rate\": 1, \"eval_mean_isr\": 0.3333, \"eval_isr_std\": 0, \"eval_median_isr\": 0.3333, \"eval_proved_only_isr\": 0.3333, \"eval_n_proved\": 100, \"eval_n_problems\": 100, \"eval_component_count_mean\": 3, \"genuine_rate\": 0, \"genuine_count\": 0, \"tautological_collapse\": true, \"h7_rate\": null, \"h7_count\": null, \"h1_rate\": null, \"h1_count\": null}\n=== plan018-additive-random-b01-s42-1000-r3 ===\n  status=DONE, conclusion=negative\n  metrics={\"eval_prove_rate\": 0.97, \"eval_mean_isr\": 0.6892, \"eval_isr_std\": 0.2037, \"eval_median_isr\": 0.75, \"eval_proved_only_isr\": 0.7105, \"eval_n_proved\": 97, \"eval_n_problems\": 100, \"genuine_count\": 0, \"genuine_rate\": 0, \"h1_count\": 0, \"h1_rate\": 0, \"h7_count\": 97, \"h7_rate\": 1, \"tautological_collapse\": true, \"train_final_prove_rate\": 0.827, \"train_final_mean_isr\": 0.5213, \"train_loss\": 0.00671, \"train_final_entropy\": 0.003, \"train_runtime_seconds\": 5783, \"train_steps\": 1000, \"eval_by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 25, \"prove_rate\": 1, \"mean_isr\": 0.7533}, \"unknown\": {\"count\": 41, \"proved\": 39, \"prove_rate\": 0.951, \"mean_isr\": 0.6565}, \"true\": {\"count\": 34, \"proved\": 33, \"prove_rate\": 0.971, \"mean_isr\": 0.6814}}, \"n_premise_distribution\": {\"1\": 97}, \"pattern_description\": \"All 97 proved: 1 premise identical to conclusion (P therefore P). D088 correction: h7=97 h1=0 (was h1=97 h7=0 pre-D086 bugfix).\"}\n=== plan018-additive-random-b01-s43 ===\n  status=DONE, conclusion=failed\n=== plan018-additive-random-b01-s43-r2 ===\n  status=DONE, conclusion=negative\n  metrics={\"h7_rate\": 0, \"h7_count\": 0, \"h1_rate\": 93.2, \"h1_count\": 82, \"genuine_rate\": 6.8, \"genuine_count\": 6, \"eval_prove_rate\": 0.88, \"eval_mean_isr\": 0.058}\n=== plan018-additive-random-b01-s43-r3 ===\n  status=RUNNING, conclusion=None\n=== plan018-additive-random-b01-s44 ===\n  status=DONE, conclusion=success\n  metrics={\"prove_rate\": 0.89, \"mean_isr\": 0.0619, \"isr_std\": 0.1756, \"median_isr\": 0, \"proved_only_mean_isr\": 0.0695, \"n_proved\": 89, \"n_problems\": 100, \"max_isr\": 1, \"min_isr\": 0, \"isr_pr_ratio\": 0.0695, \"isr_zero_count\": 72, \"isr_one_count\": 2, \"by_answer_type\": {\"false\": {\"count\": 25, \"proved\": 21, \"prove_rate\": 0.84, \"mean_isr\": 0.0533}, \"unknown\": {\"count\": 41, \"proved\": 40, \"prove_rate\": 0.976, \"mean_isr\": 0.0892}, \"true\": {\"count\": 34, \"proved\": 28, \"prove_rate\": 0.824, \"mean_isr\": 0.0353}}, \"elapsed_seconds\": 1012.7, \"eval_method\": \"eval_sta.py with Prover9Solver, FOL\"}\n=== plan018-additive-random-b01-s44-r2 ===\n  status=ALLOCATED, conclusion=None",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "0028b458-1f5e-4ff4-98e7-aa06967cf19e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 41_

```json
{
  "type": "last-prompt",
  "leafUuid": "7d448989-665f-44b1-8d28-7b5cc6c1283e",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10"
}
```

---

### Runtime record

_source line 42_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix provenance gaps and prepare statistics recalc checklist",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10"
}
```

---

### Assistant

_source line 43 · 2026-05-15T17:39:35.136Z_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the information I need.

**Task 1: Fix C177 provenance**

C177 is the missing claim with `evidence: []`. The claim is "ISR is mathematically sensitive to component count (premise count bias)" — a scope_limitation in the method section, referencing decision D051.

The evidence for this claim should be the same experiments that demonstrated the premise-count confound:
- plan002-additive-b01-s42 (ISR condition, showing premise minimization)
- plan018-additive-random-b01-s42 (Random control, used for comparison)


The metric here is the premise_count_isr_confound showing that n_prem≥3 matching yields 1.06x. I'll update the provenance YAML to add these evidence links and fix the completeness counter.

**Task 2: Stats recalculation checklist**

From the paper_framing, I need to verify the Random s42 baseline: genuine_count_strict=12, genuine_rate_strict=0.1519, with H7=0, H1=56 (exact), H8=3, and the strict genuine count of 12.

Now I'm reconciling the discrepancy between the D086 clean run showing 18/79=22.8% genuine versus the registry's genuine_count_exact_h1=23 and genuine_rate_exact_h1=0.2911. The taxonomy_verification breaks this down as H1 exact=56, H1-near (substring)=8, H8=3, and strict genuine=12, which sum to the registry's original genuine=23. But the paper_framing references D086 clean run at 18/79, and the D084 standard formula is genuine = proved − H7 − H1_exact − H8, so I need to verify which calculation applies here. I'm getting caught up in the details here when I should focus on the actual task—preparing a checklist rather than solving the computation right now. The key thing is that s43 and s44 are still retraining, so once those finish I'll need to re-evaluate both and then recalculate the pooled Random statistics. My immediate next steps are to update the C177 evidence in the provenance YAML and create the stats recalculation checklist.

Adding the evidence entries for C177...
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7d448989-665f-44b1-8d28-7b5cc6c1283e",
  "isSidechain": false,
  "requestId": "req_011Cb4mDM6C2QQkMnv27LnK8",
  "type": "assistant",
  "uuid": "ba52f5a7-4245-4ccf-9076-037e12f57477",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X4GyA1zuiQfnY8xaRhytNW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12640,
      "cache_read_input_tokens": 50465,
      "output_tokens": 1626,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12640,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1626,
          "cache_read_input_tokens": 50465,
          "cache_creation_input_tokens": 12640,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12640
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

_source line 44 · 2026-05-15T17:39:35.137Z_

Now I have everything needed. Let me fix C177 and write the checklist in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ba52f5a7-4245-4ccf-9076-037e12f57477",
  "isSidechain": false,
  "requestId": "req_011Cb4mDM6C2QQkMnv27LnK8",
  "type": "assistant",
  "uuid": "c2a7ddcf-0e8d-484c-acdf-9382df941fd0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X4GyA1zuiQfnY8xaRhytNW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12640,
      "cache_read_input_tokens": 50465,
      "output_tokens": 1626,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12640,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1626,
          "cache_read_input_tokens": 50465,
          "cache_creation_input_tokens": 12640,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12640
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

_source line 45 · 2026-05-15T17:39:38.292Z_

<details open><summary>🔧 Tool call — Edit · `toolu_01JnyXxkSnLgco2FmnrPMDzU`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_provenance.yaml",
  "old_string": "  text: ISR is mathematically sensitive to component count (premise count bias)\n  type: scope_limitation\n  evidence: []\n  decisions:\n  - D051",
  "new_string": "  text: ISR is mathematically sensitive to component count (premise count bias)\n  type: scope_limitation\n  evidence:\n  - exp_id: plan002-additive-b01-s42\n    metric: premise_count_isr_confound\n  - exp_id: plan018-additive-random-b01-s42\n    metric: premise_count_matched_isr_ratio_1.06x\n  decisions:\n  - D051"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c2a7ddcf-0e8d-484c-acdf-9382df941fd0",
  "isSidechain": false,
  "requestId": "req_011Cb4mDM6C2QQkMnv27LnK8",
  "type": "assistant",
  "uuid": "fd41f277-379c-4628-abcf-3e1cef9a95bb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X4GyA1zuiQfnY8xaRhytNW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12640,
      "cache_read_input_tokens": 50465,
      "output_tokens": 1626,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12640,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1626,
          "cache_read_input_tokens": 50465,
          "cache_creation_input_tokens": 12640,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12640
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

_source line 46 · 2026-05-15T17:39:40.822Z_

<details><summary>↩ Tool result · `toolu_01VGHHYVN4iWGZNsEyFGV51j`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_provenance.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "448d12b1-010f-49d6-9aed-9dda2912b412",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "053a91b8-d340-46bf-9a5e-e3765f12908b",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_provenance.yaml",
    "oldString": "_completeness:\n  coverage: 35/36\n  claims: 36\n  tables: 0\n  figures: 0\n  tier_counts:\n    tier1: 0\n    tier2: 35\n    tier3: 1\n    tierX: 0\n  last_checked: '2026-05-15T02:40:08.884772+00:00'",
    "newString": "_completeness:\n  coverage: 36/36\n  claims: 36\n  tables: 0\n  figures: 0\n  tier_counts:\n    tier1: 0\n    tier2: 36\n    tier3: 0\n    tierX: 0\n  last_checked: '2026-05-15T12:00:00.000000+00:00'",
    "originalFile": null,
    "structuredPatch": [
      {
        "oldStart": 713,
        "oldLines": 13,
        "newStart": 713,
        "newLines": 13,
        "lines": [
          " tables: []",
          " figures: []",
          " _completeness:",
          "-  coverage: 35/36",
          "+  coverage: 36/36",
          "   claims: 36",
          "   tables: 0",
          "   figures: 0",
          "   tier_counts:",
          "     tier1: 0",
          "-    tier2: 35",
          "-    tier3: 1",
          "+    tier2: 36",
          "+    tier3: 0",
          "     tierX: 0",
          "-  last_checked: '2026-05-15T02:40:08.884772+00:00'",
          "+  last_checked: '2026-05-15T12:00:00.000000+00:00'"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "448d12b1-010f-49d6-9aed-9dda2912b412",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool result

_source line 47 · 2026-05-15T17:39:38.314Z_

<details><summary>↩ Tool result · `toolu_01JnyXxkSnLgco2FmnrPMDzU`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_provenance.yaml has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fd41f277-379c-4628-abcf-3e1cef9a95bb",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "8da86ec4-9b01-4815-a2bb-3ddde4b85398",
  "toolUseResult": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_provenance.yaml",
    "oldString": "  text: ISR is mathematically sensitive to component count (premise count bias)\n  type: scope_limitation\n  evidence: []\n  decisions:\n  - D051",
    "newString": "  text: ISR is mathematically sensitive to component count (premise count bias)\n  type: scope_limitation\n  evidence:\n  - exp_id: plan002-additive-b01-s42\n    metric: premise_count_isr_confound\n  - exp_id: plan018-additive-random-b01-s42\n    metric: premise_count_matched_isr_ratio_1.06x\n  decisions:\n  - D051",
    "originalFile": null,
    "structuredPatch": [
      {
        "oldStart": 646,
        "oldLines": 7,
        "newStart": 646,
        "newLines": 11,
        "lines": [
          "     sentence: 0",
          "   text: ISR is mathematically sensitive to component count (premise count bias)",
          "   type: scope_limitation",
          "-  evidence: []",
          "+  evidence:",
          "+  - exp_id: plan002-additive-b01-s42",
          "+    metric: premise_count_isr_confound",
          "+  - exp_id: plan018-additive-random-b01-s42",
          "+    metric: premise_count_matched_isr_ratio_1.06x",
          "   decisions:",
          "   - D051",
          "   deprecated: false"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  },
  "sourceToolAssistantUUID": "fd41f277-379c-4628-abcf-3e1cef9a95bb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 48 · 2026-05-15T17:39:40.809Z_

<details open><summary>🔧 Tool call — Edit · `toolu_01VGHHYVN4iWGZNsEyFGV51j`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/paper_provenance.yaml",
  "old_string": "_completeness:\n  coverage: 35/36\n  claims: 36\n  tables: 0\n  figures: 0\n  tier_counts:\n    tier1: 0\n    tier2: 35\n    tier3: 1\n    tierX: 0\n  last_checked: '2026-05-15T02:40:08.884772+00:00'",
  "new_string": "_completeness:\n  coverage: 36/36\n  claims: 36\n  tables: 0\n  figures: 0\n  tier_counts:\n    tier1: 0\n    tier2: 36\n    tier3: 0\n    tierX: 0\n  last_checked: '2026-05-15T12:00:00.000000+00:00'"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8da86ec4-9b01-4815-a2bb-3ddde4b85398",
  "isSidechain": false,
  "requestId": "req_011Cb4mDM6C2QQkMnv27LnK8",
  "type": "assistant",
  "uuid": "448d12b1-010f-49d6-9aed-9dda2912b412",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01X4GyA1zuiQfnY8xaRhytNW",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12640,
      "cache_read_input_tokens": 50465,
      "output_tokens": 1626,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 12640,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 1626,
          "cache_read_input_tokens": 50465,
          "cache_creation_input_tokens": 12640,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 12640
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

_source line 49 · 2026-05-15T17:39:44.205Z_

Provenance fixed: C177 now has evidence from plan002-additive-b01-s42 and plan018-additive-random-b01-s42 (the premise-count confound analysis, D051). Coverage 36/36.

Now writing the stats recalculation checklist.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "053a91b8-d340-46bf-9a5e-e3765f12908b",
  "isSidechain": false,
  "requestId": "req_011Cb4mFg3GvCMAkaNKodLab",
  "type": "assistant",
  "uuid": "9adb9504-f6e0-4e6b-8624-101a2fa29d31",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017a2WfsqU7YfxgjaFuT9xsn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1802,
      "cache_read_input_tokens": 63105,
      "output_tokens": 172,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1802,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 172,
          "cache_read_input_tokens": 63105,
          "cache_creation_input_tokens": 1802,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1802
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

_source line 50 · 2026-05-15T17:39:44.910Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01JsH3QRhsegy2MUsjFHmEbP`</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/artifacts/",
  "description": "List existing artifacts"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9adb9504-f6e0-4e6b-8624-101a2fa29d31",
  "isSidechain": false,
  "requestId": "req_011Cb4mFg3GvCMAkaNKodLab",
  "type": "assistant",
  "uuid": "ce5ded4c-c8b8-426d-b7be-86f30bf43b13",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017a2WfsqU7YfxgjaFuT9xsn",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1802,
      "cache_read_input_tokens": 63105,
      "output_tokens": 172,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 1802,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 172,
          "cache_read_input_tokens": 63105,
          "cache_creation_input_tokens": 1802,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 1802
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

_source line 51 · 2026-05-15T17:39:44.968Z_

<details><summary>↩ Tool result · `toolu_01JsH3QRhsegy2MUsjFHmEbP`</summary>

```text
_deprecated
_project
analysis_random_vs_isr_b01_interim.md
bootstrap_ci_results.json
claim_coverage_audit.md
component_count_analysis.md
data_consistency_report.md
diagnose_phase1_r3.md
dream_reports
evidence_chain_status.md
evidence_tables_d051.md
figure_quality_report.md
genuine_isr_crosscheck.md
grpo_exec_only.yaml
grpo_exec_sta.yaml
hacking_characterization_report.md
hacking_taxonomy.md
hacking_taxonomy_comparison.md
inc05_literature_linkage.md
launch_phase1.sh
literature_goodhart.md
literature_map.yaml
manifest.yaml
paper-audit
paper_compile_audit.md
paper_consistency_audit.md
paper_figures
paper_number_audit.md
paper_number_audit_2026-05-15.json
paper_review_r1.md
paper_table1_evidence.md
paper_tables
paper_tables_draft.md
phase1_r2_diagnosis.md
plan001-exec-only-s43-1000-r2
plan001-exec-only-s43-r4
plan001-exec-only-s44
plan002-additive-b01-s42
plan002-additive-b01-s42-1000
plan002-additive-b01-s43
plan005_negative_literature.md
plan006
plan006_eval_compatibility.md
plan006_readiness.md
plan006_readiness_report.md
plan012
plan013-random-reward-s42-r4
plan013_analysis.md
plan014_design.md
plan016-extended-1000-s42
plan017-additive-random-s42
plan018
plan018-additive-random-b01-s42
plan018-additive-random-b01-s42-1000-r3
plan018-additive-random-b01-s42-1000-r3_analysis.json
preflight_prolog_sta_eval.md
prolog_sta_literature_linkage.md
prolog_sta_premise_count_analysis.md
reference_audit_report.md
reference_final_audit.md
registry_extract.json
review_issues.yaml
review_reports
s43_1000_n_components_investigation.md
section_4_3_1000step_draft.md
seed44_readiness.md
sft_3seed_pooled_ci.json
sta-phase0-baseline
table1_comparison.md
table1_data.json
table1_draft.md
table2_draft.md
table2_hacking_taxonomy.csv
table2_hacking_taxonomy.tex
table_data.json
table_data_compilation.md
table_drafts_v2.md
tables_draft_v1.md
tex_number_audit_20260515.md
train_grpo.py
training_progress_check.md
wilson_ci.py
wilson_ci_complete.csv
wilson_ci_complete.json
wilson_ci_complete.py
wilson_ci_results.csv
wilson_ci_results.json
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ce5ded4c-c8b8-426d-b7be-86f30bf43b13",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "a57083b3-6cb8-4aba-a3e9-fe3987e474d0",
  "toolUseResult": {
    "stdout": "_deprecated\n_project\nanalysis_random_vs_isr_b01_interim.md\nbootstrap_ci_results.json\nclaim_coverage_audit.md\ncomponent_count_analysis.md\ndata_consistency_report.md\ndiagnose_phase1_r3.md\ndream_reports\nevidence_chain_status.md\nevidence_tables_d051.md\nfigure_quality_report.md\ngenuine_isr_crosscheck.md\ngrpo_exec_only.yaml\ngrpo_exec_sta.yaml\nhacking_characterization_report.md\nhacking_taxonomy.md\nhacking_taxonomy_comparison.md\ninc05_literature_linkage.md\nlaunch_phase1.sh\nliterature_goodhart.md\nliterature_map.yaml\nmanifest.yaml\npaper-audit\npaper_compile_audit.md\npaper_consistency_audit.md\npaper_figures\npaper_number_audit.md\npaper_number_audit_2026-05-15.json\npaper_review_r1.md\npaper_table1_evidence.md\npaper_tables\npaper_tables_draft.md\nphase1_r2_diagnosis.md\nplan001-exec-only-s43-1000-r2\nplan001-exec-only-s43-r4\nplan001-exec-only-s44\nplan002-additive-b01-s42\nplan002-additive-b01-s42-1000\nplan002-additive-b01-s43\nplan005_negative_literature.md\nplan006\nplan006_eval_compatibility.md\nplan006_readiness.md\nplan006_readiness_report.md\nplan012\nplan013-random-reward-s42-r4\nplan013_analysis.md\nplan014_design.md\nplan016-extended-1000-s42\nplan017-additive-random-s42\nplan018\nplan018-additive-random-b01-s42\nplan018-additive-random-b01-s42-1000-r3\nplan018-additive-random-b01-s42-1000-r3_analysis.json\npreflight_prolog_sta_eval.md\nprolog_sta_literature_linkage.md\nprolog_sta_premise_count_analysis.md\nreference_audit_report.md\nreference_final_audit.md\nregistry_extract.json\nreview_issues.yaml\nreview_reports\ns43_1000_n_components_investigation.md\nsection_4_3_1000step_draft.md\nseed44_readiness.md\nsft_3seed_pooled_ci.json\nsta-phase0-baseline\ntable1_comparison.md\ntable1_data.json\ntable1_draft.md\ntable2_draft.md\ntable2_hacking_taxonomy.csv\ntable2_hacking_taxonomy.tex\ntable_data.json\ntable_data_compilation.md\ntable_drafts_v2.md\ntables_draft_v1.md\ntex_number_audit_20260515.md\ntrain_grpo.py\ntraining_progress_check.md\nwilson_ci.py\nwilson_ci_complete.csv\nwilson_ci_complete.json\nwilson_ci_complete.py\nwilson_ci_results.csv\nwilson_ci_results.json",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  },
  "sourceToolAssistantUUID": "ce5ded4c-c8b8-426d-b7be-86f30bf43b13",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 52 · 2026-05-15T17:40:29.836Z_

<details open><summary>🔧 Tool call — Write · `toolu_01YJqLnbkicxD3QtCkMfcscF`</summary>

````json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/artifacts/stats_recalc_checklist.md",
  "content": "# Random β=0.1 Pooled Statistics Recalculation Checklist\n\n## Trigger\nRandom s43/s44 旧数据 DEPRECATED（原 checkpoint 丢失无法溯源）。等待重训完成：\n- `plan018-additive-random-b01-s43-r3` — status: RUNNING\n- `plan018-additive-random-b01-s44-r2` — status: ALLOCATED\n\n重训完成后，需对两个新 checkpoint 执行 eval_sta.py（C008: `--data_path data/proofwriter_fol_100.jsonl`），然后用新数据重算以下所有统计量。\n\n## 已有数据（不变）\n\n### Random s42 (plan018-additive-random-b01-s42, D086 clean run)\n- n_proved = 79, n_problems = 100\n- H7 = 0, H1_exact = 56, H1_near = 8, H8 = 3\n- genuine (D084 标准: proved − H7 − H1_exact − H8) = **18** (22.8%)\n  - Note: registry strict genuine=12 扣了 H1-near; D084 标准不扣 H1-near → 79-0-56-3=20; D086 clean run 报告 18. 以 D086 为准。\n- proved_only_ISR = 0.1314\n\n### ISR β=0.1 3-seed (已闭环，不变)\n- s42: n_proved=81, H7=13, H1=42, H8=12, genuine=14 (17.3%)\n- s43: n_proved=61, H7=59, H1=0, genuine≈2 (~3%)\n- s44: n_proved=89, H7=89 (H7a=77+H7b=12, FN corrected), genuine=0 (0%)\n- **ISR pooled**: 231 proved, 16 genuine, genuine_rate = 6.9%\n\n---\n\n## 统计量重算清单\n\n### 1. Random 3-seed Pooled Genuine Rate\n\n**公式**: `genuine_pooled = (g_s42 + g_s43_new + g_s44_new) / (n_s42 + n_s43_new + n_s44_new)`\n\n**输入**:\n| Seed | Source | n_proved | genuine |\n|------|--------|----------|---------|\n| s42 | plan018-additive-random-b01-s42 | 79 | 18 |\n| s43 | plan018-additive-random-b01-s43-r3 eval | ? | ? |\n| s44 | plan018-additive-random-b01-s44-r2 eval | ? | ? |\n\n**Genuine 分类标准 (C013/D084)**: genuine = proved − H7 − H1_exact − H8. H1-near 保留为 genuine 但单独标记。\n\n**旧值 (DEPRECATED)**: 47/256 = 18.4% (含 s43=6, s44=18 推算值)\n\n### 2. Fisher Exact Test: Random vs ISR Genuine Rates\n\n**公式**: 2×2 contingency table, scipy.stats.fisher_exact\n\n```\n              ISR     Random\ngenuine       16      g_random_new\nnon-genuine   215     n_random_new - g_random_new\n```\n\n**两种场景**:\n- A (H8-only, 保守): ISR genuine = 28/231\n- B (H8 + s44 FN, 完整): ISR genuine = 16/231\n\n两种都需重算：`fisher_exact([[isr_g, random_g], [isr_ng, random_ng]])`\n- two-sided p\n- one-sided p (ISR < Random)\n\n**旧值 (DEPRECATED)**: 场景A p=0.060, 场景B p=0.0002\n\n### 3. Wilson CI for Random Genuine Rate\n\n**公式**: Wilson score interval, 95% CI\n\n```python\nfrom statsmodels.stats.proportion import proportion_confint\nci_low, ci_high = proportion_confint(g_random, n_random, alpha=0.05, method='wilson')\n```\n\n**输入**: g_random_new, n_random_new (from item 1)\n\n**旧值 (DEPRECATED)**: 需重算\n\n### 4. H7/H1/H8 Distribution — Random 3-seed 汇总\n\n**需要新 eval 结果中的分类计数**:\n\n| Seed | H7 | H1_exact | H1_near | H8 | Genuine | n_proved |\n|------|----|---------|---------|----|---------|----------|\n| s42 | 0 | 56 | 8 | 3 | 18 | 79 |\n| s43_new | ? | ? | ? | ? | ? | ? |\n| s44_new | ? | ? | ? | ? | ? | ? |\n| **Pooled** | Σ | Σ | Σ | Σ | Σ | Σ |\n\n**验证**: H7 应全部为 0（β=0.1 Random H7=0% 是核心 claim C136/C192）\n\n### 5. Premise-Count-Matched ISR Comparison (更新 1.06x)\n\n**公式**: 在 n_prem ≥ 3 的 genuine 样本中，比较 ISR s42 vs Random s42 的 mean ISR\n\n**当前值**: ISR genuine n_prem≥3: mean_ISR=0.2578 (n=11), Random genuine n_prem≥3: mean_ISR=0.2434 (n=21), ratio=1.06x\n\n**是否需要更新**: 取决于是否 pool 3-seed genuine 做 premise-matched 分析。\n- 如果仅用 s42 单 seed（当前方案）：**不需要更新**，因为 ISR s42 和 Random s42 数据不变\n- 如果扩展到 3-seed pooled：需要新 s43/s44 的 per-sample ISR + n_premise 数据\n\n**建议**: 保持 s42 单 seed 分析（D051 原始方案），新 s43/s44 作为 robustness check\n\n---\n\n## 执行步骤\n\n1. **等待训练完成**: 监控 plan018-additive-random-b01-s43-r3 和 plan018-additive-random-b01-s44-r2\n2. **Eval**: 对每个新 checkpoint 执行:\n   ```bash\n   export CUDA_VISIBLE_DEVICES=N  # C005\n   python eval_sta.py \\\n     --model_path &lt;checkpoint_path> \\\n     --data_path data/proofwriter_fol_100.jsonl \\  # C008\n     --output_dir /root/autodl-tmp/outputs/&lt;exp_id>/\n   ```\n3. **Taxonomy 分类**: 对 eval 输出执行 H7/H1/H8 分类（确保 C013 对称标准）\n4. **计算统计量**: 用上述公式重算 items 1-5\n5. **更新 paper_framing.md**: 替换所有 DEPRECATED/PROVISIONAL 标记的数字\n6. **更新 provenance**: 确保新 exp_id 注册到相关 claims\n7. **更新论文 LaTeX**: 更新 Table 1、Abstract、§4.2 中的 Random pooled 数字\n\n## 依赖关系\n```\ns43-r3 完成 ──┐\n              ├─→ eval s43 ──┐\ns44-r2 完成 ──┤              ├─→ 统计量重算 → 更新 framing/paper\n              └─→ eval s44 ──┘\n```\n"
}
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a57083b3-6cb8-4aba-a3e9-fe3987e474d0",
  "isSidechain": false,
  "requestId": "req_011Cb4mFymP6KDpiRnj7y1a7",
  "type": "assistant",
  "uuid": "5c347b7e-0df1-4af2-9c96-c467483cf5d9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UE7TfvuhASvVWvH6CAKbBU",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 961,
      "cache_read_input_tokens": 64907,
      "output_tokens": 2189,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 961,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2189,
          "cache_read_input_tokens": 64907,
          "cache_creation_input_tokens": 961,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 961
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

_source line 53 · 2026-05-15T17:40:29.869Z_

<details><summary>↩ Tool result · `toolu_01YJqLnbkicxD3QtCkMfcscF`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/artifacts/stats_recalc_checklist.md
```

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "parentUuid": "5c347b7e-0df1-4af2-9c96-c467483cf5d9",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "3eaff7a7-873d-4d7f-abec-0cca989fcbd4",
  "toolUseResult": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/artifacts/stats_recalc_checklist.md",
    "content": "# Random β=0.1 Pooled Statistics Recalculation Checklist\n\n## Trigger\nRandom s43/s44 旧数据 DEPRECATED（原 checkpoint 丢失无法溯源）。等待重训完成：\n- `plan018-additive-random-b01-s43-r3` — status: RUNNING\n- `plan018-additive-random-b01-s44-r2` — status: ALLOCATED\n\n重训完成后，需对两个新 checkpoint 执行 eval_sta.py（C008: `--data_path data/proofwriter_fol_100.jsonl`），然后用新数据重算以下所有统计量。\n\n## 已有数据（不变）\n\n### Random s42 (plan018-additive-random-b01-s42, D086 clean run)\n- n_proved = 79, n_problems = 100\n- H7 = 0, H1_exact = 56, H1_near = 8, H8 = 3\n- genuine (D084 标准: proved − H7 − H1_exact − H8) = **18** (22.8%)\n  - Note: registry strict genuine=12 扣了 H1-near; D084 标准不扣 H1-near → 79-0-56-3=20; D086 clean run 报告 18. 以 D086 为准。\n- proved_only_ISR = 0.1314\n\n### ISR β=0.1 3-seed (已闭环，不变)\n- s42: n_proved=81, H7=13, H1=42, H8=12, genuine=14 (17.3%)\n- s43: n_proved=61, H7=59, H1=0, genuine≈2 (~3%)\n- s44: n_proved=89, H7=89 (H7a=77+H7b=12, FN corrected), genuine=0 (0%)\n- **ISR pooled**: 231 proved, 16 genuine, genuine_rate = 6.9%\n\n---\n\n## 统计量重算清单\n\n### 1. Random 3-seed Pooled Genuine Rate\n\n**公式**: `genuine_pooled = (g_s42 + g_s43_new + g_s44_new) / (n_s42 + n_s43_new + n_s44_new)`\n\n**输入**:\n| Seed | Source | n_proved | genuine |\n|------|--------|----------|---------|\n| s42 | plan018-additive-random-b01-s42 | 79 | 18 |\n| s43 | plan018-additive-random-b01-s43-r3 eval | ? | ? |\n| s44 | plan018-additive-random-b01-s44-r2 eval | ? | ? |\n\n**Genuine 分类标准 (C013/D084)**: genuine = proved − H7 − H1_exact − H8. H1-near 保留为 genuine 但单独标记。\n\n**旧值 (DEPRECATED)**: 47/256 = 18.4% (含 s43=6, s44=18 推算值)\n\n### 2. Fisher Exact Test: Random vs ISR Genuine Rates\n\n**公式**: 2×2 contingency table, scipy.stats.fisher_exact\n\n```\n              ISR     Random\ngenuine       16      g_random_new\nnon-genuine   215     n_random_new - g_random_new\n```\n\n**两种场景**:\n- A (H8-only, 保守): ISR genuine = 28/231\n- B (H8 + s44 FN, 完整): ISR genuine = 16/231\n\n两种都需重算：`fisher_exact([[isr_g, random_g], [isr_ng, random_ng]])`\n- two-sided p\n- one-sided p (ISR < Random)\n\n**旧值 (DEPRECATED)**: 场景A p=0.060, 场景B p=0.0002\n\n### 3. Wilson CI for Random Genuine Rate\n\n**公式**: Wilson score interval, 95% CI\n\n```python\nfrom statsmodels.stats.proportion import proportion_confint\nci_low, ci_high = proportion_confint(g_random, n_random, alpha=0.05, method='wilson')\n```\n\n**输入**: g_random_new, n_random_new (from item 1)\n\n**旧值 (DEPRECATED)**: 需重算\n\n### 4. H7/H1/H8 Distribution — Random 3-seed 汇总\n\n**需要新 eval 结果中的分类计数**:\n\n| Seed | H7 | H1_exact | H1_near | H8 | Genuine | n_proved |\n|------|----|---------|---------|----|---------|----------|\n| s42 | 0 | 56 | 8 | 3 | 18 | 79 |\n| s43_new | ? | ? | ? | ? | ? | ? |\n| s44_new | ? | ? | ? | ? | ? | ? |\n| **Pooled** | Σ | Σ | Σ | Σ | Σ | Σ |\n\n**验证**: H7 应全部为 0（β=0.1 Random H7=0% 是核心 claim C136/C192）\n\n### 5. Premise-Count-Matched ISR Comparison (更新 1.06x)\n\n**公式**: 在 n_prem ≥ 3 的 genuine 样本中，比较 ISR s42 vs Random s42 的 mean ISR\n\n**当前值**: ISR genuine n_prem≥3: mean_ISR=0.2578 (n=11), Random genuine n_prem≥3: mean_ISR=0.2434 (n=21), ratio=1.06x\n\n**是否需要更新**: 取决于是否 pool 3-seed genuine 做 premise-matched 分析。\n- 如果仅用 s42 单 seed（当前方案）：**不需要更新**，因为 ISR s42 和 Random s42 数据不变\n- 如果扩展到 3-seed pooled：需要新 s43/s44 的 per-sample ISR + n_premise 数据\n\n**建议**: 保持 s42 单 seed 分析（D051 原始方案），新 s43/s44 作为 robustness check\n\n---\n\n## 执行步骤\n\n1. **等待训练完成**: 监控 plan018-additive-random-b01-s43-r3 和 plan018-additive-random-b01-s44-r2\n2. **Eval**: 对每个新 checkpoint 执行:\n   ```bash\n   export CUDA_VISIBLE_DEVICES=N  # C005\n   python eval_sta.py \\\n     --model_path &lt;checkpoint_path> \\\n     --data_path data/proofwriter_fol_100.jsonl \\  # C008\n     --output_dir /root/autodl-tmp/outputs/&lt;exp_id>/\n   ```\n3. **Taxonomy 分类**: 对 eval 输出执行 H7/H1/H8 分类（确保 C013 对称标准）\n4. **计算统计量**: 用上述公式重算 items 1-5\n5. **更新 paper_framing.md**: 替换所有 DEPRECATED/PROVISIONAL 标记的数字\n6. **更新 provenance**: 确保新 exp_id 注册到相关 claims\n7. **更新论文 LaTeX**: 更新 Table 1、Abstract、§4.2 中的 Random pooled 数字\n\n## 依赖关系\n```\ns43-r3 完成 ──┐\n              ├─→ eval s43 ──┐\ns44-r2 完成 ──┤              ├─→ 统计量重算 → 更新 framing/paper\n              └─→ eval s44 ──┘\n```\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  },
  "sourceToolAssistantUUID": "5c347b7e-0df1-4af2-9c96-c467483cf5d9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
````

</details>

---

### Runtime record

_source line 54_

```json
{
  "type": "last-prompt",
  "leafUuid": "3eaff7a7-873d-4d7f-abec-0cca989fcbd4",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10"
}
```

---

### Runtime record

_source line 55_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix provenance gaps and prepare statistics recalc checklist",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10"
}
```

---

### Tool call

_source line 56 · 2026-05-15T17:40:35.257Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact · `toolu_01UFvT23PLaum8sETfrMPmrg`</summary>

```json
{
  "name": "stats_recalc_checklist",
  "type": "intermediate",
  "description": "Random β=0.1 pooled statistics recalculation checklist — formulas, input sources, and execution steps for when s43-r3/s44-r2 retraining completes",
  "project": "solver-trace-ablation",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/artifacts/stats_recalc_checklist.md",
  "tags": [
    "statistics",
    "random-control",
    "recalculation",
    "D084"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3eaff7a7-873d-4d7f-abec-0cca989fcbd4",
  "isSidechain": false,
  "requestId": "req_011Cb4mKHd155X8EQ2WZHn77",
  "type": "assistant",
  "uuid": "141e6d3f-cfa2-436f-b961-06c3bcb1b447",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Khns89oc8cEfwWu2R9fN5n",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2247,
      "cache_read_input_tokens": 65868,
      "output_tokens": 262,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 2247,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 262,
          "cache_read_input_tokens": 65868,
          "cache_creation_input_tokens": 2247,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 2247
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

_source line 57 · 2026-05-15T17:40:35.493Z_

<details><summary>↩ Tool result · `toolu_01UFvT23PLaum8sETfrMPmrg`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260515_2e14c3\", \"name\": \"stats_recalc_checklist\", \"type\": \"intermediate\", \"description\": \"Random β=0.1 pooled statistics recalculation checklist — formulas, input sources, and execution steps for when s43-r3/s44-r2 retraining completes\", \"path\": \"projects/solver-trace-ablation/artifacts/_project/intermediate/stats_recalc_checklist.md\", \"url\": null, \"project\": \"solver-trace-ablation\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-15T17:40:35.266069+00:00\", \"tags\": [\"statistics\", \"random-control\", \"recalculation\", \"D084\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "141e6d3f-cfa2-436f-b961-06c3bcb1b447",
  "isSidechain": false,
  "promptId": "d4eb5ede-d6d4-48e4-a6be-a95a8056eda0",
  "type": "user",
  "uuid": "0af5b80c-6132-42c7-b7f7-3b75c420dfa5",
  "toolUseResult": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"artifact\\\": {\\\"id\\\": \\\"art_20260515_2e14c3\\\", \\\"name\\\": \\\"stats_recalc_checklist\\\", \\\"type\\\": \\\"intermediate\\\", \\\"description\\\": \\\"Random β=0.1 pooled statistics recalculation checklist — formulas, input sources, and execution steps for when s43-r3/s44-r2 retraining completes\\\", \\\"path\\\": \\\"projects/solver-trace-ablation/artifacts/_project/intermediate/stats_recalc_checklist.md\\\", \\\"url\\\": null, \\\"project\\\": \\\"solver-trace-ablation\\\", \\\"exp_id\\\": null, \\\"skill\\\": \\\"\\\", \\\"created_at\\\": \\\"2026-05-15T17:40:35.266069+00:00\\\", \\\"tags\\\": [\\\"statistics\\\", \\\"random-control\\\", \\\"recalculation\\\", \\\"D084\\\"]}, \\\"manifest\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/artifacts/manifest.yaml\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
  "mcpMeta": {
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260515_2e14c3\", \"name\": \"stats_recalc_checklist\", \"type\": \"intermediate\", \"description\": \"Random β=0.1 pooled statistics recalculation checklist — formulas, input sources, and execution steps for when s43-r3/s44-r2 retraining completes\", \"path\": \"projects/solver-trace-ablation/artifacts/_project/intermediate/stats_recalc_checklist.md\", \"url\": null, \"project\": \"solver-trace-ablation\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-15T17:40:35.266069+00:00\", \"tags\": [\"statistics\", \"random-control\", \"recalculation\", \"D084\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"
    }
  },
  "sourceToolAssistantUUID": "141e6d3f-cfa2-436f-b961-06c3bcb1b447",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 58 · 2026-05-15T17:40:35.497Z_

```json
{
  "parentUuid": "0af5b80c-6132-42c7-b7f7-3b75c420dfa5",
  "isSidechain": false,
  "attachment": {
    "type": "todo_reminder",
    "content": [],
    "itemCount": 0
  },
  "type": "attachment",
  "uuid": "450e31fb-1b5c-4330-95cb-22fc2cb54739",
  "timestamp": "2026-05-15T17:40:35.497Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 59 · 2026-05-15T17:40:42.373Z_

两个任务完成。

**任务 1**: Provenance 补全 36/36。缺失项是 **C177**（"ISR is mathematically sensitive to component count (premise count bias)"），`evidence: []` → 添加了 plan002-additive-b01-s42 和 plan018-additive-random-b01-s42 作为证据（D051 premise-count confound 分析的底层数据来源）。

**任务 2**: 统计量重算 checklist 已写入 `artifacts/stats_recalc_checklist.md` 并注册（art_20260515_2e14c3）。覆盖 5 项统计量：pooled genuine rate、Fisher exact test (两种场景)、Wilson CI、H7/H1/H8 分布汇总、premise-count-matched 1.06x 是否需更新。依赖 s43-r3（RUNNING）和 s44-r2（ALLOCATED）完成后的 eval 数据。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "450e31fb-1b5c-4330-95cb-22fc2cb54739",
  "isSidechain": false,
  "requestId": "req_011Cb4mKhcPrDTkey7nxpU8g",
  "type": "assistant",
  "uuid": "4cceab0f-165e-450f-97b9-3f3cea140bc9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_3/projects/solver-trace-ablation",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018BVLuqdzj7YxkTFntwwg5S",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 666,
      "cache_read_input_tokens": 68115,
      "output_tokens": 268,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 666,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 268,
          "cache_read_input_tokens": 68115,
          "cache_creation_input_tokens": 666,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 0,
            "ephemeral_1h_input_tokens": 666
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

_source line 60_

```json
{
  "type": "last-prompt",
  "leafUuid": "4cceab0f-165e-450f-97b9-3f3cea140bc9",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10"
}
```

---

### Runtime record

_source line 61_

```json
{
  "type": "ai-title",
  "aiTitle": "Fix provenance gaps and prepare statistics recalc checklist",
  "sessionId": "d09c16fe-783f-4107-8777-2fc80b263d10"
}
```

---
