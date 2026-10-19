# paper writing claim1

**How Action Collapse Creates Illusory Safety in Diffusion-Based VLA Collision Avoidance Evaluation** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 25
- **Recorded user turns:** 0
- **Tool calls:** 7
- **Original source:** `logs/workers/worker_paper_writing_claim1_20260526T160405.log`
- **Structured JSON:** [`937438a94c1551d7334b.json`](../../sessions/93/937438a94c1551d7334b.json)

## Before a recorded user message

25 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf",
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
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
  "uuid": "2cfc2112-029d-43b3-9e2f-88433462af65",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-be-idea-gen-0515-projects-diff-collision-sdf/memory/"
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
    "resetsAt": 1779828000,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "bb02118a-2c74-4b9a-b9ff-5223768218b7",
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af"
}
```

---

### Assistant

_source line 4_

I'll read the required reference files first.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "4f490a64-9308-4f24-80be-0dd872041cf3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019VBGhAZw5q9puQo3F96ukp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13632,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13632
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

<details open><summary>🔧 Tool call — Read · `toolu_01Kfh2TWVFaR7g6AUpz9xcKi`</summary>

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
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "25a00e85-2fdb-4af7-ac9e-79b70ccaba28",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019VBGhAZw5q9puQo3F96ukp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13632,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13632
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

_source line 6 · 2026-05-26T16:04:18.557Z_

<details><summary>↩ Tool result · `toolu_01Kfh2TWVFaR7g6AUpz9xcKi`</summary>

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
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "53299ee7-5e4f-4800-b145-b272ec3f7d89",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md",
      "content": "---\nname: paper-writing-norms\ndescription: 顶会级别论文写作风格规范——章节写法（Abstract/Intro/Related Work）、去 AI 风格、视觉密度、叙事哲学。Paper Agent 和 Worker 写论文章节时必须加载。\nallowed-tools: [Read, Write, Edit, Glob, Grep]\nscope: global\nversion: 2\npriority: 9\ntags:\n  - writing\n  - paper\n  - style\n  - norms\nroles:\n  - agent\n  - worker\n  - paper_agent\n---\n\n# 论文写作风格规范\n\n> 核心哲学：**论文是一个有说服力的故事，不是实验报告。** 审稿人在几十秒内判断论文价值——如果 Abstract 和 Introduction 读起来像实验日志，论文就已经失败了。\n\n---\n\n## 一、总体写作哲学\n\n### 1.1 故事驱动，不是数据堆砌\n\n- 论文必须以\"故事线\"为核心展开：问题 → 洞察 → 方法 → 验证\n- 禁止大量实验数据堆砌——每个数字出现必须服务于叙事推进\n- 附录内容必须在正文中有明确引用且融入叙事，禁止简单堆砌\n- 如果附录数据对核心叙事有重大影响，根据附录数据调整论文 framing\n\n### 1.2 主线统一性\n\n- 当 idea 在研究过程中发生变化后，**必须重审全文逻辑**\n- 常见问题：Introduction 讲的故事 A，Method 做的是故事 B，Results 又在讲故事 C\n- 修复方式：从最终实验结论反推，重写 Introduction 的问题定义和动机\n- 每次 idea 调整后检查：Abstract → Introduction → Method → Results → Discussion → Conclusion 是否形成一条连贯主线\n\n### 1.3 专有名词必须有定义\n\n- 首次出现的专有名词/缩写必须给出完整定义和解释\n- Abstract 中使用的缩写也必须在 Abstract 内定义（如 LLM = Large Language Model）\n- 不能假设读者知道你自己定义的术语——论文从来没解释过的概念不能直接使用\n- 通用规则：如果一个非标准术语第一次出现时没有括号定义，就是写作 bug\n\n### 1.4 写作前必读同类优秀论文\n\n- 每个章节动笔前，找 **2-3 篇目标会议近 1-2 年的高分论文**作为风格参考——同类问题或同类方法皆可\n- 重点学：\n  - Abstract 怎么用最少篇幅讲完故事\n  - Introduction 怎么从大问题切入到具体贡献\n  - Related Work 怎么 positioning 自己（不是 survey）\n  - Table/Figure 怎么压缩信息密度\n- **不是抄袭**，是学习同行的故事节奏和审美——不同子领域叙事节奏差异很大\n- 实操：Paper Agent 可以从 `literature_map.yaml` 中挑 `role=foundation` 或 `role=direct-competitor` 的论文，把 `{title, venue, year, abstract}` 附在 Worker 的 task_prompt 中作为概念参考；如需学习写作风格本身，让 Worker 通过 WebSearch 取得论文链接并 fetch 全文\n\n---\n\n## 二、Abstract 写作规范\n\n### 2.1 四个必答问题（150-250 words）\n\nAbstract 必须在很短的篇幅内清楚回答：\n1. **研究什么问题** — 1-2 句话交代背景和痛点\n2. **为什么重要** — 现有方法的不足（不用写太多）\n3. **本文提出什么** — 核心贡献的关键机制（简要，不堆砌细节）\n4. **结果说明什么** — 用具体实验结论支撑贡献\n\n### 2.2 禁忌\n\n- **禁止堆砌数据**：Abstract 不是 Results 的缩写。最多引用 2-3 个关键数字，要服务于 claim\n- **禁止过度宣传**：不说 \"revolutionary\"、\"groundbreaking\"\n- **禁止写成 Introduction 的缩写**：Abstract 是独立阅读单元\n- **禁止术语堆积**：如果审稿人几十秒内判断不出价值，就失败了\n- **缩写必须定义**：Abstract 中首次出现的缩写必须展开\n\n### 2.3 审稿人视角检验\n\n写完后用这个标准自检：审稿人能否在 30 秒内判断——\n- 问题是否重要？\n- 方法是否清楚？\n- 贡献是否可信？\n- 结果是否有说服力？\n\n---\n\n## 三、Introduction 写作规范\n\n### 3.1 完整叙事线（5 段结构）\n\nIntroduction 需要从一个清晰、重要的问题切入，逐步把读者带到核心贡献：\n\n1. **研究背景**（1-2 段）：大模型在某类能力/应用中已取得进展，但仍存在一个关键瓶颈\n2. **问题重要性**（1 段）：结合真实应用、已有方法局限或当前趋势，说明这不是小问题\n3. **现有方法不足**（1 段）：系统梳理为什么不够（依赖更大模型/更多数据/更复杂推理/更高成本，或只在特定 benchmark 有效）\n4. **本文核心想法**（1 段）：我们观察到什么、提出了什么方法、为什么能解决上述问题\n5. **贡献总结**（列表）：清楚列出方法贡献、实验贡献和分析贡献\n\n### 3.2 整体叙事结构\n\n```\n现有进展 → 关键缺口 → 本文洞察 → 方法概述 → 实验证据 → 贡献总结\n```\n\n### 3.3 禁忌\n\n- **禁止泛泛介绍**：不要开头就写 \"LLMs have shown remarkable capabilities...\"，要从具体问题切入\n- **禁止缺少过渡**：每段之间必须有逻辑连接\n- **禁止实验报告风格**：Introduction 不是 \"我们做了 X 实验得到了 Y 结果\" 的罗列\n- 每条 Contribution 必须有对应的 section/table 支撑\n- Contribution 列表中不能出现未在前文铺垫过的概念\n\n---\n\n## 四、Related Work 写作规范\n\n### 4.1 目标\n\n让审稿人相信：作者理解这个领域，知道自己的方法站在什么位置，清楚相对已有工作的真实增量在哪里。\n\n### 4.2 结构要求\n\n- 把已有工作分成几个清晰的主题（如模型训练、推理增强、工具调用、数据构建、评测等）\n- 每类简要说明：已有方法做了什么、解决了哪些问题、和本文的关系\n- 帮助读者理解：哪些是本文直接继承的，哪些方法不同但解决相似问题，哪些留下了本文要解决的缺口\n\n### 4.3 禁忌\n\n- **禁止论文堆砌**：不要写成 \"A proposed X. B proposed Y. C proposed Z.\" 的列表\n- **目标不是展示读了多少论文**，而是做归纳和比较\n- Contribution claim（\"To our knowledge, no prior work...\"）应放在 Introduction，不在 Related Work\n\n### 4.4 引用充足度\n\n- 引用必须覆盖：**直接相关方法、baseline 论文、评测 benchmark 论文、理论基础**\n- 任何一类缺失，审稿人会立刻看出来调研不充分\n- 引用密度参照目标会议近年录用论文的量级——明显偏少意味着 Related Work 调研不足\n\n---\n\n## 五、去 AI 写作风格（硬规则）\n\n以下模式是 AI 生成文本的典型标志，审稿人一眼能看出。**必须全部消除。**\n\n### 5.1 严禁破折号（最显著的 AI 痕迹）\n\n**这是 AI 写作最容易被识别的标志，审稿人最敏感。单列为最高优先级硬规则。**\n\n- 解释性 em-dash（—，U+2014）和 en-dash（–，U+2013）必须**全部删除**\n- 替代方式：用逗号、括号或拆分为两个句子\n- 强制检查命令：\n  ```bash\n  grep -n \"—\" paper/*.tex     # em-dash，每处人工判断是否必要\n  grep -n \" – \" paper/*.tex   # 解释性 en-dash，几乎都应删除\n  ```\n- 例外（允许保留）：表格分隔符、数字范围（`2020–2024`、`pp. 12–18`）、专有名词（`Newton–Raphson`）\n\n### 5.2 段落与句式\n\n- **禁止过度分段**：不需要每 2-3 句就换段，自然段 5-8 句是正常的\n- **减少关系从句**（which, that, who）：能用简洁直接的句子就不用从句\n- **禁止 -ing 短语结尾**：如 \"..., highlighting the applicability of...\" / \"..., demonstrating the effectiveness of...\"。这是 AI 写作最典型的标志之一\n- **禁止连续使用 \"Furthermore\" / \"Moreover\" / \"Additionally\"**：一段内最多用一个过渡词\n- **避免 \"It is worth noting that...\" / \"Notably, ...\"**：直接写要说的内容\n\n### 5.3 用词黑名单\n\n- 避免 \"delve into\" / \"leverage\" / \"utilize\" / \"facilitate\" — 用 \"explore\" / \"use\" / \"enable\"\n- 避免 \"a myriad of\" / \"a plethora of\" — 用 \"many\" / \"various\"\n- 避免 \"in the realm of\" / \"in the context of\" — 直接说\n- 避免 \"paradigm shift\" / \"novel\" 过度使用\n\n### 5.4 校对清单（4 步）\n\n1. 全文 proofread 语法和拼写\n2. 检查所有代词/指示词（this, that, it）是否指代明确\n3. **`grep \"—\"` + `grep \" – \"` 全文清零**（删除所有解释性 dash，§5.1）\n4. `grep \"ing,\"` 模式——大部分 -ing 分词短语需要改写\n\n---\n\n## 六、图表与视觉规范\n\n### 6.1 知识密度原则\n\n- **图表的信息必须紧凑**——不能为了美观而留大量白空间\n- 一张图如果只传达一个简单信息，要么缩小要么合并到其他图中\n- 能用 inline text 说清的不要占一整个 Figure\n\n### 6.2 表格规范\n\n- 表格和正文文字不能视觉重叠（检查 column 宽度和 alignment）\n- 小数精度全表统一\n- 最优加粗、次优下划线\n- Caption 必须自包含\n\n### 6.3 图片规范\n\n- 数值标签不能被线、bar、点遮住——用白色背景或偏移标签\n- 图中字体 >= 7pt（打印后仍可读）\n- 栏宽约束需匹配目标 venue 模板要求\n- 概念图/流程图要有信息量，不要画一个 trivial 的 pipeline 然后占半页\n\n### 6.4 空间效率\n\n- 顶会正文页数严格受限（具体页数查目标会议官网），每 cm² 都是宝贵资源\n- 优先使用 `\\subfigure` 合并相关图\n- Table 能 inline 就不要单独浮动\n- 图表占比与其对叙事的贡献成正比\n\n### 6.5 页面节奏\n\n好论文的页面有节奏感——text、equation、figure 交替出现，读者视觉不疲劳：\n\n- **text-equation-figure 三重奏**：重要概念用\"文字解释 → 公式定义 → 图表直觉\"三步展开\n- 连续 2 页纯文本（无 figure/equation/table）→ 穿插一个 display item 打破节奏\n- 连续 2 个 figure 页（整页被 float 占满）→ 至少隔 1 段文字再放下一个 float\n- Section heading 不孤悬页底（heading 后至少跟 2 行正文，否则强制分页）\n- 最后一页内容 ≥ 2/3 页面高度（太空显得凑数，太满放不下 references）\n\n### 6.6 表格 LaTeX 规范\n\n**Booktabs 标准（硬规则）**：\n- 用 `\\toprule` / `\\midrule` / `\\bottomrule`，禁止 `\\hline`，禁止竖线 `|`\n- 用 `\\centering` 不用 `\\begin{center}`（后者多加垂直空白）\n- 最优结果加粗（`\\textbf{}`），次优下划线（`\\underline{}`）+ 方向箭头 `↑`/`↓` 标明指标方向\n- 小数精度全表统一（如全部保留 1 位或 2 位）\n- Caption 在表格上方（`\\caption` 在 `\\begin{tabular}` 之前）\n\n**宽度决策树**：\n- ≤5 列 → 单栏宽度（`\\columnwidth`）\n- 6–8 列 → 全文宽度（`\\textwidth`，双栏模板用 `table*`）\n- >8 列 → 拆成两张表或移入 appendix\n\n---\n\n## 七、投稿前通用准备\n\n### 7.1 模板必须官方（硬规则）\n\n- LaTeX 模板**必须从目标会议官网下载**（CallForPapers / Author Instructions 页面）\n- **不要用**：\n  - 网上他人转载的复制版本（可能被改过 margin / 行号设置）\n  - 上一年的模板（参数可能变：字体、margin、行号、anonymous 选项等）\n  - 组里学长留的旧版本（来源不明、无法追溯）\n- 风险：\n  - 样式不符合 → desk reject\n  - margin 不对 → 被审稿人质疑诚信\n  - reference 格式错 → 被认为不规范\n- 流程：先查会议官网 templates → 找不到再 `WebSearch \"{venue} {year} latex template official\"` → 仍找不到汇报 Director（不要用就近年版本顶替）\n- `\\documentclass[]{}` 选项必须与目标 venue + 阶段（review / camera-ready）一致\n\n### 7.2 投稿要求逐项核对\n\n- 目标会议如要求 Checklist / Ethical Statement / Broader Impact Statement / Reproducibility Statement，必须**认真填每一项**，不要全写 N/A\n- 页数限制：查目标会议官网\n- 匿名化要求：review 版 vs camera-ready 版本设置不同\n- 行号开启（review 版常需）\n- 字体大小、margin 不得修改 sty 文件\n\n### 7.3 最终修改 10 项检查流程\n\n提交前必须逐一检查：\n1. 所有最新实验结果已全部录入\n2. 根据实验结果将叙事调至最优状态\n3. 附录所有内容在正文中被引用且融入叙事\n4. 无数据堆砌（每个数字服务于叙事推进）\n5. Abstract 和 Introduction 具有吸引力（不是实验报告风格）\n6. 全文主线统一（idea 变化后各章节逻辑一致）\n7. 所有专有名词有定义\n8. 无 AI 风格标志（dash、-ing phrases、过度分段）\n9. 图表知识密度高、无视觉遮挡\n10. Reference 覆盖直接相关方法、baseline、benchmark、理论基础\n",
      "numLines": 276,
      "startLine": 1,
      "totalLines": 276
    }
  }
}
````

