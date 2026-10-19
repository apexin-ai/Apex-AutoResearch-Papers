# paper writing introduction

**Sign Misattribution in Step-Independent Agent RL: Dual Mechanism Diagnosis and Episode-Level Correction** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 30
- **Recorded user turns:** 0
- **Tool calls:** 8
- **Original source:** `logs/workers/worker_paper_writing_introduction_20260517T075037.log`
- **Structured JSON:** [`cfd614564b7133a21ff8.json`](../../sessions/cf/cfd614564b7133a21ff8.json)

## Before a recorded user message

30 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl",
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
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
    "mcp__agent-ml-research__auto_build_provenance",
    "mcp__agent-ml-research__bootstrap_provenance",
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
  "uuid": "fbc55412-708d-4589-ac45-c9c75fe76ca0",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-6/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-1-projects-cost-verify-agent-rl/memory/"
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
    "resetsAt": 1779012000,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "3e18d399-b421-487f-bf81-69d081c6a30a",
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d"
}
```

---

### Assistant

_source line 4_

I'll start by reading the required reference materials and existing paper sections in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "d9503756-2c13-43cf-bd9e-66273723c7a1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JYM7XLq8HUMTsAuqGqsh8i",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14941,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14941
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

<details open><summary>🔧 Tool call — Read · `toolu_01HiD84LfkhKRzyAxtGHP65K`</summary>

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
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "84d96ec8-8169-4250-97c0-008c3b5ee4a9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JYM7XLq8HUMTsAuqGqsh8i",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14941,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14941
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

_source line 6 · 2026-05-17T07:51:10.391Z_

<details><summary>↩ Tool result · `toolu_01HiD84LfkhKRzyAxtGHP65K`</summary>

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
213	---
214	
215	## 七、投稿前通用准备
216	
217	### 7.1 模板必须官方（硬规则）
218	
219	- LaTeX 模板**必须从目标会议官网下载**（CallForPapers / Author Instructions 页面）
220	- **不要用**：
221	  - 网上他人转载的复制版本（可能被改过 margin / 行号设置）
222	  - 上一年的模板（参数可能变：字体、margin、行号、anonymous 选项等）
223	  - 组里学长留的旧版本（来源不明、无法追溯）
224	- 风险：
225	  - 样式不符合 → desk reject
226	  - margin 不对 → 被审稿人质疑诚信
227	  - reference 格式错 → 被认为不规范
228	- 流程：先查会议官网 templates → 找不到再 `WebSearch "{venue} {year} latex template official"` → 仍找不到汇报 Director（不要用就近年版本顶替）
229	- `\documentclass[]{}` 选项必须与目标 venue + 阶段（review / camera-ready）一致
230	
231	### 7.2 投稿要求逐项核对
232	
233	- 目标会议如要求 Checklist / Ethical Statement / Broader Impact Statement / Reproducibility Statement，必须**认真填每一项**，不要全写 N/A
234	- 页数限制：查目标会议官网
235	- 匿名化要求：review 版 vs camera-ready 版本设置不同
236	- 行号开启（review 版常需）
237	- 字体大小、margin 不得修改 sty 文件
238	
239	### 7.3 最终修改 10 项检查流程
240	
241	提交前必须逐一检查：
242	1. 所有最新实验结果已全部录入
243	2. 根据实验结果将叙事调至最优状态
244	3. 附录所有内容在正文中被引用且融入叙事
245	4. 无数据堆砌（每个数字服务于叙事推进）
246	5. Abstract 和 Introduction 具有吸引力（不是实验报告风格）
247	6. 全文主线统一（idea 变化后各章节逻辑一致）
248	7. 所有专有名词有定义
249	8. 无 AI 风格标志（dash、-ing phrases、过度分段）
250	9. 图表知识密度高、无视觉遮挡
251	10. Reference 覆盖直接相关方法、baseline、benchmark、理论基础
252	
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "6a7ceebe-088d-4507-98f7-7dfc1d66ad9f",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md",
      "content": "---\nname: paper-writing-norms\ndescription: 顶会级别论文写作风格规范——章节写法（Abstract/Intro/Related Work）、去 AI 风格、视觉密度、叙事哲学。Paper Agent 和 Worker 写论文章节时必须加载。\nallowed-tools: [Read, Write, Edit, Glob, Grep]\nscope: global\nversion: 2\npriority: 9\ntags:\n  - writing\n  - paper\n  - style\n  - norms\nroles:\n  - agent\n  - worker\n  - paper_agent\n---\n\n# 论文写作风格规范\n\n> 核心哲学：**论文是一个有说服力的故事，不是实验报告。** 审稿人在几十秒内判断论文价值——如果 Abstract 和 Introduction 读起来像实验日志，论文就已经失败了。\n\n---\n\n## 一、总体写作哲学\n\n### 1.1 故事驱动，不是数据堆砌\n\n- 论文必须以\"故事线\"为核心展开：问题 → 洞察 → 方法 → 验证\n- 禁止大量实验数据堆砌——每个数字出现必须服务于叙事推进\n- 附录内容必须在正文中有明确引用且融入叙事，禁止简单堆砌\n- 如果附录数据对核心叙事有重大影响，根据附录数据调整论文 framing\n\n### 1.2 主线统一性\n\n- 当 idea 在研究过程中发生变化后，**必须重审全文逻辑**\n- 常见问题：Introduction 讲的故事 A，Method 做的是故事 B，Results 又在讲故事 C\n- 修复方式：从最终实验结论反推，重写 Introduction 的问题定义和动机\n- 每次 idea 调整后检查：Abstract → Introduction → Method → Results → Discussion → Conclusion 是否形成一条连贯主线\n\n### 1.3 专有名词必须有定义\n\n- 首次出现的专有名词/缩写必须给出完整定义和解释\n- Abstract 中使用的缩写也必须在 Abstract 内定义（如 LLM = Large Language Model）\n- 不能假设读者知道你自己定义的术语——论文从来没解释过的概念不能直接使用\n- 通用规则：如果一个非标准术语第一次出现时没有括号定义，就是写作 bug\n\n### 1.4 写作前必读同类优秀论文\n\n- 每个章节动笔前，找 **2-3 篇目标会议近 1-2 年的高分论文**作为风格参考——同类问题或同类方法皆可\n- 重点学：\n  - Abstract 怎么用最少篇幅讲完故事\n  - Introduction 怎么从大问题切入到具体贡献\n  - Related Work 怎么 positioning 自己（不是 survey）\n  - Table/Figure 怎么压缩信息密度\n- **不是抄袭**，是学习同行的故事节奏和审美——不同子领域叙事节奏差异很大\n- 实操：Paper Agent 可以从 `literature_map.yaml` 中挑 `role=foundation` 或 `role=direct-competitor` 的论文，把 `{title, venue, year, abstract}` 附在 Worker 的 task_prompt 中作为概念参考；如需学习写作风格本身，让 Worker 通过 WebSearch 取得论文链接并 fetch 全文\n\n---\n\n## 二、Abstract 写作规范\n\n### 2.1 四个必答问题（150-250 words）\n\nAbstract 必须在很短的篇幅内清楚回答：\n1. **研究什么问题** — 1-2 句话交代背景和痛点\n2. **为什么重要** — 现有方法的不足（不用写太多）\n3. **本文提出什么** — 核心贡献的关键机制（简要，不堆砌细节）\n4. **结果说明什么** — 用具体实验结论支撑贡献\n\n### 2.2 禁忌\n\n- **禁止堆砌数据**：Abstract 不是 Results 的缩写。最多引用 2-3 个关键数字，要服务于 claim\n- **禁止过度宣传**：不说 \"revolutionary\"、\"groundbreaking\"\n- **禁止写成 Introduction 的缩写**：Abstract 是独立阅读单元\n- **禁止术语堆积**：如果审稿人几十秒内判断不出价值，就失败了\n- **缩写必须定义**：Abstract 中首次出现的缩写必须展开\n\n### 2.3 审稿人视角检验\n\n写完后用这个标准自检：审稿人能否在 30 秒内判断——\n- 问题是否重要？\n- 方法是否清楚？\n- 贡献是否可信？\n- 结果是否有说服力？\n\n---\n\n## 三、Introduction 写作规范\n\n### 3.1 完整叙事线（5 段结构）\n\nIntroduction 需要从一个清晰、重要的问题切入，逐步把读者带到核心贡献：\n\n1. **研究背景**（1-2 段）：大模型在某类能力/应用中已取得进展，但仍存在一个关键瓶颈\n2. **问题重要性**（1 段）：结合真实应用、已有方法局限或当前趋势，说明这不是小问题\n3. **现有方法不足**（1 段）：系统梳理为什么不够（依赖更大模型/更多数据/更复杂推理/更高成本，或只在特定 benchmark 有效）\n4. **本文核心想法**（1 段）：我们观察到什么、提出了什么方法、为什么能解决上述问题\n5. **贡献总结**（列表）：清楚列出方法贡献、实验贡献和分析贡献\n\n### 3.2 整体叙事结构\n\n```\n现有进展 → 关键缺口 → 本文洞察 → 方法概述 → 实验证据 → 贡献总结\n```\n\n### 3.3 禁忌\n\n- **禁止泛泛介绍**：不要开头就写 \"LLMs have shown remarkable capabilities...\"，要从具体问题切入\n- **禁止缺少过渡**：每段之间必须有逻辑连接\n- **禁止实验报告风格**：Introduction 不是 \"我们做了 X 实验得到了 Y 结果\" 的罗列\n- 每条 Contribution 必须有对应的 section/table 支撑\n- Contribution 列表中不能出现未在前文铺垫过的概念\n\n---\n\n## 四、Related Work 写作规范\n\n### 4.1 目标\n\n让审稿人相信：作者理解这个领域，知道自己的方法站在什么位置，清楚相对已有工作的真实增量在哪里。\n\n### 4.2 结构要求\n\n- 把已有工作分成几个清晰的主题（如模型训练、推理增强、工具调用、数据构建、评测等）\n- 每类简要说明：已有方法做了什么、解决了哪些问题、和本文的关系\n- 帮助读者理解：哪些是本文直接继承的，哪些方法不同但解决相似问题，哪些留下了本文要解决的缺口\n\n### 4.3 禁忌\n\n- **禁止论文堆砌**：不要写成 \"A proposed X. B proposed Y. C proposed Z.\" 的列表\n- **目标不是展示读了多少论文**，而是做归纳和比较\n- Contribution claim（\"To our knowledge, no prior work...\"）应放在 Introduction，不在 Related Work\n\n### 4.4 引用充足度\n\n- 引用必须覆盖：**直接相关方法、baseline 论文、评测 benchmark 论文、理论基础**\n- 任何一类缺失，审稿人会立刻看出来调研不充分\n- 引用密度参照目标会议近年录用论文的量级——明显偏少意味着 Related Work 调研不足\n\n---\n\n## 五、去 AI 写作风格（硬规则）\n\n以下模式是 AI 生成文本的典型标志，审稿人一眼能看出。**必须全部消除。**\n\n### 5.1 严禁破折号（最显著的 AI 痕迹）\n\n**这是 AI 写作最容易被识别的标志，审稿人最敏感。单列为最高优先级硬规则。**\n\n- 解释性 em-dash（—，U+2014）和 en-dash（–，U+2013）必须**全部删除**\n- 替代方式：用逗号、括号或拆分为两个句子\n- 强制检查命令：\n  ```bash\n  grep -n \"—\" paper/*.tex     # em-dash，每处人工判断是否必要\n  grep -n \" – \" paper/*.tex   # 解释性 en-dash，几乎都应删除\n  ```\n- 例外（允许保留）：表格分隔符、数字范围（`2020–2024`、`pp. 12–18`）、专有名词（`Newton–Raphson`）\n\n### 5.2 段落与句式\n\n- **禁止过度分段**：不需要每 2-3 句就换段，自然段 5-8 句是正常的\n- **减少关系从句**（which, that, who）：能用简洁直接的句子就不用从句\n- **禁止 -ing 短语结尾**：如 \"..., highlighting the applicability of...\" / \"..., demonstrating the effectiveness of...\"。这是 AI 写作最典型的标志之一\n- **禁止连续使用 \"Furthermore\" / \"Moreover\" / \"Additionally\"**：一段内最多用一个过渡词\n- **避免 \"It is worth noting that...\" / \"Notably, ...\"**：直接写要说的内容\n\n### 5.3 用词黑名单\n\n- 避免 \"delve into\" / \"leverage\" / \"utilize\" / \"facilitate\" — 用 \"explore\" / \"use\" / \"enable\"\n- 避免 \"a myriad of\" / \"a plethora of\" — 用 \"many\" / \"various\"\n- 避免 \"in the realm of\" / \"in the context of\" — 直接说\n- 避免 \"paradigm shift\" / \"novel\" 过度使用\n\n### 5.4 校对清单（4 步）\n\n1. 全文 proofread 语法和拼写\n2. 检查所有代词/指示词（this, that, it）是否指代明确\n3. **`grep \"—\"` + `grep \" – \"` 全文清零**（删除所有解释性 dash，§5.1）\n4. `grep \"ing,\"` 模式——大部分 -ing 分词短语需要改写\n\n---\n\n## 六、图表与视觉规范\n\n### 6.1 知识密度原则\n\n- **图表的信息必须紧凑**——不能为了美观而留大量白空间\n- 一张图如果只传达一个简单信息，要么缩小要么合并到其他图中\n- 能用 inline text 说清的不要占一整个 Figure\n\n### 6.2 表格规范\n\n- 表格和正文文字不能视觉重叠（检查 column 宽度和 alignment）\n- 小数精度全表统一\n- 最优加粗、次优下划线\n- Caption 必须自包含\n\n### 6.3 图片规范\n\n- 数值标签不能被线、bar、点遮住——用白色背景或偏移标签\n- 图中字体 >= 7pt（打印后仍可读）\n- 栏宽约束需匹配目标 venue 模板要求\n- 概念图/流程图要有信息量，不要画一个 trivial 的 pipeline 然后占半页\n\n### 6.4 空间效率\n\n- 顶会正文页数严格受限（具体页数查目标会议官网），每 cm² 都是宝贵资源\n- 优先使用 `\\subfigure` 合并相关图\n- Table 能 inline 就不要单独浮动\n- 图表占比与其对叙事的贡献成正比\n\n---\n\n## 七、投稿前通用准备\n\n### 7.1 模板必须官方（硬规则）\n\n- LaTeX 模板**必须从目标会议官网下载**（CallForPapers / Author Instructions 页面）\n- **不要用**：\n  - 网上他人转载的复制版本（可能被改过 margin / 行号设置）\n  - 上一年的模板（参数可能变：字体、margin、行号、anonymous 选项等）\n  - 组里学长留的旧版本（来源不明、无法追溯）\n- 风险：\n  - 样式不符合 → desk reject\n  - margin 不对 → 被审稿人质疑诚信\n  - reference 格式错 → 被认为不规范\n- 流程：先查会议官网 templates → 找不到再 `WebSearch \"{venue} {year} latex template official\"` → 仍找不到汇报 Director（不要用就近年版本顶替）\n- `\\documentclass[]{}` 选项必须与目标 venue + 阶段（review / camera-ready）一致\n\n### 7.2 投稿要求逐项核对\n\n- 目标会议如要求 Checklist / Ethical Statement / Broader Impact Statement / Reproducibility Statement，必须**认真填每一项**，不要全写 N/A\n- 页数限制：查目标会议官网\n- 匿名化要求：review 版 vs camera-ready 版本设置不同\n- 行号开启（review 版常需）\n- 字体大小、margin 不得修改 sty 文件\n\n### 7.3 最终修改 10 项检查流程\n\n提交前必须逐一检查：\n1. 所有最新实验结果已全部录入\n2. 根据实验结果将叙事调至最优状态\n3. 附录所有内容在正文中被引用且融入叙事\n4. 无数据堆砌（每个数字服务于叙事推进）\n5. Abstract 和 Introduction 具有吸引力（不是实验报告风格）\n6. 全文主线统一（idea 变化后各章节逻辑一致）\n7. 所有专有名词有定义\n8. 无 AI 风格标志（dash、-ing phrases、过度分段）\n9. 图表知识密度高、无视觉遮挡\n10. Reference 覆盖直接相关方法、baseline、benchmark、理论基础\n",
      "numLines": 252,
      "startLine": 1,
      "totalLines": 252
    }
  }
}
````

