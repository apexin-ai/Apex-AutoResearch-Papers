# ssh registry cleanup prep

**Instruction Routing in Fine-Tuned Vision-Language-Action Models: A Cross-Architecture Analysis** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 7
- **Recorded user turns:** 0
- **Tool calls:** 3
- **Original source:** `logs/chats/worker_ssh_registry-cleanup-prep_20260515T171117.jsonl`
- **Structured JSON:** [`88f14b07ae1123f4ad7f.json`](../../sessions/88/88f14b07ae1123f4ad7f.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

7 recorded events

### Tool call

_source line 1 · 2026-05-15T17:11:48.716012+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file",
  "max_results": "1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_ssh_registry-cleanup-prep_20260515T171117",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__read_project_file",
    "max_results": "1"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-15T17:11:48.716486+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_ssh_registry-cleanup-prep_20260515T171117",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-15T17:11:48.716751+00:00_

called mcp__agent-ml-research__read_project_file

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file</summary>

```json
{
  "project": "vla-ssd",
  "file": "report.md",
  "max_chars": "0"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_ssh_registry-cleanup-prep_20260515T171117",
  "tool": "mcp__agent-ml-research__read_project_file",
  "tool_args": {
    "project": "vla-ssd",
    "file": "report.md",
    "max_chars": "0"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-15T17:11:48.717024+00:00_

{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_15/projects/vla-ssd/report.md\", \"content\": \"# Handover — 2026-05-15\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\n|--------|------|------|---------|-----|\\n| lg_extract_untrained | — | — | — | — |\\n| lg_extract_trained | — | — | — | — |\\n| lg_extract_untrained_r2 | — | — | — | — |\\n\\n## 待处理\\n- mvp2_action_probe: VLA trained model hidden states encode action prediction knowledge (next action a_{t+1}) that untrained VLA and DINO-V2 lack. Gates: G1 R²>0.3, G2 Δ(trained-untrained)>0.15, G3 Δ(trained-DINO)>0.15（准备中）\\n\\n## 近期结论\\n- **mvp2_delta_dino** (success): DINO-V2 action-delta baseline (single layer) — establishes vision-only floor for G3 action-delta comparison ← 基于 mvp2_action_probe\\n- **mvp2_delta_untrained** (success): Action-delta prediction (Δa = a_{t+1}-a_t) on untrained VLA. Baseline for G2-delta comparison — expected lower R² than trained ← 基于 mvp2_action_probe\\n- **mvp2_delta_trained** (success): Action-delta prediction (Δa = a_{t+1}-a_t) removes autocorrelation. 33-layer sweep on trained VLA. Gate G1-delta: peak R²>0.05, G2-delta: Δ(trained-untrained)>0.03 in ≥5/10 tasks ← 基于 mvp2_action_probe\\n\\n## 趋势\\n成功 12 / 负向 2 / 失败 0 / 共 14\\noverall_R2: 0.0604 ↑（近 3 次 success）\\nper_task_mean_R2: 0.0609 ↑（近 3 次 success）\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nwestd-19183: 无 GPU 信息\\n\\n## 告警\\n（无）\\n\", \"total_chars\": 1287, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_ssh_registry-cleanup-prep_20260515T171117",
  "tool": "mcp__agent-ml-research__read_project_file",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-15T17:11:48.717282+00:00_

called mcp__agent-ml-research__read_project_file

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file</summary>

```json
{
  "project": "vla-ssd",
  "file": "ROADMAP.md",
  "max_chars": "0"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_ssh_registry-cleanup-prep_20260515T171117",
  "tool": "mcp__agent-ml-research__read_project_file",
  "tool_args": {
    "project": "vla-ssd",
    "file": "ROADMAP.md",
    "max_chars": "0"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-15T17:11:48.717559+00:00_

{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_15/projects/vla-ssd/ROADMAP.md\", \"content\": \"# vla-ssd — Research Dashboard\\n\\n> 最后更新: 2026-05-15 16:07 UTC | 更新原因: D015: 选择 Option A (LIBERO-Goal pivot)，Reviewer+Director 一致，用户授权\\n\\n## 核心方向\\n\\nVLA 训练的表征贡献取决于 task structure：vision-sufficient 场景（LIBERO-10）中 vision encoder 主导，vision-ambiguous 场景（LIBERO-Goal）中 VLA 的 language grounding 才有机会体现。\\n\\n**论文 story（候选）**: LIBERO-10 negative + LIBERO-Goal positive 构成对比叙事 + layer-wise mechanistic depth（WHERE/HOW）。\\n\\n## 当前进展\\n\\n- **阶段**: MVP-2 完成 → Pivot to LIBERO-Goal（D015）\\n- **MVP-1 Temporal Distance**: G2 FAIL (Δρ=0.043), vision-dominated\\n- **MVP-2 Action Prediction**: G2 FAIL (ΔR²=0.067), G3 FAIL (Δ=0.007 vs DINO)\\n- **MVP-2 Action-Delta**: G3-delta FAIL (DINO 0.061 ≈ trained 0.059)\\n- **跨 MVP 一致发现**: layer stability（trained 31/33 层有效 vs untrained ~15/33）\\n- **方向决策**: Option A（Reviewer + Director 一致推荐，用户授权）\\n\\n## 近期任务\\n\\n- [ ] 确认 LIBERO-Goal 数据可获取 + 与 LIBERO-10 scene overlap\\n- [ ] 确认 OpenVLA checkpoint 在 LIBERO-Goal 上的 zero-shot 能力\\n- [ ] 如 zero-shot 差 → 预留 1 天 LIBERO-Goal fine-tune\\n- [ ] 特征提取：trained VLA + untrained VLA + DINO（双卡并行）\\n- [ ] Instruction-conditioned probing：same-scene/different-goal 设置\\n- [ ] DINO baseline sanity check（DINO 在 shared-scene goals 上 R² 是否下降）\\n- [ ] 分析 + 可视化 + 论文初稿\\n\\n## 时间线（CoRL 2026）\\n\\n| 里程碑 | 日期 | 剩余天数 |\\n|--------|------|---------|\\n| Abstract DDL | May 26 | 11 |\\n| Paper DDL | May 29 | 14 |\\n| 数据+pipeline 适配 | May 16 | - |\\n| 特征提取 | May 16-17 | - |\\n| Probing 实验 | May 17 | - |\\n| 分析+可视化 | May 17-18 | - |\\n| 论文初稿 | May 18-21 | - |\\n| Review+polish | May 21-25 | - |\\n\\n## GPU 预算\\n\\nwestd-19183: 2×RTX PRO 6000 | 当前 0/2 占用\\n\\n## 关键风险\\n\\n1. **[高] OpenVLA 未训练过 LIBERO-Goal** — 先检查 scene overlap，必要时 fine-tune\\n2. **[中] 视觉仍有微妙差异** — DINO per-goal R² sanity check\\n3. **[低] Pipeline 适配 bug** — 数据格式/key naming 兼容性\\n\\n## 关键决策日志\\n\\n| ID | 日期 | 摘要 
…[truncated 1587 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_ssh_registry-cleanup-prep_20260515T171117",
  "tool": "mcp__agent-ml-research__read_project_file",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 7 · 2026-05-15T17:11:48.717916+00:00_

## Report.md (Handover 2026-05-15)

**运行中**: `lg_extract_untrained`, `lg_extract_trained`, `lg_extract_untrained_r2` — 均无状态/指标信息

**待处理**: `mvp2_action_probe` — VLA trained model hidden states encode action prediction knowledge

**近期结论**: MVP-2 action-delta 系列三个实验均 success，但 gate 判定整体 FAIL（DINO ≈ trained VLA）

**趋势**: 成功 12 / 负向 2 / 失败 0 / 共 14 次实验。overall_R² = 0.0604 ↑

**下一步**: 无活跃 idea，需通过 ideas.md 添加

---

## ROADMAP.md 摘要

**核心结论**: LIBERO-10 上 VLA 训练表征贡献不显著（vision encoder 主导），项目已 pivot 到 **LIBERO-Goal**（D015 决策），期望在 vision-ambiguous 场景中，VLA 的 language grounding 能体现差异。

**当前阶段**: MVP-2 完成 → Pivot to LIBERO-Goal
- MVP-1 Temporal Distance: G2 FAIL
- MVP-2 Action Prediction: G2/G3 FAIL
- MVP-2 Action-Delta: G3-delta FAIL（DINO ≈ trained）
- 跨 MVP 一致发现: layer stability（trained 31/33 层有效 vs untrained ~15/33）

**近期任务（LIBERO-Goal pivot）**:
1. 确认 LIBERO-Goal 数据可获取 + scene overlap
2. 确认 OpenVLA checkpoint zero-shot 能力
3. 特征提取（trained + untrained + DINO，双卡并行）
4. Instruction-conditioned probing（same-scene/different-goal）
5. 分析 + 可视化 + 论文初稿

**时间线**: CoRL 2026 — Abstract DDL **May 26**（剩 11 天），Paper DDL **May 29**（剩 14 天）

**关键风险**: OpenVLA 未训练过 LIBERO-Goal，需检查 scene overlap，必要时 fine-tune

**GPU**: westd-19183, 2×RTX PRO 6000, 当前 0/2 占用

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_ssh_registry-cleanup-prep_20260515T171117"
}
```

</details>

---