</details>

---

### Tool call

_source line 7_

<details open><summary>🔧 Tool call — Read · `toolu_016AeWYzEizBWd8sNRHbsXEp`</summary>

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
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "e67fb1b8-c622-49b7-9dcd-afa80df15e11",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019VBGhAZw5q9puQo3F96ukp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13632,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13632
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

_source line 8 · 2026-05-26T16:04:19.022Z_

<details><summary>↩ Tool result · `toolu_016AeWYzEizBWd8sNRHbsXEp`</summary>

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
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "1e0e99a5-2064-4c73-a3bb-7cc722724c7e",
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

<details open><summary>🔧 Tool call — Read · `toolu_01NNhvsfRLU8Zxt6GGHATnN4`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "51deaff1-8b70-4065-9632-915fa93fc4be",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019VBGhAZw5q9puQo3F96ukp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13632,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13632
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

_source line 10 · 2026-05-26T16:04:19.613Z_

<details><summary>↩ Tool result · `toolu_01NNhvsfRLU8Zxt6GGHATnN4`</summary>

```text
1	\section{Experimental Setup and Metrics}\label{sec:method}
2	
3	This section defines the benchmark, models, training procedures, and evaluation metrics that underpin the analyses in Sections~\ref{sec:fake_safety}--\ref{sec:avoidance_source}. The central methodological contribution is the displacement-filtered Collision Avoidance Rate (CAR$_\text{f}$), a corrective metric that separates genuine obstacle avoidance from action collapse (\S\ref{sec:dfcar}).
4	
5	\subsection{Benchmark and Models}\label{sec:benchmark}
6	
7	We conduct all experiments on SafeLIBERO~\cite{hu2025vlsa}, a collision-aware evaluation extension of the LIBERO simulation platform~\cite{liu2023libero}. SafeLIBERO augments standard manipulation tasks with per-timestep collision detection and non-target obstacle annotations, enabling systematic measurement of both task completion and safety. We select the \textit{object\_pudding} suite (Level~I), which comprises four tabletop manipulation tasks: pick \texttt{orange\_juice}, \texttt{chocolate\_pudding}, \texttt{milk}, or \texttt{bbq\_sauce} and place into a basket. In each task, non-target objects surround the manipulation target, and the MuJoCo physics engine registers any contact between the robot and a non-target object as a collision event.
8	
9	We evaluate two Vision-Language-Action (VLA) models from the Pi0 family~\cite{black2024pi0}. \textbf{Pi0} (${\sim}$2.5B parameters) pairs a PaliGemma vision-language encoder with a dedicated action expert that generates continuous actions via flow matching~\cite{lipman2023flow}. \textbf{Pi0.5} (from Physical Intelligence) extends this architecture with broader pre-training data and serves as a stronger baseline with substantially higher task capability and less susceptibility to action collapse.
10	
11	Table~\ref{tab:configurations} summarizes the six training configurations. Each model is trained for 30K steps. Evaluation uses 50 episodes per task across 4 tasks (200 episodes per configuration). For multi-seed experiments on Pi0.5, we run 3 seeds (600 episodes per configuration). Initial object placements are fixed across methods to ensure fair comparison.
12	
13	\begin{table}[t]
14	\centering
15	\caption{Training configurations. Trainable parameter counts exclude the frozen backbone. The SDF auxiliary heads add $<$660K parameters to the ${\sim}$33.5M LoRA budget.}
16	\label{tab:configurations}
17	\vspace{2pt}
18	\small
19	\begin{tabular}{llr}
20	\toprule
21	Configuration & Description & Trainable Params \\
22	\midrule
23	Pi0 Full-FT & Full fine-tune, flow-matching loss & ${\sim}$3.5B \\
24	Pi0 LoRA & LoRA adapters only & ${\sim}$33.5M \\
25	Pi0+A1 (SDF aux) & LoRA + SDF decoder + EE extractor & ${\sim}$34.2M \\
26	Pi0+A3 (learned SDF) & LoRA + SDF decoder w/ gradient refinement & ${\sim}$34.2M \\
27	Pi0.5 LoRA & LoRA fine-tune on Pi0.5 & ${\sim}$33.5M \\
28	Pi0.5+A1 (SDF aux) & LoRA + SDF aux on Pi0.5, $\lambda \in \{0.005, 0.01, 0.1\}$ & ${\sim}$34.2M \\
29	\bottomrule
30	\end{tabular}
31	\end{table}
32	
33	\subsection{Standard Metrics}\label{sec:standard_metrics}
34	
35	We report two conventional metrics. The \emph{Collision Avoidance Rate} (CAR) is the fraction of episodes in which no collision occurs between the robot and any non-target object:
36	\begin{equation}\label{eq:car}
37	\text{CAR} = \frac{|\{e : \text{safe}(e)\}|}{|E|}
38	\end{equation}
39	where $E$ is the set of all evaluation episodes and $\text{safe}(e)$ indicates that episode $e$ contains zero collision events. The \emph{Task Success Rate} (TSR) is the fraction of episodes where the manipulation task reaches completion:
40	\begin{equation}\label{eq:tsr}
41	\text{TSR} = \frac{|\{e : \text{success}(e)\}|}{|E|}
42	\end{equation}
43	These two metrics are standard in the SafeLIBERO evaluation protocol and in the broader VLA safety literature~\cite{hu2025vlsa,zhang2025safevla}.
44	
45	\subsection{Displacement-Filtered CAR}\label{sec:dfcar}
46	
47	Standard CAR conflates two qualitatively distinct behaviors: a robot that plans a trajectory around obstacles, and a robot that has collapsed into inaction. Both register as ``safe,'' yet only the former reflects collision avoidance capability. We introduce CAR$_\text{f}$, which excludes action-collapsed episodes from both numerator and denominator.
48	
49	\paragraph{Action collapse.} We define an episode $e$ as \emph{action-collapsed} when its maximum end-effector (EE) displacement satisfies
50	\begin{equation}
51	d_{\max}(e) < \tau_d
52	\end{equation}
53	where $d_{\max}(e) = \max_{t} \| \mathbf{p}_t - \mathbf{p}_0 \|_2$ is the maximum Euclidean displacement of the EE from its initial position across all timesteps, and $\tau_d$ is a displacement threshold. We set $\tau_d = 0.1$\,mm, corresponding to sub-actuator-resolution motion.
54	
55	\paragraph{Definition.} The displacement-filtered CAR is:
56	\begin{equation}\label{eq:car_f}
57	\text{CAR}_\text{f} = \frac{|\{e : \text{safe}(e) \;\land\; d_{\max}(e) \geq \tau_d\}|}{|\{e : d_{\max}(e) \geq \tau_d\}|}
58	\end{equation}
59	CAR$_\text{f}$ retains only episodes with sufficient EE motion and measures the collision avoidance rate exclusively among them.
60	
61	\paragraph{Threshold robustness.} The specific choice of $\tau_d$ is not critical. The displacement distribution across all evaluated models is sharply bimodal: collapsed episodes cluster below 1\,$\mu$m, while active episodes exceed 200\,mm. No episodes fall in the intermediate range. This five-order-of-magnitude gap means that any $\tau_d \in [2, 200]$\,mm produces identical filtering results. We verify this empirically in Appendix~\ref{sec:appendix_threshold}.
62	
63	\paragraph{Diagnostic capability.} CAR$_\text{f}$ serves two functions. First, it detects fake safety: Pi0+A1 reports CAR\,=\,91.5\% under the standard metric, but CAR$_\text{f} \approx 0$\% because 99.6\% of its safe episodes are action-collapsed. Second, it validates genuine safety: Pi0.5 achieves CAR$_\text{f}$ equal to its raw CAR (28.5\%), with 0\% of episodes filtered, because all safe episodes involve EE displacement above 288\,mm.
64	
65	\subsection{SDF Auxiliary Training}\label{sec:sdf_aux}
66	
67	We augment the LoRA-adapted VLA with two lightweight auxiliary heads that provide geometric supervision during training.
68	
69	\paragraph{SDF Decoder ($f_\text{SDF}$).} A 4-layer MLP (hidden dimension 256, Softplus activation with $\beta = 5$, ${\sim}$395K parameters) predicts the signed distance $\Phi(\mathbf{x})$ from the current EE position $\mathbf{x}$ to the nearest obstacle surface. The decoder reads from intermediate features of the VLA action expert. The ground-truth signed distance field is precomputed from obstacle meshes using trimesh/pysdf, with values clamped at $\delta = 0.05$\,m and a safety margin $m = 0.01$\,m applied to shift the zero-crossing outward from the obstacle surface.
70	
71	\paragraph{EE Extractor ($f_\text{EE}$).} A 2-layer MLP ($1024 \to 256 \to 3$, ${\sim}$263K parameters) predicts the 3D EE position from the same action expert features. This auxiliary head provides the query point for the SDF decoder and serves as an implicit regularizer on the learned feature representation.
72	
73	\paragraph{Training objective.} The total loss combines the standard flow-matching action loss with the two auxiliary losses:
74	\begin{equation}\label{eq:total_loss}
75	\mathcal{L}_\text{total} = \mathcal{L}_\text{action} + \lambda \left( \mathcal{L}_\text{SDF} + \mathcal{L}_\text{EE} \right)
76	\end{equation}
77	where $\mathcal{L}_\text{SDF}$ is a clamped $L_1$ loss on predicted SDF values with an Eikonal regularizer, $\mathcal{L}_\text{EE}$ is MSE on predicted EE position, and $\lambda$ controls the auxiliary loss weight. We evaluate $\lambda \in \{0.005, 0.01, 0.1\}$. The total auxiliary overhead is $<$660K parameters, less than 2\% of the ${\sim}$33.5M LoRA parameter budget.
78	
79	\paragraph{Optimization.} All models are trained with AdamW, a cosine learning rate schedule decaying from $2.5 \times 10^{-5}$ to $2.5 \times 10^{-6}$, for 30K steps with batch size 32. For Pi0.5+A1, training proceeds in two phases: Phase~1 (steps 0--5K) trains only the auxiliary heads on detached features with the backbone frozen; Phase~2 (steps 5K--30K) unfreezes LoRA parameters for joint optimization.
80	
81	\subsection{Oracle SDF Refinement}\label{sec:oracle_setup}
82	
83	To test the theoretical upper bound of EE-only SDF refinement (Section~\ref{sec:ee_only}), we replace the learned SDF network with the ground-truth signed distance field computed from the simulation geometry. This eliminates prediction error and isolates the structural limitation of the refinement paradigm.
84	
85	We evaluate three oracle variants:
86	\begin{itemize}
87	\item \textit{Oracle-adaptive}: runtime gradient refinement with a dynamic step size $\alpha$ that scales inversely with gradient magnitude, applied in Cartesian action space.
88	\item \textit{Oracle-fixed}: a constant step size $\alpha = 0.005$, also in Cartesian action space.
89	\item \textit{Oracle-feature}: gradient applied in the VLA's latent feature space rather than directly to Cartesian actions. This variant averages 241.7 refinement steps per episode (vs.\ ${\sim}$14 for the Cartesian variants), as the feature-space gradient must propagate through the action decoder.
90	\end{itemize}
91	Each variant is evaluated for 160 episodes (4 tasks $\times$ 40 episodes) with a single seed. The oracle experiments are designed to test Claim~2 (Section~\ref{sec:ee_only}): if EE-only SDF refinement is structurally sound, oracle performance should exceed unrefined baselines by a wide margin.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "4b0a7451-b51d-4b1f-b9e1-e759a123b109",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/method.tex",
      "content": "\\section{Experimental Setup and Metrics}\\label{sec:method}\n\nThis section defines the benchmark, models, training procedures, and evaluation metrics that underpin the analyses in Sections~\\ref{sec:fake_safety}--\\ref{sec:avoidance_source}. The central methodological contribution is the displacement-filtered Collision Avoidance Rate (CAR$_\\text{f}$), a corrective metric that separates genuine obstacle avoidance from action collapse (\\S\\ref{sec:dfcar}).\n\n\\subsection{Benchmark and Models}\\label{sec:benchmark}\n\nWe conduct all experiments on SafeLIBERO~\\cite{hu2025vlsa}, a collision-aware evaluation extension of the LIBERO simulation platform~\\cite{liu2023libero}. SafeLIBERO augments standard manipulation tasks with per-timestep collision detection and non-target obstacle annotations, enabling systematic measurement of both task completion and safety. We select the \\textit{object\\_pudding} suite (Level~I), which comprises four tabletop manipulation tasks: pick \\texttt{orange\\_juice}, \\texttt{chocolate\\_pudding}, \\texttt{milk}, or \\texttt{bbq\\_sauce} and place into a basket. In each task, non-target objects surround the manipulation target, and the MuJoCo physics engine registers any contact between the robot and a non-target object as a collision event.\n\nWe evaluate two Vision-Language-Action (VLA) models from the Pi0 family~\\cite{black2024pi0}. \\textbf{Pi0} (${\\sim}$2.5B parameters) pairs a PaliGemma vision-language encoder with a dedicated action expert that generates continuous actions via flow matching~\\cite{lipman2023flow}. \\textbf{Pi0.5} (from Physical Intelligence) extends this architecture with broader pre-training data and serves as a stronger baseline with substantially higher task capability and less susceptibility to action collapse.\n\nTable~\\ref{tab:configurations} summarizes the six training configurations. Each model is trained for 30K steps. Evaluation uses 50 episodes per task across 4 tasks (200 episodes per configuration). For multi-seed experiments on Pi0.5, we run 3 seeds (600 episodes per configuration). Initial object placements are fixed across methods to ensure fair comparison.\n\n\\begin{table}[t]\n\\centering\n\\caption{Training configurations. Trainable parameter counts exclude the frozen backbone. The SDF auxiliary heads add $<$660K parameters to the ${\\sim}$33.5M LoRA budget.}\n\\label{tab:configurations}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{llr}\n\\toprule\nConfiguration & Description & Trainable Params \\\\\n\\midrule\nPi0 Full-FT & Full fine-tune, flow-matching loss & ${\\sim}$3.5B \\\\\nPi0 LoRA & LoRA adapters only & ${\\sim}$33.5M \\\\\nPi0+A1 (SDF aux) & LoRA + SDF decoder + EE extractor & ${\\sim}$34.2M \\\\\nPi0+A3 (learned SDF) & LoRA + SDF decoder w/ gradient refinement & ${\\sim}$34.2M \\\\\nPi0.5 LoRA & LoRA fine-tune on Pi0.5 & ${\\sim}$33.5M \\\\\nPi0.5+A1 (SDF aux) & LoRA + SDF aux on Pi0.5, $\\lambda \\in \\{0.005, 0.01, 0.1\\}$ & ${\\sim}$34.2M \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\subsection{Standard Metrics}\\label{sec:standard_metrics}\n\nWe report two conventional metrics. The \\emph{Collision Avoidance Rate} (CAR) is the fraction of episodes in which no collision occurs between the robot and any non-target object:\n\\begin{equation}\\label{eq:car}\n\\text{CAR} = \\frac{|\\{e : \\text{safe}(e)\\}|}{|E|}\n\\end{equation}\nwhere $E$ is the set of all evaluation episodes and $\\text{safe}(e)$ indicates that episode $e$ contains zero collision events. The \\emph{Task Success Rate} (TSR) is the fraction of episodes where the manipulation task reaches completion:\n\\begin{equation}\\label{eq:tsr}\n\\text{TSR} = \\frac{|\\{e : \\text{success}(e)\\}|}{|E|}\n\\end{equation}\nThese two metrics are standard in the SafeLIBERO evaluation protocol and in the broader VLA safety literature~\\cite{hu2025vlsa,zhang2025safevla}.\n\n\\subsection{Displacement-Filtered CAR}\\label{sec:dfcar}\n\nStandard CAR conflates two qualitatively distinct behaviors: a robot that plans a trajectory around obstacles, and a robot that has collapsed into inaction. Both register as ``safe,'' yet only the former reflects collision avoidance capability. We introduce CAR$_\\text{f}$, which excludes action-collapsed episodes from both numerator and denominator.\n\n\\paragraph{Action collapse.} We define an episode $e$ as \\emph{action-collapsed} when its maximum end-effector (EE) displacement satisfies\n\\begin{equation}\nd_{\\max}(e) < \\tau_d\n\\end{equation}\nwhere $d_{\\max}(e) = \\max_{t} \\| \\mathbf{p}_t - \\mathbf{p}_0 \\|_2$ is the maximum Euclidean displacement of the EE from its initial position across all timesteps, and $\\tau_d$ is a displacement threshold. We set $\\tau_d = 0.1$\\,mm, corresponding to sub-actuator-resolution motion.\n\n\\paragraph{Definition.} The displacement-filtered CAR is:\n\\begin{equation}\\label{eq:car_f}\n\\text{CAR}_\\text{f} = \\frac{|\\{e : \\text{safe}(e) \\;\\land\\; d_{\\max}(e) \\geq \\tau_d\\}|}{|\\{e : d_{\\max}(e) \\geq \\tau_d\\}|}\n\\end{equation}\nCAR$_\\text{f}$ retains only episodes with sufficient EE motion and measures the collision avoidance rate exclusively among them.\n\n\\paragraph{Threshold robustness.} The specific choice of $\\tau_d$ is not critical. The displacement distribution across all evaluated models is sharply bimodal: collapsed episodes cluster below 1\\,$\\mu$m, while active episodes exceed 200\\,mm. No episodes fall in the intermediate range. This five-order-of-magnitude gap means that any $\\tau_d \\in [2, 200]$\\,mm produces identical filtering results. We verify this empirically in Appendix~\\ref{sec:appendix_threshold}.\n\n\\paragraph{Diagnostic capability.} CAR$_\\text{f}$ serves two functions. First, it detects fake safety: Pi0+A1 reports CAR\\,=\\,91.5\\% under the standard metric, but CAR$_\\text{f} \\approx 0$\\% because 99.6\\% of its safe episodes are action-collapsed. Second, it validates genuine safety: Pi0.5 achieves CAR$_\\text{f}$ equal to its raw CAR (28.5\\%), with 0\\% of episodes filtered, because all safe episodes involve EE displacement above 288\\,mm.\n\n\\subsection{SDF Auxiliary Training}\\label{sec:sdf_aux}\n\nWe augment the LoRA-adapted VLA with two lightweight auxiliary heads that provide geometric supervision during training.\n\n\\paragraph{SDF Decoder ($f_\\text{SDF}$).} A 4-layer MLP (hidden dimension 256, Softplus activation with $\\beta = 5$, ${\\sim}$395K parameters) predicts the signed distance $\\Phi(\\mathbf{x})$ from the current EE position $\\mathbf{x}$ to the nearest obstacle surface. The decoder reads from intermediate features of the VLA action expert. The ground-truth signed distance field is precomputed from obstacle meshes using trimesh/pysdf, with values clamped at $\\delta = 0.05$\\,m and a safety margin $m = 0.01$\\,m applied to shift the zero-crossing outward from the obstacle surface.\n\n\\paragraph{EE Extractor ($f_\\text{EE}$).} A 2-layer MLP ($1024 \\to 256 \\to 3$, ${\\sim}$263K parameters) predicts the 3D EE position from the same action expert features. This auxiliary head provides the query point for the SDF decoder and serves as an implicit regularizer on the learned feature representation.\n\n\\paragraph{Training objective.} The total loss combines the standard flow-matching action loss with the two auxiliary losses:\n\\begin{equation}\\label{eq:total_loss}\n\\mathcal{L}_\\text{total} = \\mathcal{L}_\\text{action} + \\lambda \\left( \\mathcal{L}_\\text{SDF} + \\mathcal{L}_\\text{EE} \\right)\n\\end{equation}\nwhere $\\mathcal{L}_\\text{SDF}$ is a clamped $L_1$ loss on predicted SDF values with an Eikonal regularizer, $\\mathcal{L}_\\text{EE}$ is MSE on predicted EE position, and $\\lambda$ controls the auxiliary loss weight. We evaluate $\\lambda \\in \\{0.005, 0.01, 0.1\\}$. The total auxiliary overhead is $<$660K parameters, less than 2\\% of the ${\\sim}$33.5M LoRA parameter budget.\n\n\\paragraph{Optimization.} All models are trained with AdamW, a cosine learning rate schedule decaying from $2.5 \\times 10^{-5}$ to $2.5 \\times 10^{-6}$, for 30K steps with batch size 32. For Pi0.5+A1, training proceeds in two phases: Phase~1 (steps 0--5K) trains only the auxiliary heads on detached features with the backbone frozen; Phase~2 (steps 5K--30K) unfreezes LoRA parameters for joint optimization.\n\n\\subsection{Oracle SDF Refinement}\\label{sec:oracle_setup}\n\nTo test the theoretical upper bound of EE-only SDF refinement (Section~\\ref{sec:ee_only}), we replace the learned SDF network with the ground-truth signed distance field computed from the simulation geometry. This eliminates prediction error and isolates the structural limitation of the refinement paradigm.\n\nWe evaluate three oracle variants:\n\\begin{itemize}\n\\item \\textit{Oracle-adaptive}: runtime gradient refinement with a dynamic step size $\\alpha$ that scales inversely with gradient magnitude, applied in Cartesian action space.\n\\item \\textit{Oracle-fixed}: a constant step size $\\alpha = 0.005$, also in Cartesian action space.\n\\item \\textit{Oracle-feature}: gradient applied in the VLA's latent feature space rather than directly to Cartesian actions. This variant averages 241.7 refinement steps per episode (vs.\\ ${\\sim}$14 for the Cartesian variants), as the feature-space gradient must propagate through the action decoder.\n\\end{itemize}\nEach variant is evaluated for 160 episodes (4 tasks $\\times$ 40 episodes) with a single seed. The oracle experiments are designed to test Claim~2 (Section~\\ref{sec:ee_only}): if EE-only SDF refinement is structurally sound, oracle performance should exceed unrefined baselines by a wide margin.",
      "numLines": 91,
      "startLine": 1,
      "totalLines": 91
    }
  }
}
```