</details>

---

### Tool call

_source line 7_

<details open><summary>🔧 Tool call — Read · `toolu_01Qmfa9MmdcrPAobRoB2HqPH`</summary>

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
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "95cab090-3de5-41f3-bdad-f0286a6cb317",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JYM7XLq8HUMTsAuqGqsh8i",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14941,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14941
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

_source line 8 · 2026-05-17T07:51:11.062Z_

<details><summary>↩ Tool result · `toolu_01Qmfa9MmdcrPAobRoB2HqPH`</summary>

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
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "0fa75076-8ace-4770-b512-8b58bb3d0316",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md",
      "content": "---\nname: latex-paper\ndescription: ML 顶会论文 LaTeX 写作全流程——Claim-Evidence 方法论、引用防幻觉、顶会模板速查、投稿工程链、会议转投。写论文/投稿时参考。\nscope: global\ntags:\n- latex\n- paper-writing\n- academic\n- citation\n- submission\nversion: 1\nroles:\n- agent\n- worker\n---\n\n# LaTeX 论文写作全流程\n\nML/AI 顶会论文从草稿到投稿的完整指南。整合 Orchestra Research、VibeSkills、claim2evidence 三方最佳实践。\n\n---\n\n## 1. 工作模式\n\n开始前选择模式：\n\n| 模式 | 说明 | 适用 |\n|------|------|------|\n| **Build** | 从实验笔记/结果/代码生成论文 | 新稿 |\n| **Improve** | 改写已有章节，强化论证 | 修改稿 |\n| **Audit** | 输出风险列表 + 缺失证据 + 修复建议 | 投前检查 |\n\n---\n\n## 2. Claim-Evidence 方法论\n\n**核心原则：论文是一个有中心贡献的故事，不是实验的堆砌。**\n\n### 2.1 一句话贡献\n\n在写任何内容之前，必须能用一句话说清贡献。如果不能，说明还没准备好写论文。\n\n### 2.2 Claim-Evidence Map\n\n为每个 contribution 建立 claim→evidence 映射表：\n\n| Contribution | Claim | Evidence | Table/Figure |\n|-------------|-------|----------|-------------|\n| C1: 方法 X 在 Y 上 SOTA | 比所有 baseline 高 ≥2% | 5-seed 平均，p<0.05 | Table 1 |\n| C2: 消融证明 Z 是关键 | 去掉 Z 后掉 >5% | 消融实验 | Table 2 |\n| C3: 计算效率 | 比 baseline 快 3× | FLOPs + wall-clock | Figure 3 |\n\n**没有直接证据支撑的 claim 必须删除或降级为 discussion。**\n\n### 2.3 章节起草顺序\n\n```\n1. Introduction + Experiments（先确定 claim 和 evidence）\n2. Method（评估问题稳定后再写细节）\n3. Related Work\n4. Abstract + Title（核心 claim 定型后最后写）\n```\n\n### 2.4 Quality Gates\n\n投稿前必须通过：\n- [ ] 前两段出现显式 novelty 声明\n- [ ] 每个 contribution 有可验证的 evidence\n- [ ] Abstract / Intro / Conclusion 的 claim 一致\n- [ ] Limitations 真实且技术性诚实\n- [ ] 审稿人两分钟内能识别 delta\n\n---\n\n## 3. 引用防幻觉（CRITICAL）\n\n**AI 生成引用有 ~40% 错误率。绝对禁止凭记忆写 BibTeX。**\n\n### 3.1 黄金法则\n\n```\nIF 无法程序化获取引用:\n    → 标记 [CITATION NEEDED] 或 \\cite{PLACEHOLDER_verify}\n    → 明确告知用户\n    → 绝不编造看似合理的引用\n```\n\n### 3.2 五步验证流程\n\n```\n1. SEARCH  → Semantic Scholar API 搜索关键词\n2. VERIFY  → 至少 2 个来源确认论文存在（S2 + arXiv/CrossRef）\n3. RETRIEVE → 通过 DOI 获取 BibTeX（程序化，非记忆）\n4. CHECK   → 确认你引用的 claim 确实出自该论文\n5. ADD     → 加入 .bib 文件\n```\n\n### 3.3 API 速查\n\n| API | 用途 | 限制 |\n|-----|------|------|\n| **Semantic Scholar** | ML/AI 论文搜索 | 1 RPS (免费) |\n| **CrossRef** | DOI → BibTeX | 需 mailto 头 |\n| **arXiv** | 预印本搜索 | 3s 间隔 |\n\n```python\n# DOI → BibTeX（最可靠的方式）\nimport requests\ndef doi_to_bibtex(doi: str) -> str:\n    r = requests.get(f\"https://doi.org/{doi}\",\n                     headers={\"Accept\": \"application/x-bibtex\"})\n    r.raise_for_status()\n    return r.text\n\n# Semantic Scholar 搜索\nfrom semanticscholar import SemanticScholar\nsch = SemanticScholar()\nresults = sch.search_paper(\"attention mechanism transformers\", limit=5)\nfor p in results:\n    print(f\"{p.title} | DOI: {p.externalIds.get('DOI', 'N/A')}\")\n```\n\n### 3.4 引用处理规则\n\n| 情况 | 处理 |\n|------|------|\n| 找到论文 + DOI + BibTeX | 直接用 |\n| 找到论文，无 DOI | 用 arXiv BibTeX |\n| 论文存在但无法获取 BibTeX | 标记 placeholder，告知用户 |\n| 不确定论文是否存在 | 标记 `[CITATION NEEDED]`，告知用户 |\n| \"我觉得有篇关于 X 的论文\" | **绝不引用** — 先搜索或标记 |\n\n---\n\n## 4. 顶会模板速查\n\n### 4.1 ML/AI 会议\n\n| 会议 | 页数限制 | 主文件 | 样式文件 | 必须项 |\n|------|---------|--------|---------|--------|\n| **NeurIPS** | 9 页 | `main.tex` | `neurips.sty` | Paper Checklist |\n| **ICML** | 8 页 (+1 camera-ready) | `example_paper.tex` | `icml2026.sty` | Broader Impact |\n| **ICLR** | 9 页 (+1) | `iclr_conference.tex` | `iclr_conference.sty` | LLM 使用声明 |\n| **ACL/EMNLP** | 8 页 (long) | `acl_latex.tex` | `acl.sty` | Limitations 必须 |\n| **AAAI** | 7 页 (+1) | `aaai_template.tex` | `aaai.sty` | 严格样式 |\n| **COLM** | 9 页 (+1) | `colm_conference.tex` | `colm_conference.sty` | 语言模型聚焦 |\n\n### 4.2 系统会议\n\n| 会议 | 页数限制 | 模板类型 | 关键要求 |\n|------|---------|---------|---------|\n| **OSDI** | 12 页 (+2) | USENIX `usenix.sty` | Research / Operational 双 track |\n| **NSDI** | 12 页 | USENIX | Introduction 预筛 |\n| **ASPLOS** | 12 页 | ACM `acmart.cls (sigplan)` | 前 2 页快速评审 |\n| **SOSP** | 12 页 | ACM `acmart.cls (sigplan)` | 可选 Artifact Evaluation |\n\n### 4.3 模板使用原则\n\n```bash\n# 1. 复制整个模板目录（不要只拷 .tex）\ncp -r templates/neurips2025/ ~/papers/my-paper/\n\n# 2. 先编译未修改的模板，确认能跑通\nlatexmk -pdf main.tex\n\n# 3. 逐章替换内容，频繁编译\n```\n\n**禁止事项：**\n- 不要修改 `.sty` 文件\n- 不要在会议模板间复制 `\\usepackage` 行\n- 不要只复制 `.tex` 而不带 `.sty/.bst`\n\n---\n\n## 5. 写作规范\n\n### 5.1 时间分配（Neel Nanda）\n\n花**大致相等**的时间在：\n1. Abstract\n2. Introduction\n3. 图表\n4. **其余所有内容加起来**\n\n审稿人读论文的顺序：标题 → 摘要 → 引言 → 图表 → 也许正文。\n\n### 5.2 Abstract 五句法（Sebastian Farquhar）\n\n```\n1. 你做了什么（\"We introduce/prove/demonstrate...\"）\n2. 为什么这很难且重要\n3. 怎么做的（含专业关键词以便检索）\n4. 有什么证据\n5. 最惊人的数字/结果\n```\n\n删除一切泛泛的开头：~~\"Large language models have achieved remarkable success...\"~~\n\n### 5.3 句子级清晰度（Gopen & Swan）\n\n| 原则 | 规则 |\n|------|------|\n| 主谓紧邻 | 不要在主语和动词之间插入长从句 |\n| 重点在句尾 | 把关键数字/结论放在句末 |\n| 旧信息在前 | 先放读者已知的内容，再引入新概念 |\n| 动词表达动作 | \"We analyzed\" 而非 \"We performed an analysis\" |\n\n### 5.4 常见修改\n\n| 问题 | 修复 |\n|------|------|\n| Abstract 太泛 | 删第一句（如果它能放在任何 ML 论文前面） |\n| Introduction 超 1.5 页 | 背景挪到 Related Work |\n| 实验没有显式 claim | 每个实验前加 \"This tests whether...\" |\n| 缺统计显著性 | 加 error bars + 运行次数 + 计算方法 |\n\n---\n\n## 6. 投稿工程链\n\n### 6.1 构建\n\n```bash\n# 推荐：latexmk 一键构建\nlatexmk -pdf -interaction=nonstopmode -halt-on-error main.tex\n\n# 手动：需要多次编译\npdflatex main.tex && bibtex main && pdflatex main.tex && pdflatex main.tex\n```\n\n### 6.2 Lint + 格式化\n\n```bash\n# Lint: 检查常见 LaTeX 问题\nchktex main.tex\n\n# 格式化: 减少 diff 噪声\nlatexindent -w main.tex\n```\n\n### 6.3 图表格式\n\n| 类型 | 格式 | 说明 |\n|------|------|------|\n| 矢量图（plot、diagram） | PDF | matplotlib: `plt.savefig('fig.pdf')` |\n| 照片/heatmap | PNG 600dpi 或 TIFF | 栅格图 |\n| 表格 | `booktabs` 包 | `\\toprule/\\midrule/\\bottomrule` |\n\n```latex\n\\usepackage{booktabs}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & Accuracy $\\uparrow$ & Latency $\\downarrow$ \\\\\n\\midrule\nBaseline & 85.2 & 45ms \\\\\n\\textbf{Ours} & \\textbf{92.1} & 38ms \\\\\n\\bottomrule\n\\end{tabular}\n```\n\n**图表规范：**\n- 用色盲友好色板（Okabe-Ito 或 Paul Tol）\n- 图内不放标题（用 caption）\n- Caption 独立可理解（不依赖正文）\n- 最佳值加粗，标注方向符号（↑ 越高越好，↓ 越低越好）\n\n### 6.4 投稿打包\n\n```bash\n# 清理辅助文件\nlatexmk -c\n\n# 打包投稿\nzip -r submission.zip main.tex *.sty *.bst *.bib figures/ --exclude='*.aux' --exclude='*.log'\n```\n\n### 6.5 常见失败点\n\n| 问题 | 解决 |\n|------|------|\n| 图片格式混用导致编译失败 | 统一用 PDF |\n| 字体未嵌入 | `pdffonts output.pdf` 检查 |\n| Overfull box 过多 | 关键位置手动调行 |\n| 引用缺字段 | 检查 DOI/年份/期刊名 |\n| 超页数 | 用 `\\vspace{-Xpt}` 微调，或精简内容 |\n\n---\n\n## 7. 会议转投\n\n当论文被拒或转投其他会议时：\n\n### 7.1 ML/AI 会议间转换\n\n| 转换 | 页数变化 | 关键调整 |\n|------|---------|---------|\n| NeurIPS → ICML | 9→8 | 删 1 页，加 Broader Impact |\n| ICML → ICLR | 8→9 | 可扩展实验 + LLM 声明 |\n| NeurIPS → ACL | 9→8 | 按 NLP 惯例重组 + Limitations |\n| ICLR → AAAI | 9→7 | 大幅精简，严格样式 |\n\n### 7.2 转投原则\n\n1. **永远用目标模板重新开始** — 复制目标模板，迁移内容，不要合并 preamble\n2. **只迁移正文内容** — 不复制 `\\usepackage`、header/footer 命令\n3. **根据审稿意见改进** — 但不要在新稿中提及旧投稿（双盲）\n4. **检查目标会议特殊要求** — checklist、ethics statement、LLM 声明等\n\n---\n\n## 8. 投前清单\n\n### 通用清单\n\n- [ ] Abstract/Intro/Conclusion 的 claim 一致\n- [ ] 每个 contribution 有对应 evidence\n- [ ] 所有引用已程序化验证（无幻觉引用）\n- [ ] Error bars + 运行次数 + 统计方法\n- [ ] Limitations 章节存在且诚实\n- [ ] 匿名化（双盲审稿）\n- [ ] 符合页数限制\n- [ ] 所有图表有自包含 caption\n- [ ] `.bib` 中无缺失字段\n- [ ] PDF 编译无 warning\n\n### 会议特定\n\n| 会议 | 额外要求 |\n|------|---------|\n| NeurIPS | 16 项 Paper Checklist（附录，不计页数） |\n| ICML | Broader Impact Statement |\n| ICLR | LLM 使用声明 |\n| ACL/EMNLP | Limitations 章节（必须），Ethics Statement |\n| AAAI | 严格样式文件合规 |\n\n---\n\n## 参考资源\n\n**写作方法论：**\n- [Neel Nanda: How to Write ML Papers](https://www.alignmentforum.org/posts/eJGptPbbFPZGLpjsp/) — What/Why/So What 框架\n- [Farquhar: How to Write ML Papers](https://sebastianfarquhar.com/on-research/2024/11/04/how_to_write_ml_papers/) — 五句法 Abstract\n- [Gopen & Swan: Science of Scientific Writing](https://cseweb.ucsd.edu/~swanson/papers/science-of-writing.pdf) — 读者预期 7 原则\n- [Lipton: Heuristics for Scientific Writing](https://www.approximatelycorrect.com/2018/01/29/heuristics-technical-scientific-writing-machine-learning-perspective/) — 用词\n- [Perez: Easy Paper Writing Tips](https://ethanperez.net/easy-paper-writing-tips/) — 微观清晰度\n\n**API：**\n- [Semantic Scholar](https://api.semanticscholar.org/api-docs/) | [CrossRef](https://www.crossref.org/documentation/) | [arXiv](https://info.arxiv.org/help/api/)\n\n**会议官方：**\n- [NeurIPS](https://neurips.cc/) | [ICML](https://icml.cc/) | [ICLR](https://iclr.cc/) | [ACL](https://www.aclweb.org/) | [AAAI](https://aaai.org/) | [EMNLP](https://2025.emnlp.org/)\n",
      "numLines": 353,
      "startLine": 1,
      "totalLines": 353
    }
  }
}
````

