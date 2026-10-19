# paper round3 discussion

**Sign Misattribution in Step-Independent Agent RL: Dual Mechanism Diagnosis and Episode-Level Correction** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 9
- **Recorded user turns:** 0
- **Tool calls:** 4
- **Original source:** `logs/chats/worker_paper_round3_discussion_20260523T164753.jsonl`
- **Structured JSON:** [`6cb34b8e16cee012cb6c.json`](../../sessions/6c/6cb34b8e16cee012cb6c.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

9 recorded events

### Tool call

_source line 1 · 2026-05-23T16:48:44.037533+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_round3_discussion_20260523T164753",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-23T16:48:44.038141+00:00_

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
74	- **
…[truncated 5709 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_round3_discussion_20260523T164753",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-23T16:48:44.038340+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_round3_discussion_20260523T164753",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/discussion.tex"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-23T16:48:44.038493+00:00_

1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{Generality and mechanism interaction.}
5	Sign misattribution arises whenever three structural properties co-occur: (a) step-level windowing, (b) sparse binary reward, and (c) group-relative normalization. Under these conditions, the advantage sign collapses to a proxy for episode outcome, and severity scales with task difficulty ($P(\text{correct} \mid \text{update}) \to p$). M1 and M2 interact in a vicious cycle: M1 lowers $p$, increasing wrong-sign updates under M2, which further degrades $p$. The A$\to$B comparison provides direct evidence: identical observation scope ($h{=}2$), yet eliminating step-level advantage converts catastrophic collapse into bounded learning. Six factors explaining why step-independent became the default are detailed in Appendix~\ref{app:why_defaults}.
6	
7	\paragraph{Seed-dependent OOD generalization.}
8	The multi-seed evaluation reveals a bimodal distribution: a stagnant cluster with OOD performance indistinguishable from SFT and a generalized cluster with significant improvement. Training duration does not explain the gap, pointing to initialization sensitivity as the likely driver.
9	
10	\paragraph{Practitioner guidance.}
11	Use episode-level credit when the full episode fits in context; otherwise use the largest feasible $h$ ($h{\geq}20$; $h{\leq}10$ collapses). Finer-grained methods should be applied only after establishing an episode-level baseline.
12	
13	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_round3_discussion_20260523T164753",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-23T16:48:44.038733+00:00_

called Edit

<details open><summary>🔧 Tool call — Edit</summary>

```json
{
  "replace_all": "False",
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/discussion.tex",
  "old_string": "\\paragraph{Seed-dependent OOD generalization.}",
  "new_string": "\\paragraph{Non-additive mechanism interaction.}\nCell~C (full trajectory with step-level advantage, isolating M2) produces NaN training instability rather than the gradual collapse observed in Cell~A. This qualitative difference suggests that windowing (M1) may have an unintended stabilizing effect: restricting gradient computation to short sequences limits gradient variance. Removing M1 while retaining M2 may release unstable gradient signals that full-trajectory optimization amplifies. If confirmed, this interaction would limit the applicability of the additive separation assumed by the factorial design, as the two mechanisms may interact non-linearly with M1 partially masking M2's destabilizing potential. We leave systematic investigation to future work.\n\n\\paragraph{Seed-dependent OOD generalization.}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_round3_discussion_20260523T164753",
  "tool": "Edit",
  "tool_args": {
    "replace_all": "False",
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/discussion.tex",
    "old_string": "\\paragraph{Seed-dependent OOD generalization.}",
    "new_string": "\\paragraph{Non-additive mechanism interaction.}\nCell~C (full trajectory with step-level advantage, isolating M2) produces NaN training instability rather than the gradual collapse observed in Cell~A. This qualitative difference suggests that windowing (M1) may have an unintended stabilizing effect: restricting gradient computation to short sequences limits gradient variance. Removing M1 while retaining M2 may release unstable gradient signals that full-trajectory optimization amplifies. If confirmed, this interaction would limit the applicability of the additive separation assumed by the factorial design, as the two mechanisms may interact non-linearly with M1 partially masking M2's destabilizing potential. We leave systematic investigation to future work.\n\n\\paragraph{Seed-dependent OOD generalization.}"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-23T16:48:44.038904+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/discussion.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_round3_discussion_20260523T164753",
  "tool": "Edit",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-23T16:48:44.039030+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_round3_discussion_20260523T164753",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/discussion.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-23T16:48:44.039170+00:00_

1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{Generality and mechanism interaction.}
5	Sign misattribution arises whenever three structural properties co-occur: (a) step-level windowing, (b) sparse binary reward, and (c) group-relative normalization. Under these conditions, the advantage sign collapses to a proxy for episode outcome, and severity scales with task difficulty ($P(\text{correct} \mid \text{update}) \to p$). M1 and M2 interact in a vicious cycle: M1 lowers $p$, increasing wrong-sign updates under M2, which further degrades $p$. The A$\to$B comparison provides direct evidence: identical observation scope ($h{=}2$), yet eliminating step-level advantage converts catastrophic collapse into bounded learning. Six factors explaining why step-independent became the default are detailed in Appendix~\ref{app:why_defaults}.
6	
7	\paragraph{Non-additive mechanism interaction.}
8	Cell~C (full trajectory with step-level advantage, isolating M2) produces NaN training instability rather than the gradual collapse observed in Cell~A. This qualitative difference suggests that windowing (M1) may have an unintended stabilizing effect: restricting gradient computation to short sequences limits gradient variance. Removing M1 while retaining M2 may release unstable gradient signals that full-trajectory optimization amplifies. If confirmed, this interaction would limit the applicability of the additive separation assumed by the factorial design, as the two mechanisms may interact non-linearly with M1 partially masking M2's destabilizing potential. We leave systematic investigation to future work.
9	
10	\paragraph{Seed-dependent OOD generalization.}
11	The multi-seed evaluation reveals a bimodal distribution: a stagnant cluster with OOD performance indistinguishable from SFT and a generalized cluster with significant improvement. Training duration does not explain the gap, pointing to initialization sensitivity as the likely driver.
12	
13	\paragraph{Practition
…[truncated 256 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_round3_discussion_20260523T164753",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 9 · 2026-05-23T16:48:44.039372+00:00_

新段落已添加在 "Generality and mechanism interaction" 之后、"Seed-dependent OOD generalization" 之前。5 句话，约 0.1 页，使用 hedging 措辞（suggests, may, if confirmed），与上方段落无内容重复。预估主文本约 7.7 页，仍在 8 页限制内。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_paper_round3_discussion_20260523T164753"
}
```

</details>

---