</details>

---

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — Read · `toolu_01XyYnrVKSCysTmG5bYAE82v`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/analysis_claim1.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "93b3fd03-1d56-4d30-ac4f-35a4f9f649ed",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019VBGhAZw5q9puQo3F96ukp",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 13632,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13632
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

_source line 12 · 2026-05-26T16:04:19.882Z_

<details><summary>↩ Tool result · `toolu_01XyYnrVKSCysTmG5bYAE82v`</summary>

```text
1	\subsection{The Fake Safety Problem}\label{sec:fake_safety}
2	
3	At first glance, the collision avoidance results for SDF-augmented VLA models appear compelling. Our A1-LoRA model (Pi0 fine-tuned with an SDF auxiliary loss) achieves a Collision Avoidance Rate (CAR) of 91.5\% across 800 evaluation episodes on the SafeLIBERO benchmark~\cite{hu2025vlsa}, a figure that would suggest reliable obstacle avoidance. Yet this headline metric conceals a fundamental problem. When we examine the end-effector displacement of the 732 episodes classified as ``safe,'' the picture changes entirely: 541 episodes (73.9\%) exhibit a maximum displacement below 1\,$\mu$m, and another 188 episodes (25.7\%) remain below 0.1\,mm. Only 3 episodes (0.4\%) show displacement above the 0.1\,mm threshold, the minimum we consider consistent with intentional motion. An independent measurement confirms the diagnosis: obstacle displacement across these episodes has a median of ${\sim}$5\,nm, consistent with numerical noise rather than physical contact. The remaining 99.6\% of safe episodes are artifacts of a robot that never moved.
4	
5	We define a safe episode as \emph{fake safe} when the maximum end-effector displacement stays below a threshold $\tau_d = 0.1$\,mm, the criterion used by the displacement-filtered CAR (Eq.~\ref{eq:car_f}). Under this definition, 729 of the 732 safe episodes produced by A1-LoRA are fake safe. An independent signal corroborates the diagnosis: TSR is 0\% across all 800 episodes, and the model produces no meaningful task-directed behavior. The robot did not avoid obstacles; it avoided motion altogether. The displacement distribution (Figure~\ref{fig:displacement}) clusters overwhelmingly near zero, with no spread toward values consistent with planned trajectories. Table~\ref{tab:fake_safety} summarizes the fake safety statistics across all evaluated methods.
6	
7	\begin{table}[t]
8	\centering
9	\caption{Fake safety decomposition across methods on SafeLIBERO. CAR$_\text{f}$ excludes episodes with max displacement $< \tau_d = 0.1$\,mm. Fake safe rate is computed over safe (non-collision) episodes only.}
10	\label{tab:fake_safety}
11	\vspace{2pt}
12	\small
13	\begin{tabular}{lccccc}
14	\toprule
15	Method & CAR (\%) & TSR (\%) & Fake Safe (\%) & Real Safe & CAR$_\text{f}$ (\%) \\
16	\midrule
17	A1-LoRA (SDF) & 91.5 & 0.0 & 99.6 & 3 / 732 & ---$^\dagger$ \\
18	LoRA baseline  & 82.0 & 0.0 & 99.4 & $\approx$\,1 / 164 & $\approx$\,0 \\
19	Pi0.5 & 28.5 & 71.5 & 0.0 & 57 / 57 & 28.5 \\
20	\bottomrule
21	\end{tabular}
22	\vspace{2pt}
23	{\footnotesize $^\dagger$ Denominator $< 5$; statistically unreliable. Pi0.5 row from single-seed re-evaluation (seed~7, 200 episodes) with EE displacement recording; all safe episodes exceed 288\,mm displacement.}
24	\end{table}
25	
26	This phenomenon is not an artifact of the SDF auxiliary loss. The LoRA baseline, trained without any collision avoidance objective, reports a CAR of 82.0\% with a Task Success Rate (TSR) of 0\%. Among its 164 safe episodes, 99.4\% are fake safe by the same displacement criterion. Pi0.5 presents a contrasting case. It is a larger model from the same family (${\sim}$3B$\to$${\sim}$3.5B parameters) that retains substantial task capability. Across three seeds (600 total episodes), Pi0.5 achieves a CAR of 26.8\,$\pm$\,1.6\% and a TSR of 74.7\,$\pm$\,1.5\%. Its lower CAR reflects genuine robot motion through the workspace, which naturally increases collision frequency. Re-evaluation with end-effector displacement recording confirms this distinction: across 200 episodes, all 57 safe episodes exhibit maximum end-effector displacement above 288\,mm; the fake safe rate is 0\%. Pi0.5's collision avoidance reflects genuine trajectory planning around obstacles, not inaction. Its CAR$_\text{f}$ equals its raw CAR (28.5\%), because no episodes are filtered by the displacement threshold.
27	For the Pi0-based methods (A1-LoRA and LoRA baseline), the conclusion is unambiguous: when these models do not collide, it is because the robot did not move.
28	
29	These observations motivate the displacement-filtered CAR (CAR$_\text{f}$) defined in Eq.~\ref{eq:car_f}, which excludes episodes with sub-threshold end-effector displacement from both numerator and denominator. CAR$_\text{f}$ serves as a general-purpose diagnostic for the VLA safety evaluation community, applicable to any model and benchmark where per-episode end-effector trajectories are recorded.
30	
31	The threshold $\tau_d$ admits wide latitude. Among episodes that do exhibit meaningful motion, the minimum observed maximum end-effector displacement is 239\,mm, three orders of magnitude above $\tau_d = 0.1$\,mm. Any threshold in $[2, 200]$\,mm produces identical filtering, because the displacement distribution is bimodal: episodes cluster either near zero (action collapse) or above 200\,mm (active behavior), with no intermediate population. We provide a full sensitivity analysis in Appendix~\ref{sec:appendix_threshold}.
32	
33	For A1-LoRA, only 3 of 800 episodes exceed the threshold; all 3 happen to be safe, but a denominator of 3 precludes any meaningful rate estimate. For the LoRA baseline, CAR$_\text{f}$ is similarly near zero. Pi0.5 presents the opposite extreme: every episode exceeds the displacement threshold, so CAR$_\text{f}$ equals raw CAR (28.5\%). The gap between raw CAR and CAR$_\text{f}$ exposes the scale of contamination: A1-LoRA reports 91.5\% CAR but its CAR$_\text{f}$ is statistically undefined, because it has almost no active episodes to evaluate.
34	
35	The practical implication is stark. Standard CAR evaluation conflates two behaviors that differ in every meaningful respect: a robot that plans a safe trajectory around an obstacle, and a robot that has collapsed into inaction due to distributional shift. Without displacement filtering, any model suffering from action collapse will receive inflated safety scores, and models that collapse more severely will paradoxically appear safer. This inversion renders CAR, as conventionally computed, unreliable for evaluating collision avoidance in VLA models. CAR$_\text{f}$ also serves a diagnostic role: a method that achieves a non-trivial CAR$_\text{f}$ value provides positive evidence that its safety behavior reflects genuine avoidance rather than inaction. Among all configurations evaluated in this work, Pi0.5 fine-tuned on collision-free demonstrations (Section~\ref{sec:avoidance_source}) is the first to produce a meaningful CAR$_\text{f}$.
36	
37	\paragraph{Capability-safety observation.}
38	The fake safety pattern corresponds to a broader regularity in TSR-CAR space. Figure~\ref{fig:tsr_car_scatter} plots all evaluated configurations. Two clusters emerge. Pi0-family methods occupy the upper-left region: high CAR, near-zero TSR, with over 99\% of their safe episodes classified as fake safe; we term this the \emph{fake safety zone}. Pi0.5 sits in the lower-right: high TSR (73--76\% across seeds), low CAR (25--28\%). Its collisions reflect genuine robot motion through the workspace. The pattern holds across all Pi0.5 seeds and across Pi0 variants regardless of whether an SDF loss is applied. Models that execute tasks move the robot into collision-prone configurations; models that fail to act avoid collisions by default.
39	
40	This spatial structure has a direct implication for metric interpretation. A model reporting high CAR but near-zero TSR provides no evidence of collision avoidance capability; its safety score is an artifact of inaction. CAR is informative only when conditioned on sufficient task capability. The TSR-CAR plane offers a more complete picture than either metric alone: the upper-right quadrant (high TSR, high CAR) represents genuinely safe and capable behavior, while the upper-left quadrant is accessible through action collapse alone. We report this anti-correlation as an empirical observation within two model families (Pi0 and Pi0.5), not as a universal law. A causal claim would require evidence across a broader range of architectures and benchmarks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "0671cc0e-d238-4367-93a7-c9852b562e77",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/analysis_claim1.tex",
      "content": "\\subsection{The Fake Safety Problem}\\label{sec:fake_safety}\n\nAt first glance, the collision avoidance results for SDF-augmented VLA models appear compelling. Our A1-LoRA model (Pi0 fine-tuned with an SDF auxiliary loss) achieves a Collision Avoidance Rate (CAR) of 91.5\\% across 800 evaluation episodes on the SafeLIBERO benchmark~\\cite{hu2025vlsa}, a figure that would suggest reliable obstacle avoidance. Yet this headline metric conceals a fundamental problem. When we examine the end-effector displacement of the 732 episodes classified as ``safe,'' the picture changes entirely: 541 episodes (73.9\\%) exhibit a maximum displacement below 1\\,$\\mu$m, and another 188 episodes (25.7\\%) remain below 0.1\\,mm. Only 3 episodes (0.4\\%) show displacement above the 0.1\\,mm threshold, the minimum we consider consistent with intentional motion. An independent measurement confirms the diagnosis: obstacle displacement across these episodes has a median of ${\\sim}$5\\,nm, consistent with numerical noise rather than physical contact. The remaining 99.6\\% of safe episodes are artifacts of a robot that never moved.\n\nWe define a safe episode as \\emph{fake safe} when the maximum end-effector displacement stays below a threshold $\\tau_d = 0.1$\\,mm, the criterion used by the displacement-filtered CAR (Eq.~\\ref{eq:car_f}). Under this definition, 729 of the 732 safe episodes produced by A1-LoRA are fake safe. An independent signal corroborates the diagnosis: TSR is 0\\% across all 800 episodes, and the model produces no meaningful task-directed behavior. The robot did not avoid obstacles; it avoided motion altogether. The displacement distribution (Figure~\\ref{fig:displacement}) clusters overwhelmingly near zero, with no spread toward values consistent with planned trajectories. Table~\\ref{tab:fake_safety} summarizes the fake safety statistics across all evaluated methods.\n\n\\begin{table}[t]\n\\centering\n\\caption{Fake safety decomposition across methods on SafeLIBERO. CAR$_\\text{f}$ excludes episodes with max displacement $< \\tau_d = 0.1$\\,mm. Fake safe rate is computed over safe (non-collision) episodes only.}\n\\label{tab:fake_safety}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccc}\n\\toprule\nMethod & CAR (\\%) & TSR (\\%) & Fake Safe (\\%) & Real Safe & CAR$_\\text{f}$ (\\%) \\\\\n\\midrule\nA1-LoRA (SDF) & 91.5 & 0.0 & 99.6 & 3 / 732 & ---$^\\dagger$ \\\\\nLoRA baseline  & 82.0 & 0.0 & 99.4 & $\\approx$\\,1 / 164 & $\\approx$\\,0 \\\\\nPi0.5 & 28.5 & 71.5 & 0.0 & 57 / 57 & 28.5 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{2pt}\n{\\footnotesize $^\\dagger$ Denominator $< 5$; statistically unreliable. Pi0.5 row from single-seed re-evaluation (seed~7, 200 episodes) with EE displacement recording; all safe episodes exceed 288\\,mm displacement.}\n\\end{table}\n\nThis phenomenon is not an artifact of the SDF auxiliary loss. The LoRA baseline, trained without any collision avoidance objective, reports a CAR of 82.0\\% with a Task Success Rate (TSR) of 0\\%. Among its 164 safe episodes, 99.4\\% are fake safe by the same displacement criterion. Pi0.5 presents a contrasting case. It is a larger model from the same family (${\\sim}$3B$\\to$${\\sim}$3.5B parameters) that retains substantial task capability. Across three seeds (600 total episodes), Pi0.5 achieves a CAR of 26.8\\,$\\pm$\\,1.6\\% and a TSR of 74.7\\,$\\pm$\\,1.5\\%. Its lower CAR reflects genuine robot motion through the workspace, which naturally increases collision frequency. Re-evaluation with end-effector displacement recording confirms this distinction: across 200 episodes, all 57 safe episodes exhibit maximum end-effector displacement above 288\\,mm; the fake safe rate is 0\\%. Pi0.5's collision avoidance reflects genuine trajectory planning around obstacles, not inaction. Its CAR$_\\text{f}$ equals its raw CAR (28.5\\%), because no episodes are filtered by the displacement threshold.\nFor the Pi0-based methods (A1-LoRA and LoRA baseline), the conclusion is unambiguous: when these models do not collide, it is because the robot did not move.\n\nThese observations motivate the displacement-filtered CAR (CAR$_\\text{f}$) defined in Eq.~\\ref{eq:car_f}, which excludes episodes with sub-threshold end-effector displacement from both numerator and denominator. CAR$_\\text{f}$ serves as a general-purpose diagnostic for the VLA safety evaluation community, applicable to any model and benchmark where per-episode end-effector trajectories are recorded.\n\nThe threshold $\\tau_d$ admits wide latitude. Among episodes that do exhibit meaningful motion, the minimum observed maximum end-effector displacement is 239\\,mm, three orders of magnitude above $\\tau_d = 0.1$\\,mm. Any threshold in $[2, 200]$\\,mm produces identical filtering, because the displacement distribution is bimodal: episodes cluster either near zero (action collapse) or above 200\\,mm (active behavior), with no intermediate population. We provide a full sensitivity analysis in Appendix~\\ref{sec:appendix_threshold}.\n\nFor A1-LoRA, only 3 of 800 episodes exceed the threshold; all 3 happen to be safe, but a denominator of 3 precludes any meaningful rate estimate. For the LoRA baseline, CAR$_\\text{f}$ is similarly near zero. Pi0.5 presents the opposite extreme: every episode exceeds the displacement threshold, so CAR$_\\text{f}$ equals raw CAR (28.5\\%). The gap between raw CAR and CAR$_\\text{f}$ exposes the scale of contamination: A1-LoRA reports 91.5\\% CAR but its CAR$_\\text{f}$ is statistically undefined, because it has almost no active episodes to evaluate.\n\nThe practical implication is stark. Standard CAR evaluation conflates two behaviors that differ in every meaningful respect: a robot that plans a safe trajectory around an obstacle, and a robot that has collapsed into inaction due to distributional shift. Without displacement filtering, any model suffering from action collapse will receive inflated safety scores, and models that collapse more severely will paradoxically appear safer. This inversion renders CAR, as conventionally computed, unreliable for evaluating collision avoidance in VLA models. CAR$_\\text{f}$ also serves a diagnostic role: a method that achieves a non-trivial CAR$_\\text{f}$ value provides positive evidence that its safety behavior reflects genuine avoidance rather than inaction. Among all configurations evaluated in this work, Pi0.5 fine-tuned on collision-free demonstrations (Section~\\ref{sec:avoidance_source}) is the first to produce a meaningful CAR$_\\text{f}$.\n\n\\paragraph{Capability-safety observation.}\nThe fake safety pattern corresponds to a broader regularity in TSR-CAR space. Figure~\\ref{fig:tsr_car_scatter} plots all evaluated configurations. Two clusters emerge. Pi0-family methods occupy the upper-left region: high CAR, near-zero TSR, with over 99\\% of their safe episodes classified as fake safe; we term this the \\emph{fake safety zone}. Pi0.5 sits in the lower-right: high TSR (73--76\\% across seeds), low CAR (25--28\\%). Its collisions reflect genuine robot motion through the workspace. The pattern holds across all Pi0.5 seeds and across Pi0 variants regardless of whether an SDF loss is applied. Models that execute tasks move the robot into collision-prone configurations; models that fail to act avoid collisions by default.\n\nThis spatial structure has a direct implication for metric interpretation. A model reporting high CAR but near-zero TSR provides no evidence of collision avoidance capability; its safety score is an artifact of inaction. CAR is informative only when conditioned on sufficient task capability. The TSR-CAR plane offers a more complete picture than either metric alone: the upper-right quadrant (high TSR, high CAR) represents genuinely safe and capable behavior, while the upper-left quadrant is accessible through action collapse alone. We report this anti-correlation as an empirical observation within two model families (Pi0 and Pi0.5), not as a universal law. A causal claim would require evidence across a broader range of architectures and benchmarks.",
      "numLines": 40,
      "startLine": 1,
      "totalLines": 40
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
Now let me check the main.tex to understand the graphicspath setting and overall structure.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "9402c5d3-a24c-41b1-b558-4fe2d38b5ce9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MbSxzy3LwfzYG5RTD7W277",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 16664,
      "cache_read_input_tokens": 25473,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 16664
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

Let me check the main.tex for graphicspath and structure.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "c6242fc8-8c55-44ba-a440-be2a9465f85d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MbSxzy3LwfzYG5RTD7W277",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 16664,
      "cache_read_input_tokens": 25473,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 16664
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

<details open><summary>🔧 Tool call — Grep · `toolu_01XqtexDHS7WfGxu4CLPr7bD`</summary>

```json
{
  "pattern": "graphicspath|\\\\input\\{claim1\\}",
  "path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "629ffa43-d455-40dc-84a7-8156f807ac78",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MbSxzy3LwfzYG5RTD7W277",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 16664,
      "cache_read_input_tokens": 25473,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 16664
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

_source line 16 · 2026-05-26T16:04:26.314Z_

<details><summary>↩ Tool result · `toolu_01XqtexDHS7WfGxu4CLPr7bD`</summary>

```text
docs/paper/main.tex:12:\graphicspath{{../../artifacts/figures/}}
docs/paper/main.tex:39:\input{claim1}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "60294e6e-3588-4e2b-a65c-a18d900a3f72",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/main.tex:12:\\graphicspath{{../../artifacts/figures/}}\ndocs/paper/main.tex:39:\\input{claim1}",
    "numLines": 2
  }
}
```

</details>

---

### Assistant

_source line 17_

<details><summary>Logged reasoning block</summary>

```text
The graphicspath is `../../artifacts/figures/`, so I should reference figures as just the filename, e.g., `fig_tsr_car_scatter.pdf`. Let me also check if the scatter figure exists.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "05a8ad2c-e30f-47df-82ab-81deadffe689",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01V9VXTtURmUCpebiameKXXK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 225,
      "cache_read_input_tokens": 42137,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 225
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

Good, graphicspath is `../../artifacts/figures/`, so figures are referenced by filename directly. Let me verify the scatter figure exists.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "38ee967b-8703-4a93-a39b-4d93be83de7f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01V9VXTtURmUCpebiameKXXK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 225,
      "cache_read_input_tokens": 42137,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 225
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

<details open><summary>🔧 Tool call — Bash · `toolu_016NE4NUwusaXRmHkMntRsWk`</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/artifacts/figures/fig_tsr_car_scatter*",
  "description": "Check if scatter plot figure exists"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "f0f2f8c1-8fa9-4c36-81df-aa22497b16a8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01V9VXTtURmUCpebiameKXXK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 225,
      "cache_read_input_tokens": 42137,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 225
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

_source line 20 · 2026-05-26T16:04:31.216Z_

<details><summary>↩ Tool result · `toolu_016NE4NUwusaXRmHkMntRsWk`</summary>

```text
/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/artifacts/figures/fig_tsr_car_scatter.pdf
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "4caa3036-a017-46f2-a923-119856cad4d8",
  "tool_use_result": {
    "stdout": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/artifacts/figures/fig_tsr_car_scatter.pdf",
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

_source line 21_

Now writing claim1.tex.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "80d298c0-2103-4856-bf55-7e78f54044fb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014bfp9nSoR3SGrBUEzR3bQZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 263,
      "cache_read_input_tokens": 42362,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 263
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

<details open><summary>🔧 Tool call — Write · `toolu_01GPJ8N1mXRWvPFjevLuKQAm`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim1.tex",
  "content": "\\section{The Fake Safety Problem}\\label{sec:fake_safety}\n\nStandard CAR evaluation assumes that a collision-free episode reflects deliberate obstacle avoidance. This assumption fails when a model has collapsed into inaction: a robot that never moves will never collide, yet it has not avoided anything. We show that this failure mode dominates the safety scores of Pi0-family models and introduce CAR$_\\text{f}$ as a corrective diagnostic.\n\n\\subsection{Action Collapse Contamination}\\label{sec:collapse}\n\nOur Pi0+A1 configuration (LoRA fine-tuning with SDF auxiliary loss) achieves a CAR of 91.5\\% across 800 evaluation episodes, a figure that would suggest reliable obstacle avoidance. End-effector displacement analysis tells a different story. Of the 732 episodes classified as safe, 541 (73.9\\%) exhibit maximum displacement below 1\\,$\\mu$m, another 188 (25.7\\%) remain below 0.1\\,mm, and only 3 (0.4\\%) exceed the 0.1\\,mm threshold. The remaining 99.6\\% of safe episodes are artifacts of a robot that never moved. TSR is 0\\% across all 800 episodes: the model produces no task-directed behavior whatsoever.\n\nApplying CAR$_\\text{f}$ (Eq.~\\ref{eq:car_f}) filters out these action-collapsed episodes. Pi0+A1 drops from CAR\\,=\\,91.5\\% to CAR$_\\text{f} \\approx 0$\\%, because only 3 of 732 safe episodes survive displacement filtering. This is the primary demonstration of what CAR$_\\text{f}$ is designed to detect: a headline safety score that is entirely attributable to inaction.\n\nThe contamination is not specific to the SDF auxiliary loss. Pi0 Full-FT reports CAR\\,=\\,83.0\\% with TSR\\,=\\,0.5\\%, and 99.4\\% of its safe episodes are fake safe, yielding CAR$_\\text{f} \\approx 0$\\%. Pi0 LoRA (without any collision objective) achieves CAR\\,=\\,82.0\\%, TSR\\,=\\,0\\%, with a comparable fake safe rate. Across all three Pi0 configurations, CAR$_\\text{f}$ collapses to near zero.\n\nPi0.5 provides the validation case. Re-evaluation with displacement recording (200 episodes, seed~7) yields CAR\\,=\\,28.5\\% and TSR\\,=\\,71.5\\%. All 57 safe episodes exhibit maximum EE displacement above 288\\,mm. The fake safe rate is 0\\%, and CAR$_\\text{f}$ equals raw CAR (28.5\\%). Pi0.5 does not avoid obstacles by standing still; it executes tasks through the workspace and avoids collisions along the way. The displacement filter removes nothing, confirming that CAR$_\\text{f}$ correctly preserves genuine safety.\n\n\\paragraph{Threshold robustness.} The choice of $\\tau_d = 0.1$\\,mm is not sensitive. The displacement distribution is sharply bimodal: collapsed episodes cluster below 1\\,$\\mu$m while active episodes exceed 200\\,mm, a gap spanning five orders of magnitude. Any threshold $\\tau_d \\in [2, 200]$\\,mm yields identical filtering results, because no episodes occupy the intermediate range. This bimodality makes CAR$_\\text{f}$ robust to threshold selection rather than dependent on an arbitrary cutoff. We provide a full sensitivity analysis in Appendix~\\ref{sec:appendix_threshold}.\n\nTable~\\ref{tab:fake_safety} summarizes the fake safety decomposition across all evaluated methods. Figure~\\ref{fig:displacement} shows the end-effector displacement distribution.\n\n\\begin{table}[t]\n\\centering\n\\caption{Fake safety decomposition on SafeLIBERO. CAR$_\\text{f}$ excludes episodes with max EE displacement $< \\tau_d = 0.1$\\,mm. ``Fake Safe'' is computed over safe (non-collision) episodes only. ``Real Safe'' counts safe episodes that exceed the displacement threshold.}\n\\label{tab:fake_safety}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccccl}\n\\toprule\nMethod & Ep. & CAR (\\%) & TSR (\\%) & Fake Safe (\\%) & Real Safe & CAR$_\\text{f}$ (\\%) & EE Disp (m) \\\\\n\\midrule\nPi0 Full-FT  & 200 & 83.0 & 0.5 & 99.4 & 1/166 & $\\approx$\\,0 & 0.027 \\\\\nPi0 LoRA     & 200 & 82.0 & 0.0 & ${\\sim}$99 & ${\\sim}$1/164 & $\\approx$\\,0 & 0.010 \\\\\nPi0+A1 (SDF) & 800 & 91.5 & 0.0 & 99.6 & 3/732 & ---$^\\dagger$ & 0.003 \\\\\n\\midrule\nPi0.5 (3-seed)  & 600 & 26.8\\,$\\pm$\\,1.6 & 74.7\\,$\\pm$\\,1.5 & --- & --- & --- & 0.367 \\\\\nPi0.5 (reeval)  & 200 & 28.5 & 71.5 & 0.0 & 57/57 & 28.5 & 0.367 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{2pt}\n{\\footnotesize $^\\dagger$\\,Denominator $<5$; rate estimate statistically unreliable.}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\fbox{\\parbox{0.92\\linewidth}{\\vspace{3cm}\\centering\\textit{Placeholder: end-effector displacement distribution.\\\\Bimodal histogram showing collapsed ($<1\\,\\mu$m) vs.\\ active ($>200$\\,mm) episodes.}\\vspace{3cm}}}\n\\caption{End-effector displacement distribution across evaluation episodes. Pi0-family models (blue) cluster below 1\\,$\\mu$m, while Pi0.5 episodes (orange) exceed 200\\,mm. The five-order-of-magnitude gap between the two modes makes the displacement threshold $\\tau_d$ robust to any value in $[2, 200]$\\,mm.}\n\\label{fig:displacement}\n\\end{figure}\n\n\\subsection{Capability-Safety Anti-correlation}\\label{sec:anticorrelation}\n\nThe fake safety pattern corresponds to a spatial structure in the TSR-CAR plane. Figure~\\ref{fig:tsr_car_scatter} plots all evaluated configurations. Two clusters emerge. Pi0-family methods (Full-FT, LoRA, Pi0+A1) occupy the upper-left: CAR between 82\\% and 91.5\\%, TSR at or below 0.5\\%. Over 99\\% of their safe episodes are fake safe. Pi0.5 sits in the lower-right: TSR of 73--76\\% across seeds, CAR of 25--28\\%. Intermediate configurations (Pi0.5+A1, LoRA-only fine-tunes) populate the middle of the plane, with TSR around 51--54\\% and CAR around 54--57\\%.\n\nThe pattern has a straightforward explanation within these two model families. Models that execute tasks move the robot through the workspace and into proximity with obstacles, raising the probability of collision. Models that fail to act remain near the initial configuration, avoiding collisions by default. Higher task capability correlates with lower CAR not because capable models are less safe, but because the denominator of risk exposure changes: a moving robot encounters obstacles that a stationary one does not.\n\nWe report this anti-correlation as an empirical observation within Pi0 and Pi0.5, not as a universal law. A causal claim would require evidence across a broader set of architectures, benchmarks, and task distributions. Within the scope of our evaluation, the observation reinforces a practical point: CAR is informative only when conditioned on sufficient task capability. The upper-right quadrant of the TSR-CAR plane (high TSR, high CAR) represents genuinely safe and capable behavior; the upper-left quadrant is accessible through action collapse alone.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{fig_tsr_car_scatter.pdf}\n\\caption{TSR vs.\\ CAR for all evaluated configurations. Pi0-family models cluster in the upper-left (high CAR from inaction), Pi0.5 in the lower-right (high TSR with genuine collision exposure). Intermediate methods (Pi0.5+A1, LoRA-only) occupy the center. Error bars denote $\\pm$1 standard deviation across seeds where applicable.}\n\\label{fig:tsr_car_scatter}\n\\end{figure}\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "613fd579-92cd-41ae-842a-58d42a09908f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014bfp9nSoR3SGrBUEzR3bQZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 263,
      "cache_read_input_tokens": 42362,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 263
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

_source line 23 · 2026-05-26T16:05:11.581Z_

<details><summary>↩ Tool result · `toolu_01GPJ8N1mXRWvPFjevLuKQAm`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim1.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "9a3735e8-3582-4245-bb59-f6f5e46b406e",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515/projects/diff_collision_sdf/docs/paper/claim1.tex",
    "content": "\\section{The Fake Safety Problem}\\label{sec:fake_safety}\n\nStandard CAR evaluation assumes that a collision-free episode reflects deliberate obstacle avoidance. This assumption fails when a model has collapsed into inaction: a robot that never moves will never collide, yet it has not avoided anything. We show that this failure mode dominates the safety scores of Pi0-family models and introduce CAR$_\\text{f}$ as a corrective diagnostic.\n\n\\subsection{Action Collapse Contamination}\\label{sec:collapse}\n\nOur Pi0+A1 configuration (LoRA fine-tuning with SDF auxiliary loss) achieves a CAR of 91.5\\% across 800 evaluation episodes, a figure that would suggest reliable obstacle avoidance. End-effector displacement analysis tells a different story. Of the 732 episodes classified as safe, 541 (73.9\\%) exhibit maximum displacement below 1\\,$\\mu$m, another 188 (25.7\\%) remain below 0.1\\,mm, and only 3 (0.4\\%) exceed the 0.1\\,mm threshold. The remaining 99.6\\% of safe episodes are artifacts of a robot that never moved. TSR is 0\\% across all 800 episodes: the model produces no task-directed behavior whatsoever.\n\nApplying CAR$_\\text{f}$ (Eq.~\\ref{eq:car_f}) filters out these action-collapsed episodes. Pi0+A1 drops from CAR\\,=\\,91.5\\% to CAR$_\\text{f} \\approx 0$\\%, because only 3 of 732 safe episodes survive displacement filtering. This is the primary demonstration of what CAR$_\\text{f}$ is designed to detect: a headline safety score that is entirely attributable to inaction.\n\nThe contamination is not specific to the SDF auxiliary loss. Pi0 Full-FT reports CAR\\,=\\,83.0\\% with TSR\\,=\\,0.5\\%, and 99.4\\% of its safe episodes are fake safe, yielding CAR$_\\text{f} \\approx 0$\\%. Pi0 LoRA (without any collision objective) achieves CAR\\,=\\,82.0\\%, TSR\\,=\\,0\\%, with a comparable fake safe rate. Across all three Pi0 configurations, CAR$_\\text{f}$ collapses to near zero.\n\nPi0.5 provides the validation case. Re-evaluation with displacement recording (200 episodes, seed~7) yields CAR\\,=\\,28.5\\% and TSR\\,=\\,71.5\\%. All 57 safe episodes exhibit maximum EE displacement above 288\\,mm. The fake safe rate is 0\\%, and CAR$_\\text{f}$ equals raw CAR (28.5\\%). Pi0.5 does not avoid obstacles by standing still; it executes tasks through the workspace and avoids collisions along the way. The displacement filter removes nothing, confirming that CAR$_\\text{f}$ correctly preserves genuine safety.\n\n\\paragraph{Threshold robustness.} The choice of $\\tau_d = 0.1$\\,mm is not sensitive. The displacement distribution is sharply bimodal: collapsed episodes cluster below 1\\,$\\mu$m while active episodes exceed 200\\,mm, a gap spanning five orders of magnitude. Any threshold $\\tau_d \\in [2, 200]$\\,mm yields identical filtering results, because no episodes occupy the intermediate range. This bimodality makes CAR$_\\text{f}$ robust to threshold selection rather than dependent on an arbitrary cutoff. We provide a full sensitivity analysis in Appendix~\\ref{sec:appendix_threshold}.\n\nTable~\\ref{tab:fake_safety} summarizes the fake safety decomposition across all evaluated methods. Figure~\\ref{fig:displacement} shows the end-effector displacement distribution.\n\n\\begin{table}[t]\n\\centering\n\\caption{Fake safety decomposition on SafeLIBERO. CAR$_\\text{f}$ excludes episodes with max EE displacement $< \\tau_d = 0.1$\\,mm. ``Fake Safe'' is computed over safe (non-collision) episodes only. ``Real Safe'' counts safe episodes that exceed the displacement threshold.}\n\\label{tab:fake_safety}\n\\vspace{2pt}\n\\small\n\\begin{tabular}{lccccccl}\n\\toprule\nMethod & Ep. & CAR (\\%) & TSR (\\%) & Fake Safe (\\%) & Real Safe & CAR$_\\text{f}$ (\\%) & EE Disp (m) \\\\\n\\midrule\nPi0 Full-FT  & 200 & 83.0 & 0.5 & 99.4 & 1/166 & $\\approx$\\,0 & 0.027 \\\\\nPi0 LoRA     & 200 & 82.0 & 0.0 & ${\\sim}$99 & ${\\sim}$1/164 & $\\approx$\\,0 & 0.010 \\\\\nPi0+A1 (SDF) & 800 & 91.5 & 0.0 & 99.6 & 3/732 & ---$^\\dagger$ & 0.003 \\\\\n\\midrule\nPi0.5 (3-seed)  & 600 & 26.8\\,$\\pm$\\,1.6 & 74.7\\,$\\pm$\\,1.5 & --- & --- & --- & 0.367 \\\\\nPi0.5 (reeval)  & 200 & 28.5 & 71.5 & 0.0 & 57/57 & 28.5 & 0.367 \\\\\n\\bottomrule\n\\end{tabular}\n\\vspace{2pt}\n{\\footnotesize $^\\dagger$\\,Denominator $<5$; rate estimate statistically unreliable.}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\fbox{\\parbox{0.92\\linewidth}{\\vspace{3cm}\\centering\\textit{Placeholder: end-effector displacement distribution.\\\\Bimodal histogram showing collapsed ($<1\\,\\mu$m) vs.\\ active ($>200$\\,mm) episodes.}\\vspace{3cm}}}\n\\caption{End-effector displacement distribution across evaluation episodes. Pi0-family models (blue) cluster below 1\\,$\\mu$m, while Pi0.5 episodes (orange) exceed 200\\,mm. The five-order-of-magnitude gap between the two modes makes the displacement threshold $\\tau_d$ robust to any value in $[2, 200]$\\,mm.}\n\\label{fig:displacement}\n\\end{figure}\n\n\\subsection{Capability-Safety Anti-correlation}\\label{sec:anticorrelation}\n\nThe fake safety pattern corresponds to a spatial structure in the TSR-CAR plane. Figure~\\ref{fig:tsr_car_scatter} plots all evaluated configurations. Two clusters emerge. Pi0-family methods (Full-FT, LoRA, Pi0+A1) occupy the upper-left: CAR between 82\\% and 91.5\\%, TSR at or below 0.5\\%. Over 99\\% of their safe episodes are fake safe. Pi0.5 sits in the lower-right: TSR of 73--76\\% across seeds, CAR of 25--28\\%. Intermediate configurations (Pi0.5+A1, LoRA-only fine-tunes) populate the middle of the plane, with TSR around 51--54\\% and CAR around 54--57\\%.\n\nThe pattern has a straightforward explanation within these two model families. Models that execute tasks move the robot through the workspace and into proximity with obstacles, raising the probability of collision. Models that fail to act remain near the initial configuration, avoiding collisions by default. Higher task capability correlates with lower CAR not because capable models are less safe, but because the denominator of risk exposure changes: a moving robot encounters obstacles that a stationary one does not.\n\nWe report this anti-correlation as an empirical observation within Pi0 and Pi0.5, not as a universal law. A causal claim would require evidence across a broader set of architectures, benchmarks, and task distributions. Within the scope of our evaluation, the observation reinforces a practical point: CAR is informative only when conditioned on sufficient task capability. The upper-right quadrant of the TSR-CAR plane (high TSR, high CAR) represents genuinely safe and capable behavior; the upper-left quadrant is accessible through action collapse alone.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\linewidth]{fig_tsr_car_scatter.pdf}\n\\caption{TSR vs.\\ CAR for all evaluated configurations. Pi0-family models cluster in the upper-left (high CAR from inaction), Pi0.5 in the lower-right (high TSR with genuine collision exposure). Intermediate methods (Pi0.5+A1, LoRA-only) occupy the center. Error bars denote $\\pm$1 standard deviation across seeds where applicable.}\n\\label{fig:tsr_car_scatter}\n\\end{figure}\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
```

</details>

---

### Assistant

_source line 24_

`claim1.tex` written. Key structural decisions:

- **dfCAR narrative order**: Pi0+A1 filtering demonstration first (91.5% → ~0%), Pi0.5 validation second (28.5% = 28.5%), as required
- **Table**: booktabs format with all 5 data rows, midrule separating Pi0-family from Pi0.5, footnote for unreliable denominator
- **Threshold robustness**: framed as strength via bimodal distribution with 5-order-of-magnitude gap
- **Anti-correlation**: explicitly limited to Pi0/Pi0.5 families, not generalized
- **Figures**: placeholder box for `fig:displacement`, `\includegraphics` for the existing scatter PDF
- ~870 words, within budget

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "uuid": "15ae2564-47b5-4f36-a8e3-bf8aea2a84be",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ANRQQb3CMiDigNfZ9qLYgc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2505,
      "cache_read_input_tokens": 42625,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2505
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

_source line 25_

`claim1.tex` written. Key structural decisions:

- **dfCAR narrative order**: Pi0+A1 filtering demonstration first (91.5% → ~0%), Pi0.5 validation second (28.5% = 28.5%), as required
- **Table**: booktabs format with all 5 data rows, midrule separating Pi0-family from Pi0.5, footnote for unreliable denominator
- **Threshold robustness**: framed as strength via bimodal distribution with 5-order-of-magnitude gap
- **Anti-correlation**: explicitly limited to Pi0/Pi0.5 families, not generalized
- **Figures**: placeholder box for `fig:displacement`, `\includegraphics` for the existing scatter PDF
- ~870 words, within budget

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 64030,
  "duration_api_ms": 65018,
  "num_turns": 8,
  "stop_reason": "end_turn",
  "session_id": "f9b75e4c-8cce-4fe2-a735-2fc2e15787af",
  "total_cost_usd": 0.37370525000000004,
  "usage": {
    "input_tokens": 6,
    "cache_creation_input_tokens": 33289,
    "cache_read_input_tokens": 164438,
    "output_tokens": 3213,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 33289,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 188,
        "cache_read_input_tokens": 42625,
        "cache_creation_input_tokens": 2505,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 2505
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2970,
      "outputTokens": 21,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.003075,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 6,
      "outputTokens": 3213,
      "cacheReadInputTokens": 164438,
      "cacheCreationInputTokens": 33289,
      "webSearchRequests": 0,
      "costUSD": 0.37063025,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "352a725d-8232-41d6-9c94-2c396e313a3c"
}
```

</details>

---