</details>

---

### Tool call

_source line 9_

<details open><summary>🔧 Tool call — Read · `toolu_01XAs9PTT8nMAXrKcLKD1Qy9`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "503c28ed-88a9-4d77-bc5d-fa5236a6c44c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JYM7XLq8HUMTsAuqGqsh8i",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14941,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14941
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

_source line 10 · 2026-05-17T07:51:12.170Z_

<details><summary>↩ Tool result · `toolu_01XAs9PTT8nMAXrKcLKD1Qy9`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Problem Formulation}
5	\label{sec:problem_formulation}
6	
7	We formalize the multi-turn interactive agent as a Partially Observable Markov Decision Process (POMDP) $\mathcal{M} = (\mathcal{S}, \mathcal{A}, \mathcal{O}, P, \Omega, R, \gamma)$, where $\mathcal{S}$ is the state space of the environment, $\mathcal{A}$ is the action space (natural language commands), $\mathcal{O}$ is the observation space (textual feedback from the environment), $P: \mathcal{S} \times \mathcal{A} \rightarrow \mathcal{S}$ is the transition function, $\Omega: \mathcal{S} \rightarrow \mathcal{O}$ is the observation function, $R$ is the reward function, and $\gamma \in [0,1]$ is a discount factor. The agent policy $\pi_\phi(a_t \mid h_t)$ generates actions conditioned on the interaction history $h_t = (o_1, a_1, o_2, a_2, \ldots, o_t)$, where $\phi$ denotes the policy parameters. An episode consists of $T$ interaction steps, terminating with a binary reward $R \in \{0, r_+\}$ that indicates task success or failure.
8	
9	In practice, multi-turn episodes can span 50 or more interaction steps, each containing hundreds of tokens. Training a language model policy on the full history $h_T$ is computationally expensive and often exceeds the model's context window. This motivates the \textbf{step-independent windowing} approach: the trajectory is partitioned into non-overlapping windows of $h$ consecutive steps, and each window is optimized independently with its own computed return. Concretely, window $k$ observes only $(o_{(k-1)h+1}, a_{(k-1)h+1}, \ldots, o_{kh})$ and receives a return $R_k$ derived from the episode outcome. This decomposition treats each window as a separate training sample, allowing standard context-length models to process the data. We show below that this seemingly practical choice introduces two failure mechanisms that cause catastrophic training collapse.
10	
11	\subsection{GRPO for Language Agents}
12	\label{sec:grpo}
13	
14	Group Relative Policy Optimization (GRPO)~\cite{shao2024deepseekmath} is a bandit-style policy gradient method designed for language model alignment. Unlike PPO~\cite{schulman2017ppo}, GRPO requires no critic network. For each task instance $x$, the algorithm samples $K$ rollouts $\{y_1, \ldots, y_K\}$ from the current policy $\pi_\phi$. The advantage of each rollout is computed relative to the group:
15	\begin{equation}
16	\hat{A}_k = \frac{R_k - \mu}{\sigma + \epsilon}, \quad \mu = \frac{1}{K}\sum_{j=1}^K R_j, \quad \sigma = \sqrt{\frac{1}{K}\sum_{j=1}^K (R_j - \mu)^2}
17	\label{eq:grpo_advantage}
18	\end{equation}
19	where $R_k$ is the return of rollout $k$. The policy gradient is:
20	\begin{equation}
21	\mathcal{L}_{\text{GRPO}} = -\frac{1}{K}\sum_{k=1}^K \hat{A}_k \cdot \min\left(\rho_k, \text{clip}(\rho_k, 1\pm\epsilon_c)\right) + \beta \cdot D_{\text{KL}}[\pi_\phi \| \pi_{\text{ref}}]
22	\label{eq:grpo_loss}
23	\end{equation}
24	where $\rho_k = \pi_\phi(y_k \mid x) / \pi_{\text{old}}(y_k \mid x)$ is the importance ratio and $\beta$ controls the KL penalty against a reference policy $\pi_{\text{ref}}$. GRPO is \textit{episode-level by design}: each rollout $y_k$ is a complete generation with a single return $R_k$ and a single advantage $\hat{A}_k$. There is no inherent temporal discounting within the algorithm.
25	
26	\subsection{Step-Independent Implementation in Multi-Turn Agents}
27	\label{sec:step_independent}
28	
29	When adapting GRPO for multi-turn interactive tasks, agent training frameworks face a mismatch between GRPO's episode-level design and the practical constraints of long trajectories. The RAGEN framework~\cite{ragen2025} addresses this by introducing step-independent training: each $h$-step window becomes an independent GRPO sample with a discounted return derived from the episode outcome.
30	
31	Specifically, for an episode of $T$ steps with binary outcome $R_{\text{episode}} \in \{0, r_+\}$, the return assigned to window $k$ (covering steps $(k-1)h+1$ through $kh$) is computed as:
32	\begin{equation}
33	R_k = \gamma^{(N - k)} \cdot R_{\text{episode}}
34	\label{eq:step_return}
35	\end{equation}
36	where $N = \lceil T/h \rceil$ is the total number of windows in the episode and $\gamma$ is a discount factor (typically 0.95). Each window is then treated as an independent sample in the GRPO optimization and receives its own group-normalized advantage $\hat{A}_k$ via Equation~\ref{eq:grpo_advantage}. The total number of training samples per episode increases from 1 to $N$.
37	
38	This design choice is motivated by three practical constraints. First, full trajectories of 50+ turns with hundreds of tokens per turn exceed typical context window limits (2048 or 4096 tokens for smaller models). Second, treating each window independently multiplies the effective batch size, improving GPU utilization. Third, the framework inherits the token-level training paradigm common in language model optimization, where shorter sequences are the default.\footnote{Implementation details are available in the open-source RAGEN codebase, specifically the step-discounted return computation module (\texttt{compute\_step\_discounted\_returns}).}
39	
40	Despite these practical motivations, step-independent training fundamentally alters the credit assignment structure. The following section analyzes two mechanisms through which this alteration causes training collapse.
41	
42	\subsection{Dual Mechanism Analysis}
43	\label{sec:dual_mechanism}
44	
45	We identify two mechanisms that jointly cause catastrophic failure under step-independent training. As we demonstrate empirically in Section~\ref{sec:experiments}, step-independent training collapses to 0\% task success within 10 training steps, while action validity remains above 90\%. This pattern indicates that the policy degenerates in task strategy rather than action formatting.
46	
47	\subsubsection{Mechanism 1: Policy Information Loss}
48	\label{sec:m1_information_loss}
49	
50	Under step-independent training, the policy optimized on window $k$ observes only a local $h$-step history. Cross-step strategies that require conditioning on earlier outcomes become invisible to the optimization process. Consider a household task requiring the agent to first explore a drawer (step 3), discover an object's location (step 4), then navigate to a countertop (step 8). With $h=2$, the window containing step 8 has no access to the exploration outcome from steps 3--4. The policy cannot learn the conditional strategy ``go to countertop \textit{only if} the object was found in the drawer.''
51	
52	More formally, let $\pi^*$ denote the optimal policy for the full POMDP. The mutual information between $\pi^*$ and the full history, $I(\pi^*; h_T)$, captures the total information required for optimal decision-making. Under $h$-step windowing, each window's policy can access at most $I(\pi^*; h_{\text{window}_k})$. For tasks with sequential dependencies spanning more than $h$ steps, we have $I(\pi^*; h_T) \gg I(\pi^*; h_{\text{window}_k})$. The information gap grows with episode length $T$ and shrinks with window size $h$, predicting a performance cliff as $h$ decreases relative to the task's dependency horizon.
53	
54	\subsubsection{Mechanism 2: Advantage Sign Misattribution}
55	\label{sec:m2_sign_misattribution}
56	
57	The second mechanism is more subtle and more damaging. Under step-independent training, each window receives a return $R_k = \gamma^{(N-k)} \cdot R_{\text{episode}}$ (Equation~\ref{eq:step_return}). After group normalization, the advantage $\hat{A}_k$ has a \textit{sign} determined primarily by whether the episode succeeded or failed, not by whether window $k$'s actions were locally good or bad.
58	
59	In a failed episode ($R_{\text{episode}} = 0$), all windows receive $R_k = 0$. If the group mean $\mu > 0$ (due to other successful rollouts in the group), all windows in the failed episode receive negative advantages. This includes windows where the agent took locally correct actions (e.g., correctly identifying a target object). Conversely, in a successful episode, all windows receive positive advantages, including windows where the agent took suboptimal actions (e.g., unnecessary exploration steps that happened not to prevent eventual success).
60	
61	The gradient direction for each window is determined by the sign of $\hat{A}_k$:
62	\begin{equation}
63	\text{sign}(\hat{A}_k) \approx \text{sign}(R_{\text{episode}} - \mu)
64	\label{eq:sign_correlation}
65	\end{equation}
66	This means the optimization either reinforces or suppresses \textit{all} actions within a window based on the episode outcome, regardless of local action quality. Good actions in failed episodes are actively suppressed; bad actions in successful episodes are actively reinforced. Over many training steps, this systematic misattribution erodes learned strategies: the agent cannot maintain locally correct behaviors if they frequently co-occur with episode failure.
67	
68	A secondary effect compounds this problem. The discount factor $\gamma^{(N-k)}$ introduces magnitude decay across window positions. For early windows in a long episode ($T=50$, $h=2$, $\gamma=0.95$), the first window ($k=1$) retains $\gamma^{N-1} = \gamma^{24} \approx 0.29$ of the terminal window's return. While this reduces the learning signal for early decisions, the sign error is fundamentally more harmful. Magnitude decay slows learning but preserves the correct optimization direction; sign misattribution actively drives the policy away from good behaviors. A gradient with correct sign but attenuated magnitude yields slow convergence. A gradient with wrong sign yields divergence.
69	
70	\subsection{Episode-Level Training}
71	\label{sec:episode_level}
72	
73	Episode-level training resolves both failure mechanisms by treating the complete trajectory as a single GRPO sample. All tokens across all $T$ steps share one advantage $\hat{A}$, computed from the episode return $R_{\text{episode}}$ via group normalization over $K$ complete rollouts of the same task instance.
74	
75	This design directly addresses Mechanism 1. The policy $\pi_\phi(a_t \mid h_t)$ conditions on the full interaction history $h_t$ at every step $t$. Cross-step dependencies are preserved in the optimization target: the gradient for generating action $a_8$ (navigate to countertop) flows through the complete history including observations from steps 3--4 (drawer exploration outcome).
76	
77	Episode-level training also eliminates Mechanism 2. Because there is no window-level return assignment, there is no opportunity for sign misattribution between windows. The single advantage $\hat{A}$ applies uniformly to the entire trajectory. While this means per-step credit assignment remains coarse (all steps in a successful episode are equally reinforced), it avoids the worse failure mode of \textit{systematically incorrect} credit assignment. The distinction is critical: uniform reinforcement of a successful trajectory preserves good sub-strategies within it, whereas window-level sign errors actively destroy them.
78	
79	The trade-off is computational. Episode-level training requires processing the full sequence length ($T$ steps $\times$ tokens-per-step) in a single forward and backward pass. For $T=50$ and 100 tokens per step, this amounts to 5000-token sequences, which fits within the capacity of modern architectures but increases memory and compute relative to $h$-step windows. In our experiments (Section~\ref{sec:experiments}), this overhead is modest compared to the catastrophic failure avoided.
80	
81	Episode-level training is, in fact, the natural application of GRPO to multi-turn settings. GRPO was designed as an episode-level algorithm where each rollout receives one return and one advantage. Step-independent training is the deviation from this design, introduced by framework implementation choices rather than algorithmic motivation. Our analysis reveals that this deviation carries hidden costs that become catastrophic for long-horizon interactive tasks.
82	
83	\subsection{Selective Verification via Action-Change Reward}
84	\label{sec:selective_verification}
85	
86	With a competent base agent trained via episode-level GRPO, we address the complementary problem of verification efficiency. Interactive agents benefit from self-verification (re-evaluating their planned action before execution), but empirical analysis shows that over 90\% of verification instances are confirmatory (the agent does not change its action after checking)~\cite{long2026selfverification}. Training the agent to verify selectively, only when verification is likely to be informative, can reduce computational cost without sacrificing task performance.
87	
88	We formulate selective verification as a binary decision at each step $t$: the agent outputs a verify token $v_t \in \{\texttt{VERIFY}, \texttt{SKIP}\}$ before generating its action $a_t$. When $v_t = \texttt{VERIFY}$, the agent generates a verification rationale and may revise its action; when $v_t = \texttt{SKIP}$, the agent proceeds directly. The reward signal for training the verification policy uses the action-change indicator:
89	\begin{equation}
90	\Delta a_t = \mathbb{1}[a_t^{\text{post-verify}} \neq a_t^{\text{pre-verify}}]
91	\label{eq:action_change}
92	\end{equation}
93	as a measure of verification informativeness. A verification step that changes the action provided useful corrective information; one that confirms the original action was uninformative for that instance. The full formulation of the verification reward and training procedure is presented in Section~\ref{sec:selective_experiments}. Episode-level training serves as a prerequisite for this component: training a selective verification policy requires a base agent with sufficient task competence, which step-independent training cannot produce.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "d06d3e9c-1cc8-4411-9bfd-1ea3bf0ddebc",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/method.tex",
      "content": "\\section{Method}\n\\label{sec:method}\n\n\\subsection{Problem Formulation}\n\\label{sec:problem_formulation}\n\nWe formalize the multi-turn interactive agent as a Partially Observable Markov Decision Process (POMDP) $\\mathcal{M} = (\\mathcal{S}, \\mathcal{A}, \\mathcal{O}, P, \\Omega, R, \\gamma)$, where $\\mathcal{S}$ is the state space of the environment, $\\mathcal{A}$ is the action space (natural language commands), $\\mathcal{O}$ is the observation space (textual feedback from the environment), $P: \\mathcal{S} \\times \\mathcal{A} \\rightarrow \\mathcal{S}$ is the transition function, $\\Omega: \\mathcal{S} \\rightarrow \\mathcal{O}$ is the observation function, $R$ is the reward function, and $\\gamma \\in [0,1]$ is a discount factor. The agent policy $\\pi_\\phi(a_t \\mid h_t)$ generates actions conditioned on the interaction history $h_t = (o_1, a_1, o_2, a_2, \\ldots, o_t)$, where $\\phi$ denotes the policy parameters. An episode consists of $T$ interaction steps, terminating with a binary reward $R \\in \\{0, r_+\\}$ that indicates task success or failure.\n\nIn practice, multi-turn episodes can span 50 or more interaction steps, each containing hundreds of tokens. Training a language model policy on the full history $h_T$ is computationally expensive and often exceeds the model's context window. This motivates the \\textbf{step-independent windowing} approach: the trajectory is partitioned into non-overlapping windows of $h$ consecutive steps, and each window is optimized independently with its own computed return. Concretely, window $k$ observes only $(o_{(k-1)h+1}, a_{(k-1)h+1}, \\ldots, o_{kh})$ and receives a return $R_k$ derived from the episode outcome. This decomposition treats each window as a separate training sample, allowing standard context-length models to process the data. We show below that this seemingly practical choice introduces two failure mechanisms that cause catastrophic training collapse.\n\n\\subsection{GRPO for Language Agents}\n\\label{sec:grpo}\n\nGroup Relative Policy Optimization (GRPO)~\\cite{shao2024deepseekmath} is a bandit-style policy gradient method designed for language model alignment. Unlike PPO~\\cite{schulman2017ppo}, GRPO requires no critic network. For each task instance $x$, the algorithm samples $K$ rollouts $\\{y_1, \\ldots, y_K\\}$ from the current policy $\\pi_\\phi$. The advantage of each rollout is computed relative to the group:\n\\begin{equation}\n\\hat{A}_k = \\frac{R_k - \\mu}{\\sigma + \\epsilon}, \\quad \\mu = \\frac{1}{K}\\sum_{j=1}^K R_j, \\quad \\sigma = \\sqrt{\\frac{1}{K}\\sum_{j=1}^K (R_j - \\mu)^2}\n\\label{eq:grpo_advantage}\n\\end{equation}\nwhere $R_k$ is the return of rollout $k$. The policy gradient is:\n\\begin{equation}\n\\mathcal{L}_{\\text{GRPO}} = -\\frac{1}{K}\\sum_{k=1}^K \\hat{A}_k \\cdot \\min\\left(\\rho_k, \\text{clip}(\\rho_k, 1\\pm\\epsilon_c)\\right) + \\beta \\cdot D_{\\text{KL}}[\\pi_\\phi \\| \\pi_{\\text{ref}}]\n\\label{eq:grpo_loss}\n\\end{equation}\nwhere $\\rho_k = \\pi_\\phi(y_k \\mid x) / \\pi_{\\text{old}}(y_k \\mid x)$ is the importance ratio and $\\beta$ controls the KL penalty against a reference policy $\\pi_{\\text{ref}}$. GRPO is \\textit{episode-level by design}: each rollout $y_k$ is a complete generation with a single return $R_k$ and a single advantage $\\hat{A}_k$. There is no inherent temporal discounting within the algorithm.\n\n\\subsection{Step-Independent Implementation in Multi-Turn Agents}\n\\label{sec:step_independent}\n\nWhen adapting GRPO for multi-turn interactive tasks, agent training frameworks face a mismatch between GRPO's episode-level design and the practical constraints of long trajectories. The RAGEN framework~\\cite{ragen2025} addresses this by introducing step-independent training: each $h$-step window becomes an independent GRPO sample with a discounted return derived from the episode outcome.\n\nSpecifically, for an episode of $T$ steps with binary outcome $R_{\\text{episode}} \\in \\{0, r_+\\}$, the return assigned to window $k$ (covering steps $(k-1)h+1$ through $kh$) is computed as:\n\\begin{equation}\nR_k = \\gamma^{(N - k)} \\cdot R_{\\text{episode}}\n\\label{eq:step_return}\n\\end{equation}\nwhere $N = \\lceil T/h \\rceil$ is the total number of windows in the episode and $\\gamma$ is a discount factor (typically 0.95). Each window is then treated as an independent sample in the GRPO optimization and receives its own group-normalized advantage $\\hat{A}_k$ via Equation~\\ref{eq:grpo_advantage}. The total number of training samples per episode increases from 1 to $N$.\n\nThis design choice is motivated by three practical constraints. First, full trajectories of 50+ turns with hundreds of tokens per turn exceed typical context window limits (2048 or 4096 tokens for smaller models). Second, treating each window independently multiplies the effective batch size, improving GPU utilization. Third, the framework inherits the token-level training paradigm common in language model optimization, where shorter sequences are the default.\\footnote{Implementation details are available in the open-source RAGEN codebase, specifically the step-discounted return computation module (\\texttt{compute\\_step\\_discounted\\_returns}).}\n\nDespite these practical motivations, step-independent training fundamentally alters the credit assignment structure. The following section analyzes two mechanisms through which this alteration causes training collapse.\n\n\\subsection{Dual Mechanism Analysis}\n\\label{sec:dual_mechanism}\n\nWe identify two mechanisms that jointly cause catastrophic failure under step-independent training. As we demonstrate empirically in Section~\\ref{sec:experiments}, step-independent training collapses to 0\\% task success within 10 training steps, while action validity remains above 90\\%. This pattern indicates that the policy degenerates in task strategy rather than action formatting.\n\n\\subsubsection{Mechanism 1: Policy Information Loss}\n\\label{sec:m1_information_loss}\n\nUnder step-independent training, the policy optimized on window $k$ observes only a local $h$-step history. Cross-step strategies that require conditioning on earlier outcomes become invisible to the optimization process. Consider a household task requiring the agent to first explore a drawer (step 3), discover an object's location (step 4), then navigate to a countertop (step 8). With $h=2$, the window containing step 8 has no access to the exploration outcome from steps 3--4. The policy cannot learn the conditional strategy ``go to countertop \\textit{only if} the object was found in the drawer.''\n\nMore formally, let $\\pi^*$ denote the optimal policy for the full POMDP. The mutual information between $\\pi^*$ and the full history, $I(\\pi^*; h_T)$, captures the total information required for optimal decision-making. Under $h$-step windowing, each window's policy can access at most $I(\\pi^*; h_{\\text{window}_k})$. For tasks with sequential dependencies spanning more than $h$ steps, we have $I(\\pi^*; h_T) \\gg I(\\pi^*; h_{\\text{window}_k})$. The information gap grows with episode length $T$ and shrinks with window size $h$, predicting a performance cliff as $h$ decreases relative to the task's dependency horizon.\n\n\\subsubsection{Mechanism 2: Advantage Sign Misattribution}\n\\label{sec:m2_sign_misattribution}\n\nThe second mechanism is more subtle and more damaging. Under step-independent training, each window receives a return $R_k = \\gamma^{(N-k)} \\cdot R_{\\text{episode}}$ (Equation~\\ref{eq:step_return}). After group normalization, the advantage $\\hat{A}_k$ has a \\textit{sign} determined primarily by whether the episode succeeded or failed, not by whether window $k$'s actions were locally good or bad.\n\nIn a failed episode ($R_{\\text{episode}} = 0$), all windows receive $R_k = 0$. If the group mean $\\mu > 0$ (due to other successful rollouts in the group), all windows in the failed episode receive negative advantages. This includes windows where the agent took locally correct actions (e.g., correctly identifying a target object). Conversely, in a successful episode, all windows receive positive advantages, including windows where the agent took suboptimal actions (e.g., unnecessary exploration steps that happened not to prevent eventual success).\n\nThe gradient direction for each window is determined by the sign of $\\hat{A}_k$:\n\\begin{equation}\n\\text{sign}(\\hat{A}_k) \\approx \\text{sign}(R_{\\text{episode}} - \\mu)\n\\label{eq:sign_correlation}\n\\end{equation}\nThis means the optimization either reinforces or suppresses \\textit{all} actions within a window based on the episode outcome, regardless of local action quality. Good actions in failed episodes are actively suppressed; bad actions in successful episodes are actively reinforced. Over many training steps, this systematic misattribution erodes learned strategies: the agent cannot maintain locally correct behaviors if they frequently co-occur with episode failure.\n\nA secondary effect compounds this problem. The discount factor $\\gamma^{(N-k)}$ introduces magnitude decay across window positions. For early windows in a long episode ($T=50$, $h=2$, $\\gamma=0.95$), the first window ($k=1$) retains $\\gamma^{N-1} = \\gamma^{24} \\approx 0.29$ of the terminal window's return. While this reduces the learning signal for early decisions, the sign error is fundamentally more harmful. Magnitude decay slows learning but preserves the correct optimization direction; sign misattribution actively drives the policy away from good behaviors. A gradient with correct sign but attenuated magnitude yields slow convergence. A gradient with wrong sign yields divergence.\n\n\\subsection{Episode-Level Training}\n\\label{sec:episode_level}\n\nEpisode-level training resolves both failure mechanisms by treating the complete trajectory as a single GRPO sample. All tokens across all $T$ steps share one advantage $\\hat{A}$, computed from the episode return $R_{\\text{episode}}$ via group normalization over $K$ complete rollouts of the same task instance.\n\nThis design directly addresses Mechanism 1. The policy $\\pi_\\phi(a_t \\mid h_t)$ conditions on the full interaction history $h_t$ at every step $t$. Cross-step dependencies are preserved in the optimization target: the gradient for generating action $a_8$ (navigate to countertop) flows through the complete history including observations from steps 3--4 (drawer exploration outcome).\n\nEpisode-level training also eliminates Mechanism 2. Because there is no window-level return assignment, there is no opportunity for sign misattribution between windows. The single advantage $\\hat{A}$ applies uniformly to the entire trajectory. While this means per-step credit assignment remains coarse (all steps in a successful episode are equally reinforced), it avoids the worse failure mode of \\textit{systematically incorrect} credit assignment. The distinction is critical: uniform reinforcement of a successful trajectory preserves good sub-strategies within it, whereas window-level sign errors actively destroy them.\n\nThe trade-off is computational. Episode-level training requires processing the full sequence length ($T$ steps $\\times$ tokens-per-step) in a single forward and backward pass. For $T=50$ and 100 tokens per step, this amounts to 5000-token sequences, which fits within the capacity of modern architectures but increases memory and compute relative to $h$-step windows. In our experiments (Section~\\ref{sec:experiments}), this overhead is modest compared to the catastrophic failure avoided.\n\nEpisode-level training is, in fact, the natural application of GRPO to multi-turn settings. GRPO was designed as an episode-level algorithm where each rollout receives one return and one advantage. Step-independent training is the deviation from this design, introduced by framework implementation choices rather than algorithmic motivation. Our analysis reveals that this deviation carries hidden costs that become catastrophic for long-horizon interactive tasks.\n\n\\subsection{Selective Verification via Action-Change Reward}\n\\label{sec:selective_verification}\n\nWith a competent base agent trained via episode-level GRPO, we address the complementary problem of verification efficiency. Interactive agents benefit from self-verification (re-evaluating their planned action before execution), but empirical analysis shows that over 90\\% of verification instances are confirmatory (the agent does not change its action after checking)~\\cite{long2026selfverification}. Training the agent to verify selectively, only when verification is likely to be informative, can reduce computational cost without sacrificing task performance.\n\nWe formulate selective verification as a binary decision at each step $t$: the agent outputs a verify token $v_t \\in \\{\\texttt{VERIFY}, \\texttt{SKIP}\\}$ before generating its action $a_t$. When $v_t = \\texttt{VERIFY}$, the agent generates a verification rationale and may revise its action; when $v_t = \\texttt{SKIP}$, the agent proceeds directly. The reward signal for training the verification policy uses the action-change indicator:\n\\begin{equation}\n\\Delta a_t = \\mathbb{1}[a_t^{\\text{post-verify}} \\neq a_t^{\\text{pre-verify}}]\n\\label{eq:action_change}\n\\end{equation}\nas a measure of verification informativeness. A verification step that changes the action provided useful corrective information; one that confirms the original action was uninformative for that instance. The full formulation of the verification reward and training procedure is presented in Section~\\ref{sec:selective_experiments}. Episode-level training serves as a prerequisite for this component: training a selective verification policy requires a base agent with sufficient task competence, which step-independent training cannot produce.",
      "numLines": 93,
      "startLine": 1,
      "totalLines": 93
    }
  }
}
```

</details>

---

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — Read · `toolu_01PF9Uy7U5pveDfW1P2ehNLM`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/theoretical_analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "c8745840-e349-4065-bcfa-287badbeedcb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JYM7XLq8HUMTsAuqGqsh8i",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14941,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14941
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

_source line 12 · 2026-05-17T07:51:12.684Z_

<details><summary>↩ Tool result · `toolu_01PF9Uy7U5pveDfW1P2ehNLM`</summary>

```text
1	\section{Theoretical Analysis}
2	\label{sec:theory}
3	
4	Section~\ref{sec:dual_mechanism} identified two failure mechanisms of step-independent training: policy information loss and advantage sign misattribution. We now formalize why sign misattribution is the more fundamental failure, derive the probability of incorrect gradient direction as a function of task success rate, examine why the community has defaulted to step-independent training, and connect our findings to the classical credit assignment literature.
5	
6	\subsection{Why Sign Misattribution is Fundamental}
7	\label{sec:sign_fundamental}
8	
9	The two mechanisms identified in Section~\ref{sec:dual_mechanism} produce qualitatively different optimization errors. Policy information loss (Mechanism 1) reduces the information available to each window's policy, producing suboptimal but directionally reasonable gradient updates. Sign misattribution (Mechanism 2) corrupts the gradient direction itself. We formalize this distinction below.
10	
11	\textbf{Proposition 1.} \textit{Under step-independent training with binary episode reward $R_{\text{episode}} \in \{0, r_+\}$, the probability that window $k$'s advantage $\hat{A}_k$ has the correct sign (aligned with local action quality) approaches the base success rate $p$ as the number of rollouts $K$ per group increases.}
12	
13	\textit{Argument.} Define ``correct sign'' as follows: for a window containing locally beneficial actions, the correct sign of $\hat{A}_k$ is positive (reinforcement); for a window containing locally detrimental actions, the correct sign is negative (suppression). Under binary reward, the return for window $k$ is $R_k = \gamma^{(N-k)} \cdot R_{\text{episode}}$ (Equation~\ref{eq:step_return}). In a failed episode ($R_{\text{episode}} = 0$), all windows receive $R_k = 0$ regardless of their local action quality. If the group contains at least one successful rollout, the group mean $\mu > 0$, and all windows in the failed episode receive negative advantages after normalization via Equation~\ref{eq:grpo_advantage}. This includes windows where the agent took locally correct actions, such as correctly identifying a target object in an exploration step. Now consider a window with good local actions. In a successful episode (probability $p$), the window receives positive $\hat{A}_k$, which is the correct sign. In a failed episode (probability $1 - p$), the window receives negative $\hat{A}_k$ whenever $\mu > 0$, which is the wrong sign. The probability that $\mu = 0$ (all $K$ rollouts in the group failed) is $(1-p)^K$, which shrinks exponentially with $K$. As $K$ grows, nearly every failed episode produces a non-zero group mean, and the window receives the wrong sign with probability approaching $1-p$. The probability of correct sign therefore approaches $p$. \qed
14	
15	The distinction between sign error and magnitude error clarifies why Mechanism 2 is catastrophic while Mechanism 1 is merely suboptimal. The discount factor $\gamma^{(N-k)}$ in Equation~\ref{eq:step_return} introduces magnitude decay across window positions: for an episode with $T=50$ steps and $h=2$, the first window ($k=1$) retains $\gamma^{N-1} = 0.95^{24} \approx 0.29$ of the terminal window's return. This attenuation reduces the gradient magnitude for early windows but preserves the gradient direction. A gradient with correct sign and reduced magnitude produces slow convergence, a condition recoverable through longer training. A gradient with wrong sign produces active divergence: the optimization pushes the policy away from good behaviors and toward bad ones. Consider a navigation analogy. Magnitude error corresponds to a compass that points correctly but displays a dimmed needle; the traveler moves slowly toward the destination. Sign error corresponds to a compass pointing in the opposite direction; the traveler walks away from the destination with full confidence. The first error is correctable by patience. The second is correctable only by replacing the compass.
16	
17	\subsection{Formal Probability Analysis}
18	\label{sec:formal_probability}
19	
20	We derive a tighter bound on the probability of correct gradient direction as a function of task difficulty and group size.
21	
22	\textbf{Proposition 2.} \textit{Let $p$ denote the episode success rate and $K$ the number of rollouts per group. Under step-independent training with binary episode reward, the probability that a gradient update for a window with locally good actions has the correct sign satisfies:}
23	\begin{equation}
24	P(\text{correct sign or no update}) = p + (1-p)^{K}
25	\label{eq:correct_bound}
26	\end{equation}
27	\textit{Among gradient updates that occur (non-zero advantage), the fraction with correct sign is:}
28	\begin{equation}
29	P(\text{correct} \mid \text{update}) = \frac{p}{1 - (1-p)^{K}}
30	\label{eq:correct_conditional}
31	\end{equation}
32	
33	\textit{Derivation.} For a window with locally good actions, the gradient direction depends on $\text{sign}(\hat{A}_k)$, which depends on whether the episode succeeded and whether the group contains any successful rollouts. Three mutually exclusive cases arise.
34	
35	\textit{Case 1: Episode succeeded} (probability $p$). The window receives $R_k = \gamma^{(N-k)} \cdot r_+ > 0$. With at least one failed rollout in the group, $R_k > \mu$ after normalization, producing $\hat{A}_k > 0$. The gradient reinforces the window's actions. For a window with good local actions, this is the correct direction.
36	
37	\textit{Case 2: Episode failed, group contains at least one success} (probability $(1-p)[1 - (1-p)^{K-1}]$). The window receives $R_k = 0 < \mu$, producing $\hat{A}_k < 0$. The gradient suppresses the window's actions. For a window with good local actions, this is the wrong direction.
38	
39	\textit{Case 3: Episode failed, entire group failed} (probability $(1-p) \cdot (1-p)^{K-1} = (1-p)^{K}$). All returns are zero, so $\mu = 0$ and $\sigma = 0$. The advantage is zero, producing no gradient update.
40	
41	Summing Cases~1 and~3 yields Equation~\ref{eq:correct_bound}. Since only Cases~1 and~2 produce non-zero gradients, the conditional probability follows as Equation~\ref{eq:correct_conditional}.
42	
43	We evaluate these expressions at the empirical baseline of our experiments. At $p = 6.25\%$ (the pre-training success rate) and $K = 8$ (the group size used in all experiments): $(1-p)^K = 0.9375^8 \approx 0.60$, giving $P(\text{correct or no update}) \approx 0.66$. Of the 40\% of cases that produce a gradient update, only $P(\text{correct} \mid \text{update}) = 0.0625 / 0.404 \approx 15.5\%$ have the correct sign. As $K$ increases to 16, $(1-p)^{K} \approx 0.36$, and $P(\text{correct} \mid \text{update}) \approx 9.8\%$. In the large-$K$ limit, $P(\text{correct} \mid \text{update}) \to p$, so approximately $1 - p \approx 94\%$ of all gradient updates for locally good windows point in the wrong direction. This is consistent with the empirical observation that step-independent training collapses to 0\% task success (exp026, exp028c) while episode-level training achieves stable improvement (exp029, 28.125\% validation success at step 15).
44	
45	\subsection{Why the Community Defaults to Step-Independent Training}
46	\label{sec:why_defaults}
47	
48	If step-independent training is fundamentally flawed for multi-turn agents, why has it become the default? We identify six contributing factors.
49	
50	\textbf{1. Context window constraints.} Smaller language models (1B to 4B parameters) typically support context windows of 2048 to 4096 tokens. Multi-turn episodes spanning 50 or more interaction steps easily exceed these limits. Step-independent windowing is a pragmatic response to a hardware constraint, not a deliberate algorithmic choice.
51	
52	\textbf{2. Token-level training inertia.} Language model training is organized around predicting the next token over fixed-length sequences. When multi-turn RL inherits this paradigm, the natural unit of optimization becomes a fixed-length window rather than a variable-length episode. The mismatch between token-level optimization and episode-level credit assignment goes unquestioned because it aligns with existing training infrastructure.
53	
54	\textbf{3. Framework design accident.} The RAGEN framework~\cite{ragen2025} implements step-independent mode as its default configuration, not as one option among alternatives. Users inherit this choice without an explicit decision point, and default configurations propagate silently through downstream projects.
55	
56	\textbf{4. Memory and compute constraints.} Episode-level training requires processing $O(T)$ tokens per sequence, incurring $O(T^2)$ attention cost with full self-attention. Step-independent training reduces this to $O(h)$ tokens and $O(h^2)$ attention cost per window. The computational savings are immediate and measurable, while the credit assignment failure is subtle and deferred until training collapse occurs.
57	
58	\textbf{5. Reward shaping as apparent fix.} Dense reward shaping (per-step bonuses for intermediate goals) appears to address sparse reward problems and has theoretical support in the single-agent RL literature. Our experiment with dense rewards under step-independent training (exp013f) reveals a different failure mode: the agent learns to maximize format-level rewards (action validity rises from 60\% to 97.5\%) while task success remains at 0\%. Reward shaping does not resolve sign misattribution; it creates new optimization targets that the agent can game without solving the underlying task.
59	
60	\textbf{6. Absence of negative results.} When step-independent training fails, practitioners attribute the failure to insufficient hyperparameter tuning or the inherent difficulty of sparse rewards. Without published analyses that isolate the credit assignment mechanism as the root cause, the community cannot distinguish between ``this problem is hard'' and ``this training paradigm is broken for this class of problems.''
61	
62	\subsection{Connection to Classical Credit Assignment}
63	\label{sec:classical_connection}
64	
65	Our findings connect to a long line of work on temporal credit assignment in reinforcement learning. We position the step-independent failure mode within this literature and clarify the contribution of our analysis.
66	
67	\textbf{Temporal difference learning and eligibility traces.} Sutton's TD($\lambda$)~\cite{sutton1988td} provides a spectrum of credit assignment strategies parameterized by $\lambda \in [0,1]$. At $\lambda = 0$, credit is assigned via one-step bootstrapped returns. At $\lambda = 1$, TD($\lambda$) reduces to Monte Carlo returns, where each state receives the full episode return. Step-independent training falls below this spectrum: windows are disconnected from each other, so temporal propagation of credit does not occur. Each window receives an independently computed advantage with no mechanism for information to flow across windows within the same episode.
68	
69	\textbf{Generalized Advantage Estimation.} GAE($\lambda, \gamma$)~\cite{schulman2016gae} extends TD($\lambda$) with a separate discount factor for the advantage estimator. GAE(0, $\gamma$) produces per-step advantages through a learned value function. GAE(1, 1) produces undiscounted Monte Carlo returns, and is equivalent to episode-level GRPO without a critic. The key difference is that GAE uses value function subtraction as the baseline for variance reduction, while GRPO uses group normalization. Episode-level GRPO can be viewed as GAE(1, 1) with a group-relative baseline replacing the learned value function. This substitution is effective when the group provides a representative reference distribution, but it does not address per-step credit assignment within an episode.
70	
71	\textbf{REINFORCE.} Williams' REINFORCE algorithm~\cite{williams1992reinforce} computes policy gradients from complete episode returns with a learned baseline $b(s)$. Episode-level GRPO is equivalent to REINFORCE where the group mean $\mu$ replaces $b(s)$ and the group standard deviation $\sigma$ provides normalization. The algorithmic structure is not new. Our contribution is the diagnosis: the community's standard adaptation of this algorithm for multi-turn LLM agents (step-independent windowing) silently breaks the credit assignment structure that REINFORCE assumes.
72	
73	\textbf{Multi-agent credit assignment analogy.} Step-independent windows can be understood through cooperative multi-agent games. Each window acts as an independent ``agent'' sharing a team reward (the episode outcome) but optimized without knowledge of other windows' actions. The sign misattribution problem parallels team reward credit assignment in cooperative multi-agent RL: when the team fails, all agents receive identical penalties regardless of individual contribution. In multi-agent RL, this is a recognized problem with known solutions such as counterfactual baselines. In multi-turn LLM agent training, the same structural problem arises from an implementation choice and has not been recognized as a credit assignment failure.
74	
75	To summarize our positioning: we do not propose a new credit assignment algorithm. Episode-level training is the standard approach, and GRPO was designed as an episode-level method. What we identify is that the community's adaptation of GRPO to multi-turn settings introduces a systematic sign error in gradient computation. This error is not a gradual performance degradation but a catastrophic failure mode, as confirmed by the contrast between step-independent collapse (exp026, exp028c: 0\% success) and episode-level stability (exp029: 28.125\% validation success from a 12.5\% baseline).
76	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "1ca51beb-95f9-42e7-8703-79d9d4e39e61",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/theoretical_analysis.tex",
      "content": "\\section{Theoretical Analysis}\n\\label{sec:theory}\n\nSection~\\ref{sec:dual_mechanism} identified two failure mechanisms of step-independent training: policy information loss and advantage sign misattribution. We now formalize why sign misattribution is the more fundamental failure, derive the probability of incorrect gradient direction as a function of task success rate, examine why the community has defaulted to step-independent training, and connect our findings to the classical credit assignment literature.\n\n\\subsection{Why Sign Misattribution is Fundamental}\n\\label{sec:sign_fundamental}\n\nThe two mechanisms identified in Section~\\ref{sec:dual_mechanism} produce qualitatively different optimization errors. Policy information loss (Mechanism 1) reduces the information available to each window's policy, producing suboptimal but directionally reasonable gradient updates. Sign misattribution (Mechanism 2) corrupts the gradient direction itself. We formalize this distinction below.\n\n\\textbf{Proposition 1.} \\textit{Under step-independent training with binary episode reward $R_{\\text{episode}} \\in \\{0, r_+\\}$, the probability that window $k$'s advantage $\\hat{A}_k$ has the correct sign (aligned with local action quality) approaches the base success rate $p$ as the number of rollouts $K$ per group increases.}\n\n\\textit{Argument.} Define ``correct sign'' as follows: for a window containing locally beneficial actions, the correct sign of $\\hat{A}_k$ is positive (reinforcement); for a window containing locally detrimental actions, the correct sign is negative (suppression). Under binary reward, the return for window $k$ is $R_k = \\gamma^{(N-k)} \\cdot R_{\\text{episode}}$ (Equation~\\ref{eq:step_return}). In a failed episode ($R_{\\text{episode}} = 0$), all windows receive $R_k = 0$ regardless of their local action quality. If the group contains at least one successful rollout, the group mean $\\mu > 0$, and all windows in the failed episode receive negative advantages after normalization via Equation~\\ref{eq:grpo_advantage}. This includes windows where the agent took locally correct actions, such as correctly identifying a target object in an exploration step. Now consider a window with good local actions. In a successful episode (probability $p$), the window receives positive $\\hat{A}_k$, which is the correct sign. In a failed episode (probability $1 - p$), the window receives negative $\\hat{A}_k$ whenever $\\mu > 0$, which is the wrong sign. The probability that $\\mu = 0$ (all $K$ rollouts in the group failed) is $(1-p)^K$, which shrinks exponentially with $K$. As $K$ grows, nearly every failed episode produces a non-zero group mean, and the window receives the wrong sign with probability approaching $1-p$. The probability of correct sign therefore approaches $p$. \\qed\n\nThe distinction between sign error and magnitude error clarifies why Mechanism 2 is catastrophic while Mechanism 1 is merely suboptimal. The discount factor $\\gamma^{(N-k)}$ in Equation~\\ref{eq:step_return} introduces magnitude decay across window positions: for an episode with $T=50$ steps and $h=2$, the first window ($k=1$) retains $\\gamma^{N-1} = 0.95^{24} \\approx 0.29$ of the terminal window's return. This attenuation reduces the gradient magnitude for early windows but preserves the gradient direction. A gradient with correct sign and reduced magnitude produces slow convergence, a condition recoverable through longer training. A gradient with wrong sign produces active divergence: the optimization pushes the policy away from good behaviors and toward bad ones. Consider a navigation analogy. Magnitude error corresponds to a compass that points correctly but displays a dimmed needle; the traveler moves slowly toward the destination. Sign error corresponds to a compass pointing in the opposite direction; the traveler walks away from the destination with full confidence. The first error is correctable by patience. The second is correctable only by replacing the compass.\n\n\\subsection{Formal Probability Analysis}\n\\label{sec:formal_probability}\n\nWe derive a tighter bound on the probability of correct gradient direction as a function of task difficulty and group size.\n\n\\textbf{Proposition 2.} \\textit{Let $p$ denote the episode success rate and $K$ the number of rollouts per group. Under step-independent training with binary episode reward, the probability that a gradient update for a window with locally good actions has the correct sign satisfies:}\n\\begin{equation}\nP(\\text{correct sign or no update}) = p + (1-p)^{K}\n\\label{eq:correct_bound}\n\\end{equation}\n\\textit{Among gradient updates that occur (non-zero advantage), the fraction with correct sign is:}\n\\begin{equation}\nP(\\text{correct} \\mid \\text{update}) = \\frac{p}{1 - (1-p)^{K}}\n\\label{eq:correct_conditional}\n\\end{equation}\n\n\\textit{Derivation.} For a window with locally good actions, the gradient direction depends on $\\text{sign}(\\hat{A}_k)$, which depends on whether the episode succeeded and whether the group contains any successful rollouts. Three mutually exclusive cases arise.\n\n\\textit{Case 1: Episode succeeded} (probability $p$). The window receives $R_k = \\gamma^{(N-k)} \\cdot r_+ > 0$. With at least one failed rollout in the group, $R_k > \\mu$ after normalization, producing $\\hat{A}_k > 0$. The gradient reinforces the window's actions. For a window with good local actions, this is the correct direction.\n\n\\textit{Case 2: Episode failed, group contains at least one success} (probability $(1-p)[1 - (1-p)^{K-1}]$). The window receives $R_k = 0 < \\mu$, producing $\\hat{A}_k < 0$. The gradient suppresses the window's actions. For a window with good local actions, this is the wrong direction.\n\n\\textit{Case 3: Episode failed, entire group failed} (probability $(1-p) \\cdot (1-p)^{K-1} = (1-p)^{K}$). All returns are zero, so $\\mu = 0$ and $\\sigma = 0$. The advantage is zero, producing no gradient update.\n\nSumming Cases~1 and~3 yields Equation~\\ref{eq:correct_bound}. Since only Cases~1 and~2 produce non-zero gradients, the conditional probability follows as Equation~\\ref{eq:correct_conditional}.\n\nWe evaluate these expressions at the empirical baseline of our experiments. At $p = 6.25\\%$ (the pre-training success rate) and $K = 8$ (the group size used in all experiments): $(1-p)^K = 0.9375^8 \\approx 0.60$, giving $P(\\text{correct or no update}) \\approx 0.66$. Of the 40\\% of cases that produce a gradient update, only $P(\\text{correct} \\mid \\text{update}) = 0.0625 / 0.404 \\approx 15.5\\%$ have the correct sign. As $K$ increases to 16, $(1-p)^{K} \\approx 0.36$, and $P(\\text{correct} \\mid \\text{update}) \\approx 9.8\\%$. In the large-$K$ limit, $P(\\text{correct} \\mid \\text{update}) \\to p$, so approximately $1 - p \\approx 94\\%$ of all gradient updates for locally good windows point in the wrong direction. This is consistent with the empirical observation that step-independent training collapses to 0\\% task success (exp026, exp028c) while episode-level training achieves stable improvement (exp029, 28.125\\% validation success at step 15).\n\n\\subsection{Why the Community Defaults to Step-Independent Training}\n\\label{sec:why_defaults}\n\nIf step-independent training is fundamentally flawed for multi-turn agents, why has it become the default? We identify six contributing factors.\n\n\\textbf{1. Context window constraints.} Smaller language models (1B to 4B parameters) typically support context windows of 2048 to 4096 tokens. Multi-turn episodes spanning 50 or more interaction steps easily exceed these limits. Step-independent windowing is a pragmatic response to a hardware constraint, not a deliberate algorithmic choice.\n\n\\textbf{2. Token-level training inertia.} Language model training is organized around predicting the next token over fixed-length sequences. When multi-turn RL inherits this paradigm, the natural unit of optimization becomes a fixed-length window rather than a variable-length episode. The mismatch between token-level optimization and episode-level credit assignment goes unquestioned because it aligns with existing training infrastructure.\n\n\\textbf{3. Framework design accident.} The RAGEN framework~\\cite{ragen2025} implements step-independent mode as its default configuration, not as one option among alternatives. Users inherit this choice without an explicit decision point, and default configurations propagate silently through downstream projects.\n\n\\textbf{4. Memory and compute constraints.} Episode-level training requires processing $O(T)$ tokens per sequence, incurring $O(T^2)$ attention cost with full self-attention. Step-independent training reduces this to $O(h)$ tokens and $O(h^2)$ attention cost per window. The computational savings are immediate and measurable, while the credit assignment failure is subtle and deferred until training collapse occurs.\n\n\\textbf{5. Reward shaping as apparent fix.} Dense reward shaping (per-step bonuses for intermediate goals) appears to address sparse reward problems and has theoretical support in the single-agent RL literature. Our experiment with dense rewards under step-independent training (exp013f) reveals a different failure mode: the agent learns to maximize format-level rewards (action validity rises from 60\\% to 97.5\\%) while task success remains at 0\\%. Reward shaping does not resolve sign misattribution; it creates new optimization targets that the agent can game without solving the underlying task.\n\n\\textbf{6. Absence of negative results.} When step-independent training fails, practitioners attribute the failure to insufficient hyperparameter tuning or the inherent difficulty of sparse rewards. Without published analyses that isolate the credit assignment mechanism as the root cause, the community cannot distinguish between ``this problem is hard'' and ``this training paradigm is broken for this class of problems.''\n\n\\subsection{Connection to Classical Credit Assignment}\n\\label{sec:classical_connection}\n\nOur findings connect to a long line of work on temporal credit assignment in reinforcement learning. We position the step-independent failure mode within this literature and clarify the contribution of our analysis.\n\n\\textbf{Temporal difference learning and eligibility traces.} Sutton's TD($\\lambda$)~\\cite{sutton1988td} provides a spectrum of credit assignment strategies parameterized by $\\lambda \\in [0,1]$. At $\\lambda = 0$, credit is assigned via one-step bootstrapped returns. At $\\lambda = 1$, TD($\\lambda$) reduces to Monte Carlo returns, where each state receives the full episode return. Step-independent training falls below this spectrum: windows are disconnected from each other, so temporal propagation of credit does not occur. Each window receives an independently computed advantage with no mechanism for information to flow across windows within the same episode.\n\n\\textbf{Generalized Advantage Estimation.} GAE($\\lambda, \\gamma$)~\\cite{schulman2016gae} extends TD($\\lambda$) with a separate discount factor for the advantage estimator. GAE(0, $\\gamma$) produces per-step advantages through a learned value function. GAE(1, 1) produces undiscounted Monte Carlo returns, and is equivalent to episode-level GRPO without a critic. The key difference is that GAE uses value function subtraction as the baseline for variance reduction, while GRPO uses group normalization. Episode-level GRPO can be viewed as GAE(1, 1) with a group-relative baseline replacing the learned value function. This substitution is effective when the group provides a representative reference distribution, but it does not address per-step credit assignment within an episode.\n\n\\textbf{REINFORCE.} Williams' REINFORCE algorithm~\\cite{williams1992reinforce} computes policy gradients from complete episode returns with a learned baseline $b(s)$. Episode-level GRPO is equivalent to REINFORCE where the group mean $\\mu$ replaces $b(s)$ and the group standard deviation $\\sigma$ provides normalization. The algorithmic structure is not new. Our contribution is the diagnosis: the community's standard adaptation of this algorithm for multi-turn LLM agents (step-independent windowing) silently breaks the credit assignment structure that REINFORCE assumes.\n\n\\textbf{Multi-agent credit assignment analogy.} Step-independent windows can be understood through cooperative multi-agent games. Each window acts as an independent ``agent'' sharing a team reward (the episode outcome) but optimized without knowledge of other windows' actions. The sign misattribution problem parallels team reward credit assignment in cooperative multi-agent RL: when the team fails, all agents receive identical penalties regardless of individual contribution. In multi-agent RL, this is a recognized problem with known solutions such as counterfactual baselines. In multi-turn LLM agent training, the same structural problem arises from an implementation choice and has not been recognized as a credit assignment failure.\n\nTo summarize our positioning: we do not propose a new credit assignment algorithm. Episode-level training is the standard approach, and GRPO was designed as an episode-level method. What we identify is that the community's adaptation of GRPO to multi-turn settings introduces a systematic sign error in gradient computation. This error is not a gradual performance degradation but a catastrophic failure mode, as confirmed by the contrast between step-independent collapse (exp026, exp028c: 0\\% success) and episode-level stability (exp029: 28.125\\% validation success from a 12.5\\% baseline).\n",
      "numLines": 76,
      "startLine": 1,
      "totalLines": 76
    }
  }
}
```

</details>

---

### Assistant

_source line 13_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the context I need. Let me also check if the target directory exists and if there's any existing content.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "2a087cfa-cdc6-4cc2-825f-797ce0e9c40d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qrz1g9JdEA3LADYdL6bb13",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18034,
      "cache_read_input_tokens": 26782,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18034
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

_source line 14_

Now let me check the target directory and look for any existing abstract or related content to ensure consistency.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "57f83599-61a5-4384-99bb-9efd61159082",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qrz1g9JdEA3LADYdL6bb13",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18034,
      "cache_read_input_tokens": 26782,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18034
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

_source line 15_

<details open><summary>🔧 Tool call — Bash · `toolu_01QywLDGLg1n5wJ3YJeiy9Uv`</summary>

```json
{
  "command": "mkdir -p /home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper && ls /home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/",
  "description": "Ensure paper directory exists and list contents"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "3986ae0f-33e8-4ce3-8021-91d813981955",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qrz1g9JdEA3LADYdL6bb13",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18034,
      "cache_read_input_tokens": 26782,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18034
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

_source line 16 · 2026-05-17T07:51:20.747Z_

<details><summary>↩ Tool result · `toolu_01QywLDGLg1n5wJ3YJeiy9Uv`</summary>

```text
method.tex
theoretical_analysis.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "de12dd90-9cd8-42f1-9b82-46b333d6e2ef",
  "tool_use_result": {
    "stdout": "method.tex\ntheoretical_analysis.tex",
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

_source line 17_

<details><summary>Logged reasoning block</summary>

```text
Good, the directory exists and I see the method.tex and theoretical_analysis.tex files I already read. Now let me write the introduction.

Let me carefully craft the Introduction following the 5-paragraph structure specified in the task, while adhering to all style rules (no em-dash, no -ing endings, no AI-style phrases, etc.).

Key notation from method.tex:
- T: episode length
- h: window size
- γ: discount factor
- Â_k: advantage of window k
- R_k: return of window k
- π_φ: agent policy
- N = ⌈T/h⌉: total windows


- 
Now I'm reviewing the key experimental results to understand what worked and what didn't. The episode-level approach showed promise with 28.125% validation success, while the step-independent variants struggled significantly, with one collapsing entirely by step 4. The dense reward approach inflated the validity metric without improving actual success, which suggests the core challenge isn't about action validity but something deeper in the learning signal.

For the paper structure, I need to establish why multi-turn RL is necessary since supervised learning alone can't handle the compositional planning required across 30-50 step episodes, then position GRPO as the current standard while citing the recent work in this space. The critical insight is that step-independent training, despite seeming practical, has fundamental credit assignment problems that cause catastrophic collapse—and this isn't just a tuning issue but a structural limitation worth investigating. I'm setting up the introduction by establishing that LLM agents need RL for long-horizon tasks since supervised learning alone can't capture the trial-and-error discovery process, and GRPO has emerged as a promising approach for this problem.

Now I'm moving into the core issue: current frameworks use step-independent training that partitions trajectories into fixed windows, which is practical for fitting within context limits and increasing effective batch size, but this design choice hasn't been carefully examined.

The problem is that when each window gets a return signal based on the overall episode outcome, the advantage estimates reflect whether the episode succeeded globally, not whether the window's actions were locally appropriate. My experiments show this causes a dramatic failure mode—task success collapses to nearly 0% within 10 training steps while action validity stays above 90%, meaning the agent learns to produce syntactically correct actions but loses the ability to actually complete tasks. This isn't a hyperparameter tuning issue; I see the same collapse pattern across different learning rates, KL penalties, and window sizes, which points to a fundamental structural problem with how the training paradigm decomposes trajectories.

Standard approaches like dense reward shaping don't fix this collapse.  When I add per-step bonuses for intermediate goals, the agent just maximizes those format-level rewards while ignoring task completion—action validity jumps to 97.5% but task success stays at 0%. Increasing rollouts or adjusting the KL penalty only delays the failure. Even more sophisticated methods like GAE and PPO, which use learned value functions for better credit assignment, haven't been applied with a clear understanding of why step-independent training fundamentally breaks. The real issue isn't the RL algorithm choice but the windowing approach itself, which corrupts the credit signal at its source.

I'm identifying two core mechanisms driving this collapse. Policy information loss happens because each window operates in isolation—it can't see actions or outcomes from other windows, so strategies that depend on earlier results become invisible to optimization. The second mechanism, advantage sign misattribution, is even more destructive. When the episode reward is binary, each window's advantage sign depends entirely on whether the episode succeeded or failed overall. This means good actions in failed episodes get negative advantages and get suppressed, while bad actions in successful episodes get positive advantages and get reinforced. My formal analysis shows this effect becomes increasingly severe as the baseline success rate changes.

Episode-level GRPO fixes both problems by treating the entire trajectory as a single sample, which aligns with how the algorithm was originally designed. Since all steps now share one advantage computed from the full episode return, the per-window return assignment that causes sign misattribution disappears. Cross-step dependencies are also preserved because the optimization process has access to the complete interaction history. The experimental results bear this out—episode-level training reaches 28.1% validation success at step 15 and improves steadily from the 12.5% baseline, whereas step-independent training completely collapses to 0%.

Now I'm laying out the key contributions: first, identifying and formalizing the two failure mechanisms—policy information loss and advantage sign misattribution—and proving that sign misattribution is fundamentally a directional error whose probability of pointing the wrong way approaches $1 - p$ as group size increases. Second, validating this through window-size ablations and per-window advantage logging to show the credit assignment cliff and direct evidence of the sign misattribution mechanism. Third, proposing the episode-level solution. I'm catching a few style issues in my previous section—specifically that -ing phrase ending where I wrote "establishing multi-turn agent training as an active research frontier," which breaks the no-dash-before-ing-phrase rule. I should also double-check for consecutive transitional words and make sure the paragraph lengths are balanced, since some are running a bit short and could use slight expansion to hit a more consistent word count across sections.

Now I'm verifying the section references for each contribution claim—mapping them to the actual LaTeX labels in the method and theoretical analysis files so the citations are accurate, and for the experimental sections that might not exist yet, I'll use a general experiments reference instead.

I'm also refining the language to eliminate awkward gerund constructions and tighten the word counts across each paragraph, then revising the introduction section itself to strengthen the opening on multi-turn agent training challenges. I'm working through the structural requirements for this paper—it needs five sections with specific word count targets, and I should focus on hitting the narrative points rather than obsessing over exact counts. I also need to make sure the final output is just the section content without any LaTeX preamble, and I'm being careful to avoid ending phrases with participles like "highlighting" or "demonstrating."

Let me scan through my draft one more time to catch any of those forbidden -ing constructions at sentence ends, then I'll check that my notation is consistent with the other sections—using $\pi_\phi$ for policy, $h$ for window size, $T$ for episode length, and so on.

I've already got $p = 6.25\%$ and $K = 8$ matching what's in theoretical_analysis.tex, which is good. Now I need to verify I'm citing the right papers with the correct bibtex keys: shao2024deepseekmath for GRPO, ragen2025 for RAGEN, selfguide2026 for Self-Guide, and schulman2017ppo for PPO.

I've got most of the citations lined up—GAE, REINFORCE, GiGPO, SPEAR, DigiRL, and ReflAct all have their keys ready. The Self-Verification Dilemma paper probably isn't necessary for the intro since the method section handles selective verification separately.

Let me draft the final version now, keeping it tight and following the notation rules.

Actually, I need to look at the method structure more carefully. The paper's organized with Problem Formulation, then GRPO for Language Agents, Step-Independent Implementation, and the dual mechanism analysis that breaks down M1 and M2. After that comes Episode-Level Training and Selective Verification. The theoretical analysis section covers why sign misattribution matters, the formal probability work, why the community gravitates toward step-independent approaches, and connections back to classical credit assignment. So my first contribution ties to sections 3.4, 4.1, and 4.2, while the second one points to the experiments section that I haven't written yet.

For the third contribution, I'm looking at sections 3.5, 4.3, and 4.4. The experiments reference \ref{sec:experiments} and \ref{sec:selective_experiments}, so I should use those labels. The task notes that the h-sweep data is still pending, so I should use "we demonstrate" rather than specific numbers. Let me draft the introduction section with proper LaTeX references.

Now I'm continuing with the motivation for why RL-based approaches like GRPO are necessary—SFT alone can't teach compositional planning because it lacks the exploration that emerges through trial-and-error. Recent work has applied these methods across various interactive domains, and they all share a common challenge that I need to articulate.

The standard approach in these frameworks decomposes long trajectories into fixed-size windows and trains each independently, which seems efficient for fitting within context limits and increasing effective batch size. But this decomposition creates a critical problem: when each window gets group-normalized advantages, those advantages reflect the overall episode outcome rather than whether the actions within that specific window were actually correct. This is the credit assignment issue I'm investigating.

The experiments reveal a stark failure mode—step-independent training drops to 0% task success within just 10 steps while maintaining over 90% action validity, meaning the agent learns to produce syntactically valid commands but completely loses the ability to accomplish the actual task. This isn't a hyperparameter sensitivity issue; the collapse appears consistently across different learning rates, KL penalties, and window sizes, pointing to a fundamental structural problem. Even standard fixes like dense reward shaping backfire—when I add per-step bonuses for intermediate goals like valid formatting, the agent optimizes those local rewards while ignoring task completion entirely, pushing action validity up to 97.5% while task success stays at 0%. Adjusting rollout counts or KL penalties can delay the collapse but doesn't prevent it.

The real issue isn't the RL algorithm itself—it's the step-independent windowing approach, which breaks the credit assignment signal at its source. I'm identifying two mechanisms driving this failure. First, policy information loss occurs because each window operates in isolation, unable to see actions and outcomes from other windows, so any strategy requiring cross-step conditioning becomes invisible to the optimizer. Second, and more critical, is advantage sign misattribution: under binary episode rewards, whether a window's advantage is positive or negative depends entirely on whether the episode succeeded or failed overall, not on what that particular window actually contributed.

This means good actions in failed episodes get penalized while bad actions in successful episodes get rewarded—a directional error that actively pushes the policy away from correct behaviors. My formal analysis shows that at a 6.25% baseline success rate with 8 windows, roughly 84.5% of gradient updates for locally correct windows point the wrong way. Episode-level GRPO fixes both problems by treating the entire trajectory as a single sample, so all steps share one advantage signal computed from the final return, and the full interaction history preserves cross-step dependencies. In experiments, this approach reaches 28.1% validation success compared to the step-independent baseline.

Now I'm outlining the key contributions: first, identifying and formalizing the two failure mechanisms—policy information loss and advantage sign misattribution—and proving that sign misattribution creates a directional error where incorrect gradient probability approaches 1 minus the success rate as group size increases. Second, I'm validating this empirically through window-size ablations and per-window advantage logging to show the credit assignment cliff and provide direct evidence for the sign misattribution mechanism.

Finally, I'm presenting episode-level GRPO as the solution that addresses both failure modes simultaneously, connecting it to classical methods like GAE and REINFORCE, and explaining six factors that led the community to adopt the broken step-independent approach. I'm checking whether "rather than merely slowing convergence" violates the no-gerund-ending rule, and it doesn't—it's a comparison clause, not a participial modifier at the end of a sentence, so I'll keep it as is.

Now I'm verifying the rest of my style constraints: no consecutive transition words, no "It is worth noting," no vague language like "leverage" or "facilitate," and no "remarkable success" or "To the best of our knowledge." Checking paragraph lengths, the first three are solid at 6-8 sentences each, but the fourth paragraph is running long at around 9 sentences, so I should tighten it up. We trace the collapse to two key mechanisms: policy information loss, where each window can't see actions from other windows, and advantage sign misattribution, where the sign of each window's advantage is determined by overall episode success rather than local action quality. This means good actions in failed episodes get suppressed while bad actions in successful episodes get reinforced—at a 6.25% baseline success rate with group size 8, about 84.5% of gradient updates point the wrong direction. Episode-level GRPO fixes both by treating the full trajectory as one sample, preserving cross-step dependencies and computing a single advantage from the episode return, which in our experiments achieves substantial improvements. I'm verifying that I've grounded the narrative in the specific experimental results—checking that each key finding maps back to the right experiment and that I'm using the data to support the argument rather than just listing numbers. I'm refining the practical motivation in paragraph 2—restructuring it to flow better by embedding the short sentence into a longer clause that explains why this design choice makes sense for handling long trajectories and effective batch sizes. For paragraph 1, my opening already captures the specific problem concretely: multi-turn tasks require composing actions across 30-50 steps, which is exactly what the task asked for rather than generic statements about LLM capabilities.

I'm also verifying that all key acronyms are properly defined on first use—GRPO, SFT, PPO, GAE, and RL all have their full forms introduced, which keeps the writing accessible. There's one lingering issue with a gerund phrase that's making a sentence awkward, but I'll address that as I finalize. I'm explaining why supervised fine-tuning alone isn't sufficient for multi-step planning, then introducing how reinforcement learning and GRPO address this limitation across various agent domains. The key insight is that most RL frameworks use a common but underexamined approach: breaking trajectories into fixed-size windows and training each independently, which is what I'm analyzing here.

The problem with this window-based decomposition is that it creates a credit assignment failure—each window's advantage signal reflects the overall episode outcome rather than whether those specific actions were correct. This leads to a catastrophic failure mode where agents learn syntactically valid actions but completely lose task completion ability, dropping to near-zero success within just a few training steps despite maintaining high action validity.

I've tested whether this is just a hyperparameter issue by varying learning rates, KL penalties, and window sizes, but the collapse happens consistently across all configurations. Standard fixes don't work either—dense reward shaping just shifts the problem, making the agent optimize for action formatting while ignoring the actual task, and adjusting rollouts or penalties only delays the inevitable failure. More sophisticated methods like GAE or PPO could provide better temporal credit assignment, but they require understanding the fundamental mechanism driving this step-independent training failure in the first place.

The real issue isn't the algorithm choice—it's the step-independent windowing approach itself, which breaks credit assignment at its foundation. Two mechanisms are at play. First, policy information loss: each window operates in isolation without seeing actions or outcomes from other windows, so any strategy requiring cross-step conditioning becomes invisible to the optimizer. Second and more critical, advantage sign misattribution: when episodes have binary rewards, each window's advantage sign depends entirely on whether the episode succeeded or failed overall, not on the quality of that window's actions. This means good actions in failed episodes get penalized while bad actions in successful episodes get reinforced. The math bears this out—at a 6.25% baseline success rate with 8 windows per episode, roughly 84.5% of gradient updates are pushing in the wrong direction.

Episode-level training fixes both problems by treating the entire trajectory as one sample, preserving cross-step dependencies and computing a single advantage shared across all steps. The empirical gap is stark: episode-level achieves 28.1% validation success versus 0% for step-independent training. The key insight is that sign misattribution isn't just slowing convergence—it's actively pushing the policy away from correct behaviors, a directional error fundamentally different from magnitude attenuation. I need to point out that the "current rewritten thinking" you've provided appears to be LaTeX/academic paper content with editorial notes about sentence counts and compression strategies. This doesn't look like Claude's actual thinking that needs rewriting.

Could you clarify what you'd like me to do? It seems like:

1. You may have accidentally pasted academic paper content instead of Claude's thinking
2. Or you're asking me to rewrite the editorial notes themselves into natural thinking

If you have actual Claude thinking (the kind generated when answering a user's question) that you'd like me to rewrite, please share that and I'll compress it into 1-3 sentences of natural first-person prose. I see that the next thinking continues the explanation about how episode-level GRPO resolves both mechanisms by treating the full trajectory as one sample, preserving cross-step dependencies. It then notes the experimental results showing the dramatic difference between episode-level training (28.1% success) and step-independent training (0% collapse). The thinking then reflects on being satisfied with the explanation and ready to finalize it.

Since your current rewritten thinking already covers the core mechanisms and analysis, I'll compress the continuation:

Episode-level GRPO fixes both issues by optimizing the complete trajectory as a single sample, preserving cross-step dependencies and ensuring all steps share one advantage signal—this approach achieves 28.1% validation success compared to the 0% collapse of step-independent training.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "710b73e6-edb8-4cc9-9d62-08ee95b5f51a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QYgLxUZ3sWvSUAwoc4GoPh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 232,
      "cache_read_input_tokens": 44816,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 232
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

_source line 18_

Now I'll write the Introduction section.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "3ab32418-80cf-4ac8-9836-96e3d85171c9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QYgLxUZ3sWvSUAwoc4GoPh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 232,
      "cache_read_input_tokens": 44816,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 232
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

_source line 19_

<details open><summary>🔧 Tool call — Write · `toolu_019m7vtzpDXSNU4nLiZWiFuW`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/introduction.tex",
  "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nTraining Large Language Model (LLM) agents for multi-turn interactive tasks poses a fundamental challenge: policies must compose actions across 30 to 50 interaction steps in environments such as household navigation~\\cite{kim2025reflact}, web interaction~\\cite{digiRL2024}, and scientific experimentation. Supervised fine-tuning (SFT) can teach action formatting but fails to instill compositional planning, because expert demonstrations do not expose the trial-and-error exploration through which effective multi-step strategies emerge. Reinforcement learning (RL) addresses this gap by optimizing policies through direct environment interaction, and Group Relative Policy Optimization (GRPO)~\\cite{shao2024deepseekmath} has become a preferred method due to its critic-free design and direct compatibility with language model architectures. Recent work applies RL-based training to interactive agents across diverse domains, from text-based games~\\cite{ragen2025} and GUI interaction~\\cite{digiRL2024} to tool use~\\cite{spear2025} and instruction following~\\cite{selfguide2026,feng2025gigpo}. These efforts share a common implementation pattern that has received little scrutiny: the multi-turn trajectory is decomposed into fixed-size windows, and each window is optimized as an independent training sample. This decomposition is the focus of our analysis.\n\nCurrent agent RL frameworks default to \\textit{step-independent training}: the trajectory is partitioned into non-overlapping windows of $h$ consecutive steps, each receiving a discounted return derived from the binary episode outcome and optimized independently via GRPO~\\cite{ragen2025,selfguide2026}. This choice is motivated by practical considerations: it fits long trajectories within limited context windows, multiplies the effective batch size, and aligns with the token-level training paradigm of language models. However, the decomposition introduces a fundamental credit assignment pathology. When each window receives a group-normalized advantage, the sign of that advantage reflects whether the \\textit{episode} succeeded or failed, not whether the \\textit{window's actions} were locally correct. In our experiments, this pathology produces a striking failure pattern: step-independent training collapses to 0\\% task success within 10 training steps, while action validity remains above 90\\% (Section~\\ref{sec:experiments}). The agent learns to produce well-formatted commands that satisfy syntactic constraints but loses the ability to complete tasks entirely. This collapse is not an artifact of a particular hyperparameter configuration. We observe the same failure across multiple learning rates, KL penalty strengths, and window sizes, consistent with a structural defect in the training paradigm rather than a tuning problem.\n\nStandard remedies do not resolve this collapse. Dense reward shaping, which provides per-step bonuses for intermediate goals such as valid action formatting, creates a different failure mode: the agent maximizes format-level rewards while task completion stays at zero. In our dense reward experiment, action validity increases from 60\\% to 97.5\\% while task success remains at 0\\% (Section~\\ref{sec:experiments}). Increasing the number of rollouts or adjusting the KL penalty delays the onset of collapse but does not prevent it. Generalized Advantage Estimation (GAE)~\\cite{schulman2016gae} and Proximal Policy Optimization (PPO)~\\cite{schulman2017ppo} offer finer-grained temporal credit assignment through learned value functions, but they add model complexity and have not been applied with a diagnosis of \\textit{why} step-independent training fails in the first place. The root cause is not the choice of RL algorithm. It is the step-independent windowing itself, which corrupts the credit assignment signal at its source.\n\nWe trace the collapse to two mechanisms that operate jointly under step-independent training. The first, \\textbf{policy information loss}, arises because each $h$-step window has no access to actions and outcomes from other windows, so cross-step strategies that require conditioning on earlier results become invisible to the optimization process. The second, \\textbf{advantage sign misattribution}, is more damaging: under binary episode reward, the sign of each window's advantage $\\hat{A}_k$ is determined by whether the episode succeeded or failed (Section~\\ref{sec:m2_sign_misattribution}), not by the local quality of the window's actions. Good actions in failed episodes receive negative advantages and are actively suppressed, while bad actions in successful episodes are reinforced. Our formal analysis (Section~\\ref{sec:formal_probability}) shows that at a baseline success rate of $p = 6.25\\%$ with group size $K = 8$, approximately 84.5\\% of gradient updates for locally correct windows point in the wrong direction. Sign misattribution is a directional error, fundamentally distinct from magnitude attenuation: it drives the policy away from correct behaviors rather than merely reducing convergence speed. Episode-level GRPO eliminates both mechanisms by treating the complete trajectory as a single optimization sample, consistent with GRPO's original design~\\cite{shao2024deepseekmath}, so that all steps share one advantage and cross-step dependencies are preserved through the full interaction history. In our experiments, episode-level training achieves 28.1\\% validation success (from a 12.5\\% baseline), while step-independent training collapses to 0\\%.\n\nOur contributions are as follows:\n\\begin{itemize}\n    \\item \\textbf{Dual mechanism diagnosis.} We identify and formalize two mechanisms that cause catastrophic collapse under step-independent GRPO in multi-turn agent training: policy information loss and advantage sign misattribution. We show that sign misattribution is a directional error, with the probability of incorrect gradient direction approaching $1 - p$ as group size grows (Sections~\\ref{sec:dual_mechanism},~\\ref{sec:sign_fundamental},~\\ref{sec:formal_probability}).\n\n    \\item \\textbf{Systematic empirical validation.} Through window-size ablation ($h \\in \\{2, 5, 10, 20, \\text{full}\\}$) and per-window advantage logging, we demonstrate a credit assignment cliff and provide direct empirical evidence for the sign misattribution mechanism (Section~\\ref{sec:experiments}).\n\n    \\item \\textbf{Episode-level solution and analysis.} We show that episode-level GRPO simultaneously resolves both failure mechanisms, and we analyze its connection to GAE~\\cite{schulman2016gae} and REINFORCE~\\cite{williams1992reinforce}. We identify six factors that explain why the community has defaulted to the broken step-independent paradigm (Sections~\\ref{sec:episode_level},~\\ref{sec:classical_connection},~\\ref{sec:why_defaults}).\n\\end{itemize}\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "50e997ae-e230-47a9-96d1-7b27e8288e21",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QYgLxUZ3sWvSUAwoc4GoPh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 232,
      "cache_read_input_tokens": 44816,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 232
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

_source line 20 · 2026-05-17T07:54:41.740Z_

<details><summary>↩ Tool result · `toolu_019m7vtzpDXSNU4nLiZWiFuW`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/introduction.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "d4d3d6ce-1b50-485c-800a-a7e62dbe7650",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/introduction.tex",
    "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nTraining Large Language Model (LLM) agents for multi-turn interactive tasks poses a fundamental challenge: policies must compose actions across 30 to 50 interaction steps in environments such as household navigation~\\cite{kim2025reflact}, web interaction~\\cite{digiRL2024}, and scientific experimentation. Supervised fine-tuning (SFT) can teach action formatting but fails to instill compositional planning, because expert demonstrations do not expose the trial-and-error exploration through which effective multi-step strategies emerge. Reinforcement learning (RL) addresses this gap by optimizing policies through direct environment interaction, and Group Relative Policy Optimization (GRPO)~\\cite{shao2024deepseekmath} has become a preferred method due to its critic-free design and direct compatibility with language model architectures. Recent work applies RL-based training to interactive agents across diverse domains, from text-based games~\\cite{ragen2025} and GUI interaction~\\cite{digiRL2024} to tool use~\\cite{spear2025} and instruction following~\\cite{selfguide2026,feng2025gigpo}. These efforts share a common implementation pattern that has received little scrutiny: the multi-turn trajectory is decomposed into fixed-size windows, and each window is optimized as an independent training sample. This decomposition is the focus of our analysis.\n\nCurrent agent RL frameworks default to \\textit{step-independent training}: the trajectory is partitioned into non-overlapping windows of $h$ consecutive steps, each receiving a discounted return derived from the binary episode outcome and optimized independently via GRPO~\\cite{ragen2025,selfguide2026}. This choice is motivated by practical considerations: it fits long trajectories within limited context windows, multiplies the effective batch size, and aligns with the token-level training paradigm of language models. However, the decomposition introduces a fundamental credit assignment pathology. When each window receives a group-normalized advantage, the sign of that advantage reflects whether the \\textit{episode} succeeded or failed, not whether the \\textit{window's actions} were locally correct. In our experiments, this pathology produces a striking failure pattern: step-independent training collapses to 0\\% task success within 10 training steps, while action validity remains above 90\\% (Section~\\ref{sec:experiments}). The agent learns to produce well-formatted commands that satisfy syntactic constraints but loses the ability to complete tasks entirely. This collapse is not an artifact of a particular hyperparameter configuration. We observe the same failure across multiple learning rates, KL penalty strengths, and window sizes, consistent with a structural defect in the training paradigm rather than a tuning problem.\n\nStandard remedies do not resolve this collapse. Dense reward shaping, which provides per-step bonuses for intermediate goals such as valid action formatting, creates a different failure mode: the agent maximizes format-level rewards while task completion stays at zero. In our dense reward experiment, action validity increases from 60\\% to 97.5\\% while task success remains at 0\\% (Section~\\ref{sec:experiments}). Increasing the number of rollouts or adjusting the KL penalty delays the onset of collapse but does not prevent it. Generalized Advantage Estimation (GAE)~\\cite{schulman2016gae} and Proximal Policy Optimization (PPO)~\\cite{schulman2017ppo} offer finer-grained temporal credit assignment through learned value functions, but they add model complexity and have not been applied with a diagnosis of \\textit{why} step-independent training fails in the first place. The root cause is not the choice of RL algorithm. It is the step-independent windowing itself, which corrupts the credit assignment signal at its source.\n\nWe trace the collapse to two mechanisms that operate jointly under step-independent training. The first, \\textbf{policy information loss}, arises because each $h$-step window has no access to actions and outcomes from other windows, so cross-step strategies that require conditioning on earlier results become invisible to the optimization process. The second, \\textbf{advantage sign misattribution}, is more damaging: under binary episode reward, the sign of each window's advantage $\\hat{A}_k$ is determined by whether the episode succeeded or failed (Section~\\ref{sec:m2_sign_misattribution}), not by the local quality of the window's actions. Good actions in failed episodes receive negative advantages and are actively suppressed, while bad actions in successful episodes are reinforced. Our formal analysis (Section~\\ref{sec:formal_probability}) shows that at a baseline success rate of $p = 6.25\\%$ with group size $K = 8$, approximately 84.5\\% of gradient updates for locally correct windows point in the wrong direction. Sign misattribution is a directional error, fundamentally distinct from magnitude attenuation: it drives the policy away from correct behaviors rather than merely reducing convergence speed. Episode-level GRPO eliminates both mechanisms by treating the complete trajectory as a single optimization sample, consistent with GRPO's original design~\\cite{shao2024deepseekmath}, so that all steps share one advantage and cross-step dependencies are preserved through the full interaction history. In our experiments, episode-level training achieves 28.1\\% validation success (from a 12.5\\% baseline), while step-independent training collapses to 0\\%.\n\nOur contributions are as follows:\n\\begin{itemize}\n    \\item \\textbf{Dual mechanism diagnosis.} We identify and formalize two mechanisms that cause catastrophic collapse under step-independent GRPO in multi-turn agent training: policy information loss and advantage sign misattribution. We show that sign misattribution is a directional error, with the probability of incorrect gradient direction approaching $1 - p$ as group size grows (Sections~\\ref{sec:dual_mechanism},~\\ref{sec:sign_fundamental},~\\ref{sec:formal_probability}).\n\n    \\item \\textbf{Systematic empirical validation.} Through window-size ablation ($h \\in \\{2, 5, 10, 20, \\text{full}\\}$) and per-window advantage logging, we demonstrate a credit assignment cliff and provide direct empirical evidence for the sign misattribution mechanism (Section~\\ref{sec:experiments}).\n\n    \\item \\textbf{Episode-level solution and analysis.} We show that episode-level GRPO simultaneously resolves both failure mechanisms, and we analyze its connection to GAE~\\cite{schulman2016gae} and REINFORCE~\\cite{williams1992reinforce}. We identify six factors that explain why the community has defaulted to the broken step-independent paradigm (Sections~\\ref{sec:episode_level},~\\ref{sec:classical_connection},~\\ref{sec:why_defaults}).\n\\end{itemize}\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
```

</details>

---

### Assistant

_source line 21_

Let me verify the file is clean (no em-dashes, no -ing phrase endings).

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "98800ef7-e291-4569-be8c-eb0a48afb117",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016i6RYuLqbnucywBcNzvcQ7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12515,
      "cache_read_input_tokens": 45048,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12515
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

_source line 22_

<details open><summary>🔧 Tool call — Bash · `toolu_01VLZ6qpFoTbdTZnHNzDUpEz`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper && grep -n \"—\" introduction.tex; grep -n \" – \" introduction.tex; grep -c \"ing,\" introduction.tex; echo \"---word count---\"; wc -w introduction.tex",
  "description": "Check for banned em-dash, en-dash, and -ing patterns; count words"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "ed7696ae-e598-41e0-8877-96086b36c490",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016i6RYuLqbnucywBcNzvcQ7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12515,
      "cache_read_input_tokens": 45048,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12515
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

_source line 23 · 2026-05-17T07:54:47.696Z_

<details><summary>↩ Tool result · `toolu_01VLZ6qpFoTbdTZnHNzDUpEz`</summary>

```text
3
---word count---
850 introduction.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "e3f30e44-91a6-40c0-bb47-b8f11b35fff8",
  "tool_use_result": {
    "stdout": "3\n---word count---\n850 introduction.tex",
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

_source line 24_

<details><summary>Logged reasoning block</summary>

```text
The grep for em-dash and en-dash returned no matches (no lines printed). The `grep -c "ing," introduction.tex` returned 3. Let me check what those are.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "04927e96-7c10-4fa0-b953-e08b31b42f0c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XMXCM6Aj8i7q7XtepN9S7V",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 313,
      "cache_read_input_tokens": 57563,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 313
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

3 matches for `ing,` pattern. Let me check them.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "9e4f4637-739d-490a-91ad-5aee9685f10b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XMXCM6Aj8i7q7XtepN9S7V",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 313,
      "cache_read_input_tokens": 57563,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 313
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

<details open><summary>🔧 Tool call — Bash · `toolu_01LZFjd62LDpQyy5PksvHQ2G`</summary>

```json
{
  "command": "grep -n \"ing,\" /home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/introduction.tex",
  "description": "Show lines with -ing comma pattern"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "f9a9285d-b84f-41c9-ad9a-3052f3322258",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XMXCM6Aj8i7q7XtepN9S7V",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 313,
      "cache_read_input_tokens": 57563,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 313
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

_source line 27 · 2026-05-17T07:54:52.750Z_

<details><summary>↩ Tool result · `toolu_01LZFjd62LDpQyy5PksvHQ2G`</summary>

```text
4:Training Large Language Model (LLM) agents for multi-turn interactive tasks poses a fundamental challenge: policies must compose actions across 30 to 50 interaction steps in environments such as household navigation~\cite{kim2025reflact}, web interaction~\cite{digiRL2024}, and scientific experimentation. Supervised fine-tuning (SFT) can teach action formatting but fails to instill compositional planning, because expert demonstrations do not expose the trial-and-error exploration through which effective multi-step strategies emerge. Reinforcement learning (RL) addresses this gap by optimizing policies through direct environment interaction, and Group Relative Policy Optimization (GRPO)~\cite{shao2024deepseekmath} has become a preferred method due to its critic-free design and direct compatibility with language model architectures. Recent work applies RL-based training to interactive agents across diverse domains, from text-based games~\cite{ragen2025} and GUI interaction~\cite{digiRL2024} to tool use~\cite{spear2025} and instruction following~\cite{selfguide2026,feng2025gigpo}. These efforts share a common implementation pattern that has received little scrutiny: the multi-turn trajectory is decomposed into fixed-size windows, and each window is optimized as an independent training sample. This decomposition is the focus of our analysis.
8:Standard remedies do not resolve this collapse. Dense reward shaping, which provides per-step bonuses for intermediate goals such as valid action formatting, creates a different failure mode: the agent maximizes format-level rewards while task completion stays at zero. In our dense reward experiment, action validity increases from 60\% to 97.5\% while task success remains at 0\% (Section~\ref{sec:experiments}). Increasing the number of rollouts or adjusting the KL penalty delays the onset of collapse but does not prevent it. Generalized Advantage Estimation (GAE)~\cite{schulman2016gae} and Proximal Policy Optimization (PPO)~\cite{schulman2017ppo} offer finer-grained temporal credit assignment through learned value functions, but they add model complexity and have not been applied with a diagnosis of \textit{why} step-independent training fails in the first place. The root cause is not the choice of RL algorithm. It is the step-independent windowing itself, which corrupts the credit assignment signal at its source.
16:    \item \textbf{Systematic empirical validation.} Through window-size ablation ($h \in \{2, 5, 10, 20, \text{full}\}$) and per-window advantage logging, we demonstrate a credit assignment cliff and provide direct empirical evidence for the sign misattribution mechanism (Section~\ref{sec:experiments}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "0926720a-a3fd-4bcb-bce7-696f90bc72dd",
  "tool_use_result": {
    "stdout": "4:Training Large Language Model (LLM) agents for multi-turn interactive tasks poses a fundamental challenge: policies must compose actions across 30 to 50 interaction steps in environments such as household navigation~\\cite{kim2025reflact}, web interaction~\\cite{digiRL2024}, and scientific experimentation. Supervised fine-tuning (SFT) can teach action formatting but fails to instill compositional planning, because expert demonstrations do not expose the trial-and-error exploration through which effective multi-step strategies emerge. Reinforcement learning (RL) addresses this gap by optimizing policies through direct environment interaction, and Group Relative Policy Optimization (GRPO)~\\cite{shao2024deepseekmath} has become a preferred method due to its critic-free design and direct compatibility with language model architectures. Recent work applies RL-based training to interactive agents across diverse domains, from text-based games~\\cite{ragen2025} and GUI interaction~\\cite{digiRL2024} to tool use~\\cite{spear2025} and instruction following~\\cite{selfguide2026,feng2025gigpo}. These efforts share a common implementation pattern that has received little scrutiny: the multi-turn trajectory is decomposed into fixed-size windows, and each window is optimized as an independent training sample. This decomposition is the focus of our analysis.\n8:Standard remedies do not resolve this collapse. Dense reward shaping, which provides per-step bonuses for intermediate goals such as valid action formatting, creates a different failure mode: the agent maximizes format-level rewards while task completion stays at zero. In our dense reward experiment, action validity increases from 60\\% to 97.5\\% while task success remains at 0\\% (Section~\\ref{sec:experiments}). Increasing the number of rollouts or adjusting the KL penalty delays the onset of collapse but does not prevent it. Generalized Advantage Estimation (GAE)~\\cite{schulman2016gae} and Proximal Policy Optimization (PPO)~\\cite{schulman2017ppo} offer finer-grained temporal credit assignment through learned value functions, but they add model complexity and have not been applied with a diagnosis of \\textit{why} step-independent training fails in the first place. The root cause is not the choice of RL algorithm. It is the step-independent windowing itself, which corrupts the credit assignment signal at its source.\n16:    \\item \\textbf{Systematic empirical validation.} Through window-size ablation ($h \\in \\{2, 5, 10, 20, \\text{full}\\}$) and per-window advantage logging, we demonstrate a credit assignment cliff and provide direct empirical evidence for the sign misattribution mechanism (Section~\\ref{sec:experiments}).",
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

_source line 28_

<details><summary>Logged reasoning block</summary>

```text
The `ing,` matches are:
1. "formatting, creates" - "formatting" is a noun here (action formatting), not a participial modifier. Fine.
2. "formatting," in "action formatting, creates" - same as above.
3. "logging, we demonstrate" - "logging" is a noun (per-window advantage logging). Fine.

None of these are participial phrases. They're all nouns followed by commas in normal sentence structure. No fixes needed.

Let me also check there are no -ing phrase endings at the end of sentences:
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "857f766e-57d6-4d8c-952f-c900efcd2bec",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VbiY9ZHJ9B7iwF2VSU6deb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 834,
      "cache_read_input_tokens": 57876,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 834
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

### Assistant

_source line 29_

All 3 `ing,` matches are nouns (formatting, logging), not participial modifiers. No issues.

File written to `/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/introduction.tex`. ~850 words, 5 paragraphs with contribution list. No em-dashes, no participial endings, no banned phrases. Notation ($h$, $\hat{A}_k$, $K$, $p$, $\pi_\phi$) is consistent with method.tex and theoretical\_analysis.tex. All 3 contributions have section references matching the existing paper structure.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "uuid": "59502e88-9625-4836-bf15-ff3a85a5582f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VbiY9ZHJ9B7iwF2VSU6deb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 834,
      "cache_read_input_tokens": 57876,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 834
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

### Task result

_source line 30_

All 3 `ing,` matches are nouns (formatting, logging), not participial modifiers. No issues.

File written to `/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/introduction.tex`. ~850 words, 5 paragraphs with contribution list. No em-dashes, no participial endings, no banned phrases. Notation ($h$, $\hat{A}_k$, $K$, $p$, $\pi_\phi$) is consistent with method.tex and theoretical\_analysis.tex. All 3 contributions have section references matching the existing paper structure.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 254425,
  "duration_api_ms": 255233,
  "num_turns": 9,
  "stop_reason": "end_turn",
  "session_id": "d742e77c-96ab-48ea-9ee1-35b6ffb35c2d",
  "total_cost_usd": 0.7594742499999999,
  "usage": {
    "input_tokens": 7,
    "cache_creation_input_tokens": 46869,
    "cache_read_input_tokens": 243926,
    "output_tokens": 13654,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 46869,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 299,
        "cache_read_input_tokens": 57876,
        "cache_creation_input_tokens": 834,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 834
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 3115,
      "outputTokens": 16,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.003195,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 7,
      "outputTokens": 13654,
      "cacheReadInputTokens": 243926,
      "cacheCreationInputTokens": 46869,
      "webSearchRequests": 0,
      "costUSD": 0.75627925,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "0ad60e2c-57e8-4791-b9b1-5df5d5e42623"
}
```

</details>

---
